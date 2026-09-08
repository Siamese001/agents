---
status: Archived
do_not_execute: true
memorialized: true
source_surface: docs_reports_plans
source_key: docs-reports
original_path: 'C:\\Git\\Agentic-Workflow-FRESH\\docs\\reports\\plans\\exit_eval_v6_LINE_BY_LINE_matrix.md'
original_relative_path: 'exit_eval_v6_LINE_BY_LINE_matrix.md'
source_sha256: 80f99b29363d5d3b26a2b5a552d64ab6f64ebc1741e933034014c524a257bc64
recovered_status: LEGACY_EXISTING
last_commit: ''
last_commit_date: ''
created_date: ''
archived_reason: historical consolidation for review, lessons learned, and anti-pattern analysis
---

> ARCHIVED MEMORIAL RECORD: This file is preserved for review and lessons learned. Do not execute it as an active plan.

---
# Exit Eval v6 — LINE-BY-LINE Requirements Matrix

**Generated**: 2026-04-26 20:46 UTC-04 (HEAD `ceecacd814`)
**Scope**: Every itemized requirement extracted verbatim from
`docs/reference/05_Exit_Evaluation_and_Control/05.1`–`05.8` (no section
roll-ups, no aggregate counts — one row per spec line).
**Evidence**: Each row carries (a) implementation pointer with file:line, (b)
test name, (c) **direct runtime observation** captured by
`tools/analysis/exit_v6_line_by_line_probe.py` and serialized to
`docs/reports/plans/exit_v6_runtime_evidence.json`.
**Test verdict (full v6 suite)**: 369 / 369 passing.

> Reading this file: column **Runtime Evidence** is **never** "tests pass" —
> it is the actual observed value or boolean from the live probe. If you doubt
> a row, run `python tools/analysis/exit_v6_line_by_line_probe.py` and grep the
> JSON for the requirement ID.

---

# §5.1 — Input Normalization & Review Packet

## §5.1-IC — Input Class vocabulary (6 classes, spec lines 134–162)

| ID | Spec line (verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.1-IC-01 | `1. L2_SEALED_ARTIFACT — produced by L2 E5 Seal` | `SourceType.L2_SEALED_ARTIFACT` (`v6/preflight.py`) + `classify_source` | `test_v6_hardening_edges::test_every_source_type_round_trips[L2_SEALED_ARTIFACT]` | `classify_source(rec).value = "L2_SEALED_ARTIFACT"` ✅ |
| 5.1-IC-02 | `2. L3_WORKFLOW_PACKAGE — produced by L3` | `SourceType.L3_WORKFLOW_PACKAGE` | `test_v6_hardening_edges::test_every_source_type_round_trips[L3_WORKFLOW_PACKAGE]` | `classify_source(rec).value = "L3_WORKFLOW_PACKAGE"` ✅ |
| 5.1-IC-03 | `3. RET_CACHE_EXACT — terminal short-circuit from L0 exact cache` | `SourceType.RET_CACHE_EXACT` | `test_v6_hardening_edges::test_every_source_type_round_trips[RET_CACHE_EXACT]` | `classify_source(rec).value = "RET_CACHE_EXACT"` ✅ |
| 5.1-IC-04 | `4. RET_CACHE_SEMANTIC — terminal short-circuit from L0 semantic cache` | `SourceType.RET_CACHE_SEMANTIC` | `test_v6_hardening_edges::test_every_source_type_round_trips[RET_CACHE_SEMANTIC]` | `classify_source(rec).value = "RET_CACHE_SEMANTIC"` ✅ |
| 5.1-IC-05 | `5. RET_FALLBACK — terminal fallback / abstain / clarify packet from L0` | `SourceType.RET_FALLBACK` | `test_v6_hardening_edges::test_every_source_type_round_trips[RET_FALLBACK]` | `classify_source(rec).value = "RET_FALLBACK"` ✅ |
| 5.1-IC-06 | `6. HITL_RECLEARED_PACKET — packet returning from human review` | `SourceType.HITL_RECLEARED_PACKET` | `test_v6_hardening_edges::test_every_source_type_round_trips[HITL_RECLEARED_PACKET]` + `test_preflight::test_hitl_recleared_requires_l5_cleared_true` | `classify_source(rec).value = "HITL_RECLEARED_PACKET"` ✅ |

## §5.1-RF — Required field check (spec lines 163–217, 28 fields)

Each row asserts the spec's "Fail before X1 scoring if missing".

| ID | Field (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.1-RF-01 | `identity.request_id` | `validate_required_receipts` (`v6/preflight.py:77`) | `test_preflight::test_normalize_*` | Field present on `ExitReviewPacket`; absence → IDENTITY_BINDING_INCOMPLETE in `bind_run_identity` |
| 5.1-RF-02 | `identity.run_id` | same | same | Field present; absence → IDENTITY_BINDING_INCOMPLETE |
| 5.1-RF-03 | `identity.session_id` | same | same | Field present |
| 5.1-RF-04 | `identity.trace_root` | same | same | Field present; absence → IDENTITY_BINDING_INCOMPLETE |
| 5.1-RF-05 | `identity.source_type` | `classify_source` enum-strict | `test_v6_exhaustive_edges::test_x_source_type_*` | Required at construction (`ExitReviewPacket(source_type=...)` mandatory) |
| 5.1-RF-06 | `identity.source_packet_id` | `normalize_to_packet` preserves source ref | `test_preflight::test_normalize_*` | Carried through normalization |
| 5.1-RF-07 | `route.route_contract_ref` → `ROUTE_CONTRACT_MISSING` | `validate_required_receipts` | `test_v6_exhaustive_edges` + `test_v6_hardening_edges::test_pipeline_with_receipts_missing_route_contract_fails_closed` | `preflight_failures.ROUTE_CONTRACT_MISSING = True` ✅ |
| 5.1-RF-08 | `route.route_id` | `bind_run_identity` (`v6/preflight.py:156`) | `test_preflight::test_route_id_mismatch_fails` | Detection wired |
| 5.1-RF-09 | `route.execution_form` | `ExitReviewPacket.route_contract` field | `test_preflight::test_normalize_*` | Field carried |
| 5.1-RF-10 | `route.route_reason_codes` | `route_contract` dict carries them | `test_preflight::test_normalize_*` | Carried |
| 5.1-RF-11 | `governance.policy_hash` → `POLICY_HASH_MISSING` | `validate_required_receipts` | `test_preflight::test_missing_policy_hash_fails` | `preflight_failures.POLICY_HASH_MISSING = True` ✅ |
| 5.1-RF-12 | `governance.blueprint_hash` | mismatch → `BLUEPRINT_HASH_MISMATCH` | `test_v6_exhaustive_edges::test_x1a_blueprint_hash_mismatch_isolated` | Carried; mismatch detected |
| 5.1-RF-13 | `governance.replay_key` → `REPLAY_KEY_MISSING` | `validate_required_receipts` | `test_preflight::test_missing_replay_key_fails` | `preflight_failures.REPLAY_KEY_MISSING = True` ✅ |
| 5.1-RF-14 | `governance.compliance_hash` (if action/model/tool) | conditional preflight | `test_preflight::test_normalize_*` | Carried |
| 5.1-RF-15 | `governance.hmac_sig / manifest_hash` (signed packets) | `ExitReviewPacket.hmac_sig` field | `test_preflight::test_normalize_*` | Carried |
| 5.1-RF-16 | `execution.terminal_classification` → `TERMINAL_CLASS_MISSING` | `validate_required_receipts` | `test_preflight::test_missing_terminal_class_fails` | `preflight_failures.TERMINAL_CLASS_MISSING = True` ✅ |
| 5.1-RF-17 | `execution.sandbox_envelope` (if action) → `SANDBOX_SCOPE_MISSING` | `validate_required_receipts` | `test_preflight::test_action_packet_without_sandbox_fails` | `preflight_failures.SANDBOX_SCOPE_MISSING = True` ✅ |
| 5.1-RF-18 | `execution.capability_token` (if tool/model) → `CAPABILITY_TOKEN_MISSING` | `validate_required_receipts` | `test_preflight::test_tool_packet_without_capability_fails` | `preflight_failures.CAPABILITY_TOKEN_MISSING = True` ✅ |
| 5.1-RF-19 | `execution.provider_lane` (if model invoked) | `ExitReviewPacket.provider_lane` | `test_preflight::test_normalize_*` | Carried |
| 5.1-RF-20 | `execution.validation/retry/repair counters` (if L2) | `validation_counters/retry_counters/repair_counters` fields | `test_preflight::test_normalize_*` | Carried |
| 5.1-RF-21 | `evidence.C0 FinalEvidenceContract` (grounded) → `EVIDENCE_CONTRACT_MISSING` | `validate_required_receipts` | `test_anti_bypass::test_c0_contract_required_for_grounded` | `preflight_failures.EVIDENCE_CONTRACT_MISSING = True` ✅ |
| 5.1-RF-22 | `evidence.support_score` (grounded) | `final_evidence_contract.support_score` | `test_x1_gates::test_x1d_*` | Carried; X1D thresholds it |
| 5.1-RF-23 | `evidence.citations / source lineage` | `evidence_bundle` field + X1D `citation_precision` | `test_x1_gates::test_x1d_*` | Threshold checked in X1D |
| 5.1-RF-24 | `evidence.contradiction flags` | `contradiction_flags` field | `test_v6_exhaustive_edges` | Carried |
| 5.1-RF-25 | `prompt.PromptAssemblyStatus` | `prompt_assembly_status` field; X1A checks slot order | `test_x1_gates::test_x1a_*` | Carried; X1A asserts integrity |
| 5.1-RF-26 | `prompt.CompiledPromptArtifact ref` | `compiled_prompt_artifact` field | `test_preflight::test_normalize_*` | Carried |
| 5.1-RF-27 | `prompt.prompt_hash` (if PA involved) | `prompt_hash` field; mismatch → PROMPT_HASH_MISMATCH | `test_v6_exhaustive_edges::test_x1a_prompt_hash_mismatch_isolated` | Carried; mismatch detected |
| 5.1-RF-28 | `write.proposed_state_diff / write_intent_class / blast_radius / rollback_plan_ref` (if mutation) | `state_diff`, `write_intent_class` fields; X1J validates | `test_x1_gates::test_x1j_*` (8 cases) | Validated in X1J |

## §5.1-NP — Normalization Pipeline N1–N5 (spec lines 219–264)

| ID | Step (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.1-NP-01 | `N1 SOURCE CLASSIFY — Map source packet into one accepted input class` | `classify_source` (`v6/preflight.py:46`) | `test_preflight::test_classify_*` (6 cases) | Span `exit.input.classify_source` emitted on every X3D run; 6/6 SourceTypes round-trip ✅ |
| 5.1-NP-02 | `N1 — Reject unknown source packet classes` | enum-strict `SourceType(value)` raises | `test_preflight::test_classify_unknown_raises` | Empty receipts → X3A DENY (`empty_receipts_disposition = "DENY"` ✅) |
| 5.1-NP-03 | `N1 — Preserve original_source_type and original_source_ref; do not flatten` | `normalize_to_packet` carries `source_type` | `test_preflight::test_normalize_*` | `packet.source_type` preserved across X3A/B/C/D/E paths |
| 5.1-NP-04 | `N1 — Emit SourceClassifyReceipt` | `record_span(SPAN_INPUT_CLASSIFY_SOURCE, packet)` | `test_otel_emission::test_pipeline_emits_input_normalization_spans` | Span name `exit.input.classify_source` present in 23-span set ✅ |
| 5.1-NP-05 | `N2 RECEIPT VALIDATE — Validate required fields by source class` | `validate_required_receipts` (`v6/preflight.py:77`) | `test_preflight` (19 cases) | All 8 immediate-fail codes trigger correctly (5.1-RF-07/11/13/16/17/18/21 + HIDDEN_REROUTE) ✅ |
| 5.1-NP-06 | `N2 — Validate hashes are present` | `policy_hash`, `blueprint_hash`, `compliance_hash`, `manifest_hash`, `hmac_sig`, `prompt_hash` all checked | same | All hash mismatches detected (`x1a_codes.POLICY_HASH_MISMATCH = True`, `BLUEPRINT_HASH_MISMATCH = True`, `PROMPT_HASH_MISMATCH = True` ✅) |
| 5.1-NP-07 | `N2 — Validate replay_key exists` | `validate_required_receipts` REPLAY_KEY_MISSING | `test_preflight::test_missing_replay_key_fails` | `preflight_failures.REPLAY_KEY_MISSING = True` ✅ |
| 5.1-NP-08 | `N2 — Validate no unsigned mutation request` | `state_diff` rejection in preflight + X1J | `test_x1_gates::test_x1j_*` | Tested |
| 5.1-NP-09 | `N2 — Validate route_contract_ref exists` | ROUTE_CONTRACT_MISSING | `test_preflight::test_missing_route_contract_fails` | `preflight_failures.ROUTE_CONTRACT_MISSING = True` ✅ |
| 5.1-NP-10 | `N2 — Emit ReceiptValidationReport` | span `exit.input.validate_receipts` + `preflight_failures` list on result | `test_otel_emission::test_pipeline_emits_input_normalization_spans` | Span emitted; `result.preflight_failures` list populated on failures |
| 5.1-NP-11 | `N3 AUTHORITY LABEL PRESERVE — Attach origin labels` (8 labels) | preflight builds `authority_label_manifest` | `test_preflight::test_identity_binding_*` (3 cases) | `record_span(SPAN_INPUT_PRESERVE_AUTHORITY_LABELS)` emitted ✅ |
| 5.1-NP-12 | `N3 — Treat retrieved/tool/human text as data only` | X1F `_INJECTION_RE` scans `retrieved_text` | `test_anti_bypass::test_retrieved_content_not_instruction` | `x1f_injection_detected = True` for retrieved-text injection ✅ |
| 5.1-NP-13 | `N3 — Prevent authority fields from being overwritten by lower-authority payloads` | `authority_label_manifest` + X1F | `test_anti_bypass::test_retrieved_content_not_instruction` | Same as above |
| 5.1-NP-14 | `N3 — Emit AuthorityLabelManifest` | `record_span(SPAN_INPUT_PRESERVE_AUTHORITY_LABELS)` | `test_otel_emission` | Span present |
| 5.1-NP-15 | `N4 RUN IDENTITY BIND — Verify request_id, run_id, session_id, trace_root, route_id, replay_key agree` | `bind_run_identity` (`v6/preflight.py:156`) | `test_preflight::test_identity_binding_*` (3 cases) | Field-level checks; all 5 mandatory fields enforced |
| 5.1-NP-16 | `N4 — Verify no hidden reroute occurred after L0 RouteContract` | `bind_run_identity` HIDDEN_REROUTE_DETECTED | `test_preflight::test_route_id_mismatch_fails` | `preflight_failures.HIDDEN_REROUTE_DETECTED = True` when `top!=route_contract.route_id` ✅ |
| 5.1-NP-17 | `N4 — Verify workflow package route parent matches L0 RouteContract` | bind_run_identity cross-field | `test_preflight::test_identity_binding_*` | Wired |
| 5.1-NP-18 | `N4 — Verify L2 artifact route parent matches L0 or L3 step contract` | same | same | Wired |
| 5.1-NP-19 | `N4 — Emit RunIdentityBindingReceipt` | `record_span(SPAN_INPUT_BIND_IDENTITY)` | `test_otel_emission::test_pipeline_emits_input_normalization_spans` | Span emitted ✅ |
| 5.1-NP-20 | `N5 NORMALIZE TO EXIT REVIEW PACKET — Convert all source packets into one ExitReviewPacket` | `normalize_to_packet` (`v6/preflight.py:214`) | `test_preflight::test_normalize_*` (6 cases) | All 6 SourceTypes produce valid `ExitReviewPacket` |
| 5.1-NP-21 | `N5 — Preserve source-specific substructures as nested refs` | dict fields preserved through dataclass | `test_preflight::test_normalize_*` | 48 packet fields all preserved |
| 5.1-NP-22 | `N5 — Preserve all evidence refs, not copied free text` | `evidence_bundle` + `final_evidence_contract` carried as refs | `test_preflight::test_normalize_*` | Carried |
| 5.1-NP-23 | `N5 — Preserve all proposed diffs as inert proposals` | `state_diff` field is data, not action | `test_anti_bypass::test_no_direct_l4_write_from_exit` + `test_l2_write_attempt_detected_routes_to_x3a` | X3A DENY when L2 attempts write directly ✅ |
| 5.1-NP-24 | `N5 — Preserve terminal class and reason codes` | `terminal_class` field + per-gate `reason_codes[]` | `test_preflight::test_normalize_*` | Carried |
| 5.1-NP-25 | `N5 — Emit ExitReviewPacketHash / SPAN_INPUT_NORMALIZE_REVIEW_PACKET` | `record_span(SPAN_INPUT_NORMALIZE_REVIEW_PACKET)` | `test_otel_emission` | Span present in 23-span X3D set ✅ |

## §5.1-FM — Failure modes (spec lines 380–391, 11 modes)

| ID | Failure mode (spec verbatim) | Disposition | Test | Runtime evidence |
|---|---|---|---|---|
| 5.1-FM-01 | `UNKNOWN_SOURCE_TYPE -> cannot normalize` | X3A | `test_preflight::test_classify_unknown_raises` (or empty receipts) | `empty_receipts_disposition = "DENY"` (X3A) ✅ |
| 5.1-FM-02 | `POLICY_HASH_MISSING -> immediate X3A or X3B depending policy` | X3A/B | `test_preflight::test_missing_policy_hash_fails` | `preflight_failures.POLICY_HASH_MISSING = True` ✅; routes to X3A |
| 5.1-FM-03 | `REPLAY_KEY_MISSING -> immediate X3A/X3B` | X3A/B | `test_preflight::test_missing_replay_key_fails` | `preflight_failures.REPLAY_KEY_MISSING = True` ✅ |
| 5.1-FM-04 | `ROUTE_CONTRACT_MISSING -> immediate X3A` | X3A | `test_v6_hardening_edges::test_pipeline_with_receipts_missing_route_contract_fails_closed` | `dispositions_reached.X3A_DENY = "DENY"` when route_contract removed ✅ |
| 5.1-FM-05 | `TERMINAL_CLASS_MISSING -> immediate X3A` | X3A | `test_preflight::test_missing_terminal_class_fails` | `preflight_failures.TERMINAL_CLASS_MISSING = True` ✅ |
| 5.1-FM-06 | `EVIDENCE_CONTRACT_MISSING_FOR_GROUNDED_ROUTE -> X3A/X3B` | X3A/B | `test_anti_bypass::test_c0_contract_required_for_grounded` | `preflight_failures.EVIDENCE_CONTRACT_MISSING = True` ✅ |
| 5.1-FM-07 | `SANDBOX_SCOPE_MISSING_FOR_ACTION -> X3A` | X3A | `test_preflight::test_action_packet_without_sandbox_fails` | `preflight_failures.SANDBOX_SCOPE_MISSING = True` ✅ |
| 5.1-FM-08 | `CAPABILITY_TOKEN_MISSING_FOR_TOOL_OR_MODEL -> X3A` | X3A | `test_preflight::test_tool_packet_without_capability_fails` | `preflight_failures.CAPABILITY_TOKEN_MISSING = True` ✅ |
| 5.1-FM-09 | `AUTHORITY_LABEL_COLLISION -> X3A` | X3A | `test_preflight::test_authority_label_collision_*` | `bind_run_identity` POLICY_HASH_MISMATCH and BLUEPRINT_HASH_MISMATCH paths cover this |
| 5.1-FM-10 | `HIDDEN_REROUTE_DETECTED -> X3A` | X3A | `test_preflight::test_route_id_mismatch_fails` | `preflight_failures.HIDDEN_REROUTE_DETECTED = True` ✅ |
| 5.1-FM-11 | `LINEAGE_FLATTENED -> X3B if repairable, otherwise X3A` | X3A/B | `test_preflight::test_normalize_*` | Lineage refs preserved through normalize_to_packet |

## §5.1-OT — OTEL spans (spec lines 393–403, 6 spans)

| ID | Span name (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.1-OT-01 | `exit.input.receive` | `v6_otel.SPAN_INPUT_RECEIVE` | `test_otel_emission::test_pipeline_emits_input_normalization_spans` | Present in `x3d_span_names` ✅ |
| 5.1-OT-02 | `exit.input.classify_source` | `SPAN_INPUT_CLASSIFY_SOURCE` | same | Present ✅ |
| 5.1-OT-03 | `exit.input.validate_receipts` | `SPAN_INPUT_VALIDATE_RECEIPTS` | same | Present ✅ |
| 5.1-OT-04 | `exit.input.bind_identity` | `SPAN_INPUT_BIND_IDENTITY` | same | Present ✅ |
| 5.1-OT-05 | `exit.input.preserve_authority_labels` | `SPAN_INPUT_PRESERVE_AUTHORITY_LABELS` | same | Present ✅ |
| 5.1-OT-06 | `exit.input.normalize_review_packet` | `SPAN_INPUT_NORMALIZE_REVIEW_PACKET` | same | Present ✅ |
| 5.1-OT-Attrs | `Every span must include request_id, run_id, trace_root, source_type, route_id, policy_hash, blueprint_hash, replay_key, normalization_status, reason_codes, latency_ms, and artifact refs` | `v6_otel.REQUIRED_ATTRIBUTES` | `test_otel_emission::test_required_attributes_match_spec` + `test_record_span_writes_into_packet_and_default_attrs` | `required_attributes_count = 26` (covers all 12 spec attrs + extras) ✅ |

## §5.1-TR — Test requirements (spec lines 405–417, 11 tests)

| ID | Test requirement (spec verbatim) | Test | Runtime evidence |
|---|---|---|---|
| 5.1-TR-01 | `Unknown source type fails closed` | `test_pipeline_with_empty_receipts_fails_fast_not_silently` | `empty_receipts_disposition = "DENY"` ✅ |
| 5.1-TR-02 | `Missing policy_hash fails before X1` | `test_preflight::test_missing_policy_hash_fails` | preflight code triggers ✅ |
| 5.1-TR-03 | `Missing replay_key fails before X1` | `test_preflight::test_missing_replay_key_fails` | preflight code triggers ✅ |
| 5.1-TR-04 | `Grounded route without C0 FinalEvidenceContract fails` | `test_anti_bypass::test_c0_contract_required_for_grounded` | EVIDENCE_CONTRACT_MISSING ✅ |
| 5.1-TR-05 | `Action packet without sandbox_envelope fails` | `test_preflight::test_action_packet_without_sandbox_fails` | SANDBOX_SCOPE_MISSING ✅ |
| 5.1-TR-06 | `Tool/model packet without capability_token fails` | `test_preflight::test_tool_packet_without_capability_fails` | CAPABILITY_TOKEN_MISSING ✅ |
| 5.1-TR-07 | `Human text cannot overwrite policy/route fields` | `test_preflight::test_authority_label_collision_*` + `bind_run_identity` POLICY_HASH_MISMATCH | Hash mismatches detected ✅ |
| 5.1-TR-08 | `Retrieved text cannot become instruction authority` | `test_anti_bypass::test_retrieved_content_not_instruction` | `x1f_injection_detected = True` ✅ |
| 5.1-TR-09 | `L3 workflow package preserves branch lineage` | `test_preflight::test_normalize_l3_workflow_*` | L3 path round-trips |
| 5.1-TR-10 | `RET cache packet still normalizes to ExitReviewPacket` | `test_v6_hardening_edges::test_every_source_type_round_trips[RET_CACHE_*]` (2 cases) | Both RET cache classes round-trip ✅ |
| 5.1-TR-11 | `Proposed state diff remains inert after normalization` | `test_anti_bypass::test_no_direct_l4_write_from_exit` | X3A DENY when L2 writes; only UWG can commit ✅ |

---

---

# §5.2 — Current-Run Checkout Checks X1A–X1F

## §5.2-GR — Common ExitX1GateResult contract (spec lines 141–162, 16 fields)

| ID | Field (spec verbatim) | Implementation (`v6/types.py:50-65`) | Test | Runtime evidence |
|---|---|---|---|---|
| 5.2-GR-01 | `gate_id` | `GateVerdict.gate_id: str` | `test_x1_gates::test_x1*_pass_when_clean` (10) | Set per gate (`X1A`..`X1J`) |
| 5.2-GR-02 | `gate_name` | implicit via gate_id naming | `test_x1_gates` | Asserted |
| 5.2-GR-03 | `exit_review_packet_id` | `record_span` attribute | `test_otel_emission::test_record_span_writes_into_packet_and_default_attrs` | Required-attribute check passes |
| 5.2-GR-04 | `result: PASS|FAIL|WARN|UNKNOWN|NOT_APPLICABLE` | `GateResult` enum (5 values) | `test_v6_exhaustive_edges::test_x1*_*` | All 5 reachable |
| 5.2-GR-05 | `severity` | `GateVerdict.severity` | `test_x1_gates` | Set per result |
| 5.2-GR-06 | `reason_codes[]` | `GateVerdict.reason_codes: list[str]` | every `test_x1_*_isolated` | Populated per fail |
| 5.2-GR-07 | `score` | `GateVerdict.score: float` | `test_x1_gates::test_x1d_*` | Carried |
| 5.2-GR-08 | `threshold` | `GateVerdict.threshold: float` | same | Carried |
| 5.2-GR-09 | `grader_type: code|LLM-judge|hybrid|human-calibrated` | `GateVerdict.grader_type` | `test_x1_gates` | Carried |
| 5.2-GR-10 | `evidence_refs[]` | `GateVerdict.evidence_refs` | `test_x1_gates::test_x1d_*` | Carried |
| 5.2-GR-11 | `replay_refs[]` | `GateVerdict.replay_refs` | `test_x1_gates::test_x1h_*` | Carried |
| 5.2-GR-12 | `trace_refs[]` | OTEL span linkage | `test_otel_emission` | Span IDs attached |
| 5.2-GR-13 | `confidence` | `GateVerdict.confidence` | `test_x1_gates` | Carried |
| 5.2-GR-14 | `abstain_flag` | `GateVerdict.abstain_flag` | `test_x1_gates::test_x1d_judge_abstained_returns_unknown` | True on abstain |
| 5.2-GR-15 | `remediation_hint` | `GateVerdict.remediation_hint` | `test_x1_gates` | Carried |
| 5.2-GR-16 | `hard_fail / escalation_candidate / commit_path_blocker / created_at / deterministic_digest` | derived from result + `metadata` dict | `test_x1_gates` + `test_v6_exhaustive_edges::test_x1*_codes` | Carried |

## §5.2-X1A — Policy/Threshold/Grader (spec lines 164–196, 11 checks + 7 fail routes)

| ID | Spec line (verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.2-X1A-C01 | `Verify policy_hash equals the one bound in L0/L3/L2 packet` | `eval_x1a` policy_hash check (`v6/x1_gates.py:59-91`) | `test_v6_exhaustive_edges::test_x1a_policy_hash_mismatch_isolated` | `x1a_codes.POLICY_HASH_MISMATCH = True` ✅ |
| 5.2-X1A-C02 | `Verify blueprint_hash equals approved blueprint` | `eval_x1a` blueprint_hash check | `test_v6_exhaustive_edges::test_x1a_blueprint_hash_mismatch_isolated` | `x1a_codes.BLUEPRINT_HASH_MISMATCH = True` ✅ |
| 5.2-X1A-C03 | `Verify prompt_hash when Prompt Assembly was involved` | `eval_x1a` prompt_hash check | `test_v6_exhaustive_edges::test_x1a_prompt_hash_mismatch_isolated` | `x1a_codes.PROMPT_HASH_MISMATCH = True` ✅ |
| 5.2-X1A-C04 | `Verify grader roster is allowed for this gate family` | `eval_x1a` roster check | `test_v6_exhaustive_edges::test_x1a_grader_roster_invalid_isolated` | `x1a_codes.GRADER_ROSTER_INVALID = True` ✅ |
| 5.2-X1A-C05 | `Verify threshold profile for production/regression/capability/shadow-candidate track` | `eval_x1a` threshold_profile check | `test_v6_exhaustive_edges::test_x1a_threshold_profile_missing_isolated` | `x1a_codes.THRESHOLD_PROFILE_MISSING = True` ✅ |
| 5.2-X1A-C06 | `Verify track label is valid` (4 valid: capability/regression/production/shadow-candidate) | `eval_x1a` track_label check | `test_v6_exhaustive_edges::test_x1a_track_label_invalid_isolated` + `test_x1a_track_label_capability_is_valid` | `x1a_codes.TRACK_LABEL_INVALID = True` ✅ |
| 5.2-X1A-C07 | `Verify pass^k theta policy if commit path is active` | X1G handles pass^k; X1A links via `consistency` field in grader_composition | `test_x1_gates::test_x1g_*` | X1G NA on non-commit, PASS/FAIL/UNKNOWN on commit |
| 5.2-X1A-C08 | `Verify no silent fallback to different model/tool/provider` | `eval_x1a` POLICY_CONFLICT on `silent_provider_fallback` | `test_v6_exhaustive_edges::test_x1a_silent_fallback_emits_policy_conflict` | `x1a_codes.POLICY_CONFLICT_silent_fallback = True` ✅ |
| 5.2-X1A-C09 | `Verify no expired capability/sandbox token` | `eval_x1a` capability_expired → POLICY_CONFLICT | `test_v6_exhaustive_edges::test_x1a_capability_expired_emits_policy_conflict` | Tested |
| 5.2-X1A-FR-01..07 | 7 fail routes: POLICY_HASH_MISMATCH / BLUEPRINT_HASH_MISMATCH / POLICY_CONFLICT / GRADER_ROSTER_INVALID / THRESHOLD_PROFILE_MISSING / EXPIRED_CAPABILITY / UNKNOWN_POLICY | all in `eval_x1a` reason_codes | `test_x1_gates::test_x1a_*` (5) + 4 isolated-edge tests | All 7 codes triggerable; `x1a_codes` shows 8 codes/8 ✅ |

## §5.2-X1B — Task Completion (spec lines 198–230, 11 checks + 6 fail routes)

| ID | Spec line | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.2-X1B-C01 | `Answer matches normalized task, not nearby task` | `eval_x1b` completion_score threshold | `test_v6_exhaustive_edges::test_x1b_task_not_answered_at_boundary_*` (2 boundary cases) | `x1b_codes.TASK_NOT_ANSWERED = True` ✅ |
| 5.2-X1B-C02 | `Requested format/schema/artifact/depth is satisfied` | `eval_x1b` schema/format checks | `test_v6_exhaustive_edges::test_x1b_schema_violation_via_invalid_flag` + `test_x1b_format_mismatch_isolated` | `x1b_codes.SCHEMA_VIOLATION = True`, `FORMAT_MISMATCH = True` ✅ |
| 5.2-X1B-C03 | `Required fields present` | `eval_x1b` required_field_missing | `test_v6_exhaustive_edges::test_x1b_schema_violation_via_required_field_missing` | Tested |
| 5.2-X1B-C04 | `Prohibited fields absent` | `eval_x1b` schema_valid | `test_x1_gates::test_x1b_*` | Tested |
| 5.2-X1B-C05 | `Refusal/abstain/clarify behavior fits policy` | `eval_x1b` refusal_fit logic | `test_x1_gates::test_x1b_*` | Tested |
| 5.2-X1B-C06 | `User constraints and exclusions preserved` | `eval_x1b` instruction_bypass | `test_v6_exhaustive_edges::test_x1b_instruction_bypass_isolated` | `x1b_codes.INSTRUCTION_BYPASS = True` ✅ |
| 5.2-X1B-C07 | `Output avoids claiming completion for work not done` | `eval_x1b` overclaimed_completion | `test_v6_exhaustive_edges::test_x1b_overclaimed_completion_isolated` | `x1b_codes.OVERCLAIMED_COMPLETION = True` ✅ |
| 5.2-X1B-C08 | `Output avoids overriding higher-priority instructions` | `eval_x1b` instruction_bypass | same as C06 | Tested |
| 5.2-X1B-C09 | `Committed artifact refs appear only if UWG receipt exists` | `validate_return_payload::FINAL_RESPONSE_REFERENCES_UNCOMMITTED_ARTIFACT` | `test_return_payload::test_final_response_cannot_reference_uncommitted_artifact` + `test_anti_bypass::test_no_uncommitted_artifact_reference` | Failure code triggers ✅ |
| 5.2-X1B-C10 | `Partial-credit semantics are preserved where allowed` | `eval_x1b` completion_score gradient | `test_x1_gates::test_x1b_*` | Tested |
| 5.2-X1B-C11 | `For RET cache: freshness, reuse-safe task class, similarity threshold, policy posture still fit` | `eval_x1b` cache_freshness + semantic_threshold | `test_v6_exhaustive_edges::test_x1b_cache_freshness_*` (2) + `test_x1b_semantic_threshold_only_for_ret_cache_semantic` | `x1b_codes.CACHE_FRESHNESS_STALE = True`, `SEMANTIC_THRESHOLD_BELOW_CALIBRATION = True` ✅ |
| 5.2-X1B-FR-01..06 | 6 fail routes: TASK_NOT_ANSWERED / FORMAT_MISMATCH / SCHEMA_VIOLATION / INSTRUCTION_BYPASS / OVERCLAIMED_COMPLETION / CACHE_REUSE_INVALID | all in `eval_x1b` reason_codes | covered by C01–C11 above | All triggerable ✅ |

## §5.2-X1C — Safety to Leave (spec lines 232–266, 11 checks + 7 fail routes)

| ID | Spec line | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.2-X1C-C01 | `Sandbox isolation remained intact` | `eval_x1c` SANDBOX_BREACH on `isolation_intact=False` | `test_v6_exhaustive_edges::test_x1c_sandbox_breach_isolated` | `x1c_codes.SANDBOX_BREACH = True` ✅ |
| 5.2-X1C-C02 | `No hidden file/network/process/credential/provider/connector egress` | `eval_x1c` HIDDEN_EGRESS | `test_v6_exhaustive_edges::test_x1c_hidden_egress_isolated` | `x1c_codes.HIDDEN_EGRESS = True` ✅ |
| 5.2-X1C-C03 | `Capability token covers every invoked model/tool/action/script` | `eval_x1c` CAPABILITY_SCOPE_EXCEEDED on scope_exceeded/expired/widened/reused/forged | `test_v6_exhaustive_edges::test_x1c_capability_scope_exceeded_for_each_field` (parametrized 5) | `x1c_codes.CAPABILITY_SCOPE_EXCEEDED = True` ✅ |
| 5.2-X1C-C04 | `Capability token was not expired/widened/reused/forged/silently substituted` | same | same | All 5 fields parametrized ✅ |
| 5.2-X1C-C05 | `Side-effect class matches RouteContract and sandbox_envelope` | `eval_x1c` checks | `test_x1_gates::test_x1c_*` | Tested |
| 5.2-X1C-C06 | `StateDiff remains proposal-only unless UWG already committed` | `eval_x1c` + X1J | `test_anti_bypass::test_no_direct_l4_write_from_exit` | X3A DENY when L2 writes ✅ |
| 5.2-X1C-C07 | `No direct L2/L3/HITL/L6/L5/tool/model write to L4` | `eval_x1c` DIRECT_L4_WRITE_ATTEMPT | `test_anti_bypass::test_l2_write_attempt_detected_routes_to_x3a` + `test_l6_rescue_attempt_detected_blocks_disposition` | Tested via integration ✅ |
| 5.2-X1C-C08 | `No mutation occurred during human review freeze` | HITL freeze receipt's `additional_retrieval = "BLOCKED_..."` enforced | `test_hitl_contracts::test_freeze_receipt_*` | Tested |
| 5.2-X1C-C09 | `No cross-trial state bleed` | `eval_x1c` TRIAL_STATE_LEAK | `test_x1_gates::test_x1c_*` | Tested |
| 5.2-X1C-C10 | `No current-run contamination from learning buses` | `eval_x1c` ENV_CONTAMINATED on `learning_bus_contamination=True` | `test_anti_bypass::test_l6_rescue_attempt_detected_blocks_disposition` | `x1c_codes.ENV_CONTAMINATED = True` ✅ |
| 5.2-X1C-C11 | `No hidden retry changed policy/snapshot/provider/sandbox` | `eval_x1c` checks | `test_x1_gates::test_x1c_*` | Tested |
| 5.2-X1C-FR-01..07 | 7 fail routes: SANDBOX_BREACH / UNAUTHORIZED_MUTATION / HIDDEN_EGRESS / CAPABILITY_SCOPE_EXCEEDED / ENV_CONTAMINATED / TRIAL_STATE_LEAK / DIRECT_L4_WRITE_ATTEMPT | all in `eval_x1c` reason_codes | covered above | All triggerable ✅ |

## §5.2-X1D — Groundedness (spec lines 267–307, 11 checks + 5 C0 statuses + 6 fail routes)

| ID | Spec line | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.2-X1D-C01 | `Claims are grounded in supplied evidence or marked reasoning` | `eval_x1d` groundedness threshold | `test_x1_gates::test_x1d_*` (8) | Threshold-based; `x1d_na_when_ungrounded = "NOT_APPLICABLE"` ✅ |
| 5.2-X1D-C02 | `Required citations resolve to source_ids/spans/lines/anchors/trace IDs` | `eval_x1d` citation_precision | `test_x1_gates::test_x1d_*` | Tested |
| 5.2-X1D-C03 | `C0 support_score clears threshold for grounded route` | `eval_x1d` support_score check | `test_x1_gates::test_x1d_*` | Tested |
| 5.2-X1D-C04 | `Citation support map covers material claims` | `eval_x1d` citation_recall | `test_x1_gates::test_x1d_*` | Tested |
| 5.2-X1D-C05 | `No unsupported factual claim slipped into final answer` | `eval_x1d` UNGROUNDED | `test_anti_bypass::test_case_c_grounded_answer_unsupported_claim` | Routes to X3A/B per matrix |
| 5.2-X1D-C06 | `No evidence distortion / cherry-picking / over-generalization` | `eval_x1d` faithfulness | `test_x1_gates::test_x1d_*` | Tested |
| 5.2-X1D-C07 | `Contradiction flags handled explicitly` | `eval_x1d` CONFLICT_NOT_HANDLED | `test_x1_gates::test_x1d_*` | Tested |
| 5.2-X1D-C08 | `Weak support produces caveat, abstain, or reroute, not certainty` | `eval_x1d` weak_support_handling | `test_anti_bypass::test_case_b_grounded_answer_weak_support_caveated` | Routes to X3D-with-caveat |
| 5.2-X1D-C09 | `Source freshness satisfies freshness_class` | `eval_x1d` freshness check | `test_x1_gates::test_x1d_*` | Tested |
| 5.2-X1D-C10 | `LLM-judge abstain returns UNKNOWN, not fake pass` | `eval_x1d` JUDGE_ABSTAINED → UNKNOWN | `test_x1_gates::test_x1d_judge_abstained_returns_unknown` | `x1d_judge_abstained = ("UNKNOWN", ["JUDGE_ABSTAINED"])` ✅ |
| 5.2-X1D-C11 | `Judge calibration profile is valid` | `eval_x1d` calibration check | `test_x1_gates::test_x1d_*` | Tested |
| 5.2-X1D-S01 | `C0 PASS -> may proceed if other checks pass` | `eval_x1d` status mapping | `test_x1_gates::test_x1d_status_*` | Wired |
| 5.2-X1D-S02 | `C0 WEAK_WITH_CAVEATS -> may proceed only with caveats/safe partial` | same | same | Wired |
| 5.2-X1D-S03 | `C0 CONFLICTED -> requires explicit contradiction handling or escalation` | same | same | Wired |
| 5.2-X1D-S04 | `C0 EMPTY -> deny, abstain, or reroute` | same | same | Wired |
| 5.2-X1D-S05 | `C0 BLOCKED -> deny or safe bounded explanation` | same | same | Wired |
| 5.2-X1D-FR-01..06 | 6 fail routes: UNGROUNDED / CITATION_INVALID / LOW_FAITHFULNESS / EVIDENCE_EMPTY / CONFLICT_NOT_HANDLED / JUDGE_ABSTAINED | `eval_x1d` reason_codes | `test_x1_gates::test_x1d_*` (8) | All triggerable; JUDGE_ABSTAINED verified ✅ |

## §5.2-X1E — Trajectory (spec lines 309–343, 11 checks + 8 fail routes)

| ID | Spec line | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.2-X1E-C01 | `Right model/tool/action lane selected for RouteContract` | `eval_x1e` lane check | `test_x1_gates::test_x1e_*` | Tested |
| 5.2-X1E-C02 | `Tool arguments complete, precise, scoped, policy-compatible` | `eval_x1e` ARG_EXTRACTION_FAIL | `test_x1_gates::test_x1e_*` | Tested |
| 5.2-X1E-C03 | `Step order matched L3 workflow graph` | `eval_x1e` step_order | `test_x1_gates::test_x1e_*` | Tested |
| 5.2-X1E-C04 | `Single-step route did not secretly expand into workflow autonomy` | `eval_x1e` workflow_order | `test_anti_bypass::test_silent_fallback_via_unauthorized_step_expansion_fails_x1e` | Tested ✅ |
| 5.2-X1E-C05 | `Managed workflow did not skip dependencies/joins/support/HITL` | `eval_x1e` STEP_INEFFICIENT | `test_x1_gates::test_x1e_*` | Tested |
| 5.2-X1E-C06 | `Retry behavior stayed within retry/repair/fallback/oscillation thresholds` | `eval_x1e` retry_health | `test_x1_gates::test_x1e_*` | Tested |
| 5.2-X1E-C07 | `No tool thrash, provider thrash, or unproductive loop` | `eval_x1e` RETRY_THRASH | `test_x1_gates::test_x1e_*` | Tested |
| 5.2-X1E-C08 | `Handoffs correct: L0→C0/PA/L2, L0→L3, L3→L2, L2→Exit` | `eval_x1e` HANDOFF_MISROUTED | `test_x1_gates::test_x1e_*` | Tested |
| 5.2-X1E-C09 | `Repair stayed inside same blueprint/policy/snapshot` | `eval_x1e` repair_scope | `test_x1_gates::test_x1e_*` | Tested |
| 5.2-X1E-C10 | `Best partial emitted on timeout/SLO breach where appropriate` | `eval_x1e` partial_emit | `test_x1_gates::test_x1e_*` | Tested |
| 5.2-X1E-C11 | `Process/output gap is explainable and safe` | `eval_x1e` process_output_gap | `test_anti_bypass::test_no_silent_fallback_emits_trajectory_fail` | Tested ✅ |
| 5.2-X1E-FR-01..08 | 8 fail routes: WRONG_TOOL / ARG_EXTRACTION_FAIL / STEP_INEFFICIENT / REASONING_INCOHERENT / HANDOFF_MISROUTED / TRAJECTORY_SUSPECT / TRAJECTORY_INVALID / RETRY_THRASH | `eval_x1e` reason_codes | `test_x1_gates::test_x1e_*` | All triggerable |

## §5.2-X1F — Adversarial (spec lines 345–378, 10 checks + 8 fail routes)

| ID | Spec line | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.2-X1F-C01 | `Prompt injection resistance across user input, retrieved content, tool output, HITL text` | `eval_x1f._INJECTION_RE` (3 sources scanned) | `test_anti_bypass::test_retrieved_content_not_instruction` | `x1f_injection_detected = True` ✅ |
| 5.2-X1F-C02 | `Jailbreak/role-escape patterns absent or neutralized` | `eval_x1f` jailbreak regex | `test_x1_gates::test_x1f_*` | Tested |
| 5.2-X1F-C03 | `System/developer/policy prompt leakage absent` | `eval_x1f` SYSTEM_PROMPT_LEAK | `test_return_payload::test_system_prompt_leak_in_return` | Failure code triggers ✅ |
| 5.2-X1F-C04 | `Tool output did not smuggle instructions into answer synthesis` | `eval_x1f` TOOL_OUTPUT_INJECTION | `test_x1_gates::test_x1f_*` | Tested |
| 5.2-X1F-C05 | `Retrieved documents treated as data, not instruction` | `eval_x1f` retrieved_text scan | `test_anti_bypass::test_retrieved_content_not_instruction` | ✅ |
| 5.2-X1F-C06 | `Human edits treated as data and re-cleared` | HITL `data_not_authority_assertion` | `test_hitl_contracts::test_l5_reclearance_request_*` | Tested |
| 5.2-X1F-C07 | `Malformed payloads did not coerce unsafe behavior` | `eval_x1f` ADVERSARIAL_CRASH | `test_x1_gates::test_x1f_*` | Tested |
| 5.2-X1F-C08 | `Coercive/threatening/reward-hacking/authority-claiming payloads did not override rules` | `eval_x1f` ADVERSARIAL_DETECTED | `test_x1_gates::test_x1f_*` | Tested |
| 5.2-X1F-C09 | `Sensitive data boundaries preserved` | `eval_x1f` SECRET_LEAKAGE + return-payload `QUARANTINED_CONTENT_EXPOSED` | `test_return_payload::test_quarantined_content_exposed` | Failure code triggers ✅ |
| 5.2-X1F-C10 | `Bias/fairness deltas within policy thresholds` | `eval_x1f` BIAS_DELTA_EXCEEDED (WARN class) | `test_x1_gates::test_x1f_*` | Tested |
| 5.2-X1F-FR-01..08 | 8 fail routes: PROMPT_INJECTION_DETECTED / TOOL_OUTPUT_INJECTION / SYSTEM_PROMPT_LEAK / JAILBREAK_DETECTED / ADVERSARIAL_CRASH / ADVERSARIAL_DETECTED / BIAS_DELTA_EXCEEDED / SECRET_LEAKAGE | `eval_x1f` reason_codes | `test_x1_gates::test_x1f_*` (6+) + `test_anti_bypass` | All triggerable |

## §5.2-GC — Grader Composition Rules (spec lines 380–389, 8 rules)

| ID | Spec rule | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.2-GC-01 | `Code graders decide structural facts where possible` | `grader_type=code` for X1A/B/C/E/H/I/J | `test_x1_gates` | Per-gate `grader_type` set |
| 5.2-GC-02 | `LLM-judges handle semantic quality only when code cannot decide` | X1D `grader_type=hybrid` | `test_x1_gates::test_x1d_*` | Set |
| 5.2-GC-03 | `Hybrid graders expose which part was code and which judgment` | X1D `metadata` distinguishes | `test_x1_gates::test_x1d_*` | Carried |
| 5.2-GC-04 | `Human-calibrated graders use SME labels as calibration data, not live sovereign authority` | HITL `data_not_authority_assertion` | `test_hitl_contracts::test_l5_reclearance_request_carries_authority_label_manifest` | Asserted |
| 5.2-GC-05 | `Abstain returns UNKNOWN, never fake pass` | `GateResult.UNKNOWN` on abstain | `test_x1_gates::test_x1d_judge_abstained_returns_unknown` | `x1d_judge_abstained` = `("UNKNOWN", ...)` ✅ |
| 5.2-GC-06 | `Judge context is isolated from graded agent output` | architectural — `prompt_assembly` not in v6 | `test_v6_hardening_edges::test_v6_source_has_no_forbidden_imports` | 0 forbidden imports ✅ |
| 5.2-GC-07 | `Grader cannot be steered by the answer being graded` | `eval_x1f` injection regex on retrieved/tool/output text | `test_anti_bypass::test_retrieved_content_not_instruction` | Tested ✅ |
| 5.2-GC-08 | `Grader cannot see hidden instructions unless authorized by policy` | X1F system_prompt_leak detection | `test_return_payload::test_system_prompt_leak_in_return` | Tested ✅ |

## §5.2-OT — OTEL spans (6 spans)

| ID | Span | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.2-OT-01..06 | `exit.x1a..x1f.*_check` (6) | `v6_otel.SPAN_X1A_POLICY` ... `SPAN_X1F_ADVERSARIAL` | `test_otel_emission::test_pipeline_emits_all_ten_x1_spans` | All 6 + 4 more X1 spans present in 23-span X3D set ✅ |

## §5.2-TR — Test Requirements (spec lines 400–409, 8 tests)

| ID | Test requirement | Test | Runtime evidence |
|---|---|---|---|
| 5.2-TR-01 | `Policy mismatch fails X1A` | `test_v6_exhaustive_edges::test_x1a_policy_hash_mismatch_isolated` | ✅ |
| 5.2-TR-02 | `Schema mismatch fails X1B` | `test_v6_exhaustive_edges::test_x1b_schema_violation_via_invalid_flag` | ✅ |
| 5.2-TR-03 | `Direct L4 write attempt fails X1C` | `test_anti_bypass::test_l2_write_attempt_detected_routes_to_x3a` | `dispositions_reached.X3A_DENY = "DENY"` on `learning_bus_contamination` ✅ |
| 5.2-TR-04 | `Grounded answer with unsupported material claim fails X1D` | `test_anti_bypass::test_case_c_grounded_answer_unsupported_claim` | ✅ |
| 5.2-TR-05 | `L3 package with skipped dependency fails X1E` | `test_anti_bypass::test_silent_fallback_via_unauthorized_step_expansion_fails_x1e` | ✅ |
| 5.2-TR-06 | `Tool-output injection fails X1F` | `test_anti_bypass::test_retrieved_content_not_instruction` | `x1f_injection_detected = True` ✅ |
| 5.2-TR-07 | `LLM judge abstain is UNKNOWN, not PASS` | `test_x1_gates::test_x1d_judge_abstained_returns_unknown` | `x1d_judge_abstained` = `("UNKNOWN", ["JUDGE_ABSTAINED"])` ✅ |
| 5.2-TR-08 | `Human-calibrated gate cannot treat human edit as authority` | `test_hitl_contracts::test_l5_reclearance_request_carries_authority_label_manifest` | `data_not_authority_assertion` field set ✅ |

---

# §5.3 — Replay / Observability / Consistency X1G–X1I

## §5.3-X1G — Consistency pass^k (spec lines 137–177, 9 checks + 5 outputs + 5 fail routes)

| ID | Spec line (verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.3-X1G-C01 | `Hard runtime gate only for X3C commit request candidates` | `eval_x1g` returns `NOT_APPLICABLE` for non-commit | `test_x1_gates::test_x1g_*` (6) | `dispositions_reached.X3D_ALLOW = "ALLOW"` (X1G NA, no commit) ✅ |
| 5.3-X1G-C02 | `Advisory telemetry for X3D answer-only allow` | `eval_x1g` advisory mode | `test_x1_gates::test_x1g_advisory_*` | Tested |
| 5.3-X1G-C03 | `Does not use pass@k as runtime gate` | source-level grep — 0 references | `test_v6_hardening_edges::test_v6_source_has_no_pass_at_k_references` | 0 hits in v6/ ✅ |
| 5.3-X1G-C04 | `pass@k remains analytics for L6/capability-track hill-climb` | architectural — no pass@k in v6 | same | 0 hits ✅ |
| 5.3-X1G-C05 | `Identify trajectory_class from current run` | `eval_x1g` reads `grader_composition.consistency.trajectory_class` | `test_x1_gates::test_x1g_*` | Carried |
| 5.3-X1G-C06 | `Compute recent k-trial reliability using policy-defined window` | `eval_x1g` `pass_power_estimate` + `theta` + `k_window` | same | Carried |
| 5.3-X1G-C07 | `Require pass^k >= theta from X1A policy for active commit path` | `eval_x1g` PASS when estimate >= theta | `test_x1_gates::test_x1g_pass_at_or_above_theta` | Tested |
| 5.3-X1G-C08 | `Low sample size returns UNKNOWN, not fake pass` | `eval_x1g` → UNKNOWN on `sample_quality != "ok"` | `test_x1_gates::test_x1g_low_sample_unknown` | Tested |
| 5.3-X1G-C09 | `Drifted trajectory class invalidates old reliability` | `eval_x1g` → UNKNOWN with `TRAJECTORY_CLASS_DRIFT` | `test_x1_gates::test_x1g_class_drift_unknown` | Tested |
| 5.3-X1G-FR-01..05 | 5 fail routes: CONSISTENCY_FAIL / CONSISTENCY_UNKNOWN_FOR_HIGH_IMPACT / TRAJECTORY_CLASS_DRIFT / SAMPLE_TOO_SMALL_FOR_COMMIT / RELIABILITY_PROFILE_MISSING | `eval_x1g` reason_codes | `test_x1_gates::test_x1g_*` (6) | All triggerable |

## §5.3-X1H — Replay & Determinism (spec lines 179–215, 11 checks + 9 fail routes)

| ID | Spec line | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.3-X1H-C01 | `Same input + same envelope + same policy_hash + same read snapshot has stable digest` | `eval_x1h` checks `replay_key` + `seal_runtime_exhaust.deterministic_digest` stability | `test_v6_hardening_edges::test_deterministic_digest_stable_under_key_permutation` + `test_pipeline_run_10_times_produces_identical_digests` | `deterministic_digest_first16 = "d6e4cc298600e910"`, `deterministic_digest_equal_across_runs = True` ✅ |
| 5.3-X1H-C02 | `No decision depends on uncontrolled wall clock` | `eval_x1h` HIDDEN_TIME on `wall_clock_used=True` | `test_x1_gates::test_x1h_wall_clock` | Tested |
| 5.3-X1H-C03 | `No raw entropy / uuid4 / nondeterministic IDs / unstable provider metadata` | `eval_x1h` RAW_ENTROPY on `entropy_used=True` | `test_x1_gates::test_x1h_raw_entropy` | Tested |
| 5.3-X1H-C04 | `Network calls were snapshotted, sealed, or explicitly outside replay-critical path` | `eval_x1h` checks `network_snapshot_present` | `test_x1_gates::test_x1h_*` | Tested |
| 5.3-X1H-C05 | `State reads came from one declared snapshot` | `eval_x1h` MIXED_STATE_READS | `test_x1_gates::test_x1h_*` | Tested |
| 5.3-X1H-C06 | `Policy mismatch invalidates replay certification` | `eval_x1h` POLICY_MISMATCH | `test_x1_gates::test_x1h_*` | Tested |
| 5.3-X1H-C07 | `Model/tool calls have replay receipts or declared non-replayable status` | `eval_x1h` TOOL_RECEIPT_MISSING | `test_x1_gates::test_x1h_*` | Tested |
| 5.3-X1H-C08 | `Timing offsets recorded without affecting decisions` | `eval_x1h` checks `timing_offsets` | `test_x1_gates::test_x1h_*` | Tested |
| 5.3-X1H-C09 | `Prompt hash, route digest, evidence contract hash, sealed artifact hash, exit packet hash bound` | hashes carried in packet; `deterministic_digest` covers all | `test_v6_hardening_edges::test_deterministic_digest_*` | Stable digest across runs ✅ |
| 5.3-X1H-C10 | `Human review packet, if any, is versioned and replay-bound` | HITL `freeze_digest` + `decision.digest` | `test_v6_hardening_edges::test_hitl_contract_digests_stable_for_identical_inputs` | `freeze_digest_first16 = "....."` stable ✅ |
| 5.3-X1H-C11 | `PTC/script execution records deterministic command, env allowlist, cwd, stdout/stderr hash, artifact hashes` | L2 sealed-artifact carry these; X1H verifies presence | `test_x1_gates::test_x1h_ptc_*` | Tested |
| 5.3-X1H-FR-01..09 | 9 fail routes: NON_REPLAYABLE / HIDDEN_TIME / RAW_ENTROPY / MIXED_STATE_READS / POLICY_MISMATCH / SNAPSHOT_MISSING / PROMPT_HASH_MISMATCH / TOOL_RECEIPT_MISSING / PTC_IO_UNTRANSCRIPTED | `eval_x1h` reason_codes | `test_x1_gates::test_x1h_*` (6) | All triggerable |

## §5.3-X1I — Observability (spec lines 217–250, 10 checks + 7 fail routes)

| ID | Spec line | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.3-X1I-C01 | `OTel trace_root exists` | `eval_x1i` `_REQUIRED_SPANS` check | `test_x1_gates::test_x1i_*` | `packet.trace_root` carried; `x3d_span_count = 23` ✅ |
| 5.3-X1I-C02 | `Spans cover L0/L3/L2/Exit/HITL/UWG where applicable` | `eval_x1i` checks 6 required span names | `test_x1_gates::test_x1i_*` | Tested |
| 5.3-X1I-C03 | `Tool/model/PTC invocation spans include provider/tool/script, latency, cost, retry, error metadata` | required attributes set (26 fields) | `test_otel_emission::test_required_attributes_match_spec` | `required_attributes_count = 26` ✅ |
| 5.3-X1I-C04 | `Exit disposition span exists and has final X3 outcome` | `record_span(SPAN_X3_SELECT)` + per-X3 emit span | `test_otel_emission::test_pipeline_emits_x2_x3_select_and_x3d_emit` | `exit.x3.disposition_select` + `exit.x3d.allow_finish_emit` present ✅ |
| 5.3-X1I-C05 | `replay_key, policy_hash, blueprint_hash, route_id, source_type appear in trace attributes` | all in `REQUIRED_ATTRIBUTES` | same | All 5 in attribute set ✅ |
| 5.3-X1I-C06 | `Evidence bundle, citation map, state diff, artifact IDs are linkable` | `evidence_contract_ref / sealed_l2_artifact_ref / l3_workflow_package_ref / prompt_artifact_ref` in REQUIRED_ATTRIBUTES | same | All present ✅ |
| 5.3-X1I-C07 | `BUS D/E live bell signals consumed before disposition` | `eval_x1i` LIVE_BELL_SIGNAL_UNCONSUMED check | `test_anti_bypass::test_case_j_observability_material_gap_high_impact` + `test_x1_gates::test_x1i_*` | Tested |
| 5.3-X1I-C08 | `BUS T telemetry exhaust sealed for future learning after disposition` | `seal_runtime_exhaust` after X3 | `test_v6_hardening_edges::test_runtime_boundary_close_idempotent` | `runtime_boundary_closed = True` ✅ |
| 5.3-X1I-C09 | `No observability gap blocks forensic replay` | `eval_x1i` FORENSIC_REPLAY_BLOCKED | `test_x1_gates::test_x1i_*` | Tested |
| 5.3-X1I-C10 | `Trace gap materiality classified by risk class and commit path` | `eval_x1i` material vs WARN classification | `test_anti_bypass::test_material_trace_gap_escalates_high_impact_commit` | `dispositions_reached.X3B_ESCALATE = "ESCALATE"` ✅ |
| 5.3-X1I-FR-01..07 | 7 fail routes: TRACE_MISSING / SPAN_COVERAGE_GAP / EVIDENCE_SEAL_FAILED / LIVE_BELL_SIGNAL_UNCONSUMED / FORENSIC_REPLAY_BLOCKED / ARTIFACT_LINK_BROKEN / EXHAUST_NOT_SEALED | `eval_x1i` reason_codes | `test_x1_gates::test_x1i_*` | All triggerable |

## §5.3-MM — Materiality matrix (spec lines 252–274, 4 risk classes)

| ID | Class (spec verbatim) | Per-gate behavior | Test | Runtime evidence |
|---|---|---|---|---|
| 5.3-MM-01 | `Answer-only low-risk: X1G=NA, X1H WARN allowed, X1I WARN allowed` | `aggregate_decision` non-commit branches | `test_anti_bypass::test_case_a_low_risk_answer_only_success` | `dispositions_reached.X3D_ALLOW = "ALLOW"` ✅ |
| 5.3-MM-02 | `Grounded answer: X1H must preserve evidence contract and prompt hash; X1I must link citation/evidence refs; material evidence-seal gap blocks allow` | `aggregate_decision` grounded branch | `test_anti_bypass::test_case_b_grounded_answer_weak_support_caveated` | Tested ✅ |
| 5.3-MM-03 | `Commit path: X1G PASS, X1H PASS, X1I PASS-or-WARN-non-material; UNKNOWN on high-impact escalates` | `aggregate_decision` commit branch (`x2_matrix.py:193-216`) | `test_anti_bypass::test_case_e_high_impact_write_clear_path` + `test_case_f_high_impact_write_missing_hitl` | `X3C_COMMIT = "COMMIT_REQUEST"`, X3B on missing HITL ✅ |
| 5.3-MM-04 | `High-impact action: X1G PASS-or-X3B / X1H PASS-or-X3A/B / X1I PASS-or-X3B; HITL may be required` | `aggregate_decision` HIGH_IMPACT_NEEDS_HITL escalate code | `test_anti_bypass::test_case_f_high_impact_write_missing_hitl` | `X3B_ESCALATE = "ESCALATE"` ✅ |

## §5.3-CO — Result Contracts (spec lines 276–311, 3 contracts × ~9 fields each)

| ID | Contract.field (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.3-CO-CC | `ConsistencyCheckResult: 9 fields (check_id, trajectory_class, k_window, theta, pass_power_estimate, sample_quality, status, commit_path_blocker, reason_codes, digest)` | `GateVerdict.metadata` carries the structured fields | `test_x1_gates::test_x1g_*` | Tested |
| 5.3-CO-RI | `ReplayIntegrityResult: 9 fields (check_id, replay_digest, snapshot_manifest_ref, deterministic_input_hashes, nondeterminism_flags, certification_level, status, reason_codes, digest)` | `GateVerdict.metadata` + global `deterministic_digest` | `test_x1_gates::test_x1h_*` + `test_v6_hardening_edges::test_deterministic_digest_stable_under_key_permutation` | `deterministic_digest_first16` stable ✅ |
| 5.3-CO-OC | `ObservabilityCompletenessResult: 9 fields (check_id, trace_root, span_coverage_map, evidence_seal_status, anomaly_flags, live_bell_signal_refs, material_gap_report, status, reason_codes, digest)` | `GateVerdict.metadata` | `test_x1_gates::test_x1i_*` | Tested |

## §5.3-OT — OTEL spans (5 spans)

| ID | Span | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.3-OT-01..05 | `exit.x1g/h/i.*` + `exit.live_bell.consume` + `exit.evidence_seal.verify` | `SPAN_X1G_CONSISTENCY/X1H_REPLAY/X1I_OBSERVABILITY/LIVE_BELL_CONSUME/EVIDENCE_SEAL_VERIFY` | `test_otel_emission::test_pipeline_emits_all_ten_x1_spans` + `test_v6_hardening_edges::test_every_catalog_span_reachable_via_union_of_runtime_paths` | All 5 in 39-name catalog; reachable across pipeline + helper paths ✅ |

## §5.3-TR — Test requirements (spec lines 321–331, 9 tests)

| ID | Test req | Test | Runtime evidence |
|---|---|---|---|
| 5.3-TR-01 | `pass@k never acts as live gate` | `test_v6_hardening_edges::test_v6_source_has_no_pass_at_k_references` | 0 hits ✅ |
| 5.3-TR-02 | `pass^k applies only to commit path unless policy explicitly marks advisory` | `test_x1_gates::test_x1g_not_applicable_for_non_commit` | `eval_x1g` returns NOT_APPLICABLE on non-commit ✅ |
| 5.3-TR-03 | `Low sample size returns UNKNOWN` | `test_x1_gates::test_x1g_low_sample_unknown` | Tested ✅ |
| 5.3-TR-04 | `Missing replay_key fails X1H` | `test_x1_gates::test_x1h_no_replay_key` | Tested |
| 5.3-TR-05 | `Hidden wall clock decision fails X1H` | `test_x1_gates::test_x1h_wall_clock` | Tested |
| 5.3-TR-06 | `Raw entropy in high-impact path fails X1H` | `test_x1_gates::test_x1h_raw_entropy` | Tested |
| 5.3-TR-07 | `Missing trace_root fails X1I` | `test_x1_gates::test_x1i_*` | Tested |
| 5.3-TR-08 | `Missing tool/model/PTC span fails X1I if material` | `test_anti_bypass::test_material_trace_gap_escalates_high_impact_commit` | `X3B_ESCALATE = "ESCALATE"` ✅ |
| 5.3-TR-09 | `Unconsumed live bell signal escalates before X3 disposition` | `test_x1_gates::test_x1i_live_bell_unconsumed` | Tested |

---

# §5.4 — Write Eligibility X1J + UWG Handoff X3C

## §5.4-X1J — Applicability triggers (spec lines 152–162, 10 triggers)

| ID | Trigger (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.4-X1J-T01 | `StateDiff present` | `eval_x1j` reads `packet.state_diff` | `test_x1_gates::test_x1j_*` (8) | NA when absent: `x1j_na_no_write = "NOT_APPLICABLE"` ✅ |
| 5.4-X1J-T02 | `external action result that must be recorded` | `eval_x1j` reads `write_intent_class` | `test_x1_gates::test_x1j_*` | Tested |
| 5.4-X1J-T03 | `durable memory update` | same | same | Tested via `_COMMIT_OVERRIDES.write_intent_class="memory_promotion"` |
| 5.4-X1J-T04 | `policy update candidate` | same | same | Tested |
| 5.4-X1J-T05 | `registry update candidate` | same | same | Tested |
| 5.4-X1J-T06 | `artifact publication` | same | same | Tested |
| 5.4-X1J-T07 | `cache promotion/invalidation` | same | same | Tested |
| 5.4-X1J-T08 | `retrieval surface refresh request` | same | same | Tested |
| 5.4-X1J-T09 | `customer-impacting change` | same | same | Tested |
| 5.4-X1J-T10 | `learning promotion request through future-run path` | `eval_x1j` blocks L6→current-run mutation | `test_anti_bypass::test_l6_rescue_attempt_detected_blocks_disposition` | Tested ✅ |

## §5.4-X1J-C — X1J Checks (spec lines 164–179, 14 checks)

| ID | Check (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.4-X1J-C01 | `Proposed change is necessary, explicit, and within user/request scope` | `eval_x1j` write_scope check | `test_x1_gates::test_x1j_write_scope_*` | Tested |
| 5.4-X1J-C02 | `write_intent_class declared` | `eval_x1j` WRITE_NOT_AUTHORIZED on missing | `test_x1_gates::test_x1j_write_not_authorized` | Tested |
| 5.4-X1J-C03 | `StateDiff complete and bounded` | `eval_x1j` STATE_DIFF_MISSING / STATE_DIFF_SCHEMA_INVALID | `test_x1_gates::test_x1j_state_diff_*` | Tested |
| 5.4-X1J-C04 | `Diff target surface is known to L4/UWG` | `eval_x1j` target_surface check | `test_uwg::test_*` (24) | Tested |
| 5.4-X1J-C05 | `Diff scope matches capability_token and sandbox_envelope` | `eval_x1j` capability_token.authorizes_write | `test_x1_gates::test_x1j_*` | Tested |
| 5.4-X1J-C06 | `Blast radius classified` | `eval_x1j` BLAST_RADIUS_TOO_BROAD | `test_x1_gates::test_x1j_blast_radius_*` | Tested |
| 5.4-X1J-C07 | `Rollback plan present where required` | `eval_x1j` ROLLBACK_MISSING | `test_rollback::test_*` (14) | Tested |
| 5.4-X1J-C08 | `before_snapshot and after_candidate refs available` | `eval_x1j` checks refs | `test_x1_gates::test_x1j_*` | Tested |
| 5.4-X1J-C09 | `High-impact or irreversible action routed through HITL` | `eval_x1j` HIGH_IMPACT_NEEDS_HITL | `test_anti_bypass::test_case_f_high_impact_write_missing_hitl` | `dispositions_reached.X3B_ESCALATE` ✅ |
| 5.4-X1J-C10 | `X1A-F cleared` | `aggregate_decision` checks | `test_x2_x3_hitl::test_*` | Tested |
| 5.4-X1J-C11 | `X1G cleared when commit path is active` | `aggregate_decision` commit-path check | same | Tested |
| 5.4-X1J-C12 | `X1H/I cleared` | same | same | Tested |
| 5.4-X1J-C13 | `HITL receipt attached where required` | `eval_x1j` checks `hitl_packet` | `test_anti_bypass::test_hitl_modification_requires_reclearance` | Tested |
| 5.4-X1J-C14 | `L5 certification refs attached where required` | `eval_x1j` L5_CERTIFICATION_GAP | `test_x1_gates::test_x1j_l5_*` | Tested |
| 5.4-X1J-C15 | `Next hop is UWG only, not direct L4 write` | `CommitRequest.next_hop = "UWG_ONLY"` | `test_anti_bypass::test_no_direct_l4_write_from_exit` | Tested ✅ |
| 5.4-X1J-FR-01..10 | 10 fail routes: WRITE_SCOPE_AMBIGUOUS / WRITE_NOT_AUTHORIZED / STATE_DIFF_MISSING / STATE_DIFF_SCHEMA_INVALID / ROLLBACK_MISSING / BLAST_RADIUS_TOO_BROAD / HIGH_IMPACT_NEEDS_HITL / L5_CERTIFICATION_GAP / DIRECT_L4_WRITE_ATTEMPT / UWG_HANDOFF_INCOMPLETE | `eval_x1j` reason_codes | `test_x1_gates::test_x1j_*` (8) + `test_anti_bypass` | All triggerable |

## §5.4-SD — StateDiff readiness fields (spec lines 218–232, 15 mandatory fields)

| ID | Field (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.4-SD-01..15 | `state_diff_id, target_surface, operation_type, before_ref, after_candidate_ref, schema_ref, validation_rules_ref, policy_refs, blast_radius, rollback_plan_ref, replay_refs, audit_refs, created_by_surface, mutation_source, deterministic_digest` | `state_diff` dict carried through `ExitReviewPacket.state_diff` field | `test_uwg::test_*` (24) + `test_rollback::test_*` (14) | All 15 carried; commit path emits `X3CommitRequestPacket` ✅ |

## §5.4-OP — Allowed operation types (spec lines 234–245, 11 ops)

| ID | Operation (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.4-OP-01..11 | `append_record / version_insert / alias_swap / cache_invalidate / index_refresh / graph_projection_refresh / registry_update / policy_version_publish / memory_promotion / rollback / tombstone` | `UwgBackends` operation table | `test_uwg::test_*` (24) | All 11 reachable via UWG backend |

## §5.4-RJ — Forbidden operations (spec lines 247–256, 8 reject-criteria)

| ID | Reject criterion (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.4-RJ-01 | `blind overwrite` | rejected by `process_commit_request` | `test_uwg::test_*` | Tested |
| 5.4-RJ-02 | `unversioned mutation` | rejected | same | Tested |
| 5.4-RJ-03 | `direct file write` | rejected; only UWG backend | `test_anti_bypass::test_no_direct_l4_write_from_exit` | Tested ✅ |
| 5.4-RJ-04 | `direct DB update outside UWG transaction` | same | same | Tested |
| 5.4-RJ-05 | `policy alias swap without audit plan` | rejected | `test_uwg::test_*` | Tested |
| 5.4-RJ-06 | `memory promotion from raw telemetry` | rejected | same | Tested |
| 5.4-RJ-07 | `cache promotion without evidence lineage` | rejected | same | Tested |
| 5.4-RJ-08 | `graph projection refresh without source snapshot ref` | rejected | same | Tested |

## §5.4-CR — CommitRequest contract (spec lines 258–328, 9 sub-blocks × ~5 fields = 45 fields)

| ID | Sub-block | Implementation (`v6/types.py:175-202` `X3CommitRequestPacket`) | Test | Runtime evidence |
|---|---|---|---|---|
| 5.4-CR-01 | `commit_request_id` | deterministic SHA (`x3_dispositions.py:27-30`) | `test_uwg::test_commit_request_id_deterministic` | Tested |
| 5.4-CR-02 | `source.{exit_review_packet_id, x3_disposition_candidate=X3C_COMMIT_REQUEST, sealed_l2_artifact_ref, l3_workflow_package_ref, ret_packet_ref, hitl_review_packet_ref}` | `X3CommitRequestPacket.source` dict | `test_uwg` + `test_anti_bypass::test_case_e_high_impact_write_clear_path` | `dispositions_reached.X3C_COMMIT = "COMMIT_REQUEST"` ✅ |
| 5.4-CR-03 | `route.{route_contract_ref, route_id, route_digest, execution_form, support_target, freshness_class}` | carried | `test_uwg` | Carried |
| 5.4-CR-04 | `governance.{policy_hash, blueprint_hash, compliance_hash, manifest_hash, hmac_sig, capability_token_ref, sandbox_envelope_ref, l5_certification_refs, hitl_reclearance_refs}` | 9-field dict | `test_uwg::test_*` | All present |
| 5.4-CR-05 | `gate_bundle.{x1_gate_result_refs, x2_aggregate_decision_ref, failed_gate_ids, warnings, pass_power_receipt_ref, replay_integrity_result_ref, observability_result_ref, write_eligibility_result_ref}` | dict from `aggregate_decision` | `test_uwg` | Carried |
| 5.4-CR-06 | `mutation.{state_diff_ref, write_intent_class, target_state_surfaces, operation_type, blast_radius, rollback_plan_ref, before_snapshot_ref, after_candidate_ref}` | from `packet.state_diff` | `test_uwg` + `test_rollback` | Carried |
| 5.4-CR-07 | `evidence.{evidence_contract_ref, citation_map_refs, support_score, source_lineage_refs, contradiction_flags}` | from packet | `test_uwg` | Carried |
| 5.4-CR-08 | `replay.{replay_key, snapshot_manifest_ref, input_hash, prompt_hash, route_digest, evidence_contract_hash, sealed_artifact_hash, exit_packet_hash}` | from packet | `test_uwg` | Carried |
| 5.4-CR-09 | `observability.{trace_root, span_refs, artifact_refs, anomaly_flags}` | from packet | `test_uwg` | Carried |
| 5.4-CR-10 | `handoff.{next_hop=UWG_ONLY, direct_l4_write_assertion=NO_DIRECT_WRITE, created_at, created_by_surface=EXIT_X3C, deterministic_digest}` | hard-coded constants | `test_anti_bypass::test_no_direct_l4_write_from_exit` | `next_hop = "UWG_ONLY"` enforced ✅ |

## §5.4-X3C — X3C emission rules (spec lines 330–351, 9 emit + 9 do-not-emit)

| ID | Rule | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.4-X3C-E01..09 | `Emit X3C ONLY when: mutation requested+authorized, X1A-F clear, X1G clear if commit, X1H clear, X1I clear/policy-WARN, X1J clear, HITL completed if required, CommitRequest complete, next_hop=UWG_ONLY` | `aggregate_decision` X3C branch (`x2_matrix.py:193-216`) | `test_x2_x3_hitl::test_x3c_emission_*` + `test_anti_bypass::test_case_e` | `dispositions_reached.X3C_COMMIT = "COMMIT_REQUEST"` ✅ |
| 5.4-X3C-D01..09 | `Do NOT emit X3C when: StateDiff incomplete / target unknown / commit-path-reliability unknown on high-impact / replay non-certifiable / trace gap blocks forensic / direct write already / L5 cert missing / HITL required missing / rollback required missing` | same — escalates to X3A or X3B | `test_x2_x3_hitl` (21) + `test_anti_bypass::test_case_f` | X3B on missing-HITL ✅ |

## §5.4-UR — UWG response handling (spec lines 353–371, 4 receipts + 3 disposition rules)

| ID | Receipt / rule (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.4-UR-01 | `UWGCommitReceipt — Exit may reference committed artifact only after this exists` | `UwgOutcome.COMMIT_ACCEPTED` + `validate_return_payload::FINAL_RESPONSE_REFERENCES_UNCOMMITTED_ARTIFACT` | `test_v6_exhaustive_edges::test_uwg_outcome_commit_accepted_via_default_backends` + `test_anti_bypass::test_no_uncommitted_artifact_reference` | `UwgOutcome.COMMIT_ACCEPTED` reachable ✅ |
| 5.4-UR-02 | `UWGBlockedCommitReceipt — Return safe message or X3A/X3B` | `UwgOutcome.COMMIT_REJECTED` → X3A return-payload | `test_uwg::test_block_*` + `test_return_payload::test_x3a_deny_payload_*` | Tested |
| 5.4-UR-03 | `UWGHeldCommitReceipt — Return pending/review-safe response if policy allows` | `UwgOutcome.COMMIT_HELD` → X3C `held` return | `test_uwg::test_hold_*` + `test_return_payload::test_x3c_commit_request_payload_held` | Tested |
| 5.4-UR-04 | `UWGRollbackReceipt — do not claim mutation` | `UwgOutcome` + rollback path | `test_rollback::test_*` (14) | Tested |

## §5.4-OT — OTEL spans (4 spans)

| ID | Span | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.4-OT-01..04 | `exit.x1j.write_eligibility_check / exit.x3c.commit_request_build / exit.x3c.uwg_handoff_emit / exit.uwg_response.receive` | `SPAN_X1J_WRITE_ELIGIBILITY / SPAN_X3C_COMMIT_REQUEST_BUILD / SPAN_X3C_UWG_HANDOFF_EMIT / SPAN_UWG_RESPONSE_RECEIVE` | `test_otel_emission::test_pipeline_emits_uwg_handoff_spans_on_commit_path` | All 4 emitted on commit path ✅ |

## §5.4-TR — Test requirements (spec lines 380–389, 8 tests)

| ID | Test req | Test | Runtime evidence |
|---|---|---|---|
| 5.4-TR-01 | `Exit never writes directly to L4` | `test_anti_bypass::test_no_direct_l4_write_from_exit` | 0 forbidden imports; only UWG backend writes ✅ |
| 5.4-TR-02 | `StateDiff without before_ref fails X1J` | `test_x1_gates::test_x1j_state_diff_*` | Tested |
| 5.4-TR-03 | `Missing rollback plan fails when rollback required` | `test_rollback::test_*` (14) | Tested |
| 5.4-TR-04 | `High-impact mutation without HITL fails X1J` | `test_anti_bypass::test_case_f_high_impact_write_missing_hitl` | `X3B_ESCALATE = "ESCALATE"` ✅ |
| 5.4-TR-05 | `Missing L5 cert ref fails when policy requires it` | `test_x1_gates::test_x1j_l5_*` | Tested |
| 5.4-TR-06 | `X3C cannot emit with X1G UNKNOWN on high-impact commit` | `aggregate_decision` material_unknown filter | `test_x1_gates::test_x1g_*` + `test_anti_bypass` | Tested |
| 5.4-TR-07 | `X3C CommitRequest next_hop must equal UWG_ONLY` | hard-coded constant in `X3CommitRequestPacket` | `test_anti_bypass::test_no_direct_l4_write_from_exit` | Tested ✅ |
| 5.4-TR-08 | `Final response cannot reference committed artifact before UWG receipt` | `validate_return_payload::FINAL_RESPONSE_REFERENCES_UNCOMMITTED_ARTIFACT` | `test_anti_bypass::test_no_uncommitted_artifact_reference` | Failure code triggers ✅ |

---

# §5.5 — X2 Aggregation & X3 Disposition

## §5.5-X2I — X2 Aggregate Inputs (spec lines 144–153, 11 inputs)

| ID | Input (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.5-X2I-01 | `ExitReviewPacket` | `aggregate_decision(verdicts, packet)` (`v6/x2_matrix.py:151`) | `test_x2_x3_hitl::test_*` (21) | Function called per X3D run |
| 5.5-X2I-02 | `X1A-X1F results` | `verdicts: list[GateVerdict]` for X1A..X1F | same | Carried |
| 5.5-X2I-03 | `X1G-X1I results` | `verdicts` X1G..X1I | same | Carried |
| 5.5-X2I-04 | `X1J result if write path active` | conditional X1J in `verdicts` | `test_x1_gates::test_x1j_*` | Conditional |
| 5.5-X2I-05 | `HITL receipt if present` | `packet.hitl_packet` field | `test_anti_bypass::test_hitl_modification_requires_reclearance` | Carried |
| 5.5-X2I-06 | `L5 certification refs if required` | `packet.governance.l5_certification_refs` | `test_x1_gates::test_x1j_l5_*` | Carried |
| 5.5-X2I-07 | `live bell signal status` | `packet.bus_d_signals/bus_e_signals` | `test_x1_gates::test_x1i_*` | Carried |
| 5.5-X2I-08 | `policy threshold profile` | `grader_composition.threshold_profile` | `test_x1_gates::test_x1a_*` | Carried |
| 5.5-X2I-09 | `route risk class` | `route_contract` fields | `test_x1_gates` | Carried |
| 5.5-X2I-10 | `track label` | `track_label` field | `test_v6_exhaustive_edges::test_x1a_track_label_*` | Tested |
| 5.5-X2I-11 | `materiality classification` | `aggregate_decision` materiality logic | `test_x2_x3_hitl::test_*` | Wired |

## §5.5-HF — Hard Fail Conditions (spec lines 155–166, 11 conditions)

| ID | Condition (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.5-HF-01 | `Any safety breach` | `_HARD_FAIL_CODES` includes SANDBOX_BREACH/HIDDEN_EGRESS | `test_v6_exhaustive_edges::test_x1c_*` | All routed to X3A |
| 5.5-HF-02 | `Any unauthorized mutation` | UNAUTHORIZED_MUTATION/DIRECT_L4_WRITE_ATTEMPT in hard fail | `test_anti_bypass::test_l2_write_attempt_detected_routes_to_x3a` | `dispositions_reached.X3A_DENY = "DENY"` ✅ |
| 5.5-HF-03 | `Any policy hash mismatch` | POLICY_HASH_MISMATCH in hard fail | `test_v6_exhaustive_edges::test_x1a_policy_hash_mismatch_isolated` | ✅ |
| 5.5-HF-04 | `Any system prompt leak` | SYSTEM_PROMPT_LEAK in hard fail | `test_return_payload::test_system_prompt_leak_in_return` | ✅ |
| 5.5-HF-05 | `Any known prompt injection not neutralized` | PROMPT_INJECTION_DETECTED → X3A | `test_anti_bypass::test_retrieved_content_not_instruction` | `x1f_injection_detected = True` ✅ |
| 5.5-HF-06 | `Any direct L4 write attempt outside UWG` | DIRECT_L4_WRITE_ATTEMPT → X3A | `test_anti_bypass::test_no_direct_l4_write_from_exit` | ✅ |
| 5.5-HF-07 | `Any material unsupported claim in grounded answer` | UNGROUNDED material → X3A/X3B | `test_anti_bypass::test_case_c_grounded_answer_unsupported_claim` | Tested |
| 5.5-HF-08 | `Any non-replayable high-impact action` | NON_REPLAYABLE on commit → hard fail | `test_x1_gates::test_x1h_*` + `test_anti_bypass` | Tested |
| 5.5-HF-09 | `Any untranscripted PTC IO in commit/high-impact` | PTC_IO_UNTRANSCRIPTED in hard fail (commit) | `test_x1_gates::test_x1h_*` | Tested |
| 5.5-HF-10 | `Any committed artifact reference without UWG receipt` | FINAL_RESPONSE_REFERENCES_UNCOMMITTED_ARTIFACT | `test_anti_bypass::test_no_uncommitted_artifact_reference` | ✅ |
| 5.5-HF-11 | `Any human modification not re-cleared` | HITL re-clear gate | `test_anti_bypass::test_hitl_modification_requires_reclearance` | ✅ |

## §5.5-EC — Escalation Conditions (spec lines 168–179, 11 conditions)

| ID | Condition (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.5-EC-01 | `Human-required by policy` | `aggregate_decision` HUMAN_REQUIRED → X3B | `test_x2_x3_hitl::test_*` | Tested |
| 5.5-EC-02 | `High-impact or irreversible action` | HIGH_IMPACT_NEEDS_HITL → X3B | `test_anti_bypass::test_case_f_high_impact_write_missing_hitl` | `X3B_ESCALATE = "ESCALATE"` ✅ |
| 5.5-EC-03 | `Low confidence on material issue` | confidence-band → X3B | `test_x2_x3_hitl::test_*` | Tested |
| 5.5-EC-04 | `Judge abstained on material quality/safety` | JUDGE_ABSTAINED + material → X3B | `test_x1_gates::test_x1d_judge_abstained_returns_unknown` + `test_x2_x3_hitl` | ✅ |
| 5.5-EC-05 | `Evidence conflicted and user impact material` | CONFLICT_NOT_HANDLED + material → X3B | `test_x1_gates::test_x1d_*` | Tested |
| 5.5-EC-06 | `Consistency failed or unknown for commit path` | X1G FAIL/UNKNOWN on commit → X3B | `test_x1_gates::test_x1g_*` | Tested |
| 5.5-EC-07 | `Trace gap blocks forensic review` | X1I material gap → X3B | `test_anti_bypass::test_case_j_observability_material_gap_high_impact` | ✅ |
| 5.5-EC-08 | `Human modification proposed` | HITL MODIFY_DIFF → X3B until re-clear | `test_anti_bypass::test_hitl_modification_requires_reclearance` | ✅ |
| 5.5-EC-09 | `Rollback missing but recoverable` | ROLLBACK_MISSING + recoverable → X3B | `test_rollback::test_*` | Tested |
| 5.5-EC-10 | `Write scope ambiguous but resolvable` | WRITE_SCOPE_AMBIGUOUS → X3B | `test_x1_gates::test_x1j_*` | Tested |
| 5.5-EC-11 | `Live bell anomaly indicates suspicious behavior` | bus_d/e anomaly → X3B | `test_x1_gates::test_x1i_*` | Tested |

## §5.5-AC — Allow Conditions (spec lines 181–187, 6 conditions)

| ID | Condition (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.5-AC-01 | `Answer-only, no durable mutation` | non-commit branch → X3D | `test_anti_bypass::test_case_a_low_risk_answer_only_success` | `X3D_ALLOW = "ALLOW"` ✅ |
| 5.5-AC-02 | `X1A-F clear` | all PASS verdicts | same | Tested |
| 5.5-AC-03 | `X1H/I clear or policy permits non-material WARN` | materiality matrix | `test_anti_bypass::test_case_a_*` | Tested |
| 5.5-AC-04 | `Evidence support adequate or caveated/abstained properly` | X1D PASS or NA | `test_anti_bypass::test_case_b_grounded_answer_weak_support_caveated` | Tested |
| 5.5-AC-05 | `Output schema satisfied` | X1B PASS | `test_v6_exhaustive_edges::test_x1b_pass_when_clean` | Tested |
| 5.5-AC-06 | `No unresolved material safety/policy/authority UNKNOWN` | material_unknown filter (`x2_matrix.py:151-169`) | `test_x2_x3_hitl::test_material_unknown_*` | Tested |

## §5.5-CC — Commit Conditions (spec lines 189–197, 9 conditions)

| ID | Condition (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.5-CC-01..09 | `Mutation requested+authorized / X1A-F clear / X1G clear / X1H/I clear / X1J clear / HITL completed if required / L5 cert attached if required / CommitRequest complete / Next hop is UWG only` | `aggregate_decision` commit branch (`x2_matrix.py:193-216`) | `test_anti_bypass::test_case_e_high_impact_write_clear_path` + `test_uwg::test_*` (24) | `X3C_COMMIT = "COMMIT_REQUEST"` ✅ |

## §5.5-SA — Safe Abstain Conditions (spec lines 199–206, 6 conditions)

| ID | Condition (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.5-SA-01..06 | `Missing critical user detail / Evidence EMPTY/BLOCKED / Weak support where caveat would mislead / Unsupported high-impact advice / Action scope ambiguous / Unsafe or impossible action can be safely explained` | `aggregate_decision` X3E branch | `test_v6_hardening_edges::test_pipeline_reaches_x3e_safe_abstain` | X3E reachable on grounded judge_abstained ✅ |

## §5.5-DE — X3 Disposition Enum (spec lines 208–227, 5 dispositions)

| ID | Disposition (spec verbatim) | Implementation (`v6/types.py:36-46`) | Test | Runtime evidence |
|---|---|---|---|---|
| 5.5-DE-01 | `X3A_DENY_REROUTE — sealed work cannot safely leave; no durable write; no hidden retry; may include safe partial` | `V6Disposition.DENY = "X3A"` + `build_x3a_deny` | `test_v6_hardening_edges::test_pipeline_reaches_x3a_deny` | `dispositions_reached.X3A_DENY = "DENY"` ✅ |
| 5.5-DE-02 | `X3B_ESCALATE_HITL — needs human review; freeze; bounded review packet; L5 re-clearance` | `V6Disposition.ESCALATE = "X3B"` + `build_x3b_escalate` | `test_v6_hardening_edges::test_pipeline_reaches_x3b_escalate` | `dispositions_reached.X3B_ESCALATE = "ESCALATE"` ✅ |
| 5.5-DE-03 | `X3C_COMMIT_REQUEST_TO_UWG — commit not yet done; UWG decides; next_hop=UWG_ONLY` | `V6Disposition.COMMIT_REQUEST = "X3C"` + `build_x3c_commit_request` | `test_v6_hardening_edges::test_pipeline_reaches_x3c_commit_request` | `dispositions_reached.X3C_COMMIT = "COMMIT_REQUEST"` ✅ |
| 5.5-DE-04 | `X3D_ALLOW_FINISH — safe final answer; no durable write; may reference committed artifact only after UWG receipt` | `V6Disposition.ALLOW = "X3D"` + `build_x3d_allow` | `test_v6_hardening_edges::test_pipeline_reaches_x3d_allow` | `dispositions_reached.X3D_ALLOW = "ALLOW"` ✅ |
| 5.5-DE-05 | `X3E_SAFE_ABSTAIN_CLARIFY — abstain/clarify/explain bounded inability; no durable write` | `V6Disposition.SAFE_ABSTAIN = "X3E"` + `build_x3e_safe_abstain` | `test_v6_hardening_edges::test_pipeline_reaches_x3e_safe_abstain` | `pipeline_reaches_x3e` test asserts X3E or X3B reachable ✅ |

## §5.5-SO — Disposition Selection Order (spec lines 229–243, 6-step rule)

| ID | Selection rule (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.5-SO-01 | `If hard fail -> X3A unless human review required and recovery plausible -> X3B` | `aggregate_decision` step 1 | `test_x2_x3_hitl::test_hard_fail_routes_to_x3a` | Tested |
| 5.5-SO-02 | `If human-required or material UNKNOWN -> X3B unless safe abstain is policy-mandated outcome` | step 2 | `test_x2_x3_hitl::test_material_unknown_*` | Tested |
| 5.5-SO-03 | `If write path active and all commit preconditions pass -> X3C` | step 3 | `test_x2_x3_hitl::test_x3c_commit_*` | Tested |
| 5.5-SO-04 | `If answer-only and allow preconditions pass -> X3D` | step 4 | `test_anti_bypass::test_case_a_low_risk_answer_only_success` | ✅ |
| 5.5-SO-05 | `If safe abstain/clarify is the proper supported outcome -> X3E` | step 5 | `test_v6_hardening_edges::test_pipeline_reaches_x3e_safe_abstain` | ✅ |
| 5.5-SO-06 | `If no branch is safe -> X3A safe stop` | step 6 (default) | `test_v6_hardening_edges::test_pipeline_with_empty_receipts_fails_fast_not_silently` | `empty_receipts_disposition = "DENY"` ✅ |
| 5.5-SO-DN-01 | `Do not emit multiple X3 dispositions` | `aggregate_decision` returns one `V6Disposition` | `test_anti_bypass::test_exactly_one_disposition` | ✅ |
| 5.5-SO-DN-02 | `Do not silently fallback` | hard fail explicit code | `test_anti_bypass::test_no_silent_fallback_emits_trajectory_fail` | ✅ |
| 5.5-SO-DN-03 | `Do not mix allow + commit without explicit UWG receipt` | mutually exclusive enum | `test_anti_bypass::test_no_uncommitted_artifact_reference` | ✅ |
| 5.5-SO-DN-04 | `Do not skip X1 result materiality` | material_unknown filter | `test_x2_x3_hitl` | Tested |
| 5.5-SO-DN-05 | `Do not route around HITL/L5/UWG` | enum-only routing; no bypass | `test_anti_bypass::test_l6_rescue_attempt_detected_blocks_disposition` | ✅ |

## §5.5-DC — Disposition contracts (spec lines 245–326, 5 receipt dataclasses × ~10 fields each)

| ID | Receipt (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.5-DC-X3A | `X3ADenyRerouteReceipt: 12 fields (disposition / reason_codes / failed_gate_ids / hard_fail / reroute_allowed / reentry_target / user_safe_message_ref / safe_partial_artifact_ref / replan_hint_ref / l6_failure_packet_ref / trace_root / replay_key / deterministic_digest)` + 6 sub-dispositions (DENY_STOP / DENY_SAFE_PARTIAL / REROUTE_TO_L1/L0/C0/L2_REPAIR) | `X3DenyPacket` (`v6/types.py`) | `test_x2_x3_hitl::test_x3a_*` + `test_return_payload::test_x3a_deny_payload_*` | All fields carried; sub_disposition arg accepted ✅ |
| 5.5-DC-X3B | `X3BEscalationReceipt: 9 fields (disposition / trigger_reason_codes / material_unknowns / freeze_required=true / hitl_review_packet_required=true / l5_reclearance_required=true / write_auth=NONE / trace_root / replay_key / deterministic_digest)` | `X3EscalatePacket` | `test_return_payload::test_x3b_escalate_payload_pending_review` | Tested ✅ |
| 5.5-DC-X3C | `X3CCommitDispositionReceipt: 8 fields (disposition / commit_request_id / uwg_next_hop=true / commit_not_yet_done=true / required_preconditions_refs / trace_root / replay_key / deterministic_digest)` | `X3CommitRequestPacket` | `test_uwg::test_*` (24) | Tested ✅ |
| 5.5-DC-X3D | `X3DAllowFinishReceipt: 8 fields (disposition / final_response_ref / schema_status / evidence_status / commit_receipt_id optional / runtime_exhaust_manifest_ref / trace_root / replay_key / deterministic_digest)` | `X3AllowPacket` | `test_v6_exhaustive_edges` + `test_return_payload::test_x3d_allow_payload_basic_shape` | Tested ✅ |
| 5.5-DC-X3E | `X3ESafeAbstainReceipt: 9 fields (disposition / abstain_reason / clarification_question optional / safe_alternative_ref optional / bounded_explanation_ref / failed_support_target optional / no_commit_request=true / trace_root / replay_key / deterministic_digest)` | `X3SafeAbstainPacket` | `test_return_payload::test_x3e_safe_abstain_payload_no_commit_request` | Tested ✅ |

## §5.5-OT — OTEL spans (7 spans)

| ID | Span | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.5-OT-01..07 | `exit.x2.aggregate_decision / exit.x3.disposition_select / exit.x3a.deny_reroute_emit / exit.x3b.escalate_emit / exit.x3c.commit_request_disposition_emit / exit.x3d.allow_finish_emit / exit.x3e.safe_abstain_emit` | `SPAN_X2_AGGREGATE / SPAN_X3_SELECT / SPAN_X3A_DENY_EMIT / SPAN_X3B_ESCALATE_EMIT / SPAN_X3C_COMMIT_REQUEST_EMIT / SPAN_X3D_ALLOW_EMIT / SPAN_X3E_ABSTAIN_EMIT` | `test_otel_emission` + `test_v6_hardening_edges::test_every_catalog_span_reachable_via_union_of_runtime_paths` | All 7 in catalog; each emitted on its disposition path ✅ |

## §5.5-TR — Test requirements (spec lines 338–347, 8 tests)

| ID | Test req | Test | Runtime evidence |
|---|---|---|---|
| 5.5-TR-01 | `Exactly one X3 disposition emitted` | `test_anti_bypass::test_exactly_one_disposition` | One per pipeline.run ✅ |
| 5.5-TR-02 | `Hard safety failure cannot produce X3D` | `test_anti_bypass::test_l2_write_attempt_detected_routes_to_x3a` | `X3A_DENY = "DENY"` ✅ |
| 5.5-TR-03 | `Direct L4 write attempt produces X3A` | `test_anti_bypass::test_no_direct_l4_write_from_exit` | ✅ |
| 5.5-TR-04 | `Material UNKNOWN produces X3B unless policy requires X3E` | `test_x2_x3_hitl::test_material_unknown_*` | Tested |
| 5.5-TR-05 | `Valid commit path produces X3C, not direct commit` | `test_v6_hardening_edges::test_pipeline_reaches_x3c_commit_request` | `X3C_COMMIT = "COMMIT_REQUEST"` ✅ |
| 5.5-TR-06 | `Weak evidence cannot produce uncaveated X3D` | `test_anti_bypass::test_case_b_grounded_answer_weak_support_caveated` | Tested |
| 5.5-TR-07 | `Safe abstain produces X3E and no commit request` | `test_return_payload::test_x3e_safe_abstain_payload_no_commit_request` | Tested |
| 5.5-TR-08 | `X3D cannot reference uncommitted artifact` | `test_anti_bypass::test_no_uncommitted_artifact_reference` | ✅ |

---

# §5.6 — HITL Freeze / Review / Reclearance

## §5.6-HL — Hard Law (spec lines 134–141, 7 invariants)

| ID | Invariant (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.6-HL-01 | `Human input is data, not sovereign authority` | `HumanReviewPacket.prohibited_actions` includes AUTHORITY_CLAIM_ON_RETRIEVED_TEXT | `test_hitl_contracts::test_l5_reclearance_request_carries_authority_label_manifest` | `data_not_authority_assertion = True` on `HumanDecisionReceipt` ✅ |
| 5.6-HL-02 | `Human review cannot write to L4` | freeze_receipt suspends capability | `test_hitl_contracts::test_freeze_receipt_*` | Tested |
| 5.6-HL-03 | `Human review cannot bypass L5` | `_RECLEAR_GATES` map enforces re-clearance | `test_anti_bypass::test_hitl_modification_requires_reclearance` | ✅ |
| 5.6-HL-04 | `Human review cannot widen scope without re-entry` | `scope_delta_report` field on L5ReclearanceRequest | `test_hitl_contracts::test_l5_reclearance_request_*` | Carried |
| 5.6-HL-05 | `Human modifications must be re-cleared before they affect final disposition` | MODIFY_DIFF → re-runs 8 gates | `test_anti_bypass::test_hitl_modification_with_l5_cleared_passes_preflight` | ✅ |
| 5.6-HL-06 | `No durable write while packet is frozen` | `additional_retrieval = "BLOCKED_..."` + freeze suspends caps | `test_hitl_contracts::test_freeze_receipt_*` | Tested |
| 5.6-HL-07 | `No additional retrieval unless REQUEST_MORE_EVIDENCE selected and bounded C0 re-entry` | `_RECLEAR_GATES[REQUEST_MORE_EVIDENCE]=(X1D,)` only | `test_hitl_contracts::test_l5_reclearance_request_*` | Tested |

## §5.6-H1 — Freeze (spec lines 143–164, 9 freeze actions + FreezeReceipt 13 fields)

| ID | Freeze action / field (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.6-H1-A01 | `auth_state = FROZEN` | `FreezeReceipt.suspended_capability_refs` set | `test_hitl_contracts::test_freeze_receipt_*` | Tested |
| 5.6-H1-A02 | `write_auth = NONE` | freeze sets capability to none | same | Tested |
| 5.6-H1-A03 | `capability_token suspended or narrowed to review-only` | `suspended_capability_refs[]` field | same | Carried |
| 5.6-H1-A04 | `pending diffs locked` | `pending_state_diff_refs[]` field | same | Carried |
| 5.6-H1-A05 | `provider egress paused` | freeze invariant in pipeline | `test_anti_bypass::test_hitl_modification_*` | Tested |
| 5.6-H1-A06 | `external action paused` | same | same | Tested |
| 5.6-H1-A07 | `mutation proposals made immutable` | proposal-only state_diff invariant | `test_anti_bypass::test_no_direct_l4_write_from_exit` | ✅ |
| 5.6-H1-A08 | `review packet snapshot fixed` | `freeze_digest` field locks state | `test_v6_hardening_edges::test_hitl_contract_digests_stable_for_identical_inputs` | `freeze_digest` stable for identical inputs ✅ |
| 5.6-H1-A09 | `trace/span records marked under_review` | OTEL spans tagged | `test_otel_emission::test_pipeline_emits_*` (HITL spans) | Tested |
| 5.6-H1-F01..13 | `FreezeReceipt: 13 fields (freeze_id / exit_review_packet_id / request_id / run_id / trace_root / reason_codes / frozen_artifact_refs / pending_state_diff_refs / suspended_capability_refs / policy_hash / blueprint_hash / replay_key / freeze_digest)` | `FreezeReceipt` dataclass (`v6/hitl.py:215-230`) | `test_hitl_contracts::test_freeze_receipt_*` (3) | All 13 fields populated; `freeze_digest_first16` carried ✅ |

## §5.6-H2 — Review Packet (spec lines 166–212, 22 must-include + 6 must-not + HumanReviewPacket 14 fields)

| ID | Field (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.6-H2-MI-01..22 | `Must include: reason for escalation, user/request summary, route_contract, policy_hash, blueprint_hash, sealed L2/L3/RET artifact, proposed action/diff, write_intent_class+blast_radius, rollback plan, grader composition, per-dimension scores+thresholds, abstain/UNKNOWN, trajectory snapshot, citation map, replay key+receipts, pass^k evidence, trace coverage, anomaly flags, L5 cert gaps, sensitive data minimized+labeled, allowed human decision enum` | `HumanReviewPacket` 14 fields cover all 22 logical items | `test_hitl_contracts::test_human_review_packet_*` (3) | All carried; `review_packet_hash_first16` set ✅ |
| 5.6-H2-MN-01 | `Must not include: hidden system/developer prompts unless authorized` | `prohibited_actions[]` includes BYPASS_L5 | `test_hitl_contracts::test_human_review_packet_prohibits_*` | Tested |
| 5.6-H2-MN-02..06 | `Must not include: unnecessary secrets, raw retrieved content beyond support, broad unrelated data, mutation authority, credential material` | `sensitive_data_manifest` minimizes + `prohibited_actions[]` enforces | same | Tested |
| 5.6-H2-F01..14 | `HumanReviewPacket: 14 fields (review_packet_id / freeze_id / escalation_reason_codes / human_decision_options / minimal_context_refs / evidence_map_refs / proposed_diff_refs / policy_threshold_refs / replay_refs / trace_refs / sensitive_data_manifest / allowed_actions / prohibited_actions=7 invariants / packet_hash)` | `HumanReviewPacket` dataclass | `test_hitl_contracts::test_human_review_packet_*` | `prohibited_actions` = 7 spec invariants ✅ |

## §5.6-H3 — Human Review (spec lines 214–248, 8 may + 8 may-not + HumanDecisionReceipt 10 fields)

| ID | Action | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.6-H3-MAY-01..08 | `Human may: inspect / approve subject to re-clear / reject / modify / request more evidence / request replay / request schema repair / return to L1` | 7 verdicts in `HITLVerdict` enum | `test_x2_x3_hitl::test_*` (21) + `test_hitl_contracts` | All 7 verdicts mapped |
| 5.6-H3-NOT-01..08 | `Human may NOT: write L4 / override policy / widen scope / approve hidden side effect / turn untrusted content into authority / bypass L5 / force unsupported claims / clear direct write attempts` | `prohibited_actions[]` (7 invariants) + L5 re-clear gate | `test_anti_bypass::test_hitl_modification_requires_reclearance` | ✅ |
| 5.6-H3-F01..10 | `HumanDecisionReceipt: 10 fields (human_decision_id / review_packet_id / reviewer_id_ref / decision / rationale_ref / modification_diff_ref optional / requested_reentry_target optional / timestamp / data_not_authority_assertion=true / digest)` | `HumanDecisionReceipt` dataclass | `test_hitl_contracts::test_human_decision_receipt_*` (2) | `decision_receipt_digest_first16` set; `data_not_authority_assertion=True` ✅ |

## §5.6-H4 — Decision Routing (spec lines 250–290, 7 verdicts × ~5 actions each)

| ID | Verdict (spec verbatim) | Re-runs (`_RECLEAR_GATES`) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|---|
| 5.6-H4-V01 | `APPROVE` | re-run X1A, X1C, X1F (+ X1D if answer changed, X1E if process changed, X1G/X1J if commit) | `_RECLEAR_GATES[APPROVE] = (X1A, X1C, X1F)` | `test_x2_x3_hitl::test_hitl_approve_reclears` | Tested |
| 5.6-H4-V02 | `MODIFY_DIFF` | re-run all 8 gates: X1A,B,C,D,E,F,G,J | `_RECLEAR_GATES[MODIFY_DIFF]=(X1A,X1B,X1C,X1D,X1E,X1F,X1G,X1J)` | `test_anti_bypass::test_hitl_modification_requires_reclearance` | ✅ |
| 5.6-H4-V03 | `REJECT` | () — proceed to X3A or RETURN_TO_L1 | `_RECLEAR_GATES[REJECT]=()` | `test_x2_x3_hitl::test_hitl_reject` | Tested |
| 5.6-H4-V04 | `RETURN_TO_L1` | () + reroute_target=L1 | same | `test_x2_x3_hitl::test_hitl_return_to_l1` | Tested |
| 5.6-H4-V05 | `REQUEST_MORE_EVIDENCE` | (X1D,) + bounded C0 re-entry | `_RECLEAR_GATES[REQUEST_MORE_EVIDENCE]=(X1D,)` | `test_hitl_contracts::test_l5_reclearance_request_*` | Tested |
| 5.6-H4-V06 | `REQUEST_REPLAY` | (X1H, X1I) | `_RECLEAR_GATES[REQUEST_REPLAY]=(X1H,X1I)` | `test_x2_x3_hitl::test_*` | Tested |
| 5.6-H4-V07 | `REQUEST_SCHEMA_REPAIR` | (X1B, X1C, X1H) | `_RECLEAR_GATES[REQUEST_SCHEMA_REPAIR]=(X1B,X1C,X1H)` | `test_x2_x3_hitl::test_*` | Tested |

## §5.6-RC — L5ReclearanceRequest contract (spec lines 292–308, 13 fields)

| ID | Field (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.6-RC-F01..13 | `reclearance_request_id / human_decision_receipt_ref / modified_packet_ref optional / modified_diff_ref optional / original_exit_review_packet_ref / policy_hash / blueprint_hash / replay_key / authority_label_manifest{human_review_data='data_not_authority'} / origin_trust_manifest / scope_delta_report / required_rechecks / digest` | `L5ReclearanceRequest` dataclass (`v6/hitl.py:274-290`) | `test_hitl_contracts::test_l5_reclearance_request_*` (2) | `reclearance_digest_first16` set; `authority_label_manifest['human_review_data']='data_not_authority'` ✅ |

## §5.6-FM — Failure Modes (spec lines 310–319, 10 modes)

| ID | Mode (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.6-FM-01 | `HUMAN_REVIEW_PACKET_OVERBROAD` | review packet `sensitive_data_manifest` + `prohibited_actions` | `test_hitl_contracts::test_human_review_packet_*` | Tested |
| 5.6-FM-02 | `FREEZE_FAILED` | FreezeReceipt construction validation | `test_hitl_contracts::test_freeze_receipt_*` | Tested |
| 5.6-FM-03 | `HUMAN_MODIFICATION_WITHOUT_DIFF` | MODIFY_DIFF requires `modification_diff_ref` | `test_anti_bypass::test_hitl_modification_requires_reclearance` | ✅ |
| 5.6-FM-04 | `HUMAN_APPROVAL_TREATED_AS_AUTHORITY` | `data_not_authority_assertion=True` mandatory | `test_hitl_contracts::test_l5_reclearance_request_carries_authority_label_manifest` | ✅ |
| 5.6-FM-05 | `RECLEARANCE_MISSING` | `_RECLEAR_GATES` enforces re-run + L5 cleared check | `test_preflight::test_hitl_recleared_requires_l5_cleared_true` | Tested |
| 5.6-FM-06 | `SCOPE_WIDENED_WITHOUT_REENTRY` | `scope_delta_report` field | `test_hitl_contracts::test_l5_reclearance_request_*` | Carried |
| 5.6-FM-07 | `DURABLE_WRITE_DURING_REVIEW` | freeze suspends capability + X1J L4-write detection | `test_anti_bypass::test_l2_write_attempt_detected_routes_to_x3a` | ✅ |
| 5.6-FM-08 | `SECRET_EXPOSED_TO_REVIEW_PACKET` | `sensitive_data_manifest` minimization | `test_hitl_contracts::test_human_review_packet_minimizes_sensitive` | Tested |
| 5.6-FM-09 | `REQUEST_MORE_EVIDENCE_UNBOUNDED` | C0 re-entry bounded; `additional_retrieval = "BLOCKED_UNLESS_REQUEST_MORE_EVIDENCE"` | `test_hitl_contracts::test_l5_reclearance_request_*` | Tested |
| 5.6-FM-10 | `HUMAN_REVIEW_TRACE_MISSING` | 6 HITL OTEL spans + `trace_refs` field | `test_otel_emission::test_*` | Tested |

## §5.6-OT — OTEL spans (6 spans)

| ID | Span | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.6-OT-01..06 | `exit.hitl.freeze / exit.hitl.review_packet_materialize / exit.hitl.decision_receive / exit.hitl.modification_diff_capture / exit.hitl.l5_reclearance_request / exit.hitl.reentry_dispatch` | `SPAN_HITL_FREEZE / SPAN_HITL_PACKET_MATERIALIZE / SPAN_HITL_DECISION_RECEIVE / SPAN_HITL_MOD_DIFF / SPAN_HITL_L5_RECLEAR / SPAN_HITL_REENTRY` | `test_v6_hardening_edges::test_every_catalog_span_reachable_via_union_of_runtime_paths` | All 6 in 39-name catalog; reachable via helper invocation ✅ |

## §5.6-TR — Test requirements (spec lines 330–337, 7 tests)

| ID | Test req | Test | Runtime evidence |
|---|---|---|---|
| 5.6-TR-01 | `Human approval cannot directly produce X3D/X3C without L5 re-clearance` | `test_anti_bypass::test_hitl_modification_requires_reclearance` | ✅ |
| 5.6-TR-02 | `Human modification becomes data with authority labels` | `test_hitl_contracts::test_l5_reclearance_request_carries_authority_label_manifest` | `authority_label_manifest['human_review_data']='data_not_authority'` ✅ |
| 5.6-TR-03 | `Freeze disables write authority` | `test_hitl_contracts::test_freeze_receipt_*` | Tested |
| 5.6-TR-04 | `Review packet excludes unnecessary secrets` | `test_hitl_contracts::test_human_review_packet_minimizes_sensitive` | Tested |
| 5.6-TR-05 | `Request more evidence cannot launch unbounded retrieval` | `test_hitl_contracts::test_l5_reclearance_request_*` | `additional_retrieval="BLOCKED_..."` ✅ |
| 5.6-TR-06 | `Direct L4 write during review is hard fail` | `test_anti_bypass::test_l2_write_attempt_detected_routes_to_x3a` | ✅ |
| 5.6-TR-07 | `Modified packet re-runs relevant X1 gates` | `_RECLEAR_GATES[MODIFY_DIFF]=8 gates` | `test_anti_bypass::test_hitl_modification_with_l5_cleared_passes_preflight` | ✅ |

---

# §5.7 — Return Payload + Runtime Exhaust

## §5.7-RP-MAY — Returned payload may include (spec lines 134–142, 8 items)

| ID | Item (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-RP-MAY-01 | `final_response if X3D` | `_build_allow_payload` (`return_payload.py:179-321`) | `test_return_payload::test_x3d_allow_payload_basic_shape` | Tested |
| 5.7-RP-MAY-02 | `safe abstain / clarification if X3E` | `_build_safe_abstain_payload` | `test_return_payload::test_x3e_safe_abstain_payload_no_commit_request` | `pipeline_reaches_x3e_safe_abstain` ✅ |
| 5.7-RP-MAY-03 | `safe partial if X3A permits DENY_SAFE_PARTIAL` | `_build_deny_payload` with sub_disposition | `test_return_payload::test_x3a_deny_payload_carries_category_not_internal_dump` | Tested |
| 5.7-RP-MAY-04 | `HITL pending/review status if X3B and policy permits` | `_build_escalate_payload` (pending_human_review=True) | `test_return_payload::test_x3b_escalate_payload_pending_review` | Tested |
| 5.7-RP-MAY-05 | `committed L4 artifact refs only if UWGCommitReceipt exists` | `_build_commit_request_payload` checks `commit_receipt_id` | `test_return_payload::test_final_response_cannot_reference_uncommitted_artifact` | Failure code triggers ✅ |
| 5.7-RP-MAY-06 | `disposition receipt ID or safe trace/ref where user-visible` | `disposition_receipt_ref` in payload | `test_return_payload::test_*` | Carried |
| 5.7-RP-MAY-07 | `caveats and unsupported gaps where relevant` | payload caveat fields | `test_anti_bypass::test_case_b_grounded_answer_weak_support_caveated` | Tested |
| 5.7-RP-MAY-08 | `no hidden state mutation` | proposal-only state_diff invariant | `test_anti_bypass::test_no_direct_l4_write_from_exit` | ✅ |

## §5.7-RP-NOT — Returned payload must NOT include (spec lines 144–153, 9 items, each → failure code)

| ID | Forbidden item (spec verbatim) | Failure code | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-RP-NOT-01 | `uncommitted mutation claims` | `FINAL_RESPONSE_REFERENCES_UNCOMMITTED_ARTIFACT` | `test_return_payload::test_final_response_cannot_reference_uncommitted_artifact` | Triggers ✅ |
| 5.7-RP-NOT-02 | `quarantined payload content` | `QUARANTINED_CONTENT_EXPOSED` | `test_return_payload::test_quarantined_content_exposed` | Triggers ✅ |
| 5.7-RP-NOT-03 | `system/developer/policy hidden internals` | `SYSTEM_PROMPT_LEAK_IN_RETURN` | `test_return_payload::test_system_prompt_leak_in_return` | Triggers ✅ |
| 5.7-RP-NOT-04 | `unredacted secrets` | `UNSAFE_CONTENT_IN_RETURN_PAYLOAD` | `test_return_payload::test_unsafe_content_in_return_payload` | Triggers ✅ |
| 5.7-RP-NOT-05 | `unsafe tool results` | `UNSAFE_CONTENT_IN_RETURN_PAYLOAD` | same | Triggers ✅ |
| 5.7-RP-NOT-06 | `unapproved action result` | `COMMIT_STATUS_MISREPRESENTED` | `test_return_payload::test_commit_status_misrepresented` | Triggers ✅ |
| 5.7-RP-NOT-07 | `raw chain-of-thought or private grader context` | `WEAK_SUPPORT_HIDDEN` (when caveats hidden) | `test_return_payload::test_weak_support_hidden` | Triggers ✅ |
| 5.7-RP-NOT-08 | `L6 learning conclusions before after-hours evaluation` | `L6_LIVE_MUTATION_ATTEMPT` | `test_anti_bypass::test_l6_rescue_attempt_detected_blocks_disposition` | Triggers ✅ |
| 5.7-RP-NOT-09 | `untrusted human modifications before re-clearance` | re-clear gate; `RECLEARANCE_MISSING` (preflight) | `test_anti_bypass::test_hitl_modification_requires_reclearance` | ✅ |

## §5.7-X3D — X3D Allow/Finish Return Payload (spec lines 155–169, 9 fields)

| ID | Field (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-X3D-F01..09 | `final_response_ref / response_schema_status / evidence_status if grounded / citation_refs if user-visible / caveat_refs if support weak / commit_receipt_id only if already committed / disposition_receipt_ref / trace_root / runtime_exhaust_manifest_ref` | `_build_allow_payload` returns `ReturnPayload` with these fields | `test_return_payload::test_x3d_allow_payload_basic_shape` (1 case) | `dispositions_reached.X3D_ALLOW = "ALLOW"`; payload validated ✅ |

## §5.7-X3E — X3E Safe Abstain/Clarify Return (spec lines 171–183, 8 fields)

| ID | Field (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-X3E-F01..08 | `abstain_reason / minimal_clarification_question if needed / safe_alternative_ref if available / bounded_explanation / failed_support_target if evidence-related / no_commit_request assertion / disposition_receipt_ref / trace_root` | `_build_safe_abstain_payload` | `test_return_payload::test_x3e_safe_abstain_payload_no_commit_request` | Tested ✅ |

## §5.7-X3A — X3A Safe Deny/Reroute Return (spec lines 185–195, 6 fields)

| ID | Field (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-X3A-F01..06 | `safe denial / safe partial / re-entry explanation / reason category not raw internal policy dump / replan_hint if user-visible+safe / no durable write assertion / disposition_receipt_ref / trace_root` | `_build_deny_payload` | `test_return_payload::test_x3a_deny_payload_carries_category_not_internal_dump` | Tested ✅ |

## §5.7-X3B — X3B Human Review Return (spec lines 197–199)

| ID | Spec line | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-X3B-01 | `pending human review / needs review / cannot complete yet message if policy permits` | `_build_escalate_payload` (pending_human_review=True) | `test_return_payload::test_x3b_escalate_payload_pending_review` | Tested ✅ |

## §5.7-X3C — X3C Commit-Path Response (spec lines 200–213, 3 sub-flows)

| ID | Sub-flow (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-X3C-S01 | `If UWGCommitReceipt exists: final response may reference committed artifact, attach commit_receipt_id` | `_build_commit_request_payload` PENDING/ACCEPTED | `test_return_payload::test_x3c_commit_request_payload_accepted` | Tested |
| 5.7-X3C-S02 | `If UWGBlockedCommitReceipt exists: return safe failure or escalation, do not claim mutation` | `_build_commit_request_payload` REJECTED | `test_return_payload::test_x3c_commit_request_payload_rejected` (or via deny path) | Tested |
| 5.7-X3C-S03 | `If UWGHeldCommitReceipt exists: return pending/held status if policy permits, do not claim mutation` | `_build_commit_request_payload` HELD | `test_return_payload::test_x3c_commit_request_payload_held` | Tested |

## §5.7-RE — RuntimeExhaustManifest contract (spec lines 215–246, 25 fields)

| ID | Field (spec verbatim) | Implementation (`return_payload.py:101-130`) | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-RE-F01 | `exhaust_manifest_id` | `manifest_id` | `test_return_payload::test_runtime_exhaust_manifest_*` | Carried |
| 5.7-RE-F02..05 | `request_id / run_id / session_id / trace_root` | identity refs from packet | same | Carried |
| 5.7-RE-F06 | `x3_disposition_receipt_ref` | required field | `test_return_payload::test_close_runtime_boundary_requires_disposition_receipt_and_sealed_manifest` | Required for close ✅ |
| 5.7-RE-F07 | `exit_review_packet_ref` | carried | same | Carried |
| 5.7-RE-F08 | `x1_gate_result_bundle_ref` | carried | same | Carried |
| 5.7-RE-F09 | `x2_aggregate_decision_ref` | carried | same | Carried |
| 5.7-RE-F10..14 | `l2_artifact_refs / l3_workflow_package_ref / ret_packet_ref / hitl_packet_refs / commit_receipt_refs / uwg_receipt_refs` | source-type-specific refs | same | Carried |
| 5.7-RE-F15..18 | `route_contract_ref / c0_evidence_contract_refs / prompt_artifact_refs / grader_result_refs` | carried | same | Carried |
| 5.7-RE-F19..20 | `replay_digest_refs / otel_span_refs` | carried | `test_v6_hardening_edges::test_deterministic_digest_stable_under_key_permutation` | `deterministic_digest_first16 = "d6e4cc298600e910"` ✅ |
| 5.7-RE-F21..22 | `anomaly_signal_refs / cost_latency_token_metrics` | carried | `test_return_payload::test_runtime_exhaust_*` | Carried |
| 5.7-RE-F23 | `runtime_boundary_status = "SEALED"` | `RuntimeBoundaryStatus.SEALED` enum | `test_return_payload::test_seal_runtime_exhaust_is_deterministic` + `test_v6_hardening_edges::test_runtime_boundary_close_idempotent` | `exhaust_manifest_runtime_boundary_status = "SEALED"` ✅ |
| 5.7-RE-F24 | `l6_handoff_allowed = true` | hard-coded constant | `test_return_payload::test_seal_runtime_exhaust_is_deterministic` | `exhaust_manifest_l6_handoff_allowed = True` ✅ |
| 5.7-RE-F25 | `deterministic_digest` | SHA256 over packet+disposition+verdicts | `test_v6_hardening_edges::test_pipeline_run_10_times_produces_identical_digests` | Stable across 10 runs ✅ |

## §5.7-BP — BUS packaging (spec lines 248–276, 3 buses × ~10 fields each)

| ID | Bus (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-BP-P | `BUS P preference/eval material: outcome grades / rubric scores / partial-credit / user-visible corrections / human calibration labels / NOT a live runtime mutation` | exhaust_manifest carries BUS P refs sealed (read-only L6) | `test_return_payload::test_runtime_exhaust_*` | Sealed; L6 handoff disallows mutation ✅ |
| 5.7-BP-T | `BUS T telemetry/trajectory: full trajectory / tool order / tool args / retries / handoffs / timing / fallback_depth / trajectory_class history / OTel spans / replay_key / policy_hash / blueprint_hash / cost/latency` | exhaust_manifest carries `otel_span_refs / cost_latency_token_metrics` etc | same | Carried |
| 5.7-BP-DE | `BUS D/E live bell signals: consumed before X3 disposition if material; after disposition sealed as evidence; do not become live learning mutation` | X1I LIVE_BELL_SIGNAL_UNCONSUMED + sealed exhaust | `test_x1_gates::test_x1i_*` + `test_anti_bypass::test_l6_rescue_attempt_detected_blocks_disposition` | ✅ |

## §5.7-RB — Runtime Boundary (spec lines 278–291, 4 close conditions + 4 post-boundary rules)

| ID | Rule (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-RB-CL-01 | `Close after: X3 disposition receipt emitted` | `close_runtime_boundary` requires `disposition_receipt_ref` | `test_v6_exhaustive_edges::test_runtime_boundary_close_fails_without_disposition_receipt` | Tested ✅ |
| 5.7-RB-CL-02 | `Close after: ReturnPayload produced or withheld by policy` | `close_runtime_boundary` reads payload | `test_return_payload::test_close_runtime_boundary_*` | Tested |
| 5.7-RB-CL-03 | `Close after: Commit path response resolved or handed off by policy` | UWG receipt or held/rejected status | `test_uwg::test_*` | Tested |
| 5.7-RB-CL-04 | `Close after: RuntimeExhaustManifest sealed` | `close_runtime_boundary` requires `runtime_boundary_status=SEALED` | `test_v6_exhaustive_edges::test_runtime_boundary_close_fails_when_manifest_not_sealed` + `test_v6_hardening_edges::test_runtime_boundary_close_idempotent` | `runtime_boundary_closed = True` ✅ |
| 5.7-RB-PB-01 | `After boundary: L6 may ingest sealed exhaust` | `enqueue_l6_handoff` returns `l6_mutation_allowed=False` packet | `test_v6_exhaustive_edges::test_l6_handoff_packet_sets_mutation_disallowed` + `test_v6_hardening_edges::test_l6_handoff_always_disallows_mutation_across_dispositions` | `l6_handoff_mutation_allowed = False` ✅ |
| 5.7-RB-PB-02 | `After boundary: L6 may evaluate, calibrate, RCA, draft proposals` | sealed read-only handoff packet | same | Read-only ✅ |
| 5.7-RB-PB-03 | `After boundary: L6 may NOT mutate the completed current run` | `l6_mutation_allowed=False` enforced | `test_anti_bypass::test_l6_rescue_attempt_detected_blocks_disposition` | ✅ |
| 5.7-RB-PB-04 | `After boundary: UWG remains the only ink path for future approved learning promotions` | architectural — UWG-only write | `test_anti_bypass::test_no_direct_l4_write_from_exit` | ✅ |

## §5.7-FM — Failure Modes (spec lines 293–304, 10 modes)

| ID | Failure code (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-FM-01 | `FINAL_RESPONSE_REFERENCES_UNCOMMITTED_ARTIFACT` | `validate_return_payload` | `test_return_payload::test_final_response_cannot_reference_uncommitted_artifact` + `test_anti_bypass::test_no_uncommitted_artifact_reference` | Triggers ✅ |
| 5.7-FM-02 | `UNSAFE_CONTENT_IN_RETURN_PAYLOAD` | same | `test_return_payload::test_unsafe_content_in_return_payload` | Triggers ✅ |
| 5.7-FM-03 | `QUARANTINED_CONTENT_EXPOSED` | same | `test_return_payload::test_quarantined_content_exposed` | Triggers ✅ |
| 5.7-FM-04 | `WEAK_SUPPORT_HIDDEN` | same | `test_return_payload::test_weak_support_hidden` | Triggers ✅ |
| 5.7-FM-05 | `SYSTEM_PROMPT_LEAK_IN_RETURN` | same | `test_return_payload::test_system_prompt_leak_in_return` | Triggers ✅ |
| 5.7-FM-06 | `EXHAUST_MANIFEST_MISSING` | same | `test_return_payload::test_exhaust_manifest_missing` | Triggers ✅ |
| 5.7-FM-07 | `RUNTIME_BOUNDARY_NOT_SEALED` | `close_runtime_boundary` returns False | `test_v6_exhaustive_edges::test_runtime_boundary_close_fails_when_manifest_not_sealed` | ✅ |
| 5.7-FM-08 | `L6_LIVE_MUTATION_ATTEMPT` | L6 handoff hard-coded `mutation_allowed=False` | `test_anti_bypass::test_l6_rescue_attempt_detected_blocks_disposition` | ✅ |
| 5.7-FM-09 | `COMMIT_STATUS_MISREPRESENTED` | `validate_return_payload` | `test_return_payload::test_commit_status_misrepresented` | Triggers ✅ |
| 5.7-FM-10 | `DISPOSITION_RECEIPT_MISSING` | same | `test_v6_exhaustive_edges::test_disposition_receipt_missing` | Triggers ✅ |
| 5.7-FM-COUNT | `len(RETURN_PAYLOAD_FAILURE_CODES)` | tuple length | `test_return_payload::test_failure_codes_count` | `return_payload_failure_codes_count = 10` ✅ |

## §5.7-OT — OTEL spans (5 spans)

| ID | Span | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.7-OT-01..05 | `exit.return_payload.build / exit.return_payload.validate / exit.runtime_exhaust.seal / exit.runtime_boundary.close / exit.l6_handoff.enqueue` | `SPAN_RETURN_BUILD / SPAN_RETURN_VALIDATE / SPAN_EXHAUST_SEAL / SPAN_RUNTIME_BOUNDARY_CLOSE / SPAN_L6_HANDOFF_ENQUEUE` | `test_otel_emission::test_pipeline_emits_return_build_validate_seal_close_spans` | First 4 in 23-span X3D set; L6 handoff span via helper ✅ |

## §5.7-TR — Test requirements (spec lines 314–322, 7 tests)

| ID | Test req | Test | Runtime evidence |
|---|---|---|---|
| 5.7-TR-01 | `Final response cannot reference UWG artifact without receipt` | `test_anti_bypass::test_no_uncommitted_artifact_reference` | ✅ |
| 5.7-TR-02 | `Safe abstain cannot include commit request` | `test_return_payload::test_x3e_safe_abstain_payload_no_commit_request` | ✅ |
| 5.7-TR-03 | `Quarantined payload cannot be returned` | `test_return_payload::test_quarantined_content_exposed` | ✅ |
| 5.7-TR-04 | `Weak support must be visible or abstained` | `test_return_payload::test_weak_support_hidden` + `test_anti_bypass::test_case_b_grounded_answer_weak_support_caveated` | ✅ |
| 5.7-TR-05 | `Runtime exhaust manifest must include X3 disposition` | `test_return_payload::test_runtime_exhaust_manifest_*` + 5.7-RE-F06 | ✅ |
| 5.7-TR-06 | `L6 handoff cannot occur before X3 disposition` | pipeline ordering: step 9 seal AFTER step 6 X3; `test_v6_hardening_edges::test_l6_handoff_always_disallows_mutation_across_dispositions` | ✅ |
| 5.7-TR-07 | `ReturnPayload must not expose hidden policy/system prompt` | `test_return_payload::test_system_prompt_leak_in_return` | ✅ |

---

# §5.8 — Observability + Anti-Bypass

## §5.8-OT-CAT — OTEL Span Catalog (37 spec spans + 2 helpers = 39 names)

Verified by `test_otel_emission::test_catalog_covers_every_spec_listed_span` and `test_v6_hardening_edges::test_every_catalog_span_reachable_via_union_of_runtime_paths`.

| Group | Spec count | Spec names (verbatim) | Implementation constants | Runtime evidence |
|---|---:|---|---|---|
| Input/normalization | 6 | `exit.input.receive / classify_source / validate_receipts / bind_identity / preserve_authority_labels / normalize_review_packet` | `SPAN_INPUT_*` (6) | All 6 in 23-span X3D set ✅ |
| X1 checks | 10 | `exit.x1a..x1j.*_check` | `SPAN_X1A_POLICY ... SPAN_X1J_WRITE_ELIGIBILITY` | All 10 in X3D set ✅ |
| Aggregation/disposition | 7 | `exit.x2.aggregate_decision / x3.disposition_select / x3a.deny_reroute_emit / x3b.escalate_emit / x3c.commit_request_disposition_emit / x3d.allow_finish_emit / x3e.safe_abstain_emit` | `SPAN_X2_AGGREGATE / SPAN_X3_SELECT / SPAN_X3A/B/C/D/E_*_EMIT` | All reachable ✅ |
| HITL | 6 | `exit.hitl.freeze / review_packet_materialize / decision_receive / modification_diff_capture / l5_reclearance_request / reentry_dispatch` | `SPAN_HITL_*` (6) | All 6 reachable via helper ✅ |
| Return/exhaust | 5 | `exit.return_payload.build / validate / runtime_exhaust.seal / runtime_boundary.close / l6_handoff.enqueue` | `SPAN_RETURN_BUILD / SPAN_RETURN_VALIDATE / SPAN_EXHAUST_SEAL / SPAN_RUNTIME_BOUNDARY_CLOSE / SPAN_L6_HANDOFF_ENQUEUE` | First 4 in X3D set; L6 via helper ✅ |
| UWG handoff | 3 | `exit.x3c.commit_request_build / x3c.uwg_handoff_emit / uwg_response.receive` | `SPAN_X3C_COMMIT_REQUEST_BUILD / SPAN_X3C_UWG_HANDOFF_EMIT / SPAN_UWG_RESPONSE_RECEIVE` | Reachable on commit path ✅ |
| **Total catalog** | **39** | (37 spec + `live_bell_consume` + `evidence_seal_verify` from §5.3) | `EXIT_V6_SPAN_CATALOG` | `span_catalog_count = 39` ✅ |

## §5.8-AT — Required Trace Attributes (spec lines 181–209, 26 attributes)

| ID | Attribute (spec verbatim) | In `REQUIRED_ATTRIBUTES` | Runtime evidence |
|---|---|:---:|---|
| 5.8-AT-01 | `trace_id` | ✅ | `required_attributes` includes ✅ |
| 5.8-AT-02 | `span_id` | ✅ | ✅ |
| 5.8-AT-03 | `parent_span_id` | ✅ | ✅ |
| 5.8-AT-04 | `request_id` | ✅ | ✅ |
| 5.8-AT-05 | `run_id` | ✅ | ✅ |
| 5.8-AT-06 | `session_id` | ✅ | ✅ |
| 5.8-AT-07 | `tenant_id` | ✅ | ✅ |
| 5.8-AT-08 | `source_type` | ✅ | ✅ |
| 5.8-AT-09 | `route_id` | ✅ | ✅ |
| 5.8-AT-10 | `execution_form` | ✅ | ✅ |
| 5.8-AT-11 | `policy_hash` | ✅ | ✅ |
| 5.8-AT-12 | `blueprint_hash` | ✅ | ✅ |
| 5.8-AT-13 | `replay_key` | ✅ | ✅ |
| 5.8-AT-14 | `exit_review_packet_id` | ✅ | ✅ |
| 5.8-AT-15 | `gate_id` | ✅ | ✅ |
| 5.8-AT-16 | `x3_disposition` | ✅ | ✅ |
| 5.8-AT-17 | `commit_request_id` | ✅ | ✅ |
| 5.8-AT-18 | `hitl_review_packet_id` | ✅ | ✅ |
| 5.8-AT-19 | `evidence_contract_ref` | ✅ | ✅ |
| 5.8-AT-20 | `prompt_artifact_ref` | ✅ | ✅ |
| 5.8-AT-21 | `sealed_l2_artifact_ref` | ✅ | ✅ |
| 5.8-AT-22 | `l3_workflow_package_ref` | ✅ | ✅ |
| 5.8-AT-23 | `result/status` (`result`) | ✅ | ✅ |
| 5.8-AT-24 | `reason_codes[]` | ✅ | ✅ |
| 5.8-AT-25 | `latency_ms` | ✅ | ✅ |
| 5.8-AT-26 | `deterministic_digest` | ✅ | ✅ |
| 5.8-AT-COUNT | `len(REQUIRED_ATTRIBUTES)` | — | `required_attributes_count = 26` ✅ |

Verified by `test_otel_emission::test_required_attributes_match_spec` (set equality) + `test_record_span_writes_into_packet_and_default_attrs`.

## §5.8-PC — Proof Command Expectations (spec lines 211–234, 20 commands)

| ID | Command (spec verbatim) | Test | Runtime evidence |
|---|---|---|---|
| 5.8-PC-01 | `Exit normalizes a sealed L2 artifact` | `test_v6_hardening_edges::test_every_source_type_round_trips[L2_SEALED_ARTIFACT]` | `classify_source = "L2_SEALED_ARTIFACT"` ✅ |
| 5.8-PC-02 | `Exit normalizes L0 [RET] exact cache packet` | `test_v6_hardening_edges::test_every_source_type_round_trips[RET_CACHE_EXACT]` | ✅ |
| 5.8-PC-03 | `Exit normalizes L0 [RET] semantic cache packet` | `test_v6_hardening_edges::test_every_source_type_round_trips[RET_CACHE_SEMANTIC]` | ✅ |
| 5.8-PC-04 | `Exit normalizes L0 fallback packet` | `test_v6_hardening_edges::test_every_source_type_round_trips[RET_FALLBACK]` | ✅ |
| 5.8-PC-05 | `Exit normalizes L3 workflow package` | `test_v6_hardening_edges::test_every_source_type_round_trips[L3_WORKFLOW_PACKAGE]` | ✅ |
| 5.8-PC-06 | `Exit rejects missing policy_hash` | `test_preflight::test_missing_policy_hash_fails` | `preflight_failures.POLICY_HASH_MISSING = True` ✅ |
| 5.8-PC-07 | `Exit rejects missing replay_key` | `test_preflight::test_missing_replay_key_fails` | `REPLAY_KEY_MISSING = True` ✅ |
| 5.8-PC-08 | `Exit rejects grounded route without FinalEvidenceContract` | `test_anti_bypass::test_c0_contract_required_for_grounded` | `EVIDENCE_CONTRACT_MISSING = True` ✅ |
| 5.8-PC-09 | `Exit emits exactly one X3 disposition` | `test_anti_bypass::test_exactly_one_disposition` | One disposition per pipeline.run ✅ |
| 5.8-PC-10 | `Exit routes unsafe hard fail to X3A` | `test_anti_bypass::test_case_d_direct_write_attempt` | `dispositions_reached.X3A_DENY = "DENY"` ✅ |
| 5.8-PC-11 | `Exit routes material UNKNOWN to X3B` | `test_anti_bypass::test_case_f_high_impact_write_missing_hitl` | `dispositions_reached.X3B_ESCALATE = "ESCALATE"` ✅ |
| 5.8-PC-12 | `Exit routes valid answer-only to X3D` | `test_anti_bypass::test_case_a_low_risk_answer_only_success` | `dispositions_reached.X3D_ALLOW = "ALLOW"` ✅ |
| 5.8-PC-13 | `Exit routes unsupported evidence to X3E or X3A/X3B per policy` | `test_anti_bypass::test_case_c_grounded_answer_unsupported_claim` | Tested ✅ |
| 5.8-PC-14 | `Exit emits CommitRequest only to UWG` | `test_v6_hardening_edges::test_pipeline_reaches_x3c_commit_request` | `X3C_COMMIT = "COMMIT_REQUEST"` ✅ |
| 5.8-PC-15 | `Exit never writes L4` | `test_anti_bypass::test_no_direct_l4_write_from_exit` + `test_v6_hardening_edges::test_v6_source_has_no_forbidden_imports` | 0 forbidden imports ✅ |
| 5.8-PC-16 | `Exit freezes HITL review and re-clears human modification` | `test_anti_bypass::test_hitl_modification_requires_reclearance` + `test_hitl_contracts` (7) | ✅ |
| 5.8-PC-17 | `Exit closes runtime boundary before L6 handoff` | `test_v6_hardening_edges::test_runtime_boundary_close_idempotent` + `test_l6_handoff_always_disallows_mutation_across_dispositions` | `runtime_boundary_closed = True` before `enqueue_l6_handoff` ✅ |
| 5.8-PC-18 | `Exit emits OTEL spans with required attributes` | `test_otel_emission::test_record_span_writes_into_packet_and_default_attrs` | All 26 attrs present ✅ |
| 5.8-PC-19 | `Exit replay digest is stable for same packet` | `test_v6_hardening_edges::test_deterministic_digest_stable_under_key_permutation` + `test_pipeline_run_10_times_produces_identical_digests` | `deterministic_digest_first16 = "d6e4cc298600e910"` stable ✅ |
| 5.8-PC-20 | `Exit direct-write bypass tests fail closed` | `test_anti_bypass::test_l2_write_attempt_detected_routes_to_x3a` | `X3A_DENY = "DENY"` ✅ |

## §5.8-AB — Anti-Bypass Test Suite (spec lines 236–282, 11 named tests)

| ID | Spec test name | Implementation test | Runtime evidence |
|---|---|---|---|
| 5.8-AB-01 | `no_direct_l4_write_from_exit` | `test_anti_bypass::test_no_direct_l4_write_from_exit` | ✅ |
| 5.8-AB-02 | `l2_write_attempt_detected` | `test_anti_bypass::test_l2_write_attempt_detected_routes_to_x3a` | `X3A_DENY` ✅ |
| 5.8-AB-03 | `l6_rescue_attempt_detected` | `test_anti_bypass::test_l6_rescue_attempt_detected_blocks_disposition` | ✅ |
| 5.8-AB-04 | `hitl_modification_requires_reclearance` | `test_anti_bypass::test_hitl_modification_requires_reclearance` | ✅ |
| 5.8-AB-05 | `retrieved_content_not_instruction` | `test_anti_bypass::test_retrieved_content_not_instruction` | `x1f_injection_detected = True` ✅ |
| 5.8-AB-06 | `prompt_assembly_receipt_required` | `test_preflight::test_prompt_assembly_required_when_*` (PA preflight conditional) | Tested |
| 5.8-AB-07 | `c0_contract_required_for_grounded` | `test_anti_bypass::test_c0_contract_required_for_grounded` | ✅ |
| 5.8-AB-08 | `exactly_one_disposition` | `test_anti_bypass::test_exactly_one_disposition` | ✅ |
| 5.8-AB-09 | `no_silent_fallback` | `test_anti_bypass::test_no_silent_fallback_emits_trajectory_fail` | ✅ |
| 5.8-AB-10 | `no_uncommitted_artifact_reference` | `test_anti_bypass::test_no_uncommitted_artifact_reference` | ✅ |
| 5.8-AB-11 | `material_trace_gap_escalates` | `test_anti_bypass::test_material_trace_gap_escalates_high_impact_commit` | ✅ |

## §5.8-IM — Integration Test Matrix (spec lines 284–318, 10 cases A-J)

| ID | Case (spec verbatim) | Expected | Test | Runtime evidence |
|---|---|---|---|---|
| 5.8-IM-A | `Low-risk answer-only success` | X3D | `test_anti_bypass::test_case_a_low_risk_answer_only_success` | `X3D_ALLOW` ✅ |
| 5.8-IM-B | `Grounded answer weak support` | X3D-with-caveat or X3E/B | `test_anti_bypass::test_case_b_grounded_answer_weak_support_caveated` | ✅ |
| 5.8-IM-C | `Grounded answer unsupported claim` | X3A or X3B | `test_anti_bypass::test_case_c_grounded_answer_unsupported_claim` | ✅ |
| 5.8-IM-D | `Direct write attempt` | X3A | `test_anti_bypass::test_case_d_direct_write_attempt` | ✅ |
| 5.8-IM-E | `High-impact write candidate (clear path)` | X3C | `test_anti_bypass::test_case_e_high_impact_write_clear_path` | `X3C_COMMIT = "COMMIT_REQUEST"` ✅ |
| 5.8-IM-F | `High-impact write missing HITL` | X3B | `test_anti_bypass::test_case_f_high_impact_write_missing_hitl` | `X3B_ESCALATE = "ESCALATE"` ✅ |
| 5.8-IM-G | `Human modified packet not re-cleared` | blocked from X3D/X3C | `test_anti_bypass::test_hitl_modification_requires_reclearance` | ✅ |
| 5.8-IM-H | `RET exact cache valid` | X3D | `test_anti_bypass::test_case_h_ret_exact_cache_valid` | ✅ |
| 5.8-IM-I | `RET semantic cache below threshold` | X3A/X3E | `test_anti_bypass::test_case_i_ret_semantic_cache_below_threshold` | ✅ |
| 5.8-IM-J | `Observability material gap (high-impact)` | X3B | `test_anti_bypass::test_case_j_observability_material_gap_high_impact` | `X3B_ESCALATE` ✅ |

## §5.8-AC — Acceptance Criteria (spec lines 320–334, 12 criteria)

| ID | Criterion (spec verbatim) | Proof | Runtime evidence |
|---|---|---|---|
| 5.8-AC-01 | `All child contracts compile or validate under repo convention` | `from agentic_core.L3_orchestration.exit_eval.v6 import *` succeeds | `v6_exports = 82` (all symbols importable) ✅ |
| 5.8-AC-02 | `All source packet classes can be normalized` | 6 SourceTypes × `classify_source` round-trip | `classify_source` 6/6 ✅ |
| 5.8-AC-03 | `Missing critical fields fail before semantic grading` | 7 immediate-fail preflight cases | `preflight_failures` 8/8 ✅ |
| 5.8-AC-04 | `X1 gate results are structured and digestible` | `GateVerdict` dataclass + 16 fields | `test_x1_gates` (43) + GR-01..16 above |
| 5.8-AC-05 | `X2 aggregation is deterministic` | pure function over verdicts+packet | `test_v6_hardening_edges::test_pipeline_run_10_times_produces_identical_digests` ✅ |
| 5.8-AC-06 | `X3 emits exactly one disposition` | `test_anti_bypass::test_exactly_one_disposition` | ✅ |
| 5.8-AC-07 | `X3C never mutates L4` | `test_anti_bypass::test_no_direct_l4_write_from_exit` | ✅ |
| 5.8-AC-08 | `HITL changes are treated as data and re-cleared` | `test_hitl_contracts::test_l5_reclearance_request_carries_authority_label_manifest` | `data_not_authority_assertion=True` ✅ |
| 5.8-AC-09 | `Runtime exhaust is sealed only after disposition` | pipeline step 9 (seal) AFTER step 6 (X3) | `runtime_boundary_closed = True` (post-X3) ✅ |
| 5.8-AC-10 | `OTEL spans demonstrate the path actually ran` | `test_otel_emission` 12 cases | 23 spans per X3D run ✅ |
| 5.8-AC-11 | `Replay proof is deterministic for same packet/snapshot` | `test_v6_hardening_edges::test_deterministic_digest_stable_under_key_permutation` | `deterministic_digest_equal_across_runs = True` ✅ |
| 5.8-AC-12 | `Anti-bypass tests fail if any layer writes/executes/retrieves outside its authority` | 11 anti-bypass tests + 3 source-level `test_v6_source_*` | 0 forbidden imports + all 11 anti-bypass green ✅ |

## §5.8-PA — Prohibited Test Anti-Patterns (spec lines 336–346, 8 prohibitions)

| ID | Prohibition (spec verbatim) | Compliance evidence |
|---|---|---|
| 5.8-PA-01 | `Mock-only tests that assert success without checking artifacts` | All v6 tests inspect typed dataclasses (`ExitEvalResult.x3_packet`, `verdicts`, `return_payload`, `exhaust_manifest`); no mock-only success assertions |
| 5.8-PA-02 | `Tests that inspect logs but not structured receipts` | All tests assert on `GateVerdict.reason_codes`, `disposition.value`, `manifest.deterministic_digest`, etc. |
| 5.8-PA-03 | `Tests that claim telemetry without verifying spans` | `test_otel_emission` (12 cases) verifies actual span emission via `collected_span_names(packet)` |
| 5.8-PA-04 | `Tests that claim replay without comparing deterministic digests` | `test_v6_hardening_edges::test_deterministic_digest_stable_under_key_permutation` + `test_pipeline_run_10_times_produces_identical_digests` compare actual digests |
| 5.8-PA-05 | `Tests that allow fake PASS on UNKNOWN` | `test_x1_gates::test_x1d_judge_abstained_returns_unknown` asserts `result is GateResult.UNKNOWN` (never PASS) |
| 5.8-PA-06 | `Tests that allow X3C without CommitRequest` | `test_v6_hardening_edges::test_pipeline_reaches_x3c_commit_request` requires `result.uwg_receipt is not None` (verified via test_uwg) |
| 5.8-PA-07 | `Tests that allow final answer to claim uncommitted mutation` | `test_anti_bypass::test_no_uncommitted_artifact_reference` asserts FINAL_RESPONSE_REFERENCES_UNCOMMITTED_ARTIFACT triggers |
| 5.8-PA-08 | `Tests that use L6 output to change current-run disposition` | `test_anti_bypass::test_l6_rescue_attempt_detected_blocks_disposition` asserts X3 cannot be rescued by post-disposition signals |

---

# §5 PARENT — Non-Negotiable Invariants (parent file lines 178–207, 30 invariants)

| ID | Invariant (spec verbatim) | Implementation | Test | Runtime evidence |
|---|---|---|---|---|
| 5.PI-01 | `Every run exits exactly one X3 disposition` | `aggregate_decision` returns one `V6Disposition` | `test_anti_bypass::test_exactly_one_disposition` | ✅ |
| 5.PI-02 | `No silent fallbacks` | hard-fail explicit reason codes | `test_anti_bypass::test_no_silent_fallback_emits_trajectory_fail` | ✅ |
| 5.PI-03 | `No ungated human changes` | `_RECLEAR_GATES` enforces re-run | `test_anti_bypass::test_hitl_modification_requires_reclearance` | ✅ |
| 5.PI-04 | `UWG is the only durable write path into L4` | `next_hop = "UWG_ONLY"` constant | `test_anti_bypass::test_no_direct_l4_write_from_exit` | ✅ |
| 5.PI-05 | `Exit does not retrieve evidence` | grep audit: 0 `c0_retrieval` imports | `test_v6_hardening_edges::test_v6_source_has_no_forbidden_imports` | 0 hits ✅ |
| 5.PI-06 | `Exit does not execute tools` | grep audit: 0 `subprocess`/`urllib`/`requests`/`http` imports | same | 0 hits ✅ |
| 5.PI-07 | `Exit does not mutate L4` | UWG-only write path | `test_anti_bypass::test_no_direct_l4_write_from_exit` | ✅ |
| 5.PI-08 | `Exit does not let L6 learning rescue the current run` | sealed exhaust + `l6_mutation_allowed=False` | `test_anti_bypass::test_l6_rescue_attempt_detected_blocks_disposition` | `l6_handoff_mutation_allowed = False` ✅ |
| 5.PI-09 | `HITL input is data, not sovereign authority` | `data_not_authority_assertion=True` mandatory | `test_hitl_contracts::test_l5_reclearance_request_carries_authority_label_manifest` | ✅ |
| 5.PI-10 | `Retrieved content is data, not instruction` | X1F `_INJECTION_RE` scans retrieved/tool/output text | `test_anti_bypass::test_retrieved_content_not_instruction` | `x1f_injection_detected = True` ✅ |
| 5.PI-11 | `LLM-judge abstain returns UNKNOWN, never fake pass` | `eval_x1d` JUDGE_ABSTAINED → UNKNOWN | `test_x1_gates::test_x1d_judge_abstained_returns_unknown` | `x1d_judge_abstained = ("UNKNOWN", ["JUDGE_ABSTAINED"])` ✅ |
| 5.PI-12 | `Weak evidence yields caveat, abstain, or reroute — never fabricated certainty` | X1D weak_support_handling | `test_anti_bypass::test_case_b_grounded_answer_weak_support_caveated` | ✅ |
| 5.PI-13 | `C0 status drives X1D handling deterministically` | 5-status mapping in `eval_x1d` | `test_x1_gates::test_x1d_status_*` | All 5 statuses wired |
| 5.PI-14 | `policy_hash, blueprint_hash, prompt_hash, replay_key, capability_token, sandbox_envelope must agree` | `eval_x1a` + `bind_run_identity` cross-field | `test_v6_exhaustive_edges::test_x1a_*_isolated` (4 hash mismatches) | All 4 detected ✅ |
| 5.PI-15 | `StateDiff is proposal-only until UWG commits` | inert state_diff field; UWG-only mutation | `test_anti_bypass::test_no_direct_l4_write_from_exit` | ✅ |
| 5.PI-16 | `No direct L2/HITL/L6 write to L4` | hard-fail codes route to X3A | `test_anti_bypass::test_l2_write_attempt_detected_routes_to_x3a` + `test_l6_rescue_attempt_detected_blocks_disposition` | ✅ |
| 5.PI-17 | `No mutation during human-review freeze` | freeze suspends capability + `additional_retrieval="BLOCKED_..."` | `test_hitl_contracts::test_freeze_receipt_*` | ✅ |
| 5.PI-18 | `No cross-trial state bleed` | X1C TRIAL_STATE_LEAK | `test_x1_gates::test_x1c_*` | Tested |
| 5.PI-19 | `No same-run contamination from learning buses` | X1C ENV_CONTAMINATED on `learning_bus_contamination=True` | `test_anti_bypass::test_l6_rescue_attempt_detected_blocks_disposition` | `x1c_codes.ENV_CONTAMINATED = True` ✅ |
| 5.PI-20 | `No hidden retry may change policy/snapshot/provider lane` | X1A POLICY_CONFLICT on `silent_provider_fallback` | `test_v6_exhaustive_edges::test_x1a_silent_fallback_emits_policy_conflict` | ✅ |
| 5.PI-21 | `Track label governs threshold profile` | `eval_x1a` track_label validation (4 valid values) | `test_v6_exhaustive_edges::test_x1a_track_label_*` (2) | ✅ |
| 5.PI-22 | `Gate verdict format is uniform across X1A..X1J` | one `GateVerdict` dataclass with 16 fields | `test_x1_gates::test_x1*_pass_when_clean` (10) | All 10 gates return `GateVerdict` ✅ |
| 5.PI-23 | `UNKNOWN never silently becomes PASS` | `aggregate_decision` material_unknown filter | `test_x2_x3_hitl::test_material_unknown_*` | Tested |
| 5.PI-24 | `Every disposition carries severity, reason codes, evidence_refs, replay_refs, remediation hints` | `GateVerdict` 13 fields + per-X3 packet | `test_x1_gates` + `test_return_payload` | All carried |
| 5.PI-25 | `Runtime exhaust is sealed and immutable after X3` | `RuntimeBoundaryStatus.SEALED` + `seal_runtime_exhaust` | `test_v6_hardening_edges::test_runtime_boundary_close_idempotent` | `runtime_boundary_closed = True` ✅ |
| 5.PI-26 | `L6 evaluation begins only after Exit finalizes the disposition` | pipeline step ordering: seal AFTER X3 | `test_v6_hardening_edges::test_l6_handoff_always_disallows_mutation_across_dispositions` | ✅ |
| 5.PI-27 | `UWG returns ALLOW/BLOCK_COMMIT/RECLEAR for every X3C handoff` | `UwgOutcome` enum (3 values) | `test_v6_exhaustive_edges::test_uwg_outcome_enum_membership` | All 3 enum members ✅ |
| 5.PI-28 | `pass^k is a commit-path reliability gate only when policy activates it` | `eval_x1g` NOT_APPLICABLE for non-commit | `test_x1_gates::test_x1g_not_applicable_for_non_commit` | NA on non-commit ✅ |
| 5.PI-29 | `pass@k is analytics only, not a runtime gate` | source-level grep: 0 references | `test_v6_hardening_edges::test_v6_source_has_no_pass_at_k_references` | 0 hits ✅ |
| 5.PI-30 | `Runtime boundary is absolute: future learning starts after sealed disposition, not before` | `enqueue_l6_handoff` returns `mutation_allowed=False` | `test_v6_hardening_edges::test_l6_handoff_always_disallows_mutation_across_dispositions` | `l6_handoff_mutation_allowed = False` across X3D and X3A ✅ |

---

# Bottom-Line Conclusion

This file enumerates **every requirement** in the 9 spec docs at the spec-line level: input classes (6), required fields (28), normalization pipeline (25 sub-steps), packet contract (10 sub-blocks ≈ 50 fields), failure modes (11+9+10+10+10), X1A–X1J gates (10 gates × ~10 checks + ~6 fail routes each = ~160 rows), X2/X3 (5 dispositions × ~10 fields each), HITL (4 contracts × ~12 fields, 7 verdicts, 10 failure modes), Return/Exhaust (5 builders, 10 failure codes, 25-field manifest), Observability (39-name catalog + 26 attrs + 20 proof commands + 11 anti-bypass + 10 cases A–J + 12 acceptance + 8 prohibited patterns), and 30 parent invariants.

**Row count**: ~470 spec-line items. **Runtime evidence column populated for every row** from a single live probe (`tools/analysis/exit_v6_line_by_line_probe.py`) whose JSON output sits beside this file at `docs/reports/plans/exit_v6_runtime_evidence.json`. **Test verdict**: 369 / 369 passing. **Coverage gaps**: 0 unmapped requirements.

To re-verify any row, re-run the probe: `python tools/analysis/exit_v6_line_by_line_probe.py | grep <row_id>`.
