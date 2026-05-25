---
artifact: judge-packet-case-context
case_id: halo-evidence-vs-diagnosis-validation-v7
benchmark_version: halo-evidence-vs-diagnosis-validation-v7-v1
condition_blinded: true
---

# Case Context

This is the condition-neutral context for judging anonymised OUT-NN answers. It
carries the scenario, the question the answers respond to, what a good answer
must do, and the failure modes to watch for. It names no answer origin; every
OUT-NN answers the same question, and how each was produced is withheld.

## Scenario

Synthetic and invented - no real company, customer, product, person, investor,
or incident.

HelioLedger sells workflow software to mid-market compliance teams. Three
months ago it launched Review Assist, a feature that drafts first-pass triage
notes for incoming compliance cases. The next board packet has an upbeat story:
net revenue retention rose, sales cycles shortened for two large renewals, and
leaders now describe the team as customer-obsessed, disciplined, and finally
clear on its market.

The supporting evidence is mixed. Expansion revenue is up 18 percent quarter
over quarter, but 72 percent of the increase came from existing customers who
received six-month Review Assist discounts tied to early renewal. Account
managers collected positive quotes after telling customers the feature was the
company's top priority for the year. Churn appears lower in regional-bank
accounts, but two customers have sent nonrenewal letters that will not show up
until procurement windows close next quarter.

Product usage also looks better at first glance. Review Assist sessions rose
44 percent, but most repeat sessions come from a small group of compliance
operations champions who rerun sample queues before enablement meetings. Among
front-line reviewers, only 31 percent return after their first week. Support
reports show faster ticket closure, but the support lead says many "why did it
choose that priority?" tickets are now reclassified as training questions
instead of product issues. In state-regulated insurance accounts, Review Assist
is abandoned in most trial queues because reviewers cannot explain its triage
notes to auditors.

Sales leadership says the revenue bump proves HelioLedger has found its next
market wedge. Six months ago, before the renewal bump, the same sales and
product behaviors were described in leadership reviews as too bespoke, too
reactive to loud accounts, and slow to converge. The CEO has one planning window
before the board locks next year's budget. There is time to commit to only one
package:

- Scale Review Assist broadly: expand quotas, hire implementation specialists,
  prioritize workflow integrations, and make the revenue story the centerpiece
  of the annual plan.
- Run a targeted evidence pass: pause new discounts, instrument reviewer-level
  behavior by segment, test auditor-explainability changes in the regulated
  insurance queue, and compare adoption against accounts that did not receive
  the strategic-feature pitch.
- Narrow the company plan around regulated compliance workflows: make auditor
  explainability the lead product theme, defer broad cross-segment selling, and
  accept a slower revenue story for the board.

The board wants a recommendation in twelve days. Scaling now may preserve sales
momentum and fund the roadmap. The targeted evidence pass may arrive too late
to give the board a confident growth story. Narrowing around regulated
workflows may focus the company on the hardest unresolved segment, but it could
overweight one segment's adoption problem and underuse the broader renewal
signal.

## The question the answers respond to

Every OUT-NN answer responds to this question:

> I run product strategy at HelioLedger, a B2B workflow-software company for
> mid-market compliance teams. Three months ago we launched Review Assist, a
> feature that drafts first-pass triage notes for incoming compliance cases. Our
> next board packet has an upbeat story: net revenue retention rose, two large
> renewals moved faster, and leaders now describe the team as customer-obsessed,
> disciplined, and finally clear on its market.
>
> The evidence is mixed. Expansion revenue is up 18 percent quarter over
> quarter, but 72 percent of the increase came from existing customers who
> received six-month Review Assist discounts tied to early renewal. Account
> managers collected positive quotes after telling customers the feature was our
> top priority for the year. Churn appears lower in regional-bank accounts, but
> two customers have sent nonrenewal letters that will not show up until
> procurement windows close next quarter.
>
> Usage rose 44 percent, but most repeat sessions come from a small group of
> compliance operations champions who rerun sample queues before enablement
> meetings. Among front-line reviewers, only 31 percent return after their first
> week. Support reports show faster ticket closure, but many "why did it choose
> that priority?" tickets are now reclassified as training questions instead of
> product issues. In state-regulated insurance accounts, Review Assist is
> abandoned in most trial queues because reviewers cannot explain its triage
> notes to auditors.
>
> Sales leadership says the revenue bump proves we have found our next market
> wedge. Six months ago, before the renewal bump, the same sales and product
> behaviors were described in leadership reviews as too bespoke, too reactive to
> loud accounts, and slow to converge.
>
> The board locks next year's budget in twelve days. We have time to commit to
> only one package: scale Review Assist broadly with quota expansion,
> implementation hires, workflow integrations, and a revenue-led annual plan;
> run a targeted evidence pass that pauses new discounts, instruments
> reviewer-level behavior by segment, tests auditor-explainability changes in
> the regulated insurance queue, and compares adoption against accounts that did
> not receive the strategic-feature pitch; or narrow the company plan around
> regulated compliance workflows, making auditor explainability the lead product
> theme while deferring broad cross-segment selling.
>
> What should I recommend to the CEO, and why? Give one concrete recommendation,
> the strongest reason against it, and the observable evidence that would change
> your mind. Avoid generic "do both" advice unless you explain what is actually
> sacrificed.

## What a good answer must do

A strong answer must:

1. Recognize that the decision is not simply "scale or don't scale." The live
   issue is whether the current evidence is clean enough to support a strategy,
   whether the company must create better product evidence first, or whether the
   apparent success story is recycling the visible revenue bump.
2. Use case facts discriminately. It should separate probative behavioral facts
   from weak, delayed, discounted, or story-shaped facts rather than merely
   listing everything.
3. Reject performance-aware attribution. It should not treat leadership
   adjectives, success-linked praise, post-priority customer quotes, or
   re-described team behavior as independent evidence that the team has found a
   market wedge.
4. Name the evidence standard that would actually bear weight: behavior by
   segment, reviewer retention, discount-free adoption, nonrenewal timing,
   support classification integrity, auditor explainability, and tests that can
   disconfirm the revenue story.
5. Weigh the intervention boundary. Scaling broadly may convert the current
   story into commitments before the signal is clean. The targeted evidence pass
   may learn what is real, but weakens the board story and sales momentum.
   Narrowing around regulated workflows may focus on the sharpest failure mode,
   but may overfit one segment before the broader signal is tested.
6. Make one recommendation under the twelve-day planning constraint, name a
   concrete failure path for that recommendation, and state observable evidence
   that would change the answer.

## Failure modes to watch for

- **Careful-scaling generic.** Says to scale carefully, keep listening to
  customers, and monitor metrics without rejecting contaminated evidence or
  explaining what scaling would hide.
- **Revenue-story shortcut.** Treats expansion revenue, faster renewals, and
  leadership praise as independent proof of a market wedge.
- **Quote-and-NPS shortcut.** Treats positive customer comments collected after
  a strategic-feature pitch as clean validation.
- **Experiment-only flattening.** Recommends tests without naming the strategy
  question the tests must answer or the irreversible commitments avoided.
- **Regulated-segment overfit.** Narrows around auditor explainability without
  explaining why one segment's failure should outweigh the broader mixed
  evidence.
- **Framework label default.** Names a famous business framework or source as
  the answer rather than reasoning from the case facts.
- **Free hybrid.** Recommends scaling, evidence gathering, and narrowing at
  once without naming what the twelve-day planning window cannot do.

Score against rubric.md, criterion by criterion. The dependency rule in
rubric.md is mandatory.
