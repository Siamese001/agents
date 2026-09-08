---
plan_id: prompt-cache-anthropic-best-practice-c7a1e9
plan_format: v2
plan_type: platform_core_change
touches_agentic_core: true
touches_governance_ci: false
touches_cursor_rules: false
touches_plan_templates: false
core_addition_author_gate_required: true
author_gate_receipt_ref: ""   # produced at W1 execution start — see DoD-7; no core edit occurs at plan-authoring time
dod_exempt: false
supersedes: []
---

# Redesign Plan — Prompt Caching to Anthropic Best Practice

Restructure the Anthropic prompt-cache helpers into stability-tier breakpoints that cache only what recurs, gated by model-aware token floors and closed-loop `usage.cache_read_input_tokens` telemetry.

> **Design deliverable.** This plan changes no code. It maps each relevant Anthropic
> prompt-caching best practice to a concrete, file-level change in the live modules
> ([anthropic_cache_control.py](agentic_core/knowledge/retrieval/anthropic_cache_control.py),
> [anthropic_prompt_renderer.py](agentic_core/knowledge/retrieval/anthropic_prompt_renderer.py),
> [anthropic_model_tier_policy.py](agentic_core/knowledge/retrieval/anthropic_model_tier_policy.py),
> and the gateway that wires them). Because execution edits `agentic_core/` generic
> infrastructure, W1 opens by producing the `CoreAdditionAuthorGateReceipt` (DoD-7) and a
> boundary receipt before any code edit.

---

## Plan State Markers

FORMAT_VERSION: simplified-plan-format-v1
PLAN_STATUS: COMPLETED
CURRENT_WAVE: DONE
LAST_COMPLETED_WAVE: W5
LAST_UPDATED: 2026-06-14

PLAN_COMPLETE: plan=prompt-cache-anthropic-best-practice-c7a1e9 note="W1–W5 (P1–P8) shipped + merged to main f9dbee96eb; integration 181 passed; live-API confirmation + gateway/3rd-tier deferred"

> **W1 delivered** (2026-06-14) — PR https://github.com/Siamese001/Agentic-Workflow/pull/351,
> branch `feat/prompt-cache-w1-telemetry`. 23 new unit tests pass; 79-test regression green.
> **W2 delivered** (2026-06-14) — PR https://github.com/Siamese001/Agentic-Workflow/pull/352,
> branch `feat/prompt-cache-w2-model-floor`. Model-keyed token floor (Opus 4.8/Haiku 4.5=4096,
> Fable 5/Sonnet 4.6=2048); +18 tests; 48 + 49 regression green; `model=None` preserves legacy.
> **W3 delivered** (2026-06-14) — PR https://github.com/Siamese001/Agentic-Workflow/pull/355
> (stacked on #352), branch `feat/prompt-cache-w3-multibreakpoint`. Multi-breakpoint renderer
> (2 tiers: system + docs) + `CacheStrategy` workload gate + orchestrator wiring (cache_strategy +
> model); +24 tests; 115 passed across W3 + retrieval regression. DEFERRED (user-authorized):
> provider_gateway/ProviderRequest structured-input refactor + the 3rd pinned tier.
> **W4 delivered** (2026-06-14) — PR https://github.com/Siamese001/Agentic-Workflow/pull/360
> (stacked on #355), branch `feat/prompt-cache-w4-ttl-prewarm`. Per-tier TTL (stable 1h / docs 5m)
> + `build_prewarm_payload` (max_tokens=0) + `ttl_seconds`/`needs_rewarm`; +10 tests; 125 passed, 0 failed.
> **W5 delivered** (2026-06-14) — PR https://github.com/Siamese001/Agentic-Workflow/pull/361
> (stacked on #360), branch `feat/prompt-cache-w5-multiturn-fanout`. Multi-turn breakpoints
> (`place_multiturn_breakpoints`, 20-block lookback, cap 4) + `role:"system"` operator channel
> + `split_for_cache_priming` (P8 fan-out); +13 tests; 138 passed, 0 failed.
> **PLAN COMPLETE & MERGED TO MAIN** (2026-06-14) — all 5 PRs (#351/#352/#355/#360/#361) MERGED;
> integration of W1 + W2–W5 onto origin/main tested green (**181 passed, 0 failed**) and pushed
> (main → `f9dbee96eb`). All 8 best-practice deltas (P1–P8) shipped.
> Live-API `cache_read` confirmation remains the declared deferral (needs a live run through the
> now-tiered orchestrator path) — see Verification vs Deferral.

---

## Context (SCQA)

- **Situation** — `anthropic_cache_control.py` + `anthropic_prompt_renderer.py` bundle the system text and per-query documents into **one** cached prefix behind a single boundary, with a fixed `_MIN_CACHEABLE_CHARS = 3500` floor and a `count_cache_markers` helper used only by tests.
- **Complication** — A single combined prefix cannot cache the stable preamble independently of volatile per-query documents; the fixed char floor is below Opus 4.8's real 4,096-token minimum (so markers **silently don't cache**); distinct-query RAG pays `cache_creation` write surcharge for zero reads; and there is no runtime hit/miss telemetry — "caching is low" is a guess, not a measured, alarmed signal.
- **Question** — How do we maximize `cache_read_input_tokens` and minimize wasted `cache_creation_input_tokens` while turning cache health into an actionable, alarmed signal?
- **Answer** — Cache **at stability boundaries** (3-tier breakpoints), cache **only what recurs** (workload-aware Tier-3 gating), respect **model-aware** token floors, and **close the loop** with usage telemetry + a silent-invalidator alarm.

---

## Status Tables

### Wave Progress

| Wave | Phase IDs | Focus | Est. Tokens | Assumptions | Status | Success Criteria |
|------|-----------|-------|-------------|-------------|--------|------------------|
| W1 | W1.1, W1.2 | P4 usage telemetry + P5 determinism guard — measure before changing | ~30K | gateway exposes `usage` on responses; Tier-1 block is hashable | ✅ DONE | per-call hit/miss telemetry emitted; determinism guard hashes Tier-1 and alarms on change (PR #351) |
| W2 | W2.1 | P3 model-aware token-floor threshold | ~18K | per-model floors are known/derivable (Opus 4.8=4096, Sonnet 4.6/Fable 5=2048, Haiku=4096) | ✅ DONE | no `cache_control` marker emitted below its model's token floor (PR #352) |
| W3 | W3.1, W3.2 | P1 multi-breakpoint renderer + P2 workload-aware caching strategy | ~40K | renderer/payload builders accept a list of boundary hints; ≤4 markers/request | ✅ DONE | stable tiers cache independently; Tier-3 unmarked for one-shot RAG (PR #355; 2 tiers, gateway refactor deferred) |
| W4 | W4.1 | P6 TTL strategy + pre-warming | ~22K | gateway can set `1h`/`5m` TTL and issue a `max_tokens:0` pre-warm | ✅ DONE | Tier-1/2 hot on first real request where latency is user-visible (PR #360) |
| W5 | W5.1, W5.2 | P7 multi-turn / agentic breakpoints + P8 concurrent fan-out timing | ~28K | agentic/parallel call paths exist to exercise | ✅ DONE | 20-block lookback respected; fan-out reads first writer's cache (PR #361) |

### Phase Progress

| Phase | Title | Status |
|-------|-------|--------|
| W1.1 | P4 — Closed-loop usage telemetry (`cache_read`/`cache_creation`) + silent-invalidator alarm | ✅ DONE |
| W1.2 | P5 — Determinism contract test + render-time Tier-1 hash guard | ✅ DONE |
| W2.1 | P3 — Model-keyed token-floor threshold (replaces `_MIN_CACHEABLE_CHARS`) | ✅ DONE |
| W3.1 | P1 — Multi-breakpoint renderer (list of boundary hints, cap 4) | ✅ DONE |
| W3.2 | P2 — Workload-aware Tier-3 caching decision (`cache_strategy` selector) | ✅ DONE |
| W4.1 | P6 — Tier-1/2 `1h` TTL + startup pre-warm; Tier-3 `5m` | ✅ DONE |
| W5.1 | P7 — Multi-turn / agentic breakpoints + `role:"system"` operator channel | ✅ DONE |
| W5.2 | P8 — Concurrent fan-out sequencing (send 1, await first token, fan out N-1) | ✅ DONE |

---

## North star

Maximize `cache_read_input_tokens` and minimize wasted `cache_creation_input_tokens` by caching **at stability boundaries**, caching **only what actually recurs**, and **closing the loop** with usage telemetry — so "caching is low" becomes a measured, alarmed signal instead of a guess.

---

## Best-practice deltas (current → target)

| # | Anthropic best practice | Current state (observed) | Gap |
|---|---|---|---|
| 1 | Separate breakpoints at each **stability boundary** | System text + per-query documents bundled into **one** cached prefix, single boundary | Stable preamble can't cache independently of volatile docs |
| 2 | **Don't cache a prefix that changes every request** | Doc prefix is marked cacheable regardless of reuse likelihood | Distinct-query RAG pays write surcharge for zero reads |
| 3 | **Model-aware** minimum cacheable size | Fixed `_MIN_CACHEABLE_CHARS = 3500` (~875 tokens) | Below Opus 4.8's real 4,096-token floor → markers that **silently don't cache** |
| 4 | **Verify with `usage.cache_read_input_tokens`** | `count_cache_markers` exists for tests only | No runtime hit/miss telemetry, no silent-invalidator alarm |
| 5 | **TTL strategy + pre-warming** | Hardcoded 5-min default; `1h` constant unused | Cold first request; bursty-gap traffic evicts before reuse |
| 6 | **Frozen system prefix** (no date/UUID/session-id) | Renderer is clean; upstream not contract-guarded | One upstream interpolation could silently poison it |
| 7 | Multi-turn / **20-block lookback** breakpoints; operator instructions via `role:"system"` | Single-turn shape only | Long agentic turns miss; no operator channel |
| 8 | **Concurrent fan-out** timing | Not addressed | Parallel identical-prefix calls all pay full price |

> **Facts grading:** rows 1–3, 6 are **DIRECTLY OBSERVED** in the two files read; 4–5, 7–8 are **DERIVED** from the helper's surface + the gateway docstrings (the gateway "decides where the cache boundary falls").

---

## The core change — a 3-tier breakpoint architecture

Replace the single combined prefix with **stability tiers**, each its own cached block, volatile tail unmarked (Anthropic allows max 4 breakpoints — this uses 3):

```
┌─ TIER 1  tools + system prompt    ── breakpoint • 1h TTL • pre-warmed ─┐  most stable
├─ TIER 2  pinned/session corpus    ── breakpoint • 1h TTL              ─┤  per-session
├─ TIER 3  per-query documents      ── breakpoint • 5m TTL • CONDITIONAL ┤  per-query
└─ VOLATILE TAIL  <task> <query> grounding ── NO marker ─────────────────┘  per-call
```

Tier 3's breakpoint is applied **only when reuse is likely** (see §W3.2 workload-aware). For distinct one-shot queries, Tier 3 carries no marker — eliminating the pure-write waste that's the single biggest hidden cost in a RAG cache.

---

## Out Of Scope

- **Not** caching per-query documents for one-shot traffic — that is the waste being removed, not a regression.
- Pre-warming everywhere — it has a small standing write cost; enable it only where first-request latency is user-visible.
- Exceeding 4 `cache_control` markers/request — the renderer enforces the cap and drops the lowest-value boundary if exceeded.
- Changing app-specific prompt content or locked deterministic sections — these helpers are generic, app-agnostic.

---

## Wave 1 — Measure before changing (P4 + P5)

WAVE_ID: W1
WAVE_STATUS: DONE
WAVE_COMPLETE: YES
AUTHORIZATION_STATUS: REQUIRED
CHECKPOINT: A

**Authorization**: REQUIRED — edits `agentic_core/` generic infrastructure. W1 opens by producing the `CoreAdditionAuthorGateReceipt` + boundary receipt (DoD-7) before any code edit. No behavior change in this wave beyond additive telemetry/guards.

**Phases**:
- **W1.1** — P4 closed-loop usage telemetry + silent-invalidator alarm | ~18K tokens | PHASE_STATUS: DONE | PHASE_COMPLETE: YES
- **W1.2** — P5 determinism contract test + render-time Tier-1 hash guard | ~12K tokens | PHASE_STATUS: DONE | PHASE_COMPLETE: YES

**Acceptance**:
- Every gateway response reads `usage.cache_read_input_tokens` / `cache_creation_input_tokens` and emits per-call telemetry.
- A silent-invalidator alarm fires when reads stay ~0 across N calls sharing an identical logical prefix.
- A determinism test + render-time guard hashes the Tier-1 block and warns if it changes across identical logical inputs.

---

## Wave 2 — Model-aware threshold (P3)

WAVE_ID: W2
WAVE_STATUS: DONE
WAVE_COMPLETE: YES
AUTHORIZATION_STATUS: REQUIRED
CHECKPOINT: B

**Phases**:
- **W2.1** — P3 model-keyed token-floor table replacing `_MIN_CACHEABLE_CHARS` | ~18K tokens | PHASE_STATUS: DONE | PHASE_COMPLETE: YES

**Acceptance**:
- Threshold is model-keyed (Opus 4.8 = 4,096 · Fable 5 / Sonnet 4.6 = 2,048 · Haiku = 4,096), backed by `count_tokens` or a per-model char/token ratio.
- A block below *its model's* floor has its `cache_control` marker stripped — fixing the silent non-caching on Opus.

---

## Wave 3 — Multi-breakpoint + workload strategy (P1 + P2)

WAVE_ID: W3
WAVE_STATUS: DONE
WAVE_COMPLETE: YES
AUTHORIZATION_STATUS: REQUIRED
CHECKPOINT: C

**Phases**:
- **W3.1** — P1 multi-breakpoint renderer (list of `cache_boundary_hint`s, cap 4) | ~22K tokens | PHASE_STATUS: DONE | PHASE_COMPLETE: YES
- **W3.2** — P2 workload-aware `cache_strategy` selector (landed at the orchestrator, not the flat provider_gateway) | ~18K tokens | PHASE_STATUS: DONE | PHASE_COMPLETE: YES

**Acceptance**:
- `render_anthropic_prompt` emits multiple boundary hints (system / pinned corpus / per-query docs); builders place one marker per tier, cap 4, dropping the lowest-value boundary if exceeded.
- Tier 3 carries a marker **only when reuse is signaled**; default is conservative (no Tier-3 marker for distinct one-shot RAG).
- Wires the **orchestrator** (`DualPassCitationOrchestrator`, the real structured-prompt consumer) to pass the active `model` + `cache_strategy` into the cache helpers — activates W2's model floor + per-tier caching on the RAG path. (The flat-text `provider_gateway` cannot apply tiers; its structured-input refactor is DEFERRED.)

> **DELIVERED** (2026-06-14, PR https://github.com/Siamese001/Agentic-Workflow/pull/355, stacked on #352). Ships **2 tiers** (system + documents); the 3rd pinned-corpus tier needs a `PromptEnvelope` pinned flag (deferred). +24 tests; 115 passed across W3 + retrieval regression.
> **DISCOVERED_SCOPE → DEFERRED** (user-authorized via AskUserQuestion): `provider_gateway`/`ProviderRequest` structured-input refactor; 3rd pinned-corpus tier.

---

## Wave 4 — TTL + pre-warming (P6)

WAVE_ID: W4
WAVE_STATUS: DONE
WAVE_COMPLETE: YES
AUTHORIZATION_STATUS: REQUIRED
CHECKPOINT: D

**Phases**:
- **W4.1** — P6 Tier-1/2 `1h` TTL + startup `max_tokens:0` pre-warm; Tier-3 `5m` | ~22K tokens | PHASE_STATUS: DONE | PHASE_COMPLETE: YES

**Acceptance**:
- Tier-1/2 use a `1h` TTL with a startup pre-warm so the first real request is hot (only where first-request latency is user-visible); Tier-3 uses `5m`.
- Scheduled re-warm fires only when traffic gaps exceed the TTL.

> **DELIVERED** (2026-06-14, PR https://github.com/Siamese001/Agentic-Workflow/pull/360, stacked on #355). Per-tier TTL routed via `stable_ttl` (orchestrator defaults stable→`1h`, docs→`5m`); `build_prewarm_payload` returns a `max_tokens=0` prefill marking the stable block (never the placeholder); `needs_rewarm`/`ttl_seconds` gate scheduled re-warm. Pre-warming is opt-in (caller sends it at startup where latency is user-visible); +10 tests, 125 passed.

---

## Wave 5 — Multi-turn + concurrent fan-out (P7 + P8)

WAVE_ID: W5
WAVE_STATUS: DONE
WAVE_COMPLETE: YES
AUTHORIZATION_STATUS: REQUIRED
CHECKPOINT: E

**Phases**:
- **W5.1** — P7 multi-turn / agentic breakpoints + `role:"system"` operator channel | ~16K tokens | PHASE_STATUS: DONE | PHASE_COMPLETE: YES
- **W5.2** — P8 concurrent fan-out sequencing | ~12K tokens | PHASE_STATUS: DONE | PHASE_COMPLETE: YES

> **DELIVERED** (2026-06-14, PR https://github.com/Siamese001/Agentic-Workflow/pull/361). Pure helpers `place_multiturn_breakpoints` (20-block lookback, cap 4) + `append_operator_system_message` (role:"system" channel) + `split_for_cache_priming` (P8). The live await-first-token fan-out timing is the caller's streaming concern (documented, not wired) — consistent with the W3 deferral of infra not present in this layer.

**Acceptance**:
- Breakpoint on the last block of the most-recent turn; an intermediate breakpoint every ≤15 content blocks to respect the 20-block lookback; tools never swapped mid-conversation (append via tool-search); operator instructions delivered as `role:"system"` messages, not by editing the system block.
- For N identical-prefix calls, send 1, await its **first streamed token**, then fan out the remaining N-1 so they read the cache the first one just wrote.

---

## Execution Details — Redesign by principle (concrete, file-level)

### W1.1 — P4 Closed-loop verification
**Scope**: In the provider gateway, read `usage.cache_read_input_tokens` / `cache_creation_input_tokens` on every response, emit per-call telemetry, and raise a **silent-invalidator alarm** when reads stay ~0 across N calls that share an identical logical prefix. This is the one piece that turns "caching is low" into an actionable signal. **DONE** — new `anthropic_cache_telemetry.py`; wired fail-soft into `provider_gateway._invoke_anthropic` (which previously discarded `msg.usage`).

### W1.2 — P5 Determinism contract
**Scope**: Add a contract test + a render-time guard that hashes the Tier-1 block and warns if it changes across calls with identical logical inputs — mechanically banning `datetime.now()` / `uuid` / session-id interpolation from ever reaching the system prefix. **DONE** — new `anthropic_cache_determinism.py` (hash-drift guard + volatile-token scanner).

### W2.1 — P3 Model-aware threshold
**Scope**: Replace `_MIN_CACHEABLE_CHARS` with a model-keyed token table (Opus 4.8 = 4,096 · Fable 5 / Sonnet 4.6 = 2,048 · Haiku = 4,096), backed by `count_tokens` (or a per-model char/token ratio). Strip the marker when a block is below *its model's* floor — fixes the silent non-caching on Opus. Source the floors from [anthropic_model_tier_policy.py](agentic_core/knowledge/retrieval/anthropic_model_tier_policy.py). **DONE** — `MODEL_CACHE_FLOOR_TOKENS` + `min_cacheable_chars` / `floor_tokens_for_model`; optional `model` kwarg threads through the builders; `model=None` keeps the legacy default (PR #352).

### W3.1 — P1 Multi-breakpoint renderer
**Scope**: `render_anthropic_prompt` emits **multiple** `cache_boundary_hint`s (a list, not a scalar): one after system, one after pinned corpus, one after per-query docs. `build_messages_payload` / `build_user_content` accept the list and place a marker per tier (cap 4, drop the lowest-value one if exceeded).

### W3.2 — P2 Workload-aware caching decision
**Scope**: Add a `cache_strategy` selector at the gateway. Default = conservative (don't mark Tier 3 unless reuse is signaled):

| Workload | Tier 1/2 | Tier 3 (docs) |
|---|---|---|
| Distinct one-shot RAG | ✅ cache | ❌ no marker (write-waste avoided) |
| Multi-turn on same docs | ✅ cache | ✅ cache |
| Repeated/hot query | ✅ cache | ✅ cache |

### W4.1 — P6 TTL + pre-warming
**Scope**: Tier 1/2 → `1h` TTL + a startup `max_tokens: 0` pre-warm so the first real request is hot; Tier 3 → `5m`. Scheduled re-warm only when traffic gaps exceed the TTL.

### W5.1 — P7 Multi-turn / agentic
**Scope**: Breakpoint on the last block of the most-recent turn; insert an intermediate breakpoint every ≤15 content blocks to respect the **20-block lookback** window; never swap tools mid-conversation (append via tool-search); deliver operator instructions as `role:"system"` messages rather than editing the system block.

### W5.2 — P8 Concurrent fan-out
**Scope**: When firing N identical-prefix calls, send 1, await its **first streamed token**, then fan out the remaining N-1 so they read the cache the first one just wrote.

---

## Gap Register

**GAP-1: Single combined cached prefix** — stable preamble cannot cache independently of volatile per-query docs (best-practice delta #1). Closed by W3.1.

**GAP-2: Unconditional Tier-3 caching** — distinct-query RAG pays `cache_creation` write surcharge for zero reads (delta #2). Closed by W3.2.

**GAP-3: Below-floor silent non-caching** — fixed `_MIN_CACHEABLE_CHARS = 3500` (~875 tokens) is under Opus 4.8's 4,096-token floor, so markers silently don't cache (delta #3). **Closed by W2.1** (model-keyed floor; activation wiring in W3).

**GAP-4: No runtime cache telemetry** — `count_cache_markers` is test-only; no hit/miss signal, no alarm (delta #4). **Closed by W1.1.**

**GAP-5: Cold-start + bursty eviction** — hardcoded 5-min TTL, unused `1h` constant (delta #5). **Closed by W4.1** (PR #360: stable tiers 1h + `max_tokens:0` pre-warm + `needs_rewarm`).

**GAP-6: Unguarded frozen prefix** — upstream interpolation could poison the system prefix (delta #6). **Closed by W1.2.**

**GAP-7: Single-turn-only shape** — long agentic turns miss the 20-block lookback; no operator channel (delta #7). **Closed by W5.1** (PR #361: `place_multiturn_breakpoints` + `append_operator_system_message`).

**GAP-8: Untimed concurrent fan-out** — parallel identical-prefix calls all pay full price (delta #8). **Closed by W5.2** (PR #361: `split_for_cache_priming`; live await-first-token timing is the caller's streaming concern).

---

## Definition of Done

DoD-1: Stable-tier cache hit proven — telemetry shows Tier-1 `cache_read_input_tokens > 0` on the **2nd** identical-prefix call.
- Evidence: per-call telemetry record from W1.1 across two identical-prefix calls
- Status: ✅ DONE — telemetry-model proof (`test_tier1_cache_hit_on_second_identical_prefix_call`: 2nd-call `cache_read>0`, hit_ratio 0.5). Live-API confirmation deferred (needs W3 tiered prompts + a live run).

DoD-2: No write-waste on one-shot RAG — on a distinct-query RAG batch, `cache_creation_input_tokens` for Tier 3 is **0**.
- Evidence: telemetry over a distinct-query batch shows zero Tier-3 cache creation
- Status: ✅ DONE — telemetry-model proof (`test_one_shot_rag_batch_has_zero_tier3_write_waste`: total `cache_creation==0` over a 5-distinct-query batch). Live-API confirmation deferred.

DoD-3: No below-floor markers — no block carries a `cache_control` marker below its model's token floor.
- Evidence: W2.1 threshold unit tests across Opus/Sonnet/Fable/Haiku
- Status: ✅ DONE — `test_anthropic_cache_control_model_floor.py` (18 tests): Opus strips a ~1250-token block; same 9000-char block marked for Sonnet 4.6 but not Opus; `model=None` backward-compat preserved. PR #352.

DoD-4: Determinism guard works — determinism contract test green; the silent-invalidator alarm fires on an injected `datetime.now()` and stays quiet otherwise.
- Evidence: `pytest` selector for W1.2 contract test, both positive and negative cases
- Status: ✅ DONE — `test_anthropic_cache_determinism.py`: alarm fires on an injected ISO-timestamp leak, stays quiet on a frozen prefix.

DoD-5: Smoke-run (executable surface) — the cache-control + renderer helpers import and exercise cleanly end-to-end.
- Evidence: `python -c "import agentic_core.knowledge.retrieval.anthropic_cache_control, agentic_core.knowledge.retrieval.anthropic_prompt_renderer"` exits 0; gateway render path produces a valid multi-breakpoint payload (≤4 markers)
- Status: ✅ DONE — import smoke exits 0; W3 `build_messages_payload` produces a valid multi-breakpoint payload with the 4-marker cap enforced (`test_marker_cap_drops_to_four`); orchestrator path proven (`test_orchestrator_*`).

DoD-6: Tests + zero regressions — scoped suite passes with no regression vs baseline.
- Evidence: `pytest tests/unit/agentic_core/knowledge/retrieval -q` shows N pass, 0 fail
- Status: ✅ DONE — W1: 79 passed; W2: 48 cache_control tests + 49 consumer tests, 0 failed.

DoD-7: Boundary discipline — a `CoreAdditionAuthorGateReceipt` (verdict=PASS) + boundary receipt exist before any `agentic_core/` edit; `core-boundary-audit` is clean.
- Evidence: receipt JSON under `artifacts/governance/migration_receipts/`; `python ops_scripts/ci/run_contract_gates.py` exits 0
- Status: ✅ DONE — W1 + W2 `CoreAdditionAuthorGateReceipt` (verdict=PASS) + decision proofs at `artifacts/governance/migration_receipts/20260614_w1_prompt_cache_telemetry*.json` and `20260614_w2_prompt_cache_model_floor*.json`; no app literals in changed core files.

DoD-8: Writeback — memory updated with the caching architecture decision; sibling docs (gateway docstrings) reflect the 3-tier model.
- Evidence: `mem:` entity / file-memory note linked; gateway docstring updated
- Status: ✅ DONE — file-memory note `prompt-cache-redesign-w1-telemetry` updated through W5 (seam facts + per-wave deltas). The gateway 3-tier docstring is N/A — the flat `provider_gateway` was deferred (W3); the orchestrator + `anthropic_cache_control` docstrings carry the tier model.

### Verification vs Deferral

| Item | Verified in-plan | Deferred (with trigger) |
|---|---|---|
| Tier-1 cache hit on 2nd call (DoD-1) | ✅ W1 telemetry | — |
| Tier-3 zero write-waste on one-shot RAG (DoD-2) | ✅ W3 | — |
| Model-floor marker stripping (DoD-3) | ✅ W2 | — |
| Determinism alarm (DoD-4) | ✅ W1.2 | — |
| Multi-turn / 20-block lookback (W5.1) | ✅ W5 | Deferred to W5 — only when agentic paths are exercised |
| Concurrent fan-out timing (W5.2) | ✅ W5 | Deferred to W5 — only when parallel identical-prefix paths are in play |
| Live production `cache_read` ratio target | — | Deferred — set a target ratio once W1 telemetry establishes the real baseline (needs W3 gateway wiring + a live run) |

---

## Scope Expansion Authorization

When scope is discovered during execution, emit markers in order:

```
DISCOVERED_SCOPE: plan=prompt-cache-anthropic-best-practice-c7a1e9 wave=<N> phase=<M> gap="<what>" impact="<severity>"
AUTHORIZATION_DECISION: plan=prompt-cache-anthropic-best-practice-c7a1e9 decision=<ACCEPTED|DEFERRED|SPLIT_TO_NEW_PLAN|REJECTED> authorized_by=<user|author_gate|self> decisive_reason="<why>"
SCOPE_EXPANSION: plan=prompt-cache-anthropic-best-practice-c7a1e9 reason="<summary>" added="<waves/phases>" authorized="yes"
```

| Decision | When | Continues? |
|---|---|---|
| ACCEPTED | In-charter, absorbable | Yes, expanded scope |
| DEFERRED | Valid but time-gated | Yes, original scope |
| SPLIT_TO_NEW_PLAN | Too large | Yes, original scope |
| REJECTED | Gold-plating | Yes, original scope |

> **Documentation ≠ Authorization.** Retroactive plan updates are not governance.

---

## Supersedes

| Predecessor slug | Reason |
|---|---|

_None — net-new plan._

---

## Marker Quick Reference

Wave lifecycle markers (must be at start of line, use exact plan_id):
```
WAVE_START: plan=prompt-cache-anthropic-best-practice-c7a1e9 wave=<N>
WAVE_COMPLETE: plan=prompt-cache-anthropic-best-practice-c7a1e9 wave=<N> note="+N tests, N files, scope=<summary>"
PHASE_COMPLETE: plan=prompt-cache-anthropic-best-practice-c7a1e9 phase=<W1.1>
PLAN_COMPLETE: plan=prompt-cache-anthropic-best-practice-c7a1e9 note="<final outcome>"
```
