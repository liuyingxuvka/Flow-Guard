# Modeling Protocol

This document is the `core_modeling` sub-protocol for the FlowGuard Skill
Kernel. The main Skill routes here for ordinary model-first work. Specialized
routes such as UI flow structure, code structure recommendation, model-test
alignment, model topology hazard review, Risk Evidence Ledger, ModelMesh,
TestMesh, StructureMesh, DevelopmentProcessFlow, model-miss review,
conformance/adoption, long-check observability, and framework upgrades live in
their dedicated reference protocols.

Use this protocol before implementing non-trivial behavior involving workflows, state, retries, deduplication, idempotency, caching, or module boundaries.

## 0. Choose The Lightest Mode

Before changing files, separate three situations:

- `read_only_audit`: inspect an existing project without changing production
  code. Run import preflight, existing FlowGuard models/replays when present,
  adoption evidence review, and stale fallback checks. Do not create a new model
  solely because the task is read-only.
- `model_first_change`: production behavior may change. Build or update the
  fit-for-risk model before editing production code. If no FlowGuard model
  exists yet, create one from the current plan or adapt the model template.
- `model_maintenance`: existing `.flowguard` models, replay adapters, or
  adoption evidence appear stale. Update those artifacts before making claims
  from them.
- `artifact_schema_upgrade`: a repository has an older FlowGuard adoption
  record or old FlowGuard artifacts/tests/guidance. Audit the old shape and
  stop. Do not run a migration, compatibility reader, or automatic rewrite.
  The maintaining agent must directly rewrite the current model/artifact,
  then rerun current checks and receipts; block ambiguous or stale data
  instead of preserving an old runtime path.
- `layered_boundary_proof`: parent model confidence depends on child models and
  leaf real-code boundary evidence. Join parent coverage, child disjointness,
  child reattachment, and leaf boundary-matrix rows before claiming the parent
  stayed inside its model.
- `model_test_alignment`: model obligations and ordinary tests both exist, and
  the risk is whether scenarios, invariants, hazards, transitions, contracts,
  or owner code external contracts have matching current test evidence. When
  broad transition coverage is claimed, derive a transition coverage matrix so
  modeled transitions become explicit Model-Test Alignment obligations and
  owner code contracts. When
  real Python source/tests are in scope, first run or request conservative
  source audit evidence for the code and test rows.
- `contract_exhaustion_mesh`: a declared finite boundary, same-class family,
  payload contract, transition matrix, parent/child closure, or no-delta loop
  must be expanded into canonical bad-case ids with explicit oracle reactions
  and downstream route handoffs. Broad/full claims must also declare the
  coverage universe and make observed real misses map back to generated and
  same-class case ids. Use this after the owning route declares the boundary
  and before treating similar-bug or exhaustive-boundary coverage as current
  evidence.
- `model_topology_hazard_review`: a locally green model topology may imply
  future-use hazards before broad done, release, publish, or full-confidence
  claims. Read topology and usage intent first; only hazards with concrete
  anchors can affect confidence.
- `test_mesh_maintenance`: validation is too large, broad, stale-prone, or
  layered to trust as one flat test command or script. Build a TestMesh that
  partitions parent test confidence into child-suite/script ownership and
  evidence contracts.
- `structure_mesh_maintenance`: structure refactoring is the risky boundary.
  Build a StructureMesh that partitions a large script, package, module,
  command, or API surface into child-module ownership and compatibility
  evidence contracts.
- `code_structure_recommendation`: implementation structure is unclear or the
  user asks for a code architecture recommendation. Use or create a FlowGuard
  functional model, then recommend module boundaries, ownership maps, facades,
  side-effect adapters, and validation boundaries without writing production
  code.
- `ui_flow_structure`: UI interaction behavior itself needs modeling before
  layout or visual design. Build or review the UI interaction model first,
  then derive parent/child UI topology, menu levels, stable placements,
  overlays, navigation ownership, and state/control/event ownership.
- `development_process_flow`: non-trivial staged development or modification
  with validation, development lifecycle ordering, artifact overwrite,
  validation evidence freshness, peer writes, V-style validation pairs, or
  minimum revalidation is the risky boundary. Use this sibling route to review
  lifecycle rows without supervising ModelMesh, TestMesh, StructureMesh, or
  Model-Test Alignment internals.
- `development_process_flow`: a non-trivial FlowGuard-managed project change is
  ending or changing direction and the agent must check whether changed
  artifacts, remembered maintenance obligations, stale evidence, skipped
  checks, or split/reduction signals require an owner route.
  DevelopmentProcessFlow consumes those typed inputs directly and reopens only
  their exact owners; it does not delegate this decision to another scanner.
- `risk_evidence_ledger`: a final done, release, publish, or full-confidence
  claim depends on whether user risks are linked to model obligations, owner
  code contracts, and current proof evidence. Use this boundary after the
  producing routes have generated evidence; do not treat it as a replacement
  for Model-Test Alignment, TestMesh, ModelMesh, StructureMesh, UI Flow
  Structure, conformance replay, or ordinary tests.
- `model_impact_freshness`: a FlowGuard framework upgrade or installed-helper
  sync must account for existing `.flowguard` models. Classify each model
  against the upgrade impact, rerun affected models, and allow unchanged models
  to reuse previous evidence only with a current reuse ticket.
- `model_maturation_loop`: later model-miss, model-test, state-closure,
  topology-hazard, ModelMesh, code-boundary, or freshness evidence says the
  model itself is too coarse, stale, disconnected, or only supports a scoped
  claim. Translate that signal into a model-upgrade action before broad
  confidence is claimed.
- `flowguard_closure_contract`: a guard-family child closure helper may support
  a full done, release, publish, or production-confidence claim from FlowGuard
  evidence, but RiskEvidenceLedger remains the final broad-confidence owner.
  Treat the closure chain as intrinsic support, not as a direct route mode:
  required
  plan/risk intake, model ownership, exact commitment and blueprint-gap
  identity for a model miss, finite canonical relations and
  ContractExhaustionMesh case ids, task-bound ModelMaturation evidence,
  model-test/code alignment, affected topology/parent replay when relevant,
  evidence freshness, Risk Evidence Ledger, and typed claim-chain support must
  be current or the claim stays partial/scoped.

If real FlowGuard is importable but a current `.flowguard` Python model still
claims `flowguard_package_available = False`, uses a fallback finite runner, or
defines local replacement `Workflow` or finite-runner classes, record a
`stale_fallback_model` warning. This is a confidence gap, not a hard failure.
If a current `.flowguard` model calls the internal finite runner directly without a
`FlowGuardCheckPlan`, `RiskIntent`, `MinimumModelContract`, and
`KnownBadProof`, record `direct_runner_formal_entry_required` and upgrade the
model before making a complete FlowGuard claim.

## 0.2 Enter The Process Simulator For Rough Plans

When the request is non-trivial but still a rough idea, short plan, or
AI-generated outline, enter `flowguard-development-process-flow` first as the
development-process simulator and record `plan_detailing` before writing the
behavior model. Delegate to PlanDetailing when full rows are needed. Create
`PlanDetail` rows for goal, sources, risk surfaces, artifacts, state surfaces,
side effects, ordered steps, receipts, validation, failure branches, rework
gates, human-review questions, freshness rules, and final evidence. Run
`review_plan_detail(...)` and keep scoped or missing rows visible.

After delegated detail review, project rows with `plan_detail_to_plan_intake(...)`,
`plan_detail_to_step_contracts(...)`,
`plan_detail_to_development_process(...)`, and
`plan_detail_to_agent_workflow_plan(...)` as needed. A plan-detail pass means
the plan is detailed enough to proceed; it is not implementation or production
confidence.

Keep the API surface boundary clear:

- core modeling primitives use `FunctionBlock`, `FunctionResult`, `Invariant`,
  and `Workflow`;
- formal model-first entry uses `FlowGuardCheckPlan`,
  `run_model_first_checks`, `RiskIntent`, `MinimumModelContract`,
  and `KnownBadProof`;
- reporting helpers explain gaps and skipped work, but warnings are not hard
  failures;
- evidence and benchmark helpers are mainly for FlowGuard maintenance and
  upgrade validation, not ordinary project gates.

See `docs/api_surface.md` for the public API layer map.

## 0.25 Create Or Evolve The Model Script

FlowGuard does not require an existing production implementation or an existing
model script. It does require the real `flowguard` package to be connected
before claiming FlowGuard adoption. When that import preflight passes and no
model exists yet, create one from the current plan or adapt the included model
template. The model script is the executable design artifact that makes the
proposed workflow inspectable.

The first model should be small enough to review, but it does not have to be
the shortest possible script. It should be fit for the customer's risk: include
the state, branches, retries, side effects, ordering constraints, and invariants
needed to make the important failure modes visible. When later work reveals new
risks, revise, strengthen, or connect the model instead of treating the first
version as final.

When creating or materially updating a FlowGuard model file, put a short
**Risk Purpose Header** at the top of the model. It should identify FlowGuard
and link to `https://github.com/liuyingxuvka/FlowGuard`, then explain which
workflow the model reviews, which concrete bugs or invalid states it guards
against, when future agents should run or update it, and the companion command
that runs the checks. Keep this as a lightweight model header; do not add
manifest files or extra project scaffolding unless the task separately requires
them.

## 0.3 Check The Model-Test Alignment Trigger

Before trusting a claim that model coverage and test coverage agree, ask
whether the model obligations need a direct test-evidence alignment review.
Trigger Model-Test Alignment when a FlowGuard model has explicit scenarios,
invariants, hazards, state transitions, or input/output contracts and ordinary
tests are expected to prove those obligations. Every required model-backed
behavior in the confidence claim needs an owner code external contract row in
the same direct review, including public functions, APIs, CLIs, facades,
adapters, persisted outputs, and other externally visible code surfaces.
When that code surface claims finite inputs or outputs, include
code-boundary conformance rows so real-code observations prove allowed inputs,
rejected inputs, outputs, error paths, state writes, and side effects stay
inside the declared boundary.

When a claim depends on which useful business route was exercised, record
business path identity before trusting the model/test match: stable path id,
business intent, trigger, expected terminal, state writes, side effects,
equivalent or exclusive paths, old-path disposition, and source/runtime
evidence ids. Runtime path evidence should bind observations to the same
business path, not only to a node id.

Model-Test Alignment is not a mesh route. It does not split tests, split code,
split models, or read TestMesh, StructureMesh, or ModelMesh reports. It
compares `ModelObligation` rows, required owner `CodeContract` rows, optional
`CodeBoundaryContract` / `CodeBoundaryObservation` rows, and `TestEvidence`
rows and reports missing evidence, missing or mismatched code contracts,
boundary-crossing code observations, orphan tests, orphan code contracts,
duplicate same-kind test claims, duplicate code contract owners,
internal-path-only tests, model-code-test binding mismatches,
stale/non-passing evidence, missing required test kinds, and overclaimed model
confidence.
If a `TestEvidence` row reuses a previous result, mark `result_reused=True` and
attach a current `TestResultReuseTicket` plus `ProofArtifactRef`; the old result
must prove unchanged command, test source, tested artifacts, dependencies,
environment, result fingerprint, and covered obligation scope.

For transition-heavy models, use `TransitionCoverageMatrix` and
`transition_coverage_to_model_obligations(...)` before a broad coverage claim.
If the resulting cell set is too large or slow for direct evidence rows, use
`transition_coverage_to_required_leaf_cell_ids(...)` and route the evidence
hierarchy to TestMesh while keeping the semantic obligations visible in
Model-Test Alignment.

When several obligations are being treated as one family-level promise, add
`ObligationFamily` and `ObligationFamilyEvidence` rows. The family review blocks
green alignment when one sibling lacks a required mechanism, when evidence is
manual/controller-level but the family requires durable reconciliation, or when
the family evidence is stale, non-passing, or internal-only for an external
claim.

When real Python code and tests are available, add conservative source audit
evidence before trusting the rows. The audit should parse AST-visible source
and test structure, generate or check code-contract evidence and
test-assertion evidence, and feed those rows into the same alignment review.
It is deliberately limited: it is not a perfect semantic proof for Python, does
not replace conformance replay, and must send dynamic, ambiguous, or complex
behavior to manual review.
For real-code claims that name concrete paths and symbols, attach the source
audit report to `ModelTestAlignmentPlan.source_audit_reports` and set
`require_source_audit=True`; a missing, red, or unrelated green audit keeps the
binding row blocked.

When a counterexample trace or known-bad proof is part of the repair, record it
as a `ClosureEvidenceTarget`. The closing `TestEvidence` must be current,
external-contract or mixed-scope, bound to the owner `CodeContract`, and use the
same `evidence_target_id` with `counterexample_regression` or
`known_bad_replay`. A happy-path test for the same function is not enough.

Use `review_model_test_alignment(...)` for this direct comparison. Use
`review_code_boundary_conformance(...)` when only the real-code boundary needs
a focused review.

Use TestMesh only when the validation flow itself is large, slow, layered, or
needs parent/child suite ownership. Use StructureMesh only when a large script,
module, command, or API surface is being split. Use ModelMesh only when the
risk is parent/child model evidence or model partitioning.

Read
`.agents/skills/flowguard/references/model_test_alignment_protocol.md`
for the checklist and prompt template.

## 0.34 Check The Risk Evidence Ledger

Before saying a task is fully validated, release-ready, done, or safe to
publish, build or update a risk evidence ledger for the important user-facing
risks. Each row should name the risk, the owning FlowGuard model obligation, the
public code contract when that matters, and the proof evidence IDs that are
current. If the risk follows a model miss, the row should also name the exact
commitment, blueprint gap, generated ContractExhaustion coverage, and
independently verified ModelMaturation evidence id.
If the risk depends on several related obligations being equivalently covered,
the row should also name the current obligation-family gate and whether that
gate is full, scoped, partial, or blocked.
The affected scope comes from declared current DNA/BCL/topology relations; an
unmaterialized required relation remains blocked rather than triggering a free
repository-wide search.

Use `review_risk_evidence_ledger(...)` to make these gaps explicit:

- a risk was modeled but has no proof evidence;
- a remembered maintenance obligation is missing, still open, stale, or
  resolved without owner-route evidence;
- a test passed only through an internal helper path instead of the external
  contract;
- evidence is stale, skipped, failed, progress-only, or still running in the
  background;
- child or sibling route evidence has not been reattached to the parent claim;
- a scoped-out risk has no reason, or a report overclaims full confidence.

When the final claim depends on an AI-built plan or a project evidence adapter,
run the plan-intake and typed claim helpers first:
`review_plan_intake_completeness(...)`,
`review_evidence_adapter_conformance(...)`,
`review_false_negative_backpropagation(...)`, `review_plan_mutations(...)`, and
`review_flowguard_claim_chain(...)`. They check whether the ledger rows and
claim promotion were too narrow before the ledger is used as final evidence.

When the final claim is a FlowGuard framework upgrade, run
`review_model_impact_freshness(...)` before broad freshness claims about old
models. Do not rerun every historical model by default. Do not reuse prior
green results silently. The allowed shortcut is a current not-impacted
classification plus a reuse ticket that names the prior evidence and proves the
model output or fingerprint stayed the same.

## 0.33 Check The Model Maturation Loop

After implementation, validation, model-miss review, Model-Test Alignment,
ModelMesh, TestMesh, code-boundary review, or evidence-freshness review has
produced new signals, ask whether the model needs to mature before the claim can
stay broad. Use `review_model_maturation_loop(...)` to turn those signals into
explicit actions such as adding a state field, transition case, invariant,
same-class scenario, code-boundary observation, model obligation, child split,
parent reattachment, or evidence refresh.

This check is deliberately small. It does not replace the owning route that
found the signal. It answers the follow-up question: "Does this evidence mean
the model is still too coarse for the claim we are making?" If yes, either
upgrade the model and rerun the relevant checks, or downgrade the final claim to
the scope that the current model actually proves.

Read `docs/risk_evidence_ledger.md` for the API sketch and template.

## 0.345 Check The FlowGuard Closure Contract

Before saying FlowGuard was fully used for a done, release, publish, or
production-confidence claim, verify the closure contract for the claim. The
thin model-first path starts the work; it does not replace final claim support.

The closure contract consumes evidence from the sibling routes that actually
own each boundary: plan intake and adapter conformance for source coverage,
Existing Model Preflight for model ownership, Model-Miss Review for
non-trivial bug repairs and post-green bugs, Model-Test Alignment for
model/code/test rows, ModelMesh/TestMesh or
layered proof for parent/child confidence, the model maturation loop for
post-evidence model-upgrade signals, DevelopmentProcessFlow for freshness, Risk
Evidence Ledger for user-risk support, and the typed claim-chain helper for
scope promotion. Missing or stale required support means partial/scoped
FlowGuard evidence, not complete FlowGuard use.

## 0.35 Check The Local Model Mesh Trigger

Before trusting prior green results, scan for existing local FlowGuard models,
runners, persisted result files, adoption logs, and replay/conformance
artifacts. If the project has three or more local FlowGuard models, or the
current decision spans multiple existing model boundaries, create or update a
local model mesh before making broad continue, release, completion, or
production-confidence claims. Also trigger mesh review when a single new or
legacy model is too large to inspect comfortably, such as an estimated or
observed state count above the configured threshold, a budgeted model group that
remains incomplete, or one model mixing several unrelated functional areas.

The mesh is a model-of-models. It should inventory child models and classify
their evidence tiers, freshness rules, dependencies, contracts, skipped checks,
and blindspots. Do not inline every child model's full state graph unless a
specific contradiction requires a narrow adapter.

For hierarchical modeling, treat the parent model as a total map and child
models as region maps. The mesh should check the partition map for complete
coverage, excessive sibling overlap, duplicate state-write ownership, duplicate
side-effect ownership, stale evidence, and split-review decisions for oversized
models. A child can become a parent and have its own local partition map and
mesh review when that child grows large enough to split again.

When the parent claims whole-flow confidence, also model the model-to-model
handoffs themselves. A `MeshClosureModel` records root entries, child outputs,
parent or sibling consumers, required joins, terminal dispositions, and
out-of-scope branches as finite FlowGuard-style obligations. Parent mesh green
confidence for whole-flow claims requires that closure model to pass; otherwise
the mesh is only evidence for partition, target split, reattachment, and
freshness.

Before a ModelMesh parent can trust the child-model layout, record a target
split derivation from the FlowGuard source model or model-of-models. The
derivation must name the source model, target child model ids, covered partition
items, state owner fields, side-effect owner fields, and rationale for the
split. A partition map alone is not enough parent confidence.

When a non-trivial bug repair or post-runtime miss changes a local child model,
route through Model-Miss Review and the affected ModelMesh. The child-local
pass is not complete until the parent reattachment gate consumes the current
child evidence id and confirms the input, output, state, side-effect, and
outgoing-contract handoff still matches the parent flow.

When the model hierarchy is meant to prove code boundaries, add layered
boundary proof after the mesh inventory. The parent model must have every
responsibility owned or explicitly scoped out, child models must be disjoint
except for declared bridge/shared-kernel cases, the parent must consume each
current child evidence id, and every leaf model must have a complete finite
`Input x State -> Set(Output x State)` matrix backed by real-code tests or
observations. If a leaf cannot be fully covered, split it into a lower model
instead of treating a coarse internal test as enough.

When code progress output is used as model/code evidence, emit runtime path
observations that name the FlowGuard `model_id`, `model_path`, `node_id`, run
id, status, and obligation or code contract. Anonymous progress logs do not
prove model alignment; use runtime path evidence rows so another AI can find
the model being compared.

Keep the current bug instance separate from the bug class. Model-Miss Review
owns classification and same-class representation or out-of-scope recording;
ModelMesh owns child-boundary propagation upward and affected sibling review
when the repair changes inputs, outputs, state ownership, side-effect
ownership, risk boundary, or outgoing guarantees. Background long-running
checks may support either route only after final artifacts and exit status
exist; progress is liveness, not pass evidence.

Read `docs/model_mesh_protocol.md` for the inventory fields, evidence tiers,
required hazards, prompt template, and completion standard. At minimum, the
mesh must catch abstract-only permission, hidden skipped live/replay checks,
stale result reuse, unregistered model evidence, cross-model contradictions,
hidden blockers, missing conformance, unrepresented model misses, sealed/private
body reads, stale installed skill/source copies, oversized mesh expansion, and
absence of a mesh when the model count or large-model threshold is met. For
child repairs, it must also catch child-local green evidence that was not
reattached to the parent.

## 0.4 Check The TestMesh Trigger

Before trusting a broad validation claim, ask whether tests need their own
parent/child hierarchy mesh. Trigger TestMesh when a large test script, suite,
or validation flow should split into child suites/scripts, when a suite is too
slow for routine work, mixes unrelated behavior or release gates, runs in the
background, hides skips or timeouts, or depends on stale result reuse.

The TestMesh is the test-side sibling of ModelMesh and StructureMesh: the
parent test gate is the total validation contract, while child suites or child test scripts own regions of that contract. The parent layer consumes child
ownership and evidence contracts instead of expanding every child test case,
fixture, or internal state route. A child suite can become its own parent gate
when it grows large enough to split again.

TestMesh does not run pytest, unittest, Playwright, shell commands, or manual
checks. Project adapters run the suites and pass `TestSuiteEvidence` into
FlowGuard. The parent gate lists `TestPartitionItem` entries for behavior,
state, module, command, side effect, invariant, or release boundaries.
`review_test_mesh(...)` checks coverage, ownership conflicts, freshness,
skipped visibility, timeout/failure status, background completion artifacts,
routine-vs-release confidence, and reused-result proof. A reused child suite
needs both a current `TestResultReuseTicket` and proof artifact before it can
support parent confidence.

Before TestMesh parent confidence, record a target split derivation from a
FlowGuard validation-structure model. The derivation must name the source
model, target child suites/scripts, covered partition items, state owner fields,
side-effect owner fields, and rationale for the split. A flat child-suite list
without derivation is not enough.

Read `docs/test_evidence_mesh.md` for the API sketch and
`.agents/skills/flowguard/references/test_mesh_protocol.md` for
the agent checklist.

## 0.45 Check The StructureMesh Trigger

Before trusting a large script or module split, ask whether the structure needs
its own parent/child ownership mesh. Trigger StructureMesh when functions,
state, config, side effects, public entrypoints, behavior contracts, or release
obligations are being split across child modules.

The StructureMesh is a structure-refactor evidence model for existing large
scripts or modules. It does not move code or parse source files. Before
ownership review, it requires a FlowGuard model-derived target child structure:
FunctionBlock-to-module, state-owner, side-effect-owner, facade, and validation
maps. Project adapters collect source inventory, model-derived target
structure, dependency edges, facade status, public entrypoint compatibility,
config/default changes, and parity evidence, then pass
`CodeStructureRecommendation`, `ModuleStructureEvidence`,
`PublicEntrypointEvidence`, and `StructurePartitionItem` objects into
`review_structure_mesh(...)`.

Read `docs/structure_mesh.md` for the API sketch and
`.agents/skills/flowguard/references/structure_mesh_protocol.md`
for the agent checklist.

## 0.47 Check The Code Structure Recommendation Route

Use the parallel code structure recommendation route when a user directly asks
for a code architecture recommendation, or when a functional model exists and
the next implementation step needs a module/function split plan. This route can
create or use a functional or hierarchical model, but it does not write
production code and it is not mandatory for every ordinary model-first task.

Read `docs/code_structure_recommendation.md` and
`.agents/skills/flowguard/references/code_structure_recommendation_protocol.md`
for the recommendation shape.

## 0.48 Check The UI Flow Structure Route

Use the parallel UI flow structure route when a UI's buttons, menus, controls,
screens, panels, overlays, navigation, information displays, state
availability, duplicate/overlapping controls, headings, labels, action text,
status/helper messages, error/recovery copy slots, complete app
launch-to-terminal journey coverage, or implemented/runnable UI click-through
evidence alignment need a model-first interaction flow before
visual design or frontend implementation. This route models the UI as
`UI event x UI state -> Set(UI output x UI state)`, reviews that interaction
model, reviews journey coverage and reachable visible-control/event ownership
when a complete app-level UI claim is made, validates feature/UI/click-through
evidence when an implemented UI claim is made, derives parent/child UI topology,
first-level persistent menus, second-level contextual regions, third-level
local controls, information-display ownership, stable layout positions, overlay
hierarchy, and explicit rationale for intentional redundancy, then derives the
UI text hierarchy blueprint from the reviewed structure.

Read `docs/ui_flow_structure.md` and
`.agents/skills/flowguard-ui-flow-structure/references/ui_flow_structure_protocol.md`
for the route shape.

## 0.49 Check The DevelopmentProcessFlow Route

Use the parallel development process route for non-trivial staged development
or modification work that has validation, such as plan, edit, test, fix, and
verify. Also use it when the question is whether a done, release, archive, or
publish claim still has current evidence after lifecycle steps changed
requirements, designs, models, code, tests, docs, adapters, or release
artifacts. This route models the development lifecycle itself as a stateful
process. It may reference sibling route evidence ids and covered artifact
versions, but it does not inspect or replace sibling routes.

Read `docs/development_process_flow.md` and
`.agents/skills/flowguard/references/development_process_flow_protocol.md`
for the lifecycle evidence shape.

## 0.5 Write A Minimum Valuable Risk Intent

Before defining state or function blocks, write the short brief that tells the
model what accidents it is meant to expose. This is the agent's own preflight;
ask the user only when materially different risk priorities exist and the
protected harm cannot be inferred safely.

Answer these questions before creating or editing the model:

- Which failure modes are we trying to prevent?
- Which protected error class should this model make impossible or visible?
- What protected harms would happen if those failures slipped through?
- Which state fields, side effects, confirmations, durable records, or external
  commitments must be modeled or the failure would be invisible?
- Which completion evidence proves the workflow is actually done?
- Which adversarial inputs, repeated inputs, retries, partial successes,
  ordering changes, concurrent actions, or exception branches must be simulated?
- Which representative known-bad implementation or trace should fail?
- Which hard invariants must never be weakened merely to pass checks?
- What blindspots remain because the model is intentionally smaller than the
  real workflow?

The first/default model should be a minimum valuable model, not a happy-path
stub. It can stay small, but it needs state, side effects or completion
evidence, and at least one known-bad case with current proof that the broken
variant fails unless the claim is explicitly scoped.

Template reuse/publication is a separate conditional operation. Enter the
single strict `risk_template_library` route only when the user explicitly asks
for template reuse/publication or current executable evidence identifies a
bounded stable pattern intended for use outside the target project. Then ask
which packaged public or per-machine local templates match, record exact used
ids or a reviewed no-match, and close harvest by writing, merging,
duplicate-linking, or recording an accepted not-harvestable reason. Ordinary
modeling, repair, maintenance, cleanup, and release do not search templates or
create no-match/harvest records merely to finish.

Put the brief into `RiskProfile` through a `RiskIntent` or equivalent
`risk_intent` mapping, bind the minimum model contract and known-bad proof on
the `FlowGuardCheckPlan`, and run `run_model_first_checks(plan)`. Direct
finite engine calls remain internal execution primitives, not the formal
entry for non-trivial model creation.

## 1. Identify External Inputs

List the finite abstract inputs that can enter the workflow. Use behavior classes, not full production payloads.

Examples:

- A new job.
- The same job repeated.
- A low-signal item.
- A retry after partial progress.
- The same rejected AI packet repeated after missing feedback.

## 2. Identify Abstract Finite State

Model only state that affects future behavior or invariants. Use hashable immutable values such as frozen dataclasses, tuples, strings, integers, booleans, and frozensets.

Do not use live databases, files, network calls, clocks, random values, or LLM calls.

## 3. Identify Function Blocks

Split the workflow into named function blocks. Each block should correspond to one behavioral boundary, such as scoring, recording, decisioning, validation, cache lookup, or persistence.

Each block must represent:

```text
Input x State -> Set(Output x State)
```

## Model Fidelity Requirement

Treat the model as a falsifiable simulator of the real workflow, not as ground
truth. Before trusting model findings, compare representative traces with real
code paths, logs, tests, user workflows, or production conformance evidence when
available.

Choose the smallest model that is faithful enough for the current risk. Include
the control-flow branches, state writes, retry/cache/deduplication behavior,
terminal paths, exceptions, and side effects that could affect the bug class
under review.

If a trace is impossible, suspicious, or misses known production behavior,
revise the model, scenario oracle, or replay adapter first, then rerun the
checks. Do not report model-level confidence as production confidence until
conformance evidence supports it.

## 4. Define Possible Outputs

For each block, enumerate every output class the block may produce. If a score can be `low`, `medium`, or `high`, return all possible score outputs for that abstract input and state.

Do not hide possible outcomes in comments or prose.

## 5. Define State Reads and Writes

For each block, document:

- `reads`: state fields that affect the result.
- `writes`: state fields the block may change.

This exposes state ownership and prevents the model from spreading writes across the wrong modules.

Before trusting an invariant over a state field, make a state write inventory.
For every field named by the invariant, search the production code for all
writers of that field and record whether each writer is modeled, intentionally
skipped, or outside the current boundary.

Examples:

- `recommendation_status`
- `output_status`
- `analysis_json`
- cache/source-of-truth fields
- queue or retry status fields

If a field has multiple production writers, cleanup jobs, runtime repair paths,
or finalizers, missing one writer is a model-fidelity gap. It is not an
automatic FlowGuard runtime failure, but it must be visible before claiming
production confidence. See `docs/state_write_inventory.md` for the lightweight
table format.

## 6. Define Idempotency

Write down what happens if the same input reaches the same block again.

Examples:

- A cached job score should be reused.
- A duplicate record should return `already_exists`.
- A retry should not create a second side effect.

## 7. Define Failure Modes

Model expected failures explicitly. A block may return zero results, but that creates a reportable dead branch. If a branch is supposed to terminate, model it as a terminal output or a consumed output rather than letting it disappear.

Unexpected exceptions should be reported structurally, not swallowed.

## 8. Define Invariants

Write hard invariants over state and trace. They should describe guarantees that must hold on every explored path.

Examples:

- No duplicate records.
- No repeated scoring without refresh.
- Every application record has a cached score.
- No contradictory final decisions.
- No hidden second source of truth.

Do not weaken invariants merely to make checks pass.

When the bug class matches a common pattern, prefer the standard property
factories in `flowguard.checks` over hand-written boilerplate. Examples include
`no_duplicate_by`, `at_most_once_by`, `all_items_have_source`,
`no_contradictory_values`, `cache_matches_source`,
`only_named_block_writes`, `require_label_order`, and `forbid_label_after`.
These factories still return ordinary `Invariant` objects. They are helper
building blocks, not a required modeling layer.
They also attach optional `property_classes` metadata, such as
`deduplication`, `at_most_once`, or `cache_consistency`, so `audit_model(...)`
can recognize common property types without relying only on invariant names.
Custom invariants can add the same metadata when useful, but metadata is not
required and unknown values are not hard failures.

For common risks, optional domain packs can reduce boilerplate:
`DeduplicationPack`, `CachePack`, `RetryPack`, and `SideEffectPack`. A pack only
uses selectors and key functions you provide. It does not infer state, enforce
a model shape, or become a required structure.

For neutral starter scaffolds, the public CLI can print or write templates:

```powershell
python -m flowguard project-template --output .
python -m flowguard risk-intent-template --output .
python -m flowguard model-miss-template --output .
python -m flowguard code-structure-recommendation-template --output .
python -m flowguard structure-mesh-template --output .
```

Treat them as starting points only. Rename the state, inputs, outputs,
invariants, and blindspots to match the real workflow before claiming
confidence.

For recurring multi-role maintenance systems, such as
Sleep/Dream/Architect/Installer/Reviewer flows, the optional maintenance
template can reduce setup time:

```powershell
python -m flowguard maintenance-template --output .
```

It scaffolds repeated-action, missing-report, and install-sync checks. Rename
the roles and state fields before treating it as project evidence.

## 9. Run The Formal Check Plan With Repeated Inputs

Choose:

- `external_inputs`
- `initial_states`
- `max_sequence_length`
- optional required labels or reachable predicates

Always include repeated-input exploration when duplicate side effects are possible. For one input and length two, the explorer must check both `[x]` and `[x, x]`.

The formal runner delegates finite exploration to the internal model runner,
which emits bounded progress on `stderr` by default, counted by top-level
`initial_state x input_sequence` work units. This helps agents distinguish a
long serial run from a silent process, but it is not pass/fail evidence and it
does not change report semantics. Use plan progress settings or
`FLOWGUARD_PROGRESS=0` when a strict environment requires no progress output.

Put the intended coverage boundary in `RiskProfile`, create a
`FlowGuardCheckPlan`, bind the minimum model contract and known-bad proof, then call
`run_model_first_checks(plan)`. The runner performs the minimum model review,
known-bad proof review, audit, automatic state/input closure review, optional
scenario scaffolding, finite model run, counterexample minimization, scenario review,
optional progress/contract/conformance sections, and a unified summary. The
closure review generates representative `other`, malformed, and missing-field
cases for inferred finite dimensions; undeclared policies scope confidence, and
unsafe unknown handling blocks it.

## 10. Inspect Counterexamples

When a report fails, read the counterexample trace. A useful trace shows:

- external input sequence;
- each function block;
- function input and output;
- old state and new state;
- labels and reasons.

The trace should make the failing architecture visible without guessing.

If the failing external input sequence is longer than needed, use
`minimize_failing_sequence` or `minimize_report_counterexample` to produce a
smaller deterministic reproduction. Minimization should preserve the original
counterexample in the report; a shortened trace is easier to review, but it
does not replace the original evidence.

## 11. Revise Model or Architecture

If the counterexample shows a real design bug, change the model and intended architecture. If it shows the model is incomplete, fix the model. Then rerun the checks.

Do not replace executable modeling with prose.

## 12. Only Then Implement Production Code

After the model passes, implement production code against the modeled behavior. Use the model to guide unit tests and code review.

An unchanged abstract run does not need to be repeated just because production
code was edited. If the same model, scenarios, oracle, invariants, risk
boundary, and task revision already passed, it is acceptable to reuse that
result and spend the post-edit check on focused tests, conformance replay, or
other production-facing evidence. Rerun the abstract model when its inputs
changed, previous evidence is unavailable or stale, a counterexample or design
revision needs confirmation, the user asks for a refresh, or a quick rerun
would materially help confidence.
The same principle applies to tests: reuse an old completed test result only
when a test-result reuse ticket and proof artifact prove the command, test
source, tested artifact, dependencies, environment, result fingerprint, and
coverage scope are unchanged. Background progress output is not reusable pass
evidence.

Production implementation should preserve:

- the same state ownership boundaries;
- the same idempotency behavior;
- the same deduplication behavior;
- the same downstream object compatibility;
- the same invariants.

For retry, rejection, or AI-packet repair loops, the model should also preserve
why the next packet changes or why the route blocks. A repeated input that emits
the same rejected shape without repair feedback, progress, or a blocker is a
stuck-loop counterexample, even if each individual rejection is locally valid.

## 13. Replay Production Code Against Model Traces

After production code is implemented or modified, add conformance replay when feasible.

Conformance replay should be the default next check when any of these are true:

- the invariant depends on a state field with multiple production write points;
- the production change has database writes or other durable side effects;
- runtime, cleanup, repair, or finalizer paths can reach the same state;
- the model result will be used to claim production behavior, not just
  model-level behavior;
- adapter projection is needed to compare model state with real state.

If replay is skipped in one of these cases, record the reason explicitly and
report the result as model-level confidence only.

The intended order is:

1. Model check first.
2. Implement production code second.
3. Conformance replay third.

Export representative model traces with `Trace.to_dict()` or `Trace.to_json_text()`. Write a replay adapter that maps each abstract `TraceStep` to the real production call. The adapter should project production state and output into abstract observations.

Do not require real internal state to equal abstract state directly. Use projection:

- production output -> abstract observed output;
- production state -> abstract observed state;
- production branch behavior -> observed label.

The production behavior must conform to model expectations or the model must be explicitly revised. Do not silently diverge from the model.

## 13.5 Handle Bug Repairs And Post-Runtime Model Misses

Treat a non-trivial bug repair, or a runtime, test, replay, log, or
manual-validation failure that appears after a FlowGuard pass, as a model-miss
review trigger until proven otherwise. The earlier pass is still useful, but it
is provisional evidence, not a reason to patch and finish directly.

When this happens:

1. Reopen the model-first work and keep completion blocked while the model-miss
   obligation is open.
2. Run existing-model preflight when the bug is inside an existing modeled
   system, then build or inspect the finding ledger across invariant/model
   checks,
   model-quality audit, scenario or live-audit evidence, progress, contracts,
   conformance, skipped/not-run sections, and adoption evidence. The ledger is
   the coverage-first view used to avoid patching only the visible failure.
3. Classify why the prior model missed the issue with one of the practical
   categories: `boundary_missing`, `code_boundary_mismatch`,
   `state_too_coarse`, `input_branch_missing`, `invariant_too_weak`, or
   `evidence_overclaimed`.
   Record unusual details in plain language instead of expanding the formal
   daily category list.
4. Backpropagate the root cause into the previous plan/model/test gap when a
   prior green claim existed: previous claim, observed failure, supported cause,
   `would_have_failed_if`, new plan/model/test item, and closure evidence.
5. Bind the failed promise to one affected commitment, its primary owner, and
   one `affected_blueprint_gap_id`. Reuse the current owner when it covers the
   promise; create a coverage gap only when none does.
6. If the issue belongs in scope, represent it as executable evidence: a
   scenario, invariant, replay adapter, representative trace, leaf cell, or
   model-boundary update. Declare only finite affected relations licensed by
   current DNA/BCL/topology source identities, pass them through one
   `CanonicalRelationHandoff`, and materialize them through
   ContractExhaustionMesh as stable case, combination, coverage-receipt, and
   oracle identities. An unmaterialized required relation stays open.
7. If the miss involves a field, schema key, config or prompt field, payload
   column, or persisted attribute, run or update FieldLifecycleMesh so the
   root-cause field, generated field cases, and any old or replaced field are
   visible.
8. Add current test evidence for the observed regression, every required
   generated case, and any concrete counterexample or known-bad replay target.
   Run Model-Test Alignment to verify that the repaired obligation, owner code
   contract, closure target, and external tests cover the same behavior. A
   single observed regression is not full closure.
9. If old, fallback, alternate paths, or old fields remain reachable, record
   whether they are deleted, blocked, migrated, delegated to the repaired
   contract or replacement field, same-contract repaired, or explicitly out of
   scope with a reason. Record important `BusinessPathIdentity` values so
   topology, runtime, and risk checks can bind the exact useful route.
10. If the finite validation is large, slow, layered, background, or
    release-only, route it through TestMesh and report scoped confidence until
    current child evidence exists.
11. Emit a task-bound ModelMaturation contribution with exact owner, coverage,
    probe, blueprint-gap, candidate, and native-receipt identities. Run the
    maturation loop over the miss, alignment, code-boundary, mesh, and
    freshness signals. Resolve every required gap through a current receipt or
    keep the claim scoped.
12. Rerun the relevant model checks and confirm that both the observed weakness
    and required ContractExhaustion cases are visible, or explicitly out of
    scope. Validate the repair with the strongest practical production-facing
    evidence.
13. If a child boundary changed, rerun the affected topology and parent
    reattachment gates. The parent must consume current child evidence and
    recheck inputs, outputs, state ownership, side effects, joins, outgoing
    guarantees, and affected siblings.
14. Run DevelopmentProcessFlow over changed plan, model, code, test, and
    documentation artifacts so later edits and peer writes cannot silently
    reuse stale evidence.
15. Project independently verified ModelMaturation evidence into the Risk
    Evidence Ledger and record the commitment/owner/blueprint-gap ids,
    canonical relation and generated case ids, code/test bindings, lifecycle
    dispositions, topology/parent replay, freshness, skipped checks, residual
    blindspots, and final claim boundary in adoption evidence.
16. Do not use a background long-running check as closure until final artifacts
    and exit status exist; progress output is only liveness.

A later green runtime check, point patch, one observed regression, or raw
relation id does not close a known model miss. An in-scope miss closes only
when its exact commitment and blueprint gap, finite generated cases, owner
code/test binding, relevant lifecycle dispositions, affected topology replay,
task-bound ModelMaturation result, freshness, and risk evidence are current;
otherwise the remaining boundary stays explicit.

## 14. Run Scenario Sandbox Review

Before connecting a model to larger production workflows, run scenario review when the task involves:

- repeated input;
- retries;
- refresh;
- queues;
- reprocessing;
- human review loops;
- uncertain AI decisions;
- caching;
- deduplication;
- side effects.

Write scenarios with explicit human expectations. Expected violations in broken models should be successful review outcomes when flowguard observes the intended violation. Use `needs_human_review` when the model exposes a policy gap that should not be falsely treated as proven.

For retry, deduplication, cache, idempotency, queue, or side-effect risks,
`ScenarioMatrixBuilder` can scaffold a small deterministic set of high-value
scenarios: single input, repeated same input, pairwise order, and ABA. Generated
scenarios default to `needs_human_review` unless you provide a domain
expectation. They cover input shapes, not business correctness, so they do not
silently become pass/fail claims.

## 15. Run Loop / Stuck-State Review

When a workflow has retry, rewrite, waiting, refresh, queue, or human-review cycles, build a reachable state graph and run loop checks.

Look for:

- stuck non-terminal states;
- bottom SCCs with no terminal or success state;
- unreachable required success states;
- terminal states with outgoing transitions;
- cycles with escape edges that require future fairness/progress modeling.

Do not claim bottom-SCC detection proves universal termination for cycles that have escape edges. Mark those as `known_limitation` or model a progress rule explicitly.

## 16. Run The Evidence Baseline Before Upgrades

Before starting a major flowguard upgrade, run the evidence baseline:

```powershell
python examples/evidence_baseline/run_baseline.py
```

Use it as an upgrade-readiness check. The baseline records:

- unit-test inventory;
- scenario review outcomes;
- conformance replay outcomes;
- model-check outcomes;
- loop/stuck review outcomes;
- bug-class scorecard.

An upgrade should improve or preserve the expected-vs-observed scorecard. Do not silently convert `needs_human_review` or `known_limitation` into `pass`. Do not accept new `unexpected_violation`, `missing_expected_violation`, or `oracle_mismatch` cases without a clear reason.

## 17. Keep The Real Software Problem Corpus In View

Before major flowguard framework upgrades, also run the real software problem corpus quality review:

```powershell
python examples/problem_corpus/run_corpus_review.py
```

The corpus quality review checks the problem-intent matrix. It is not the same as executable behavior testing. Reports must keep this distinction explicit:

```text
Problem-intent corpus: 2100 cases
Executable corpus review: 2100 executable cases, 0 not_executable_yet
Real-model corpus review: 2100 real_model_cases, 0 generic_fallback_cases
Evidence baseline: <N> evidence cases
Unit-test inventory: <U> test entries
```

For Phase 10.8 and later, also run:

```powershell
python examples/problem_corpus/run_executable_corpus_review.py
```

The executable corpus review must run real flowguard checkers, such as `Workflow + ScenarioReview + Invariant` or `LoopCheck`. Do not count a corpus case as executable if it only has prose fields or string evidence.

For Phase 11 and later capability claims, executable coverage is still not enough. The report must also show:

```text
real_model_cases: 2100
generic_fallback_cases: 0
model_variant_total: 150
model_families_with_six_variants: 25
```

The main corpus includes `pressure_100`, which is intentionally part of the
baseline before the next mathematical upgrades. Preserve `known_limitation`
for pressure cases that current checks cannot prove, rather than converting
them to `pass`.

The baseline freeze rules are documented in
`docs/benchmark_baseline_contract.md`.

This means each case is bound to a workflow-family-specific domain model with concrete block names, state slots, model variants, and structural evidence. A generic corpus template can remain useful for plumbing checks, but it is not a valid capability baseline.

For durable product-grade benchmark claims, also run:

```text
python examples/problem_corpus/run_benchmark_hardening.py
```

The hardening review must report:

```text
variant_min_cases >= 8
variants_below_target: 0
families_missing_required_case_kinds: 0
families_missing_required_bug_classes: 0
benchmark_conformance_family_count = 25
production_conformance_family_count = 26
total_replays = 78
failures = 0
```

This prevents the benchmark from becoming broad but shallow. A variant should
not count as mature if it was only touched once.

The corpus is not a roadmap mapping and not a current capability assessment. It defines real software workflow problems independent of future phase ownership.

Use it to keep future work grounded in broad software structures:

- cache and materialized views;
- retry and side effects;
- file pipelines;
- queues and leases;
- approval and human review;
- permissions and sessions;
- payments and inventory;
- deployment and configuration rollout;
- audit and traceability;
- classifier routing without API calls.

Do not add future phase ownership, current support status, or implementation assignment fields to corpus cases. Those belong in later reports, not in the problem case itself.

## 18. Use Quality Audit and Summary Reports As Helpers

`audit_model` provides a lightweight `ModelQualityAuditReport` for obvious
coverage gaps. It is intentionally heuristic and warning-oriented. A warning
means "this is a confidence boundary", not "the model failed". A suggestion is
an improvement idea. Only structural problems such as a workflow with no blocks
should be treated as audit errors.

Use a `FlowGuardSummaryReport` when you need to present minimum-model,
known-bad proof, model check, audit, scenario review,
progress, contract, conformance, and skipped/not-run sections together. If
the finite model check passes but a formal gate blocks or audit warns, the overall status
should not be treated as plain `pass`. If production conformance is not run,
record `not_run` or `skipped_with_reason`; skipped is not pass.

`FlowGuardSummaryReport.finding_ledger` flattens every section finding and
every non-pass section gap into a `FlowGuardFindingLedger`. Use that ledger
before FlowGuard/LiveFlowGuard framework upgrades, live failure triage, and
model-miss repair decisions. The repair choice should be explicit: fix the real
system, adjust the check flow, extend the model, or mark a boundary out of
scope. A point rule is acceptable only after the ledger shows it is the right
repair rather than the first visible patch.

`FlowGuardSummaryReport.maintenance_obligations` turns non-pass gaps into
route-owned memory. DevelopmentProcessFlow compares relevant prior obligations
directly with changed artifacts; anchored open items reopen their exact owner
route, while unanchored observations remain visible memory rather than hard
gates.

Do not report model-level confidence as production confidence unless
conformance replay or another production-facing evidence source supports that
claim.

Recommended low-friction agent flow:

1. Create a model if none exists yet, or reuse/update the existing model.
2. Start with the smallest inspectable boundary that still exposes the customer
   risk.
3. Declare `RiskProfile` with a minimum valuable `RiskIntent`.
4. Bind `MinimumModelContract` and current `KnownBadProof`.
5. If and only if template reuse/publication was explicitly requested or
   current executable evidence proves a bounded stable pattern intended for
   use outside the target project, run the strict `risk_template_library`
   search/review/harvest path.
6. Use standard property factories or domain packs when they fit.
7. Run `run_model_first_checks()`.
8. Inspect the finding ledger before choosing a repair path for framework
   upgrades, live failures, or model misses.
9. Inspect minimized counterexamples if any.
10. Treat `pass_with_gaps`, `blocked`, skipped, stale, or `not_run` sections as
   claim boundaries.
11. Do not claim production conformance unless conformance replay or equivalent
   real-code evidence exists.
12. Record skipped checks; skipped is not pass.

For older adopted repositories, run project upgrade before relying on existing
FlowGuard files. FlowGuard's runtime path is latest-schema-first: old artifacts
can be detected and upgraded at project/tool boundaries, but current route
reviews should not keep accepting obsolete fields, aliases, or wrappers.

## Completion Checklist

- A minimum valuable Risk Intent names failure modes, protected error classes,
  protected harms, model-critical state and side effects, completion evidence,
  adversarial inputs, known-bad cases, hard invariants, and blindspots.
- When the separate template route is triggered, its exact reuse/no-match
  review and template harvest closure are current. When it is not triggered,
  their absence is not a gap.
- The model includes current known-bad proof evidence showing a representative
  broken path fails for the protected error class.
- If no model existed before FlowGuard applied, an AI-created model script now
  captures the relevant customer risk instead of waiting for a preexisting
  script.
- Existing models are revised or connected when new failure modes make the old
  boundary too weak.
- Projects with three or more local FlowGuard models have a model mesh, or an
  explicit reason why the current narrow task does not rely on cross-model
  evidence.
- The model mesh, when required, inventories child models, evidence tiers,
  freshness, dependencies, skipped checks, live/conformance adapters, and
  cross-model contradictions before broad continue/release/completion claims.
- Whole-flow parent confidence uses a mesh closure model to prove root entries,
  child outputs, joins, terminals, and out-of-scope branches close without
  expanding child internals.
- Child model repairs under a parent mesh pass the parent reattachment gate, or
  the stale/missing/drifted handoff remains a visible blocker.
- Large script or module splits have a StructureMesh, or an explicit reason why
  the current narrow task does not rely on parent/child refactor evidence.
- The StructureMesh, when required, inventories function, state, config,
  side-effect, public-entrypoint, facade, model-derived target structure,
  dependency, parity, and release-scope ownership before broad refactor or
  compatibility claims.
- Direct code architecture recommendations, when requested, include a source
  FlowGuard functional model, target modules, ownership maps, validation
  boundaries, and rationale instead of only prose.
- The model uses only the Python standard library.
- Inputs and state are finite and hashable.
- Every block returns all possible branches.
- Zero-result and non-consumable paths are reportable.
- Repeated external inputs are explored.
- Invariant violations include counterexample traces.
- Correct models pass.
- Broken variants fail for the intended reason.
- Representative traces can be exported for audit or replay.
- Production implementations have conformance replay adapters when feasible.
- Production replay either conforms to the model or documents why the model changed.
- Non-trivial bug repairs and post-FlowGuard runtime/test/replay/manual
  failures trigger model-miss review before completion.
- FlowGuard/LiveFlowGuard upgrades and live-failure triage use a full finding
  ledger before point-rule patches.
- Known model misses are classified, represented in executable evidence or
  marked out of scope, rerun, and then validated with production-facing checks.
  In-scope misses add one ContractExhaustionMesh same-class or finite-boundary
  case when practical.
- Scenario reviews compare expected and observed outcomes.
- Broken-model scenarios produce expected violations rather than ordinary failures.
- Loop/stuck review is run for workflows with retries, refresh, waiting, or reprocessing.
- Evidence baseline is run before major upgrades and after the upgrade changes land.
- Real software problem corpus quality review is run before major upgrades to keep the broader problem space visible.
- Executable corpus review is run before major upgrades when the task claims corpus behavior-test coverage.
- Real-model corpus review is required before claiming broad flowguard capability across the 2100-case corpus.
- Benchmark hardening review is required before claiming the test rig is a durable product-grade baseline.
- Progress/fairness checks are required when a workflow has a cycle with an
  escape edge but no ranking or bounded-progress guarantee.
- FunctionContract checks are required when input/output compatibility,
  forbidden writes, ownership, traceability, or projection refinement is the
  risk being modeled.
- Thin CLI, pytest, schema, and template helpers must preserve structured
  expected-vs-observed reports rather than hiding review status.
- Reports distinguish problem-intent case count, executable case count, evidence baseline count, and unit-test inventory count.
- ModelQualityAudit warnings, missing conformance, skipped checks, and not-run
  sections are reported as confidence boundaries rather than hidden or
  mislabeled as passes.
- Real project adoptions record status, trigger reason, elapsed time, commands run,
  findings, counterexamples, skipped steps, risk evidence summaries, friction points, and next actions
  in an adoption log.

## Real Adoption Logging

When using flowguard in another project, keep a project-local adoption record:

- `.flowguard/adoption_log.jsonl` for machine-readable entries;
- `docs/flowguard_adoption_log.md` for a human-readable log.

Use `flowguard.adoption.AdoptionTimer` to time the session and
`AdoptionCommandResult` to record checks. The log should explain why the skill
was triggered, which model files changed, which checks ran, what was found,
what was skipped, what the risk evidence ledger allowed or blocked, and what
should happen next.

Use status values honestly:

- `in_progress`: the adoption work has started but is not final;
- `completed`: the model-first work is finished and executable checks were recorded;
- `blocked`: a real blocker remains;
- `skipped_with_reason`: a step was intentionally skipped and the reason is recorded;
- `failed`: a command, model check, conformance replay, or oracle review failed.

This log is not a substitute for executable modeling. Its purpose is to make
real usage reviewable so future flowguard work can improve the parts that were
slow, confusing, or insufficient.
