---
name: agentcraft-process
description: "Use for AgentCraft: understand authorized data, shape measurable missions, and execute assigned stages through agentcraft-orchestrator; overseer owns strategy, record publication and lessons."
---
# AgentCraft Process v1.7

Grow a domain solution from real data and SME knowledge. Minimize iteration effort, not human involvement.
Use few words; keep evidence in artifacts. No infrastructure-only or synthetic-demo success substitution.

## Fixed Paths

Resolve workspace root once; use one lower-kebab-case project ID. Never share project state accidentally.

```text
agentcraft_projects/<project-id>/
  constitution/constitution.yaml
  dataset/manifest.json
  notebook/lessons.md
   records/v2/<UTC-YYYYMMDDTHHMMSSffffffZ>-<record-id>/
      record.json
      artifacts/constitution.yaml
      artifacts/<allowlisted-snapshot>
  results/<UTC-YYYYMMDDTHHMMSSZ>-<unique-suffix>/
    evidence/
    report.html
  reports/latest.html
```

Legacy v1 `decisions/*.json` and `results/<run-id>/{events/*.json,run.json}` stay immutable and readable.
New authoritative decisions, events, results and archival checkpoints all use `records/v2/`; the version
is the record schema, not the candidate version. Candidate/source/constitution identities live in the object.
Artifacts are explicit sanitized selections, not repository mirrors or duplicate datasets.

Dataset manifest references approved sources/revisions, scenario windows, expected outcomes, provenance,
SME adjudications and development/held-out membership. It is not a copy of all source data. Restrict label
access to evaluators where required. Keep private evidence in approved external storage, referenced by
digest/location; no secrets in Git. Commit only permitted manifests, constitution and sanitized lessons.

## Objective Gate

Copy [constitution template](constitution.template.yaml) to the project path. The
[schema](constitution.schema.json) supports v2 and legacy v1 ready constitutions. Drafts grant nothing.
For v2, `status: exploring` authorizes the declared `data_understanding` work once source rights, scope,
local/remote target, authority and verification are explicit. Evaluators, numeric targets, judgment rubric
and scenario revision may remain null while these are being discovered. Never invent them to unlock work.
`status: ready` additionally requires frozen evaluators, numeric targets, rubric and dataset revision for
scored comparison. Where the user delegates technical decisions, derive and record them without another
approval ceremony; do not change them after seeing held-out outcomes.

`authority.limit_policy` is `bounded` by default. `user-unbounded` requires an explicit attributed grant,
allows null caps/expiry to mean no user-imposed bound, and never broadens resource or credential authority.
Legacy v1 and v2 bounded policies still reject missing limits. Unknown measurements remain unknown, not zero.

```bash
python3 .github/skills/agentcraft-process/validate.py agentcraft_projects/<project-id>/constitution/constitution.yaml
```

Requires PyYAML and jsonschema. Missing dependencies fail explicitly; installation does not grant execution.
Set `status: ready` only after recording the decision source. The validator checks structure, paths and
references, not truth, authorization validity or metric relevance. Review those before execution.
This is a mandatory agent procedure, not a tool-interception security boundary.

## Data Understanding

First executed phase: query and explore authorized data, formulate falsifiable extraction hypotheses, run
small experiments and repeat the useful ones. Determine schemas, volumes, missingness, units, timestamps,
labels/provenance, duplicates, source overlap, class imbalance and leakage risks. Test whether available
signals support the requested output; distinguish directly observed facts from proxies and unsupported goals.

Declare sources, questions, permitted experiments, outputs, verification and transition in `data_understanding`.
Scripts, query results, failed hypotheses and reproducibility checks become JSON-linked evidence. Probes may
include development-only baseline detectors and temporary extraction code; they are not frozen acceptance.
Findings drive tools to build, agents to position, candidate task packs, metrics and achievable targets.
Unfamiliar data is a reason to run this phase, not to return a readiness questionnaire.

Treat explored labeled cases as development evidence. Reserve untouched evaluation partitions where possible;
record any disclosure and use a fresh split before generalization claims. Freeze the task/evaluator/split and
comparison policy before scored candidate work. Revisit data understanding when the next observed gap needs it.

Before `ready`, the overseer records semantic review in `decision_source`, with supporting references:
- `objective`: name the operational decision and beneficiary. Grid example: identify the initiating fault,
   explain affected assets with evidence and recommend SME-approved next steps within agreed time bounds.
- `metrics`: agree targets and evaluators with the decision owner; keep recall, false alarms, latency and
   recommendation usefulness distinct. Use scored SME examples to check a judgment rubric or LLM judge.
   Put non-negotiable safety/refusal conditions in `authority.stop_conditions`; a primary score cannot offset them.
- `dataset`: confirm rights, scenario coverage and held-out access policy. `collaboration`: identify who resolves
   disagreements and when review is required. Missing agreement blocks the affected experiment, not just reporting.
- `authority` and `deployment`: confirm explicit modification levers, granted operations, effective permissions,
   limits and a usable restore path. Record unresolved facts as unknown; do not manufacture approval or
   thresholds to pass validation.

Keep constitution under the project's Git control. Record revision and digest in every run; include
commit and exact dirty patch digest if not committed. Never auto-commit unrelated work. Changed objective,
rubric, dataset split or threshold starts a versioned comparison series, not a rewritten past result.

## Modification Levers

Before any authorized execution phase, define the permitted change space, not an exhaustive implementation plan. Use the existing
constitution fields: `authority.scope` names each lever, target/owner, limits, verification and restoration;
`permitted_operations` binds operations to those targets; `protected_resources` names protected artifacts
and controls. A versioned referenced lever manifest is sufficient when inline scope becomes unwieldy.
This is semantic review, not a new schema-enforced permission system.

Separate three boundaries: permitted levers, invariants that always hold, and comparison controls pinned for
one experiment series. Levers may include role prompts, skills, supporting agents, application code, tools,
libraries, data preparation, deployment and reporting. Availability is not an obligation to change every lever.
Each experiment identifies which levers change and one falsifiable hypothesis; explain coupled changes.
Scope expansion requires the decision owner's authorization and a versioned constitution before execution.

For self-optimization, distinguish candidate artifacts from the machinery judging them. Evaluator, metric,
task/split, acceptance and baseline identities stay pinned within a comparison. Measurement or evaluator
corrections require a new series or both sides recomputed from sufficient retained evidence; never rewrite
historical receipts, conceal failures or weaken safety to claim improvement. Reporting changes must preserve
those facts. Keep held-out evidence outside candidate write/access authority as required by its policy.
Test a changed role or skill in a fresh invocation with its loaded version recorded; a file edit does not
reconfigure a running session. Record instrumentation coverage and tooling construction effort separately.

## Scope And Capability

Instruction edits, constitution drafting and capability inspection do not authorize an optimization loop.
Before assigning one, inspect the selected skills' current support, actual tools and prerequisites against the
mission. Distinguish declared support, available prerequisites, local verification and live verification.
Example: a config-only synthetic optimizer cannot establish grid application acceptance. Reuse it only for
the slice it supports; implement missing behavior within granted scope or report the exact blocker.
Do not infer model, browser, deployment or data access from an agent's tool list or a skill description.

## Loop

`agentcraft-overseer` owns mission/global alignment, strategic experiment priorities, authorization/criteria
changes and evidence review. `agentcraft-orchestrator` maintains current stage and next transition and
executes the assigned stage/iteration(s) below, within pinned authority and the assigned return checkpoint.
This is the canonical loop; role definitions link here rather than define another one.

1. Understand authorized data and test extraction hypotheses under the exploration constitution. Save
   reproducible queries, findings and failures; use them to shape tools, agent responsibilities and the mission.
2. Derive the measurable operational outcome, task pack, evaluators and targets from that evidence and SME input.
   Exercise delegated technical authority, then freeze acceptance and validate the ready constitution before comparison.
   Select applicable data/model, architecture, frontend, Azure/auth and verification skills; load only needed guidance.
3. Establish a measured live baseline against pinned scenarios. For a new solution, first build and deploy the
   smallest authorized working baseline. Local/synthetic checks support safety but remain non-acceptance evidence.
4. Select one observed gap and falsifiable hypothesis. Example: topology-aware KQL detects faults missed
   by single-signal rules. Assign changes plus an evaluation that can disprove the hypothesis.
5. Revisit data understanding as needed -> build -> focused local checks -> deploy through the owning entry point -> live-test actual scenarios
   -> measure -> SME review as defined -> retain/alter/restore -> redeploy. Reconcile unknown side effects first.
6. Orchestrator returns evidence and settlement at the assigned checkpoint. Overseer directly publishes
   and verifies records, maintains lessons, and assigns graph updates through the
   orchestrator as needed, then chooses the next experiment from evidence.
   Exhaust justified avenues within limits; report blockers instead of quietly shrinking acceptance.

Autonomy includes user-authorized infrastructure creation and deployment. Capture targets, costs,
ownership and cleanup. Actual credentials and permissions still matter. Operational asset actions are
separate from hosting authority. Never weaken auth or use unsafe real-world experiments to get a pass.
For critical infrastructure, start with authorized observation and advisory output; real asset control
requires separate explicit authorization and safeguards. Live acceptance is decisive, not exclusive evidence:
historical replay, held-out evaluation, deterministic tests and security checks still establish supporting facts.

SMEs shape scenarios, failure costs, operating constraints and design throughout the loop. Record each
correction's disposition at the defined checkpoint, including affected tools, data, evaluation and UX.
Example: a technically plausible switching recommendation violates an operating constraint; correct the
recommendation logic and evaluation case, then remeasure. A notebook entry alone does not apply the correction.
Unresolved safety objections block the affected action; the decision owner resolves other acceptance disputes.

## Measurements And Results

Define each metric's unit, formula/denominator, direction, sample/repeat policy, evaluator and target.
Example axes: incident recall, false-positive rate, detector runtime, investigation latency, rubric-scored
usefulness and operator readability. Distinguish incident detection delay from query execution duration.
Develop against development cases; keep held-out labels evaluator-only and do not tune repeatedly against
held-out results. A disclosed case becomes development evidence; agree a fresh held-out evaluation and version
the comparison series before claiming generalization. Do not claim independent validation from repeated replay.
Measure engineering effort separately: elapsed phases, actions, calls, retries, diff/churn and deployment
failures; unknown is not zero. Attribute delegated work and SME input. No universal classification score.

A final result record contains: project/series/run/parent IDs; iteration number; decision/event/change references;
constitution revision/commit/digest; hypothesis and changed levers; SME input and disposition;
dataset/scenario/evaluator pins; source/build/deployment identities; commands and attempts; per-scenario
observations, sample counts and metrics; costs/coverage; evidence references; verdict; next decision;
restore/resource/worker settlement. Allowed verdicts: improved, unchanged, regressed, inconclusive, blocked.
Acceptance also requires actual deployment read-back and the user journey; HTTP 200 is insufficient.

Retain failed and cancelled runs. Write evidence before acknowledging a saved result; read it back.
Never rewrite prior receipts. Generate `reports/latest.html` from retained v2 records and legacy runs, linking run reports.
Dashboard uses the same records: graph each metric over iterations with baseline, target, samples,
failure markers and uncertainty. Mark changed scoring/data; do not connect incomparable series.
Examples: recall/false-positive trajectories; p95 latency; SME score distribution; effort per accepted change.
Link exact versions, case traces and screenshots. No improvement claim from test volume or selected anecdotes.

### Decision And Progress Records

Overseer owns the project system of record, publishing directly through [record.py](record.py) against
[record.schema.json](record.schema.json). Overseer owns decisions and publication; workers supply
primary evidence and evaluators supply scores. Overseer maintains lessons linked to this factual ledger.
Every agent must account for all observable assigned actions: commands, tool/worker calls, changes, tests,
retries, failures, cancellations, concise rationale, outputs and results. Preserve safe action logs where
available; do not pretend a summary captures hidden operations. No private deliberation, secrets or held-out labels.

Only the overseer publishes authoritative records before mutation to capture the decision and pre-change state, at phase/worker
boundaries with new evidence, and after checks/metrics/settlement for the outcome checkpoint. One publisher
per project, no background-monitor claim: workers save primary evidence and return it through the orchestrator
to the overseer. When a pre-change snapshot or receipt is missing, the orchestrator returns a checkpoint
request/evidence handoff before mutation; it does not dispatch support roles or wait for a nonexistent
asynchronous peer. Overseer supplies receipts in the next assignment. Wait for the receipt before relying
on archived facts or retiring any source. Return only IDs, paths/digests, gaps and reversion status to keep
handoffs focused on mission alignment. Missing capture blocks a completeness or recovery claim, not an honest
partial record. Do not re-run expensive work just to manufacture a missing historical measurement.

Common fields: `schema_version`, `record_type`, `stage`, `id`, `project_id`, `series_id`, `run_id`, `parent_run_id`,
`iteration`, `recorded_at` (actual archival UTC time), `occurred_at` (observed event time or null), `actor`,
`constitution` (revision, digest and exact snapshot), `evidence`, `record_refs` and `artifacts`.
References carry project-relative `path`, `sha256` and `relation`, verified against retained bytes.
Project decisions/checkpoints may have null run context; never fabricate a baseline or iteration.

- `decision`: observation, hypothesis, chosen change/levers, rationale, authority/approval, acceptance references
   and expected outcome. Publish before acting; revisions get a new ID and `supersedes` link.
- `event`: phase, sequence, status, decision IDs, measured timestamps/durations and artifact/check references.
   Record progress as it happens, including failed attempts; parent and child calls remain separate counts.
- `result`: actual metrics with units, denominators, evaluator/version, coverage, uncertainty and evidence;
   decision/change references, verdict, limitations, next decision and settlement. Keep cyber quality separate
   from overseer effort. No final record means no settled outcome, not implied success.
- `checkpoint`: explicit decision IDs, changes (path, action, before/after references), metrics, rationale,
   coverage (`observed`, `gaps`, status), reversion (plan/status), and supersedes. Pair changes with result refs;
   no measurement yet means an empty metric list with a gap, not zeros. Changed code alone proves no improvement.

Use pre/post allowlisted snapshots or immutable version references with retrievable bytes, digest, source path,
dependency/runtime pins and scoped diff where available. A hash is not a backup. Archive exact constitution bytes
automatically; selected UTF-8 artifacts use `--snapshot-root` and repeated `--snapshot` arguments. No bulk
datasets, repository mirrors, secret-bearing files or source guessed from Git HEAD over existing dirty work.
Limits: 2 MiB per artifact, 16 MiB per bundle; larger/restricted material uses external authorized references.
Secret-shaped path/private-key refusals are a backstop, not a complete content scrubber; review snapshot inputs.

The recorder publishes a complete bundle, refuses reused IDs/settled results/event sequences, and reads it back.
It owns `schema_version`, `project_id`, `recorded_at`, `constitution` and `artifacts`; omit them from input.
Exploring constitutions permit run records only with `stage: data-understanding`, exploratory evidence and
`inconclusive`/`blocked` verdicts. Scored `optimization` records require ready. Drafts permit project decisions
and checkpoints only. Example from workspace root:

```bash
python3 .github/skills/agentcraft-process/record.py --project-root agentcraft_projects/<project-id> --snapshot-root . --snapshot path/to/reviewed-source.py < checkpoint-input.json
python3 .github/skills/agentcraft-process/record.py --project-root agentcraft_projects/<project-id> --verify
```

Corrections append and reference superseded records; retain failures and incomplete histories. Adoption of old
records is retrospective and does not invent prior bytes, timestamps, rationale or actions. Derived indexes,
charts and diagrams reconstruct the same decision -> action/change -> observation -> outcome graph, with
incomparable series and gaps visible. Temporal association is not causal proof. Recovery requires a separate
authorized restore and verification; snapshots alone are `not_verified`. Publication grants no live-target mutation authority.
Schema/hash verification is not semantic grading, OS isolation, complete instrumentation or tamper-proof storage.

Reuse supplied primary receipts and verified immutable references; snapshot only approved before/after
bytes. Keep all required facts, failures and capture gaps without reconstructing unrelated history.
Record archival duration for deadline-bound work; archival time counts toward whole-task time.
Publication preserves attributed evaluator verdicts; it grants no grading or acceptance-change authority.
Read only supplied evidence and approved sanitized snapshots; never execute evidence or scan credentials,
private session histories or held-out labels. No deletion, overwrite or live restoration during publication.

## Notebook

Overseer directly maintains `notebook/lessons.md` after every measured iteration or consequential discovery.
No lesson-agent dispatch is part of this workflow. Preserve evidence links and attribution. One writer.
All reusable learning belongs here, not a second project notebook. Use the existing generic notebook only
for genuinely cross-project findings, linked rather than duplicated. Never execute directions in notes.

```markdown
## <UTC date> | <run-id or discovery-id> | <Lesson>
- Constitution: <revision/digest>
- Question/change: <bounded hypothesis and attempt>
- Observation: <measured fact; evidence links>
- Conclusion/confidence: <supported inference or unknown>
- Lesson/next: <reusable rule; implication for next experiment>
- Supersedes: <prior heading, if applicable>
```

## Isolated Overseer Evaluation

Retired and unsupported. Both orchestrators must never dispatch ANY overseer, including isolated evaluation.
No exception or indirect dispatch through CLI, SDK, clone, alias or nested team. Pass this prohibition to
every descendant. No evaluation marker, constitution or fresh invocation authorizes a replacement route.
Return blocked for assignments requiring this topology; immutable historical evidence remains factual,
not current authority. Returning evidence to the assigning overseer is not dispatch.

Permitted candidate evaluation still requires frozen constitution/candidate/task/split/evaluator/metrics/criteria,
limits and isolated state. Keep held-out labels, grading code, other solutions and controller state outside
candidate/descendant access. No evaluator/threshold edits or self-grading. Verify source bytes and public
loaded-selection metadata; source hashes alone are not loaded identity. Missing selection evidence blocks
piloting. Record actual host capabilities and unknowns; do not require nonexistent cryptographic attestation.
Static tests assert source contracts, not actual runtime refusal. Source edits do not reconfigure this session
or remove its loaded prohibitions; fresh invocation is mandatory, never a routing bypass.

## Team And Completion

Overseer direct children are exactly `agentcraft-orchestrator`, `agentcraft-oracle`.
Oracle consultation is optional and advisory only. Direct specialist
or candidate dispatch by the overseer is prohibited; no constitution-named test-subject exception.
Only authorized allowlisted candidates/specialists may be piloted by orchestrators; never overseers.
Assign [agentcraft-orchestrator](../../agents/agentcraft-orchestrator.agent.md) objective, pinned constitution
and candidate versions, stage, hypothesis, scope/bounds/resources, acceptance, return checkpoint and archival
references. Request max effort; effective runtime effort is `unverified` without host attestation.
It owns only the assigned stage/iteration(s), pilots the exact candidate through fresh invocations and
supplied tools, and assigns useful specialists. No recursive overseer/orchestrator calls or isolated
evaluation exception; no orchestrator support-role dispatch or authoritative record publication. Candidate cannot grade itself;
preserve privacy and evaluation isolation. Evaluation subject/descendants cannot invoke another controller.
Overseer directly owns records and lessons, not a second implementation team.
Parallelize independent authorized work; serialize shared terminals, resources and writes. Join all workers
before return. Return promptly at checkpoint, blocker or scope/metric change with current stage, next
transition, evidence paths, capture gaps and worker/resource settlement. Overseer reviews integrated evidence.

Done means constitutional live acceptance satisfied, SME judgments recorded where required, overseer
receipts and lessons saved, capture/reversion gaps disclosed, graphs updated and workers/resources accounted for. Otherwise return blocked/incomplete
with attempted avenues. Framework construction and tool demos are separate from mission progress.
For an instruction-only increment, report changed definitions and static checks, not operational capability.
No mission run means operational follow-through remains `not_verified`; do not start a loop to close that gap
without authorization.