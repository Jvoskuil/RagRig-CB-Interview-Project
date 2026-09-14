You are an independent occupational-task analyst. Classify the tasks actually described in the interview below using only the taxonomy and definitions supplied in this prompt.

Do not classify the occupation in general. Classify the work activity and decision episode represented in this interview. Do not infer categories solely from the job title, industry, prestige, assumed education, or stereotypes. Use the interview text as the primary evidence.

Do not assess cognitive biases. Do not use any hidden bias-generation specification. Do not use any prior validator output. This is an independent task-taxonomy annotation.

Return valid JSON only. Do not return prose outside the JSON object.

INTERVIEW
{{Interviewer: Thanks for taking the time. This is for an internal case-study review, and it stays within that context. Comfortable proceeding?

Participant: Yes, that's fine.

Interviewer: Can you start with your role and what you're responsible for?

Participant: I'm CISO at NorthGate Financial. We process card and ACH payments, about 450 employees. I own the security program broadly — SOC, vendor risk, incident response, board reporting, budget. We run lean, six people in the SOC, so I'm closer to the operational detail than a CISO at a bigger shop would be.

Interviewer: Walk me through the incident you'd like to discuss, and what you were trying to accomplish.

Participant: This was about ten days ago. We had an intrusion land right in the middle of our annual vendor-renewal and budget cycle, which made everything more complicated than it needed to be. The goal was simple to state — contain whatever was happening without disrupting payments, and still get the vendor contract and budget numbers turned in on schedule. Those two threads kept crossing. It started with our SIEM flagging an anomalous login on a jump server one of our payments engineers uses — off-hours, from a network range we hadn't seen on that account. The SIEM's default model scored it Medium. That model doesn't factor in whether the account is privileged, it just looks at behavioral deviation. I saw Medium and it matched my gut read, so we moved from there. We had one analyst on triage that day since someone was out on leave. There'd also been a second, lower-priority alert nine minutes earlier on an adjacent auth server — it didn't get opened right away; the jump server was the concrete thing in front of us.

Interviewer: What happened after that?

Participant: The analyst worked the jump server specifically — process history, recent auth events. A few hours later, once we circled back through the queue, we noticed the earlier auth-server alert shared the same source IP range. That's when it stopped looking like an isolated event and started looking like lateral movement toward the payments database segment.

Interviewer: Take me through the sequence in order — what did you know, and when?

Participant: Morning: the jump-server alert and its Medium score. Midday: the IP overlap with the auth-server alert. That afternoon, the vendor renewal deadline landed on top of it — five business days before auto-renewal on our EDR and threat-intel contract, incident or no incident. That evening, once lateral movement was confirmed, my team wrote a monitoring script overnight for the compromised account, and I had a call with our CFO about containment options. Two days later, with things stabilized, I had to submit a remediation budget figure to the board.

Interviewer: Let's slow down on that first call — the triage decision. What stood out to you, and was anything competing for attention?

Participant: The account being privileged stood out, honestly. But the Medium score was already sitting there, and normally that's a reasonable starting point for how fast we move. I didn't loop the second alert in as something to check in parallel — the analyst was stretched thin, and the jump server was the concrete lead.

Interviewer: What alternatives did you consider, and what tipped the decision?

Participant: Escalating both alerts jointly right away, or running a correlation sweep across that time window before locking in severity. I did neither. The score gave me a number to build the response around, and given the staffing gap, narrowing the analyst's focus felt efficient rather than risky in the moment.

Interviewer: How confident were you in that call?

Participant: Reasonably, not fully. I knew the score doesn't weigh account privilege. I just didn't push past it that morning.

Interviewer: Moving to the vendor decision — walk me through that.

Participant: Six years with this EDR and threat-intel vendor. My team built a lot of custom detection logic and dashboards on their platform. Procurement had actually flagged three other vendors with comparable bundles this cycle, including transition support that looked broadly workable, but I didn't work through that list closely. A couple of peer CISOs mentioned they use either this vendor or the closest competitor, so my real comparison ended up being just those two.

Interviewer: What made you settle on renewal?

Participant: Mostly the investment already sitting in our detection rules and dashboards. Rebuilding that on a new platform is real time and real exposure, especially mid-incident. If I'm honest, those dashboards just felt more valuable because they were ours — built by my own team over years — and I didn't actually sit down and test whether that feeling matched their current value against what procurement's options offered. It was more that switching felt costly given what we'd already built.

Interviewer: Did the live incident affect that judgment?

Participant: Maybe implicitly — I wasn't eager to bring in a new tool mid-incident. But the core reasoning was really about the integration work already sunk into it, not the incident timing.

Interviewer: Third decision point — containment, once lateral movement was confirmed.

Participant: This was the hardest one. Our IR retainer firm recommended full segment isolation pending forensics — their position was that it's the safer play, though they couldn't prove isolation would fully stop the threat. My team had the overnight script watching the compromised account specifically. Nobody had actually validated whether that script would catch the same credentials being reused on a different host or opening a parallel session elsewhere — but in the moment, having eyes on that one account felt like enough to hold off on isolation. The CFO's framing was blunt: isolating payments meant a guaranteed same-day hit, around $180,000 in processing fees. That number was concrete and immediate. The security upside from isolating wasn't quantified the same way — it was "reduces risk," not a figure. Given the script gave us visibility on that account, I went with targeted lockout and monitoring instead of full isolation.

Interviewer: What was decisive there?

Participant: Honestly, the guaranteed dollar figure against an unquantified benefit made isolation feel like the more expensive option, even though I couldn't put a number on the other side. And I felt like the script had that account covered.

Interviewer: What happened afterward?

Participant: About two hours later, the same compromised credentials touched a second internal system the script wasn't watching. Forensics later found a small amount of data had already been exfiltrated before the script was even running.

Interviewer: Last decision point — the board budget recommendation.

Participant: We'd scoped a privileged-access segmentation project eighteen months back at $240,000, never funded. This week, with the incident fresh, I pulled current vendor quotes for the same scope — they came back $310,000 to $340,000, partly inflation, partly expanded scope since we've added cloud components. The board wanted one number. I went with something close to the original $240,000, nudged up a bit, rather than building the recommendation off this week's actual quotes.

Interviewer: Why start from the old figure instead of the new quotes?

Participant: It was already the reference point in my head from prior planning cycles. Adjusting it felt like less friction than justifying a jump straight to $340,000 without more scoping work behind it.

Interviewer: If the SIEM hadn't pre-scored that first alert, would your response have gone differently?

Participant: Possibly. Without a number already on the screen, I might have leaned harder on the account's privilege level from the start and caught the auth-server overlap sooner.

Interviewer: What if the CFO's number hadn't been quantified?

Participant: I think I'd have treated the isolation call less like a straight cost comparison and spent more time pressing the IR firm on what "reduces risk" actually meant in concrete terms.

Interviewer: Looking back, what would you tell yourself facing that same budget deadline with a stale internal estimate on file?

Participant: Get fresh numbers before you anchor on the old one. Even under deadline pressure, a couple of quotes reframes the whole conversation.
}}

OPTIONAL METADATA
The following metadata may help identify the setting but must not determine the classification:
{
  "interview_id": "{{CS_Counterfactual_7}}",
  "occupational_domain": "{{Cyber Security}}",
  "role": "{{Chief Information Security Officer (CISO)}}"
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
