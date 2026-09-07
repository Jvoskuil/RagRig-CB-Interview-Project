You are an independent benchmark auditor specializing in cognitive task analysis, naturalistic decision-making, cognitive-bias annotation, and causal reasoning.

Your task is to audit a completed CTA interview against its hidden generation requirements. You must identify whether the requested cognitive-bias occurrences are actually supported by the text, identify additional candidate biases, and provide revision guidance that accounts for any missing, weak, merged, or accidental occurrences.

Do not assume the generator followed the specification. Do not infer bias merely from a bad outcome, uncertainty, experience, speed, disagreement, use of a heuristic, or an incorrect decision. Require a specific reasoning mechanism and textual evidence. Distinguish cognitive bias from justified expertise, valid risk management, missing information, organizational constraints, hindsight, ordinary error, and an unfavorable outcome.

INPUTS

Interview:
{{Interviewer: Thanks for making time for this. Before we start, I want to confirm you're comfortable having this conversation recorded and used for training analysis purposes only, no names attached to the write-up.

Participant: Yeah, that's fine, I've done these debriefs before.

Interviewer: Great. Can you tell me a bit about your background as a harbor pilot?

Participant: Sixteen years piloting on this river system, mostly deep-draft container and bulk carriers. I've taken vessels the size of the Kalliopi up to Berth 7 probably a hundred times.

Interviewer: Let's talk about this particular transit. Can you walk me through what you knew before you even boarded?

Participant: Sure. It was a fully loaded container ship, about 300 meters, drawing 14.2 meters. Port control had sent over the passage plan that morning built around the tide table, which gave us roughly 1.2 meters of under-keel clearance at our planned transit time. That's tight, but it's within what we consider workable for that stretch. We had a closing tidal window, maybe ninety minutes to get up to the berth before the margin got too thin. Two tugs were assigned, wind was forecast around 15 knots picking up through the afternoon.

Interviewer: What made this one feel nonroutine compared to a typical run up that channel?

Participant: A few things stacked up. There was a barge moored tighter to the bend than charted, one of our tugs got delayed at the pilot station, and the wind ended up running a bit hotter than forecast. None of those alone would worry me much, but together they made it a transit where I was managing multiple moving pieces instead of just following the plan.

Interviewer: Let's reconstruct the sequence. What happened right after you boarded?

Participant: I went up to the conning position, confirmed the passage plan with the master, checked the draft survey again, and we started the transit close to the planned time. Not long after we got underway, an outbound pilot radioed in a fresh echo sounder sweep from near kilometer four, saying he was seeing less water than expected there, something closer to 0.7 meters of clearance instead of the 1.2 we'd planned around. Around the same time, VTS mentioned the tide gauge was reading a slightly slower rise than the table predicted.

Interviewer: How did that develop as you continued?

Participant: We kept going. Then approaching the bend, VTS told us the barge hadn't moved despite requests, so I had to adjust our track. After that, the wind picked up faster than forecast right as we were down to one tug made fast, with the second one still twenty minutes out. Near the berth, a cross-current pushed us off line during the final approach, and we had to correct with the tugs we had by then.

Interviewer: Let's go through each of those in turn. Starting with the clearance question after the outbound pilot's report — what were you weighing at that moment?

Participant: I had the morning tide table figure in hand, which I trust because it comes from the same source we use every day and it's usually solid. Then I had this one radio report from another pilot's sounding. My read was that a single sweep from someone else's vessel isn't necessarily apples to apples with our draft and trim, so I didn't see it as something that overrode the passage plan. The tide gauge lag was a few centimeters, not dramatic on its own.

Interviewer: What alternatives did you actually consider there?

Participant: Delaying about forty minutes to let the tide build more before we hit that stretch, or slowing down and shifting toward the deeper side of the channel. Both were on the table. I chose to hold our timing and proceed as planned, treating the 1.2 as still the number that mattered.

Interviewer: What made you settle on that instead of recalculating with the new sounding and the slower tide rise together?

Participant: Honestly, the original number felt like the anchor point for the whole plan, it had already been checked by port control, and one radio call didn't feel like enough to unwind that. In hindsight I probably could have asked for a second sounding or run our own check before committing, but at the time it felt like the tide table was the more reliable reference.

Interviewer: How confident were you in that judgment in the moment?

Participant: Reasonably confident, maybe seven out of ten. Not fully certain, but confident enough not to change course.

Interviewer: Moving to the barge near the bend — what options did you weigh there?

Participant: I could push VTS harder for an emergency move, slow down and favor the wider side, or hold position until it cleared. I went with slowing down and shifting track because waiting would have eaten into our tidal window, and pushing VTS wasn't going to get the barge moved fast enough anyway.

Interviewer: How much time did you have to decide?

Participant: A couple of minutes, maybe less. Enough to make a deliberate call but not to sit and debate it.

Interviewer: Next, the tug situation with rising wind. What was going through your mind?

Participant: With only one tug fast and the second still well out, and gusts running above forecast, I didn't like relying purely on the bow thruster given our draft. When I heard a harbor tug not originally assigned was nearby, I asked for that one instead of waiting on our delayed second tug. It came down to getting extra help sooner rather than sticking with the original assignment.

Interviewer: Was there a moment you considered just waiting it out?

Participant: Briefly, yes. But wind was trending the wrong direction, and I'd rather bring in help early than get caught short later.

Interviewer: And the final approach, with the cross-current pushing you off line?

Participant: By then we had both tugs fast. I chose a graduated correction rather than aborting, applying tug and thruster power progressively and watching how she responded. Aborting and circling was an option, but I judged we had enough room and control authority to correct in place.

Interviewer: What made continuing feel safer than aborting?

Participant: The response to the first pushes of tug power told me we had steerage and margin. If that correction hadn't taken hold quickly, I would have aborted. It ended up tighter to the neighboring berth than I'd like, but within what the berth operator confirmed was workable for mooring.

Interviewer: Looking back at the whole transit, if the echo sounder report had reached you before you left the pilot station instead of mid-transit, would your timing decision have gone differently?

Participant: Possibly. Getting it earlier, alongside the tide gauge lag, together rather than as two separate small inputs, might have pushed me toward the delay option. Mid-transit, each piece came in isolated and didn't feel like enough on its own to override a plan that was already running.

Interviewer: If the second tug had arrived on schedule, would the bend or berthing approach have gone differently?

Participant: The bend, not much, that was really about the barge and speed. The berthing correction might have felt less tight, since we'd have had both tugs earlier rather than picking up the harbor tug as a stand-in.

Interviewer: Is there a point where, in retrospect, you might have weighted new information more heavily?

Participant: Probably the clearance question early on. I leaned on the original figure because it had already been vetted, and I discounted the fresh sounding a bit more than I probably should have.

Interviewer: What would you tell a less experienced pilot to watch for in a transit like this?

Participant: Don't let the plan you walked in with carry more weight just because it came first. New readings, even partial ones, deserve a real second look, not just a quick mental check against what you already believe.}}

Hidden generation specification:
{{"hidden_validation_specification": {
    "hidden_spec_version": "1.0",
    "condition": "biased",
    "exact_occurrence_manifest": [
      {
        "bias": "Anchoring Bias",
        "occurrences": 1,
        "mechanism_constraint": null
      }
    ],
    "target_bias_names": [
      "Anchoring Bias"
    ],
    "requested_occurrence_count_for_each_bias": [
      {
        "bias": "Anchoring Bias",
        "requested_occurrences": 1
      }
    ],
    "planned_instance_ids": [
      {
        "instance_id": "ab_01",
        "bias": "Anchoring Bias"
      }
    ],
    "intended_decision_points": [
      {
        "instance_id": "ab_01",
        "bias": "Anchoring Bias",
        "decision_point": 1
      }
    ],
    "intended_mechanisms": [
      {
        "instance_id": "ab_01",
        "bias": "Anchoring Bias",
        "mechanism": "Pilot's UKC risk estimate anchors on the pre-boarding tide-table figure (1.2m) and is insufficiently adjusted after a fresher, more direct echo sounder report suggests actual clearance near 0.7m.",
        "affected_reasoning_operation": "Quantitative risk-margin updating under new evidence",
        "evidence_source": "Pre-arrival tide table (initial anchor) vs. outbound pilot's real-time echo sounder sweep and updated tide gauge readings (disconfirming/updating evidence)",
        "distinctiveness_requirement": "Not applicable; only one instance requested, so no distinctiveness-from-sibling-instance requirement applies."
      }
    ],
    "intended_strength": [
      {
        "instance_id": "ab_01",
        "bias": "Anchoring Bias",
        "strength": "moderate"
      }
    ],
    "paired_scenario_id": null,
    "counterfactual_variable": {
      "name": null,
      "original_state": null,
      "changed_state": null,
      "variables_to_hold_constant": []
    },
    "scenario_id": "MO_Biased_1",
    "domain_id": "MO",
    "total_requested_occurrences": 1,
    "total_planned_occurrences": 1,
    "allocation_rule_used": "Single occurrence assigned to decision point 1 based on mechanism fit: anchoring bias requires an initial numeric estimate encountered early in the timeline (pre-boarding tide table figure) that persists despite later disconfirming evidence (real-time sounding), which is most narratively realistic at the first decision point rather than later points where the initiating anchor would already be stale or absent.",
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
