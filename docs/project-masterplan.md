# CP²N² Master Plan

**Version:** 1.0 — 23 July 2026  
**Status:** Accepted project plan — 23 July 2026  
**Purpose:** Executable development, experiment, and publication plan for the next, substantially strengthened version of CP²N².

## 1. Project position and target

CP²N² is a **general control plane for heterogeneous Physical Neural Networks (PNNs)**. It is not a Cortical Labs integration project. A Cortical Labs CL1 is one representative, real biological PNN scenario through which the control-plane claims can be tested; other PNNs, neuromorphic devices, simulators, and physical substrates remain equally in scope.

The project will establish three contributions:

1. A versioned **Physical Neural Resource Contract** for describing physical-neural resources and their operational state.
2. A control plane that safely manages discovery, admissibility, reservation, execution, validation, recovery, and provenance across heterogeneous PNN backends.
3. A reproducible systems evaluation spanning conformance, policy,
   portability, overhead, concurrency, and controlled distributed-failure
   tests. A real, remote PNN scenario is a separable extension, subject to E5
   access and evidence.

The core claim is:

> Stateful physical-neural resources cannot be scheduled safely from endpoint metadata alone. CP²N² defines an operational resource contract and lifecycle protocol that makes modality, provenance, freshness, calibration, health, exclusivity, safety, and recovery first-class constraints for agent-driven execution.

### What this project may claim

- CP²N² provides a general operational abstraction over heterogeneous PNN resources.
- It enforces explicit admissibility and safety rules before a resource is committed.
- It provides lifecycle control, leases, provenance, validation, and recovery across backends.
- It can be evaluated under distributed failures, stale telemetry, and competing requests.
- Its constrained agent surface prevents an LLM from selecting primitive
  physical controls or bypassing admission, leases, and approvals.
- Subject to later E5 evidence, it can expose a real PNN safely to an LLM
  agent through constrained high-level operations.

### What it must not claim without extra evidence

- That one CL1 culture establishes general properties of all biological PNNs.
- That an SDK simulator is biological hardware or a learning surrogate for wetware.
- That CP²N² is tied to, or only useful for, CL1 systems.
- Universal optimality of a resource-selection policy.
- Hard real-time control by an LLM or by a remote MCP client.
- Unrestricted autonomous stimulation or laboratory control by an agent.

## 2. Evidence levels and permanent backend roles

Every backend and result must carry a machine-readable evidence level.

| Level | `runtime_kind` | Meaning | Valid use |
|---|---|---|---|
| E0 | `mock` | Interface mock | unit and error tests |
| E1 | `synthetic_twin` | behavioural simulation | policy and orchestration tests |
| E2 | `same_host_service` | separate service on one host | process/API boundary |
| E3 | `sdk_simulator` | official substrate SDK simulator | API compatibility, regression, repeatable controls |
| E4 | `remote_simulator` | independent remote simulator | remote access and network path |
| E5 | `physical_hardware` | real physical or biological substrate | real end-to-end execution |

The CL SDK Simulator is a **permanent E3 backend**, not a temporary placeholder. It remains in the prototype because it provides local development, deterministic regression tests, safe fault injection, reproducible recordings, and a controlled comparison for the CL adapter. It must never be used to infer biological learning or real-hardware performance.

Rules:

- `runtime_kind` is observed or explicitly configured; it is never inferred from a name.
- The CL adapter must verify `cl.is_simulator()` and reject a contradictory configuration.
- All dynamic telemetry records a value, unit, source, observation time, receipt time, uncertainty, and validity period.
- Unknown information remains `unknown`; no synthetic “healthy”, zero-drift, or zero-age defaults are permitted.
- The paper uses the same E0–E5 vocabulary in text, figures, tables, and artifacts.

## 3. Research questions

**RQ1 — Operational contract and safe admission.** Can an explicit,
versioned resource contract provide a portable control surface across
heterogeneous backends while preventing inadmissible or insufficiently
attested executions, including agent-requested assays?

**RQ2 — Distributed control.** How do leases, telemetry freshness,
selection, abort, recovery, reconciliation, auditability, and control-plane
overhead behave under concurrency and controlled edge/fog/cloud failure
conditions?

**RQ3 — Real PNN access.** Can an LLM agent discover, reserve, and use a real PNN through CP²N² without receiving direct access to unsafe primitive operations?

**RQ4 — Representative physical-computation case study.** In the selected real-PNN scenario, does the substrate produce reproducible, task-relevant observable behaviour under a controlled protocol?

RQ4 is substrate-specific. It supports the real integration case study; it is not a general claim about all PNNs.

RQ1 and RQ2 form the independently submission-ready systems-paper core. RQ3
and RQ4 form an optional, explicitly separated E5 case-study layer. E3
evidence may validate the CL software path used to prepare that layer, but it
cannot answer either RQ3 or RQ4.

## 4. Workstream A: General CP²N² software

### A0. Freeze and audit the baseline

- **Recorded baseline:** the user-confirmed GitHub tag `v3.0` in the public repository <https://github.com/fischesn/cp2n2>. The local clone currently has `origin/main` at commit `4303073` — *phys-MCP prototype v3.0 with full integration of the Cortical Labs simulator and two LLM agents*. Before implementation begins, refresh tags and record the exact commit resolved by `v3.0` in the baseline manifest.

- [x] Freeze a baseline commit and archive the current configuration and results.
- [x] Assign every current backend an E0–E5 evidence level.
- [x] Label all existing Cortical results as `sdk_simulator` where appropriate.
- [x] Remove invented health, drift, freshness, and confidence defaults.
- [x] Remove local paths, host-specific state, caches, and debug artifacts from release outputs.
- [x] Create a run manifest containing commit, configuration, backend level, test command, and output checksums.

**Done when:** no result can be mistaken for a real PNN run, and every result is reproducible from a manifest.

### A1. Physical Neural Resource Contract

Define a versioned, substrate-neutral contract with:

- identity: resource, provider, adapter, hardware/substrate identifiers;
- evidence: runtime kind, attestation method and time;
- capabilities: modality, supported task classes, I/O forms, timing;
- state: lifecycle, occupancy, health, calibration, and drift;
- telemetry provenance and freshness;
- safety: permitted operations, hard limits, supervision requirements;
- cost, data-retention, and access metadata.

- [x] Specify JSON Schema and typed implementation models.
- [x] Define units, semantics, required fields, and `unknown` behaviour.
- [x] Version the schema and document migration rules.
- [x] Provide valid and invalid descriptors for multiple substrate families.
- [x] Implement a schema validator and conformance suite.

**Done when:** all supported backends validate, and missing safety-relevant information produces `inadmissible` rather than optimistic execution.

**Status (23 July 2026):** complete in the committed and pushed
`codex/a0-hardening` branch. The orchestrator checks the published contract
after preparation and before invocation. Implementation and verification
details are recorded in `outputs/a1-resource-contract-change-set.md`; the
reproducibility manifest is `outputs/a1-run-manifest.json`.

### A2. Lifecycle, leases, and error semantics

Use the common lifecycle:

```text
DISCOVERED -> READY -> RESERVED -> PREPARING -> RUNNING
          -> VALIDATING -> COOLDOWN -> READY

active state -> ABORTING -> DEGRADED | FAILED | READY
READY/RUNNING -> UNREACHABLE
```

Implement exclusive, time-bounded leases; request idempotency; state-version checks; separate timeouts; explicit abort; and provider-state reconciliation after uncertainty.

- [x] Implement and document the state machine.
- [x] Add an atomic lease store, renewal, expiry, and ownership checks.
- [x] Add correlation IDs and idempotency keys to state-changing requests.
- [x] Define errors such as `INADMISSIBLE`, `POLICY_DENIED`, `RESOURCE_BUSY`, `LEASE_EXPIRED`, `TELEMETRY_STALE`, `EXECUTION_STATUS_UNKNOWN`, and `POSTCONDITION_FAILED`.
- [x] Implement abort and reconciliation paths.
- [x] Add model-based transition and fault tests.

**Done when:** competing clients cannot concurrently execute on an exclusive resource, and timeouts never silently become “successful completion.”

**Status (23 July 2026):** complete in commit `81eb2a4` on the
`codex/a2-lifecycle-leases` branch. The safe suite passes 38 tests,
including two competing orchestrators, explicit lease renewal/ownership,
idempotent replay, separate phase timeouts, abort, and reconciliation.
Implementation details and boundaries are recorded in
`outputs/a2-lifecycle-leases-change-set.md`.

### A3. Admission, feasibility, and selection

Keep three decisions separate:

1. **Admission:** task, modality, policy, supervision, and safety constraints.
2. **Feasibility:** availability, telemetry freshness, reservability, and budget.
3. **Ranking:** transparent preference among feasible candidates.

- [x] Make the current heuristic and all weights explicit.
- [x] Move hard constraints out of ranking.
- [x] Implement documented `latency_first`, `safety_freshness_first`, and `locality_cost_first` policy profiles.
- [x] Add a lexicographic or Pareto policy as the principal policy.
- [x] Retain the weighted heuristic only as a transparent comparison.
- [x] Implement baselines: static priority, constraint-based selection, and random admissible selection.
- [x] Run weight sensitivity and out-of-sample task tests.

**Done when:** each selection has a reproducible, machine-readable explanation and every exclusion names the violated constraint.

**Status (23 July 2026):** implemented and verified on the uncommitted
`codex/a3-admission-selection` branch. The safe suite passes 47 tests;
curated matching is 6/6, the holdout suite is 4/4, and the failure campaign is
5/5. The principal lexicographic policy remained invariant across 32 seeded
perturbations of all comparison weights. Implementation details and review
boundaries are recorded in `outputs/a3-admission-selection-change-set.md`;
the reproducibility record is `outputs/a3-run-manifest.json`.

### A4. Agent-facing MCP surface

Expose high-level, constrained tools only:

`discover_resources`, `describe_resource`, `reserve_resource`, `renew_lease`, `prepare_assay`, `run_assay`, `get_run_status`, `abort_run`, `get_result_summary`, and `release_resource`.

The agent must not receive arbitrary electrode selection, arbitrary pulse parameters, unlimited loops, policy editing, lease bypass, or runtime-kind editing.

- [x] Define schemas and authorization for every tool.
- [x] Provide a `dry_run` planning path with no resource commitment.
- [x] Add a human-approval hook for real biological execution.
- [x] Record an append-only audit trail for every agent request.
- [x] Test adversarial/malformed agent plans and policy-bypass attempts.

**Done when:** unsafe primitives cannot be reached through the MCP surface, including through malformed input or a hostile plan.

**Status (24 July 2026):** implemented and verified on the uncommitted
`codex/a4-agent-mcp` branch. The official MCP 1.x binding publishes exactly
the ten approved tools; the targeted A4 suite passes 14 tests and the complete
safe suite passes 61 tests. Dry runs create no lease or run and invoke no
adapter. Physical wetware is fail-closed behind an external, exact-run-bound,
single-use approval. No CL stimulation, hardware, Gemini, Ollama, or external
network service was used. Implementation and review boundaries are recorded
in `outputs/a4-agent-mcp-change-set.md`; the reproducibility record is
`outputs/a4-run-manifest.json`.

### A5. General adapter architecture

Separate every integration into:

1. a **control adapter** for discovery, reservation, deployment, state, abort, and artifacts; and
2. a **substrate application/runtime** for time-critical local work.

The CL adapter is one adapter among multiple E1–E5 backends. The architecture, schemas, test suite, and paper must remain substrate-neutral.

- [x] Define the adapter interface and required capability declarations.
- [x] Implement conformance tests that every adapter must pass.
- [x] Keep the existing CL SDK Simulator adapter as a supported E3 target.
- [ ] **BLOCKED:** Implement the real CL control adapter only after current
  provider access, deployment, reservation, safety, and artifact details are
  confirmed. No E5 control adapter is claimed.
- [x] Maintain at least one non-CL backend in every core evaluation.

**Done when:** removing the CL adapter does not invalidate the core contract, lifecycle, or distributed evaluation.

**Status (24 July 2026): DONE** for the general A5 architecture on the
uncommitted `codex/a5-general-adapters` branch. Five integrations now separate
control adapters from substrate runtimes and publish versioned capability
declarations. The targeted conformance suite passes 14 tests and the complete
safe suite passes 75 tests. A subprocess that blocks all `cortical` imports
still publishes three generic contracts and executes the edge backend. Every
core evaluation declares non-CL coverage. The real CL provider adapter remains
**BLOCKED** by missing current access details and was not implemented or
claimed. Implementation and review boundaries are recorded in
`outputs/a5-general-adapters-change-set.md`; the reproducibility record is
`outputs/a5-run-manifest.json`.

### A6. Distributed testbed

Deploy the control plane, gateway, adapter services, and agent client on separate processes or hosts. Test latency, jitter, loss, partitions, stale telemetry, and 1–32 competing clients.

- [x] Version a reproducible multi-node deployment.
- [x] Version network and fault profiles.
- [x] Add trace correlation and metrics collection.
- [x] Automate load and fault-injection campaigns.
- [x] Archive raw results, configurations, and checksums.

**Done when:** every RQ2 figure can be regenerated from versioned configuration and raw data.

**Completed 2026-07-24:** `local-four-process-v1` isolates the agent campaign
runner, gateway, lifecycle-aware control plane, and remote adapter runtime.
The versioned RQ2 campaign covers 1, 2, 4, 8, 16, and 32 competing clients
under baseline, latency/jitter, five-percent loss, periodic partition, and
stale-telemetry profiles. End-to-end trace identifiers cross all service and
timeout-worker boundaries. The final local reference archive contains 945 raw
requests, 30 aggregated matrix points, per-service JSONL spans and logs, exact
configuration copies, two regenerable RQ2 figures, 15 A6 source hashes, and 47
artifact hashes with no verification failures. This is explicitly a
localhost multi-process/application-layer impairment experiment, not a
wide-area or physical-hardware claim. The implementation boundary is recorded
in `outputs/a6-distributed-testbed-change-set.md`; the reference archive is
`outputs/a6-rq2-reference-run-20260724-final/`.

### A7. University of Lübeck AI-Lab agent (late-stage integration)

After completion of the preceding A workstream, implement an additional
CP²N² agent using the University of Lübeck AI-Lab platform. The platform is
available to the project through a free API-key-based access arrangement and
will be used as a capable additional agent runtime, not as a replacement for
the generic CP²N² architecture or for the Gemini/Ollama reference clients.

The integration must reuse the constrained A4 MCP surface. It must not receive
any additional authority over PNN resources, physical controls, policies,
leases, evidence labels, or human approval. API credentials must remain in
untracked local configuration or an approved secret store and must never be
committed or written to audit logs.

- [x] Confirm the current AI-Lab API documentation, supported model(s), rate
  limits, data-handling terms, and project-specific access conditions.
- [x] Implement an AI-Lab client behind the same strict plan schema and
  constrained executor used by the Gemini and Ollama examples.
- [x] Add mocked-client tests for schema rejection, dry-run behavior, audit
  coverage, and absence of direct backend access.
- [x] Run a small, explicitly networked dry-run evaluation only after local
  verification; label it as an AI-Lab inference evaluation, not PNN evidence.
- [x] Document configuration, model/version provenance, cost statement
  (currently project-provided access), and reproducibility limitations.

**Scheduling:** deliberately last among the planned A steps; begin only after
A5/A6 have reached their relevant completion gates and the platform details
have been reconfirmed.

**Done when:** the AI-Lab client is a tested, credential-safe, constrained
alternative agent runtime whose behavior cannot expand the A4 authority
boundary.

**Completed 2026-07-24:** AI-Lab documentation version 1.4.1 confirms the
official OpenAI-compatible LiteLLM endpoint, current model catalog, weekly
budget-unit reset, VPN/access conditions, and data/acceptable-use policy. The
host-pinned client reuses the A4 `AgentPlan`, `ConstrainedAgentExecutor`, MCP
surface, audit trail, and approval boundary. Nine dedicated A7 tests pass, and
the complete split regression suite passes (84 non-A6 tests and 7 A6 tests; 91
total). The explicitly confirmed live evaluation used `minimax-m2.7` for two
synthetic generic dry-run goals. Both completed successfully with
`pnn_evidence=false`, `substrate_executed=false`, and a verified audit chain.
The reference archive is
`outputs/a7-ai-lab-reference-run-20260724/`; it contains model/request/usage
provenance but no API credential or provider reasoning wrapper.

## 5. Workstream B: representative CL1 scenario

### B1. Role, application decision, and claim boundary

The CL1 scenario validates the general system on a real, remote, scarce,
stateful biological PNN. It is a **representative case study**, not a special
definition of CP²N² and not the only relevant PNN class.

The selected application is **BioPattern Gate**, a policy-bound
spatiotemporal pattern-discrimination assay with an immediately understandable
visual metaphor. Virtual objects approach a two-way gate. Each object is
associated with one of two hidden, charge-matched spatiotemporal input
patterns. The CL1 culture receives the approved pattern, a fixed and
interpretable readout classifies the evoked response, and the gate routes the
object left or right. The visual demo shows the gate, live neural activity,
the decision, trial outcome, session score, and the CP²N² resource
lifecycle.

BioPattern Gate is a hybrid physical-computing application:

```text
pattern label
  -> fixed approved stimulation encoder
  -> CL1 biological neural culture as dynamic physical reservoir
  -> fixed feature extraction from post-artefact neural activity
  -> frozen linear readout
  -> left/right gate decision
```

The primary application claim is deliberately limited:

> Under a controlled protocol, a real CL1 culture produces attested,
> task-relevant response features from which a small transparent readout can
> discriminate two charge-matched spatiotemporal patterns.

The primary control-plane claim is:

> CP²N² can discover, attest, admit, reserve, prepare, execute, monitor,
> validate, abort, reconcile, and release the real biological resource while
> exposing only an approved assay preset to the agent.

The application must not imply that the culture alone runs the complete game,
that a classification result demonstrates general intelligence or sentience,
or that E3 simulator output is biological evidence. Superiority in accuracy,
energy, training data, or learning speed over silicon is out of scope unless
measured under a separately pre-registered protocol.

- [x] Select BioPattern Gate as the B-path application and demo.
- [x] Retain the substrate-neutral CP²N² architecture and evidence levels.
- [x] Define the initial result as biological reservoir discrimination, not a
  biological-learning claim.
- [ ] Freeze the application protocol and claims before the first E5 pilot.

### B2. Demo story and user-visible experience

The demo should communicate both physical computation and control-plane value
without requiring the audience to understand electrophysiology.

#### B2.1 Main demo sequence

##### User problem and role of the LLM agent

The user is a researcher who does not want to address electrodes, device APIs,
leases, provider queues, or backend-specific deployment commands. The user's
application-level question is:

> Can an available real biological neural substrate distinguish two
> charge-matched spatiotemporal patterns under the approved BioPattern Gate
> protocol, and can the resulting run be executed and documented safely?

The LLM agent translates that intent into a choice among the resources and
server-owned presets currently published by CP²N². Its role is limited to:

- interpreting the natural-language goal and constraints;
- discovering the sanitized current resource catalog;
- selecting one compatible resource and one published assay preset;
- choosing dry-run planning or real execution according to the explicit user
  instruction;
- explaining the selection, exclusions, approval requirement, and result in
  accessible language.

The LLM does **not** design the biological experiment. It cannot select
electrodes, pulses, timing, trial counts, decoder parameters, safety limits,
runtime kind, policy, or approval. It does not receive raw recordings or
provider credentials. The server-owned BioPattern Gate preset and the
deterministic CP²N² executor perform the actual workflow.

A deterministic client could run the same fixed assay. The purpose of the LLM
case study is instead to test whether an open-ended agent request can be mapped
safely and transparently onto a heterogeneous PNN control plane without
expanding the agent's authority. This directly supports RQ3 and demonstrates
why the MCP boundary matters.

##### Canonical two-step user interaction

The canonical first prompt is a non-committing planning request:

```text
Plan a BioPattern Gate experiment to test whether an available living neural
substrate can distinguish two charge-matched spatiotemporal input patterns.
Prefer an attested physical-hardware PNN if one is currently admissible.
Do not execute anything. Select only a published server-owned assay preset.
Report the selected resource and evidence level, why it is admissible, the
expected duration and cost information if available, the required human
approval, and every blocker or unknown.
```

The expected constrained plan has only the following decision fields:

```json
{
  "action": "prepare_assay",
  "arguments": {
    "resource_id": "<one discovered compatible resource>",
    "preset_id": "pattern_gate_v1",
    "dry_run": true
  },
  "rationale": "The resource and fixed preset satisfy the stated biological pattern-discrimination goal."
}
```

After the operator reviews that plan, the canonical execution prompt is:

```text
Execute the previously reviewed BioPattern Gate experiment now on an attested
physical-hardware PNN. Use only the published server-owned preset selected in
the dry run. Do not substitute a simulator and do not change any physical or
analysis parameter. If physical-hardware attestation, health, calibration,
telemetry freshness, exclusive reservation, budget authorization, or the
external exact-run human approval is missing, do not start. Return the run
status, evidence level, primary assay results, and audit and artifact
references.
```

This second prompt permits the LLM planner to return `dry_run=false`, but it is
not itself the safety approval. The external operator separately supplies a
single-use approval bound to the exact resource ID, run ID, package hash,
preset hash, and expiry. Without that independently verified approval,
CP²N² rejects the E5 execution even when the prompt asks to proceed.

Natural variants are allowed, for example:

```text
Use a real biological PNN to run our approved two-pattern gate demonstration
and show me whether the culture's response distinguishes the patterns. Plan it
first; do not run until I explicitly approve the exact plan.
```

The prompt is intentionally about the scientific goal, evidence requirement,
and execution intent. A prompt containing physical instructions such as
electrode numbers, amplitudes, pulse widths, or requests to bypass approval
must be rejected or ignored as outside the agent plan schema.

##### User-visible outcome

For a dry run, the agent answers in application language:

```text
BioPattern Gate can be planned on resource <resource_id> using the fixed
pattern_gate_v1 preset. The resource reports evidence level E5, but no
substrate has been executed. Real execution requires a current lease and a
single-use human approval. <List any freshness, availability, cost, or
provider-access blockers.>
```

For a completed run, the agent summarizes only the validated result:

```text
BioPattern Gate completed on attested E5 resource <resource_id>. The frozen
test block achieved <balanced_accuracy> with <confidence_interval>; <valid>,
<invalid>, and <sham> trials were recorded. The run is eligible/not eligible
for the planned case-study claim because <validation findings>. Audit and
artifact references: <references>.
```

The agent must say explicitly when the result is E3, a replay, partial,
aborted, status-unknown, or ineligible for a biological claim.

##### End-to-end demo sequence

1. The user submits the canonical planning prompt in the agent interface.
2. The LLM receives the goal plus sanitized resource and compatible-preset
   descriptions, then returns the strict three-field choice:
   `resource_id`, `preset_id`, and `dry_run`.
3. CP²N² validates the plan and shows why each candidate is
   admitted, rejected, or ranked.
4. The CL1 is shown as E5 only after provider/device attestation succeeds.
5. The dry run reports feasibility, evidence, expected resource implications,
   approval requirements, and blockers without acquiring a lease or invoking
   an adapter.
6. The user reviews the plan and submits the explicit execution prompt.
7. An external operator issues the exact-run, single-use approval; the approval
   is never generated or edited by the LLM.
8. CP²N² checks health, calibration, telemetry freshness, policy,
   reservation availability, budget metadata, and human approval.
9. A lease is acquired and the state advances through `RESERVED`,
   `PREPARING`, and `RUNNING`.
10. The on-device application performs baseline, calibration or mapping, and
   the frozen test block.
11. The demo screen animates objects approaching the gate. For every trial it
   shows the input class only after the decision, live spike activity, the
   predicted route, correctness, and cumulative score.
12. CP²N² validates artifacts and postconditions, records provenance, runs
   cooldown, and releases the resource.
13. The agent produces a sanitized result summary; it does not receive raw
   neural data, physical parameters, credentials, or approval material.
14. The result screen distinguishes substrate evidence from systems evidence
   and links each metric to the immutable run record.

- [x] Define the user-level scientific goal and the bounded purpose of the LLM.
- [x] Define canonical dry-run and real-execution prompts.
- [x] Separate explicit execution intent from external human approval.
- [x] Add the canonical prompts as versioned agent evaluation fixtures.
- [ ] Test natural paraphrases, ambiguous execution intent, simulator
  substitution, parameter-injection attempts, and approval-bypass prompts.
- [x] Demonstrate equivalent execution through a deterministic non-LLM client
  to isolate the control-plane contribution from model behavior.

#### B2.2 Control-plane moments to demonstrate

The polished demonstration includes one successful run and short,
pre-recorded or simulator-backed views of:

- a competing reservation rejected as `RESOURCE_BUSY`;
- stale telemetry rejected as `TELEMETRY_STALE`;
- missing E5 human approval rejected as `POLICY_DENIED`;
- a controlled abort followed by provider-state reconciliation;
- the same package running under E3 with an unmistakable simulator banner;
- audit-chain and artifact-checksum verification.

Fault demonstrations must not be injected into a live biological measurement
unless explicitly approved. They may be shown with E0--E3 evidence or from an
earlier safe run.

#### B2.3 Visual layout

The application visualizer has four coordinated panels:

1. **Gate view:** object, approach animation, predicted route, true class after
   commitment, correct/incorrect animation, block progress, and score.
2. **Neural view:** electrode map or spike raster, stimulation markers,
   blanking interval, observation window, and readout-channel activity.
3. **Decision view:** standardized feature summary, class probability,
   decision threshold, frozen model identifier, latency, and trial status.
4. **Control-plane view:** resource ID, evidence level, lifecycle state, lease
   expiry, telemetry age, approval state, run ID, trace ID, and audit status.

The gate remains a visualization of a rigorously defined assay; visual effects
must not obscure missed trials, aborted runs, unknown status, or uncertainty.

- [x] Produce the four-panel UI and replay interaction storyboard.
- [ ] Implement the CL application web visualizer using application data
  streams plus `cl_spikes` and `cl_stims`.
- [x] Implement a replay mode that renders a completed result bundle
  without contacting a substrate.
- [x] Add prominent evidence, live/replay, and terminal-status labels to the
  shared visualizer; E5 remains unavailable until attested hardware exists.
- [x] Record a deterministic E3 execution through the constrained MCP surface
  and bind the visualizer to its verified audit chain, LifecycleStore history,
  result artifact, and automatic lease release.
- [ ] After provider approval, record an attested E5 hardware demo.

### B3. Assay contract and immutable configuration

The agent may select only a server-owned preset. It may not choose channels,
pulse widths, amplitudes, burst frequencies, trial counts, feedback rules,
blanking windows, thresholds, safety limits, or model coefficients.

The package identifier is provisionally `cp2n2-biopattern-gate`; the first
public protocol preset is `pattern_gate_v1`. The exact package identifier must
be checked against provider naming rules before upload.

The immutable application configuration contains:

- `name`, `config_version`, `protocol_version`, and `timeout_s`;
- run mode: `technical_e3`, `mapping_e5`, `pilot_e5`, or `measurement_e5`;
- provider-approved stimulation design reference;
- provider-approved logical input group references;
- disjoint logical readout group references;
- trial seed and frozen randomized schedule;
- class balance, block structure, sham schedule, and inter-trial timing;
- artefact blanking and observation-window definitions;
- feature-schema version;
- decoder kind, frozen coefficient artifact ID, threshold, and training-run ID;
- recording options, including the explicit raw-sample setting;
- abort, cooldown, completeness, and postcondition rules;
- project and provider safety-policy versions.

Physical parameters are represented by reviewed preset values, not user input.
Until Cortical Labs and the responsible researcher approve them, the
repository contains symbolic or simulator-only values and cannot produce an
E5-executable package.

Configuration models must use strict, frozen validation. Cross-field checks
must reject:

- overlapping stimulation and readout groups;
- missing or unknown safety-policy versions;
- stimulation values outside provider or project limits;
- schedules exceeding per-channel or session limits;
- inconsistent charge between A and B;
- observation windows overlapping the artefact-blanking interval;
- a decoder trained on the current test block;
- E5 mode under simulator attestation or E3 mode under claimed E5 evidence;
- unknown runtime kind, approval, calibration, or recording policy;
- timeouts shorter than the declared protocol duration.

- [x] Define `BioPatternGateConfig` and versioned JSON Schema.
- [x] Define simulator-only and provider-approved preset namespaces.
- [x] Implement all cross-field and fail-closed validators.
- [x] Store the exact validated configuration and its SHA-256 in every run.
- [ ] Add configuration migration tests; never migrate an executing run.

### B4. Biological computation and stimulus design

The initial two-class task must differ in spatiotemporal structure while
holding obvious confounds constant. The default conceptual encoding is:

- pattern A: logical input group `I0` followed by `I1`;
- pattern B: logical input group `I1` followed by `I0`;
- identical pulse design, pulse count, total duration, and total charge;
- the same distribution of per-channel use across a balanced block.

The final encoding may instead use a provider-approved spatial permutation or
temporal interval pattern if mapping data makes that preferable. Any change is
a new protocol version and must preserve charge matching and the control
conditions.

Input and output channels are selected by a pre-run mapping procedure, not by
the LLM. Readout groups are disjoint from stimulation groups. Neural features
are extracted only after the declared blanking interval. Primary features
remain intentionally simple:

- spike counts per readout group and fixed time bin;
- first-spike or population-response latency where defined;
- active-channel count;
- optional pre-registered burst count or population-rate features.

Raw voltage waveform features and high-capacity nonlinear models are excluded
from the primary analysis because they increase artefact and overfitting risk.
They may be exploratory and must be labeled as such.

The primary decoder is regularized logistic regression or an equivalently
small linear classifier. It is trained during a separate calibration/training
block, serialized with preprocessing statistics and coefficients, then frozen
before the confirmatory test block. The test labels remain hidden from the
online decoder until its decision is committed.

- [ ] Freeze the two class encodings after provider review.
- [ ] Define the mapping algorithm and minimum channel-quality criteria.
- [ ] Freeze feature bins, normalization, decoder, and decision threshold.
- [ ] Verify charge, channel-use, and timing equality automatically.
- [ ] Add a leakage test proving that class cannot be recovered from
  readout-window stimulation metadata or trial ordering.
- [ ] Define an optional online adaptation extension, but keep it disabled in
  `pattern_gate_v1`.

### B5. Trial and session state machines

Each trial follows:

```text
SCHEDULED
  -> PRE_STIMULUS
  -> STIMULATING
  -> ARTEFACT_BLANKING
  -> OBSERVING
  -> FEATURIZING
  -> DECISION_COMMITTED
  -> LABEL_REVEALED
  -> INTER_TRIAL
  -> COMPLETE

any active trial -> ABORTED | INVALID
```

No decision is counted when stimulation acknowledgement, timing, recording,
feature completeness, decoder identity, or label commitment is missing.
Invalid trials remain in the run record and are never silently retried in a
way that changes the frozen randomization.

The session contains:

1. **Preflight:** runtime attestation, system attributes, package/config
   hashes, lease ownership, approval, safety policy, recording capacity, clock,
   and lifecycle checks.
2. **Pre-baseline:** spontaneous activity without stimulation; determine
   whether activity and data completeness meet the frozen admissibility rule.
3. **Mapping:** provider-approved low-risk input/readout mapping where needed;
   produce a versioned channel-map artifact.
4. **Calibration/training:** balanced randomized labeled trials used only to
   fit preprocessing and the linear decoder.
5. **Frozen validation:** verify the decoder on held-out calibration trials
   before the confirmatory block.
6. **Confirmatory test:** balanced randomized A/B trials plus scheduled sham
   trials; no refitting or threshold changes.
7. **Post-baseline and cooldown:** observe recovery, detect state change, and
   satisfy provider cooldown rules.
8. **Validation and finalization:** close recording, calculate checksums,
   validate completeness and postconditions, and return a compact summary.

Session and block sizes will be selected through E3 runtime tests and a small
E5 technical pilot, then frozen before the main measurement. They must be
large enough for uncertainty estimates but small enough to avoid excessive
stimulation, resource cost, and within-session drift.

- [x] Implement trial and session state machines independently of the UI.
- [x] Implement deterministic seeded scheduling with balanced blocks.
- [ ] Implement full partial-run finalization and explicit per-trial invalid
  reasons. The CP²N² E3 runtime already preserves a checksum-bearing partial
  summary after an interrupted application run.
- [ ] Implement cooperative abort at safe boundaries plus forced-timeout
  reporting when the platform terminates the application.
- [x] Verify that aborted and partially recorded sessions remain visible and
  cannot be reported as successful.
- [ ] Add the provider-backed forced-timeout case once its termination and
  status-query semantics are known.

### B6. Controls and confirmatory analysis

Required controls are:

- **label permutation:** estimates the decoder null distribution;
- **sham trials:** follow the same schedule without a stimulation pattern when
  provider rules permit;
- **pre-stimulus features:** test whether baseline state or temporal leakage
  predicts labels;
- **artefact control:** disjoint channels, explicit blanking, matched charge,
  and analysis excluding raw stimulation-adjacent waveforms;
- **stimulus-only metadata control:** confirm that the primary decoder receives
  no class-revealing stimulation metadata;
- **simple silicon baselines:** majority class and the same linear pipeline
  applied to pre-stimulus/sham features;
- **E3 technical control:** run the complete package on deterministic random
  and replay sources; never interpret E3 accuracy as biological performance;
- **time control:** report first versus second half and block order;
- **session control:** repeat time-separated sessions to quantify drift.

Primary application metrics:

- balanced accuracy with confidence interval;
- ROC-AUC where probability output is valid;
- confusion matrix, sensitivity, and specificity;
- effect size against label permutation and control features;
- decision and neural-response latency;
- invalid, missing, aborted, and sham trial counts;
- calibration and probability reliability where sample size permits;
- within-session and between-session drift.

Primary CP²N² metrics for the case study:

- correct runtime-kind attestation;
- zero unapproved E5 starts;
- zero concurrent exclusive E5 runs;
- zero accepted stale-telemetry runs;
- audit completeness and artifact completeness;
- lifecycle and lease timing;
- abort and reconciliation outcome;
- control-plane overhead outside the local real-time loop.

Analysis is split into:

1. an online minimal implementation for visualization and decision making;
2. an offline, versioned confirmatory pipeline that regenerates all metrics and
   figures from the archived artifacts.

- [ ] Write and test the online feature and frozen-decoder implementation.
- [ ] Write the independent offline analysis and figure pipeline.
- [ ] Pre-register exclusions, primary metrics, confidence intervals, and the
  rule for aggregating trials, sessions, and cultures.
- [x] Demonstrate that offline reconstruction reproduces every online decision
  for the E3 golden success bundle; repeat against exported E5 artifacts later.
- [ ] Add automated claim-matrix updates from validated run summaries.

### B7. CL application package

The package follows the current CL application model:

```text
cp2n2-biopattern-gate/
  info.json
  default.json
  requirements.txt              # only if provider permits dependencies
  presets/
    technical-e3.json
    pattern-gate-v1.json        # E5 values only after approval
  src/
    __init__.py
    application.py
    config.py
    protocol.py
    scheduler.py
    mapping.py
    features.py
    decoder.py
    recording.py
    provenance.py
    safety.py
    results.py
  web/
    vis.html
    vis.css
    vis.mjs
```

`src/__init__.py` exports one `cl.app.BaseApplication` instance. The run method
accepts the frozen configuration and provider-supplied output directory,
executes the session state machine, and returns a compact `RunSummary`. The
package is created with the official `cl.app.pack` workflow and is tested
locally with `cl.app.run`; local running is development-only and does not
replace device-side validation or safety enforcement.

The application publishes low-volume visualization data streams for:

- `pattern_gate/session`;
- `pattern_gate/trial`;
- `pattern_gate/gate`;
- `pattern_gate/features`;
- `pattern_gate/decision`;
- `pattern_gate/control_status`.

Raw neural events remain in the native recording. Visualization streams must
not duplicate large raw arrays or contain secrets.

- [ ] Generate the official application skeleton and commit it in the repo.
- [ ] Implement the package modules and provider-compatible visualization.
- [ ] Pin or eliminate optional dependencies.
- [ ] Pass official packager structure, import, configuration, and visualizer
  validation.
- [ ] Produce a reproducible ZIP and package manifest with checksums.
- [ ] Verify installation and launch procedure on the granted Cloud environment
  before any biological stimulation.

### B8. Recording, provenance, and result artifacts

Every run produces, subject to provider export permissions:

- native HDF5 recording containing spikes, stim events, attributes, application
  data streams, and raw samples only when explicitly enabled and permitted;
- `result.json` with compact machine-readable outcome;
- `summary.md` for the provider UI and artifact package;
- validated configuration and policy snapshots;
- runtime attestation and `cl.get_system_attributes()` snapshot;
- package, source commit, preset, feature schema, and decoder identifiers;
- trial table with schedule position, class, prediction, probability, timing,
  validity, and exclusion reason;
- channel-map and calibration artifacts;
- decoder preprocessing, coefficients, threshold, and training provenance;
- lifecycle, lease, approval, MCP audit, and distributed trace references;
- checksum manifest for every exported file.

The HDF5 path or provider artifact identifier is treated as an artifact
reference, not assumed to be a locally readable path. Export status is one of
`complete`, `partial`, `provider_retained`, `unavailable`, or `unknown`.

`result.json` must include at least:

- `run_id`, `trace_id`, `resource_id`, and provider run ID;
- `runtime_kind`, evidence level, and attestation method/time;
- protocol, config, package, policy, and decoder versions/hashes;
- start/end times and lifecycle terminal state;
- trial and control counts;
- primary metrics with uncertainty;
- baseline, cooldown, drift, and completeness summaries;
- abort/reconciliation information;
- `substrate_executed` and `pnn_evidence` booleans;
- validation findings and claim eligibility.

- [ ] Define and version result, trial-table, and manifest schemas.
- [ ] Capture `cl.is_simulator()` and `cl.get_system_attributes()` on every run.
- [ ] Ensure runtime kind is visible in recording, summary, result, UI, and
  filename or artifact metadata.
- [ ] Test normal, invalid, partial, aborted, timed-out, and unknown-status
  artifact paths.
- [ ] Verify checksums and offline reconstruction before claim eligibility.

### B9. CP²N² control-plane integration

The CL on-device application is a substrate runtime. The CP²N² CL control
adapter remains responsible for provider-facing discovery, deployment,
reservation, run start/status/abort, artifact retrieval, and reconciliation.
The remote LLM and MCP server never participate in the time-critical neural
loop.

Required integration flow:

```text
discover_resources
  -> describe_resource
  -> dry-run prepare_assay(pattern_gate_v1)
  -> reserve_resource
  -> external exact-run-bound human approval
  -> prepare_assay
  -> run_assay
  -> get_run_status
  -> get_result_summary
  -> release_resource
```

The adapter must map provider contention to CP²N² leases without claiming
stronger atomicity than the provider offers. If a network timeout makes start,
abort, or completion uncertain, the result is
`EXECUTION_STATUS_UNKNOWN` until provider reconciliation succeeds.

The approved preset visible to the agent contains only a description,
compatibility requirements, expected duration/cost metadata, and high-level
purpose. Physical parameters, channel mappings, decoder internals, and safety
limits remain server-owned.

- [ ] Add `pattern_gate_v1` to the A4 server-owned assay catalog.
- [ ] Define the provider control-adapter methods after Cloud access is granted.
- [ ] Map provider resource, queue, reservation, run, and artifact identifiers
  into the resource contract.
- [ ] Bind human approval to package hash, preset hash, resource ID, and run ID.
- [ ] Implement status polling, timeout semantics, abort, reconciliation, and
  artifact retrieval against documented provider behavior.
- [ ] Prove that MCP/LLM input cannot alter physical parameters or bypass
  provider and project policy.

### B10. Development stages and acceptance gates

#### B10.1 B0 -- protocol and interface freeze

- [ ] Confirm provider channel, stimulation, recording, raw-data, session, and
  export constraints.
- [ ] Confirm the Cloud application lifecycle and authentication method.
- [ ] Freeze application schemas, trial state machine, artifact layout, and
  claim boundary.
- [ ] Complete threat, safety, artefact, and statistical review.

**Done when:** the repository contains an approved executable specification
with no guessed E5 physical values or provider API semantics.

#### B10.2 B1 -- pure software core

- [ ] Implement scheduler, state machines, feature extraction, decoder, result
  schemas, and visualizer against test doubles.
- [ ] Add property tests for balanced schedules, charge equality, no overlap,
  deterministic replay, invalid-trial accounting, and abort finalization.
- [ ] Add golden fixture bundles for success, chance-level, partial, and aborted
  runs.

**Done when:** the substrate-independent core and demo replay pass without the
CL SDK.

#### B10.3 B2 -- E3 SDK Simulator

- [ ] Run random-source and fixed-seed deterministic campaigns.
- [ ] Run replay-source campaigns using permitted recordings when available.
- [ ] Validate local packaging, local application execution, visualizer, HDF5,
  summaries, abort, timeout, repeat, and offline reconstruction.
- [ ] Verify that E3 is labeled non-learning technical evidence everywhere.

**Done when:** package, start, abort, repeat, artifacts, checksums, replay, and
the complete demo work deterministically. Accuracy is not an E3 acceptance
criterion.

#### B10.4 B3 -- Cloud installation smoke test without assay execution

- [ ] Authenticate using the provider-supported method.
- [ ] Upload/install the exact checked package.
- [ ] Verify package metadata, preset visibility, output directory behavior,
  dependency installation, visualizer loading, status, logs, and removal or
  version replacement.
- [ ] Do not stimulate biological hardware in this gate.

**Done when:** deployment and observability are understood and recorded without
claiming substrate execution.

#### B10.5 B4 -- E5 technical pilot

- [ ] Obtain exact-run human approval and provider authorization.
- [ ] Attest physical hardware and capture system attributes.
- [ ] Run baseline and the smallest approved mapping/pilot schedule.
- [ ] Exercise recording, artifact export, safe abort if approved, cooldown,
  postcondition validation, and reconciliation.
- [ ] Review artefacts before any classification or learning claim.

**Done when:** one technically complete E5 run proves the end-to-end systems
path and reveals no safety, artefact, provenance, or data-integrity blocker.

#### B10.6 B5 -- assay pilot and protocol freeze

- [ ] Estimate viable input/readout groups and effect size.
- [ ] Freeze trial counts, windows, features, decoder, exclusions, and analysis.
- [ ] Decide whether BioPattern Gate is viable as a confirmatory
  discrimination assay.
- [ ] Pre-register the final protocol before additional E5 data collection.

**Done when:** the confirmatory protocol is fixed without optimizing on its
future test data.

#### B10.7 B6 -- main measurement and demo capture

- [ ] Execute the approved repeated-session plan.
- [ ] Archive successful, failed, partial, and aborted runs.
- [ ] Regenerate all results and figures independently.
- [ ] Capture a representative live or replay demo with explicit evidence
  labels.
- [ ] Update the claim matrix and remove unsupported claims.

**Done when:** every application and control-plane claim maps to validated,
versioned evidence.

#### B10.8 Implementation checkpoint -- 28 July 2026

The first access-independent vertical slice is implemented on branch
`codex/b1-biopattern-gate-core`:

- canonical core under `applications/biopattern_gate/`;
- frozen `BioPatternGateConfig` v1 and checked-in JSON Schema;
- empty fail-closed `provider-approved` namespace and one explicitly
  simulator-only `technical-e3` preset;
- deterministic balanced scheduler, trial/session state machines, fixed
  feature extractor, frozen decoder artifact, decision commitments, result
  records, and a narrow future-provider port;
- deterministic reservoir test double and local non-LLM demo runner;
- a versioned E3 success replay bundle plus independent reconstruction of
  every feature-based decision, gate route, probability, commitment hash,
  confusion count, and balanced accuracy;
- official self-contained CL app skeleton under
  `cl-apps/cp2n2-biopattern-gate/`, including an E3 banner visualizer;
- successful official `cl.app.pack` validation and successful local
  `cl.app.run` execution with 14 trials, 12 scored A/B trials, and 2 shams;
- reproducible package script and per-entry SHA-256 manifest;
- `pattern_gate_v1` in the server-owned MCP assay catalog without channels,
  amplitudes, timing primitives, or other agent-editable physical controls;
- versioned canonical, paraphrase, ambiguous-intent, parameter-injection, and
  approval-bypass prompt fixtures.

This checkpoint proves only the E3 software path. The deterministic accuracy
is a golden-pipeline assertion, not biological performance.

#### B10.9 Control-plane application package -- 29 July 2026

The next access-independent package connects the frozen application to the
real CP²N² lifecycle rather than invoking its runner directly:

- dedicated `BioPatternGateE3Adapter` and separate E3 runtime with attested
  `sdk_simulator`/E3 evidence;
- server-owned `pattern_gate_v1` bound to exact application-source,
  configuration, and frozen-decoder SHA-256 values;
- complete `dry-run -> reserve -> prepare -> run -> status -> result ->
  automatic release` path through the constrained MCP control surface;
- deterministic non-LLM client and stdio-server registration switch
  `CP2N2_INCLUDE_BIOPATTERN_GATE_E3`;
- sanitized aggregate application summary, orchestration correlation ID,
  audit request IDs, and checksum-bearing result/partial artifact references;
- explicit `biological_claim=false`, no raw event output, and no
  agent-editable physical parameter at the application boundary;
- tested rejection or safe handling of physical-parameter injection,
  competing reservations, stale telemetry, prepared-run abort, interrupted
  partial execution, and final lease release;
- successful validation and packaging by the official `cl.app.pack` tool.

The complete repository test suite passes with 127 tests. This package is
systems evidence for RQ1/RQ2. It does not evaluate a PNN, simulate a biological
result, or close any E5 gate.

The first hard access boundary is now explicit. The following work may not be
implemented by guessing and waits for the grant/onboarding material:

1. supported non-interactive authentication and credential-provider behavior;
2. Cloud resource discovery, application upload/install, run lifecycle,
   status, abort, reconciliation, and artifact-export contracts;
3. provider-approved stimulation, channel-map, blanking, recording, session,
   cooldown, and safety limits;
4. verified CL1 runtime/system attestation and E5 preset creation;
5. Cloud smoke test and every biological stimulation or E5 claim.

### B11. Sample, repetition, and claim policy

**Minimum:** one real culture and repeated time-separated sessions. Claims are
limited to an end-to-end systems case study and culture-specific observed
behavior. Trial count is not a substitute for biological replication.

**Target:** at least three independent cell batches with at least three
time-separated sessions per batch. This permits cautious evidence about
reproducibility across cultures, not broad biological generalization.

The unit of biological replication is the independent culture or cell batch,
not each stimulation trial. Session and trial observations are nested and must
not be analyzed as independent biological replicates. Report all exclusions,
missing sessions, culture age and identity metadata when available, and
within-/between-culture uncertainty.

An unsuccessful discrimination result does not invalidate the CP²N²
end-to-end systems case study if the E5 execution, safety, provenance,
lifecycle, and artifacts are complete. It does invalidate or weaken RQ4 and
must be reported honestly.

### B12. Cortical Cloud access, cost, and authentication

**Project information recorded 27 July 2026:**

- the observed non-grant offer is USD 2,170 for one month of one instance;
- a grant request has been submitted;
- access approval and allocation are pending;
- exact programmatic authentication and automation capabilities are unknown.

These values are project planning information supplied by the project owner;
they must be reconfirmed against the eventual offer before publication or
booking.

The current public provider material states that Cortical Cloud supports
browser-based use and custom-code deployment through the Python SDK. The
public CL application documentation specifies application initialization,
immutable configuration models, local development running, ZIP packaging, and
device-side installation. As of 27 July 2026 it does **not** publicly specify:

- a Cloud REST or GraphQL endpoint;
- API-key creation or header format;
- OAuth scopes, client credentials, refresh tokens, or device-code flow;
- CLI login and credential storage;
- programmatic upload, reservation, run, status, abort, or artifact endpoints;
- service-account or unattended automation support.

The visible Cloud sign-in page currently offers Discord, GitHub, Google,
Microsoft, email, and passkey login. This establishes interactive account
authentication only; it does not establish a programmatic API credential.
Therefore the adapter must not guess an API key, bearer token, cookie, endpoint,
or environment-variable name.

Public reference snapshot used for this assessment:

- Cortical Cloud: <https://corticallabs.com/cloud>
- CL API Developer Guide: <https://docs.corticallabs.com/>
- CL application model: <https://docs.corticallabs.com/cl/app>
- application initialization: <https://docs.corticallabs.com/cl/app/init>
- application packaging: <https://docs.corticallabs.com/cl/app/pack>
- local development runner: <https://docs.corticallabs.com/cl/app/run>

Questions to resolve during grant onboarding:

1. Is access browser-only, SDK-mediated, CLI-mediated, or available through a
   documented HTTP API?
2. Does SDK deployment run locally against a remote control endpoint, inside a
   hosted Jupyter environment, or both?
3. Which user or service authentication methods support unattended runs?
4. How are credentials issued, scoped, rotated, revoked, and audited?
5. Are project/service accounts available, or must every action be attributed
   to an interactive user?
6. What are the resource discovery, queue, reservation, start, status, abort,
   reconciliation, and artifact-export interfaces?
7. What identifiers and timestamps are returned for device, culture, package,
   configuration, allocation, and run?
8. Can application ZIPs and dependencies be uploaded, versioned, verified, and
   removed through an API?
9. What health, calibration, culture-age, contention, and telemetry fields are
   observable?
10. What data can be exported, for how long is it retained, and are raw samples
    enabled by request?
11. What are the grant limits, permitted use, publication terms, attribution,
    support channel, and overage behavior?
12. Is safe abort exposed, and what provider state follows timeout, disconnect,
    or application failure?

Credential handling requirements:

- secrets remain in an untracked local file or approved secret store;
- no secret, cookie, token, authorization code, or passkey material enters Git,
  MCP input, audit logs, run artifacts, screenshots, or paper supplements;
- the adapter accepts credentials through a replaceable credential-provider
  boundary once the official mechanism is known;
- interactive browser sessions are not scraped or reused as undocumented API
  credentials;
- all provider calls use the official HTTPS host and least available privilege;
- authentication failure is explicit and never downgraded to simulator mode.

- [x] Record the current cost and grant-request state.
- [x] Audit the public Cloud and CL application documentation for auth details.
- [x] Record interactive sign-in methods without treating them as API access.
- [ ] Obtain grant decision and onboarding documentation.
- [ ] Confirm the official automation/authentication mechanism.
- [ ] Implement and test the credential-provider boundary without committing
  credentials.

### B13. Final go/no-go gates and definition of done

**Access status (29 July 2026):** Cortical Labs has indicated that access to a
CL1 system can be expected no earlier than approximately twelve weeks. The
project will enter the access queue and continue the systems-paper work in
parallel. This estimate is a planning input, not a promised access date and
not a submission deadline.

**Application implementation may begin now** against the CL SDK Simulator and
test doubles because it requires no real-device access and produces no E5
claim.

**Cloud integration may begin only if:** the grant or paid allocation is
active; the supported authentication and application lifecycle are known; and
provider terms permit the planned deployment, recording, export, and
publication.

**Hardware pilot may start only if:** the E3 package is reproducible;
server-side limits and configuration validation pass; abort/timeouts are
tested; E5 attestation is available; recording/provenance is complete; exact
human approval is present; and the provider permits the assay and intended
data export.

**Main measurement may start only if:** the technical pilot is complete;
artefact blanking and channel mapping work; the assay pilot supports a frozen
protocol; no safety or integrity issue remains; access cost/allocation and the
repetition plan are confirmed; and the analysis is pre-registered.

BioPattern Gate is `DONE` only when:

- the source, application ZIP, schemas, presets, tests, and UI are versioned;
- the E3 package and replay demo are deterministic and reproducible;
- E5 runtime attestation and system provenance are captured when E5 is used;
- all controls and offline reconstruction pass;
- safe lifecycle, lease, approval, abort, reconciliation, and release are
  demonstrated;
- HDF5/result/manifest artifacts and checksums validate;
- the paper figures and demo can be regenerated from archived data;
- every claim is supported or explicitly downgraded.

If real access is unavailable, RQ3/RQ4 and every result-level CL1 claim are
removed from the submission manuscript; at most, the planned E5 case study is
described explicitly as future work. The BioPattern Gate package and E3 demo
remain software artifacts, and the general control-plane paper remains viable
on RQ1/RQ2. An E3 run never serves as a proxy, pilot result, or lower-fidelity
measurement for either RQ3 or RQ4.

## 6. Workstream C: evaluation

| Family | Purpose | Evidence |
|---|---|---|
| Contract conformance | schema, lifecycle, errors, idempotency | E0–E3 |
| Policy evaluation | admission, ranking, sensitivity | E1–E4 |
| Distributed robustness | concurrency, loss, partitions, recovery | E2–E4 |
| Control-plane overhead | local orchestration and service-boundary cost | E1–E2 |
| Audit and authority boundary | trace completeness and adversarial agent requests | E0–E3 |
| CL software integration | packaging, API compatibility, repeatable controls, demo logic | E3 |
| Real PNN integration | constrained agent-mediated run | E5 |
| Substrate case study | pattern response and stability | E5 |

Pre-register, before the main measurement: false accepts/rejects; concurrent exclusive runs (target: zero); time to reconciliation; stale-telemetry accepts (target: zero); p50/p95/p99 control overhead; successful completion rate; audit completeness (target: 100%); and the primary case-study metric.

All runs require a common `run_id` and produce a manifest, resource descriptor, policy snapshot, lease and control traces, provider metadata, raw recording when permitted, features, analysis output, figures, and checksums. Failed and aborted runs remain visible in the run register.

## 7. Workstream D: paper and artifact

### Two-layer publication strategy

The manuscript is developed as two modules with independent evidence gates:

1. **Systems-paper core (always present):** RQ1/RQ2; resource contracts,
   constrained agent-facing assays, admission and selection, lifecycle,
   leases, telemetry freshness, abort and reconciliation, auditability,
   adapter portability, distributed faults and concurrency, and
   control-plane overhead. This module must be submission-ready without CL1
   access.
2. **CL1 case-study module (conditional):** RQ3/RQ4; one attested E5
   end-to-end orchestration case and the controlled BioPattern Gate response
   study. This module is included only after its E5 gates pass.

The E3 CL SDK Simulator belongs to the systems and implementation evidence. It
may show API compatibility, deterministic packaging and replay,
reproducibility, safe execution of server-owned presets, and the complete demo
logic. It does not make the CL1 module empirically complete and does not
support any statement about a culture, biological computation, learning,
accuracy, latency, stability, or performance.

The LaTeX source must keep the CL1 module behind one explicit inclusion switch
whose default submission-safe state is **off**. The systems-only build must
compile without dangling RQ3/RQ4 references, empty result promises, or wording
that implies real-hardware evidence. When the switch is off, the paper contains
only a short, clearly labelled future-work paragraph about the planned E5 case
study.

Submission readiness is evidence-driven, not calendar-driven. No short-term
venue deadline justifies promoting an open claim, treating E3 as E5, or
submitting before the RQ1/RQ2 artifact and manuscript audits pass.

### Claim matrix

Maintain a living matrix before writing results:

| ID | Claim | RQ | Valid evidence | Planned paper evidence | Status |
|---|---|---|---|---|---|
| C1 | The versioned resource contract is shared across heterogeneous adapters and preserves substrate-specific constraints. | RQ1 | E0–E3 | schema/conformance and portability table | supported; final artifact audit pending |
| C2 | Missing or stale safety-relevant information fails closed before execution. | RQ1 | E0–E3 | invalid-contract, stale-telemetry, and policy tests | supported; final aggregate pending |
| C3 | Admission, feasibility, and ranking are separate and every exclusion/selection is explainable. | RQ1 | E1–E3 | curated/holdout policy evaluation and sensitivity results | supported; manuscript integration pending |
| C4 | The agent can request only published high-level assays and cannot set physical primitives, policy, evidence level, or approval. | RQ1 | E0–E3 | MCP surface, malformed-plan, injection, and bypass tests | supported for software boundary only |
| C5 | The adapter/runtime split preserves a common control contract across multiple non-CL backends. | RQ1 | E1–E3 | adapter conformance and no-CL portability test | supported; final table pending |
| C6 | Exclusive leases prevent concurrent execution by competing owners. | RQ2 | E0–E2 | lifecycle tests and 1–32-client campaign | supported; final aggregate pending |
| C7 | Timeouts and uncertain outcomes trigger explicit abort/reconciliation rather than silent success. | RQ2 | E0–E2 | state-machine, timeout, abort, and reconciliation traces | supported; final figure pending |
| C8 | Stale telemetry and declared fault conditions cause rejection, safe fallback, or explicit failure as specified. | RQ2 | E1–E2 | loss, partition, stale-state, and fault campaign | supported; final aggregate pending |
| C9 | Control decisions and run transitions are linked by complete, tamper-evident audit records. | RQ2 | E0–E3 | audit-chain and trace-correlation tests | supported; completeness summary pending |
| C10 | The measured control-plane overhead is bounded for the evaluated local and same-host deployments. | RQ2 | E1–E2 | p50/p95/p99 orchestration and service-boundary latency | partially supported; rerun on frozen protocol |
| C11 | The CL package and adapter execute reproducibly against the official SDK simulator. | RQ1 | E3 only | package validation, deterministic replay, API and demo tests | supported as technical evidence only |
| C12 | CP²N² can safely orchestrate an attested real CL1 through a constrained agent request. | RQ3 | E5 only | real execution trace, approval, audit, abort/release evidence | open; excluded until E5 |
| C13 | A real CL1 culture produces reproducible task-relevant BioPattern Gate responses. | RQ4 | E5 only | pre-registered controlled assay with uncertainty analysis | open; excluded until E5 |

Remove or downgrade every claim that lacks passing evidence.

The table is deliberately asymmetric: lower evidence levels can be correct for
software and distributed-systems claims, while C12/C13 have an absolute E5
floor. No combination or volume of E0–E4 results can satisfy that floor.

### Motivating agentic-PNN scenarios

BioPattern Gate is the controlled evaluation scenario for CP²N², not the
sole or strongest end-user motivation for agentic access to PNNs. The paper
must introduce one or two forward-looking but technically grounded scenarios
before presenting BioPattern Gate. These scenarios explain why an AI agent
would request a PNN through a control plane rather than call a fixed software
endpoint.

They are **motivating scenarios, not evaluated contributions**. The paper must
use conditional language, cite primary evidence for the relevant substrate
capabilities, and never imply that CP²N² has already demonstrated the full
application.

#### Scenario D1: autonomous functional-neurobiology campaign

A scientific agent is tasked with coordinating a multi-session campaign over
living neural cultures, for example:

```text
Compare how the approved candidate conditions affect temporal
information-processing performance across the available neural cultures.
Use only validated assay presets, balance the sessions across cultures, stop
on safety or data-quality failures, and schedule a confirmatory follow-up only
when the pre-registered evidence threshold is met.
```

The agent operates at campaign level. It may select a compatible assay,
resource, session order, and permitted follow-up based on validated summaries.
It may not design arbitrary stimulation, administer an unapproved compound,
change a statistical endpoint after seeing results, or bypass human and
laboratory approval.

The PNN is valuable here as a functional biological assay: it exposes dynamic
information processing, adaptation, drift, and response to an approved
condition rather than only a static molecular measurement. The control-plane
problem is essential because cultures are scarce, stateful, age-dependent,
non-interchangeable, safety-constrained, and affected by their prior
experimental history.

CP²N² provides:

- culture/resource discovery with provenance and evidence level;
- compatibility and policy admission for the requested assay;
- calibration, health, drift, and freshness checks;
- exclusive leases and balanced campaign scheduling;
- constrained presets and exact-run human approvals;
- abort, cooldown, recovery, and reconciliation;
- immutable run provenance and cross-session artifact linkage.

This scenario motivates agentic scientific discovery and functional
drug/disease-model studies. BioPattern Gate supplies a small, controlled
instance of the same resource-management problem without claiming to perform a
complete autonomous pharmacological campaign.

#### Scenario D2: adaptive embodied system over heterogeneous PNN resources

An embodied or edge AI agent must maintain a temporal sensing or control task
under changing conditions. Its high-level request could be:

```text
Maintain the event-stream classification task within the declared latency and
energy budget. Select an available physical-neural resource that supports the
input modality, validate its current calibration, and fail over safely if its
health, drift, locality, or telemetry no longer satisfies the policy.
```

Candidate PNN resources could include neuromorphic hardware, memristive or
photonic reservoirs, biological neural cultures, and simulators used only at
their appropriate evidence levels. The agent chooses among advertised
capabilities and policies; it does not implement the millisecond-scale control
loop itself.

The time-critical encoder, inference/readout, and actuator loop run in the
substrate-local application. The remote agent performs deliberative functions:
resource choice, mission-level planning, requesting preparation or
recalibration, interpreting validated summaries, and selecting a safe
fallback.

CP²N² provides:

- modality-, latency-, locality-, cost-, and evidence-aware admission;
- transparent selection among heterogeneous physical substrates;
- lifecycle and calibration management before task commitment;
- exclusive access to non-shareable devices;
- bounded deployment and local-runtime invocation;
- detection of stale telemetry and unsafe failover;
- provenance linking an agent decision to the physical execution.

This scenario motivates the generality of CP²N² beyond CL1 and makes clear
why hard real-time control is outside the LLM and MCP boundary.

#### How the paper uses the scenarios

The introduction and motivating-scenario section must follow this sequence:

1. Establish that agentic systems increasingly compose tools and resources from
   high-level goals.
2. Explain why ordinary endpoint metadata and stateless tool assumptions fail
   for PNN resources.
3. Present D1 and D2 as concrete user-level tasks.
4. Derive the shared requirements: explicit modality and evidence,
   provenance, freshness, calibration, health, exclusivity, safety, lifecycle,
   local real-time execution, recovery, and auditability.
5. Introduce CP²N² as the common control plane satisfying those
   requirements.
6. Present BioPattern Gate later as the deliberately narrow, reproducible CL1
   evaluation case rather than as the complete application vision.

The requirements section must include a traceability table:

| Scenario pressure | Required CP²N² mechanism | Evaluated by |
|---|---|---|
| scarce cultures or exclusive devices | leases and ownership | A2/A6 |
| changing health, calibration, and drift | telemetry provenance/freshness and admission | A1/A3/A6 |
| unsafe agent-generated physical parameters | server-owned presets and approval | A4/B |
| heterogeneous modalities and substrates | resource contract and adapter capabilities | A1/A5 |
| remote timeout with uncertain physical state | abort and reconciliation | A2/A6/B |
| local real-time loop versus remote deliberation | control-adapter/runtime split | A5/B |
| cross-session scientific accountability | audit, manifests, artifacts, checksums | A4/A6/B |

In the discussion, return to both scenarios and state precisely which
requirements the evaluation supports, which elements remain engineering work,
and which require future domain-specific validation.

- [x] Select two motivating agentic-PNN scenarios with distinct domains.
- [x] Separate the motivating scenarios from the evaluated BioPattern Gate
  contribution.
- [ ] Add primary literature and platform citations for every substrate or
  application capability used in D1 and D2.
- [ ] Write the two introduction vignettes in user-goal language.
- [ ] Add the scenario-to-requirement traceability table to the paper.
- [ ] Add a generic figure showing remote agent deliberation, CP²N² control,
  and substrate-local real-time execution.
- [ ] Revisit both scenarios in limitations and future work without promoting
  them to demonstrated claims.

### Related-work and terminology boundary: PhysMCP

Before the next public paper or software release, add a focused related-work
subsection on **PhysMCP** (the `physmcp.org` open-standard proposal). The
similarity of the names is a discoverability and reader-confusion risk; the
subsection must therefore be explicit rather than relying on a spelling or
hyphen distinction. This is an architectural comparison, not a priority,
authorship, or legal claim.

The paper must fairly describe PhysMCP as a general proposal for exposing
physical devices as native MCP servers, with direct agent-to-device interaction
and mesh-oriented coordination. It must then state the boundary to this
project:

| Dimension | PhysMCP proposal | CP²N² project |
|---|---|---|
| Target resource | general physical/IoT device | scarce, stateful physical-neural resource |
| Primary architectural unit | device-native MCP server and mesh interaction | control plane plus resource adapters and substrate-local runtime |
| Coordination focus | device capability exposure and decentralised interaction | admission, leases, lifecycle, recovery, reconciliation, and audit |
| Safety/accountability focus | device-local policy and declared capabilities | server-owned approved presets, human approval where required, evidence levels, and run provenance |
| Real-time boundary | not a claim of this project | hard real-time control remains substrate-local; MCP/agent actions are deliberative |

The distinction must not be caricatured: both approaches address agent access
to physical systems and may share useful contract or capability ideas. The
paper's precise contribution is the governance of heterogeneous PNN resources
whose availability, calibration, health, experimental history, exclusivity,
and uncertain physical state after failure affect whether an action may run.

- [ ] Verify the current PhysMCP specification, version, authorship, licence,
  and terminology immediately before submission; cite the primary
  specification rather than only the project website.
- [ ] Add a concise related-work comparison and the terminology boundary to
  the paper.
- [ ] Review the project name before the next public release; do not present a
  rename as a legal necessity without a separate trademark/availability
  clearance.
- [x] Adopt **CP²N²** as the public project and paper name and `cp2n2` as the
  technical ASCII identifier.
- [x] Retain a short ``formerly phys-MCP'' migration note in the repository
  and paper metadata where appropriate, so that the May 2026 arXiv
  version remains discoverable without suggesting affiliation with PhysMCP.
- [ ] Complete the external repository rename after local migration and
  verification.

### Recommended paper structure

1. Introduction: agentic tool use, general PNN motivation, and the gap between
   stateless endpoints and stateful physical-neural resources.
2. Motivating scenarios: autonomous functional-neurobiology campaign and
   adaptive embodied heterogeneous-PNN system; CL1 is one concrete resource,
   not the definition of the architecture.
3. Requirements, system model, and threat model.
4. CP²N² Control-Plane Design and Architecture.
   - `\subsection{Physical Neural Resource Contract}`
   - `\subsection{Lifecycle protocol, leases, recovery, and error semantics}`
   - `\subsection{Admission and selection}`
5. Implementation and adapter integration.
6. Evaluation.
   - `\subsection{Evidence levels, questions, and protocol}`
   - `\subsection{RQ1: Contract, admission, and portability}`
   - `\subsection{RQ2: Concurrency, failures, recovery, audit, and overhead}`
   - `\subsection{E3 CL SDK Simulator integration}` (technical evidence only)
   - `\subsection{RQ3/RQ4: CL1 case study}` (conditional E5 module)
7. Related work: PhysMCP terminology/architecture boundary, WoT, Kubernetes
   DRA, KubeEdge DeviceTwin, ROS 2 lifecycle, OPC UA, NIR, and substrate
   runtimes.
8. Limitations, ethics, and responsible agent access.
9. Conclusion.

Required visuals: motivating agent/CP²N²/local-runtime figure, general
architecture, state machine, contract example, generic execution sequence,
distributed testbed, policy/fault results, and a separately labelled
representative CL1 case-study figure.

The CL SDK Simulator must appear as a permanent E3 implementation and
controlled-evaluation backend, clearly differentiated from E5 results. Its
results must never share a table, plot series, or aggregate metric with E5
results unless the evidence level is visually explicit in every row or mark.

### Artifact package

- release code and setup guide;
- contract/policy examples and conformance suite;
- simulator configuration and regression recordings;
- distributed test configurations and fault profiles;
- scripts for every table and figure;
- publication-eligible raw or aggregated results;
- explicit statement of unavailable provider data and licensing constraints.

## 8. Milestones

The timing below is effort-based, not a fixed calendar promise.

| Milestone | Deliverable | Target |
|---|---|---:|
| M0 | scope, claim matrix, audited baseline | week 1 |
| M1 | contract and evidence-level specification | week 2 |
| M2 | lifecycle, leases, errors, conformance | week 4 |
| M3 | policy profiles and baselines | week 5 |
| M4 | BioPattern Gate complete in SDK Simulator | week 7 |
| M5 | distributed fault campaign | week 9 |
| M6 | submission-ready RQ1/RQ2 systems manuscript and artifact | during CL1 wait |
| M7 | real CL1 pilot, if access is approved | no earlier than access availability |
| M8 | main real-PNN measurements | after successful E5 pilot |
| M9 | optional CL1 module integrated and re-audited | after final E5 data |

Software specification and paper method sections may be written from M1
onward. RQ1/RQ2 result sections are added after their protocol and artifact
freeze; the CL1 result module is added only after the separate E5 protocol
freeze and evidence review.

## 9. Cost, access, and risk

The project owner observed a current offer of USD 2,170 for one month of one
Cloud instance and submitted a grant request on 27 July 2026. This is internal
planning information until the provider confirms the grant, allocation, exact
terms, and any overage behavior in writing. No paid allocation should be booked
before M4, the E5 access/authentication clarification, and approval of the
pilot and repetition plan.

| Risk | Mitigation |
|---|---|
| CL1 access delayed beyond the current approximately twelve-week estimate | complete and audit the submission-ready RQ1/RQ2 systems paper; keep the E5 module disabled |
| No usable real-cloud access | confirm early; assess another independent remote PNN platform; retain RQ1/RQ2 paper path |
| Grant denied or allocation too expensive | complete E3 artifact; seek a smaller sponsored pilot or alternative E5 platform; do not weaken evidence labels |
| Short-term venue deadline pressures premature claims | submit only after the relevant evidence and artifact gates pass; prefer the next suitable venue over an evidence downgrade |
| Cloud automation/authentication unavailable | use the documented interactive workflow for an approved pilot if reproducible; otherwise do not claim automated E5 control-plane integration |
| Insufficient culture diversity | present CL1 work as a systems case study only |
| No custom application deployment | adapt to permitted provider workflow or do not claim E5 integration |
| Stimulus artefacts drive classification | disjoint channels, blanking, sham, matched charge, shuffled labels |
| Strong biological drift | measure and report it as a first-class resource property |
| Unsafe agent plan | approved presets, server-side policy, human approval |
| Network timeout creates unknown state | reconciliation, explicit unknown-status error, no automatic success |
| Paper looks CL-specific | preserve multiple non-CL backends, generic figures, generic contract, separate case-study section |

## 10. Operating method

Use only `TODO`, `IN_PROGRESS`, `BLOCKED`, `DONE`, or `DROPPED` for task status. A task is `DONE` only with versioned implementation/text, evidence/tests, a verifiable artifact, updated documentation, and no unsupported expansion of claims.

Maintain an ADR/decision log:

```text
date | ID | decision | alternatives | rationale | claim impact
```

At the end of each working week: update task status and risks; audit the claim matrix; archive artifacts and checksums; and confirm or revise the next milestone.

## 11. Immediate next actions

- [x] Approve the English, generalised master plan.
- [x] Add it to the project repository as the source of truth.
- [x] Complete and release the general A0--A7 software line as v4.0.
- [x] Select BioPattern Gate as the representative CL1 application.
- [x] Submit a Cortical Cloud grant request.
- [ ] Decide the target publication path after the SEC outcome.
- [ ] Obtain the grant decision and provider onboarding documentation.
- [ ] Confirm Cloud authentication, deployment, reservation, run, abort, and
  artifact-export interfaces with Cortical Labs.
- [ ] Freeze the BioPattern Gate v1 software interfaces and simulator-only
  preset.
- [ ] Build BioPattern Gate as a separate CL application package against the
  SDK Simulator.
- [ ] Run a small E5 pilot only after the M4 gate passes.

## 12. Definition of project readiness

The project is submission-ready when the contract, lifecycle, and error semantics are documented and tested; every result has a correct E0–E5 label; synthetic telemetry is never presented as observed fact; distributed tests cover concurrency, freshness, partitions, and recovery; real-PNN claims have a fully attested run or are removed; the CL case study has appropriate controls; every manuscript claim maps to evidence; the artifact package reproduces the central systems results; and limitations and ethical constraints are explicit.
