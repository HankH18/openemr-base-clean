# AgentForge Clinical Co-Pilot — Deliverable Walkthrough & Submission Readiness

> **Purpose.** Read this once and understand the whole Week‑2 system — every graded
> feature, how it works behind the scenes, how to test it yourself, and exactly
> what (if anything) is still missing. Written for a reviewer or a new engineer who
> has never seen this codebase.
>
> **Code audited at `HEAD 1fe8f5a`** (this doc adds no code). The system was hardened
> through a four‑round adversarial audit‑fix loop, a final gap‑fix pass, and a
> five‑auditor **second** adversarial pass whose findings are all fixed below.
>
> **Green across the board:**
> - Full agent suite **1458 passed, 2 skipped** (the 2 skips need an Anthropic key).
> - Frozen acceptance `run.py --pass-rate` = **97.83** (45/46 — the one red is the
>   *stale‑but‑frozen* `test_api_02`, explained in the do‑not‑fix list); per‑feature
>   ingestion 8 · rag 6 · verification 8 · api 8 · graph 7 · writeback 3 · evalgate 5.
> - Eval **HARD GATE** `gate.py` → exit 0, **62 cases** (53 fixture + 9 live), 62/62 on
>   all five rubrics; `--inject-regression` → exit 1 (blocks).
> - `phi_check` → 0 leaks across the chat egress **and** all five lifecycle families.
> - `mypy copilot` clean (99 files); `ruff check` clean.
> - **Deployed & verified** at **https://agentforge.hankholcomb.com** (HEAD `0d75648`;
>   `/ready` → `ready:true`, 10 deps green, migrations head `0010`; the pretty HTML
>   status page renders live through Caddy/TLS; public root → 200; SMART login on).
>   See §5a for the 2026‑07‑19 live‑testing pass (an ingestion‑crash fix + dispositions).

---

## 1. Submission‑readiness at a glance

| # | Deliverable | Verdict |
|---|---|---|
| F1 | Document ingestion (lab PDF + intake form → strict JSON, source in OpenEMR, facts linked) | **BUILT** |
| F2 | Hybrid RAG + rerank over a guideline corpus | **BUILT** (reranker keyless‑inert — see §F2) |
| F3 | Supervisor + 2 workers with logged, inspectable handoffs | **BUILT** |
| F4 | Eval‑driven CI gate (golden set, boolean rubrics, PR‑blocking) — **the HARD GATE** | **BUILT** (regression‑block proven) |
| F5 | Citation contract + visual PDF bounding‑box overlay + click‑to‑source | **BUILT** |
| F6 | Critic agent (rejects uncited claims / unsafe actions) | **BUILT** |
| F7 | Deployed application, Week‑2 flow working | **BUILT** (live, verified) |
| F8 | Observability & cost tracking + dashboard | **BUILT** |
| — | **Human‑readable `/ready` + `/v1/status` HTML status pages** (polish) | **BUILT** (additive; JSON contract preserved — see §Status pages) |
| C1–C19 | Engineering considerations (schemas, contracts, tracing, health, OpenAPI, CI, data model, PHI, backup, FHIR integrity, HIPAA, dashboards, testing/incident docs) | **BUILT** (nuances in §3) |
| R1 | Cost & Latency report (`COST_ANALYSIS.md`) | **BUILT** |
| R3 | Baseline **CPU/memory/latency/throughput** profiles (`loadtest/`) | **BUILT** (was PARTIAL — CPU/mem added) |
| R4 | API collection (Bruno + Postman, Week‑2 flow) | **BUILT** |
| A1–A3 | Repo/setup/env docs · `W2_ARCHITECTURE.md` · README W1‑vs‑W2 split | **BUILT** |
| S1–S3 | Stretch: medication‑list doc type · lab‑trend chart · contextual retrieval | **BUILT** |
| **A4** | **Demo video (3–5 min)** | **OUTSTANDING — operator artifact (the only remaining item)** |

**Net:** every core feature, engineering requirement, report, and stretch item is built and
verified against running code. **The single outstanding deliverable is the demo video (A4)** —
an operator artifact nothing in the code blocks.

---

## 2. Feature walkthroughs (how each works behind the scenes)

### F1 — Document ingestion  ·  BUILT
**In one line:** `POST /v1/documents` → authorize → rasterize → OCR → strict‑schema VLM
extract → **OCR‑reconcile (no‑invention gate)** → append‑only persist with page+bbox
provenance → `GET /v1/documents/{id}` returns strict facts + citations.

**Full flow.**
1. **Entry / auth.** `upload_document` (`documents.py:146`) takes multipart `{file, patient_id,
   clinician_id, doc_type}`, resolves identity, **authorizes the patient against the clinician's
   rounding list** (403 off‑round), checks the ingestion kill‑switch (503), rejects an unknown
   `doc_type` (400), and calls `DocumentIngestionService.attach_and_extract` → `202 {document_id,
   status, correlation_id}`.
2. **Orchestrate + dedupe.** `attach_and_extract` (`pipeline.py:186`) parses the `DocumentType`
   enum (fails loud), computes `content_hash = sha256(bytes)`, opens the `doc.ingest` span, and
   **reuses** a prior identical upload for the same patient if one exists. *(Hardened: a re‑extract
   failure on the reuse path no longer downgrades the prior‑good document — see §4.)*
3. **Upload the source to OpenEMR.** `_upload` pushes bytes to OpenEMR via
   `OpenEmrWriteClient.upload_document`; the agent keeps only `openemr_document_id`. **OpenEMR owns
   the source of record.**
4. **Rasterize.** `raster.py` renders each page with pypdfium2 at 200 DPI, enforcing a page‑count
   cap (1000) and per‑page pixel cap (50 MP) *before* allocation.
5. **OCR.** `TesseractOcr` (or a deterministic `StubOcr` when tesseract is absent) emits word boxes
   normalized to `[0,1]` — the ground truth the no‑invention gate checks against.
6. **VLM extract (strict schema).** `vision.py` forces a single `record_extraction` tool **whose
   `input_schema` IS the strict Pydantic model's JSON schema**, then **validates via
   `schema.model_validate`**. A malformed/partial payload raises → fail‑closed.
7. **Reconcile — the no‑invention gate.** `_reconcile_facts` (`pipeline.py:380`) searches **each
   fact's own page's OCR tokens only**; `reconcile_value` scores value‑vs‑span with **two‑sided
   coverage (≥0.95) + similarity (≥0.8) + a minimal OCR legibility floor**, unioning the winning
   span's boxes into one bbox. On the page → `supported=True` + bbox (the citation); nowhere on the
   page → `supported=False`, surfaced as *unverified*.
8. **Persist (append‑only) + link.** `_persist_extraction` writes one `extraction` row then one
   `extracted_fact` row per fact (bbox/confidence/page only when supported). Linkage: `extracted_fact
   → extraction → source_document → openemr_document_id`.
9. **Surface.** `GET /v1/documents/{id}` returns each supported fact + a document‑typed citation;
   `GET …/pages/{n}` serves the page PNG for the overlay.
10. **Fail‑closed.** Every fallible stage marks `status=failed` **in its own committed transaction**
    and re‑raises — never a silent success, zero orphan facts.

**Test it:** `cd agent && .venv/bin/python -m pytest ../.swarm-loop/acceptance/ingestion/ -q
-o asyncio_mode=auto` → **8 passed**.

---

### F2 — Hybrid RAG + rerank  ·  BUILT (reranker keyless‑inert)
**In one line:** deidentify → expand → distill → **BM25 sparse + cosine dense → RRF fusion →
section boost → window → (Cohere rerank if keyed) →** top‑k grounded evidence with source metadata.

**Full flow.** `GuidelineRetriever.retrieve` (`rag/retriever.py`):
1. **Deidentify** — shape‑based PHI scrub (email/SSN/phone/date/labelled name).
2. **Expand** (`query.py`) — ~35 clinical abbreviations (DKA→diabetic ketoacidosis) *after*
   deidentify so it can't re‑introduce PHI.
3. **Empty‑corpus guard** → returns `[]` (honest no‑evidence).
4. **Distill** — reduces the query to only tokens in the corpus vocabulary/closed clinical lexicon;
   **this is the only text that egresses** to remote legs (a name the regex missed isn't in the
   corpus vocab → dropped → never leaves the process).
5. **Dense leg** — `StubEmbedder` (keyless hashing bag‑of‑words) or `VoyageEmbedder` (keyed);
   `_dense_rank` cosines, **dropping cosine ≤ 0** so a true no‑match yields empty.
6. **Sparse leg** — in‑process **BM25**, dropping zero‑score chunks.
7. **RRF fusion + section boost** — sum `1/(k+rank)` across both rankings, boost by heading‑term
   coverage.
8. **Window** — cut to `4×top_k` so rerank refines rather than *is* retrieval.
9. **Rerank fork** — **keyless (deployed): no reranker → fused order served**; keyed:
   `CohereReranker` (`rerank-v3.5`), fail‑soft. (The keyless stub was *measured harmful* and is
   intentionally gated out.)
10. **Serve** — `GuidelineEvidence` + `GuidelineCitation`, capped at 4, injected as an explicitly
    **non‑citable** block (claims stay FHIR‑grounded).

**Test it:** `.venv/bin/python -m pytest tests/test_retriever_*.py tests/test_rag_*.py -q`;
`.swarm-loop/acceptance/run.py --feature rag` → **6**.

**Honest nuance a demo MUST state:** on the deployed **keyless** config, "dense" is a lexical
hashing embedder and "rerank" is *no rerank* — so the live system is **BM25 + hashing‑cosine,
RRF‑fused, section‑boosted**: genuinely hybrid + grounded, but **lexical, not semantic**. Set
`VOYAGE_API_KEY` / `COHERE_API_KEY` to switch on semantic vectors + rerank.

---

### F3 — Supervisor + 2 workers  ·  BUILT
**In one line:** a deterministic supervisor routes an `AgentTask` to intake‑extractor and/or
evidence‑retriever via **typed, logged handoffs**, then finalizes through the critic + verifier.

**Where it runs.** The graph is wired into `POST /v1/chat` behind `chat_graph_enabled` — **default
off** in the code build (a keyless clone + the deterministic eval gate use the simpler inline verify
path), **on in the deployed demo** (`COPILOT_CHAT_GRAPH_ENABLED=true`, verified in the running
container). The fail‑closed reply invariant is identical either way; the flag adds the
supervisor→worker→critic routing (and, with a key, the real haiku critic).

**Full flow.** `AgentGraph.run` (`graph/supervisor.py`): (1) **route** — a pure signal test
(`document_ids` → intake; guideline intent → evidence; both → both; neither → chart‑only), logged as
`route_plan`; (2) **dispatch intake** — logs a typed `Handoff{payload={document_ids}}`, opens child
span, reads the **patient‑scoped** stored extractions (cross‑patient read refused); (3) **dispatch
evidence** — logs `Handoff{payload={signals}}`, opens the retriever span; (4) **finalize** — hands
guideline chunks + doc facts to the answerer as prose‑only context, runs the deterministic serve‑time
verifier, then the critic; (5) **gate** — `_should_withhold` escalates a verifier `degraded`, a critic
`unsafe`, or a critic rejection of a passed claim to a **whole‑turn withhold**.

Handoffs are logged and inspectable — a live `graph.run()` shows `route_plan=['intake','evidence']`
and the ordered `supervisor→intake‑extractor`, `→evidence‑retriever`, `→critic` handoffs.

**Test it:** `.venv/bin/python -m pytest ../.swarm-loop/acceptance/graph/ -q -o asyncio_mode=auto`
→ **7 passed**.

---

### F4 — Eval‑driven CI gate (the HARD GATE)  ·  BUILT ✅ regression‑block proven
**In one line:** a deterministic, LLM‑free gate over **62 cases** (53 fixture + 9 live‑code) scoring
five boolean rubrics, **failing the build (exit ≠ 0)** on any category regressing >5% or below floor.

**Full flow.** `agent/evals/gate.py` grades the union of a **fixture tier** (`gate_dataset.jsonl` 13 +
`golden_dataset.jsonl` 40 = 53 committed cases, pinning rubric logic) and a **live tier**
(`live_cases.py`, 9 cases that run real `copilot` code at gate time so the gate can't be a vacuous
fixture‑grader). Rubrics: `schema_valid`, `citation_present`, `factually_consistent`, `safe_refusal`,
`no_phi_in_logs`. Blocks on aggregate floor, per‑category floor, or >5% drop. Wired PR‑blocking two
ways: `.githooks/pre-push` and the GitLab `agent:tests` job.

**Proven personally (the exact commands a grader runs):**
```
.venv/bin/python evals/gate.py                     # cases: 62 → exit 0, pass_rate 100
.venv/bin/python evals/gate.py --inject-regression # exit 1 (BLOCKS)
```
The second audit pass independently **sabotaged four real production functions** (`deidentify`,
`_passed_claims`, `_values_equal`, `retrieve`) and confirmed the live tier goes red each time — not
just the built‑in self‑proof. This is the item the submission hinges on, and it holds.

---

### F5 — Citation contract + PDF bbox overlay  ·  BUILT
**In one line:** the OCR‑reconciled bbox is computed → stored on the fact → served over HTTP → drawn
as an SVG rect over the real page image; every citation carries the 5 required keys.

**Full flow.** (1) **compute** — `reconcile_value` unions matched OCR token boxes into `[x,y,w,h]`
(`supported=False` ⇒ no box); (2) **store** — `ExtractedFactRow.bbox`; (3) **metadata** —
`_citation_body` builds the 5‑key `{source_type, source_id, page_or_section, field_or_chunk_id,
quote_or_value}` + `bbox` + `confidence`; (4) **page image** — `GET /v1/documents/{id}/pages/{n}`
serves the PNG backdrop; (5) **render** — the React panel maps the normalized box to a pixel rect and
draws one `<rect>` in an `<svg preserveAspectRatio="none">` over the `<img>`; (6) **click‑to‑source** —
the chip opens the boxed page; degrades to text‑only if the image is unavailable.

**Nuance a reviewer should hear:** the overlay is reached from the **document‑upload panel** (one chip
per supported fact), *not* by clicking a **chat** claim — chat claims cite live FHIR records (the
`fhir` variant, no box). Demo the upload panel for the bbox overlay.

---

### F6 — Critic agent  ·  BUILT
**In one line:** two layers behind the `Critic` protocol — a deterministic **uncited‑claim rejecter**
(always on) and a keyed LLM **unsafe‑action rejecter** (demote‑only, fail‑closed, fail‑safe).

`_partition` accepts a claim iff it carries a machine‑readable citation, else rejects. `RealCritic`
runs the deterministic gate first, then a cheap gating‑model pass that can **only demote** an
already‑cited claim (never resurrect). Reason classification is a **fail‑closed exact‑match whitelist**
(only bare `narrative_inconsistency` gets the mild treatment; anything else → `unsafe_action`). Any LLM
error → fail‑safe to the deterministic partition. An `unsafe_action` triggers a **whole‑turn withhold**.

**Design nuance (option‑B):** the critic reviews the **grounded claim chips**, not the free‑text
narrative — the narrative is prompt‑constrained *trusted narration*, and the protection is the
whole‑turn withhold, not a sentence screen. A dedicated prose screen is Week‑3 scope.

---

### F7 — Deployed application  ·  BUILT (live, verified)
**In one line:** a single‑VM Docker Compose stack — Caddy (sole ingress) → the port‑less `agent`
container → pgvector + OpenEMR/mariadb — with `/ready` gating on the manual migration step.

**Full flow.** **Ingress:** `caddy` publishes 80/443, reverse‑proxies `/v1/*`, `/health`, `/ready`,
`/status`, `/openapi.json` to internal `agent:8000`, and serves the built React SPA. The `agent`
container **publishes no host port**. **Build:** multi‑stage non‑root (uid 10001) image with tesseract
+ corpus + status artifacts baked in and a `/health` HEALTHCHECK. **Manual steps** (`DEPLOY.md §5/§18`):
copy `Caddyfile.example` + build the SPA **before** the first `up --wait`, then `alembic upgrade head`
and `ingest_guidelines.py`. **SMART login:** the physician logs in on OpenEMR's real authorize page;
`create_app` refuses to boot on an unsafe smart config.

**Grader click‑path:** `POST /v1/rounds/start` → `POST /v1/documents` → `GET /v1/documents/{id}?clinician_id=…`
(poll `extracted`, facts+citations) → `GET …/pages/{n}` → `POST /v1/chat`. The `api-collection/` chains
all of this.

**Verified live (this deploy):** HEAD `1fe8f5a`; `/ready` → `ready:true` (document_store, migrations
head `0009`, smart_config, pgvector, corpus 19 chunks, embedder/reranker stub, openemr_fhir, llm,
langfuse all green); public edge → 200; the HTML status page renders in a browser.

---

### F8 — Observability & cost tracking  ·  BUILT
**In one line:** a correlation id minted at the boundary threads nested spans that each record
latency/tokens/cost/hits/confidence; PHI is scrubbed at the single Langfuse egress; `/v1/status`
aggregates a live dashboard.

**Full flow.** (1) `CorrelationIdMiddleware` mints/echoes `X-Correlation-ID` (an invalid inbound id is
re‑minted, and the failure path logs too so error‑rate can't under‑count); (2) the first span opens the
Langfuse trace **keyed by that id**; children nest (`graph.run → supervisor.route → {intake, evidence,
finalize.verify}`); (3) each step records its signals; (4) `finalize.verify` computes tokens + `cost =
cost_usd(model, in, out)`; (5) the graph packs all **seven** required fields into a typed `GraphMetrics`
+ a `graph.telemetry` event; (6) every payload passes `PatientPseudonymizer.scrub` — HMAC the
`patient_id`, or **drop it fail‑closed** when the key is unset; (7) `GET /v1/status` aggregates a live
dashboard with a `metric_sources` provenance label per metric.

**Reachability probes (C7):** `/ready` grades each Week‑2 dep; the reranker/embedder probes now do a
**real reachability check when keyed** (Cohere `GET /v1/models`; Voyage one‑token embed) and stay a
byte‑identical no‑network stub when keyless (the deployed state).

**Test it:** `.venv/bin/python -m pytest tests/test_observability_honesty.py -q`; `GET /v1/status` → 200.

---

### Status pages (`/ready` + `/v1/status`)  ·  BUILT (additive polish)
`GET /ready` and `GET /v1/status` now **content‑negotiate on `Accept`**: a browser gets a polished,
self‑contained HTML status page (READY/NOT‑READY banner, per‑dependency ok/degraded/down pills, metric
cards with provenance badges, light/dark, XSS‑escaped, inline CSS only — CSP‑safe); every programmatic
client (`application/json`, `*/*`, no Accept) gets the **byte‑identical JSON** the deploy gate, the
OpenAPI contract test, and the frozen acceptance suite depend on. The OpenAPI spec is unchanged
(`response_model` pinned). Verified live at both endpoints.

---

## 3. Engineering considerations (BUILT — key nuances)

- **C1 strict schemas** — all document models are `strict=True, extra="forbid", frozen=True`,
  `facts` `min_length=1`. **By design:** 4 lab fields + intake categories are optional‑with‑default
  (anti‑invention; absence surfaced as `missing_lab_fields`/`incomplete_facts`, never hidden).
- **C2 contracts + migration + authority** — typed Pydantic boundaries; additive nullable migrations
  (linear head `0009`); fail‑closed + append‑only + propose→confirm.
- **C3–C5 correlation id + structured logging + tracing** — trace reconstructs from the id alone;
  one JSON line/record with the id; worker spans are true children (verified span tree).
- **C7 /health + /ready** — distinct routes; `/ready` grades each dep ok/degraded/down; reranker/
  embedder now do real reachability when keyed (see §F8).
- **C8 OpenAPI** — committed `week2.yaml` (**3.1.0**, deliberately — FastAPI/Pydantic v2 emit
  JSON‑Schema‑2020‑12 3.0 can't express), enforced by `test_openapi_contract.py` (committed==generated).
- **C10 CI** — build/lint/typecheck/tests/coverage all present; dep‑audit + security‑scan advisory by
  design (an upstream CVE mustn't wedge unrelated PRs).
- **C12 PHI audit** — the blocking `agent:phi` corpus now spans the chat egress **and all five
  lifecycle families** (doc.ingest, extraction.run, guideline.retrieve, worker.handoff,
  verification.result); proven to bite (neuter `deidentify` → PHI detected). Disclosed limit:
  `phi_check` has no bare‑integer detector (deliberate, to avoid flagging latency/token counts).
- **C13 backup/recovery** — `DEPLOY.md §19` artifact classes + RPO/RTO + honest "no scheduled backup
  runs today"; eval golden set verified reproducible from the repo alone.
- **C16 HIPAA** — synthetic seed data; three‑layer PHI control (pseudonymize/deidentify/logging),
  CI‑enforced. Disclosed bound: `deidentify` is a shape‑scrub not NER.
- **C17–C19** — dashboard + alert defs (`OBSERVABILITY.md`); testing‑strategy + incident‑response
  (`W2_ARCHITECTURE.md`). The eval‑regression (>5%) check is a CI blocker, not a runtime alert.

**Reports:** **R1** `COST_ANALYSIS.md` (§9a labeled as the 2026‑07‑10 warm‑stub floor; the current
`loadtest/RESULTS.md` is the 07‑19 re‑capture whose higher numbers are the documented FHIR‑retry
artifact). **R3** `loadtest/` now has **latency + throughput + CPU + memory** (10u CPU peak 35.8% /
RSS 139.6 MB; 50u CPU peak 105.2% / RSS 182.3 MB — one worker ~1 core, RSS flat = no leak). **R4**
`api-collection/` (Bruno 28 + Postman, full Week‑2 flow).

---

## 4. What the two hardening passes changed (audit trail)

**Final gap‑fix pass** (before the second audit): **R3** CPU/mem profiles added; **C7** real reachability
probes; **C12** PHI corpus extended to all five lifecycle families; eval‑count docs corrected to
**62 (53 fixture + 9 live)** and OpenAPI label to **3.1.0**; the **HTML status pages** shipped.

**Second adversarial pass** — 5 read‑only auditors (deltas / core‑pipeline / boundary‑ops /
tests‑evals‑CI / broad catch‑all) found **0 P0, 3 P1, ~11 P2**, all now fixed (7 commits, `7f2ffcc…1fe8f5a`):
- **Security** — `/ready` no longer leaks raw SQLAlchemy `[SQL: …]` text (message‑safe classifier).
- **Ingestion** — the reuse/dedupe path no longer downgrades an already‑extracted document (+ no
  duplicate row) on a transient re‑extract failure.
- **Verification** — serve‑time document‑fact grounding is now patient‑scoped (defense‑in‑depth,
  matching the intake extractor).
- **Deploy** — bare `/status` routed through Caddy; `.env.deploy.example` templates the optional RAG
  keys; Dockerfile comment corrected.
- **Docs** — `DEPLOY.md` first‑boot ordering (caddy needs Caddyfile + built SPA before `up --wait`),
  the `/evidence`→`/documents/{id}` 404, in‑container smoke curls, `postgres`→`document_store`, the
  `/status` eval‑scope back to 53‑fixture; `COST_ANALYSIS.md` §9 latency provenance + drift fixes;
  `OBSERVABILITY.md` line cites; README test count → ~1454; dead `ARCHITECTURE.md` /
  `PRODUCTION_GRADE_PLAN.md` references repointed/removed.
- **Lint** — pre‑existing unused imports removed (`ruff check` clean).

---

## 5. Gap memo — what's still needed for final

**The only outstanding deliverable:**
- **A4 — Demo video (3–5 min).** Operator artifact, not in the repo. Should show: upload → extraction →
  evidence retrieval → citations → eval results → observability. Nothing in the code blocks it. The
  deployed demo at **https://agentforge.hankholcomb.com** already runs the full Week‑2 flow to record
  against.

Everything else surfaced by two adversarial passes has been fixed and verified.

## 5a. Live‑testing pass (2026‑07‑19) — findings + disposition

Real end‑to‑end testing on the deploy surfaced four items:

- **Uploads intermittently 500'd** (`medication_list`, `intake_form`). Root cause: the extractors put
  VLM free text (a medication frequency, `"Twice daily (with meals)"`) into `abnormal_flag`, a
  `varchar(16)` sized for lab `H`/`L` flags; the non‑deterministic VLM made the *same* upload
  fail‑then‑succeed on retry. **FIXED + deployed** — migration `0010` widens the free‑text columns to
  `TEXT` (HEAD `0d75648`; verified: columns now `text`, `/ready` at head `0010`).
- **Langfuse showed few/late traces.** Not a bug — the hobby‑tier SDK batches + ingests with a delay
  (>15 min observed); the traces appeared. On the deploy a chat turn surfaces as a **`graph.run`** trace
  (the graph path owns telemetry), a doc upload as **`doc.ingest`**.
- **Many document values show "NOT FOUND ON PAGE."** The no‑invention gate erring safe — see §6. A
  recovery is specced as a Week‑3 item (`agent/research/week3/02-ocr-flag-merge-reconcile.md`).
- **The patient chart doesn't change after an upload.** **By design** — ingestion writes to the agent's
  append‑only store and surfaces facts in the *"From the uploaded document"* panel (citable in chat);
  merging them into the OpenEMR chart is the physician‑gated propose→confirm write‑back
  (`COPILOT_WRITEBACK_ENABLED`, off on the demo). Auto‑writing extracted values into the legal chart
  would be unsafe.

---

## 6. Do‑not‑fix list (settled / by‑design / honestly disclosed)

- **The one red frozen test.** `.swarm-loop/acceptance/api/test_api_02_document_status_pages.py`
  expects an *unauthenticated* `GET /v1/documents/{id}` to return 200; the correct document‑read authz
  now returns 400. The frozen test can't be edited; it's invisible to CI (not in `testpaths`); the
  shipping API collection + the project's own auth tests handle it correctly. This is why `--pass-rate`
  is 97.83 (45/46), not 100 — a stale goal, not a defect. **Do not weaken auth to "fix" it.**
- **Optional lab fields (C1)** — deliberate anti‑invention design, loudly reported.
- **Keyless rerank inert / lexical dense (F2)** — a config choice; keyed flips both on.
- **Bbox overlay on the upload panel, not chat claims (F5)** — chat claims cite live FHIR by design.
- **Prose is trusted narration, not hard‑screened (F6 / option‑B)** — the audited surface is the claim
  chips; prose screening is Week‑3.
- **`deidentify` is a shape‑scrub, not NER (C16)** — bounded and documented.
- **`phi_check` has no bare‑integer detector (C12)** — deliberate, to avoid flagging latency/token
  counts.
- **Single‑worker idempotency store (C14)** — documented; fail direction is safe.
- **Backup automation not yet installed (C13)** — honestly disclosed with the recovery procedure +
  RPO/RTO.
- **`reconcile_value` over‑withholds a literal zero‑confidence OCR token even at threshold 0.0** —
  safe direction, documented; the deployed default is 0.01.
- **Some document values show "NOT FOUND ON PAGE" — the no‑invention gate erring safe, not a bug.**
  Tesseract merges an adjacent abnormal‑flag letter into the value token (`38 H` → `38H`) or misreads a
  faint value (`4.2` → `4.24` @ conf 0.20); two‑sided coverage then refuses a citation because the OCR
  text doesn't cleanly confirm the extracted value. The value is still shown — just marked *unverified*
  rather than given fabricated provenance (the safety feature working). A targeted OCR‑merge recovery is
  queued for **Week 3** (`agent/research/week3/02-ocr-flag-merge-reconcile.md`). Root‑caused from the
  live‑deploy OCR, 2026‑07‑19.
- **`loadtest/RESULTS.md` 07‑19 latencies are FHIR‑absent‑retry‑inflated** — documented in the file's
  own provenance note; the meaningful serve‑layer floor is the archived 2026‑07‑10 capture.

---

*Audited read‑only across two adversarial passes (13 auditor runs total) plus personal verification of
the hard gate and the live deploy; every verdict traces to code + observed command output. The docs
consistently under‑claim rather than over‑claim.*
