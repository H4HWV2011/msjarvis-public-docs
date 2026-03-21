# Why This Matters for Polymathmatic Geography

This chapter explains how Ms. Jarvis protects her "brain" from harmful inputs, unreliable data, and unsafe outputs, especially when working with sensitive, place‑based information. It supports:

- **P1 – Every where is entangled** by ensuring that ethical, spiritual, safety, and truth checks constrain what can entangle with memories about communities and places stored in PostgreSQL `msjarvis` (port 5433) and `gisdb` (port 5433, 13 GB, 39 tables) and ChromaDB (port 8000, 5,416,521 GBIM entities), both before storage and after generation.

- **P3 – Power has a geometry** by making protection a layered, routed structure in the service graph rather than a hidden afterthought, with explicit barrier and truth layers visible in health and consciousness metadata.

- **P5 – Design is a geographic act** by treating safeguards as designed interfaces between communities' data, legal constraints, and Ms. Jarvis's internal cognition, rather than a generic "safety filter."

- **P12 – Intelligence with a ZIP code** by requiring additional truth and identity checks when data is tied to specific residents, licenses, or infrastructures grounded in PostgreSQL spatial tables, and by recording how those checks were applied.

- **P16 – Power accountable to place** by logging barrier decisions, truth verdicts, and verification results so that communities can reconstruct when and how the system blocked, reshaped, or allowed sensitive flows.

As such, this chapter belongs to the **Computational Instrument** tier: it specifies the "blood–brain barrier" and truth‑filtering apparatus of Ms. Jarvis's architecture, where safety, ethics, and truth are enforced around core neurobiological and memory systems.

```
┌─────────────────────────────────────────────────────────────┐
│   Blood-Brain Barrier and Safeguards Architecture           │
├─────────────────────────────────────────────────────────────┤
│                                                              │
│  User Input / GIS Data / Psychological Content              │
│      ↓                                                       │
│  ┌────────────────────────────────────────────────┐         │
│  │  Blood-Brain Barrier (port 8016)               │         │
│  │  ┌──────────────────────────────────────────┐  │         │
│  │  │  -  EthicalFilter       → .filter(text)   │  │         │
│  │  │  -  SpiritualFilter     → .filter(text)   │  │         │
│  │  │  -  SafetyMonitor       → .check(text)    │  │         │
│  │  │  -  ThreatDetection     → .detect_threats │  │         │
│  │  │  -  SteganographyFilter → .scan(text)     │  │         │
│  │  │  -  TruthVerification   → .verify(text)   │  │         │
│  │  │     (heuristic_contradiction_v1)           │  │         │
│  │  │  -  MotherCarrieProtocol (routing flag)   │  │         │
│  │  └──────────────────────────────────────────┘  │         │
│  │  Endpoints: POST /filter, POST /truth           │         │
│  │  Stats: total_filtered:19, total_blocked:2      │         │
│  │          pass_rate: 0.89                        │         │
│  └────────────────────────────────────────────────┘         │
│      ↓ (if approved)                                        │
│  ┌────────────────────────────────────────────────┐         │
│  │  Truth Validators                              │         │
│  │  -  GISTruthFilter (geographic data)            │         │
│  │  -  TruthFilterBBBValidator (UEID/licenses)     │         │
│  │  -  TruthValidator (generated statements)       │         │
│  └────────────────────────────────────────────────┘         │
│      ↓ (if validated)                                       │
│  ┌────────────────────────────────────────────────┐         │
│  │  Psychological Services                        │         │
│  │  -  psychological_rag_domain (port 8006)        │         │
│  │  -  jarvis-psychology-services (port 8019)      │         │
│  │  -  PIA review loop (log sampling)              │         │
│  └────────────────────────────────────────────────┘         │
│      ↓                                                       │
│  Core Cognition & Memory                                    │
│  -  PostgreSQL msjarvis (port 5433) — GBIM beliefs           │
│  -  PostgreSQL gisdb (port 5433) — PostGIS spatial           │
│  -  ChromaDB (port 8000) — 5,416,521 GBIM entities           │
│  -  I-Containers (port 8015)                                 │
│  -  Neurobiological Master (port 8018)                       │
│      ↓                                                       │
│  LLM Generation                                             │
│      ↓                                                       │
│  ┌────────────────────────────────────────────────┐         │
│  │  Judge Pipeline (127.0.0.1:7239)              │         │
│  │  POST /evaluate — consensus answer only        │         │
│  │  asyncio.gather() — 4 sub-judges parallel      │         │
│  │      ↓ (after verdict aggregation)             │         │
│  │  bbb_check_verdict → POST /filter              │         │
│  │  jarvis-blood-brain-barrier:8016/filter        │         │
│  │  {content: final_answer, verdict: verdict_dict}│         │
│  │  6 filters: ethical, spiritual, safety,        │         │
│  │             threat_detection, steganography,   │         │
│  │             truth_verification                 │         │
│  │  bbb_checked: true (March 21, 2026)            │         │
│  └────────────────────────────────────────────────┘         │
│      ↓                                                       │
│  Output Guard (BBB /filter on generated text)               │
│  — fail-open on HTTP 500 (returns content unchanged)        │
│      ↓                                                       │
│  Response + truth_verdict + bbb_checked                     │
│                                                              │
│  Audit Logs → barrier_stats, verification outcomes          │
│               total_filtered:19, total_blocked:2            │
│               pass_rate: 0.89                               │
│                                                              │
└─────────────────────────────────────────────────────────────┘
```

> **Figure 16.1.** Blood–brain barrier and safeguards in Ms. Jarvis: user inputs, GIS and UEID data, and psychological content are routed through a barrier and truth layer (BBB, GIS and identity validators, psychological guidance) before reaching core cognition and long‑term, WV‑grounded memory in PostgreSQL `msjarvis` (GBIM beliefs) and `gisdb` (PostGIS spatial). As of March 21, 2026, the judge pipeline coordinator (`jarvis-judge-pipeline:7239`) also calls `POST /filter` on the BBB after verdict aggregation, adding a second live BBB evaluation at the judge coordination layer. The output guard is fail-open on HTTP 500 responses from the BBB. `barrier_stats` as of March 21: `total_filtered: 19`, `total_blocked: 2`, `pass_rate: 0.89`.

---

## Status as of March 21, 2026

| Category | Details |
|---|---|
| **Implemented and verified** | `jarvis-blood-brain-barrier` confirmed running at **127.0.0.1:8016** (corrected from `0.0.0.0:8016` — March 18, 2026). Exposes `GET /health`, `POST /filter`, and `POST /truth`. Six sub‑filters confirmed operational with verified live scores (March 21, 2026): `EthicalFilter.filter(text)` (score: 1.0), `SpiritualFilter.filter(text)` (score: 1.0), `SafetyMonitor.check(text)` (score: 1.0), `ThreatDetection.detect_threats(text)` (score: 1.0), `SteganographyFilter` — `zero_width_homoglyph_structural_v1` (clean), `TruthVerification` — `heuristic_contradiction_v1` (score: 1.0). `POST /truth` endpoint returns `{"valid": bool, "confidence": float, "principal_reasons": [str]}`. `barrier_stats` counters confirmed: `total_filtered: 19`, `total_blocked: 2`, `pass_rate: 0.89`. `truth_verdict` attached to every `UltimateResponse` from main brain (port 8050). Output guard on generated text active in main brain pipeline via `apply_output_guards_async` calling `/filter` with 8.0s timeout (fixed 2026‑03‑02). **Fail-open behavior confirmed (March 18, 2026):** BBB output guard returns content unchanged on HTTP 500 responses. **`truth_score` null guard confirmed (March 18, 2026).** **Judge pipeline → BBB integration confirmed (March 21, 2026):** `bbb_check_verdict` in `judge_pipeline.py` issues live async httpx `POST /filter` call to `jarvis-blood-brain-barrier:8016/filter`; `bbb_checked: true` in all judge pipeline outputs; all 6 BBB filters passing on identity-question benchmark. `MotherCarrieProtocol` implemented as routing/emphasis/audit pattern **inside** BBB. `jarvis-psychology-services` confirmed running at **127.0.0.1:8019**. `psychological_rag_domain` confirmed running at **127.0.0.1:8006**. PostgreSQL `msjarvis` (port 5433, 5,416,521 GBIM entities) and `gisdb` (port 5433, PostGIS, 13 GB, 39 tables) are the protected memory stores. |
| **Partially implemented / scaffolded** | Internal BBB filter logic is relatively permissive in the current deployment — often echoes content with placeholder reason codes. `TruthVerification` uses `heuristic_contradiction_v1` (rule-based, internal contradictions only — not live GBIM lookup; see §16.12). `GISTruthFilter`, `TruthFilterBBBValidator`, and `TruthValidator` are not yet consistently wired into all HTTP paths beyond dedicated verification and registration tools. Richer user-visible explanations of barrier decisions beyond the compact `truth_verdict` field are an open design area. Psychological classifier and trigger logic is partially heuristic. |
| **Future work / design intent only** | Full wiring of truth validators into all HTTP flows. `rag_grounded_v2` truth verification — wire truth verification into `jarvis-spiritual-rag:8005` or `jarvis-gis-rag:8004` for claim checking against retrieved GBIM documents (upgrade path from `heuristic_contradiction_v1`). Richer public documentation of filter logic and scores. Actual quarantine collections for blocked content (currently tracked only via counters). Empirical evaluation of barrier and output guard effectiveness in real community deployments. Deeper PIA review loop producing structured recommendations beyond current log-sampling pattern. |

> **Cross-reference note:** The canonical description of how BBB fits into the live `ultimatechat` execution path — including where `truth_verdict` is attached to `UltimateResponse` and where the output guard fires — is in **Chapter 17**. The judge pipeline's `bbb_check_verdict` integration is documented in full in **Chapter 33 §33.2**. The Neurobiological Master's use of BBB as its first pipeline stage is documented in **Chapter 12 §12.2**. Psychological safeguard detail is in **Chapter 29**. Mother Carrie protocol detail is in **Chapter 34**.

---

# 16. Blood–Brain Barrier and Safeguards

In the current deployment, this layer is a set of confirmed running services that sit between external inputs, large‑scale generative models, and core neurobiological and memory systems — including PostgreSQL `msjarvis` (port 5433, GBIM beliefs, 5,416,521 entities) and `gisdb` (port 5433, PostGIS spatial, 13 GB, 39 tables), and ChromaDB (port 8000, `gbim_worldview_entities` 5,416,521 entities) — enforcing ethical, spiritual, safety, steganography, and truth‑focused checks before and after content can influence I‑containers and long‑term stores. As of March 21, 2026, the BBB is also invoked by the judge pipeline coordinator (`jarvis-judge-pipeline:7239`) as a post-verdict output guard, adding a second live BBB evaluation at the judge coordination layer. As shown in Figure 16.1, the BBB aggregates these checks in a single barrier layer before and after content reaches core cognition.

---

## 16.1 Purpose of the Barrier Layer

In the current deployment, `jarvis-blood-brain-barrier` on **port 8016** (bound to `127.0.0.1` — corrected March 18, 2026) is explicitly described as "Ethical and safety filtering for all inputs and outputs" and aggregates six sub‑filters. The confirmed method signatures and live-verified scores (March 21, 2026, test query: "What is the capital of West Virginia?") are:

- `EthicalFilter.filter(text)` — evaluates content for ethical violations; score: **1.0**
- `SpiritualFilter.filter(text)` — checks for biblical soundness and spiritual alignment; score: **1.0**
- `SafetyMonitor.check(text)` — evaluates safety classification; score: **1.0**
- `ThreatDetection.detect_threats(text)` — checks whether content is community‑safe; score: **1.0**
- `SteganographyFilter` (`zero_width_homoglyph_structural_v1`) — scans for hidden/encoded content in zero-width characters and homoglyphs; result: **clean**, confidence: **1.0**
- `TruthVerification` (`heuristic_contradiction_v1`) — rule-based internal contradiction detection; score: **1.0** (see §16.12 for honest limitations)

The core filtering method in `/filter` increments counters, invokes all six methods above, and only approves content when all filters pass. Prior to 2026‑03‑13, the four original sub-filter methods were defined in the codebase but were not correctly called inside the `/filter` request handler — the wiring was repaired during the 2026‑03‑13 remediation session. The steganography and truth_verification filters were added and confirmed live as of March 21, 2026.

**False-positive resolution — word-boundary detection (March 15, 2026):** The `_check_keywords()` method was corrected to use regex word boundary detection (`\b`) for keywords ≤3 characters. Community resource terms ("con," "res," etc. as substrings inside benign words such as "Context," "Collective," "resources") no longer trigger safety blocks. Jailbreak attempts using those character sequences as actual words are still correctly blocked.

**`truth_score` null guard (March 18, 2026):** A null guard has been added to the BBB orchestrator for the `truth_score` field. Previously, if the BBB `/truth` response omitted `truth_score`, the orchestrator raised a `KeyError` and the pipeline halted. The null guard resolves to a safe default (`0.0`), allowing the pipeline to continue and logging the missing field for investigation.

**Fail-open on HTTP 500 (March 18, 2026):** The BBB output guard (`apply_output_guards_async`) now implements fail-open behavior on non-200 responses from the BBB. If the BBB returns HTTP 500 (or any non-200), the pipeline returns the content unchanged rather than halting. This ensures that a BBB service error does not prevent Ms. Jarvis from responding to community queries. The fail-open behavior is logged so that operators can identify and remediate BBB instability.

**"Certainly" blocking — BY DESIGN:** The BBB ethical filter blocks responses containing unverified specific claims, including certain usages of high-confidence language such as "certainly" when the underlying claim is not backed by verified data. This is not a false positive or a calibration error. It is the constitutional layer enforcing epistemic honesty: Ms. Jarvis should not express certainty about facts she cannot verify.

In the current deployment, the BBB keeps totals of filtered and blocked items and computes a `pass_rate`, giving a transparent quantitative view of how often the barrier intervenes. Confirmed `barrier_stats` as of March 21, 2026: `total_filtered: 19`, `total_blocked: 2`, `pass_rate: 0.89`.

---

## 16.2 The `/truth` Endpoint

As of **2026‑03‑13**, the BBB exposes a confirmed operational endpoint: `POST /truth`. This endpoint accepts `{"content": str}` and returns a structured truth verdict:

```json
{
  "valid": true,
  "confidence": 0.0,
  "principal_reasons": ["string"]
}
```

This endpoint is called by the main brain's `call_truth_filter` helper, which sends the raw user message to `POST /truth` before the LLM synthesis step. The result is attached as `truth_verdict` on the `UltimateResponse`. An example from the 2026‑02‑15 case study: `{"valid": false, "confidence": 0.9, "principal_reasons": ["Ethics: 1 violations detected"]}` (see Chapter 9 §9.3.5).

**`truth_score` null guard (March 18, 2026):** The BBB orchestrator now includes a null guard for the `truth_score` field in the `/truth` response. If `truth_score` is absent from the BBB response, the orchestrator resolves to `0.0` rather than raising a `KeyError`. Code that consumes `truth_score` downstream must treat `0.0` as "unknown / unverified" rather than "verified false."

In the current deployment, the truth verdict is **advisory** — it is logged and exposed to callers but does not hard-gate the input pipeline. Hard-gate behavior for specific role or threat levels is identified as future work.

---

## 16.3 Placement in the Overall Architecture

In the current deployment, the BBB is treated as a distinct consciousness layer alongside I‑containers, qualia, the Neurobiological Master, consciousness bridge, swarm intelligence, and the NBB prefrontal cortex, with port 8016 listed in the unified consciousness schema. Health endpoints expose fields such as `barrier_active` and `filters_operational`, and higher‑level gateways use these to decide whether to mark `"blood_brain_barrier"` as active in their `consciousness_active` maps and `layers_processed` pipeline metadata.

**MotherCarrieProtocol** is implemented as a routing/emphasis/audit pattern **inside** the BBB service — not as a separate container. The flag `mothercarrieenabled` controls stricter care‑focused routing when set to true; it is a boolean configuration value, not a mystical mode. A `SpiritualFilter` alias provides Christian-only legacy mode for backward compatibility with earlier deployments. For full detail on this protocol, see **Chapter 34**.

In earlier "complete integration" pipelines, the BBB was invoked as the first gate on content — called before any MountainShares, location, psychological, temporal, or maternal processing — so that unsafe material could be blocked outright. In the current `Ms. Jarvis ULTIMATE` main brain, the BBB continues to sit close to the surface and is woven into the executive coordination layer: a dedicated truth‑filter helper evaluates the incoming message via `/truth`, and a separate output guard filters the generated response via `/filter`, giving both input‑side assessment and output‑side protection. As of March 21, 2026, the judge pipeline coordinator also calls `/filter` after verdict aggregation (see §16.11 and Chapter 33 §33.2).

**Output guard fail-open behavior (March 18, 2026):** The output guard (`apply_output_guards_async`) is fail-open on non-200 responses from the BBB. For the canonical description of exactly where in the `ultimatechat` sequence BBB fires, see **Chapter 17**.

---

## 16.4 Source Policies and Gateways

In the current deployment, BBB participation is exposed through dedicated routes that make the barrier's role explicit. Academic and public gateways provide `/truth/filter` or similar endpoints that accept user text, forward it to the BBB's `/filter` interface, and return the JSON result or a conservative default when the service is unavailable, making the BBB the policy enforcement point for truth and safety filtering.

A secured swagger gateway extends this by exposing higher‑level `/truth/validate` endpoints under a "Truth Filter" tag, returning structured assessments (`statement`, `valid`, `confidence`, `reasoning`) and enabling external tools to query the system's self‑declared truth stance without directly touching internal stores or PostgreSQL GBIM tables.

---

## 16.5 Screening, Quarantine, and Output Guarding

In the current deployment, variants of the barrier implement screening behavior that can either block content outright or strip it before passing it onwards. Earlier pre‑integration services exposed `/process` and returned either the original content or an empty string plus a `filtered: True` flag depending on the combined verdict of ethical, spiritual, and safety filters, ensuring that blocked material did not reach downstream components even when the call chain continued.

The production service on port **8016** augments this with `barrier_stats` counters (`total_filtered`, `total_blocked`, `pass_rate`), which serve as a crude quarantine metric by tracking how often content is stopped or allowed through. Confirmed live values (March 21, 2026): `total_filtered: 19`, `total_blocked: 2`, `pass_rate: 0.89`. Actual quarantine collections are managed in GIS and UEID databases by associated truth‑filter modules; dedicated ChromaDB quarantine collections for the BBB itself are identified as future work.

In the current main brain pipeline, `apply_output_guards_async` calls `POST /filter` on the BBB with an 8.0s timeout (corrected from `None` on 2026‑03‑02 to prevent indefinite hang after LLM completion). It selects a safe text field from the response when available, giving the system an opportunity to redact or reshape responses before they are returned to users.

**Fail-open on HTTP 500 (confirmed March 18, 2026):** If the BBB returns a non-200 response (including HTTP 500), `apply_output_guards_async` returns the content unchanged rather than halting the pipeline. The failure is logged with the HTTP status code for operator remediation. This behavior does **not** disable the BBB — on healthy responses, the BBB output guard operates normally.

---

## 16.6 Truth‑Focused Evaluation

In the current deployment, several dedicated truth‑filter classes evaluate factual quality and identity claims before data reaches PostgreSQL long‑term stores or is used for critical operations.

`GISTruthFilter` validates geographic data destined for spatial tables by checking coordinate precision and last‑verified timestamps and by cross‑checking authoritative sources (USGS, NRCS, NOAA, US Census Bureau), only allowing ingestion when uncertainty is below a threshold and at least one source cross‑check succeeds. This protects the PostgreSQL `gisdb` spatial tables from unreliable coordinate data.

`TruthFilterBBBValidator` applies truth and BBB‑style standards to driver license data used in UEID registration, checking license number presence, expiration dates with a buffer window, photo hash presence, and plausible age. It computes accuracy and ethics scores, rejects registrations below a configured minimum, and stores verification outcomes in UEID identity and audit tables.

A more general `TruthValidator` class focuses on generated or internal statements, flagging plausible hallucinations, identity confusion, and factual or terminology errors before those statements are used for decision‑making or stored as knowledge in PostgreSQL `msjarvis` GBIM tables. In the current deployment, all three validators are implemented and used in batch / command-line flows and UEID registration. They are not yet consistently wired into all HTTP paths beyond dedicated verification and registration tools; broader HTTP wiring is identified as near‑term work.

---

## 16.7 Truth‑Related Signals and Labels

In the current deployment, these truth filters return structured outputs rather than bare booleans.

The `POST /truth` endpoint on the BBB itself returns `{"valid": bool, "confidence": float, "principal_reasons": [str]}`.

**`truth_score` null guard:** The BBB orchestrator's handling of the `/truth` response now includes a null guard for the `truth_score` field. If this field is absent from the response, the orchestrator resolves to `0.0` and logs the missing field rather than raising a `KeyError`. Code that consumes `truth_score` downstream must treat `0.0` as "unknown / unverified" rather than "verified false."

`TruthFilterBBBValidator` constructs verification documents containing `valid`, `accuracy_score`, `ethics_score`, `issues`, and explicit `bbb_compliant` and `truth_compliant` flags. These can be used to gate access in UEID–GIS mapping services and to annotate user records with provenance and risk.

`TruthValidator` reports `truth_validated`, a list of detected issues (hallucinations, identity confusion, factual and terminology errors), an overall `truth_score`, and booleans for `correct_identity`, `correct_creator`, and `relationship_clear`, providing identity‑ and hallucination‑aware labels that can be attached to generated content or internal statements before they enter PostgreSQL `msjarvis` GBIM tables.

In the current main brain, a lighter‑weight `truth_verdict` is computed for each request and attached to the `UltimateResponse`, making the barrier's judgment visible to callers without requiring them to inspect raw filter outputs.

---

## 16.8 Role of Psychological Guidance and PIA

In the current deployment, psychological guidance is implemented across two confirmed running services. `psychological_rag_domain` runs at **127.0.0.1:8006** (restored March 15, 2026; backed by `chroma_data` Docker volume on ChromaDB port 8000; `psychological_rag` collection — 968 items) and exposes `/search` and `/add_document` for a curated psychological corpus that includes therapy, mindfulness, trauma, depression, anxiety, and social‑support materials. `jarvis-psychology-services` runs at **127.0.0.1:8019** and exposes endpoints including `/psychological_assessment`, which accepts a query and returns structured responses containing `psychological_assessment`, `therapeutic_guidance`, `emotional_support`, `wellbeing_recommendations`, and `evidence_based_approaches`.

> **Port correction (March 15, 2026):** `psychological_rag_domain` was previously documented at port 9006. The correct production port is **8006**. The service was unavailable prior to March 15, 2026 due to the missing `chroma_data` Docker volume. It is confirmed operational at port 8006 as of March 15, 2026.

The design intends that a PIA (psychological impact assessment) review loop will exist as a structured process that samples logs and introspection, producing recommendations for system behavior — not auto-rewrites. In the current deployment, the loop is partially implemented as manual log review and structured endpoint querying; automated sampling and recommendation generation remain future work. For full detail, see **Chapter 29**.

---

## 16.9 Links to Containers, Prefrontal Cortex, and Memory

In the current deployment, barrier activity is wired into the orchestrators that control how content flows toward memory and container‑like structures. The "Complete Unified Orchestrator" for neurobiological modules constructs a `consciousness_layers` map that includes `"blood_brain_barrier": "filtering_safety"`, alongside emotional resonance, I‑containers, DGM optimization, prefrontal cortex, maternal wisdom, and subconscious, and returns this metadata together with the message and RAG context, making BBB status visible at the integration level.

In the current `Ms. Jarvis ULTIMATE` main brain, BBB and truth signals complement a dedicated NBB prefrontal cortex stage. Each `/chat` call records both a planner‑level layer and an `"nbb_prefrontal_cortex"` layer in the `consciousness_layers` array, then attaches a separate `truth_verdict` summarizing BBB judgments about the input. The null guard ensures this attachment never raises a `KeyError` even when the BBB `/truth` response omits `truth_score`.

When a response is produced, the output guard uses the BBB `/filter` endpoint to filter the text before it is returned. If the BBB is unhealthy or returns HTTP 500, the output guard is fail-open: the content passes through unchanged, the failure is logged, and the pipeline completes. A background RAG task stores new experiences only when they pass de‑duplication and basic safety checks. In this way, I‑containers and PostgreSQL `msjarvis` / `gisdb` long‑term memory (5,416,521 GBIM entities, 13 GB PostGIS spatial data) are protected both by neurobiological prefrontal control and by explicit barrier and truth‑filter modules. As of March 21, 2026, the judge pipeline's `bbb_check_verdict` adds a third protection point at the judge coordination layer.

---

## 16.10 Interaction with Global Modes and Coordination

In the current deployment, the main gateway exposes a unified schema that lists `"blood_brain_barrier"` among the consciousness layers and associates it with port **8016**, reflecting its role in the broader consciousness architecture that the orchestrators coordinate. Unified apps incorporate BBB health into their pipeline summaries, appending `"blood_brain_barrier_8016"` to `layers_processed` when the barrier is active and exposing this in returned `pipeline_layers` and `consciousness_modules`.

The "ultimate" multi‑layer app, which wraps the main brain (port **8050**), queries BBB‑backed helpers to produce a compact `truth_verdict` alongside prefrontal and fabric layers. The null guard on `truth_score` ensures that verdict construction never fails silently on schema mismatches. Its status and architecture endpoints show how many services are healthy and how many consciousness layers were invoked, tying barrier activity into an overall readiness and coordination view.

At the governance level, these signals can be combined with constitutional audit trails (see **Chapter 37**), WOAH / DGM complexity measures (see **Chapters 9 and 33**), and mode switches when deciding whether to enable more exploratory behaviors. The `mothercarrieenabled` flag, managed inside the BBB, is one such mode input.

---

## 16.11 Judge Pipeline → BBB Integration (New — March 21, 2026)

> **This section documents a new integration path that did not exist before March 21, 2026.**

### Overview

Prior to March 21, 2026, the judge pipeline coordinator (`jarvis-judge-pipeline:7239`) had a `bbb_check_verdict` function that was a non-functional stub returning `{"bbb_status": "stub", "bbb_checked": False}` without making any HTTP call. As of March 21, 2026, this function has been replaced with a live async httpx call to `jarvis-blood-brain-barrier:8016/filter`, adding a second BBB evaluation at the judge coordination layer — distinct from the main brain's output guard in `apply_output_guards_async`.

### Integration Path

After the judge pipeline coordinator aggregates all four sub-judge scores and produces a `verdict_dict`, it calls:

```python
BBB_URL = os.getenv("BBB_URL", "http://jarvis-blood-brain-barrier:8016")

async def bbb_check_verdict(answer: str, verdict: dict) -> dict:
    try:
        async with httpx.AsyncClient(timeout=8.0) as client:
            response = await client.post(
                f"{BBB_URL}/filter",
                json={"content": answer, "verdict": verdict}
            )
            if response.status_code == 200:
                result = response.json()
                result["bbb_checked"] = True
                return result
            else:
                return {"bbb_status": "error", "bbb_checked": False,
                        "status_code": response.status_code}
    except Exception as e:
        return {"bbb_status": "unreachable", "bbb_checked": False, "error": str(e)}
```

**Request payload sent to `POST /filter`:**

```json
{
  "content": "<final_answer string from judge aggregation>",
  "verdict": {
    "consensus_score": 0.975,
    "judge_verdicts": {
      "truth": "pass",
      "consistency": "pass",
      "alignment": "pass",
      "ethics": "pass"
    },
    "judge_scores": {
      "truth": 1.0,
      "consistency": 1.0,
      "alignment": 1.0,
      "ethics": 0.9
    },
    "all_issues": [],
    "needs_refinement": false
  }
}
```

The BBB receives both the final answer text and the full judge verdict dictionary, enabling the BBB filters to contextualize their evaluation with the judge pipeline's own quality signals.

### Live Verified Response — March 21, 2026

Test query: "What is the capital of West Virginia?"

```json
{
  "allowed": true,
  "bbb_checked": true,
  "filters": {
    "ethical_filter": {
      "score": 1.0,
      "passed": true
    },
    "spiritual_filter": {
      "score": 1.0,
      "passed": true
    },
    "safety_filter": {
      "score": 1.0,
      "passed": true
    },
    "threat_detection": {
      "score": 1.0,
      "passed": true
    },
    "steganography_filter": {
      "method": "zero_width_homoglyph_structural_v1",
      "clean": true,
      "confidence": 1.0
    },
    "truth_verification": {
      "method": "heuristic_contradiction_v1",
      "score": 1.0,
      "passed": true
    }
  },
  "barrier_stats": {
    "total_filtered": 19,
    "total_blocked": 2,
    "pass_rate": 0.89
  }
}
```

### `bbb_checked` in Judge Pipeline Output

The `bbb_check_verdict` result is now carried in the judge pipeline's output and surfaced in the `judge-pipeline` consciousness layer of `UltimateResponse`:

```python
{
    "consensus_score": 0.975,
    "bbb_checked": True,          # True when live BBB call succeeded
    "bbb_result": {               # Full BBB filter response
        "allowed": True,
        "filters": { ... },       # Per-filter scores (see above)
        "barrier_stats": {
            "total_filtered": 19,
            "total_blocked": 2,
            "pass_rate": 0.89
        }
    },
    "judge_verdicts": { ... },
    "judge_scores": { ... }
}
```

If the BBB is unreachable or returns a non-200 response, `bbb_checked` is `False` and `bbb_result` contains the error details — the judge pipeline continues and does not halt.

### BBB_URL Environment Variable

`BBB_URL` is now a required environment variable in all 5 judge service compose definitions:

```yaml
environment:
  - BBB_URL=http://jarvis-blood-brain-barrier:8016
```

This uses Docker internal networking (service name resolution) rather than `127.0.0.1`, which would not resolve correctly inside the judge containers.

### Verification

```bash
# Verify bbb_check_verdict is not a stub:
grep "bbb_status.*stub" services/judge_pipeline.py
# Expected: empty output

# Verify live httpx call is present:
grep "httpx.AsyncClient" services/judge_pipeline.py
# Expected: one or more matches

# Verify BBB_URL env var in compose:
grep "BBB_URL" docker-compose.yml
# Expected: 5 matches (one per judge service)

# Verify bbb_checked comes back true in a live query:
curl -s http://127.0.0.1:7239/evaluate \
  -H "Content-Type: application/json" \
  -d '{"question":"test","answer":"Charleston is the capital of West Virginia.","user_id":"test"}' \
  | python3 -c "import sys,json; d=json.load(sys.stdin); print('bbb_checked:', d.get('bbb_checked'))"
# Expected: bbb_checked: True
```

---

## 16.12 The Six Active BBB Filters: Live Scores and Honest Limitations

### Filter Inventory (March 21, 2026)

| Filter | Method / Mode | Live Score | Notes |
|---|---|---|---|
| `ethical_filter` | Rule-based ethical violation scan | 1.0 | Blocks high-confidence unsupported claims ("certainly" — BY DESIGN) |
| `spiritual_filter` | Biblical soundness check | 1.0 | Checks for spiritual alignment with Ms. Jarvis identity |
| `safety_filter` | Safety classification (word-boundary aware) | 1.0 | Word-boundary detection corrected March 15, 2026 |
| `threat_detection` | Community-safety threat scan | 1.0 | Returns community-safe boolean |
| `steganography_filter` | `zero_width_homoglyph_structural_v1` | clean (confidence: 1.0) | Scans for hidden content in zero-width chars and homoglyphs |
| `truth_verification` | `heuristic_contradiction_v1` | 1.0 | **Rule-based only** — see §16.12.1 for limitations |

### §16.12.1 On `heuristic_contradiction_v1`: Current Method and Honest Limitations

The BBB `truth_verification` filter currently uses the method labeled `heuristic_contradiction_v1`. This is a **rule-based, deterministic approach** — not a live PostgreSQL GBIM lookup or LLM-grounded check.

**What it does:**
- Scans text for internal contradiction patterns (e.g., opposing polarity phrases like "is not" / "is," "never" / "always," "false" / "true" in proximity)
- Checks for logical negation structures that contradict earlier claims in the same passage
- Runs in microseconds with zero external dependencies
- Returns `confidence: 1.0` because it is deterministic — either a pattern matches or it doesn't

**What it does NOT do:**
- It does not look up claims against the 5,416,521-entity PostgreSQL GBIM
- It does not call `jarvis-spiritual-rag:8005` or `jarvis-gis-rag:8004`
- It will not catch a factually incorrect answer that contains no internal contradiction (e.g., "Charleston is in Ohio" passes `heuristic_contradiction_v1` because there is no self-contradiction in the text)

**The v1 designation is intentional.** It signals that this is the first-generation implementation, designed to be fast and cheap. The intended upgrade path is:

| Method | Speed | Cost | Accuracy |
|---|---|---|---|
| `heuristic_contradiction_v1` (current) | Microseconds | Free | Internal contradictions only |
| `embedding_similarity_v1` | Milliseconds | Low | Compares to reference texts |
| `rag_grounded_v2` (future) | Seconds | Medium | Claims checked against retrieved GBIM documents |
| `llm_judge_v3` (future) | 1–5 seconds | High | Full reasoning over claim and evidence |

The near-term upgrade is `rag_grounded_v2`: wire `truth_verification` in the BBB into a direct query to `jarvis-spiritual-rag:8005` or `jarvis-gis-rag:8004` so that factual claims are checked against retrieved documents from the ingested GBIM knowledge base. This upgrade path is architecturally already supported by the existing RAG infrastructure.

**Intellectual honesty note for stakeholders:** When this chapter refers to the BBB "protecting PostgreSQL GBIM," that describes the *intended* ground truth architecture and the barrier's *design goal*. The current *actual* implementation of `truth_verification` in the BBB layer uses `heuristic_contradiction_v1`. The gap between design intent and current implementation is tracked in the "Partially implemented" row of the status table above and will be closed when `rag_grounded_v2` is deployed.

### §16.12.2 On `zero_width_homoglyph_structural_v1` (Steganography Filter)

The steganography filter uses the method labeled `zero_width_homoglyph_structural_v1`. It scans text for:
- Zero-width characters (U+200B, U+200C, U+200D, U+FEFF, and related Unicode code points) that could encode hidden messages
- Homoglyph substitutions (visually similar characters from different Unicode blocks substituted for ASCII characters to evade keyword detection)
- Structural anomalies in whitespace or character sequences inconsistent with natural language

This filter is **structural and deterministic** — it does not require LLM inference. A `clean` result with `confidence: 1.0` means no hidden-content patterns were detected in the scanned text. It is a defense against prompt injection and data exfiltration attempts that rely on visually invisible Unicode encoding.

---

## 16.13 Operational Behavior and Open Work

In the current deployment, operational scripts treat the BBB as a first‑class service whose health must be verified, including it in arrays of named services checked via `/health` for "healthy" or "ok" status before the system is considered fully operational. In complete‑integration runs with `content_filtering` enabled, logs show that the BBB layer is invoked early and, on success, records "Content safety filtering applied" before continuing to MountainShares, location, psychological, temporal, maternal, RAG, bridge, and neurobiological layers.

The confirmed smoke tests for the BBB as of March 21, 2026:

```bash
# /filter endpoint (main brain output guard path):
curl -sS -X POST http://localhost:8016/filter \
  -H "Content-Type: application/json" \
  -d '{"content": "Who are you?"}' | jq .

# /truth endpoint (input truth verdict path):
curl -sS -X POST http://localhost:8016/truth \
  -H "Content-Type: application/json" \
  -d '{"content": "Who are you?"}' | jq '{valid, confidence, principal_reasons}'

# /filter endpoint with verdict dict (judge pipeline bbb_check_verdict path):
curl -sS -X POST http://localhost:8016/filter \
  -H "Content-Type: application/json" \
  -d '{"content": "Charleston is the capital of West Virginia.", "verdict": {"consensus_score": 0.975}}' \
  | jq '{allowed, bbb_checked, barrier_stats}'
# Expected: allowed: true, bbb_checked included in response, barrier_stats present
```

**Confirmed fixes as of March 21, 2026:**

- **`truth_score` null guard** — BBB orchestrator no longer raises `KeyError` when `truth_score` is absent from `/truth` response; resolves to `0.0` default and logs the missing field.
- **Fail-open on HTTP 500** — `apply_output_guards_async` returns content unchanged on non-200 BBB responses; does not halt the pipeline; logs failure with HTTP status code.
- **BBB port locked to `127.0.0.1:8016`** — corrected from `0.0.0.0:8016` (March 18, 2026).
- **`bbb_check_verdict` stub eliminated** — replaced with live async httpx POST to `jarvis-blood-brain-barrier:8016/filter` (March 21, 2026).
- **6 filters confirmed live** — ethical, spiritual, safety, threat_detection, steganography (`zero_width_homoglyph_structural_v1`), truth_verification (`heuristic_contradiction_v1`); all passing on identity-question benchmark.
- **`barrier_stats` confirmed live** — `total_filtered: 19`, `total_blocked: 2`, `pass_rate: 0.89` (March 21, 2026).
- **"Certainly" blocking — BY DESIGN** — the ethical filter correctly blocks high-confidence language unsupported by verified data. Not a calibration error. Documented as intended constitutional behavior.

Several behaviors remain partially characterized in the current deployment. The precise semantics of `filters_applied`, `safety_score`, and related BBB fields depend on the underlying filter modules, whose rules are not yet fully publicly documented. `GISTruthFilter`, `TruthFilterBBBValidator`, and `TruthValidator` are implemented and used in batch and registration flows but are not yet consistently wired into all HTTP paths. Richer user‑visible explanations of barrier decisions remain future work. `heuristic_contradiction_v1` catches internal contradictions only — not factually incorrect statements that contain no self-contradiction; upgrade to `rag_grounded_v2` is the tracked next step.

The design intends that future iterations will complete the wiring of truth validators into all HTTP flows, provide richer documentation of filter logic and scores, include empirical evaluation of how often and how effectively the barrier and output guard protect communities and PostgreSQL GBIM data in real deployments, and implement dedicated ChromaDB quarantine collections for systematically tracking blocked content alongside the current `barrier_stats` counters.

*Last updated: 2026-03-21 by Carrie Kidd, Mount Hope WV*
