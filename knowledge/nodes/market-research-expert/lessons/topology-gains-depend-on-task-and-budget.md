---
type: Lesson
title: Compare agent topologies by task dependence, capability baseline and budget
description: The 2026-11-02/03 research separates task, capability, budget, interface coverage and handoff opportunities when comparing topologies, without establishing a universal single-writer or multi-agent advantage.
tags: [research, multi-agent, topology, evaluation, compute, model-capability]
timestamp: 2026-11-03
---

# Conclusion and scope

Treat coordinated parallel reading and single-writer execution as a useful
**candidate baseline**, not a late-2026 consensus or a universally best
architecture. The source's research distinguishes decomposable search and
analysis from tightly coupled sequential work. Extra agents can add context
and inference budget as well as coordination overhead; a performance gain
alone does not identify which change caused it.

This is a source-reported synthesis dated **2026-11-02**. It informs how to
compare systems, not a prescription that every OATS task must have one writer.

# Evidence and the disagreement to preserve

The source identifies a Google/DeepMind/MIT scaling study, arXiv 2512.08296,
v3 dated 2026-04-08, as reporting sharply different multi-agent outcomes by
task: gains on decomposable finance work, losses on sequential planning, and
less error amplification with central coordination than independent agents.
The captured summary does not supply enough experimental detail to turn its
aggregate, threshold or benchmark-specific figures into general rules.

Two practitioner accounts do not settle the same write-topology question:

- Cognition's *Multi-Agents: What's Actually Working* (2026-04-22) is reported
  to favor single-threaded writes with additional read/review intelligence.
- Cursor's scaling account (2026-01-14) is reported to reject flat lock-based
  peers in favor of planners, workers and a judge, while retaining a case
  for parallel writers under hierarchy.

Thus these accounts support examining coordination structure, **not** a
claim that all successful systems serialize writing. The source also
reports that Anthropic's research-system improvement (2025-06-13) used a
substantially larger token budget. Its summary of equal-compute studies
includes an exception but insufficient study detail to resolve the issue;
no blanket equal-compute verdict is retained.

# Recency refinement: compare the direction of model-dependent gains

The 2026-11-02 recency proposal reports diminishing collaboration benefit
as single-agent capability rises, including disadvantages on SWE-bench
Verified in the scaling study [1]. It identifies the measured models as
**GPT-5, Sonnet 4.5 and Gemini 2.5 Pro**. It also reports mid-2026 preprints
pointing in that direction [3]. These are the source's readings, not an
independently checked cross-study result or an exhaustive literature census.

The capture lacks matched configurations and controls sufficient to isolate
model strength from task, budget and topology changes. Do not retain its
numerical crossover threshold, benchmark effect sizes or error multiplier as
a portable rule. Do not infer that stronger models always reduce the value
of collaboration. Instead, compare the **change in marginal benefit** on the
same task and budget after a model upgrade, as well as which topology wins.
This capture establishes no test on a newer generation; transfer remains
unconfirmed under the [model-generation decision](/nodes/market-research-expert/decisions/date-evidence-and-name-model-generations.md).

# Capability-baseline comparison added on 2026-11-02

A further recency pass makes **single-agent capability on the tested task** an
explicit comparison variable, not just model name or release date. That pass
identifies the scaling study's models more broadly, as GPT-5, Gemini 2.x and
Claude 3.7–4.5; the refinement above names GPT-5, Sonnet 4.5 and Gemini 2.5
Pro. Neither reading was checked against the paper here, and neither is a
measurement on the newer models named below. That pass's reported
journal-publication update does not establish that the preprint's figures
survived unchanged, so no new publication status or threshold is asserted here.

The source reports a Vals AI comparison, page dated 2026-10-09, of **GPT 6 Sol
and Claude Opus 5.5**, one run over 50 apps [4]. It reports higher costs for a
lead with five subagents, a significant gain only at the weakest baseline,
no significant gain at the high baselines, and a larger gain from increasing
single-agent reasoning effort. This is a bounded reported result, not a
replicated current-generation verdict. The capture does not retain methods,
uncertainty or configurations sufficient to reuse its numerical effects or
to establish an equal-cost causal comparison.

Keep the counterexample: the source reports that Agensh, **GPT-5.6-sol**,
raised pass rates with parallel writers but lacked an equal-cost control [5].
Neither report establishes that teams never improve high-capability models,
that more writers cause the gain, or that single-writer execution is universal.
Anthropic's 2026-10-22 one-loop-first guidance is vendor advice, not a measured
comparison; its canonical home is the
[scaffolding lesson's vendor-advice section](/nodes/market-research-expert/lessons/retest-scaffolding-after-model-changes.md).

# Breadth-search evidence still needs budget qualification

A follow-up recency pass dated **2026-11-02** reports that a coordinated
**Mythos Preview** swarm found more vulnerabilities than independent agents
in Anthropic's 2026-08-13 multiagent study [6], but used a substantially
larger token budget. This is a **source-reported vendor finding**, not an
independent replication or an equal-budget coordination gain. Exact counts
and the claimed per-token parity are not retained: the captured summary
lacks validation, coverage and budget-accounting detail sufficient for
reusing them. The note's description says "Mythos 5" while its experiment
summary says "Mythos Preview"; no model equivalence is inferred here.

This is a reason to compare breadth search separately from coupled writes,
not to infer a universal swarm advantage or that stronger models cannot
coordinate better. Record the measured model, search scope, token budget
and method for validating distinct discoveries. Do not rank shared-code
integration against search breadth by comparing their headline output
counts; the [coordination-practice conclusion](/nodes/market-research-expert/conclusions/coordination-practice-2026.md)
owns the separate merge-fraction findings. Transfer to later models remains
unconfirmed by this capture under the [model-generation decision](/nodes/market-research-expert/decisions/date-evidence-and-name-model-generations.md).

# Transfer to personal-agent workflows is untested here

A separate personal-use research pass, also dated 2026-11-02, reports that
its controlled multi-agent evidence concerns coding, research, finance and
QA, not personal mail, calendars or notes. It establishes no controlled
personal-workflow comparison and documents no personal-store clobbering
incident. These are limits of that investigation, not proof that no study
or incident exists.

Consequently, do not present file-ownership guidance from coding products
as a measured advantage for personal data stores. Data ownership is a
candidate design axis to test there, not an established replacement for
roles. Recheck this transfer boundary when controlled personal-workflow
studies or vendor reports with measured personal-use outcomes appear. The
[persona-attribution lesson](/nodes/market-research-expert/lessons/persona-labels-need-isolated-ablation.md)
remains the canonical home for role-label evidence; neither finding tests
or supersedes durable specialization.

# Coordinator span and responsibility splits remain unmeasured here

An org-scale investigation dated **2026-11-02** did not identify a benchmark
varying the number of open efforts under one coordinator, or a controlled
comparison of responsibility-based splits (such as architecture versus
landing) with surface-based splits (such as repository or epic). The capture
does not retain a reproducible search inventory, so this is a limit of the
investigation, not a claim that no such study exists on any generation.
A configurable concurrency cap or a practitioner's session-count anecdote
is not an experimentally justified span of control.

Treat coordinator load as a trial variable rather than quote a safe child
count. Evaluate carried state, handoff fidelity and the coordinator's ability
to check results alongside headcount; this capture does not establish that
state load is causally more important than count. The distinct
[compaction finding](/nodes/market-research-expert/lessons/coordination-recovery-is-not-task-correctness.md)
motivates measuring retained scope and process constraints, not deriving a
capacity threshold. Assigning a responsibility only where it has a runnable
check is an untested design hypothesis here, not a measured winning partition
or authority to replace the accepted domain roster.

# Cross-repository comparisons need task and scaffold controls

The refined [WideSWE account](/nodes/market-research-expert/limitations/cross-repo-architecture-ownership-evidence-gap.md)
owns the source-reported failure table and the joint/independent comparison's
unequal-budget and task-type limits. It does not isolate a scope-discovery or
architecture-owner benefit. The verification note also reports same-model
scaffold sensitivity for **GPT-5.6-sol**. Hold scaffold choice explicit when
comparing models, and separate bug fixes from feature work rather than
promote one aggregate topology score to a universal rule. No numerical
leaderboard is adopted from the unresolved success-score evidence.
The [multi-domain planning conclusion](/nodes/market-research-expert/conclusions/multi-domain-plan-authorship-evidence-2026.md)
separately owns the whole-plan authorship candidate and CooperBench/Specification
Gap readings: execution topology and contract-detail interventions do not
compare one plan author against per-area planners plus a coordinator.

# Unowned-seam failure and oracle-message recovery are different studies

A verification pass on **2026-11-02** reports reading two papers in raw
arXiv HTML [7, 8]. Keep their tasks, models and interventions separate:

- **arXiv 2608.16801, Sonnet 4.6:** a synthetic eight-agent chain in one
  harness failed at an unowned rounding seam in all ten runs, although the
  agents discussed rounding in each run. The same task reportedly succeeded
  in nine of ten runs with two to four agents when one agent owned both
  adjacent steps. Team size and ownership changed together; this does not
  isolate ownership as the cause or show that messaging repaired the seam.
- **arXiv 2609.25396v1, GPT-5.5:** in constructed Django tasks, the source
  reports interference in 105/108 runs and recovery in 89/108 runs (82%)
  with a template-generated oracle message about a completed change. The
  denominator for that recovery figure is all 108 runs, not just the 105
  interference runs. Messages generated during ongoing work were not
  evaluated. In a separate mined-pair setting, only one of 834 runs over
  417 Django pairs reportedly showed interference.

These are **source-reported study readings**, not harvest replication. The
capture retains enough setting and denominator detail to bound the quoted
results, but not the full task-selection, judging and uncertainty analysis.
The constructed and mined settings do not supply one pooled interference
rate. An oracle message is an idealized information intervention, not
measured performance of an agent-generated messaging workflow.

Do not fuse the first paper's failures with the second paper's recovery
percentage into a causal story that messaging fixes unowned interfaces.
Compare ownership, team size, information supplied and task construction as
separate variables. Neither captured account tests agents run by different
people, so transfer to cross-person coordination remains unestablished here;
this is not a claim that no such study exists elsewhere. Any proposed remedy
needs runnable integration checks and a matched trial, not only a prompt
encouraging agents to discuss the seam.

## Ownership means covering the interface, not naming a coordinator

A **2026-11-03** follow-up reading of Destefanis and Aste [7] reinforces
what the first study's ownership condition means: one agent owns both
adjacent steps and reconciles them internally, rather than a third party
merely recording their agreement. It also reports that naming one agent as
coordinator created no communication hub and supplied no reliable success
improvement in that setting. This is a source-reported reading, not a new
replication or evidence that every coordinator is ineffective. The follow-up
note does not identify the model; Sonnet 4.6 above comes from the earlier
capture, not a fresh model check.

When transferring this result, check **which agent can see and reconcile
both sides**, not only whether an ownership field or coordinator title
exists. This captured reading does not establish a test of a third-party
contract owner as an isolated intervention. Missing support for that remedy
is not proof the remedy cannot help. Keep team-size confounding and the distinction from the
oracle-message experiment intact. The
[planning conclusion](/nodes/market-research-expert/conclusions/multi-domain-plan-authorship-evidence-2026.md)
owns the implication for plan-review comparisons.

# Attribute stalls to interactions as well as failure classes

The **2026-11-03** source reports inspecting a stall table from a small
coordination fixture run on 2026-11-02/03: seven of nine variant stalls
occurred at section-review handoffs (three) or plan-approval handoffs to the
section expert (four), with the result recorded only on the issue. The
control had one stall in three runs. These are **source-reported event
counts**, not per-handoff failure rates or an isolated effect of plan
fan-out. The proposal describes three runs per arm on one model but does
not name it; the capture lacks the full ledger, handoff denominators and
controls needed for a causal comparison. No trial was repeated here.

For a fair topology comparison, classify a stall both by its immediate
failure mode and by the interaction that required the handoff. More required
handoffs create more opportunities for a handoff failure even if the
per-handoff risk is unchanged; that does not establish linear scaling,
independence or the net cost-benefit of the extra review. Measure required
handoffs, notification compliance, stalls and rescue work separately by arm
and interaction. Do not infer from the issue-only records that every
observed handoff followed its notification rule.

The existing [missing-wake lesson](/nodes/oats-expert/lessons/overdue-handbacks-need-a-record-check.md)
owns operational notification repair; this refinement owns attribution in
research comparisons. Put interaction identifiers and transition/recipient
checks in the trial harness for separate review rather than rely only on a
failure-class summary. Those checks are not implemented by this lesson,
and these counts select no planning or approval policy.

# Consequence for research

Compare topologies on the same task and model with explicit token/cost and
context budgets. Record the single-agent baseline and compare adding agents
with spending more effort on that baseline; report quality, cost and wall-clock
time separately. Separate read-only decomposition from shared-state writes,
and test whether the integration step preserves the workers' useful output.
A centralized coordinator is itself an error source to evaluate, not an
assumed cure. Do not equate adding agent names with adding expertise; see
[persona-label ablations](/nodes/market-research-expert/lessons/persona-labels-need-isolated-ablation.md).

This provides evidence questions for the
[coordination investigation](/nodes/oats-maintainer/stewardship/coordination-redesign-precedes-adaptive-onboarding.md),
not a chosen replacement for existing OATS coordination policy.

**Owner and recheck:** market-research-expert. Recheck on controlled topology
studies with matched budgets, evidence about conflicting parallel writes,
or changed lab guidance. Recheck the stall attribution with per-interaction
handoff denominators, rule-compliance records and matched replicated arms.
Recheck the seam/interference interpretation when
matched ownership interventions, realistic agent-generated messages or
cross-person trials separate the variables above. Recheck the coordinator-span
gap on controlled load/partition comparisons with named models and task outcomes, and the
WideSWE interpretation on matched-budget interventions or newer-model
replications. Recheck the breadth-search finding on a new frontier
generation, a controlled study, or by 2027-02-01. Update or supersede the
conclusion and log the change rather than extending it to a new model
generation silently.

# Citations

1. Scaling study, [arXiv 2512.08296](https://arxiv.org/abs/2512.08296),
   v3 2026-04-08 as identified in the proposal.
2. Cognition, *Multi-Agents: What's Actually Working*, 2026-04-22; Cursor,
   scaling-agents account, 2026-01-14; Anthropic, multi-agent research-system
   account, 2025-06-13. These are the source's attributions, not independent
   reproductions or re-fetches by this harvest.
3. [arXiv 2606.13003](https://arxiv.org/abs/2606.13003),
   [2607.16133](https://arxiv.org/abs/2607.16133),
   [2609.19759](https://arxiv.org/abs/2609.19759) and
   [2609.20804](https://arxiv.org/abs/2609.20804): source-supplied preprint
   locators for shrinking collaboration or scaffolding benefit. Per-study
   model identifiers are not retained in the recency note; do not extend
   the scaling study's model list to these papers.
4. Vals AI, single-agent versus lead-plus-subagents comparison, page dated
   2026-10-09 by the source; no exact page URL is supplied in the capture.
5. Agensh, [arXiv 2609.26781](https://arxiv.org/abs/2609.26781), dated
   2026-09-22 by the source.
6. Anthropic, [multiagent-systems study](https://anthropic.com/research/multiagent-systems),
   dated 2026-08-13 by the follow-up source; breadth-search result reported
   on 2026-11-02, not independently fetched or reproduced by this harvest.
7. Seam-failure study, [arXiv 2608.16801](https://arxiv.org/abs/2608.16801),
   raw-HTML reading reported on 2026-11-02; paper version unstated in the
   capture, measured model Sonnet 4.6. Follow-up reading of Destefanis and
   Aste at [the HTML page](https://arxiv.org/html/2608.16801) reported on
   2026-11-03; that follow-up retains no model identifier or full methods.
8. Interference/recovery study, [arXiv 2609.25396v1](https://arxiv.org/html/2609.25396v1),
   raw-HTML reading reported on 2026-11-02; measured model GPT-5.5.
   Neither paper was independently fetched or replicated by this harvest.

The capability-baseline addition uses the captured proposal and note, not
independent page fetches or experimental replication. Model names and dates
in it are source-supplied; they do not establish which models are currently
leading.

Evidence: OKF proposal from market-research-expert/coord-frontier-research-expert,
2026-11-02; notes/single-writer-parallel-readers.md (initial synthesis and
subsequent capability-baseline addition).

Evidence: OKF proposal from market-research-expert/coord-personal-research-expert,
2026-11-02; notes/personal-agents-organise-by-data-ownership-not-roles.md
(personal-workflow transfer limit).

Evidence for the recency refinement: OKF proposal from
market-research-expert/coord-practice-research-expert, 2026-11-02;
notes/multi-agent-gains-shrink-with-capability.md.

Evidence for the breadth-search qualification: OKF proposal from
market-research-expert/coord-products-research-expert, 2026-11-02;
notes/coordination-across-model-generations.md.

Evidence: OKF proposal from market-research-expert/coord-orgdesign-research-expert,
2026-11-02; notes/coordinator-span-is-unmeasured-state-not-headcount.md.

Evidence: OKF proposal from market-research-expert/coord-claims-verification-expert,
2026-11-02; notes/cross-repo-agent-failures-are-mostly-post-edit.md.

Evidence for the seam/interference refinement: OKF proposal from
market-research-expert/coord-claims-verification-expert, 2026-11-02;
notes/agent-seam-and-interference-evidence-is-narrow.md.

Evidence: OKF proposal from market-research-expert/study-design-opus-expert,
2026-11-03; notes/cited-sources-cut-against-section-review.md
(interface-coverage and named-coordinator refinement).

Evidence: OKF proposal from market-research-expert/study-design-opus-expert,
2026-11-03; notes/stalls-concentrate-in-plan-fanout.md
(interaction-level stall attribution; underlying trial ledger not inspected).
