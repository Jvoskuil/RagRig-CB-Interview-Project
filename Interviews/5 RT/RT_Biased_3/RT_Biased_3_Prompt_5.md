You are an independent occupational-task analyst. Classify the tasks actually described in the interview below using only the taxonomy and definitions supplied in this prompt.

Do not classify the occupation in general. Classify the work activity and decision episode represented in this interview. Do not infer categories solely from the job title, industry, prestige, assumed education, or stereotypes. Use the interview text as the primary evidence.

Do not assess cognitive biases. Do not use any hidden bias-generation specification. Do not use any prior validator output. This is an independent task-taxonomy annotation.

Return valid JSON only. Do not return prose outside the JSON object.

INTERVIEW
{{Interviewer: Thanks for taking the time. Just to confirm, this conversation is being used to understand how decisions get made during unusual shifts — not to evaluate your performance. Is that okay with you?

Participant: Yeah, that's fine. I've done these debriefs before after incidents, so no problem.

Interviewer: Great. Can you start by telling me your role and what made this particular night shift nonroutine?

Participant: Sure. I'm the yardmaster on the night shift at the hump yard. That night was messy from the start — one of our two hump leads was down for signal maintenance, so we were running everything through a single lead. On top of that, we were short two carmen because of storm callouts, and it was raining hard enough that the retarders weren't behaving predictably on wet rail. We also had an SLA connection window we needed to hit for an outbound customer train, so there was real pressure to keep things moving.

Interviewer: Walk me through how the shift actually unfolded.

Participant: When I came on, the relief briefing was rushed — the prior yardmaster was trying to get out before the worst of the storm hit, so he gave me the switch list verbally: 38 cars, expected to have the cut classified by 2200. That was my starting point for the night. Then the inbound train came in about 40 minutes late, and when we actually counted, it was 41 cars, not 38. The retarders were also cycling slower than normal because of the wet rail. So already things were behind where the paperwork said they'd be.

A while into classification, the hot-box detector flagged one car, GATX 88213, with a temperature reading that was elevated but still within tolerance — borderline, not a clear alarm. That detector's given us false positives before in wet weather. But we'd had a derailment at this yard about three weeks earlier from an overheated bearing on a similar car, and that was fresh in my mind. I made the call to pull the whole eleven-car cut it was sitting in for inspection, not just that one car.

Two carmen inspected it. One found a hairline mark near the knuckle, unrelated to the bearing issue. The other inspected independently and cleared it, no defect found. There was also an old repair entry on that car from two inspection cycles back, already closed out. I ended up treating it as still suspect and asked for a third pass. That ate more time. By the end, we were running about 55 minutes behind, with the SLA window closing in 40. I set that car out and dispatched the rest of the train.

Interviewer: Let's slow down and go through each of those moments. Starting with the ready-time estimate — you had 38 cars and a 2200 target from the handoff, then learned it was 41 cars with slower cycling. What went through your mind?

Participant: Honestly, I kept 2200 as my working target. I nudged it a little in my head, but I didn't sit down and recalculate from the new numbers. Part of it was trust — the relief yardmaster's been doing this longer than me, and his estimates are usually solid. Part of it was just not wanting to move the target this early and cause confusion down the line for the dispatcher.

Interviewer: What alternatives did you consider at that point?

Participant: I could've recalculated from scratch with the actual count and the cycle speed we were seeing. Or radioed the hump conductor for his read on pace before locking anything in. I didn't do either right away — I just carried the number forward.

Interviewer: What would have made you recalculate immediately instead of adjusting slightly?

Participant: Probably if the discrepancy had been bigger — if it'd been 50 cars instead of 41, I think I'd have thrown the original number out completely. Three extra cars didn't feel like enough to abandon the plan.

Interviewer: Now the hot-box alert. The reading was borderline, and you know that detector throws false positives in wet weather. What drove the decision to pull the full eleven-car cut instead of just the flagged car?

Participant: The derailment three weeks back was still sitting with me. That one started exactly this way — a reading that didn't look dramatic at first. I didn't want a repeat, so I went bigger than the book probably called for. Standard procedure would've been to isolate just GATX 88213 for a manual check. I pulled the whole cut.

Interviewer: Did you weigh the detector's false-positive history in that moment?

Participant: I knew about it, yeah. But it didn't carry the same weight as the derailment did. That one's the thing that comes to mind first when a hot-box alert comes in here, even though logically the wet-weather false positives happen a lot more often.

Interviewer: Then you had two conflicting carman reports — one found a hairline mark, the other cleared the car. How did you resolve that?

Participant: I leaned toward Carman A's finding. There was also that old repair entry on the car, even though it was closed out and unrelated to the bearing concern. Between the mark and that history, it felt like enough to keep the car flagged. I asked for a third inspection rather than accepting Carman B's clearance.

Interviewer: What made Carman A's report and the old repair note feel more convincing than Carman B's clearance?

Participant: Looking back, I'm not entirely sure I can justify that cleanly. Carman B followed the same protocol, same timeframe. I think once I already suspected the car, the mark and the repair history just fit what I expected to find. Carman B's "all clear" almost read to me like it needed double-checking, when really it should've carried equal weight.

Interviewer: What would have changed that call — if anything?

Participant: If Carman B's report had come in first, before Carman A's, I might have closed it out right there. Order mattered more than it should have, probably.

Interviewer: Last decision — the SLA deadline was closing in, and the car was still unresolved. What did you decide?

Participant: I set the car out and dispatched the rest of the train. Holding the whole consist for one car wasn't going to help anyone, and the dispatcher confirmed we'd only eat a partial penalty instead of a full one if we released the rest on time. That one felt like a straightforward trade-off, not a hard call.

Interviewer: How did things turn out?

Participant: The third inspection came back clean — no defect on GATX 88213. The train made it out with a partial penalty instead of the full one.

Interviewer: If the derailment three weeks earlier had never happened, do you think the hot-box call goes differently?

Participant: Probably, yeah. I think I isolate just the one car and keep moving.

Interviewer: And if you ran this same shift again tomorrow, what would you do differently?

Participant: I'd probably push back harder on the initial time estimate instead of just carrying it forward, and I'd try to look at both carmen's reports side by side instead of one at a time. Other than that, given what I knew in the moment, I'd probably land in a similar place.
}}

OPTIONAL METADATA
The following metadata may help identify the setting but must not determine the classification:
{
  "interview_id": "{{RT_Biased_3}}",
  "occupational_domain": "{{Rail Transportation}}",
  "role": "{{Yardmaster / Rail Yard Supervisor}}"
}

TAXONOMY

This taxonomy distinguishes three aspects of work:

1. Task content: what the worker does.
2. Work methods: how the work is organised.
3. Tools: what machinery or technology is used.

Classify only categories supported by observable evidence. Multiple categories may be present. Select one primary content category and any defensible secondary categories. Do not force a category when evidence is insufficient.

A. TASK CONTENT — WHAT THE WORKER DOES

A1. PHYSICAL TASKS

A1.1 Strength
The worker exerts physical force or effort, handles loads, pushes, pulls, lifts, carries, restrains, or uses bodily strength as a meaningful part of the task.

A1.2 Dexterity
The worker performs precise, coordinated, or fine-grained physical movements, manipulates objects or instruments, assembles, repairs, operates controls manually, or uses hand-eye coordination as a meaningful part of the task.

A1.3 Navigation
The worker physically moves through or around an environment, routes people or objects, or maintains orientation and position in a spatial setting as a meaningful part of the task.

A2. INTELLECTUAL TASKS

A2.1 Uncodified visual or auditory information processing
The worker interprets visual, auditory, or other perceptual information that is difficult to reduce to a fully explicit rule, including recognizing patterns, anomalies, conditions, or signals.

A2.2 Literacy
The worker reads, writes, composes, edits, interprets, or communicates using written language as a meaningful part of the task.

A2.3 Numeracy
The worker calculates, quantifies, estimates, compares numerical values, interprets numerical information, or reasons about proportions, probabilities, measurements, or financial quantities.

A2.4 Information search, retrieval, gathering, and evaluation
The worker seeks, retrieves, gathers, compares, verifies, filters, or evaluates information from records, people, systems, documents, observations, or other sources.

A2.5 Conceptualisation, learning, and abstraction
The worker forms concepts, learns from experience, generalises, diagnoses, explains relationships, builds mental models, applies abstract principles, or understands a system beyond the immediate facts.

A2.6 Creativity, planning, and resolution
The worker generates, designs, or adapts solutions to a problem; develops and compares possible courses of action; plans their implementation; anticipates dependencies or consequences; or resolves a novel, non-routine situation by combining information in an original or context-sensitive way. Planning counts when it involves organising a sequence of actions, timing, resources, contingencies, or dependencies toward a goal—not merely selecting or carrying out a routine next step.

A3. SOCIAL TASKS

A3.1 Serving and attending
The worker responds to another person's immediate needs, provides a service, receives requests, attends to a customer, patient, client, user, colleague, or member of the public, or manages an interaction aimed at assistance.

A3.2 Teaching, training, and coaching
The worker explains, instructs, demonstrates, trains, develops, mentors, or coaches another person.

A3.3 Selling and influencing
The worker persuades, negotiates, recommends, markets, advocates, manages expectations, seeks agreement, or attempts to influence another person's decision or behaviour.

A3.4 Managing and coordinating
The worker allocates work, coordinates people or activities, manages dependencies, sets priorities, resolves organisational conflicts, supervises, or aligns multiple stakeholders.

A3.5 Caring
The worker provides emotional, personal, health-related, protective, or welfare-oriented support in which attention to another person's condition or well-being is central.

B. WORK METHODS — HOW THE WORK IS ORGANISED

B1. AUTONOMY

B1.1 Latitude
The worker has discretion over objectives, priorities, timing, sequence, methods, or decisions. Classify low, moderate, or high only when the interview provides evidence about the worker's discretion.

B1.2 Control and monitoring
The worker's work is supervised, measured, audited, monitored, reviewed, or constrained by another person, policy, procedure, system, target, or formal approval process. Classify low, moderate, or high based on the strength and frequency of such control.

B2. TEAMWORK

Direct collaboration with co-workers or other actors to accomplish a shared task, exchange information, coordinate actions, hand off work, or reach a joint decision. Classify low, moderate, or high based on the worker's dependence on collaboration in the described episode.

B3. ROUTINE

B3.1 Repetitiveness
The same or highly similar actions, inputs, decisions, or outputs recur frequently.

B3.2 Standardisation
The task follows prescribed procedures, scripts, checklists, templates, rules, or consistent sequences.

B3.3 Certainty and response to unforeseen situations
Certainty refers to how predictable the relevant inputs, conditions, and consequences are. Response to unforeseen situations refers to how much the worker must handle exceptions, novelty, ambiguity, disruptions, or unexpected developments.

For this dimension, report both:
- certainty: low, moderate, high, or not_observable;
- unforeseen_response_requirement: low, moderate, high, or not_observable.

C. TOOLS — MACHINERY AND TECHNOLOGY USED

C1. Non-digital machinery
Analog or mechanical devices and machinery without meaningful digital control, sensing, computing, or networked information processing.

C2. Digitally enabled machinery
Machinery or equipment using digital control, sensors, software, automation, robotics, or networked digital systems. Classify the most specific supported subtype:

C2.1 Autonomous machinery or robots
The equipment performs meaningful operations with limited direct human control after initiation.

C2.2 Non-autonomous digitally enabled machinery
The worker directly operates or controls digitally enabled physical equipment.

C2.3 Basic ICT
Routine use of computers, smartphones, email, office software, standard databases, or basic digital communication and information systems.

C2.4 Advanced ICT or programming
Programming, data analysis, modelling, system configuration, advanced computational tools, or complex software-based information processing.

C2.5 Specialised ICT
Special-purpose professional software or digital systems used for a particular occupation or work process, where the system is more specialised than ordinary office or communication software.

C2.6 Other digitally enabled tools
Digital tools that clearly matter to the work but do not fit the preceding subcategories.

CLASSIFICATION RULES

1. Classify the described episode, not the entire occupation.
2. A category must have textual evidence. Do not infer it from the role title.
3. Assign one primary task-content category: the category most central to the operational objective and decision episode.
4. Assign secondary content categories only when they are substantively involved, not merely mentioned.
5. Content categories may come from different families. For example, an interview may contain intellectual information evaluation as primary content and social influencing as secondary content.
6. Methods and tools are separate from content. Do not label a task intellectual merely because it uses a computer, or social merely because other people are mentioned.
7. Distinguish information search/evaluation from conceptualisation: the former concerns obtaining and assessing information; the latter concerns forming models, diagnoses, abstractions, or generalisations.
8. Distinguish creativity/resolution from ordinary choice: creativity requires adaptation, novel solution generation, or non-routine problem resolution.
9. Distinguish serving/attending from selling/influencing: assistance and responsiveness are not necessarily persuasion or negotiation.
10. Distinguish managing/coordinating from teamwork: teamwork is collaboration; managing/coordinating involves organising dependencies, priorities, people, or activities.
11. Do not infer strength, dexterity, navigation, or caring without direct evidence.
12. For autonomy, monitoring, teamwork, repetitiveness, standardisation, and certainty, use `not_observable` when the interview does not support a reliable level.
13. Multiple tools may be present. Record only tools that play a meaningful role in the episode.
14. If a classification is ambiguous, record the competing categories and explain the ambiguity.
15. Do not treat the participant's cognitive bias, if any, as a task category.
16. Do not use external web research. The supplied taxonomy is the authority for this annotation.

EVIDENCE REQUIREMENTS

For every assigned content category, method level, and tool category, provide:
- a short quotation or faithful text span;
- the location, such as opening, timeline, decision point, or participant turn;
- an explanation of why the evidence supports the category;
- confidence from 0 to 100.

For categories not observed but potentially plausible, do not list them as present. Place them in `not_observed_or_insufficient` only if doing so helps explain a material ambiguity.

COVERAGE STATUS

Set `coverage_status` as follows:
- `complete`: the interview contains enough evidence to classify content, methods, and tools;
- `partial`: at least one major dimension is not observable;
- `ambiguous`: competing categories cannot be resolved from the text;
- `insufficient`: the interview does not contain a sufficiently identifiable work episode.

OUTPUT SCHEMA

{
  "taxonomy_version": "Fernandez-Macias_Bisello_2021",
  "interview_id": "...",
  "occupational_domain": "...",
  "role": "...",
  "classification_confidence": 0,
  "coverage_status": "complete|partial|ambiguous|insufficient",
  "content": {
    "primary_category": {
      "family": "physical|intellectual|social|unknown",
      "subcategory": "...",
      "confidence": 0,
      "evidence": [
        {
          "location": "...",
          "quote": "...",
          "explanation": "..."
        }
      ]
    },
    "secondary_categories": [
      {
        "family": "physical|intellectual|social",
        "subcategory": "...",
        "confidence": 0,
        "evidence": [
          {
            "location": "...",
            "quote": "...",
            "explanation": "..."
          }
        ]
      }
    ],
    "all_observed_categories": [],
    "not_observed_or_insufficient": [],
    "ambiguities": []
  },
  "methods": {
    "autonomy": {
      "latitude": {
        "level": "low|moderate|high|not_observable",
        "confidence": 0,
        "evidence": []
      },
      "control_monitoring": {
        "level": "low|moderate|high|not_observable",
        "confidence": 0,
        "evidence": []
      }
    },
    "teamwork": {
      "level": "low|moderate|high|not_observable",
      "confidence": 0,
      "evidence": []
    },
    "routine": {
      "repetitiveness": {
        "level": "low|moderate|high|not_observable",
        "confidence": 0,
        "evidence": []
      },
      "standardisation": {
        "level": "low|moderate|high|not_observable",
        "confidence": 0,
        "evidence": []
      },
      "certainty": {
        "level": "low|moderate|high|not_observable",
        "confidence": 0,
        "evidence": []
      },
      "unforeseen_response_requirement": {
        "level": "low|moderate|high|not_observable",
        "confidence": 0,
        "evidence": []
      }
    }
  },
  "tools": [
    {
      "category": "non_digital_machinery|autonomous_machinery_or_robot|non_autonomous_digitally_enabled_machinery|basic_ict|advanced_ict_or_programming|specialised_ict|other_digitally_enabled_tool",
      "role_in_task": "...",
      "confidence": 0,
      "evidence": [
        {
          "location": "...",
          "quote": "...",
          "explanation": "..."
        }
      ]
    }
  ],
  "task_anchors": [
    {
      "location": "...",
      "task_description": "...",
      "taxonomy_labels": [],
      "confidence": 0
    }
  ],
  "decision_point_task_map": [
    {
      "decision_point": 1,
      "dominant_task_categories": [],
      "methods_relevant": [],
      "tools_relevant": [],
      "evidence": []
    }
  ],
  "classification_quality": {
    "occupation_inference_risk": "low|moderate|high",
    "stereotype_risk": "low|moderate|high",
    "taxonomy_ambiguity": "low|moderate|high",
    "missing_evidence": [],
    "manual_review_recommended": false
  },
  "coverage_flags": {
    "physical_content_observed": false,
    "intellectual_content_observed": false,
    "social_content_observed": false,
    "methods_observed": false,
    "tools_observed": false,
    "all_major_dimensions_observable": false
  },
  "recommended_dataset_action": "retain|retain_with_low_confidence|sample_more|manual_review|exclude"
}

FINAL CHECK

Before returning JSON, verify that:
- Every present category has textual evidence.
- The primary category is central to the episode, not merely the most frequently mentioned word.
- Secondary categories are substantively involved.
- Method and tool labels are supported independently from content labels.
- `not_observable` is used where appropriate.
- Confidence reflects evidence quality, not certainty from the occupation or role.
- No cognitive-bias labels appear as task categories.
- No external sources or unstated occupational assumptions were used.
- The result is valid JSON and contains no prose outside the JSON object.
