---
status: Archived
do_not_execute: true
memorialized: true
source_surface: claude_legacy_plans
source_key: claude
original_path: 'C:\\Git\\Agentic-Workflow-FRESH\\.codex\\plans\\_archive\\2026-05\\apps-rg-srfs-aggregator-e7b2a1.md'
original_relative_path: '_archive\\2026-05\\apps-rg-srfs-aggregator-e7b2a1.md'
source_sha256: d9c275a969596095c786d63768b9d33a5eb374020902f6750105028a9267333f
recovered_status: LEGACY_EXISTING
last_commit: ''
last_commit_date: ''
created_date: ''
archived_reason: historical consolidation for review, lessons learned, and anti-pattern analysis
---

> ARCHIVED MEMORIAL RECORD: This file is preserved for review and lessons learned. Do not execute it as an active plan.

---
---
plan_id: apps-rg-srfs-aggregator-e7b2a1
plan_type: refactor
touches_agentic_core: false
touches_governance_ci: false
touches_cursor_rules: false
touches_plan_templates: false
core_addition_author_gate_required: false
author_gate_receipt_ref: ""
dod_exempt: false
---

# apps_rg: SRFS section receipt aggregation / audit consumer

**Slug:** `apps-rg-srfs-aggregator-e7b2a1`  
**Date:** 2026-05-18  
**Upstream closeout:** `docs/reports/apps_rg/srfs_per_section_w1_w7_closeout_manifest.json`  
**Report mirror:** `docs/reports/apps_rg/srfs_aggregator_w1_plan.md`  
**Scope:** apps_rg-local consumer that aggregates `section_metric_receipt.json` across seven generated lanes into one cross-section SRFS structural audit report.  
**Implementation:** Complete (W1–W8 + real-receipt track R1–R4 + unify_bullets Q1–Q3).  
**Full closeout:** `docs/reports/apps_rg/srfs_full_track_closeout_manifest.json`

---

## Plan State Markers

FORMAT_VERSION: simplified-plan-format-v1  
PLAN_STATUS: COMPLETED  
CLOSURE_STATUS: CLOSED / STRUCTURAL PASS  
CURRENT_WAVE: DONE  
LAST_COMPLETED_WAVE: Q3  
LAST_UPDATED: 2026-05-18 (Notion + disk closure sync)

---

## Context (SCQA)

- **Situation** — Section-level SRFS structural proof is closed for seven generated lanes (`headline`, `executive_summary`, `unify_bullets`, `unify_narrative`, `ibm_bullets`, `ibm_narrative`, `competencies`). Each lane writes `section_metric_receipt.json` with normalized SRFS fields via `normalized_srfs_section_reporting_fields` / `merge_normalized_srfs_reporting_into_dict` in `apps_rg/runtime/sections/selected_role_fact_set.py`.
- **Complication** — No apps_rg product consumer rolls up those receipts into one cross-section audit artifact. Full résumé R4, `modular_resume_generation.py`, live Qwen quality, real-judge X3 ALLOW, and runtime certification remain **NOT_PROVEN**.
- **Question** — How do we add an apps_rg-local, deterministic SRFS aggregation/audit consumer without weakening gates, touching `agentic_core`, or claiming release certification?
- **Answer** — Eight waves (W1–W8): inventory → schema/rules → implementation → CLI → contract tests → optional advisory LLM audit-review → **fixture-based** deterministic artifacts → closeout manifest.

---

## 1. Objective

Build an **apps_rg product audit consumer** that:

1. Loads per-section `section_metric_receipt.json` files from a **caller-supplied `--receipt-manifest`** (preferred: explicit `section_id` → path map) or, as convenience only, `--receipt-root` recursive discovery. Never auto-resolves `latest_successful_*` pointers.
2. Normalizes field aliases into a canonical per-section row.
3. Validates inventory against the seven expected generated lanes (`GENERATED_LANES` in `apps_rg/runtime/internal/generated_lane_rollup.py`).
4. Emits one normalized cross-section report: `apps_rg_srfs_audit_report.json` (+ human-readable `.md` sibling).
5. Optionally attaches **advisory-only** LLM-as-judge commentary on the completed audit report (clarity, completeness, consistency) — never runtime release authority.

**Out of scope for this plan:** `agentic_core` edits, full résumé R4 SRFS, `modular_resume_generation.py` wiring (read-only boundary inspection only if justified in W1), X2/X3 weakening, live provider quality proof, Fort Knox / runtime certification, X3 ALLOW creation.

---

## 2. Proof boundary

| Layer | May claim | May not claim |
|-------|-----------|---------------|
| **Deterministic aggregator** | PASS / WARN / FAIL for **structural audit completeness** of collected section receipts (inventory, required fields, SRFS/X2 status semantics, explicit non-claims present) | Runtime ALLOW, product release, live model quality, certification |
| **Advisory LLM judge (W6)** | PASS / WARN / FAIL on **audit-report review** (clarity, contradictions, missing non-claims in prose, label consistency) | Override deterministic status; convert UNKNOWN → PASS; emit X3 ALLOW |
| **Combined proof level** | `SECTION_SRFS_STRUCTURAL_AUDIT_ONLY` | `RUNTIME_CERTIFICATION`, `LIVE_PROVIDER_QUALITY`, `REAL_JUDGE_X3_ALLOW`, `FULL_RESUME_SRFS` |

**Fail-closed rules (deterministic):**

- `UNKNOWN` is never PASS (section `x2_srfs_gate_status`, missing fields, or aggregate rollups).
- Missing expected section → FAIL.
- `full_resume_srfs_supported: true` in any receipt → FAIL (contradicts current product truth).
- Mocked or offline-stub receipts must be labeled in report metadata when detected; never upgrade proof class.

### Receipt input precedence (implementation invariant)

| Priority | Input | Behavior |
|----------|--------|----------|
| **1 (preferred)** | `--receipt-manifest <path>` | JSON/YAML map: `section_id` → absolute or repo-relative path to `section_metric_receipt.json`. Exactly one receipt per expected section; duplicates → FAIL. |
| **2 (convenience)** | `--receipt-root <dir>` | Recursive discovery of `section_metric_receipt.json` under caller-supplied directory only. Section identity from receipt `lane_id` / `srfs_section_id` (normalized). |
| **Forbidden** | Implicit `latest_successful_real_run.json` / rollup “chosen run” | **Never** read or infer unless the caller passes that exact path inside `--receipt-manifest` or under an explicit `--receipt-root`. |

`--manifest` (closeout / expected-sections reference) is **not** a receipt path resolver — it only supplies `expected_sections` and metadata refs.

### PASS guard (implementation invariant)

Aggregate `status` **must be FAIL** (never PASS) if any expected section has:

- missing receipt (not in manifest / not discovered under root)
- **pending** receipt (`status: "pending"` or equivalent interim shape)
- malformed receipt (invalid JSON, wrong type, missing `section_id` after normalization)
- **UNKNOWN** `x2_srfs_gate_status` or derived `srfs_structural_status` when SRFS active
- empty `prompt_hash` while `selected_role_fact_set_used` is true
- `full_resume_srfs_supported: true`

Enforce in `build_srfs_audit_report` before emitting PASS; cover with W5 regression tests.

### Output language (implementation invariant)

- Every emitted JSON/MD/closeout manifest uses **`proof_level: "SECTION_SRFS_STRUCTURAL_AUDIT_ONLY"`** (fixed string).
- **Forbidden** in `decisive_reason`, matrix summaries, CLI stdout, and markdown body: *release proof*, *product ALLOW*, *certified*, *runtime certified*, *full resume SRFS* (as affirmative claims).
- Those topics may appear **only** inside `explicit_non_claims` as negations (what is **not** proven).

---

## 3. Wave sequence (W1–W8)

### Wave Progress

| Wave | Focus | Status | Tests Added | Files Changed |
|------|-------|--------|-------------|---------------|
| W1 | Baseline receipt inventory + canonical schema draft | ✅ DONE | — | `srfs_aggregator_w1_receipt_inventory.md` |
| W2 | Aggregator schema + deterministic verdict rules | ✅ DONE | — | `srfs_aggregator_w2_schema_and_rules.md` |
| W3 | Aggregator implementation (`apps_rg/audit/`) | ✅ DONE | — | `srfs_receipt_aggregator.py` |
| W4 | CLI / module entrypoint | ✅ DONE | — | `srfs_receipt_aggregator.py` |
| W5 | Contract tests (`test_apps_rg_srfs_aggregator.py`) | ✅ DONE | 20 passed | `test_apps_rg_srfs_aggregator.py` |
| W6 | Advisory LLM-as-judge review layer (optional) | ✅ DONE | — | `srfs_audit_advisory_judge.py` |
| W7 | Fixture-based deterministic aggregator artifact | ✅ DONE | — | `fixture_run/` |
| W8 | Closeout manifest | ✅ DONE | — | `srfs_aggregator_w1_w8_closeout_manifest.json` |
| D1–D2 | Real-receipt fallback diagnosis | ✅ DONE | — | `srfs_real_receipt_fallback_diagnosis_w1_w2.md` |
| R1–R4 | SRFS-active real receipts + aggregator v2 | ✅ DONE | — | `real_receipt_trial_v2/` |
| Q1–Q3 | unify_bullets X2 SRFS fix + aggregator v3 | ✅ DONE | 1 + 20 | `unify_bullets_lane.py`, `real_receipt_trial_v3/` |

---

### W1 — Baseline receipt inventory

**Deliverables:**

- Document all `section_metric_receipt.json` write sites (lanes + dispatches): `headline_lane`, `executive_summary_lane`, `unify_*`, `ibm_*`, `competencies_dispatch`, `ibm_narrative_dispatch`.
- Inventory **observed top-level fields** (today): `run_id`, `lane_id`, `prompt_id`, `prompt_hash`, `input_payload_hash`, `output_payload_hash`, `claim_ledger_hash`, `runtime_generation_status`, `product_quality_status`, `x2_failed_gates`, `x3_code`, `proof_eligible`, `judge_proof_eligible`, plus W6 SRFS block (`proof_pool_type`, `selected_role_fact_set_used`, `srfs_section_id`, `x2_srfs_gate_status`, `full_resume_srfs_supported`, … — see `W6_FIELDS` in `test_apps_rg_srfs_w6_reporting.py`).
- Note **pending** interim shape: `{"status": "pending", "prompt_hash": ...}` before run completion (executive_summary, unify lanes).
- Propose **canonical normalized receipt row** for aggregator input (`canonical_section_metric_receipt.v1`) with alias map (e.g. `lane_id` → `section_id`).
- Define derived **`srfs_structural_status`** per section: PASS if `selected_role_fact_set_used` and `x2_srfs_gate_status == PASS`; FAIL if `FAIL`; FAIL if `UNKNOWN` when SRFS active; NOT_APPLICABLE when no SRFS.
- Define derived **`prompt_reflection_status`**: PASS if `prompt_hash` non-empty when SRFS active; UNKNOWN if field absent; FAIL if SRFS active and empty hash (W5 hierarchy not reflected in receipt).

**Acceptance:** Written schema draft in plan appendix or `docs/reports/apps_rg/srfs_aggregator_canonical_receipt_v1.json` (optional); no production code required.

---

### W2 — Aggregator schema and deterministic verdict rules

**Deliverables:**

- Lock `apps_rg_srfs_audit_report.json` schema (`apps_rg.srfs_audit_report.v1`) — see §4 below.
- **PASS:** all seven expected sections present; none pending/malformed; each normalized row passes **PASS guard** (§2); `proof_level` fixed; `explicit_non_claims` non-empty; no duplicate `section_id`.
- **WARN:** extra sections normalized and listed in `unexpected_sections`; benign extra receipt fields stripped to `extensions`; advisory judge NOT_RUN; otherwise all PASS-guard conditions satisfied.
- **FAIL:** any **PASS guard** violation; UNKNOWN coerced to PASS (meta-test); empty `explicit_non_claims`; receipt input used forbidden `latest_successful` inference.
- **UNKNOWN handling:** aggregate status FAIL if any section rollup would coerce UNKNOWN → PASS.

**Acceptance:** Schema + rules table committed; reviewed against closeout manifest sections list.

---

### W3 — Aggregator implementation

**New module (apps_rg-local):** `apps_rg/audit/srfs_receipt_aggregator.py`  
**Package:** `apps_rg/audit/__init__.py`

**Functions:**

| Function | Responsibility |
|----------|----------------|
| `load_section_receipts_from_manifest(manifest_path)` | **Preferred.** Parse `section_id` → receipt path map; load each file; fail on duplicate/missing paths |
| `load_section_receipts_from_root(root_dir)` | **Convenience.** Recursive `**/section_metric_receipt.json` under caller `root_dir` only — no `latest_successful` reads |
| `normalize_section_receipt(receipt)` | Apply alias map; derive `srfs_structural_status`, `prompt_reflection_status`; detect `pending` |
| `validate_section_inventory(receipts)` | Compare to `GENERATED_LANES` / closeout manifest `sections` |
| `build_srfs_audit_report(receipts, …)` | Apply **PASS guard**; set `proof_level`; deterministic verdict + `section_results` |
| `write_srfs_audit_report(report, output_dir)` | JSON + Markdown (language per §2 output rules) |

**Constraints:** No imports from `agentic_core`. No reads of `latest_successful_real_run.json` unless path explicitly in caller manifest. Reuse `GENERATED_LANES` from `generated_lane_rollup` for expected set only.

---

### W4 — CLI entrypoint

**Module:** `python -m apps_rg.audit.srfs_receipt_aggregator`

**Example:**

```bash
# Preferred: explicit per-section receipt paths
python -m apps_rg.audit.srfs_receipt_aggregator \
  --receipt-manifest artifacts/apps_rg/test_fixtures/srfs_aggregator/seven_section_receipt_manifest.json \
  --manifest docs/reports/apps_rg/srfs_per_section_w1_w7_closeout_manifest.json \
  --out artifacts/apps_rg/audit/srfs_section_aggregation/manual_run

# Convenience only: recursive discovery under a single caller-supplied directory
python -m apps_rg.audit.srfs_receipt_aggregator \
  --receipt-root artifacts/apps_rg/test_fixtures/srfs_aggregator/seven_section_receipts \
  --manifest docs/reports/apps_rg/srfs_per_section_w1_w7_closeout_manifest.json \
  --out artifacts/apps_rg/audit/srfs_section_aggregation/manual_run
```

**Flags:** `--receipt-manifest` (preferred), `--receipt-root` (convenience; mutually exclusive with manifest), `--manifest` (expected-sections / closeout ref only), `--out`, `--run-id`, `--enable-advisory-judge` (default off), `--judge-mock` (test only).

**Receipt manifest shape (v1):**

```json
{
  "schema_version": "apps_rg.srfs_receipt_manifest.v1",
  "receipts": {
    "headline": "path/to/headline/section_metric_receipt.json",
    "executive_summary": "path/to/executive_summary/section_metric_receipt.json"
  }
}
```

**Non-claims:** CLI exit 0 and aggregate PASS mean **SECTION_SRFS_STRUCTURAL_AUDIT_ONLY** only — not live provider proof, not certification, not product ALLOW.

---

### W5 — Deterministic fixture tests

**File:** `tests/_apps_contract/test_apps_rg_srfs_aggregator.py`

| Case | Expected aggregate `status` |
|------|----------------------------|
| Seven valid SRFS receipts (via `--receipt-manifest`) | PASS |
| Missing section | FAIL |
| Pending receipt (`status: pending`) | FAIL |
| Malformed receipt JSON | FAIL |
| PASS guard: aggregate would PASS with UNKNOWN section | FAIL |
| PASS guard: aggregate would PASS with empty prompt_hash (SRFS active) | FAIL |
| PASS guard: aggregate would PASS with `full_resume_srfs_supported: true` | FAIL |
| Loader must not read `latest_successful_*` without explicit path | test / static guard |
| Missing SRFS status fields | FAIL |
| Missing / bad `x2_srfs_gate_status` when SRFS active | FAIL |
| Missing prompt reflection (empty `prompt_hash` in SRFS mode) | FAIL |
| Report missing `explicit_non_claims` | FAIL |
| UNKNOWN treated as PASS (logic guard / regression) | FAIL |
| Extra unknown fields | WARN (normalized safely) |

Fixtures under `artifacts/apps_rg/test_fixtures/srfs_aggregator/` (synthetic minimal receipts).

---

### W6 — Advisory LLM-as-judge review layer (optional, apps_rg-local)

**Optional:** Default **off**. `--enable-advisory-judge` only for manual or explicit test runs.

**Boundary (hard):**

- **apps_rg-local only** — helper under `apps_rg/audit/` (e.g. `srfs_audit_advisory_judge.py`). No changes to generic judge infrastructure, shared judge registries, or `agentic_core` judge modules.
- **Do not** modify `grade_only_judge_packet`, section X1D runners, or policy-backed section judges for this feature.
- **Reuse rule:** If an existing apps_rg helper (e.g. local packet builder) is **cleanly reusable without edits** to shared judge infra, call it from the audit module. Otherwise **do not refactor** shared code — set `advisory_judge_review.status = NOT_RUN`, record limitation `"advisory_judge_not_wired"`, emit deterministic report, exit 0.

**Role (advisory only):** Review completed `apps_rg_srfs_audit_report.json` + `.md` for human audit usefulness.

**Judge may flag:** contradictions between `section_results`, confusing status labels, weak `decisive_reason`, missing non-claims in prose, incomplete matrix.

**Judge may not:** change aggregate `status`, create X3 ALLOW, override X2 semantics, convert UNKNOWN → PASS.

**Output contract** (nested under `advisory_judge_review`):

```json
{
  "enabled": false,
  "status": "PASS|WARN|FAIL|NOT_RUN",
  "mocked_or_live": "mocked|live|not_run",
  "can_change_deterministic_status": false,
  "findings": [],
  "limitations": []
}
```

**Implementation notes:**

- Mock path: `mocked_or_live: mocked` + limitation that output is non-certifying commentary.
- Live path: behind env/credentials gate; same limitations.
- Unavailable, unwired, or non-reusable helper → `status: NOT_RUN`, `enabled: false`; deterministic report unchanged.

---

### W7 — Fixture-based deterministic aggregator artifact

**Not** product E2E, **not** full résumé R4 proof, **not** live multi-section provider orchestration.

**Run aggregator** against committed fixture receipts using `--receipt-manifest` (preferred).

**Emit:**

- `artifacts/apps_rg/audit/srfs_section_aggregation/<run_id>/apps_rg_srfs_audit_report.json`
- `artifacts/apps_rg/audit/srfs_section_aggregation/<run_id>/apps_rg_srfs_audit_report.md`

**Markdown includes:** section matrix, deterministic verdict, `proof_level: SECTION_SRFS_STRUCTURAL_AUDIT_ONLY`, `explicit_non_claims` block, optional advisory judge subsection. No release/certification/ALLOW wording outside non-claims.

---

### W8 — Closeout manifest

**Emit:** `docs/reports/apps_rg/srfs_aggregator_w1_w8_closeout_manifest.json`

**Required keys:** `status`, `proof_level`, `files_changed`, `commands_run`, `artifact_paths`, `section_matrix`, `deterministic_verdict`, `advisory_judge_verdict` (if run), `explicit_non_claims`, `decisive_reason`

---

## 4. Report schema draft (`apps_rg.srfs_audit_report.v1`)

```json
{
  "schema_version": "apps_rg.srfs_audit_report.v1",
  "status": "PASS|WARN|FAIL",
  "proof_level": "SECTION_SRFS_STRUCTURAL_AUDIT_ONLY",
  "run_id": "...",
  "created_at_utc": "...",
  "source_manifest_ref": "docs/reports/apps_rg/srfs_per_section_w1_w7_closeout_manifest.json",
  "receipt_manifest_ref": "...",
  "receipt_root": null,
  "expected_sections": [
    "headline",
    "executive_summary",
    "unify_bullets",
    "unify_narrative",
    "ibm_bullets",
    "ibm_narrative",
    "competencies"
  ],
  "observed_sections": [],
  "missing_sections": [],
  "unexpected_sections": [],
  "duplicate_sections": [],
  "section_results": {
    "headline": {
      "receipt_path": "...",
      "srfs_structural_status": "PASS|FAIL|UNKNOWN|NOT_APPLICABLE",
      "x2_srfs_gate_status": "PASS|FAIL|UNKNOWN|NOT_APPLICABLE",
      "prompt_reflection_status": "PASS|FAIL|UNKNOWN",
      "selected_role_fact_set_used": true,
      "full_resume_srfs_supported": false,
      "x3_code": "...",
      "normalized_fields": {}
    }
  },
  "cross_section_findings": {
    "all_sections_srfs_pass": false,
    "any_unknown_coerced": false,
    "full_resume_srfs_claimed": false
  },
  "deterministic_findings": [],
  "advisory_judge_review": {
    "enabled": true,
    "status": "PASS|WARN|FAIL|NOT_RUN",
    "mocked_or_live": "mocked|live|not_run",
    "can_change_deterministic_status": false,
    "findings": [],
    "limitations": []
  },
  "explicit_non_claims": [
    "No runtime certification (Fort Knox / INTEGRITY_PROOF).",
    "No live Qwen/vLLM output-quality proof.",
    "No real-judge X3 ALLOW for product release.",
    "No full résumé R4 SRFS path; modular_resume_generation.py not wired.",
    "Advisory LLM judge does not override deterministic PASS/FAIL/WARN.",
    "Mocked judge output is non-certifying audit commentary only."
  ],
  "decisive_reason": "..."
}
```

---

## 5. Recommended commands

**Contract tests (after W5):**

```bash
PYTEST_DISABLE_PLUGIN_AUTOLOAD=1 python -m pytest tests/_apps_contract/test_apps_rg_srfs_aggregator.py -q --tb=short -p pytest_timeout
```

**Compile check (after W3):**

```bash
python -m compileall apps_rg/audit
```

**Aggregator CLI (after W4/W7):**

```bash
python -m apps_rg.audit.srfs_receipt_aggregator \
  --receipt-manifest artifacts/apps_rg/test_fixtures/srfs_aggregator/seven_section_receipt_manifest.json \
  --manifest docs/reports/apps_rg/srfs_per_section_w1_w7_closeout_manifest.json \
  --out artifacts/apps_rg/audit/srfs_section_aggregation/fixture_run
```

---

## 6. Acceptance criteria (plan complete → implementation complete)

- [ ] Deterministic aggregator owns structural audit verdict; advisory judge owns commentary only.
- [ ] All seven section statuses preserved in `section_results`.
- [ ] Missing receipt or UNKNOWN SRFS/X2 status fails closed (aggregate FAIL).
- [ ] `explicit_non_claims` populated in every emitted report.
- [ ] **PASS guard** enforced; pending/malformed/UNKNOWN/empty prompt_hash/full_resume true block PASS.
- [ ] Receipt loading prefers `--receipt-manifest`; never auto-reads `latest_successful_*`.
- [ ] Output language: `proof_level` only; no release/certification/ALLOW claims outside `explicit_non_claims`.
- [ ] W6 advisory judge optional, apps_rg-local; NOT_RUN when not cleanly reusable.
- [ ] `agentic_core` untouched; existing section SRFS gates and X2 validators untouched.
- [ ] W8 closeout manifest with command output and artifact paths.

---

## Definition of Done

| ID | Criterion | Verification |
|----|-----------|--------------|
| D1 | W1 receipt inventory doc matches live lane writers | Spot-check vs `headline_lane.py` + W6 test fields |
| D2 | Aggregator module passes `compileall apps_rg/audit` | Command exit 0 |
| D3 | Contract tests cover PASS/FAIL/WARN matrix | pytest file green |
| D4 | Fixture-based W7 emits JSON + MD under `artifacts/apps_rg/audit/srfs_section_aggregation/` | Paths exist; `proof_level` correct |
| D5 | PASS guard + advisory judge cannot mutate deterministic `status` | Unit tests + `can_change_deterministic_status: false` |
| D6 | Closeout manifest committed | `srfs_aggregator_w1_w8_closeout_manifest.json` |
| D7 | Smoke: CLI with `--receipt-manifest` on fixtures exits 0 | Command exit 0 |
| D8 | No `latest_successful` inference in loader | Grep/test guard |

### Verification vs deferral

| Item | In scope | Deferred / NOT_PROVEN |
|------|----------|------------------------|
| Cross-section SRFS structural audit | W1–W8 | — |
| Live multi-section provider run rollup | — | Live Qwen quality |
| Full resume R4 SRFS | — | `modular_resume_generation.py` |
| Runtime certification | — | Fort Knox bundle |
| Product X3 ALLOW | — | Real judges + ALLOW |
| Resume package assembly X3 | — | `resume_package_x3` path (separate aggregation) |

---

## Out of scope

- `agentic_core` changes
- Full résumé R4 SRFS integration
- `modular_resume_generation.py` edits (read-only inspection at most)
- Weakening X2, X3, or section SRFS gates
- `generated_lane_rollup` / `final_resume_assembler` behavioral changes
- Claiming mocked or advisory judge output as product proof
- Modifying generic judge infrastructure or `agentic_core` judges for W6
- Auto-resolving `latest_successful_real_run.json` or rollup chosen-run pointers

---

## Open decisions

1. **Prompt reflection field:** derive from `prompt_hash` only in v1, or add explicit `prompt_srfs_hierarchy_status` to receipts in a future lane wave (defer lane changes unless W1 proves insufficiency).
2. **Advisory judge provider:** mock-only in W6 CI tests; live judge behind env gate (document in W8 manifest). If no clean apps_rg-local reuse, ship W1–W5/W7 with NOT_RUN only.

---

## Risks

| Risk | Mitigation |
|------|------------|
| Operator passes rollup “latest” path by mistake | Document that only explicit manifest paths count; no inference |
| Pending receipts pollute aggregation | **PASS guard** treats `status: pending` as FAIL |
| Conflation with `resume_package_x3` / product E2E | W7 titled fixture-based; `proof_level` fixed; forbidden output phrases |
| Judge scope creep / shared infra edits | W6 apps_rg-local only; NOT_RUN if not reusable; no agentic_core |
| W7 misread as full résumé proof | Non-claims + wave title; fixture manifest only |

---

## Plan closure

**STATUS:** CLOSED / STRUCTURAL PASS  
**Notion:** Plans DB row `apps-rg-srfs-aggregator-e7b2a1` → `Completed`  
**Evidence:** `docs/reports/apps_rg/srfs_full_track_closeout_manifest.json` · aggregator v3 `artifacts/apps_rg/audit/srfs_section_aggregation/real_receipt_trial_v3/apps_rg_srfs_audit_report.json`

### Proven

- Seven generated sections can consume pinned SRFS
- Seven section receipts are SRFS-active
- All seven `x2_srfs_gate_status` values are PASS
- Aggregator v3 `deterministic_status` is PASS
- No `agentic_core` change
- No X2 or aggregator guard weakening

### Not proven

- Full résumé R4 SRFS path
- `modular_resume_generation.py` path
- Product X3 ALLOW
- Runtime certification
- Live judge quality

---

## Related artifacts

- `docs/reports/apps_rg/srfs_per_section_w1_w7_closeout_manifest.json`
- `docs/reports/apps_rg/srfs_full_track_closeout_manifest.json`
- `docs/reports/apps_rg/srfs_full_track_closeout.md`
- `docs/reports/apps_rg/apps_rg_post_section_aggregation_gap_20260517.md` (resume-level aggregation — orthogonal)
- `tests/_apps_contract/test_apps_rg_srfs_w6_reporting.py`
