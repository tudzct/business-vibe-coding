# Experiment metrics schema

Canonical runs start at `gates.current: prompt` with empty history after automatic validation of the researcher-prepared Confirmed configuration. No configuration summary/confirmation receipt is required. Preserve the configuration path/ID/checksum in `experiment_configuration`; existing pins remain immutable. The four pre-prompt inputs must be prepared before invocation using any tool. Preflight only reads/validates them and never creates or fills them. Whole-turn tokens still include actual reads, validation and timestamp calls; never subtract estimated overhead to claim 100% prompt-only tokens. External setup has no fabricated local telemetry; setup done in a separate observed UC turn retains its existing auxiliary classification. Execution timing still starts after validation. Prompt-close records approval; subsequent commands record their own completion.

## Supplementary flow, optional UI and Excel output

`audit-generation-metrics` automatically invokes `audit-flow-accuracy` during the requested first-pass audit and within authorized repair work, before repair completion. The denominator is frozen before source generation from every explicit Basic/Main, Alternative and Exception Flow. Each flow has equal weight. A completion-critical failed step or unmet terminal outcome makes the whole flow incorrect. `flow_error_percent = incorrect / total * 100`; `flow_accuracy_percent = (total - incorrect) / total * 100`. Unknown evidence keeps both exact percentages null and reports coverage plus accuracy bounds.

Configuration freezes `flow_audit_rubric: completion-critical-flow-runtime-v2` independently of auditor assignment. Its assessment and canonical `flow_accuracy` block use integer schema 2 and the same `rubric_id`. Critical/outcome `met` requires target-specific evidence linked to a verified integrated-runtime observation; `correct` additionally requires a connected completed attempt. Input retains runtime/deployment linkage, ordered observation actions, sanitized checksummed artifacts, separate source findings and categorized limitations. See [flow assessment schema](../../.codex/skills/audit-flow-accuracy/references/assessment-schema.md) and [per-flow procedure](../../.codex/skills/audit-flow-accuracy/references/per-flow-audit.md).

Initial/final retain the same baseline and method. For repaired source, the repair operation automatically observes every flow using final source before closure. With no repair and an unchanged audited source hash, the original initial flow assessment serves as terminal evidence, retaining its stage/ID/time and immutable content; final BR values equal initial BR values and `repair_skip_reason` records the decision. There is no mandatory separate final-audit gate. Aggregation revalidates runtime evidence, recomputes stored scores and checks final source identity. Reports identify the configured rubric. Standalone audit/runtime time is excluded from generation execution totals; integrated repair verification and final evidence persistence are included in Repair.

Every UI field is optional: `ui_accuracy`, `ui_accuracy_percent`, `ui_accuracy_status`, and manual UI provenance may be omitted or null. Their absence never causes schema validation failure, blocks a gate, prevents a report/export or changes run completion. No placeholder assessment or successful UI score is required. Local UI evidence validation and statuses such as `not_evaluable`, `similarity_pending` or `repair_required` concern only the optional comparison; they are not experiment gate conditions. Audit and export remain independent of these fields.

Reports render available UI data without recomputing it; absent data may be omitted and incomplete optional UI data is shown as unavailable without blocking the rest of the report. The frozen Figma dataset remains required implementation input where specified, independently of optional UI scoring.

`$export-experiment-excel <UC-ID> <LINK_OR_FILEPATH> <TAB_NAME>` is invoked separately after final workflow measurement. The AI inspects every target-tab heading and dynamically maps its meaning and row identity across the entire canonical JSON, including telemetry, BR counts, recorded repair data, flow and optional UI results. There is no field-family allow-list. It writes a new Excel copy and cell-level provenance/error receipt, never canonical metrics or newly computed scores. Missing/null/invalid/ambiguous values become literal `N/A` in known writable result cells; formulas, protected cells, unresolved destinations and unrelated/manual content remain unchanged. Missing UI does not block other cells. Measure retains token/time ownership and never invokes this skill. The reporting-only export turn is excluded from workflow telemetry.

## Canonical record

Flow results are persisted in `flow_accuracy.current_summary`, independent of the immutable assessment schema. Projection schema 2 uses `flow_accuracy.selection_policy: accepted-audit-results-v1`: the latest conclusive accepted verdict per frozen flow across all audit stages is reported. Repair/source changes and later `not_evaluable` attempts never erase accepted verdicts. New conclusive results replace earlier ones per flow. `result_scope: experiment_accepted_audit`, `stage: experiment`, and null aggregate `source_revision` prevent attributing all results to one revision. Each row retains its actual evidence assessment, record, stage and source revision. Latest assessment ID/source/status/counts and `retained_from_prior_source_count` expose limitations independently.

The summary records evaluated-only accuracy/error, coverage, bounds, per-flow source, pending details, measurement_status and has_incorrect_flows. Top-level flow fields match the accepted summary: whole-baseline percentages remain null only while accepted rows are unknown; evaluated-only rates are null when none are evaluated. Original assessments keep their status, scores and hashes. Final-source evidence validation still uses the current immutable assessment, not the aggregate report's null source.

For missing accepted results offer both researcher verdicts and bounded LLM measurement. Both paths save directly into canonical JSON in the same turn. `flow_accuracy.followups` is append-only, pins actual evidence parent/hash/stage/baseline/source and request/time, with researcher_result or llm_measurement attribution. Follow-up schema 2 permits re-auditing scored flows. Researcher replies require no additional runtime proof; LLM results retain the frozen evidence standard. The follow-up write preserves source, BRs, metrics, run status and gates. After saving, the coordinator applies [automatic continuation](../00-context/workflow/gates/FLOW-FOLLOWUP-AUTO-REPAIR.md) to the pending Repair Decision, without another confirmation. Save current results and follow-ups in canonical JSON; preserve runtime evidence and immutable assessments. Refresh existing derived reports; Excel remains separately requested. See [follow-up contract](../../.codex/skills/audit-flow-accuracy/references/follow-up-measurement.md). Terminal runs never reopen automatically.

Researcher repair commands record `gate: repair_decision`, outcome `authorized`, the actual command turn/time, evidence hashes and `repair_authorization: {approved: true, turn_id}`. After an all-passing follow-up, the coordinator may record outcome `skipped` with `decided_at`, `automatic_decision` (policy ID/path/checksum, follow-up ID/checksum, source revision and defect lists) and `repair_authorization` with `approved: false`. Automatic skip requires unchanged source and conclusive passing results; defects require the subsequent repair command.

The canonical run JSON records:

- configuration, UC, configured prompt variant, model, replicate, order, wall-clock time and token use;
- frozen final-source checksum;
- initial and final assessment for every frozen BR;
- each BR status: `met`, `unmet` or `not_evaluable`, with evidence and rationale;
- repair count/time/tokens and affected BR IDs;
- optional researcher estimates, UI/flow accuracy and structural complexity.

Required consistency:

- assessed BR IDs exactly equal the baseline's ordered BR IDs;
- each BR occurs once per assessment snapshot;
- overall totals equal status counts;
- repairs never mutate the immutable initial snapshot;
- claims require inspectable source, configuration, build or bounded runtime evidence;
- prompt text alone is not evidence.

No test metrics or generated test cases are part of this schema.

## Gate-closed telemetry (metrics schema version 3)

Run templates set `metrics_schema_version: 3` and `metrics: null` until the requested telemetry command completes. Metrics use `generation_execution_with_repair_audit_v2`: Repair includes integrated verification and core token labels match captured execution. All consumers read `metrics` as the telemetry authority.

Measure is the only telemetry writer. It updates canonical `metrics` and mirrors it under `docs/02-construction/implementation/<UC-ID>/runs/<RUN-ID>/workflow-metrics.json`. The adjacent `workflow-metrics.md` is refreshed on every measurement. `phase-ledger.json` stores live work segments and phase state; `phase-ledger.md` is the readable control record. Audit validates the metrics block and preserves it while updating BR evidence. Renderer reads canonical fields without recomputation.

`metrics` contains UC/run identity, `schema_version: 3`, `token_attribution_method: semantic_primary_phase_per_turn`, `provenance_class: observed_post_run`, `timing_method: system_timestamp_delta`, `timing_protocol: generation_execution_with_repair_audit_v2`, `repair_timing`, `status: open|finalized`, session/hash provenance, selected `turns`, explicit `excluded_turns`, `phase_ledger`, `phases`, `token_phase_breakdown` and `workflow`.

The only core measurement phase keys are `prompt_generation`, `source_generation`, `repair`. Each has `status: not_started|open|closed|skipped` and `values`. Values are null until closed or legitimately skipped. An explicitly skipped repair has a reason and zero observed work; Excel copies its stored zero token/time/turn/tool values, while null model-call counts and unavailable evidence stay N/A. These measurement buckets do not alter the method's two research phases.

Each closed phase's `values`, and `metrics.workflow`, has:

| Field | Meaning |
|---|---|
| `tokens.input_tokens` | Original input counter, including cached input |
| `tokens.cached_input_tokens` | Cached subset of input |
| `tokens.output_tokens` | Original output counter, including reasoning |
| `tokens.reasoning_output_tokens` | Reasoning subset of output |
| `tokens.total_tokens` | Input + output; never add cached/reasoning again |
| `duration_seconds` | Sum of core execution intervals by `timing_phase`; workflow = Prompt + Source + all Repairs, including integrated repair verification under the execution protocol |
| `workflow_turn_count` | Number of selected researcher-initiated turns with the matching token label (all selected turns for workflow) |
| `tool_call_count` | Observable tool invocation records for those token-labelled turns, deduplicated by call ID |
| `model_call_count` | Null until an exact model-request event schema is supported |

Missing cached/reasoning counters have null and `token_unavailable_reasons`. Missing captured time makes the containing aggregate duration null, with `timing_unavailable_reason`; known durations are not passed off as a complete sum. No fresh-input/cache-write fields, money costs, usage-update counts or three-phase subtotal appear in the main report. Parser diagnostics may count usage updates internally, never relabel them as model calls.

Required UC-specific approvals, clarification, Figma/dataset resolution and blocked turns count toward that UC workflow. For tokens, AI labels each completed turn by actual primary work and supplies a reason. Only `prompt_generation`, `source_generation` and `repair` labels contribute tokens to the corresponding core phase. Config/approval-only, dataset-only, audit-only, runtime-only, finalization-only and setup-only turns remain auxiliary even inside an open generation bucket. Failed generation/repair attempts remain chargeable under their actual work. Mixed turns retain one primary label and whole telemetry, never an estimated split. See the shared selection-schema.md. Review every earlier session turn; explicitly exclude common setup, unrelated/other-UC work and every Measure/report-only turn with reasons so earlier UC-specific configuration is not silently omitted.

`turns[].phase` is the semantic token label; `turns[].timing_phase` is the captured timing bucket. Under the execution protocol, a turn with any core execution segment must retain that same core token label, including an unfinished segment; integrated repair audit cannot be labeled auxiliary `audit`. Whole-turn tokens still cover more work than the captured interval. Auxiliary-only turns without core execution have zero counted generation seconds plus `timing_exclusion_reason`, not an observed zero elapsed time. `metrics.phases.<phase>.values.tokens` and counts sum matching token labels; `duration_seconds` sums matching timing buckets. `metrics.token_phase_breakdown.<label>` records all labels, including auxiliary, with five token fields, unavailable reasons and turn/tool counts. Workflow token/count totals include each selected turn once; workflow seconds include only the three core execution scopes. The rendered view shows per-label totals and each turn's token label, timing bucket and rationale. A later standalone Excel export reads these finalized fields without reclassifying or recomputing them.

Timestamp endpoints are captured live by the shared helper with ISO/epoch, UC/run/session/turn/phase/segment/event/source revision. Compute `(end_epoch_ms - start_epoch_ms)/1000`, validate timezone/ISO consistency, reject negative/overlapping or mismatched intervals. End before researcher waits and resume with a new segment. Captured work duration is not an exact UI Worked-for claim. START only after prerequisites, immediately before generating the Draft, first source mutation or each repair execution. END after Draft persistence before review, after first-pass source before build/audit/runtime, or after correction plus integrated BR/flow/runtime verification and final evidence/hash/status persistence, respectively. Do not open overlapping child audit/runtime intervals. Workflow time = Prompt + first-pass Source + all Repairs; standalone configuration/approval/dataset/setup/audit/runtime/finalization time is excluded. Workflow seconds are null while any phase is pending or missing endpoints, and do not represent the gap between first and last chat messages. Each repair has its own endpoint pair with matching `repair_id`; `metrics.repair_timing.<repair_id>` stores `duration_seconds`, `segment_ids` and `timing_unavailable_reason`. Optional auxiliary diagnostic segments remain raw evidence but never enter execution totals.

One turn is indivisible. After the prior response completes, the researcher invokes the appropriate Measure command to close prompt/source telemetry or finalize the workflow. The script rejects current/incomplete selections, missing telemetry, duplicate turns, unexplained gaps, identity conflicts and changes to committed rows. Whole-file session hashes are observation-specific; completed-turn prefix hashes remain stable.

Work may reach terminal `run_status` before `metrics.status=finalized`. The one final workflow measurement turn closes an open Repair bucket (or persists a validated skipped bucket), recomputes and validates all aggregates, records the internal Repair-close and Final transitions in order, and commits finalized canonical telemetry atomically. Repair automatically persists terminal verification and source identity before this command; no separate Repair-close or final-audit turn is required. Explicit refusal and automatic no-defect decisions use their actual `repair_skip_reason`; they do not fabricate successful source results. The current run holds after first generation, requires source measurement and first-pass BR assessment, and requires a recorded authorization from the explicit repair command before correction.
