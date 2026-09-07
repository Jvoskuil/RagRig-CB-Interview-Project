You are an independent benchmark auditor specializing in cognitive task analysis, naturalistic decision-making, cognitive-bias annotation, and causal reasoning.

Your task is to audit a completed CTA interview against its hidden generation requirements. You must identify whether the requested cognitive-bias occurrences are actually supported by the text, identify additional candidate biases, and provide revision guidance that accounts for any missing, weak, merged, or accidental occurrences.

Do not assume the generator followed the specification. Do not infer bias merely from a bad outcome, uncertainty, experience, speed, disagreement, use of a heuristic, or an incorrect decision. Require a specific reasoning mechanism and textual evidence. Distinguish cognitive bias from justified expertise, valid risk management, missing information, organizational constraints, hindsight, ordinary error, and an unfavorable outcome.

INPUTS

Interview:
{{Interviewer: Thanks for sitting down with me. This is a routine cognitive task analysis interview — I want to understand how you actually worked through the feedwater heater trend during the ascension test, not evaluate your performance. It'll be de-identified for training and procedure review. Okay with you?

Participant: Sure, no problem.

Interviewer: Let's start broad. Can you walk me through what you were doing when you first noticed the temperature trend?

Participant: We were about three hours into the ascension test, sitting around 90 percent power, working toward a dispatch commitment at end of shift. I was doing my normal rounds on the trend recorders and caught that heater 1B outlet temperature had come up about three degrees over maybe twenty minutes. Train 1A was steady, no alarm, nothing outside our Tech Spec limit. My first thought was that it looked like the calibration deviation we'd had on that sensor last cycle — but I didn't want to just assume that, because I didn't actually remember the details of that event well enough to say it matched.

Interviewer: What was going through your head in terms of goals and pressures?

Participant: Getting to a hundred percent within the dispatch window, with about two hours of slack at that point. I wasn't rushed, but I was aware of the clock. At the same time, I didn't want to just label the drift and move on without checking whether it actually fit.

Interviewer: Let's reconstruct the timeline before we get into the decisions. What happened after you noticed the drift?

Participant: I pulled the closed-out fault report from last cycle to compare against what I was seeing. About fifteen minutes later the trend was still creeping, still shallow. Then, maybe forty minutes in total, a maintenance tech on an unrelated walkdown radioed that the 1B heater shell felt warmer than usual on his infrared scanner. I asked him to take a second reading. Shortly after that the trend recorder started flattening as we came up on the final ascension step.

Interviewer: Okay, let's go through this decision by decision. First: when you noticed the drift, what alternatives did you actually weigh?

Participant: Either treat it as the same calibration issue from last cycle, or treat it as an open question and get an independent check before assuming anything. I ended up somewhere in between — I pulled up the old fault log to see how closely the pattern matched.

Interviewer: What did that comparison tell you?

Participant: Honestly, it was partial. The timing and the size of the rise were similar. But the rate of onset — how fast it ramped at the very start — wasn't something the old log tracked consistently, so I couldn't really say whether that piece matched or not. I logged it as a probable but unconfirmed recurrence, which felt like the most honest way to write it up given what I had.

Interviewer: Did that ambiguity bother you?

Participant: A little. I would've liked a cleaner match one way or the other. But I didn't think it was worth pulling I&C off other work for a value that was still well inside limits.

Interviewer: Second decision point. The trend kept climbing slightly, and you had a discretionary hold point available to brief the STA before continuing. What went into that call?

Participant: That one I thought about for a bit. The STA was right there. Part of me thought, with the comparison being inconclusive, maybe I should just brief him now and let him weigh in. But I also didn't have much to brief him with yet — just an unconfirmed resemblance to an old fault. So I decided to keep trending for a defined stretch, I think I gave it another fifteen minutes in my head, with the idea that either the data would firm up enough to justify a briefing, or it would settle down and not need one.

Interviewer: Was the schedule part of that?

Participant: A bit, sure. But it wasn't the deciding factor — I genuinely thought waiting a short, bounded amount of time would give me better information either way.

Interviewer: Right after that, the technician's infrared call came in. How did you weigh that against the trend recorder?

Participant: That's the one where I felt most uncertain. His reading suggested localized heating, which could point to fouling, but it could also just be a warm spot from wherever that drifted sensor sits — I honestly wasn't sure which. The trend recorder showed a smooth rise, which didn't obviously rule either explanation in or out. Rather than pick one, I asked him to take a second reading and tell me what the scan conditions were, since I wanted something to compare against rather than deciding off one data point.

Interviewer: What came back?

Participant: A similar but not identical reading. He mentioned the scan angle and surface conditions weren't perfectly controlled either time, so even the comparison didn't fully resolve it. At that point I had two data sources that each pointed somewhere, but neither one closed the question.

Interviewer: How did you feel about leaving it open like that?

Participant: A little uneasy, if I'm honest. Usually you want a cleaner answer before you keep moving. But nothing in front of me demanded an immediate call, so I didn't force one.

Interviewer: Last decision point. As you approached the final step to a hundred percent, the trend had started flattening. What led you to proceed?

Participant: The flattening helped, but I didn't treat it as proof the earlier question was settled. I still had that inconclusive infrared comparison sitting unresolved. What I did was log it as an open item — wrote it up for the oncoming shift and put in a request for maintenance to follow up — and then proceeded with the step, since there wasn't a procedural or Tech Spec basis to hold at that point.

Interviewer: Did you consider holding anyway, just to close out the comparison first?

Participant: I did think about it. It came down to whether an unconfirmed field reading, with no limit approached, was enough reason to interrupt a scheduled step. I decided documenting it and handing it off was the more defensible path, but I won't pretend that was the only reasonable call.

Interviewer: What single piece of information would have changed that decision?

Participant: If the repeat scan had come back clean and consistent — clearly showing localized heating with good scan conditions both times — I think I would've held and gotten the STA involved before the final step.

Interviewer: And if the trend had kept climbing instead of flattening?

Participant: Then the flattening wouldn't have been there to lean on, and I think the open item alone would've been enough to justify a hold.

Interviewer: Looking back, is there a point where you wish you'd had better information, even if the decision felt reasonable at the time?

Participant: The infrared piece, definitely. I'd have liked a way to get a controlled comparison reading rather than two scans taken under different conditions. That's really where most of my uncertainty sat the whole time.

Interviewer: One last thing for the record, unrelated to how you reasoned through it at the time — a maintenance work order filed after your shift ended found early-stage fouling on the 1B heater, separate from the old calibration issue. That wasn't information you had available during the ascension, so I'm just noting it for the file.

Participant: Understood — that's good to have documented either way.

Interviewer: That's really helpful, thank you.}}

Hidden generation specification:
{{"hidden_validation_specification": {
    "hidden_spec_version": "1.0",
    "condition": "ambiguous_control",
    "exact_occurrence_manifest": [
      {
        "bias": "Confirmation Bias",
        "occurrences": 0,
        "mechanism_constraint": "No intended instance; operator must explicitly treat the prior-calibration match as partial and unconfirmed rather than selectively accepted."
      },
      {
        "bias": "Imperfect Rationality",
        "occurrences": 0,
        "mechanism_constraint": "No intended instance; the escalation decision at decision point 2 must reflect a reasoned, time-bounded data-gathering choice rather than an informal, non-systematic satisficing judgment."
      },
      {
        "bias": "Salience Bias",
        "occurrences": 0,
        "mechanism_constraint": "No intended instance; evidence weighting at decision point 3 must not be driven by visual prominence of the trend display over the verbal field report."
      },
      {
        "bias": "Similarity Bias",
        "occurrences": 0,
        "mechanism_constraint": "No intended instance; source-credibility reasoning must not discount the technician based on role dissimilarity or shared operator identity."
      },
      {
        "bias": "Bounded Rationality",
        "occurrences": 0,
        "mechanism_constraint": "No intended instance; the final decision must explicitly document the unresolved item rather than proceeding on a restricted information set without acknowledgment."
      }
    ],
    "target_bias_names": [
      "Confirmation Bias",
      "Imperfect Rationality",
      "Salience Bias",
      "Similarity Bias",
      "Bounded Rationality"
    ],
    "requested_occurrence_count_for_each_bias": [
      { "bias": "Confirmation Bias", "requested_occurrences": 0 },
      { "bias": "Imperfect Rationality", "requested_occurrences": 0 },
      { "bias": "Salience Bias", "requested_occurrences": 0 },
      { "bias": "Similarity Bias", "requested_occurrences": 0 },
      { "bias": "Bounded Rationality", "requested_occurrences": 0 }
    ],
    "planned_instance_ids": [],
    "intended_decision_points": [],
    "intended_mechanisms": [],
    "intended_strength": [],
    "paired_scenario_id": "NP_Biased_6",
    "counterfactual_variable": {
      "name": null,
      "original_state": null,
      "changed_state": null,
      "variables_to_hold_constant": []
    },
    "scenario_id": "NP_Ambigious_6",
    "domain_id": "NP",
    "total_requested_occurrences": 0,
    "total_planned_occurrences": 0,
    "allocation_rule_used": "Not applicable — this is an ambiguous_control scenario with a zero-occurrence manifest for all five target biases named in the paired biased scenario (NP_Biased_6). No allocation across decision points was performed since no bias instances are intentionally planned. Instead, each of the four decision points (matched one-to-one to the biased scenario's decision points) was redesigned so that the specific reasoning pattern that constituted each bias instance in NP_Biased_6 is replaced with an explicitly underdetermined, dual-hypothesis, or corroboration-seeking judgment that resists classification as any named bias while remaining a defensible point of expert disagreement.",
    "control_zero_bias_requirement": true,
    "variables_to_hold_constant": [
      "Occupational domain and role (PWR licensed Reactor Operator)",
      "Setting and operational objective (power ascension test toward 100% power within a dispatch window)",
      "Four-decision-point structure and their sequential relationship to the same underlying incident (initial drift interpretation, escalation/hold-point choice, weighing technician field report, final ascension go-decision)",
      "Core factual anchors (heater 1B outlet temperature drift, redundant train 1A stability, prior-cycle calibration history, technician infrared report, flattening trend, post-hoc work order revealing fouling)",
      "Stakeholders, vocabulary level, difficulty, and overall emotional tone",
      "Ambiguous, non-diagnostic consequence structure"
    ],
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
