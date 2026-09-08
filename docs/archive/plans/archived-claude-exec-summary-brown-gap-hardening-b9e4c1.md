---
status: Archived
do_not_execute: true
memorialized: true
source_surface: claude_legacy_plans
source_key: claude
original_path: 'C:\\Git\\Agentic-Workflow-FRESH\\.codex\\plans\\exec-summary-brown-gap-hardening-b9e4c1.md'
original_relative_path: 'exec-summary-brown-gap-hardening-b9e4c1.md'
source_sha256: e18b933fd70bd290dfe50b02eed3db06f36b2668abe988b500119c0027cef75d
recovered_status: LEGACY_EXISTING
last_commit: ''
last_commit_date: ''
created_date: ''
archived_reason: historical consolidation for review, lessons learned, and anti-pattern analysis
---

> ARCHIVED MEMORIAL RECORD: This file is preserved for review and lessons learned. Do not execute it as an active plan.

---
---
plan_id: exec-summary-brown-gap-hardening-b9e4c1
plan_type: enhancement
touches_agentic_core: false
touches_governance_ci: true
touches_cursor_rules: false
touches_plan_templates: false
core_addition_author_gate_required: false
author_gate_receipt_ref: ""
dod_exempt: false
parent_plan: exec-summary-anthropic-surgical-regen-f3c8d2
evidence_run: exec_summary_20260527_073959
---

# Executive Summary — Brown SVP Gap Hardening (Prompt + Regen + Judge)

Close gaps surfaced by Brown & Brown SVP REAL_LLM run [`exec_summary_20260527_065747`](../../artifacts/apps_rg/runtime_proofs/executive_summary/real/exec_summary_20260527_065747): Qwen scratch quality, 9-slot prompt contradictions, regen delta/proof mismatch, judge score drift, and operator visibility for regen quality controls.

FORMAT_VERSION: simplified-plan-format-v1
PLAN_STATUS: Completed
CURRENT_WAVE: —
LAST_COMPLETED_WAVE: W4
LAST_UPDATED: 2026-05-27
NOTION_PAGE_ID: 36d27693-f55c-81ab-879e-def5569f1007

PLAN_CREATED: slug=exec-summary-brown-gap-hardening-b9e4c1 path=.cursor/plans/exec-summary-brown-gap-hardening-b9e4c1.md status=Completed notion=36d27693-f55c-81ab-879e-def5569f1007
PLAN_COMPLETE: plan=exec-summary-brown-gap-hardening-b9e4c1 note="W1–W4 engineering DONE; 20 unit tests; W4 REAL_LLM exec_summary_20260527_073959; certification deferred (X2 block before judges)"

---

## Context (SCQA)

- **Situation** — Executive-summary lane produces DRAFT_READY scratch via Qwen (`executive_summary.generate_scratch_v1`, 9 prompt slots S0–R0). X1D panel (Gemini, OpenAI, Anthropic) grades post-X2. Judge regen uses frozen compile + `REGEN_DELTA_v1` via `SameAuthorityRegenRunner`. Brown SVP run completed with X2 PASS, exit 0, ~3.4 min.
- **Complication** — Anthropic soft-fail (3.8) blocked certification. Two regen cycles ran but **both failed X2** (`x2_unsupported_industry_claim_zero`, `x2_claim_field_maps_to_display_sentence`) and were reverted; judges re-scored **identical scratch** (Anthropic flat 3.8; Gemini 4.5→4.0; OpenAI 4.6→4.4). Regen delta asked for insurance-sector S1 sharpening without allowlist proof IDs. E0 positive example S6 violates `s6_no_looking_ahead_opener` and thin-recap bans. `regen_caps_enabled: false` allowed full S1–S6 rewrite while `delta_class=S6_forward_synthesis`. Reflexion/ToT controls reported BLOCK/IGNORED in regen receipt but not in operator status.
- **Question** — How do we harden scratch generation, prompt slots, regen targeting, and judge observability so the next Brown SVP run can lift Anthropic above floor without X2 regressions or score roulette?
- **Answer** — Fix prompt contradictions and regen proof-boundary filtering first (P0), then I0/Y0/E0 slot guidance and judge variance guard (P1), then process surfacing and stuck-loop escalation (P2), then Brown proof re-run with acceptance criteria on all three judges.

---

## Status Tables

### Wave Progress

| Wave | Phase IDs | Focus | Est. Tokens | Assumptions | Status | Success Criteria |
|------|-----------|-------|-------------|-------------|--------|------------------|
| W0 | W0.1 | Plan disk + Notion registration | ~8K | NOTION_TOKEN set | ✅ DONE | Plan file + Plans DB row |
| W1 | W1.1–W1.3 | P0: E0 S6 fix + regen proof-gap filter | ~25K | apps_rg prompts only | ✅ DONE | 30 unit tests pass (W1 + regen_delta_policy) |
| W2 | W2.1–W2.4 | P1: I0/Y0/C0 slot + judge variance guard | ~35K | W1 merged | ✅ DONE | Prompt compile tests + variance receipt |
| W3 | W3.1–W3.3 | P2: operator surfacing + stuck-loop escalation | ~20K | W2 or parallel | ✅ DONE | CLI receipt shows reflexion BLOCK; cycle-3 widen path |
| W4 | W4.1 | Brown SVP REAL_LLM proof re-run | ~25K | Qwen + judges up | ✅ DONE | Artifact + W4 report; certification criteria documented deferred |

### Phase Progress

| Phase | Title | Scope (files) | Pain Points | Est. Tokens | Status |
|-------|-------|---------------|-------------|-------------|--------|
| W0.1 | Register plan (Notion + `PLAN_CREATED`) | `.cursor/plans/`, Notion Plans | — | ~8K | ✅ DONE |
| W1.1 | Fix E0 positive example S6 (Looking ahead / extend arc) | `executive_summary_examples.yaml`, template hydrate | Contradictory style signal | ~8K | ✅ DONE |
| W1.2 | Regen remediation filter: strip/reframe proof-impossible findings | `executive_summary_regen*.py`, delta pack builder | Insurance S1 → X2 fail | ~12K | ✅ DONE |
| W1.3 | Align `delta_class` with EDIT_BUDGET (S6-only vs full-arc) | regen policy + receipts | Scope inflation | ~8K | ✅ DONE |
| W2.1 | I0: approved non-stock S2–S5 openers + enforce ≤2 stock bridges | `executive_summary.generate_scratch_v1.yaml` I0 | Formulaic triple stack | ~10K | ✅ DONE |
| W2.2 | I0/Y0: positive S5 integration pattern (quant + HPC metric) | I0, Y0 slots | Biographical S5 | ~8K | ✅ DONE |
| W2.3 | C0: `preferred_display_framing` for fact_quant_hpc_003 | fact capsule / C0 hydrate | Verbatim derivatives bleed | ~8K | ✅ DONE |
| W2.4 | Judge score variance guard on identical `judge_packet_hash` | `executive_summary_x1d.py` + receipt | Gemini −0.5 same input | ~12K | ✅ DONE |
| W3.1 | Surface regen `quality_certification_denied` / reflexion BLOCK in operator status | lane CLI + receipt | Hidden BLOCK | ~8K | ✅ DONE |
| W3.2 | Stuck-loop escalation (widen delta or proof-gap note on cycle 3+) | `judge_remediation_cycles.json` producer | Identical X2 signature ×2 | ~8K | ✅ DONE |
| W3.3 | Tighten `s5_no_derivatives_or_employer_inventory` self_check | scratch parser / self_check validator | False-positive pass | ~6K | ✅ DONE |
| W4.1 | Brown SVP re-run + gap-close verifier | CLI + artifacts | Certification | ~25K | ✅ DONE (engineering); certification deferred |

---

## Evidence Summary (exec_summary_20260527_065747)

| Signal | Value |
|--------|-------|
| Published text | [resume_display_text.txt](../../artifacts/apps_rg/runtime_proofs/executive_summary/real/exec_summary_20260527_065747/resume_display_text.txt) |
| X2 | All PASS on scratch |
| Judges R1 → R2 (same text) | Gemini 4.5→4.0; OpenAI 4.6→4.4; Anthropic 3.8→3.8 |
| Regen cycles | 2; stopped `x2_stuck_same_failure` |
| Regen cycle 1 failure | `x2_unsupported_industry_claim_zero` (S1 "federated insurance operations") |
| Regen caps | `regen_caps_enabled: false` → full S1–S6 edit allowed |
| Judge API retries | 0 per judge per call |
| Reflexion on regen | BLOCK (`reflexion_loop_not_executed_in_gateway_singleton_generate`) |

---

## Out Of Scope

- Changing `agentic_core` `SameAuthorityRegenRunner` contract (apps bridge + filter only unless Author-Gate core migration).
- Adding insurance-brokerage proof facts to master ledger (separate data initiative).
- Lowering Anthropic or panel score thresholds.
- Mock-only PASS / skipped judge panels.

---

## Wave 0 — Plan registration

WAVE_ID: W0
WAVE_STATUS: DONE
WAVE_COMPLETE: YES
AUTHORIZATION_STATUS: NOT_REQUIRED

**Acceptance**
- [x] [`.cursor/plans/exec-summary-brown-gap-hardening-b9e4c1.md`](exec-summary-brown-gap-hardening-b9e4c1.md) on disk.
- [x] Notion Plans row: `Status=Completed`, `Exists On Disk=true`, `Plan File Path=.cursor/plans/exec-summary-brown-gap-hardening-b9e4c1.md` — [Notion page](https://www.notion.so/exec-summary-brown-gap-hardening-b9e4c1-36d27693f55c81ab879edef5569f1007) (`36d27693-f55c-81ab-879e-def5569f1007`).

---

## Wave 1 — P0 prompt + regen proof boundary

WAVE_ID: W1
WAVE_STATUS: DONE
WAVE_COMPLETE: YES
AUTHORIZATION_STATUS: NOT_REQUIRED
CHECKPOINT: A

**Phases**
- [x] **W1.1** — E0 positive S6 + SRFS exemplar: compliant forward capstone (no "Looking ahead," no "extend that arc toward").
- [x] **W1.2** — `filter_judge_remediation_feedback_for_proof_gap` + `PROOF_BOUNDARY_REGEN` guard when TARGETING_GAP active; `allowed_fact_ids` threaded through regen bridge.
- [x] **W1.3** — `S6_forward_synthesis` allowlist clamped to S6 only; multi-sentence judge cites route to `executive_signal_and_voice_v1`; caps-disabled uses delta-class allowlist (not full S1–S6).

**Acceptance**
- [x] `pytest tests/unit/apps_rg/test_executive_summary_w1_brown_gap_hardening.py tests/unit/apps_rg/test_executive_summary_regen_delta_policy.py -o addopts=` → 30 passed.

---

## Wave 2 — P1 nine-slot prompt optimization

WAVE_ID: W2
WAVE_STATUS: DONE
WAVE_COMPLETE: YES
AUTHORIZATION_STATUS: NOT_REQUIRED
CHECKPOINT: B

**Phases**
- [x] **W2.1** — I0 `approved_non_stock_openers`; `check_exec_summary_stock_bridge_count` lint + `x2_exec_summary_stock_bridge_max_two` in `run_x2_gates`.
- [x] **W2.2** — I0/Y0 + E0 positive S5: FSA foundation + HPC 40% metric weave (no derivatives inventory).
- [x] **W2.3** — C0 `preferred_display_framing` for `fact_quant_hpc_003` in evidence capsule.
- [x] **W2.4** — `judge_score_variance_receipt.json` on dual-panel refresh (`emit_judge_score_variance_if_dual_panel`).

**Acceptance**
- [x] Compiled prompt contains non-stock opener examples.
- [x] `pytest tests/unit/apps_rg/test_executive_summary_w2_brown_gap_hardening.py -o addopts=` → 8 passed.

---

## Wave 3 — P2 process hardening

WAVE_ID: W3
WAVE_STATUS: DONE
WAVE_COMPLETE: YES
AUTHORIZATION_STATUS: NOT_REQUIRED
CHECKPOINT: C

**Phases**
- [x] **W3.1** — `regen_reasoning_execution_blocks` in `cli_section_execution_report.json` operator fields (`executive_summary_operator_reporting.py`).
- [x] **W3.2** — `regen_escalation_receipt.json` on `x2_stuck_same_failure` (cycle ≥2) with widen_delta / document_proof_gap / stop options.
- [x] **W3.3** — X2 gates `x2_exec_summary_s5_no_derivatives_inventory` + `x2_self_check_s5_no_derivatives_inventory`.

**Acceptance**
- [x] Operator guide § Receipt glossary updated.
- [x] `pytest tests/unit/apps_rg/test_executive_summary_w3_brown_gap_hardening.py -o addopts=` → 7 passed.

---

## Wave 4 — Brown SVP proof re-run

WAVE_ID: W4
WAVE_STATUS: DONE
WAVE_COMPLETE: YES
AUTHORIZATION_STATUS: NOT_REQUIRED
CHECKPOINT: D

**Command**
```bash
python -m apps_rg --section executive_summary \
  --target-company "Brown & Brown" \
  --target-role "SVP IT Strategy & Innovation" \
  --jd apps_rg/config/targeting/brown_brown_svp_it_strategy_innovation_jd.txt \
  --manual-brief apps_rg/config/targeting/brown_brown_svp_it_strategy_innovation_briefing.md
```

**Run evidence:** [exec_summary_20260527_073410](../../artifacts/apps_rg/runtime_proofs/executive_summary/real/exec_summary_20260527_073410/) · [exec_summary_20260527_073959](../../artifacts/apps_rg/runtime_proofs/executive_summary/real/exec_summary_20260527_073959/) · report [exec_summary_brown_gap_w4_rerun_20260527.md](../../docs/reports/apps_rg/exec_summary_brown_gap_w4_rerun_20260527.md)

**Closeout patch:** `retry_qwen_for_synthesis` reverts to first-pass text when shape regen does not achieve `accepted` (prevents publishing regen output that still fails stock/S5 X2).

**Acceptance**
- [x] New artifact dir under `artifacts/apps_rg/runtime_proofs/executive_summary/real/`.
- [ ] `x1d_certified: true` OR documented proof gap with all judges ≥4.0 — **deferred** (`X3_BLOCK`, `NO_JUDGE_ROWS_EMITTED`; X2 failed before panel).
- [ ] No formulaic triple-bridge stack — **deferred** (3 stock bridges in S2–S4 on `073959`; gates now enforce max-two).
- [x] `x2_unsupported_industry_claim_zero` on scratch; W3 S5 gates fired as designed.

**Wave outcome:** Engineering scope complete; REAL_LLM proof documented; certification acceptance criteria remain a follow-on generation task (not gate weakening).

---

## Gap Register

**GAP-1: E0 positive S6 contradicts I0 self_check** — **CLOSED** (W1.1)

**GAP-2: Regen delta requests proof-impossible industry framing** — **CLOSED** (W1.2)

**GAP-3: delta_class vs EDIT_BUDGET mismatch** — **CLOSED** (W1.3)

**GAP-4: Formulaic transition stacking (Qwen default)** — **MITIGATED** (W2.1 + X2 stock bridge gate); generation still triple-stacked on `073959` → follow-on prompt/model work

**GAP-5: S5 biographical inventory** — **MITIGATED** (W2.2, W3.3 X2 gates); S5 inventory still fails on `073959`

**GAP-6: Judge score variance without guard** — **CLOSED** (W2.4)

**GAP-7: Regen quality controls not operator-visible** — **CLOSED** (W3.1)

**GAP-8: Stuck loop with no escalation** — **CLOSED** (W3.2)

**GAP-9: Synthesis regen published failing shape** — **CLOSED** (closeout: `reverted_to_first_pass` when `accepted` false)

---

## Definition of Done

DoD-1: E0 positive example S6 is compliant with `s6_no_looking_ahead_opener` and thin-recap negative patterns
- Evidence: `pytest tests/unit/apps_rg/test_executive_summary_w1_brown_gap_hardening.py::test_e0_positive_svp_s6_compliant` → pass
- Status: DONE

DoD-2: Regen delta never instructs industry claims absent from `ALLOWED_SOURCE_FACT_IDS`
- Evidence: `test_proof_gap_filters_insurance_remediation_lines` + `test_collect_delta_includes_proof_boundary_guard` → pass
- Status: DONE

DoD-3: Brown SVP smoke run completes with artifact dir and `cli_section_execution_report.json`
- Evidence: [exec_summary_20260527_073959](../../artifacts/apps_rg/runtime_proofs/executive_summary/real/exec_summary_20260527_073959/cli_section_execution_report.json); `REAL_LLM`; exit 1 (NOT_READY)
- Status: DONE (runtime); certification exit 0 not claimed

DoD-4: Panel scores documented in `x1d_llm_judge_outputs.json`; variance receipt if dual panel
- Evidence: judges not invoked — X2 block; no variance receipt
- Status: DEFERRED (certification path)

DoD-5: Operator guide + plan Notion row updated
- Evidence: [executive_summary_operator_guide.md](../../docs/apps_rg/executive_summary_operator_guide.md); Notion `Status=Completed` on closeout
- Status: DONE

### Verification vs Deferral

| Item | In scope | Deferred |
|------|----------|----------|
| Insurance proof facts in ledger | — | New facts require separate data plan |
| Core reflexion in gateway | — | apps_rg receipt surfacing only |
| Anthropic threshold change | — | Policy decision |
| All judges ≥4.0 on Brown SVP | — | Next REAL_LLM run after scratch passes new X2 gates |

---

## Marker Quick Reference

```
PLAN_CREATED: slug=exec-summary-brown-gap-hardening-b9e4c1 path=.cursor/plans/exec-summary-brown-gap-hardening-b9e4c1.md status=Completed
WAVE_COMPLETE: plan=exec-summary-brown-gap-hardening-b9e4c1 wave=4 note="+synthesis revert, 20 tests, W4 073959, certification deferred"
PLAN_COMPLETE: plan=exec-summary-brown-gap-hardening-b9e4c1 note="W1–W4 engineering DONE; certification deferred"
```
