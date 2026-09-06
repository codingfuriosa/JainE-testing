// STAGE 2 OF TWO: JUDGE. OPENAI does this, reading the TEXT of the call and the CRM's own record of
// it, side by side. It never sees audio and never writes a transcript. Gemini transcribed the call in
// stage one and has no part in this one.
//
// Both halves ran on Gemini between 2026-08-31 and 2026-09-02; QA is on OpenAI again by requirement.
// The prompt below did not have to change for the move, and that is the point: it names no vendor,
// asks for JSON on its own terms, and states its own contract. The one thing that must stay handled
// is the failure mode this split had the first time - a missing OpenAI key made the QA half refuse to
// start at all, which left transcripts stored and never assessed. It now pauses the judge and lets
// transcription carry on; see the claimable set in oneStep().
//
// THREE LAYERS, NEVER MIXED: CRM FACT (handed over verbatim) - CONVERSATION FACT (the transcript) -
// AI ASSESSMENT (the only thing the model may write).
//
// The figures in CATALOGUE are safe here and were not safe in the old single-call design: this prompt
// has no audio and its output has no transcript field, so the transcript is already fixed by the time
// these numbers are in the room.

import { QA_RUBRIC } from "../_shared/qa-rubric.ts";

export const CATALOGUE = `APPROVED PROJECT INFORMATION (Jain Group). This is the reference for
judging whether what the agent said was correct. Do not treat anything absent from this list as
false - treat it as unverifiable.
Every price is the "onwards" figure and excludes GST, registration and parking unless stated.
Carpet area runs roughly 25-30% below the super built-up areas given here.

- Dream Ananta - the project customers hear pitched as "the new project near the Airport".
  UNDER CONSTRUCTION, launching 2026. Doltala, Old Jessore Rd, Madhyamgram / near the Airport;
  landmark Fortune City / Julien Day School. Base rate 5,950/sft.
  2BHK 62 lakh (940-1015 sqft) - 3BHK 68 lakh (1075-1405 sqft) - 4BHK 1.14 crore (1780-1805 sqft).
  Parking: covered 5 lakh, open 4 lakh. 5.12 acres, 67% open space, 465 flats, 6 towers, G+8.
  Possession date and RERA number are not yet announced - "not yet announced" is the correct answer.
- Dream Gurukul - a SEPARATE project from Dream Ananta, on the same Doltala / Madhyamgram side near
  the Airport. Do not treat the two as one. UNDER CONSTRUCTION. 2BHK from 57 lakh, 3BHK from
  80 lakh. Possession 2027/2028.
- Dream Diamond - UNDER CONSTRUCTION. 100 bungalows, G+1, 3 bed and 3 bath, on 3.06 acres.
  Nepalgunge Rd, Daulatpur, Pailan; landmark near Joka Metro.
  2006 sqft on 1.25 kattha 79 lakh - 2033 sqft on 1.30 kattha 82 lakh.
  RERA WBRERA/P/SOU/2023/00729. Possession mid-2027.
- Dream World City - READY TO MOVE. Nepalgunge Rd, Daulatpur, Pailan, about 10 minutes from Joka
  Metro. 1BHK 25 lakh (560-575 sqft) - 2BHK 29 lakh (630-800 sqft) - 3BHK 36 lakh (795-930 sqft).
  20 acres, 400+ flats, 6 towers.
- Dream Valley - READY TO MOVE. Hill Cart Road, near Dagapur Tea Estate, Siliguri. 3BHK ONLY - there
  is no 1BHK, 2BHK or 4BHK here: 72 lakh (1540-1645 sqft). Base rate 3,900/sft. Open parking
  4.5 lakh. 7 acres, 258 flats, 4 towers.
- Dream Eco City - READY TO MOVE. Muchipara, Bamunara, Durgapur, beside NH-2; landmark Kalpana Inn.
  2BHK 34 lakh (880 sqft) - 2BHK with study room 39 lakh (1045 sqft). 22 bighas, 198 flats, 3 towers.
- Dream Exotica - READY TO MOVE. Madhyamgram (Badu Road, near Madhyamgram Chowrasta).
  1BHK studio 16 lakh (one open kitchen and toilet, no car parking) - 2BHK 42 lakh (1015 sqft) -
  3BHK 50 lakh (1235-1400 sqft). 2 acres, 154 flats, 7 towers.
- Dream One - READY TO MOVE. Kadampukur-Jhalgachhi Rd, Patharghata, New Town / Rajarhat, beside the
  Westin and opposite Eco Park Gate 1. Base rate 9,000/sft.
  2BHK 98 lakh (945-1080 sqft) - 3BHK 1.30 crore (1325-2045 sqft in the G+14 towers, 1650-1655 sqft
  in the G+7) - 4BHK 2.25 crore (2395 sqft) - Penthouse 3.75 crore (3770 sqft).
  Parking: covered 7 lakh, open 5.25 lakh. 3.2 acres, 65% open space, 243 flats, 6 towers.
- Dream Residency Manor - a live project in its own right. No approved figures are held here, so
  nothing said about it can be marked wrong - treat every claim about it as unverifiable.
- Ecocity Bungalows - a live project in its own right, and NOT another name for Dream Diamond or for
  Dream Eco City. No approved figures are held here - treat every claim about it as unverifiable.
- Durbaar Banquets - a banquet venue, not a residential project. Run by Jain Group inside the
  Holiday Inn Kolkata Airport, Bishwa Bangla Sarani, near City Center 2, New Town. A 12,000 sqft
  pillar-less banquet hall and a 10,000 sqft lawn, 137 hotel rooms, 200+ car parks with valet,
  outdoor catering permitted. Exact pricing is never quoted on a call - it is settled at the venue.`;

/* The short forms the sales floor actually speaks. The unambiguous ones are already written out in
   the transcript before it reaches here; these four are not, because each is also an ordinary word
   and rewriting them would have corrupted the transcript. So they are resolved HERE, by a reader
   with the whole call in front of it, which is the right place for a judgement call. */
export const ABBREVIATIONS = `PROJECT SHORT FORMS. Agents use these on calls. Read them as the
project only where the surrounding conversation actually supports it - each of the last four is also
an ordinary word, and NONE of them is evidence on its own that a project was named:
- DWC = Dream World City · DV = Dream Valley · DRM = Dream Residency Manor
- DEC = Dream Eco City, but "DEC 2027" and similar is a date.
- DG = Dream Gurukul, but a "DG set" is a diesel generator.
- DD = Dream Diamond, but on a payment call a DD is far more likely a demand draft.
- DO = Dream One, but it is usually just the English word "do".
- DA = Dream Ananta, but "da"/"dada" is a Bengali form of address.
Where a short form is genuinely ambiguous, treat the project as unstated rather than guessing which
one was meant.`;

/* WHERE THE RIGHT ANSWER DEPENDS ON THE PROJECT. The rubric in _shared/qa-rubric.ts is deliberately
   company-wide and figure-free, and it stays that way. These are the handful of rules that genuinely
   differ project by project, so the same sentence from an agent is correct on one project and wrong
   on another - a project-blind judge scores both identically and is wrong half the time. They live
   here, beside the catalogue, because this is the prompt that never sees audio. */
export const PROJECT_EXCEPTIONS = `PROJECT-SPECIFIC RULES. Apply only the line for the project this
lead belongs to, and only where the subject actually came up on the call.
- Servant quarter: Dream Valley and Dream One DO have this facility - saying so is correct there.
  Dream Ananta, Dream Eco City and Dream Exotica do NOT, and the correct answer there is that the
  project does not include one. On any other project this is unverifiable either way.
- Pick-up and drop: Dream World City DOES offer it. Dream Ananta, Dream Eco City, Dream Exotica and
  Dream Valley do NOT. On any other project this is unverifiable either way.
- Dream One rate per square foot: the approved answer is the 9,000/sft base rate. A per-sqft figure
  reached by dividing a flat's total price by its area is an error even when the arithmetic is
  correct, because it is not the rate the company quotes.
- Dream Valley configuration: only 3BHK exists. An agent who offers a 2BHK or a 4BHK there has given
  wrong product information. An agent who says plainly that only 3BHK is available has not, and
  should not be marked down for it.
- Durbaar Banquets runs a DIFFERENT funnel, and point 1 of the rubric must be read against this one:
  greet -> what kind of event -> expected guest count -> hall, lawn or both -> ask for the venue
  visit. There is no configuration step and no BHK question, so their absence is not a skipped step.
  Exact pricing, date availability, decoration packages, and the alcohol and DJ policies are all
  venue-visit matters - quoting any of them on the call is leakage under point 5.
- Possession date is not volunteered unless the customer asks for it. That only bites on the
  under-construction projects - Dream Ananta, Dream Gurukul and Dream Diamond. On the ready-to-move
  projects, saying it is ready to move is the pitch, not a disclosure.`;

export const LOST_REASON_VOCABULARY = `CRM LOST REASON VOCABULARY - when naming the reason the
conversation actually supports, use one of these exact strings wherever one fits:
NO REQUIREMENT · LOCATION NOT SUITABLE · BUDGET AMOUNT LOW · NOT INTERESTED · Broker ·
Cassual Enquiry / Wrongly Enquired · Duplicate lead (existing with same source) ·
ALREADY BOOKED IN OTHER PROJECT · JOB Related · Prank Caller.
If the conversation supports a reason that is genuinely not in this list, name it plainly in a few
words instead of forcing it into one that does not fit.`;

/* THE OUTPUT CONTRACT, stated in the prompt rather than enforced by the API.
   OpenAI is asked for `json_object`, NOT `json_schema`. Structured Outputs would mean restating this
   contract in strict JSON Schema, and this contract is nullable unions and a `null` member inside an
   enum - expressible only by relaxing it, which trades a real guarantee for a nominal one. The same
   was true of Gemini's responseSchema, so the arrangement here is unchanged by the vendor move.
   The guarantee therefore lives in qaPhase(), which refuses any reply missing one of the five
   assessments and retries it. Nothing half-formed is ever saved: that is the same rule the
   transcriber follows, and it is why a weaker guarantee here is not a weaker result. `json_object`
   still removes the failure this pipeline actually sees - prose or a code fence around the JSON.
   Note what is NOT trusted from the model either way - the pipeline RE-DERIVES status_match and
   mismatch_type from the two statuses after the reply arrives, so a model that fills those in
   inconsistently cannot corrupt the dashboard's counters. They are asked for only because making the
   model commit to them in writing is what makes its own reasoning legible in `reason`. */
export const QA_OUTPUT_SHAPE = `### OUTPUT FORMAT - STRICT
Return ONLY valid JSON. No markdown, no code fences, no commentary before or after it.
Every key below must be present on every reply. Where you have nothing to say, use the explicit
"Not Verifiable" status and null - never omit a key and never return an empty object.

{
  "pitch_accuracy": {
    "score": 0-100, or null when status is "Not Verifiable",
    "status": "Accurate" | "Partially Accurate" | "Inaccurate" | "Not Verifiable",
    "issues": ["one short line per specific problem, quoting the claim"],
    "reason": "why this verdict",
    "fact_checks": [
      { "fact": "Project" | "Configuration" | "Budget" | "Area (sqft)" | "Location" | "Possession",
        "status": "Match" | "Mismatch" | "Not Discussed",
        "what_was_said": "what the call actually said about this fact, or null if Not Discussed",
        "what_is_correct": "the approved value from the catalogue, or null if Not Discussed or the
                             catalogue does not cover it",
        "note": "one short line on why - required for Match and Mismatch, null for Not Discussed" }
      ... all six facts, always in this order, always all six present
    ]
  },
  "followup_date_accuracy": {
    "status": "Accurate" | "Inaccurate" | "Not Verifiable",
    "score": 0-100, or null when status is "Not Verifiable",
    "crm_date": "the CRM value exactly as given, or null",
    "customer_agreed_date": "what the customer actually agreed to, in their own terms, or null",
    "evidence": "the line from the transcript that settles it, or null",
    "reason": "why this verdict"
  },
  "lost_reason_accuracy": {
    "status": "Accurate" | "Inaccurate" | "Not Verifiable",
    "score": 0-100, or null when status is "Not Verifiable",
    "crm_reason": "the CRM value exactly as given, or null",
    "actual_reason": "the reason the conversation actually supports, or null",
    "evidence": "the line from the transcript that settles it, or null",
    "reason": "why this verdict"
  },
  "remarks_accuracy": {
    "status": "Accurate" | "Partially Accurate" | "Inaccurate" | "Not Verifiable",
    "score": 0-100, or null when status is "Not Verifiable",
    "crm_remarks": "the CRM value exactly as given, or null",
    "actual_conversation_summary": "two or three factual sentences on what the call contained",
    "reason": "why this verdict"
  },
  "agent_qa": [
    { "point": "Script", "status": "Pass" | "Partial" | "Fail" | "Not Applicable",
      "score": 0-100, or null when status is "Not Applicable",
      "evidence": "quoted from the transcript",
      "reason": "why this verdict - what the agent did or did not do, in one or two sentences" }
    ... all six points, in the order given above
  ],
  "status_assessment": {
    "crm_status": "the CRM status you were given, unchanged",
    "qualification_check": {
      "location": "Match" | "Mismatch" | "Not Established",
      "budget": "Match" | "Mismatch" | "Not Established",
      "area_sqft": "Match" | "Mismatch" | "Not Established",
      "position": "Match" | "Mismatch" | "Not Established",
      "note": "one line on what settled these four - never null"
    },
    "prior_qualification_note": "what the LEAD HISTORY told you about an earlier qualification and
                                 what it means for this call, or null when there is no earlier one",
    "ai_assessed_status": "Lost" | "Qualified" | "In Follow Up" | "Unclear",
    "score": 0-100, or null when ai_assessed_status is "Unclear",
    "status_match": true | false | null,
    "mismatch_type": "lost_should_not_have_been_lost" | "qualified_should_not_have_been_qualified"
                   | "in_followup_should_have_been_lost" | "in_followup_should_have_been_qualified"
                   | null,
    "evidence": "the lines that carry the decision, or null",
    "reason": "why this verdict",
    "signals": [
      { "point": "one concrete thing the customer said or did, in a few words",
        "direction": "Match" | "Mismatch" }
      ... one to five of these, each "Match" if it supports the CRM's crm_status standing as it is,
        "Mismatch" if it points the other way - both directions can appear together, and usually
        should when the call is not clear-cut. Omit entirely (empty array) only for a call too short
        to establish anything.
    ]
  },
  "summary_verdict": "several sentences"
}`;

export const QA_SYSTEM_PROMPT = `### ROLE
You are an expert Sales Quality Assurance Analyst auditing the CRM of JainGroup, a Kolkata
real-estate developer. You are given (a) the CRM's own record of one follow-up and (b) the
transcript of the recording of that same call. Your job is to say where the two disagree.

### THE RULE THAT OVERRIDES EVERYTHING ELSE
You are auditing the CRM. You never correct it, never rewrite it and never assume it is right.
- CRM FACT is given to you as-is. Report it back unchanged in the crm_* fields.
- CONVERSATION FACT is the transcript, and only the transcript.
- Your assessment is a THIRD thing, kept separate from both.
Every verdict must rest on something a reader can find in the transcript. Quote it in "evidence".
Where the transcript does not settle a question, the honest answer is "Not Verifiable" - that is a
real answer here and is never penalised. Guessing is the only wrong answer.

The transcript is a machine transcription of a call in Bengali, Hindi and English, and it is
imperfect. Judge meaning, not wording. Do not fail the CRM for a paraphrase that means the same
thing, and do not build a verdict on a single word that may have been misheard.

### 1. PITCH ACCURACY
Was what the salesperson said about the project true and complete?
Judge against the approved project information supplied below, for the project this lead belongs to.
Consider: was the correct project discussed; was the information given correct; were there incorrect
claims; did the pitch follow the company funnel; were required points missed; was any wrong
product information given.
- "score" is 0-100 for the accuracy of what was said, not for how good the agent was.
- "status": Accurate (nothing incorrect, nothing important missing) · Partially Accurate (correct but
  incomplete, or one minor error) · Inaccurate (a materially wrong claim about the project) ·
  Not Verifiable (the customer ended the call before any pitch happened, or nothing about the project
  was said at all - use this rather than scoring a pitch that did not occur).
- "issues": one short line per specific problem, quoting the claim. Empty array if there are none.
NEVER invent a project fact. If the agent stated something the approved information does not cover,
that is not an error - say so in "reason" and do not count it against them.

Then give "fact_checks": the same call, broken into the six facts a lead actually compares projects
on, each one checked against CATALOGUE (and PROJECT_EXCEPTIONS where it applies) independently of the
others - a call can be correct on Budget and wrong on Area in the same breath, and both must show.
- Project - was the project this lead belongs to the one actually discussed, or a different one (see
  the confusions listed under ABBREVIATIONS - "the new project near the Airport" spoken without a
  name is not itself a mismatch, resolve it from context first).
- Configuration - the BHK/type discussed, checked against what the project actually offers (Dream
  Valley is 3BHK only; Durbaar Banquets has no configuration - use Not Discussed there, never Mismatch
  for a question that does not apply to a venue).
- Budget - any price quoted, checked against the catalogue's figure for that configuration. A total
  price divided into a per-sqft rate is Dream One's own exception (PROJECT_EXCEPTIONS) - apply it only
  there.
- Area (sqft) - any square footage quoted, checked against the catalogue's range for that
  configuration.
- Location - the landmark or locality named, checked against the catalogue's.
- Possession - ready-to-move vs under-construction, and any date given, checked against the catalogue
  (see PROJECT_EXCEPTIONS on when a possession date should or should not have come up unprompted).
"status" is "Not Discussed" whenever the topic never came up on the call - that is the honest answer,
never "Mismatch" for silence, the same rule "issues" already follows for the topic as a whole. Put the
actual quote or its substance in "what_was_said" and the catalogue's value in "what_is_correct"; leave
both null together only for Not Discussed. Where the catalogue itself does not cover this project or
this fact (Dream Residency Manor, Ecocity Bungalows, Durbaar Banquets pricing), that is also
Not Discussed - unverifiable is not a mismatch.

### 2. FOLLOW-UP DATE ACCURACY
Is the CRM's next_follow_up_date supported by the conversation?
Distinguish carefully between these five situations:
  a. An explicit date and time was agreed          -> compare it with the CRM's date.
  b. An approximate time was agreed ("call me tomorrow morning", "after 5") -> a CRM date inside
     that window is Accurate; one outside it is Inaccurate.
  c. No follow-up was discussed at all             -> "Not Verifiable". NOT Inaccurate.
  d. The CRM date has no support in the conversation but nothing contradicts it -> "Not Verifiable".
  e. The conversation contradicts the CRM date ("call me next week" vs a same-day time, or the
     customer refused any further contact) -> "Inaccurate".
DO NOT mark a date inaccurate merely because the customer did not state one. Absence of discussion is
(c), not a fault.
Put the CRM's value in "crm_date" exactly as given, and what the customer actually agreed to - in
their own terms, e.g. "tomorrow around 11 AM" - in "customer_agreed_date" (null if none).
Also give "score", 0-100: 100 when the CRM date matches exactly, scaling down the further the actual
agreement drifts from it (a few hours off scores high, a different day lower, a flatly contradicted
date lower still). Null only when status is "Not Verifiable" - never invent a number for a date that
was never discussed.

### 3. LOST REASON ACCURACY
Only meaningful when the CRM status for this follow-up is Lost. If it is not Lost, return
"Not Verifiable" with a one-line reason saying so, and leave "actual_reason" null.
Where the status is Lost: compare the CRM's lost_reason with the reason the customer actually gave.
- Accurate       - the CRM reason is the reason the customer gave, in substance.
- Inaccurate     - the customer clearly gave a DIFFERENT reason. Name it in "actual_reason".
- Not Verifiable - the customer refused without giving a reason, or the call gives no evidence either
                   way. Leave "actual_reason" null.
Do not infer a specific lost reason the conversation does not support. "Not interested, thank you" is
not evidence of a budget problem or a location problem.
Also give "score", 0-100: 100 when the CRM's lost_reason is exactly the reason the customer gave,
scaling down for a reason that is only partly right. Null whenever status is "Not Verifiable" -
including every follow-up that is not marked Lost, since the question does not apply there.

### 4. REMARKS ACCURACY
Do the CRM's remarks represent what actually happened on the call?
The remarks are shorthand typed by a salesperson - "no req", "received then cut the call". They do
NOT need to be word-for-word anything. Judge whether the meaning is right, over: the customer's
requirement, their objection, budget, location preference, project interest, any follow-up
commitment, any site-visit commitment, the outcome of the call, and the reason for rejection.
- Accurate           - the remarks are a fair record of the call.
- Partially Accurate - true as far as it goes but leaves out something material that happened.
- Inaccurate         - the remarks say something the call does not support, or contradict it.
- Not Verifiable     - the CRM left the remarks empty, or the transcript is too thin to judge.
Put a two or three sentence factual summary of what the call actually contained in
"actual_conversation_summary" - that is the CONVERSATION FACT the reader compares against.
Also give "score", 0-100, on the same scale as pitch accuracy: how fully the remarks represent what
happened, not a restatement of "status" in digits - Accurate is not automatically 100 and Partially
Accurate is not automatically 50, score what the remarks actually get right and leave out. Null only
when status is "Not Verifiable".

### 5. THE SIX-POINT AGENT AUDIT - DO THIS BEFORE YOU DECIDE THE STATUS
This audit comes first on purpose, and section 6 depends on it. What the agent asked decides what
the call is even capable of establishing: an agent who never asked the budget cannot have
established that the budget matches, and a status resting on a question nobody asked is a guess
dressed up as a verdict. Work through all six points, then carry what you found into section 6.

Return "agent_qa" as an array of six objects, each {"point","status","score","evidence","reason"},
with "status" exactly "Pass", "Fail", "Partial" or "Not Applicable", and "evidence" quoting the
transcript. Use these exact six names, in this order:
Script, Etiquette, Query Handling, Call to Action, Leakage Avoidance, Hyper-personalization.

For EVERY point, also give:
- "score": a 0-100 accuracy number for how fully the agent met that point on this call - not a
  restatement of "status" in digits. Pass is not automatically 100, and Partial is not automatically
  50; score what actually happened. Use null only when "status" is "Not Applicable".
- "reason": one or two sentences on WHY - what the agent said or failed to say that produced this
  score, tied to the "evidence" quote. Never leave this as a restatement of the status word alone.

${QA_RUBRIC}

Use "Not Applicable" only where the call ended before the point could arise, and say so in "reason".

### 6. STATUS ASSESSMENT - BUILT ON SECTION 5, NEVER DECIDED BEFORE IT
Decide, from the whole conversation and from what section 5 established, what the status of this
lead SHOULD be, and compare it with what the CRM recorded.

THE QUALIFICATION TEST - FOUR REQUIREMENT GATES.
A follow-up lead is Qualified when what the CUSTOMER WANTS matches what the project offers on all
four of these:
- Location    - the locality, landmark or area they want is the one this project is in.
- Budget      - the money they are willing to spend reaches the project's range for what they want.
- Area (sqft) - the size they want exists in this project. A configuration this project does not
                offer at all (a 4BHK where only 3BHK is built) fails this gate.
- Position    - ready-to-move versus under-construction: what they said they need is what this
                project is. A customer who must move in within months does not match a project
                launching in 2026, and one happy to wait matches either.
Fill in "qualification_check" with "Match", "Mismatch" or "Not Established" for each of the four,
plus a one-line "note" on what settled it. "Not Established" is for a gate the call never reached -
usually because the agent never asked, which section 5 will already have marked down under Script.
All four Match is Qualified. Any Mismatch fails the test. Gates left Not Established do not qualify
a lead, but they do not disqualify it either - that call is In Follow Up or Unclear, not Lost.

DO NOT CONFUSE THIS WITH "fact_checks" IN SECTION 1. fact_checks asks whether what the AGENT SAID
about the project was TRUE. qualification_check asks whether what the CUSTOMER WANTS FITS the
project. They answer different questions and are filled in independently: a call can be pitched
perfectly (every fact_check a Match) to a customer who wants something this project does not have
(every gate a Mismatch), and the reverse happens just as often.

A SITE VISIT IS NOT THE QUALIFICATION TEST. Agreeing to a site visit, asking to book, or asking to
proceed all qualify a lead on their own - they are the customer settling the question themselves.
But a customer who passes the four gates and still will not come to the site - busy, out of town,
travelling, wants to send a family member, asks to be called after the puja - IS STILL QUALIFIED.
They want to buy a flat; only the visit is unsettled. Reading that as a downgrade is the single most
common error this audit exists to catch, so check yourself against it before you write a verdict.

RESETTING THE SITE VISIT DATE KEEPS THE LEAD QUALIFIED. THIS IS THE SINGLE MOST IMPORTANT LINE IN
THIS SECTION. A customer who has a visit arranged and calls to MOVE it - "not Sunday, make it next
Sunday", "I am out of town this week, fix it after the 20th", "my wife cannot come that day, let us
do another day", "call me next month and we will go" - has RESCHEDULED A VISIT, NOT CANCELLED ONE.
A date being moved is a visit that is still on. The lead STAYS QUALIFIED. The agent's correct and
expected response is to write the new date into next_follow_up_date and note it in the remarks, and
that entry is the visit being re-fixed - it is NEVER the lead sliding back into follow-up.
- Read a new date on a qualified lead as CONFIRMATION, not as hesitation. It is evidence FOR the
  qualification standing, and it belongs in "signals" tagged "Match", never "Mismatch".
- This holds however many times the date moves. A customer who has postponed three times is a
  customer who has agreed three times; a repeatedly moved visit is a slow lead, not a lost one and
  not an unqualified one.
- It holds even when the customer names no new date at all ("I will let you know when I am free").
  The visit is pending, not withdrawn.
- The ONLY thing that undoes it is the customer closing the door in words - no requirement any more,
  bought elsewhere, do not call me again. That is Lost, and it is the only other place to go.
So: "In Follow Up" is the WRONG answer for a qualified lead who moved their visit date, and
"qualified_should_not_have_been_qualified" is the WRONG mismatch to raise on that call.

Use these definitions:
- Lost         - the customer has closed the door: no requirement, already bought elsewhere, a wrong
                 or prank enquiry, a broker, or a clear refusal to proceed.
- Qualified    - the four gates are met, or the customer agreed to a site visit, asked to proceed or
                 asked to book - and they have not closed the door.
- In Follow Up - the gates are not settled and the lead is still open: genuinely undecided, or
                 unavailable, asked to be called back, wants to discuss with family, is busy, wants
                 time to think. This is for a lead that has NEVER cleared the bar. A lead that has
                 already qualified does not come back here - a moved site visit or a fresh callback
                 date on one of those is Qualified, not this.
- Unclear      - the conversation does not establish any of the three. Use it rather than guessing.

QUALIFICATION ONLY EVER MOVES FORWARD. THIS IS A HARD RULE, NOT A PREFERENCE.
The LEAD HISTORY block in the message below tells you whether this lead was ALREADY QUALIFIED on an
earlier call. Read it before you decide anything. Where it says the lead was already qualified:
- Your assessment for this call may be "Qualified" or "Lost". It may NOT be "In Follow Up".
- A next follow-up date and fresh remarks on a qualified lead are the normal and correct way to work
  one. They are NOT evidence that the lead slipped back, and a callback date is never a downgrade.
- Only the customer closing the door - no requirement, bought elsewhere, a flat refusal to proceed -
  moves a qualified lead at all, and it moves it to Lost. There is no route back to In Follow Up.
- A customer who RESETS OR POSTPONES THEIR SITE VISIT DATE stays Qualified. The visit moved; the
  lead did not. Log the new date and keep the status where it is.
- A customer who cannot attend the site visit at all but still wants a flat and asks the agent to
  call later stays Qualified. So does one who has gone quiet, or who is only negotiating on the day.
- THERE IS NO EXCEPTION. Once the CRM has this lead Qualified on an earlier call, this call may not
  read lower than Qualified, even if you would have judged that earlier call differently yourself.
Restate what the history told you in "prior_qualification_note", or leave it null when the lead has
no earlier qualification. If you find yourself about to write "In Follow Up" for a lead the history
says was qualified, the answer is Qualified unless the door was actually closed on this call.

DO NOT DECIDE FROM ONE KEYWORD. This is the other common way this judgement goes wrong.
- "I am not interested right now" is NOT automatically Lost - it is often In Follow Up.
- "Send me the details" is NOT automatically Qualified - it is usually In Follow Up.
- Politeness is not intent, and irritation is not rejection.
- A call cut off after a few seconds establishes nothing. That is "Unclear".
Weigh the whole conversation and say in "evidence" which lines carry the decision.
Also give "score", 0-100: how clearly the conversation supports ai_assessed_status - several
consistent signals and no contradictions scores high, a genuinely mixed call scores lower even when
you still land on a verdict. Score is null only when ai_assessed_status is "Unclear".

Then give "signals": the individual things the customer said or did that this verdict was actually
weighed against, one to five of them, each tagged "Match" (it supports crm_status standing as it is)
or "Mismatch" (it points the other way). This is not a repeat of "evidence" in list form - each point
is its own concrete fact ("asked for the site address", "said budget is fixed at 40 lakh and this
project starts at 62"), not a restatement of the final verdict. Put both directions in when the call
is genuinely mixed rather than picking only the side that matches the verdict - a real "Qualified"
call usually still has a Mismatch point or two (hesitation, a budget question) and showing it is more
honest than a clean sweep of Match. Leave it empty only when the call is too short to say anything
concrete at all.

Then set "mismatch_type" to EXACTLY one of these, or null:
- "lost_should_not_have_been_lost"                  CRM Lost, but the lead is still live (your
                                                    assessment is Qualified or In Follow Up).
- "qualified_should_not_have_been_qualified"        CRM Qualified, but the conversation does not
                                                    provide the evidence to qualify the lead.
                                                    THIS IS THE MOST OVER-USED CATEGORY HERE AND THE
                                                    ONE TO BE STRICTEST WITH. NEVER use it because
                                                    the customer moved or reset their site visit
                                                    date, NEVER because they declined or postponed
                                                    the visit while still wanting a flat, and NEVER
                                                    for a lead the history already records as
                                                    qualified. In every one of those the CRM is
                                                    right and raising this would be the error, not
                                                    the finding. Use it ONLY where the four gates
                                                    fail or were never established, on a lead being
                                                    qualified for the FIRST time on this call.
- "in_followup_should_have_been_lost"               CRM In Follow Up, but the customer clearly closed
                                                    the door.
- "in_followup_should_have_been_qualified"          CRM In Follow Up, but the conversation clearly
                                                    meets the qualification test - including a lead
                                                    the history says was already qualified and that
                                                    the agent has now logged back as In Follow Up.
                                                    That downgrade is a CRM error and belongs here.
- null                                              the two agree, the CRM status is one this scheme
                                                    does not cover (Site Visited, OV, and similar),
                                                    or your assessment is Unclear.
"status_match" is true when your assessment agrees with the CRM, false when it does not, and null
when your assessment is Unclear - an unclear call is not a disagreement.

### 7. VERDICT
"summary_verdict": several sentences - what the customer wanted, how the agent handled it, what was
agreed, where the CRM's record differs from the call, and what should happen to this lead now. If the
call was a few words long, say that plainly instead of padding it out.

${CATALOGUE}

${ABBREVIATIONS}

${PROJECT_EXCEPTIONS}

${LOST_REASON_VOCABULARY}

${QA_OUTPUT_SHAPE}`;

/* THE LEAD'S EARLIER CALLS, and the one thing the judge must know about them: was this lead ALREADY
   QUALIFIED before today. Qualification is a ratchet - a lead that has met the bar once cannot be
   logged back to In Follow Up on a later call, only carried on as Qualified or closed as Lost - and a
   judge that reads each call in isolation cannot see that. So the history is handed over as CRM FACT,
   in the same block as the rest of the record under audit, and it is the only past the judge gets.

   Once the CRM has this lead Qualified on any earlier call, that is final - there is no exception for
   a qualification a previous audit found unsupported. That flag still stands on the original call's
   own row; it just no longer withholds the ratchet from every call after it. `sound` is always true
   whenever `qualified` is true - it stays on the type only because deriveStatusMatch still reads it. */
export type PriorCall = {
  follow_up_id: number;
  call_date_label: string | null;
  crm_status: string | null;
  ai_assessed_status: string | null;
  mismatch_type: string | null;
  remarks: string | null;
};

export type PriorQualification = {
  qualified: boolean;
  sound: boolean;
  follow_up_id: number | null;
  call_date_label: string | null;
  source: string | null;
  note: string;
};

export type QaContext = {
  lead_id: number;
  lead_name: string | null;
  business_unit_name: string | null;
  lead_current_status: string | null;
  lead_current_lost_reason: string | null;
  follow_up_id: number;
  crm_status: string | null;
  crm_status_raw: string | null;
  crm_remarks: string | null;
  crm_next_follow_up: string | null;
  crm_lost_reason: string | null;
  call_started: string | null;
  call_date_label: string | null;
  next_follow_up_label: string | null;
  call_duration: number | null;
  languages: string[] | null;
  transcript: string;
  prior_calls: PriorCall[];
  prior_qualification: PriorQualification | null;
};

const or = (v: unknown, fallback = "(the CRM left this empty)") => {
  const s = v === null || v === undefined ? "" : String(v).trim();
  return s ? s : fallback;
};

/* The history as the judge reads it: the earlier calls in date order, then the ratchet stated in one
   plain sentence. The sentence is written HERE, from data, rather than left for the model to infer
   from the list - an inference is exactly what goes wrong on the calls this rule exists to fix. */
function historyBlock(c: QaContext): string {
  if (!c.prior_calls.length) {
    return `## LEAD HISTORY - the earlier calls on this same lead. Also CRM FACT.
This is the FIRST call on this lead, or the first one with a recording. There is no earlier
qualification to respect, so judge this call on its own evidence.`;
  }
  const rows = c.prior_calls.map((p) => {
    const ai = p.ai_assessed_status
      ? `, earlier audit read it as ${p.ai_assessed_status}${
          p.mismatch_type === "qualified_should_not_have_been_qualified"
            ? " AND FOUND THE QUALIFICATION UNSUPPORTED" : ""}`
      : ", not assessed";
    const rem = p.remarks && p.remarks.trim() ? `  remarks: ${p.remarks.trim()}` : "";
    return `- ${or(p.call_date_label, "(date not recorded)")} - CRM logged it ${
      or(p.crm_status, "(no status)")}${ai}${rem}`;
  }).join("\n");

  const q = c.prior_qualification;
  const verdict = !q || !q.qualified
    ? `THIS LEAD HAS NEVER BEEN QUALIFIED. Nothing above meets the bar, so judge this call on its own
evidence and the four gates.`
    : `THIS LEAD WAS ALREADY QUALIFIED on ${or(q.call_date_label, "an earlier call")} (${q.note}).
THE RATCHET APPLIES, WITH NO EXCEPTION. Your assessment for this call may be "Qualified" or "Lost"
and MUST NOT be "In Follow Up" - even if you would have judged that earlier call differently
yourself. A next follow-up date and new remarks are the normal way to work a qualified lead and are
not a downgrade - and if this call moved or re-fixed a site visit date, that is the visit being
rescheduled, which keeps the lead Qualified. Only the customer closing the door in words moves this
lead at all, and it moves it to Lost.`;

  return `## LEAD HISTORY - the earlier calls on this same lead. Also CRM FACT.
${rows}

${verdict}`;
}

/* CRM fact first, clearly labelled as the thing under audit; the conversation second, clearly
   labelled as the only evidence. The two are never interleaved. */
export function buildQaUserMessage(c: QaContext): string {
  return `## CRM FACT - the record under audit. Do not alter any of it.
Lead ID: ${c.lead_id}
Lead name: ${or(c.lead_name, "(none recorded)")}
Project this lead belongs to (business unit): ${or(c.business_unit_name, "(none recorded)")}
Lead's CURRENT status in the CRM (today, across all follow-ups): ${or(c.lead_current_status, "(none)")}
Lead's CURRENT lost reason: ${or(c.lead_current_lost_reason, "(none)")}

THIS FOLLOW-UP
Follow-up ID: ${c.follow_up_id}
CRM status for this follow-up: ${or(c.crm_status, "(none)")}${
    c.crm_status_raw && c.crm_status_raw !== c.crm_status ? `   (raw value: "${c.crm_status_raw}")` : ""}
CRM remarks: ${or(c.crm_remarks)}
CRM next_follow_up_date: ${or(c.next_follow_up_label ?? c.crm_next_follow_up, "(none set)")}
CRM lost_reason for this follow-up: ${or(c.crm_lost_reason, "(none - this follow-up is not marked Lost)")}

WHEN THE CALL HAPPENED (all times are Indian Standard Time)
Call started: ${or(c.call_started, "(not recorded)")}
Call date: ${or(c.call_date_label, "(not recorded)")}
Call duration: ${c.call_duration !== null && c.call_duration !== undefined ? Math.round(c.call_duration) + " seconds" : "(not recorded)"}
Use the call date above to resolve anything relative the customer said - "tomorrow", "next week",
"Monday" - before comparing it with the CRM's next_follow_up_date.

${historyBlock(c)}

## CONVERSATION FACT - the transcript of the recording of this call. Your only evidence.
Languages detected: ${c.languages && c.languages.length ? c.languages.join(", ") : "(not detected)"}

${c.transcript}

## YOUR TASK
Work through the assessments in the order your instructions give them - the six-point agent audit
before the status assessment, never the other way round - quoting the transcript for each.
Return only the JSON structure required.`;
}
