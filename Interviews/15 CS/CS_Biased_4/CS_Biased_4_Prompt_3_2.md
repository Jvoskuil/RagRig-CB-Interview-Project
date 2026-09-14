You are an independent benchmark auditor specializing in cognitive task analysis, naturalistic decision-making, cognitive-bias annotation, and causal reasoning.

Your task is to audit a completed CTA interview against its hidden generation requirements. You must identify whether the requested cognitive-bias occurrences are actually supported by the text, identify additional candidate biases, and provide revision guidance that accounts for any missing, weak, merged, or accidental occurrences.

Do not assume the generator followed the specification. Do not infer bias merely from a bad outcome, uncertainty, experience, speed, disagreement, use of a heuristic, or an incorrect decision. Require a specific reasoning mechanism and textual evidence. Distinguish cognitive bias from justified expertise, valid risk management, missing information, organizational constraints, hindsight, ordinary error, and an unfavorable outcome.

INPUTS

Interview:
{{Interviewer: Thanks for making time for this. Just to confirm, this is a debrief on the finance-server incident from a few weeks back, it's being recorded for internal process review, and you're free to skip anything you're not comfortable detailing. Sound okay?

Participant: Yeah, that's fine. Happy to walk through it.

Interviewer: Great. Can you start with your role that night and what you were responsible for?

Participant: I'm the on-call DFIR analyst, so I was solo overnight — it was a Sunday going into quarter-end close, which matters because that file server is basically untouchable without a director sign-off during that window. My senior lead was reachable on chat but not really available to jump on calls. So triage, scoping, containment, remediation — all of it was on me until morning.

Interviewer: Walk me through what happened.

Participant: Around 1 a.m. I got a SIEM alert for an off-hours process spawning a staging directory on the finance file server. Honestly, my first reaction was "here we go again" — I'd closed six tickets in the past three weeks that all started exactly like this, staging directory, off-hours process, and every one of those turned out to be ransomware-precursor activity. So the pattern was extremely familiar. There was also a quieter log line underneath it — a single authenticated session copying files in small batches out to an external cloud storage endpoint over a few hours. But no ransom note, no encryption, no mass renaming, so nothing screaming "this is it" yet.

Interviewer: How did you weigh those two signals?

Participant: I opened the ticket under the ransomware-precursor category. That staging-directory behavior is just what I've been seeing constantly lately, so it felt like the obvious bucket. The batch-copy line registered, but it felt secondary — slower, quieter, didn't match the urgency of what I'd been dealing with recently. In hindsight, when I actually looked at what was in those batches later, they were finance close spreadsheets, not the file types those recent ransomware precursors usually go after. And the external endpoint had no ransomware C2 history in threat intel. But at 1 a.m. I went with the category that matched what I'd just spent three weeks fighting.

Interviewer: Let's reconstruct the rest of the timeline. What came next?

Participant: Within the first ten minutes I set the ticket scope at 3 endpoints, based on the initial SIEM correlation window. About 40 minutes later, an EDR sweep came back showing authentication artifacts touching 9 more hosts — lower confidence, but there. Around then, the finance director started pinging for an update ahead of the 6 a.m. close deadline, so there was real pressure to say something concrete. I decided the 9-host signal was probably noise from that same original window and kept the scope close to 3. A later, fuller sweep ended up confirming lateral movement had actually touched 7 of those 9 hosts.

Interviewer: What made you treat that second signal as noise rather than expansion?

Participant: Partly the confidence rating on it, it wasn't a clean hit. But I'll be honest, I'd already told the director "3 hosts, contained," and adjusting that number upward with only 40 minutes of new low-confidence data felt like it'd cause more panic than it was worth before I had something firmer. So I stuck close to the original number and figured I'd revisit if something else lit up.

Interviewer: Move on to containment. What did you actually do?

Participant: I ran my own PowerShell isolation and log-collection script — I wrote that thing two years ago, and it's worked well on plenty of past incidents. My lead pinged me suggesting I use the EDR platform's one-click network isolation feature instead, said it'd be faster and less error-prone, especially now that we were looking at more hosts. That feature's only been live about three months and I've used it maybe twice.

Interviewer: What went into sticking with your script over that suggestion?

Participant: I know exactly how my script behaves, what it logs, where it's failed before and how I fixed that. The EDR feature, I just don't have the same feel for it yet. My lead's point about the host count was fair, and I didn't really have anything showing my script would hold up better at that scale — I just wanted to give it the benefit of the doubt because it's mine, I built it, I've kept it running this long, and it felt like it deserved the first shot before I'd fall back on the platform's version. So I kept running my script across the hosts, and only tried the EDR isolation on a couple of them after my lead brought it up a second time. In the end, isolating everything with my script took a good 90 minutes longer than the EDR route probably would have at that host count. It wasn't built for a scope that size, honestly, it's more of a one-or-two-host tool.

Interviewer: Did the delay change your view of which tool to use for the rest of containment?

Participant: Not really in the moment — I was mid-process and switching tools halfway through felt like it'd create more inconsistency in the logs than just finishing what I started.

Interviewer: Let's talk remediation. What options were in front of you?

Participant: The ticketing system's playbook for that category gave me exactly two actions: reset affected credentials, and reimage the affected endpoints. Neither one said anything about preserving a forensic image of the staging directory first, or checking whether that external cloud endpoint triggered any legal notification requirement.

Interviewer: Did you consider anything outside those two?

Participant: There's an escalation path to our external IR retainer that could've given a broader set of options, but it's not built into the playbook flow, you have to go looking for it separately. I didn't go down that road. I just worked through the two actions on the screen since that's what the category pointed me to.

Interviewer: Was there a point where that choice got revisited?

Participant: Two days later, compliance asked whether we'd preserved a forensic image of the staging directory before reimaging, since that affects whether this gets reported as a data exposure. That's when it became clear the playbook's two options hadn't covered that angle at all.

Interviewer: Looking back, if the staging-directory pattern hadn't been so common in your recent caseload, do you think you'd have categorized this the same way?

Participant: Probably not as quickly. If I hadn't just closed six of those tickets, I think the batch-copy line would've stood out more on its own merits instead of getting overshadowed.

Interviewer: If the EDR isolation feature had been the tool you knew best instead of your script, would containment have gone differently?

Participant: Almost certainly faster. I think I'd have reached for it first instead of treating it as the backup option.

Interviewer: And if the playbook screen had shown four remediation options instead of two?

Participant: Hard to say for sure, but I'd like to think the forensic-preservation piece would've been visible instead of something I only heard about after compliance asked.

Interviewer: Last question — what's one point where more time or information would have changed your approach?

Participant: Probably right after that second EDR sweep. If I'd had another 20 minutes before the director needed an answer, I think I'd have pushed the scope number instead of holding it, and maybe things downstream would've looked a bit different.
}}

Hidden generation specification:
{{"hidden_validation_specification": {
    "hidden_spec_version": "1.0",
    "condition": "biased",
    "exact_occurrence_manifest": [
      {
        "bias": "Availability Frequency",
        "occurrences": 1,
        "mechanism_constraint": "ease of recall of one category over that of another leading to the selection of that category even if the other category is a better fit."
      },
      {
        "bias": "Adjustment and anchoring",
        "occurrences": 1,
        "mechanism_constraint": null
      },
      {
        "bias": "Endowment",
        "occurrences": 1,
        "mechanism_constraint": null
      },
      {
        "bias": "Exposure to limited alternatives",
        "occurrences": 1,
        "mechanism_constraint": null
      }
    ],
    "target_bias_names": [
      "Availability Frequency",
      "Adjustment and anchoring",
      "Endowment",
      "Exposure to limited alternatives"
    ],
    "requested_occurrence_count_for_each_bias": [
      { "bias": "Availability Frequency", "requested_occurrences": 1 },
      { "bias": "Adjustment and anchoring", "requested_occurrences": 1 },
      { "bias": "Endowment", "requested_occurrences": 1 },
      { "bias": "Exposure to limited alternatives", "requested_occurrences": 1 }
    ],
    "planned_instance_ids": [
      { "instance_id": "cb_01", "bias": "Availability Frequency" },
      { "instance_id": "cb_02", "bias": "Adjustment and anchoring" },
      { "instance_id": "cb_03", "bias": "Endowment" },
      { "instance_id": "cb_04", "bias": "Exposure to limited alternatives" }
    ],
    "intended_decision_points": [
      { "instance_id": "cb_01", "bias": "Availability Frequency", "decision_point": 1 },
      { "instance_id": "cb_02", "bias": "Adjustment and anchoring", "decision_point": 2 },
      { "instance_id": "cb_03", "bias": "Endowment", "decision_point": 3 },
      { "instance_id": "cb_04", "bias": "Exposure to limited alternatives", "decision_point": 4 }
    ],
    "intended_mechanisms": [
      {
        "instance_id": "cb_01",
        "bias": "Availability Frequency",
        "mechanism": "Ease of recall of the frequently-seen ransomware-precursor category leads to its selection over the better-fitting data-exfiltration category.",
        "affected_reasoning_operation": "Categorization of the anomaly under a playbook category",
        "evidence_source": "Log pattern comparison: staging-directory frequency vs. batch-copy exfiltration signal",
        "distinctiveness_requirement": "Must be tied specifically to categorization at DP1 based on recall frequency of a category, not to scoping, tool choice, or remediation option selection."
      },
      {
        "instance_id": "cb_02",
        "bias": "Adjustment and anchoring",
        "mechanism": "Initial 3-endpoint scope estimate anchors subsequent scope judgment, causing insufficient adjustment despite new evidence of 9 additional hosts.",
        "affected_reasoning_operation": "Scope revision under new EDR evidence",
        "evidence_source": "Comparison of initial correlation-window scope vs. later EDR sweep results",
        "distinctiveness_requirement": "Must be tied specifically to numeric/scope-estimate revision at DP2, distinct from the categorical judgment in DP1 or tool/option choices in DP3-DP4."
      },
      {
        "instance_id": "cb_03",
        "bias": "Endowment",
        "mechanism": "Overvaluation of the self-built containment script relative to the platform's isolation feature, driven by ownership rather than a stated performance comparison.",
        "affected_reasoning_operation": "Containment tool/method selection",
        "evidence_source": "Comparison of self-built script usage history vs. colleague-recommended EDR feature and observed containment delay",
        "distinctiveness_requirement": "Must be tied specifically to tool ownership/attachment at DP3, distinct from category or scope judgments and from the option-set framing in DP4."
      },
      {
        "instance_id": "cb_04",
        "bias": "Exposure to limited alternatives",
        "mechanism": "Remediation decision is constrained to the two options displayed on the playbook screen, with no independent search for additional remediation paths.",
        "affected_reasoning_operation": "Generation/selection of remediation alternatives",
        "evidence_source": "Playbook screen option set vs. unexplored escalation path to retainer vendor and forensic-preservation option",
        "distinctiveness_requirement": "Must be tied specifically to the narrowness of the presented option set at DP4, distinct from the tool attachment reasoning in DP3."
      }
    ],
    "intended_strength": [
      { "instance_id": "cb_01", "bias": "Availability Frequency", "strength": "subtle" },
      { "instance_id": "cb_02", "bias": "Adjustment and anchoring", "strength": "subtle" },
      { "instance_id": "cb_03", "bias": "Endowment", "strength": "subtle" },
      { "instance_id": "cb_04", "bias": "Exposure to limited alternatives", "strength": "subtle" }
    ],
    "paired_scenario_id": null,
    "counterfactual_variable": {
      "name": null,
      "original_state": null,
      "changed_state": null,
      "variables_to_hold_constant": []
    },
    "scenario_id": "CS_Biased_4",
    "domain_id": "CS",
    "total_requested_occurrences": 4,
    "total_planned_occurrences": 4,
    "allocation_rule_used": "One occurrence per named bias, each assigned to a distinct decision point (DP1-DP4) selected for mechanism fit and narrative realism; no bias shares a decision point since each has only one requested occurrence.",
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
