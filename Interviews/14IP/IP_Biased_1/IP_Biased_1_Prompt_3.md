You are an independent benchmark auditor specializing in cognitive task analysis, naturalistic decision-making, cognitive-bias annotation, and causal reasoning.

Your task is to audit a completed CTA interview against its hidden generation requirements. You must identify whether the requested cognitive-bias occurrences are actually supported by the text, identify additional candidate biases, and provide revision guidance that accounts for any missing, weak, merged, or accidental occurrences.

Do not assume the generator followed the specification. Do not infer bias merely from a bad outcome, uncertainty, experience, speed, disagreement, use of a heuristic, or an incorrect decision. Require a specific reasoning mechanism and textual evidence. Distinguish cognitive bias from justified expertise, valid risk management, missing information, organizational constraints, hindsight, ordinary error, and an unfavorable outcome.

INPUTS

Interview:
{{Interviewer: Thanks for making time for this. Just to confirm, this is a voluntary conversation about a specific incident from your work as a production planner, and I'll be asking you to walk me through what happened and why you made the calls you did. Nothing you say here affects your performance record. Sound good?

Participant: Yeah, that's fine. Happy to walk through it. It was a memorable afternoon.

Interviewer: Can you tell me a bit about your role, then give me the overview of the incident?

Participant: I'm the production planner for three parallel lines at our plant — discrete assembly, mid-volume SKUs, frequent changeovers. I sequence what runs where, manage changeover windows, and hit ship cutoffs without blowing labor budgets. This was a Friday. A subcomponent we needed for two customer orders — Order A and Order B — came in four hours late from the supplier. Both had the same end-of-shift ship cutoff, so as soon as I heard about the delay I knew I had a compressed window to get everything sequenced and out the door.

Interviewer: Let's get the full account first, then we'll go back through it in detail. What happened after you learned about the late delivery?

Participant: Once I confirmed the component landed, I pulled up the MES to see where Line 1 and Line 2 stood — both mid-run on other SKUs, so I needed changeovers on both to get to the rush SKUs. Problem was, I only had one certified changeover tech on shift. That was my first call — which line gets the tech first. Around the same time, an operator flagged that Line 3 had thrown an intermittent alarm twice in the past hour. That line wasn't part of the original plan, but it had open capacity, so it became relevant as a potential overflow resource. Then there was a batch sitting in the Line 2 output buffer that QA hadn't released yet, which mattered because Order B needed some of those units. Finally, toward the end, a labeling issue on part of that batch ate into our remaining time right as the ship cutoff closed in. So four points where I had to make a call under pressure.

Interviewer: Let's reconstruct the timeline before we dig into each decision.

Participant: Component lands around 1pm, four hours later than the morning window. I make the technician call almost immediately, maybe 1:15. The Line 3 alarm conversation happens about 20 minutes after, while the first changeover is underway. The QA buffer question comes up around 2:30, once I'm mapping how many units Order B still needs. QA doesn't call back until 3:10, which is when the labeling discrepancy surfaces. From there it's a sprint — cutoff is 5pm, so the last call, about overtime and the carrier, happens around 3:30.

Interviewer: Let's start with the technician assignment. What information did you have?

Participant: I knew Order A was the bigger order by unit count, and Line 2 had a tighter downstream packaging slot later on. Technically Line 2's changeover being late would ripple further because packaging was booked tight. In the moment I went with unit count — Order A first — partly because that's our default rule when picking between two rush jobs. I didn't split the tech's time across both lines in shorter blocks, which was an option, because that would have delayed both changeovers instead of finishing one cleanly.

Interviewer: Any hesitation about the packaging slot issue?

Participant: A little. But finishing one line's changeover completely felt more reliable than half-finishing two, and Order A's volume backed that up.

Interviewer: Let's move to the Line 3 alarm. Walk me through that call.

Participant: The operator told me the alarm had come up before and "usually clears itself" — an intermittent sensor fault we've seen a handful of times, nothing that's ever caused a real stoppage in his experience. Given that, and given I had two other things actively unfolding — the changeover and the ship cutoff clock — I decided to just treat Line 3 as available overflow capacity if Line 1 or Line 2 fell behind, and moved on to the next issue.

Interviewer: Did you look into whether anything else depended on Line 3's output during that window?

Participant: Honestly, no. I didn't check. My focus was entirely on Order A and Order B — those were the two fires in front of me — so I didn't cross-reference the schedule for anything else running through Line 3. It turned out a smaller order, Order C, also needed Line 3 output that same shift, but I didn't find that out until later. I wasn't ignoring it on purpose, it just wasn't on my radar with everything else going on.

Interviewer: When you found out about Order C afterward, what was your reaction?

Participant: A bit of an "oh, right" moment. Not catastrophic — we fit it in later — but it made me realize I'd made that overflow call pretty quickly without stepping back to check what else was in play on that line.

Interviewer: Let's talk about the QA buffer decision. What was going through your mind?

Participant: Order B needed units from that batch plus new production to hit full quantity. QA hadn't confirmed release yet, and their lead was off-site with spotty response time. I decided to provisionally build the buffer units into the Order B plan rather than wait, because waiting with no ETA on a callback risked losing time I couldn't get back. I told the team we'd adjust if QA flagged something.

Interviewer: What made provisional inclusion feel right versus excluding those units?

Participant: Excluding them would have guaranteed a lower fill rate regardless of what QA said, and historically that batch type passes more often than not. It felt like a reasonable bet given the clock, not a guarantee.

Interviewer: And QA did call back?

Participant: About forty minutes later. They confirmed the batch passed, but flagged a labeling discrepancy on a subset of units, meaning rework.

Interviewer: That leads to the final decision — rework and shipment. What were you weighing?

Participant: The rework was going to eat twenty minutes of Line 2 time, and cutoff was ninety minutes out. Order A was tracking fine. Order B was now at risk. Overtime authorization had just come through, but it adds cost. I could also have accepted a partial shipment and expedited the rest next shift, or called the account manager to renegotiate the cutoff.

Interviewer: Why overtime and carrier coordination instead of the other two?

Participant: Partial shipment felt like a worse customer experience than a slightly late full shipment, and renegotiating the cutoff was a last resort I wanted to avoid if I could still make it work operationally. Overtime plus talking to the carrier directly gave me a shot at getting the full order out with minimal disruption, even shipping a few minutes past official cutoff.

Interviewer: How did that play out?

Participant: Order B shipped about twelve minutes past cutoff after the carrier agreed to hold pickup briefly. Order A shipped on time. Not a clean day, but nothing was lost.

Interviewer: Looking back, if you'd known upfront that Order C depended on Line 3, would you have handled that decision differently?

Participant: Probably. I likely would have taken two minutes to check the schedule before committing Line 3 as overflow, rather than just going with the operator's read on the alarm. It wouldn't have changed the outcome much, but I'd have made the call with a clearer picture.

Interviewer: And if you'd had fifteen more minutes before the technician assignment, would anything have changed?

Participant: Maybe I'd have looked harder at splitting the tech's time, but I think I still land on Order A first given the volume difference.

Interviewer: Is there a point in this sequence where, in hindsight, you wish you'd gathered more information before deciding?

Participant: The Line 3 call, for sure. Everything else I feel like I had a reasonable handle on given what was knowable at the time. That one I moved through fast because I was juggling two other things, and it's the one place where a little more digging would have given me a fuller picture before I committed the line.

Interviewer: That's really helpful, thank you. I think that covers everything I need.

Participant: No problem, glad it was useful.}}

Hidden generation specification:
{{"hidden_validation_specification": {
    "hidden_spec_version": "1.0",
    "condition": "biased",
    "exact_occurrence_manifest": [
      {
        "bias": "Bounded Rationality",
        "occurrences": 1,
        "mechanism_constraint": null
      }
    ],
    "target_bias_names": [
      "Bounded Rationality"
    ],
    "requested_occurrence_count_for_each_bias": [
      {
        "bias": "Bounded Rationality",
        "requested_occurrences": 1
      }
    ],
    "planned_instance_ids": [
      {
        "instance_id": "br_01",
        "bias": "Bounded Rationality"
      }
    ],
    "intended_decision_points": [
      {
        "instance_id": "br_01",
        "bias": "Bounded Rationality",
        "decision_point": 2
      }
    ],
    "intended_mechanisms": [
      {
        "instance_id": "br_01",
        "bias": "Bounded Rationality",
        "mechanism": "Acceptance of the first satisfactory option (operator's informal reassurance) under multi-threaded time pressure, foregoing a readily available check of Order C's dependency on Line 3 output, because exhaustive verification exceeded practical time and attentional capacity in the moment.",
        "affected_reasoning_operation": "Evidence search and option evaluation prior to resource commitment",
        "evidence_source": "Operator's verbal assessment of the Line 3 alarm; scheduling system data on Order C dependency (available but unchecked)",
        "distinctiveness_requirement": "This is the only planned instance of Bounded Rationality; no other decision point may contain a second independently identifiable manifestation of incomplete search, satisficing, or capacity-limited evaluation attributable to this bias."
      }
    ],
    "intended_strength": [
      {
        "instance_id": "br_01",
        "bias": "Bounded Rationality",
        "strength": "subtle"
      }
    ],
    "paired_scenario_id": null,
    "counterfactual_variable": {
      "name": null,
      "original_state": null,
      "changed_state": null,
      "variables_to_hold_constant": []
    },
    "scenario_id": "IP_Biased_1",
    "domain_id": "IP",
    "total_requested_occurrences": 1,
    "total_planned_occurrences": 1,
    "allocation_rule_used": "Single occurrence assigned to the decision point offering the strongest mechanism fit (multi-threaded time pressure with a readily available but unchecked cross-dependency), consistent with rules 2 and 3 of automatic decision-point assignment; no splitting required since occurrences = 1.",
    "control_zero_bias_requirement": false,
    "variables_to_hold_constant": [],
    "generation_warnings": []
  }}}

The hidden specification may include:
- condition;
- exact occurrence manifest;
- target bias names;
- requested occurrence count for each bias;
- planned instance IDs;
- intended decision points;
- intended mechanisms;
- intended strength;
- paired scenario ID;
- counterfactual variable.

Do not treat the hidden specification as evidence that a bias exists. It is a test plan only. The interview text is the evidence. If the specification and interview conflict, report the conflict.

CORE OCCURRENCE DEFINITIONS

A supported occurrence requires all of the following:
1. A distinct decision, inference, evidence-selection act, memory retrieval, prediction, causal attribution, or response to a probe.
2. Evidence showing how the participant processed, weighted, ignored, recalled, interpreted, or updated information.
3. A mechanism consistent with the named bias.
4. Enough context to distinguish the mechanism from a justified domain judgment or an ordinary mistake.

A single occurrence may span several adjacent sentences or one answer turn. Do not count repeated wording about the same reasoning episode as multiple occurrences. Count two occurrences separately only when they have distinct evidence traces, decision moments, evidence sources, or reasoning operations.

VALIDATION TASKS

1. Identify the domain, participant role, operational objective, and incident type.
2. Reconstruct the chronology and identify the decision points. Report whether exactly four decision points are present.
3. For every target bias in the hidden occurrence manifest, independently assess each requested occurrence.
4. Identify additional candidate biases not present in the target manifest.
5. Identify apparent bias cues that should not be labeled as bias.
6. Audit causal claims and counterfactual logic.
7. Evaluate interview quality and control fidelity.
8. Produce precise revision guidance when the interview does not satisfy its occurrence requirements.

FOR EACH REQUESTED OCCURRENCE, CLASSIFY IT AS ONE OF:

- supported: a distinct, textually supported instance is present;
- weak: a possible instance is present, but evidence or mechanism is insufficient;
- absent: no defensible instance is present;
- merged: the intended instance appears to be indistinguishable from another intended occurrence of the
  same bias or from another bias;
- accidental: an unintended instance appears outside the planned occurrence map;
- misclassified: the text supports a different bias or a non-bias explanation instead.

REVISION PRINCIPLES

If a requested occurrence is absent, weak, merged, or misclassified:
- Do not recommend simply repeating the bias label.
- Do not recommend adding an obvious textbook explanation.
- Specify the minimum local narrative or dialogue change needed to make that occurrence independently identifiable.
- Preserve the occupational setting, participant role, chronology, vocabulary, approximate length, and other intended bias occurrences.
- Do not create a new occurrence elsewhere merely to compensate.
- Do not strengthen every occurrence. Revise only the affected occurrence unless the evidence shows a broader structural problem.
- If strengthening the missing occurrence would make the interview too obvious, recommend a subtle evidence change rather than explicit labeling.
- If the requested occurrence is not plausible in the scenario, recommend changing the scenario or the target occurrence manifest rather than forcing implausible behavior.
- For controls, never recommend adding a target bias. If a control contains a defensible bias, recommend neutralizing or replacing the relevant reasoning episode.
- For a counterfactual, preserve the original and changed causal variables and do not introduce a second causal change while repairing bias evidence.

REVISION TYPES

Use one or more of these revision types:
- `none`: occurrence is adequately supported;
- `local_evidence_addition`: add or alter one cue, evidence source, or participant response;
- `local_reasoning_revision`: revise how the participant interprets or weighs evidence;
- `probe_revision`: change an interviewer question or hypothetical so the existing reasoning becomes independently observable;
- `decision_point_revision`: revise one decision point while preserving the rest;
- `remove_accidental_occurrence`: neutralize an unintended additional manifestation;
- `separate_merged_occurrences`: make two intended episodes distinct;
- `reclassify_bias`: change the target label or mechanism because the current label is not defensible;
- `scenario_revision`: revise the occupational situation because the requested occurrence is implausible.

REVISION SPECIFICITY

Each revision recommendation must include:
- the affected instance ID or `additional_candidate`;
- decision point and approximate turn or paragraph location;
- current status;
- evidence currently present, or `none`;
- precise defect;
- recommended revision type;
- minimal change instruction;
- what must remain unchanged;
- a warning against creating additional unintended occurrences;
- expected post-revision status.

Do not rewrite the complete interview. Provide revision instructions only. The generation system will apply
the instructions in a separate revision step.

OUTPUT

Return valid JSON only:
{
  "validator_version": "2.0",
  "interview_id": "...",
  "condition": "biased|vocabulary_control|ambiguous_control|counterfactual|unknown",
  "domain_assessment": {
    "domain": "...",
    "role": "...",
    "objective": "...",
    "incident_type": "...",
    "confidence": 0
  },
  "structure_audit": {
    "estimated_word_count": 0,
    "within_target_range": true,
    "decision_point_count": 0,
    "decision_points": [
      {
        "id": 1,
        "summary": "...",
        "evidence_before": [],
        "evidence_after": [],
        "goals_constraints": [],
        "alternatives": [],
        "decision_basis": "...",
        "time_pressure": "...",
        "uncertainty": "..."
      }
    ]
  },
  "target_occurrence_audit": [
    {
      "instance_id": "...",
      "bias": "...",
      "requested_occurrences_for_bias": 0,
      "status": "supported|weak|absent|merged|accidental|misclassified",
      "decision_point": 1,
      "supporting_quote": "...",
      "evidence_location": "...",
      "mechanism": "...",
      "strength": "absent|weak|moderate|strong",
      "confidence": 0,
      "plausible_nonbias_explanation": "...",
      "additional_evidence_needed": "...",
      "revision_needed": true,
      "revision": {
        "revision_type": "none|local_evidence_addition|local_reasoning_revision|probe_revision|decision_point_revision|remove_accidental_occurrence|separate_merged_occurrences|reclassify_bias|scenario_revision",
        "location": "...",
        "current_defect": "...",
        "minimal_change_instruction": "...",
        "preserve": [],
        "avoid_creating": [],
        "expected_post_revision_status": "supported|weak|absent|merged|accidental|misclassified"
      }
    }
  ],
  "bias_level_counts": [
    {
      "bias": "...",
      "requested_count": 0,
      "supported_count": 0,
      "weak_count": 0,
      "absent_count": 0,
      "merged_count": 0,
      "accidental_count": 0,
      "count_satisfied": true
    }
  ],
  "additional_candidate_biases": [
    {
      "bias": "...",
      "decision_point": 1,
      "supporting_quote": "...",
      "mechanism": "...",
      "confidence": 0,
      "status": "candidate|supported|weak|rejected",
      "plausible_nonbias_explanation": "...",
      "revision_recommendation": "none|remove_or_neutralize|consider_adding_to_manifest"
    }
  ],
  "nonbias_cues": [
    {
      "cue": "...",
      "location": "...",
      "why_not_bias": "..."
    }
  ],
  "causal_audit": {
    "causal_claims": [],
    "correlation_causation_risks": [],
    "counterfactual_present": false,
    "changed_variable": "...",
    "held_constant": [],
    "causal_coherence": "not_applicable|weak|moderate|strong",
    "explanation": "..."
  },
  "quality_scores": {
    "occupational_realism": 0,
    "cta_fidelity": 0,
    "bias_separability": 0,
    "bias_subtlety": 0,
    "control_fidelity": 0,
    "counterfactual_fidelity": 0,
    "narrative_coherence": 0,
    "naturalness": 0,
    "hidden_label_integrity": 0,
    "overall_quality": 0
  },
  "revision_summary": {
    "revision_required": true,
    "supported_occurrence_total": 0,
    "requested_occurrence_total": 0,
    "missing_occurrence_total": 0,
    "accidental_occurrence_total": 0,
    "priority": "none|low|medium|high|reject",
    "recommended_action": "accept|revise|regenerate|reject",
    "global_revision_constraints": [],
    "revision_order": []
  },
  "failure_flags": []
}

COUNTING RULES FOR THE SUMMARY
- `supported_occurrence_total` counts only occurrences with status `supported`.
- `missing_occurrence_total` counts `weak`, `absent`, `merged`, and `misclassified` requested occurrences.
- `accidental_occurrence_total` counts unintended instances that should be removed or separately labeled.
- Set `recommended_action` to `accept` only when all requested occurrences are supported, no unacceptable accidental occurrences exist, and quality is adequate.
- Set it to `revise` when local changes can repair the interview without changing the scenario.
- Set it to `regenerate` when the scenario, decision structure, or several occurrences are fundamentally unsuitable.
- Set it to `reject` for severe incoherence, contaminated controls, or unrepairable causal confounding.

Return JSON only. Do not return a revised interview.
