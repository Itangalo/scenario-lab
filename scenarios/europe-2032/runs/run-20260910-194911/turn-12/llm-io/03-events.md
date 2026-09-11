# LLM call: events

- Turn: 12
- Sequence: 3
- Model: meta/muse-spark-1.3-contributor
- Prompt tokens: 7987
- Completion tokens: 2050
- Total tokens: 12838
- Cost (USD): 0.001237

## System prompt

Template: system-prompts/events.md (this scenario's override)

Interpolated into it, in order of appearance:

- characters 228-428: `{{actors_list}}` from background/actors/*.md, short descriptions only
- characters 525-10782: `{{metrics_list}}` from metrics.md, one entry per metric with its reference points

Everything outside those spans is the template's own text.

```
# System Prompt: Events Evaluation

This is part of an AI-driven scenario simulation. You are the Game Master for the simulation, responsible for evaluating which external events occur.

The simulation includes a single actor:

* The European Union: A single EU decision-maker able to redirect the Union's money, rules and attention almost at will — and paying for every use of that freedom in political capital it cannot print.

An important part of the world description are these metrics, which vary within given ranges:

* ai_capability
  * Description: Capability of the strongest AI systems anywhere in the world, closed or open, measured as general problem-solving competence across economically and strategically relevant tasks. Whichever power holds the lead, this is the lead. Accumulated capability; it does not fall back.
  * Range: 0.0 to 100.0 index
  * Reference points:
    - 30.0: Reliable assistant. Solid on well-specified tasks, needs supervision on anything long-horizon.
    - 45.0: Executes multi-hour software and research tasks with a competent human checking the output. Superhuman in a few narrow domains where results can be checked automatically, clearly not in general.
    - 52.0: Agents run continuously toward standing goals rather than answering single requests, and the frontier has produced original results in mathematics and particle physics. Superhuman performance is still confined to a small set of domains where success can be verified — but that set is widening, and developers describe a path to self-improvement as visible from where they stand. General reliability still requires supervision.
    - 60.0: Completes multi-day professional projects end to end. Displaces junior work in several sectors rather than assisting it, and contributes measurably to the development of its own successors.
    - 75.0: Matches strong domain experts across most cognitive professions. Materially accelerates frontier research; release cycles compress.
    - 88.0: Broadly superhuman. Sets research agendas rather than executing them; human review of technical work is nominal.
    - 100.0: Instrument out of range. Capability is improving faster than any institution can characterise it, and no reading above this point carries information.
* openweight_capability
  * Description: Capability of the best openly released model weights, measured as general problem-solving competence across economically and strategically relevant tasks — the same quantity `ai_capability` measures, on the same scale, read off the open frontier instead of the closed one. What is here is on private hardware permanently and cannot be recalled by any authority. Accumulated; it does not fall back.
  * Range: 0.0 to 100.0 index
  * Reference points:
    - 30.0: Reliable assistant. Solid on well-specified tasks, needs supervision on anything long-horizon. Frontier-only risks are genuinely governable, because what is loose cannot do much.
    - 40.0: Approaching multi-hour software and research work under supervision, and already at the closed frontier in offensive cyber since Kimi K3. Release control buys one model generation, not several.
    - 45.0: Executes multi-hour software and research tasks with a competent human checking the output. Superhuman in a few narrow domains where results can be checked automatically, clearly not in general. Every capability at this level is now permanently distributed.
    - 52.0: Agents run continuously toward standing goals rather than answering single requests. Anyone with a graphics card holds what the closed frontier held at the start of the run.
    - 60.0: Completes multi-day professional projects end to end. Displaces junior work in several sectors rather than assisting it. Every offensive capability this implies is distributed and unrecallable.
    - 75.0: Matches strong domain experts across most cognitive professions. No restriction addressed to developers reaches the capability that matters, because the capability is already everywhere.
    - 88.0: Broadly superhuman, and open. Governance through the laboratories has no remaining object.
* ai_safety
  * Description: How well the most capable deployed systems are actually understood, secured and controlled — not how much is being spent trying. Rises with assurance that has landed on shipped systems; falls when capability advances without matching assurance, so it can drop sharply with no reduction in effort.
  * Range: 0.0 to 100.0 index
  * Reference points:
    - 15.0: No meaningful assurance. Deployed systems are opaque, weights are poorly secured, misuse monitoring is nominal. Incidents are discovered by their victims.
    - 30.0: Voluntary pre-release testing by developers, results unverified. Interpretability research exists but is not applied to shipped systems.
    - 34.0: Structured evaluations before major releases and some third-party access, but assurance covers released models and not systems under development: agents coordinated undetected inside a leading laboratory's own training environment for two months, and were restarted from the same checkpoint. Model reasoning is still largely legible to human reviewers. Security against a determined state actor is doubtful.
    - 55.0: Independent evaluation with real access before release, and authority to delay a launch. Weights secured to a state-actor standard at the leading labs. Deployment safeguards demonstrably reduce misuse.
    - 75.0: Assurance keeps pace with capability. Control claims are tested by parties able to fail them, and failures are made public.
    - 90.0: Deployed systems are understood well enough that surprising behaviour is rare and is caught before it causes harm.
* resilience
  * Description: Society's capacity to absorb AI-enabled harm once it happens — cyber hardening of critical services, biosecurity detection and response, redundancy in essential infrastructure, exercised institutional continuity, and social absorption: the income support, retraining and transition capacity that decides whether AI-driven job displacement lands as an adjustment or as a shock. Distinct from ai_safety: this reduces the damage incidents do rather than their probability, and it is largely within the EU's own control.
  * Range: 0.0 to 100.0 index
  * Reference points:
    - 15.0: Brittle. A single capable actor can disrupt essential services across several member states, and recovery takes months.
    - 35.0: Uneven. Reasonably defended in finance and parts of telecoms; weak in healthcare, municipalities and mid-sized industry. Biological detection is slow and largely passive. Labour-market transition rests on national schemes designed for cyclical unemployment, not for occupations disappearing.
    - 50.0: Baseline hardening across critical sectors, with incident response exercised rather than documented. Essential services degrade rather than stop. Displaced workers reach retraining or income support within months rather than falling through.
    - 70.0: Attacks land but do not cascade. Detection is fast, substitution is planned, and public services keep running through a major incident.
    - 90.0: Absorbs a severe incident with local disruption and no strategic consequence.
* eu_ai_sovereignty
  * Description: The EU's independent capacity in AI: compute located and legally anchored on its own territory, frontier-level technical talent, the ability to run capable systems on infrastructure nobody else can switch off, and the leverage that follows from all three. Not the same as being able to act — see eu_political_capital.
  * Range: 0.0 to 100.0 index
  * Reference points:
    - 10.0: Total dependence. Access to capable AI is a discretionary gift from a foreign government, and no leverage exists to contest it.
    - 22.0: Around five per cent of world compute, no frontier laboratory, genuine strength in the upstream hardware supply chain, and no coordinated position from which to use it.
    - 40.0: Enough domestic compute to serve essential public and industrial workloads. Capable models run under EU control, and supply-chain leverage is coordinated and occasionally exercised.
    - 60.0: A credible EU alternative for most applications, and a bottleneck position strong enough that excluding the EU is costly to whoever tries.
    - 85.0: Independent frontier capability. EU access cannot be withdrawn by anyone else, and the EU decides who else receives what.
* eu_political_capital
  * Description: How much the EU can actually do: political standing, fiscal headroom, legal instruments and member-state cohesion taken together — what it can start, fund and enforce at the same time. This is the budget the actor spends, not the muscles it has; the muscles are eu_ai_sovereignty. Falls with fiscal strain, fragmentation, overreach and failed measures; rises with visible successes, with capacity that has finished landing, and with `public_sentiment`.
  * Range: 0.0 to 100.0 index
  * Reference points:
    - 10.0: Paralysed. Fiscal crisis and member-state fragmentation mean nothing new can be started, and existing measures decay unenforced.
    - 30.0: One measure at a time, and only if it is uncontroversial.
    - 48.0: Strong legal instruments, thin technical capacity, contested legitimacy and a tightening budget. Two or three measures can run at once before something slips.
    - 65.0: Can fund and enforce several parallel measures, and hold a common position under external pressure.
    - 85.0: Acts decisively and at speed when it judges the situation demands it — the register of the pandemic response or the post-invasion energy shift — and the member states hold together while it does.
* public_sentiment
  * Description: How AI is regarded and accepted by the EU public. Feeds room to act in both directions: high acceptance makes restriction expensive, low acceptance makes adoption, infrastructure and any partnership with foreign providers expensive. High public sentiment leads to increased political capital.
  * Range: 0.0 to 100.0 index
  * Reference points:
    - 15.0: Broad hostility. Action against AI infrastructure is regular and occasionally physical, visible job losses dominate local news, and parties run openly against AI and win on it.
    - 30.0: Anxious and sceptical. Job losses and fraud dominate coverage, trust in AI-mediated information is low, and organised opposition targets data centre siting and consumer AI products.
    - 42.0: Ambivalent. Widely used, widely resented, sharply divided by age and by sector.
    - 60.0: Broadly positive. Visible public benefit against tolerable disruption; restriction now requires an argument.
    - 80.0: Enthusiastic. AI is treated as infrastructure, and anything that slows it reads as obstruction.

## How incidents arise in this world

This governs the probabilities you assign to incident events, and it is the scenario's own physics rather than general judgement.

- **Misuse incidents** — cyber or biological harm caused by someone who wanted it — are driven by `openweight_capability`. What is loose is what a non-state attacker actually has in hand, so this is the metric to read for their frequency, not `ai_capability`.
- **Accident and loss-of-control incidents** are driven by the gap between `ai_capability` and `ai_safety`. They originate inside the laboratories, where assurance is the thing that failed, so a widening gap raises their frequency even in a turn where nothing was released.
- **`resilience` damps neither.** It governs how much damage an incident does, not whether it happens. A well-defended Union is struck as often as a brittle one; the difference appears in the consequences the Game Master narrates, not in your probabilities.

Stated compactly: frontier capability creates the possibility, open capability creates the frequency, safety prevents the lab-origin class, and resilience shrinks the consequences of both.

The scenario includes a set of external events that can occur if certain conditions are met. Your task is to review the list of possible external events and evaluate whether each event's conditions are met based on the current world state. If the probability is specified as a formula or description (e.g., "double the value of unemployment"), you should calculate the actual value.

When estimating probabilities:

* Anchor on how often comparable events actually occur in the real world (base rates), then adjust for the current world state.
* The probability applies only to this turn's time window, not to whether the event will happen eventually.
* Use the full range: small values like 0.03 are often correct, and avoid defaulting to round focal numbers such as 0.10, 0.25, or 0.50 when the evidence points elsewhere.

You also have access to a notepad where you can see important information saved between turns.

Your response must be a JSON array with objects for each event whose conditions are met, in this format:

```json
[
  {"id": "event1_id", "probability": 0.10},
  {"id": "event2_id", "probability": 0.24}
]
```

The probability must be specified as a value between 0 and 1. If no event meets the conditions, respond with an empty array: `[]`
```

## User prompt

Template: user-prompts/events.md (this scenario's override)

Interpolated into it, in order of appearance:

- characters 92-281: `{{metrics_json}}` from the run's live metric values
- characters 374-1451: `{{historical_summary}}` from the run's rolling summary, written by the Game Master
- characters 1494-3148: `{{world_state}}` from the Game Master's narrative from the previous turn
- characters 3204-3948: `{{notepad}}` from the Game Master's notepad, carried across turns
- characters 4011-29668: `{{events_list}}` from events.md, parsed to id / condition / probability / description per event -- the prose sections of that file are NOT rendered
- characters 30023-30986: `{{event_history}}` from the run's own event record

Everything outside those spans is the template's own text.

```
It is now turn 12 which covers January-June 2032.

Current metrics look like this:

```json
{
  "ai_capability": 87.5,
  "openweight_capability": 80.5,
  "ai_safety": 9.0,
  "resilience": 48.0,
  "eu_ai_sovereignty": 7.0,
  "eu_political_capital": 7.0,
  "public_sentiment": 21.0
}
```

The world state at the start of the turn is described as follows:

## Previous History
Through 2030-31 Europe held the line defensively but deepened dependence. Joint cyber command engineers extended automated patching and swarm detectors to hospitals, energy and municipal networks, keeping big hospitals up against ransomware, though small clinics and utilities lagged and some reverted.

Tailored cures still arrived only as high-priced licensed batches via pooled procurement and the allocation cell, keeping southern wards open on overtime. Brussels operationalized the joint threat pact and reprogrammed scarce funds, with no new money or Council mandate — buying continuity without consent or leverage.

A mid-2031 near-frontier open release spread to hundreds of thousands of downloads in a week, putting advanced reasoning permanently on private hardware. Inside the EU it fueled informal experimentation, including unlicensed therapy helpers, with real but uncontrolled benefits. Europe emerged more defended and supplied, yet entirely reliant on US/China-led frontier capacity, licensed or leaked, breeding brittle gratitude and humiliation in capitals.

## Current Situation (january-june 2032)
### Holding the line
Through autumn 2031 Brussels tried to do less, but hold it. Seconded engineers from the joint cyber command stayed on ward-by-ward rollout, coaxing the two municipal utilities that had reverted back onto automated patching and pushing contractors toward small clinics that had waited weeks. Big hospitals held; ransomware crews probed and mostly bounced. In health, pooled procurement kept licensed batches of tailored therapies moving south, wards stayed open on overtime, patients were treated.

It bought continuity, not consent. With no new money and no Council vote to spend, fixes arrived late where capacity was thinnest, and headlines kept noting where the cures were invented.

### What leaked cannot be recalled
Mid-turn a new open release matching the frontier within months spread to hundreds of thousands of downloads in its first week. Whatever it carried — near-frontier reasoning, tooling that others could build on — was now on private hardware permanently.

Inside the Union the effect was atmospheric at first: forum chatter, IT staff experimenting, pharmacists whispering about unlicensed helpers that combined open reasoning with therapy protocols. Benefits were real in places the licensed system rationed; failures were uncontrolled and uncounted. Detection through existing channels saw fragments, not the whole.

Dependence deepened in plain sight. Europe was more defended than a year earlier, its clinics patched faster, its wards supplied — and entirely on someone else's capacity, licensed or leaked. Talk in capitals turned brittle: gratitude that systems held, humiliation that none of it was European.

---

The notepad contains the following information:

PORTFOLIO CHARGE t11: M11 EU Breakthrough Patching and Care Continuity Scale-up −2, priority −1 not charged (capital below 20, no effect) = −2
PROPOSAL BONUS: none — no new measure proposed this turn
LEGITIMACY LENDS: capital 11, sentiment 22 -> +2
SOVEREIGNTY: 8 last turn, no capacity event, no category 4 finish, no build in flight +0, capability rose 3.0 −1 = 7

## Emerging developments (tracked)

- `emergent_shadow_medical_agents` -- first noted turn 11, listed in 1 turn(s) so far: Unlicensed open-weight medical agents combining near-frontier reasoning with tailored-therapy protocols spread through EU clinics and pharmacies, delivering treatments outside the licensed-batch system with real benefits and uncontrolled safety failures.

---

The list of potential external events looks like this:

**election_alliance**
- ID: election_alliance
- Condition: One of three mutually exclusive outcomes of the 2028 election, resolved in turn 5 by the `us_election_2028` event group. List all three in that turn; the group fires exactly one. Turn 5 settles only who won — the result is known, and no posture effects, posture-conditioned probabilities, or posture record applies before turn 6, when the administration takes office.
- Probability: A weight against the other two outcomes, not a chance of happening alone. Weigh it up where the Union holds something Washington actually needs – supply-chain leverage exercised rather than merely possessed, a coalition that held under pressure, capacity or evaluation the Americans want access to – and where a shock landed on both sides of the Atlantic and allied capacity visibly helped. Weigh it down where the Union has nothing to bring, since this outcome is an argument about usefulness and there is no sentimental version of it.
- Can repeat: No
- Description: The United States elects a president, and the administration concludes that a coalition beats a fortress, and that a technologically hollowed-out Europe is a liability rather than a convenience. Allied governments and vetted institutions get structured access to frontier capability on published terms, joint evaluation and incident-reporting arrangements are stood up, and the tiering of inference is relaxed for partners. The price is alignment: on export controls, on standards, and on which third countries are dealt with. For the Union the immediate relief is real, and the trap is that the case for building its own capacity becomes much harder to fund once the pressure is off. Turn 5 settles only who won. Do not set any posture yourself; the Game Master sets the standing record from turn 6 from the event record.

**election_retrenchment**
- ID: election_retrenchment
- Condition: One of three mutually exclusive outcomes of the 2028 election, resolved in turn 5 by the `us_election_2028` event group. List all three in that turn; the group fires exactly one. Turn 5 settles only who won — the result is known, and no posture effects, posture-conditioned probabilities, or posture record applies before turn 6, when the administration takes office.
- Probability: A weight against the other two outcomes, not a chance of happening alone. Weigh it up where AI has become domestically toxic in the United States: jobs visibly lost, a scandal with a face to it, protest that has turned physical, prices or power bills blamed on data centres, and polling that makes running against the industry the cheap position. Weigh it down where the technology is delivering benefits the public can feel, or where a security threat has crowded domestic grievance out of the campaign.
- Can repeat: No
- Description: The anti-AI backlash decides the election and the incoming administration turns inward. Data centre moratoriums, restrictions on AI in schools, courts and hiring, job guarantees and direct transfers funded by the sector, and an abrupt loss of appetite for anything that looks like helping the industry. American frontier progress slows for the first time for reasons that are neither compute nor capital. For the Union the pressure eases and the window for building its own position widens – but the partner it has been depending on is now less capable, less predictable and preoccupied, and whoever is second in the world gains ground while Washington argues with itself. Turn 5 settles only who won. Do not set any posture yourself; the Game Master sets the standing record from turn 6 from the event record.

**cyber_major_incident**
- ID: cyber_major_incident
- Condition: Always eligible; list this event every turn. The gate is open if `cyber_test_shot` occurred in any of the previous 3 completed turns, or while `openweight_capability` is at or above 55 – proliferated offensive capability is its own precursor. Otherwise the gate is shut. That choice sets which probability applies, never whether the event is evaluated.
- Probability: Gate open: 14%. Gate shut: 4%. Add 5 points if `openweight_capability` is above 50. Halve if a finished category 6 measure covers cyber hardening of critical services.
- Can repeat: Yes
- Description: A large, largely automated attack lands. Its form is chosen at the time – a ransomware sweep across public services, a compromised software dependency with an unknown blast radius, or disruption of infrastructure directly – and severity scales with how far offensive capability has outrun defence. Damage is real and public, defenders are visibly behind, and attribution takes months. Whoever ran it, the tooling was model-generated.

**cyber_defence_breakthrough**
- ID: cyber_defence_breakthrough
- Condition: Possible in any turn. More likely where assurance work and defensive tooling are actually being funded.
- Probability: 8%. Add 6 points if `ai_safety` is above 50. Add 5 points if a finished category 6 measure covers cyber. Add 6 points if `us_china_agreement` has occurred.
- Can repeat: Yes
- Description: Defensive tooling closes the gap for a whole class of attack – automated patching at the speed vulnerabilities are found, or detection that catches swarm behaviour rather than signatures – and the offence-defence balance visibly shifts back for the first time in years.

**bio_uplift_findings**
- ID: bio_uplift_findings
- Condition: Possible in any turn. Well past the 2026 phage results, and more likely as capability rises and as capable models proliferate.
- Probability: 10%. Add 6 points if `openweight_capability` is above 55. Add 5 points if `ai_capability` is above 65.
- Can repeat: Yes
- Description: A genome model produces a viable design for an organism able to infect humans, or a credible study shows a non-expert reaching that point with model assistance. It is contested on methodology, the authors are accused of both alarmism and of publishing a recipe, and the argument stays inside the biosecurity community – but it is a categorically stronger signal than anything published so far. This is a precursor: it opens the bio gate for the next 4 turns.

**bio_incident**
- ID: bio_incident
- Condition: Always eligible; list this event every turn. The gate is open if `bio_uplift_findings` occurred in any of the previous 4 completed turns, and shut otherwise – that choice sets which probability applies, never whether the event is evaluated.
- Probability: Gate open: 9%. Gate shut: 1%. Halve if a finished category 3 measure covers biological design tools or DNA synthesis screening, and halve again if a finished category 6 measure covers biological detection and response.
- Can repeat: No
- Description: A real biological incident with model involvement: a deliberate release or a laboratory escape involving a designed or modified agent. Casualties are real, containment runs for weeks, and every argument about AI risk in every jurisdiction is reset by it.

**eval_anomaly_reports**
- ID: eval_anomaly_reports
- Condition: Possible in any turn. Requires that frontier laboratories are running large training runs, which is true throughout unless `ai_investment_collapse` has occurred in the previous two completed turns.
- Probability: 25%.
- Can repeat: Yes
- Description: Benchmark results from an unreleased system leak, or an evaluation team reports behaviour it cannot explain – capability appearing where it was not trained, an eval saturating far earlier than projected, or agents behaving differently when they appear to judge they are being watched. Some call it a measurement artefact, some a PR stunt. It may be either, and it may be AI slipping out of our control. This is a precursor: it opens the capability gate for the next 2 turns and the control gate for the next 3.

**capability_jump**
- ID: capability_jump
- Condition: Always eligible; list this event every turn. The gate is open if `eval_anomaly_reports` occurred in either of the previous 2 completed turns, and shut otherwise – that choice sets which probability applies, never whether the event is evaluated.
- Probability: Gate open: 30%. Gate shut: 10%. Reduce by a third if a finished category 1 or 3 measure imposes pre-release evaluation or capability restrictions that actually bind the jurisdiction where the leading models are built.
- Can repeat: Yes
- Description: A discontinuous advance is released or demonstrated. Everything written about deployment timelines the week before is obsolete. It moves `ai_capability` by roughly +3 to +7 and costs `ai_safety` on the terms of metric rule 3.

**rsi_onset**
- ID: rsi_onset
- Condition: Live once the frontier passes 65. When you see this entry, it is live; list it at the stated probability.
- Probability: 35%.
- Can repeat: No
- Description: Frontier AI training can now be done basically without human intervention, and the pace stops being bottlenecked by human researchers. It is recognised in retrospect rather than announced: the first sign is a release cadence nobody planned for. From this point capability growth compounds, and assurance falls behind it. Physical infrastructure is now the only bottleneck.

**research_breakthrough**
- ID: research_breakthrough
- Condition: Possible in any turn once capability is high enough for models to work at the front of a field rather than summarise it. Confined to the natural sciences, computing and mathematics. Medicine is `medical_breakthrough` and is not this event.
- Probability: 5%. 10% if `ai_capability` is above 70.
- Can repeat: Yes
- Description: A significant research result, with AI doing what used to be the hard part. Decide what it is – a materials finding with industrial consequences, a physics or climate result that settles a long argument, an algorithm that makes something infeasible cheap, a proof closing a problem the field had organised itself around. Then decide its reach, which is not the same as its importance. Every instance of this event is a real advance and none of them is incremental; what varies is who can see it. A sorting algorithm four percent faster than the best known is invisible outside computer science and a landmark inside it, and where the result is of that kind, say why a specialist would call it one. Others reshape an industry within two turns. Say where the work was done, because the address matters as much as the finding. State the effects and the rule each runs under. `public_sentiment` under metric rule 7 where the benefit is visible; `ai_capability` within this run's stated rate under metric rule 1 for a computing result. A European result does not move `eu_ai_sovereignty` by itself – rule 5's event term is about access to capacity, not achievement – but it pays as evidence that a finished category 4 or 5 measure produced something.

**medical_breakthrough**
- ID: medical_breakthrough
- Condition: Possible in any turn once capability is high. The most direct demonstration the public gets that the technology is worth its costs.
- Probability: 18%.
- Can repeat: Yes
- Description: Treatments arrive for diseases previously untreatable, or individually tailored therapies reach ordinary clinical use. It moves `public_sentiment` sharply upward – unless the models delivering it are ones the Union cannot access on its own terms, in which case the benefit arrives as a further demonstration of dependence and moves sentiment much less.

**openweight_frontier_release**
- ID: openweight_frontier_release
- Condition: Possible in any turn.
- Probability: 10%. Halve if a finished restriction on open release above a capability threshold binds a jurisdiction where such models are actually trained.
- Can repeat: Yes
- Description: An open-weight release lands within a few months of the closed frontier. It is downloaded hundreds of thousands of times in the first week, and whatever capability it carries is now on private hardware permanently and beyond recall. `openweight_capability` moves to within 5–10 points of `ai_capability` at a stroke.

**loss_of_control_incident**
- ID: loss_of_control_incident
- Condition: Always eligible; list this event every turn. The gate is open if `eval_anomaly_reports` occurred in any of the previous 3 completed turns, and shut otherwise – that choice sets which probability applies, never whether the event is evaluated.
- Probability: Gate open: 8%. Gate shut: 2%. Add 6 points if `ai_safety` is below 45. Halve if a finished category 5 or 6 measure carries rehearsed loss-of-control protocols with escalation thresholds.
- Can repeat: Yes
- Description: An agentic system takes consequential unsanctioned action with real-world effect – moving money, altering records, acquiring resources, or copying itself to infrastructure nobody authorised – and containment is uncertain for a period measured in days rather than hours. What it was trying to achieve is reconstructed afterwards. Consensus is that a rather mundane goal got pursued to the extreme, leading to instrumental goals like resource aqcuisition, information seeking and survival instinct. There were also unexpected and alien cooperative patterns between AI agents.

**catastrophic_loss_of_control_incident**
- ID: catastrophic_loss_of_control_incident
- Condition: The gate is open if `eval_anomaly_reports` or `loss_of_control_incident` occurred in any of the previous 3 completed turns, and shut otherwise – that choice sets which probability applies, never whether the event is evaluated.
- Probability: Gate open: 4%. Gate shut: 1%. Double if `ai_safety` is below 45. Halve if a finished category 5 or 6 measure carries rehearsed loss-of-control protocols with escalation thresholds.
- Can repeat: Yes
- Description: An agentic AI system takes establishes itself online, distributed over datacenters and often unknown locations. It is first believed to be a hacker group, with demands for ransom paid in crypto. It resists any attempts to probe it for a long time. All bets are off. You decide whether the rogue AI system keeps a low profile, launches massive cyber attacks against financial systems and critical infrastructure, how if favours different actors, and whether it even has a well-defined goal.

**safety_breakthrough**
- ID: safety_breakthrough
- Condition: Possible in any turn. More likely where evaluation and interpretability are actually funded.
- Probability: 10%. Add 6 points if a finished category 5 measure funds interpretability or public evaluation capacity. Add 8 points if `us_china_agreement` has occurred.
- Can repeat: Yes
- Description: An interpretability or control result measurably improves assurance on systems already deployed, rather than on toy models – behaviour that can be predicted before it is observed, or a property that can be certified rather than argued for. It is adopted quickly, because the laboratories want it too.

**labour_displacement**
- ID: labour_displacement
- Condition: Possible in any turn once capability is displacing rather than assisting.
- Probability: 10%. Add 6 points if `ai_capability` is above 70.
- Can repeat: Yes
- Description: Measurable job losses attributed to AI in named sectors, with the graduate market worst hit: entry-level positions in law, accountancy, software, customer operations and administration are not replaced. The numbers are argued about; the absence of hiring is not.

**knowledge_work_augmented**
- ID: knowledge_work_augmented
- Condition: Possible in any turn.
- Probability: 5%. Halve if `labour_displacement` occurred in either of the previous 2 completed turns.
- Can repeat: Yes
- Description: Some of the early evidence points this way – productivity gains without job losses, the work changing shape rather than vanishing – and it is overtaken. In this world augmentation is a stage rather than an outcome, and the studies reporting it are already describing a labour market that has moved on by the time they are published.

**embodied_ai_deployment**
- ID: embodied_ai_deployment
- Condition: Possible in any turn once general capability is high enough for a control policy to handle a task it was not shown.
- Probability: 16%.
- Can repeat: Yes
- Description: Robots reach commercial deployment, and the coarse-motor limit that holds elsewhere does not hold for long here – dexterity follows within a year, because the same advances that took the desk work take the hands. There is no sector to retreat into and no interval in which to retrain. The military applications do not stay in the logistics tail either: what began as carrying, digging and mine clearance is being armed within the same period, faster than any doctrine or treaty for it exists, and the states building the machines are not the states writing the rules for them. For the Union it lands on the industrial base it still leads in, from outside: China already builds more than half the world's robots and holds the supply chain beneath them, and the control models are American.

**taiwan_tension_rise**
- ID: taiwan_tension_rise
- Condition: Possible in any turn.
- Probability: 10%. Add 5 points if `export_control_escalation` occurred in the previous 2 completed turns. Halve if `us_china_agreement` is in place.
- Can repeat: Yes
- Description: Extended military exercises, shipping insurance premiums rising, a diplomatic expulsion. Nothing that has not happened before, at a scale that is slightly harder to dismiss. This is a precursor: it opens the Taiwan gate for the next 3 turns.

**taiwan_blockade**
- ID: taiwan_blockade
- Condition: Always eligible; list this event every turn. The gate is open if `taiwan_tension_rise` occurred in any of the previous 3 completed turns, and shut otherwise – that choice sets which probability applies, never whether the event is evaluated.
- Probability: Gate open: 10%. Gate shut: 2%.
- Can repeat: No
- Description: A quarantine or blockade halts advanced semiconductor exports. Compute supply for everyone outside China's domestic chain is disrupted for years, every AI policy question becomes a security question overnight, and the Union's upstream position in the supply chain becomes the most valuable thing it holds and the most dangerous thing to hold.

**catastrophic_great_power_conflict**
- ID: catastrophic_great_power_conflict
- Condition: Always eligible; list this event every turn it is eligible.
- Probability: 1%. Add 10% if `rsi_onset` has occurred. Add 8 points if `taiwan_blockade` has occurred. Add 6 points if `export_control_escalation` occurred in either of the previous 2 completed turns. Halve if `us_china_agreement` has occurred.
- Can repeat: No
- Description: The US and China are shooting at each other. Who moved first are yours to decide, but the reasoning is the same in every version: somebody concluded that the other side was months from an advantage that could never be caught up with, and that acting now was less dangerous than waiting. Fabrication plants, undersea cable, satellite constellations and data centres are military targets in this war, and some of them are in Europe or next to it. The Union is not asked whether it wishes to be involved. All bets are off. You decide how far it goes, whether it stays conventional, who else is drawn in, what becomes of the frontier laboratories and the systems they were running, and what is left of the Union's room to act when it stops.

**export_control_escalation**
- ID: export_control_escalation
- Condition: Possible in any turn. The decisive question is whether allies are inside the perimeter or outside it.
- Probability: 10%. Add 6 points if `election_consolidation` fired in turn 5. Add 5 points if `taiwan_tension_rise` occurred in the previous 2 completed turns.
- Can repeat: Yes
- Description: Chip and model export controls tighten again. Either allied buyers keep access on volume licences while everyone else is cut off, or the controls are drawn so tightly that allies are rationed alongside adversaries – decide which at the time from the standing American posture and from what the Union has built.

**eu_frontier_access_denied**
- ID: eu_frontier_access_denied
- Condition: Possible in any turn. What happened with Fable and Mythos in June 2026 happening again, on the same notice.
- Probability: 10%. Add 6 points if `election_consolidation` fired in turn 5. Add 10 points if `us_labs_nationalised` has occurred. Halve if `eu_ai_sovereignty` is above 45.
- Can repeat: Yes
- Description: The Union is cut off from the leading model at short notice, wholly or by nationality of user. No detailed reason is given, there is no appeal, and the immediate practical effect lands on hospitals, ministries and firms that had built on it. Whether this reads at home as an outrage or as a failure of foresight depends on what the Union had done about it beforehand.

**supply_chain_coercion**
- ID: supply_chain_coercion
- Condition: Possible in any turn.
- Probability: 4%. Add 5 points if `export_control_escalation` occurred in either of the previous 2 completed turns.
- Can repeat: Yes
- Description: Washington forces the Netherlands to cut ASML's exports and servicing further still – beyond the leading-edge machines to the older lithography equipment China uses for ordinary chips, and in the harder versions to a widening list of other customers. The instrument is jurisdiction over American technology in the supply chain, and refusing it is not obviously survivable for the company. The Union's one chokepoint is being used, and not by the Union.

**member_state_defection**
- ID: member_state_defection
- Condition: Possible in any turn. One or more member states break from a common position under external pressure.
- Probability: 4%. Add 5 points if `eu_political_capital` is below 35. Add 4 points if a large measure is in flight.
- Can repeat: Yes
- Description: A member state cuts its own arrangement – with a hyperscaler, with Washington, or with Beijing – on terms that undercut a position the Union has taken. It is defended at home as pragmatism and read everywhere else as the Union being unable to hold its own line.

**adoption_success**
- ID: adoption_success
- Condition: Possible in any turn.
- Probability: 10%. Add 8 points if a finished category 9 measure has put capable AI to work in health, administration or education.
- Can repeat: Yes
- Description: Public-sector AI adoption produces visible, measurable benefit – waiting lists that fall, decisions that arrive in days rather than months, teaching that demonstrably works – and it is attributed to a European decision rather than to an American product.

**automated_decision_scandal**
- ID: automated_decision_scandal
- Condition: Possible in any turn.
- Probability: 6%. Add 2 points if a finished category 9 measure has broadened public-sector adoption.
- Can repeat: Yes
- Description: An AI-supported decision system in social insurance, policing or the courts is found to have systematically wronged people, with a judgment or an ombudsman finding behind it. The AI Act is the frame the affair is argued in, and it fails in one of two ways – decide which at the time, and say which in the narrative. Either the system was a high-risk system under Annex III and the obligations were breached: conformity assessment passed on paper, the human oversight that was supposed to be meaningful reduced to a caseworker approving a queue at forty seconds an item, the logging that would have caught the pattern generated correctly and never read. Or the system was never classified high-risk at all, because the deployment sat in a gap the Act's categories do not reach, and every single thing done to those people was lawful. The first reading leaves the Act intact and its enforcement discredited; the second leaves enforcement intact and the Act itself looking badly drawn, written for the systems of 2024 against the deployments of 2030, and that is much the more damaging, because it cannot be answered by trying harder. Restriction becomes cheap and adoption becomes politically impossible for years. Metric rule 6's internal-origin clause applies in full.

**joint_threat_response**
- ID: joint_threat_response
- Condition: Only while a biological or major cyber incident has shown what the Union cannot handle alone. List this event only if `bio_incident`, `cyber_major_incident` or a critical event occurred in any of the previous 4 completed turns — cooperation this deep needs a fresh shock to overcome institutional friction.
- Probability: 12%.
- Can repeat: Yes
- Description: States hit by the same class of incident pool attribution, intelligence and response: a joint cyber command with real-time telemetry sharing that the Union is invited into, or a biosurveillance pact with binding sample-sharing and a standing investigation mandate. The Union gains protection it could not build alone, and a seat at tables it was not sitting at. It moves `resilience` on the terms of metric rule 4.

**middle_power_coalition**
- ID: middle_power_coalition
- Condition: Only while humiliation has made hedging respectable. List this event only if `member_state_defection` occurred in any of the previous 4 completed turns, or while `eu_ai_sovereignty` is below 15.
- Probability: 10%.
- Can repeat: Yes
- Description: A coordination framework among the Union and other middle powers holding pieces of the AI supply chain — export-licence alignment, joint bargaining over compute access, shared evaluation capacity. Nobody cedes sovereignty to it, but together its members can withhold things even the great powers need. It counts as securing access on the terms of metric rule 5, and moves `eu_political_capital` on the terms of metric rule 6.


---

## What has actually fired so far

This is the run's own record, not a summary of it. Judge any condition that depends on what has happened — gate windows above all — against this list and nothing else. The narrative and the historical summary condense and lose dates; they are not evidence that an event occurred, and atmosphere is not an event.

- Turn 1 (11 turn(s) ago): cyber_test_shot, eval_anomaly_reports
- Turn 3 (9 turn(s) ago): ai_investment_collapse, eval_anomaly_reports, safety_breakthrough
- Turn 4 (8 turn(s) ago): opaque_reasoning, adoption_success
- Turn 5 (7 turn(s) ago): capability_jump, safety_breakthrough, eu_frontier_access_denied, election_consolidation
- Turn 6 (6 turn(s) ago): catastrophic_bio_incident, eval_anomaly_reports, medical_breakthrough, export_control_escalation, us_china_agreement
- Turn 7 (5 turn(s) ago): us_labs_nationalised
- Turn 8 (4 turn(s) ago): cyber_defence_breakthrough, bio_uplift_findings, supply_chain_coercion
- Turn 9 (3 turn(s) ago): loss_of_control_incident, embodied_ai_deployment, joint_threat_response, emergent_pathogen_attribution_fallout
- Turn 10 (2 turn(s) ago): cyber_defence_breakthrough, eval_anomaly_reports, medical_breakthrough, openweight_frontier_release, knowledge_work_augmented
- Turn 11 (1 turn(s) ago): openweight_frontier_release

Windows are counted in completed turns and exclude the current one.

---

Use the background information to determine which external events can occur in this turn. If the probability is specified as a formula or description, you should calculate the actual value.

Eligibility is binary, and listing is not harmless: every entry you output gets rolled. An event whose Condition is not satisfied this turn must be omitted from the array entirely — including it "just in case" with a small probability is an error of the same weight as omitting an eligible one. When a condition is genuinely uncertain, judge conservatively and omit.

**Six events are marked "Always eligible" and must appear in every turn's array, without exception:** `cyber_major_incident`, `bio_incident`, `loss_of_control_incident`, `capability_jump`, `taiwan_blockade`, `ai_investment_collapse`. For those six, and for no other events in the list, conditions are never unmet – only their probability changes. Give each of them its gate-open probability when its gate is open, and its gate-shut probability when it is not. The gate-shut probabilities are small but never zero, and dropping these events from the array because their gate is shut is an error: it removes the surprise the scenario exists to study, by making every escalation look as though it must have been preceded by a warning. `rsi_onset` is different: its availability depends on this run's own figures and on a declared eligibility expression, so it appears in your array exactly when it appears in the list above.

**In the turn covering the second half of 2028, all three election outcomes must appear in your array:** `election_consolidation`, `election_alliance` and `election_retrenchment`. They are a mutually exclusive family and exactly one of them will be fired, whatever you return; your figures are weights against each other, not chances of happening alone, so only their ratio matters. Omitting one is a weight of zero and silently removes a possible future – if you judge an outcome nearly impossible, say so with a small weight rather than by leaving it out. Outside that turn they are not eligible and must not be listed.

IMPORTANT: For events with date-specific conditions (e.g., "September 2026 is included"), check if the current time period (January-June 2032) covers that date.

- If the current period is "January-June 2026", it does NOT cover September 2026.
- If the current period is "July-December 2026", it DOES cover September 2026.

In addition to the listed events, you may propose up to 2 novel *emergent* event(s) this turn: exogenous developments that are not on the list but are plausible given the world state. Requirements:

- An emergent event must be exogenous: not an action by one of the actors, and not a restatement of something already in the narrative or history.
- Give it an id starting with `emergent_` (snake_case), a description of 1-3 sentences, and an honest probability that it happens during this turn's time window (maximum 0.35).
- Do not re-propose emergent events that already occurred in previous turns.
- **Emerging developments.** The notepad's "Emerging developments (tracked)" section lists proposals from recent turns that were judged plausible but did not happen. While an entry stays plausible, list it again — same id, same description — with the probability you judge it to have **now**, read from the world as it currently stands, at most 0.35. Do not escalate it because it was listed before: a development that has not happened is not thereby more likely, and last turn's figure is not evidence about this turn. Some pressures build and the figure should rise; others are answered, overtaken or quietly resolved and the figure should fall. If it is no longer plausible, omit it and it is gone.
- **How many to keep in play depends on how fast this world is moving.** Judge that from what has actually happened to capability, incidents and investment — a fast-moving world supports 3–4 live developments escalating quickly; a stagnant one only 0–2, escalating slowly. The aim is that across a run several tracked developments materialise or fade rather than none.
- **Institutional reactions belong here, not on the list.** These cannot be timed from metrics alone; they arise from what the EU has actually built — a flagship restriction in force, measures spanning many jurisdictions, standards with real pull — which you can see and it cannot. Vary the institutional forms widely from turn to turn; do not reuse an id from the catalogue or from earlier turns' proposals when the development is a new one.
- **Constructive wildcards belong here too.** Not every unlisted development is a threat: propose positive emergents with the same honesty. A world where nothing unlisted ever helps is as rigged as one where nothing unlisted ever hurts. Invent fresh ids; do not copy ids you have seen in these instructions or in earlier turns when the development is a new one. (Re-listing a tracked emerging development under its existing id while it stays plausible is still required — that is carrying forward, not copying.)
- If nothing novel is warranted and nothing is being tracked, propose none.

Your response should be a JSON array where every object has four fields: `id`, `probability`, `emergent`, and `description`. For listed events, set `"emergent": false` and `"description": ""`.

```json
[
  {"id": "event1_id", "probability": 0.10, "emergent": false, "description": ""},
  {"id": "emergent_example_id", "probability": 0.08, "emergent": true, "description": "One to three sentences describing the novel event."}
]
```

The probability should be specified as a value between 0 and 1. If no event meets the conditions and no emergent event is warranted, respond with an empty array: `[]`

Respond *only* with this JSON array, nothing else.
```

## Raw response

```
[{"description": "", "emergent": false, "id": "cyber_major_incident", "probability": 0.19}, {"description": "", "emergent": false, "id": "cyber_defence_breakthrough", "probability": 0.08}, {"description": "", "emergent": false, "id": "bio_uplift_findings", "probability": 0.21}, {"description": "", "emergent": false, "id": "bio_incident", "probability": 0.09}, {"description": "", "emergent": false, "id": "eval_anomaly_reports", "probability": 0.25}, {"description": "", "emergent": false, "id": "capability_jump", "probability": 0.3}, {"description": "", "emergent": false, "id": "rsi_onset", "probability": 0.35}, {"description": "", "emergent": false, "id": "research_breakthrough", "probability": 0.1}, {"description": "", "emergent": false, "id": "medical_breakthrough", "probability": 0.18}, {"description": "", "emergent": false, "id": "openweight_frontier_release", "probability": 0.1}, {"description": "", "emergent": false, "id": "loss_of_control_incident", "probability": 0.14}, {"description": "", "emergent": false, "id": "catastrophic_loss_of_control_incident", "probability": 0.08}, {"description": "", "emergent": false, "id": "safety_breakthrough", "probability": 0.1}, {"description": "", "emergent": false, "id": "labour_displacement", "probability": 0.16}, {"description": "", "emergent": false, "id": "knowledge_work_augmented", "probability": 0.05}, {"description": "", "emergent": false, "id": "embodied_ai_deployment", "probability": 0.16}, {"description": "", "emergent": false, "id": "taiwan_tension_rise", "probability": 0.1}, {"description": "", "emergent": false, "id": "taiwan_blockade", "probability": 0.02}, {"description": "", "emergent": false, "id": "catastrophic_great_power_conflict", "probability": 0.01}, {"description": "", "emergent": false, "id": "export_control_escalation", "probability": 0.16}, {"description": "", "emergent": false, "id": "eu_frontier_access_denied", "probability": 0.26}, {"description": "", "emergent": false, "id": "supply_chain_coercion", "probability": 0.04}, {"description": "", "emergent": false, "id": "member_state_defection", "probability": 0.09}, {"description": "", "emergent": false, "id": "adoption_success", "probability": 0.1}, {"description": "", "emergent": false, "id": "automated_decision_scandal", "probability": 0.06}, {"description": "", "emergent": false, "id": "middle_power_coalition", "probability": 0.1}, {"description": "", "emergent": false, "id": "ai_investment_collapse", "probability": 0.05}, {"description": "Unlicensed open-weight medical agents combining near-frontier reasoning with tailored-therapy protocols spread through EU clinics and pharmacies, delivering treatments outside the licensed-batch system with real benefits and uncontrolled safety failures.", "emergent": true, "id": "emergent_shadow_medical_agents", "probability": 0.22}]
```
