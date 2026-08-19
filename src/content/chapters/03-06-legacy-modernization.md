# 3.6 Legacy modernization

## Overview and motivation

[Legacy systems](https://en.wikipedia.org/wiki/Legacy_system) are the systems that run the world. The core banking ledgers, tax and benefits engines, air traffic and defence systems, insurance policy administration, and government registries that societies depend on are frequently decades old. Many are written in [COBOL](https://en.wikipedia.org/wiki/COBOL) (Common Business-Oriented Language) or other older technologies, and they still process the majority of critical transactions. "Legacy" is not an insult. It means the system is valuable enough to have survived, critical enough that failure is catastrophic, and old enough that changing it safely is hard. Legacy modernization is the discipline of improving, migrating, or replacing these systems without breaking the essential services they provide.

This is disproportionately an enterprise and government problem, and it is where the largest, most public IT failures occur. A vast share of major transactions worldwide still touch [mainframe](https://en.wikipedia.org/wiki/Mainframe_computer) systems. A large fraction of production code in big institutions is in older languages maintained by an aging, shrinking pool of specialists. Governments carry the heaviest burden: statutory obligations encoded over decades, procurement and budget cycles that outlast administrations, and citizen services that cannot be interrupted. The dominant risk is not that these systems are old, since many run superbly. It is that the knowledge to maintain them is retiring, the platforms are increasingly costly and constrained, and the temptation to "just rewrite it" leads to some of the most expensive failures in the history of the field.

This chapter covers the incremental modernization patterns that actually work (strangler fig and branch-by-abstraction), how to assess and prioritize legacy risk, the stewardship of mainframe and COBOL estates, the discipline of [data migration](https://en.wikipedia.org/wiki/Data_migration) and dual-running, and above all how to resist the big-rewrite temptation. The central conviction is that successful modernization is almost always incremental, evidence-driven, and continuously delivering value. It is never a multi-year big bang.

## Key principles

- **Legacy means valuable and foundational, not merely old.** Respect what the system does before you touch it; it encodes decades of hard-won business rules.
- **Incremental beats big-bang, almost always.** Replace piece by piece behind a stable interface; deliver value continuously and keep risk small.
- **The big rewrite is the default failure mode.** Full rewrites routinely overrun, under-deliver, and are cancelled; treat the urge with deep suspicion.
- **You cannot modernize what you do not understand.** [Reverse-engineer](https://en.wikipedia.org/wiki/Reverse_engineering) and document behaviour (including undocumented rules) before replacing it.
- **Data migration is where projects die.** The data is older, dirtier, and more entangled than anyone expects; plan for it as a first-class effort.
- **Run old and new in parallel to build confidence.** Dual-running and comparison catch discrepancies before cutover.
- **Prioritize by risk and value, not by age.** Modernize what is riskiest and most valuable first, not what is simply oldest.
- **Keep the lights on while you change the engine.** The service must keep running throughout; there is no acceptable downtime for critical citizen or financial systems.

## Recommendations

### Modernize incrementally with the strangler fig pattern

The **strangler fig** (named for the vine that grows around a tree and gradually replaces it) is the workhorse of safe modernization. Place a routing layer (an API gateway, facade, or proxy) in front of the legacy system. Then, capability by capability, build the replacement in a modern system and redirect that slice of traffic to it, leaving the rest on the legacy system. Over time the new system grows and the old one shrinks, until it can be retired. This delivers value continuously, keeps each change small and reversible, avoids a risky cutover, and lets you stop or reprioritize at any point. It is the opposite of the big bang. The legacy system keeps running and keeps earning its keep while you replace it around it.

### Use branch-by-abstraction for internal seams

Where you need to replace a component that many parts of the system depend on, use **branch-by-abstraction**. Introduce an abstraction layer (an interface) over the existing implementation, migrate callers to depend on the abstraction, build the new implementation behind the same abstraction, switch over (often behind a [feature flag](https://en.wikipedia.org/wiki/Feature_toggle), gradually), and finally remove the old implementation. This lets a large component be replaced incrementally on the main line of development without a long-lived branch, keeping the system releasable throughout. It pairs naturally with the strangler fig: the facade handles external seams, branch-by-abstraction handles internal ones.

### Assess and prioritize legacy risk deliberately

Before modernizing, build a clear-eyed inventory and risk assessment of the estate. For each system, score it on business criticality, technical risk (obsolescence, unsupported platforms, security exposure), change frequency, and, crucially, **knowledge risk** (how many people can still maintain it, and how close they are to retirement). Plot systems on a risk-versus-value grid. Prioritize modernizing what is both high-risk and high-value. Consider leaving stable, low-change, well-understood systems alone even if they are old, because a working system that no one needs to change is not an emergency. This assessment turns "everything is old and scary" into a defensible, sequenced roadmap.

### Steward the mainframe and COBOL estate, not just replace it

Not every mainframe or COBOL system should, or can safely, be replaced soon. The near-term priority is often **stewardship**: capture the knowledge before it retires. Document the business rules the code encodes (much of it undocumented and irreplaceable), invest in automated tests that pin current behaviour so future change is safe, recruit and cross-train maintainers, and modernize the surrounding delivery practices (source control, [continuous integration](https://en.wikipedia.org/wiki/Continuous_integration) (CI), automated testing) even while the core stays in place. Where you do modernize, prefer exposing legacy capabilities through modern APIs (encapsulation) as a first step. Treat automated COBOL-to-modern-language translation with caution, because it produces code that runs but often faithfully reproduces incomprehensible logic. The scarcest resource is understanding, not compute.

### Treat data migration and dual-running as the core of the project

The hardest and riskiest part of most modernization efforts is the **data**. It is voluminous, of poor and inconsistent quality, and full of undocumented meaning accreted over decades. Profile and cleanse it, map old to new schemas explicitly, and build repeatable, automated migration with full reconciliation (counts, checksums, business totals) so you can prove nothing was lost or altered. De-risk cutover with **dual-running** (parallel running): operate the old and new systems side by side on the same inputs and compare outputs until the new system matches the old to your confidence threshold. Only then cut over, and keep the ability to roll back. For truly critical systems, migrate and cut over in slices rather than all at once.

### Manage the big-rewrite temptation

The instinct to throw away the messy old system and build a clean new one from scratch is powerful, and it is almost always wrong for large, critical systems. Full rewrites underestimate the value hidden in the "ugly" code (edge cases, regulatory rules, bug-compatible behaviours real users depend on), take far longer than projected, deliver no value until the end, and are frequently cancelled after enormous spend. Default to incremental modernization. Reserve rewrites for cases where the platform is genuinely unsustainable and incremental paths are exhausted. Even then, decompose the rewrite into independently deliverable pieces via the strangler pattern rather than a single big-bang release. When leadership pushes for a total rewrite, insist on the question: what value ships in the first three months, and what happens if the programme is stopped halfway?

## Trade-offs: pros and cons

| Approach | Pros | Cons |
|---|---|---|
| Strangler fig (incremental) | Continuous value, low risk, reversible, keeps service running | Longer overall timeline, must run two systems in parallel, integration overhead |
| Big-bang rewrite | Clean slate, no legacy constraints in the new code | Very high failure rate, no value until end, huge cost, business rules lost |
| Encapsulate (wrap with APIs) | Fast, low-risk, modernizes access without touching core | Core remains legacy; defers, not solves, the underlying risk |
| Leave as-is (steward) | No project risk; cheapest short term | Knowledge and platform risk keep accumulating; eventual forced action |

The fundamental trade-off is speed of transformation versus risk of failure, and legacy modernization is the domain where that trade is most lopsided. The "fast, clean" big-bang rewrite is a mirage that repeatedly produces the slowest and most expensive outcome of all: a cancelled programme and a still-unmodernized system. Incremental approaches feel slower and require running two systems in parallel, but they deliver value throughout, keep risk small and reversible, and are the empirically reliable path. The genuine judgement call is between stewarding a stable legacy system a while longer and starting incremental replacement now. Let risk trajectory drive that call, especially knowledge risk, rather than discomfort with old technology.

## Questions to discuss with your team

1. **Do you have a place to put a routing layer in front of your legacy system, and if not, what would it take to create one?** The strangler fig depends on a seam: an API gateway, facade, or proxy through which you can redirect one capability at a time to a new implementation. Many old systems have no such seam, so the first modernization increment is often just building the interception point, and that work is easy to underestimate. Bring the current integration map and ask where traffic could be intercepted per capability without a big-bang cutover. If there is nowhere, branch-by-abstraction on an internal seam may be the starting move instead. Without a routing layer you have no incremental path, which is exactly how organizations get pushed back toward the rewrite that usually fails.

2. **Have you actually plotted your estate on a risk-versus-value grid, or is your roadmap driven by which system feels oldest?** The chapter insists you modernize what is high-risk and high-value first, and deliberately leave stable, low-change, well-understood systems alone even when they are ancient. Without an explicit grid, attention flows to the loudest complaint or the least fashionable technology, and genuine time bombs (a critical system with two maintainers near retirement) wait. Score each system on business criticality, technical risk, change frequency, and knowledge risk, then sequence from the top-right corner. Bring that grid to the meeting as the shared map. Knowledge risk deserves the heaviest weight, because it is the one input that only gets worse and cannot be bought back once the people leave.

3. **When you cut over, how will you prove that not a single record was lost or altered, and who signs off on that evidence?** Data migration is where these projects die, and confidence comes from reconciliation: row counts, checksums, and business control totals that match between old and new, plus dual-running that compares outputs on the same inputs until they agree to a high threshold. For a benefits or ledger system, a discrepancy is a citizen underpaid or a cent lost, so the evidence has to satisfy an auditor, not just an engineer. Decide now which totals you will reconcile, what confidence threshold triggers cutover, and how long you will run old and new in parallel. Keep rollback available throughout, and cut over in slices rather than all at once. The discrepancies you find during dual-running are usually undocumented legacy rules you must preserve, so treat each one as a discovery, not just a defect.

4. **Which of your legacy systems are you stewarding versus actively replacing, and who decided which is which?** The chapter draws a deliberate line between systems worth stabilizing in place (documenting rules, adding characterization tests, cross-training maintainers) and systems worth incrementally replacing, and the two demand very different funding and staffing. For a large organization the danger is drift: a system labelled "steward for now" quietly becomes "steward forever" until the last maintainer retires and the choice is made for you under crisis. The competing considerations are stewardship cost and platform obsolescence on one side against the risk and disruption of replacement on the other, and knowledge risk should tip the balance because it only worsens. Bring the risk-versus-value grid, the maintainer headcount and retirement horizon for each system, and an explicit owner for the steward-or-replace decision. In enterprise and government estates, name a review cadence and an accountable officer for each system, because a classification nobody revisits is a decision nobody is making.

5. **When leadership asks for a full rewrite, what is your standing answer, and can you show what an incremental path ships in the first three months?** The big-bang rewrite is the default failure mode, yet it keeps getting funded because a clean slate is easy to sell and a strangler fig is not. A large team needs a rehearsed response so the argument is won on evidence rather than on whoever is most senior in the room. The genuine tension is that some platforms really are unsustainable and a rewrite is warranted, so the answer cannot be a blanket refusal: it must weigh whether incremental seams still exist against the true cost of keeping the old platform alive. Bring the value an incremental first increment would deliver, the historical failure rate of comparable rewrites, and a decomposition of any proposed rewrite into independently shippable pieces. In government, where a cancelled multi-year programme burns public money in full view, insist that any rewrite deliver value early and survive being stopped halfway without total loss.

6. **How will you capture the business rules locked in your oldest code before the people who understand them are gone?** Much of the value in a legacy system is undocumented behaviour that decades of edge cases, regulations, and bug-compatible fixes have accreted, and it lives in a shrinking pool of retiring specialists rather than in any written record. For a large organization this is the one risk that cannot be bought back once the people leave, so it deserves funding ahead of the more visible platform work. The competing pull is that knowledge capture (documentation, characterization tests, reverse engineering, cross-training) feels like overhead that ships nothing, which is exactly why it gets deferred. Bring an inventory of who holds critical knowledge, how close they are to leaving, and what test coverage pins current behaviour today. In regulated and public settings, treat the statutory rules encoded in old code as a compliance asset: losing them silently is not a technical debt, it is a legal exposure.

## Sector lens

**Startup.** Your legacy is your own hurried MVP, not a mainframe: a prototype that now carries revenue and that everyone fears to touch. Do not rewrite it. Wrap the scariest module behind a clean interface, add characterization tests to pin its behaviour, and carve functionality out incrementally so each small release ships value and shrinks the risk. You have no runway for a from-scratch rebuild, so optionality matters more than elegance.

**Small business.** You have no modernization team and a tight budget, so the practical move is usually to keep a working system working: capture what the one person who understands it knows, get it into source control with a few automated tests, and lean on a vendor or packaged product rather than a bespoke rebuild. Frame the decision as buy versus build, and prefer buying when the capability is a commodity. Spend your limited effort on the single system whose failure would stop the business, not on whatever simply looks oldest.

**Enterprise.** The problem is portfolio scale: dozens of systems, many teams, and estate-wide knowledge risk. Run a shared risk-versus-value assessment, standardize on incremental patterns (strangler fig and branch-by-abstraction), and treat data migration and dual-running as first-class disciplines with reconciliation everyone trusts. Govern modernization as a continuous portfolio against risk trajectory rather than a scatter of heroic projects, and budget stewardship and knowledge capture explicitly so no critical system depends on a single retiring maintainer.

**Government.** Statutory obligations encoded over decades, procurement rules, and citizen services that cannot be interrupted make big-bang replacement especially dangerous. Favour incremental strangler-fig migration with slice-by-slice cutover, prove through reconciliation and long parallel running that not one citizen record was lost or miscalculated, and keep rollback available throughout. Procurement should demand data portability and disclosure of business rules rather than opaque translation, and any multi-year programme must deliver auditable value early and survive public scrutiny if it is stopped partway.

## Examples

**Startup.** A three-year-old startup's original MVP has become its own kind of legacy: a rushed prototype that now handles real revenue and that everyone is scared to touch. Rather than a rewrite, the team wraps the worst module behind a clean interface, adds characterization tests to pin its current behaviour, and moves functionality out of it piece by piece over a few months. Each small release ships value and shrinks the scary part, so the startup gets a maintainable system without betting the company on a from-scratch rebuild it cannot afford.

**Enterprise.** A large insurer runs policy administration on a mainframe COBOL system that is reliable but expensive to change and maintained by a handful of engineers nearing retirement. Rather than a rewrite, the insurer wraps the mainframe with modern APIs and applies the strangler fig: new quote-and-buy and self-service capabilities are built on a modern platform and routed through a facade, while core policy records stay on the mainframe. In parallel, the team documents business rules and adds [characterization tests](https://en.wikipedia.org/wiki/Characterization_test) around the COBOL. Over several years, capability after capability moves off the mainframe, each release delivering value, until the remaining core can be retired on the insurer's terms rather than under crisis.

**Government.** A social security agency must modernize a decades-old benefits calculation system that pays millions of citizens and cannot be interrupted or paid incorrectly. It rejects a big-bang replacement after studying comparable failed programmes. Instead it profiles and cleanses the data, builds automated migration with full reconciliation against control totals, and runs the new benefits engine in parallel with the old one for many months, feeding both the same claims and comparing every calculation, investigating each discrepancy (often uncovering undocumented legacy rules that must be preserved). Only once the new system matches the old to a very high confidence does it cut over benefit type by benefit type, retaining rollback throughout. The strangler facade lets citizens see one continuous service across the transition.

## Business case: motivations, ROI, and TCO

Legacy modernization has an unusual business case, because the largest cost is often the cost of *inaction* and the largest risk is the modernization project itself. The mounting costs of not modernizing are concrete: rising maintenance and licensing on obsolescent platforms, an increasingly scarce and expensive specialist workforce, inability to meet new regulatory or service demands quickly, and growing exposure to a catastrophic failure with no one left who understands the system. Against that, the cost of modernization is high, and done as a big bang it carries a genuinely high probability of failure. That is precisely why the incremental approach matters to the ROI: it converts a single large bet into a series of small ones that each return value and can be stopped.

Make the case to leadership by reframing the choice. The question is not "modernize or not." It is "modernize incrementally now, or pay escalating stewardship costs and face a forced, higher-risk modernization later under crisis." Quantify the TCO of the status quo (platform and licence costs, the premium for scarce skills, the risk-weighted cost of an unrecoverable outage) and compare it to a phased programme that reduces risk and cost with each increment while keeping the service running. Critically, insist that any proposed rewrite be structured to deliver value early and often. A programme that delivers nothing for three years and can be cancelled with total loss is not an investment; it is a gamble. The strongest ROI argument for the strangler approach is optionality: value ships continuously and the organization can adjust course at any point.

## Anti-patterns and pitfalls

- **The big-bang rewrite.** Multi-year, all-or-nothing replacement that delivers no value until the end and is frequently cancelled at great cost.
- **Rewriting without understanding.** Replacing code whose business rules were never documented, silently dropping edge cases real users and laws depend on.
- **Underestimating the data.** Treating data migration as an afterthought when it is the hardest, riskiest part of the project.
- **Skipping dual-running.** Cutting over to the new system without parallel comparison, discovering discrepancies only after they affect real people.
- **Automated translation as a solution.** Machine-translating COBOL to a modern language and believing the job is done, producing incomprehensible code that reproduces the old logic verbatim.
- **Modernizing by age, not risk.** Spending effort on old-but-stable systems while high-risk, high-change systems wait.
- **Losing the knowledge.** Letting the last maintainers retire without capturing the business rules and adding characterization tests.
- **No rollback.** Cutting over with no way back when the new system misbehaves under real load and real data.

## Maturity model

- **Level 1: Initiate.** Legacy systems are feared and frozen; change is avoided. No inventory or risk assessment exists. Modernization, when attempted at all, is an ad hoc all-or-nothing rewrite driven by frustration. Knowledge lives in a few retiring heads with nothing written down.
- **Level 2: Develop.** Some teams have an inventory and a rough sense of risk, and a few legacy systems are wrapped with APIs for access. Incremental patterns are known but applied unevenly, and thinking still drifts toward big-bang rewrites. Data migration is attempted but underestimated, and practice varies widely from team to team.
- **Level 3: Standardize.** Systems are prioritized by risk and value against a documented, org-wide method. Incremental patterns (strangler fig, branch-by-abstraction) are the enforced default, and every modernization follows a standard playbook. Data migration is a planned, reconciled effort with dual-running before cutover, and knowledge capture and characterization tests are required practice rather than optional.
- **Level 4: Manage.** Modernization is measured and controlled with data. The estate carries baselines: maintainer headcount and retirement horizon per system, characterization-test coverage, migration reconciliation pass rates, dual-running discrepancy counts, and value shipped per increment, all tracked against targets. Steward-or-replace decisions and cutover go or no-go calls are made on this evidence, and a system drifting past its knowledge-risk threshold triggers action rather than waiting for a crisis.
- **Level 5: Orchestrate.** Modernization is continuous, integrated with business and risk planning, and adaptive. The portfolio is rebalanced against risk trajectory (especially knowledge risk) as it shifts, incremental replacement is routine and low-drama, every increment delivers value and is reversible, and the organization steers the pace deliberately. Lessons from each migration feed back into the shared playbook so the whole estate improves over time.

## Ideas for discussion

1. For your most critical legacy system, how many people can still maintain it, and how close are they to leaving?
2. Where are you tempted by a big-bang rewrite, and what value could an incremental approach ship in the first three months instead?
3. How well are the business rules in your oldest systems documented, and what happens to them if the code is replaced?
4. Have you profiled the data you would need to migrate, and do you know how dirty and entangled it really is?
5. Which old-but-stable systems are you spending modernization energy on that you could safely leave alone?
6. Could you run your new system in parallel with the old one and prove they agree before cutting over?

## Key takeaways

- Legacy means valuable and foundational; respect and understand a system before you change it.
- Modernize incrementally with the strangler fig and branch-by-abstraction, delivering value continuously and keeping every change small and reversible.
- Treat the big-bang rewrite as the default failure mode; reserve it for genuinely unsustainable platforms and even then decompose it.
- Prioritize by risk and value (especially knowledge risk), not by age; some old systems are best stewarded, not replaced.
- Data migration and dual-running are the heart of the effort; profile, reconcile, run in parallel, and keep rollback.
- The strongest business case is optionality: incremental modernization converts one large, risky bet into many small, value-returning ones.

## References and further reading

- Michael Feathers, *Working Effectively with Legacy Code*
- Martin Fowler, "StranglerFigApplication" and "BranchByAbstraction"
- Sam Newman, *Monolith to Microservices*
- Nicholas Carr / industry studies on mainframe and COBOL dependency (context on the scale of legacy estates)
- Robert Annett, *Working with Legacy Systems*
- Eric Evans, *Domain-Driven Design* (anti-corruption layer)
- Gregor Hohpe, *Enterprise Integration Patterns* and *The Software Architect Elevator*
- Standish Group *CHAOS Report* (evidence on large project and rewrite failure rates)
