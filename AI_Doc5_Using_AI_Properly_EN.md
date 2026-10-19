# Using AI Properly in Software Development — using it, checking it, accounting for it

*AIASD · Atlas University · Fall 2026–27 · Prof. Dr. Vedat Coşkun*
*This document is the companion to `AI_Doc4`, which explains what the tools are and how to
spend them. This one explains what you should do with what they give you. It is part of
the examinable material: the final exam contains questions on it.*

---

## 0. Four people, one assistant

If the same prompt — *"Write me a login endpoint that sends a six-digit code by e-mail
and checks it"* — is given to four different people, the assistant returns essentially the
same answer to each of them: a few dozen lines of code, call it forty. In Week 1, the four repositories look identical. By Week 5,
they no longer do, and that difference is the subject of this document.

The four people differ in two respects. The first is whether they have the **concepts of
software engineering**: what a requirement is, what an interface is, what the status code
`409` means, what a test proves, what a version is, and what a risk is. The second is
whether they have the **discipline of using an assistant**: treating its output as a claim
rather than a fact, checking it, recording the decision, and knowing where not to use it at
all. This course assumes that the first is being taught around you in your degree
programme, and it teaches the second. What it grades is the combination of the two.

| | Without the assistant discipline | With the assistant discipline |
|---|---|---|
| **Without the engineering concepts** | This person pastes those lines, sees that the code runs, and pushes it. When the first real user does not receive the code and asks for a second one a few seconds later, the endpoint simply sends a second code; nobody had thought about that case. When the first bug appears, this person "fixes" it by asking the assistant again, without reading the answer. The commit history is a single commit made on Saturday night. The product works in the demonstration and nowhere else. | This person writes a careful prompt, is suspicious of the answer, and asks a second assistant the same question, but cannot say *what* should be checked. He or she does not know that "a user asks for a second code before the first one has expired" is a case the code must handle, has never seen the HTTP status `409 Conflict` (the server's way of saying "this request clashes with something that already exists"), and cannot write an acceptance criterion, because nobody has taught the concept yet. The doubt is justified, but nothing gets verified. |
| **With the engineering concepts** | This person knows exactly what the endpoint should do, but is in a hurry. He or she accepts the assistant's changes without reading them line by line, pastes a real tester's e-mail address into the prompt as test data, and does not notice that the e-mail library the assistant chose was last updated two years ago. The concepts are present, but they are not applied to the assistant's output, because "it compiled". Alternatively, this person refuses to use the assistant at all and is three weeks behind by Week 6. | This person reads those lines against requirement REQ-006 ("one code per e-mail address per minute"), sends two requests for the same address within a minute, sees that a second code is issued, rejects the code, adds a test for that case, commits the fix on its own with a message that names it, and writes four lines in the AI log with both server responses pasted. It is the same assistant and the same prompt, but a different engineer. |

Nothing in the right-hand column requires a different assistant or a better prompt. It
requires knowing what the output is supposed to satisfy, checking whether it does, and
leaving a record that someone else can read. These three activities are the eight
techniques described below. The examples under each technique are labelled according to
the two columns, **Untrained user** and **Trained in this course**, and each pair shows the
same situation handled by two different people.

A student who arrives without the engineering concepts is not excluded from the right-hand
column. Every technique below names the concept it depends on and the week in which the
course introduces that concept. The order matters: the concept comes first, and the
assistant comes second.

---

## 0.1 The one sentence

This course does not grade what the assistant produced. It grades how well **you
specified, checked, corrected and accounted for** what it produced. An assistant can write
every file an assignment asks for in ten minutes. The two points of your weekly `ai_log`
are awarded for the moment at which you caught the assistant being wrong, for the evidence
you pasted, and for what you did about it.

Everything below is a named technique for producing that moment deliberately, instead of
waiting for it to happen. Each week's assignment names the technique it expects, and the
table in §10 shows the whole term. You may use any of the techniques in any week, but one
of them is compulsory each week.

The techniques operate inside the weekly routine you already know: the checker before
every push; the pushes at 10:00, 11:00 and at the end of the lecture (11:45), and the freeze that follows; the Saturday
23:59 deadline; the ids in your `requirements.json`; the Change log at the end of
`PROPOSAL.md`; your group of four and its one-hour online meeting between the lecture and
Saturday; and `weekNN/group_NN.json` (`contributors_NN.json` in Weeks 2–3). None of the techniques asks for a new file or
a new habit. They specify what should go into the files you already push.

### Where the assistant sits in the twelve weeks

The same assistant is a different tool in each phase of your project. The table below
shows what it does well in each phase, what it reliably gets wrong, and which technique
catches the error.

| Phase (weeks) | What it does well | What it reliably gets wrong | Technique that catches it |
|---|---|---|---|
| Proposal and requirements (2–3) | It produces lists and structure quickly: eight requirements in a minute. | It does not know your priorities or your users; it gives numbers (market size, review time) for which it has no source; and it adds features you never asked for, such as a `Payment` table in an app that takes no money. | §4, §3, §5 |
| Prototype, test cases and design (4–5) | It draws screen flows, test cases, diagrams and data models from a short description. | It forgets a constraint unless you repeat it in every prompt; it adds one entity too many; it puts a field on the wrong table (for example the check-in time on the user instead of on the reservation). | §1 |
| Server, login and clients (5–7) | It writes boilerplate code, endpoints, tests, and the glue code between the server and the clients. | It misses edge cases: for example, a user asks for a second login code before the first has expired, and the code sends a new one instead of refusing. It installs library versions that have since been removed or renamed, so `pip install` fails. When asked for one change, it also makes a second change it does not mention. | §2, §3, §6 |
| The three tiers (8) | It writes each tier (server, web, mobile) correctly on its own. | It does not make the three tiers agree with each other: the same field is `room_id` on the server and `roomId` in the app; the server returns a status code that no client handles. | §7 |
| Testing with people (9–10) | It writes test plans, bug-report templates and a list of likely failures. | It cannot know what your five testers will actually do, because it has never met them. | §8 |
| Store and release (11) | It writes checklists and the text of the store listing. | It quotes store rules as they were a year ago, and the review time for an established account rather than for a new one. | §3, §5 |
| Closure and defence (12–14) | It writes summaries and the first draft of the poster. | It cannot say why you decided what you decided; only you know this, and you will be asked. | §9 |

Read from top to bottom, the table shows that the assistant's value is highest where the
work is generic and lowest where the work concerns *your* product and *your* people. That
is also the order in which this course trusts it less and less.

---

## 1. Acceptance criteria first

**What.** Before you ask for anything, write down how you will know that the answer is
right. Two or three lines in your own words are enough, written *before* the prompt. Then
include them in the prompt.

**Why.** A request without a test is a request for something plausible, and models are
very good at producing plausible things. "Write me a data model for StudyRoom" returns a
tidy diagram that contains a `Payment` table. "Write me a data model for StudyRoom with at
most five entities, no money anywhere, and a reservation that records who checked in and
when" returns something you can check line by line, and the check has already been
written.

**Untrained user.** *"I asked Claude for the data model. It looked fine, so I used it."*

**Trained in this course.** *"My criteria before asking were: at most five entities, no
payment, and the check-in time stored on the reservation. The first answer had seven
entities, including `Invoice`. The second prompt, with the criteria pasted in, produced
five entities, but the check-in time was on `User` rather than `Reservation`, which is
wrong because one user has many reservations. I fixed it by hand; the final model is in
`docs/data_model.md`."*

**In the log.** Record the criteria you wrote first, the answer measured against them, and
what failed.

**In this course.** Your criteria already exist: they are the ids in `requirements.json`,
whose meaning has been fixed since Week 3 and which form your baseline from the end of Week 5. Paste into the prompt the REQ lines that the design
or the code must satisfy. An answer that breaks a REQ is the error of the week. An answer
that needs a REQ you do not have is recorded as a dated line in the Change log, not added
silently.

---

## 2. Verify by running, not by reading

**What.** Anything that can be executed is verified by executing it: run the code, send
the request, open the page on a phone, paste the Mermaid source into the preview. Reading
the output and nodding is not verification.

**Why.** Generated code reads correctly far more often than it runs correctly. The
assistant has never run it either; it has merely seen a great deal of code that looked like
it.

**Untrained user.** *"Copilot generated the OTP endpoint. The code looks right."*

**Trained in this course.** *"I ran the endpoint. A second request with the same e-mail
address within 60 seconds returned a new code instead of being refused. The specification
(REQ-006) says one code per minute. The traceback and the two responses are pasted below.
I fixed it with a timestamp check and added a test."*

**In the log.** Record the command you ran, the output (pasted and trimmed), and the fix.

**In this course.** The first run is always `python .github/check_deliverables.py`, before
the pushes at 10:00, 11:00 and at the end of the lecture (11:45) and before Saturday 23:59. A red check is evidence, so
paste it. The second run is on your own phone: the application narrowed to a phone width
is a requirement in every week, not a task left for Week 10.

---

## 3. The hostile reviewer

**What.** Give the assistant your own work together with a role: the investor who wants to
say no, the store reviewer who wants to reject the application, or the tester who wants to
break it. Ask for the three strongest objections, numbered. Then **answer one of them** in
the document and **show that one of them is wrong**, with evidence.

**Why.** A model that is asked "Is this good?" says yes. A model that is asked "Why will
this fail?" produces a list, and roughly one item in three is a real problem you had not
seen. The other two are where you learn to disagree with it, with reasons.

**Untrained user.** *"I asked ChatGPT to review my proposal. It gave useful feedback, which
I applied."*

**Trained in this course.** *"Objection 2 was: 'Nobody will enter a reservation by hand;
they will just walk in.' This is true for the ground-floor rooms, so I added a QR check-in
to §4. Objection 3 was: 'The library already has a booking system.' I checked: the Atlas
library has none (I asked at the desk on 2026-10-07). I kept the project and wrote the
check into §9."*

**In the log.** Record the three objections verbatim, which one you answered and where,
and which one you refuted and with what evidence.

**In this course.** You have two hostile reviewers every week, and their comments go into
different files. The other members of your group hear you in the weekly online
meeting; their sentences, quoted, together with your `accepted: true/false` and `why`, go
into `weekNN/group_NN.json`. The assistant's objections go into `ai_log_NN.md`. Put
the two side by side. Where the assistant and your group disagree, the people are usually
right about *your* users and the assistant is usually right about the market or the
technology; say which is the case, and why, in the `why` field. In Week 3 the reviewers
were the people in the room (slide 7); in Week 11 the role is the store reviewer, using the
store's own rejection reasons from `AI_PLATFORMS_AND_STORES`.

---

## 4. Cross-examination: two assistants, one prompt

**What.** Give two different assistants exactly the same prompt and the same source text.
Compare the two answers with each other and with what you already know.

**Why.** Where two models agree, you have a candidate, not a fact. Where they disagree, at
least one of them is wrong, and finding out which one is the fastest route to a real error
with real evidence. This is the Week 2 technique, and it remains useful for the whole term.

**Untrained user.** *"Both gave similar requirements, so I merged them."*

**Trained in this course.** *"Claude wrote: 'The reservation expires after 15 minutes
without check-in.' Gemini wrote: 'after 2 hours.' Neither asked me. The right number is in
my §3: the problem is rooms held all afternoon by people who have left, so 15 minutes is
correct. I made it REQ-004 with my own acceptance test."*

**In the log.** Record the prompt once, the two answers side by side (trimmed), and the
decision.

**In this course.** This was the Week 2 exercise: the same §3–§4 given to two assistants,
eight requirements from each, and one wrong requirement found. The technique returns
whenever two answers are cheap and the truth is in your own documents, for example the
data model in Week 5 and the test plan in Week 9. The two assistants must be two of those
you set up in Week 1 (`AI_SETUP_CARD`); the free tiers are sufficient.

---

## 5. Make it cite, and let it say "I don't know"

**What.** Ask for the source of every factual claim: a document, a page, or a line of your
own code. Tell the assistant explicitly that "I don't know" is an acceptable answer. Then
**open the source**.

**Why.** Models produce references with the same fluency as everything else, and a
proportion of those references do not exist. A fact you did not check is not a fact you
know.

**Untrained user.** *"According to the AI, Google Play review takes one to three days."*

**Trained in this course.** *"I asked for the source of 'one to three days'. It gave a Play
Console help page. I opened the page (2026-10-08): it says that review 'can take up to 7
days or longer for new developer accounts'. §12 now says 7 days and cites the page. I asked
Gemini the same question; it said that it did not have a current figure, which was the
better answer."*

**In the log.** Record the claim, the source the assistant gave, and what the source
actually says.

**In this course.** In Weeks 3 and 10, every number in `PROPOSAL.md` §8–§12 and in the UAT
report, including store fees, review times and market sizes, carries the page or the
person it came from, with a date.

---

## 6. Small diffs: one change at a time, and read it

**What.** Ask for one change, not a rewrite. Read the diff before you accept it, all of it,
including the lines you did not ask to change. Commit each accepted change on its own.

**Why.** "Refactor this file" returns a file in which three things you did not request have
changed, one of them silently. A diff you can read in two minutes is a diff you can take
responsibility for. This is also what makes your commit history readable when the
week's commit-discipline point is given.

**Untrained user.** *"I asked Copilot to clean up `app.py`, accepted the result, and
pushed."*

**Trained in this course.** *"I asked only for the unused imports to be removed. The diff
also changed the OTP length from six digits to four, which I had not requested and which
was not mentioned. I rejected that hunk and kept the import changes. `ruff` confirms the
result; commit `e41c…` contains the import changes only."*

**In the log.** Record the change you asked for, the change you received, and what you
refused.

**In this course.** This is what the weekly commit-discipline point looks for: several
commits made as you work, each one a change you can name in
its message (for example `week05: OTP expiry check, test added`), and no single
Saturday-night dump that could have been pasted in whole. Run `ruff check .` before every
commit. A key in a commit costs ten points and a revoked key, as described in the workflow
document.

---

## 7. Consistency across the three tiers

**What.** When the same feature exists in the server, the web client and the mobile client,
give the assistant all three and ask it to find the inconsistencies. Then verify the one it
finds, and look for the one it missed.

**Why.** Three generated pieces of code are each consistent with themselves and not with
each other: a field named `room_id` on the server and `roomId` in the application, or a
status the server can return that no client handles. Models are good at spotting these
when asked to, and of no use when not asked.

**Untrained user.** *"Everything works on all three."*

**Trained in this course.** *"I asked for mismatches across `server/api.py`, `web/app.js`
and `mobile/api.dart`. It found `checked_in` versus `checkedIn`, which was real, and I
fixed it. It missed that the server returns `409 Conflict` for a double booking while the
mobile client treats anything other than 200 as a 'network error'. I found that by testing
(technique 2) and added the handling."*

**In the log.** Record what the assistant found, what you verified, what it missed, and how
you found it.

**In this course.** Week 8 is the week in which the project's own core feature runs on all
three tiers (server, web and mobile), and the end-of-session check reads all three. Bring
the mismatch you found to the group meeting: the other members have the same three
tiers and usually the same class of mistake.

---

## 8. Predicted versus observed

**What.** Before a test with people (the Week 9 beta test and the Week 10 UAT), ask the
assistant what will go wrong, and write the prediction down. After the test, place the
testers' real bug list next to it.

**Why.** This is the cleanest measurement in the course of what a model knows about your
users: usually something, never everything. The gap is the evidence that human testing was
not optional, and it is the paragraph that makes your test report worth reading.

**Untrained user.** *"The testers found some bugs, which I fixed."*

**Trained in this course.** *"Predicted (five items): the login code not arriving, a slow
list, and so on. Observed (seven items from five testers): two of the five predicted items
occurred, and the most frequent complaint, 'I cannot tell which room is mine on the map',
was in nobody's prediction. The table is in `docs/test_report.md`."*

**In the log.** Record the prediction (dated, before the test), the observed list, and the
overlap between them.

**In this course.** Your testers are the five people on slide 3 of `PITCH_03.md`. They are
not your group of four, who are your reviewers, and not your contributors from Week 2. The
prediction is dated in `ai_log_08.md` before the Week 9 lecture; the testers' list is kept
in `week09/` and the UAT report in `week10/`; the store's test track (S3–S4) is where the
testers install the application from. Five real people who could not use the product is
the finding of the term, and it is the reason the second rule of this course exists.

---

## 9. The decision record: what the log is for

Your `weekNN/ai_log_NN.md` is **not a chat transcript**, and it is not a diary of how much
you used AI. It is an engineering record of one decision per week, in four parts:

| Part | The question it answers | It fails when it says |
|---|---|---|
| **Used for** | Which assistant, which prompt, and on which of your files? | "I used ChatGPT for the proposal." |
| **Got right** | What did you keep, and why was it right? | "It was helpful." |
| **Got wrong** | One concrete error, produced by the technique of the week | "Some things were not relevant." |
| **Evidence and fix** | The pasted output, and the change you made by hand | Nothing is pasted; "I fixed it." |

The **Evidence** block is the part a person reads first. It is pasted, trimmed to the lines
that matter, and it shows the error rather than describing it. A log with no evidence earns
nothing, however long it is.

**The people in the loop.** The assistant is not your only reviewer, and it must not become
the only one. Every week, between the lecture and Saturday, your group meets
online for one hour: each member shows what has changed, and the others say what they
think. Bring that week's assistant error to the meeting; the question "Did it fool you
too?" is the fastest cross-check available. The entries in
`weekNN/group_NN.json` are those people, quoted; the assistant has no entry
there. One student, one computer, one GitHub account: a log written on a classmate's
machine is not yours. Questions to me are sent as an issue in your own repository, which I
read on Sundays.

### Four risks that are not about correctness

A perfectly correct answer can still be the wrong thing to have asked for, or the wrong
thing to have pushed. Four such risks arise in this project, each in a particular week.

**Security.** Generated code likes to log things. In Week 6, a login endpoint that prints
every login code to the console "for debugging" has leaked every login to anyone who can
read the server log. A login that accepts unlimited guesses lets anyone try every
six-digit code, and the assistant that wrote it did not think of that user. An API key
committed to the repository costs ten points and must be revoked, whoever wrote the line.
Read generated code for what it *sends* and what it *stores*, not only for what it
returns.

**Personal data.** The five people on slide 3, your testers' names and e-mail addresses in
Week 9, and the student numbers in `contributors_NN.json` and `group_NN.json` must never
be placed in a prompt to a hosted assistant. Describe the person ("a second-year classmate
who works in the evenings"); do not paste the person. The rule you already follow for the
repository, no names and no numbers of other people, applies to the chat window as well.

**Stale knowledge.** Every model was trained on data up to a certain date; mobile
frameworks and store rules keep changing after that date. An assistant will write code for
a version of the Expo SDK or the Flutter API that has since been replaced, and the code will
not compile. It will quote a Play Console policy that has since changed. Treat every version
number and every store rule it gives you as a claim to be verified against the official
page, and note the date on which you checked (§5). When the error message you receive does
not match what the assistant said would happen, it is the model that is out of date, not
you.

**Provenance.** Code produced by an assistant may be a close copy of code that someone
else published under a licence, which you would then be breaking without knowing it. For this project the rule is simple: nothing longer than a function that you did
not write and cannot explain line by line goes into the repository, and a library enters
through `requirements.txt` with its name and version rather than being pasted in. In the
defence you will be asked why a given block of code is there, and "the assistant wrote it"
is not an answer. The push is yours, so the code is yours.

The log also carries two further rules:

- **A changed plan is written down.** A requirement you drop, a tier you simplify, or a
  store you switch to is recorded as one dated line in the Change log of `PROPOSAL.md`, or
  as one line in the AI log, with the reason. Changing your mind is engineering; changing
  it silently is not.
- **Some things are not done with an assistant at all.** Your pitch (`PITCH_03.md`), the
  last time the problem happened to you, the five people who will test your product, and
  the sentences your reviewers wrote and what you decided about them are all written by
  you alone. They concern your life and your people; an assistant cannot know them, and I
  will ask about them. **The AI log itself is on this list.** Everything in
  `ai_log_NN.md` outside the Evidence block is written by you, in your own words, and
  the assistant is not used even to improve the language. Your English or Turkish is
  not graded; a log in plain, imperfect sentences earns full marks, a log written by an
  assistant earns 0 from Week 4 on (at most 1 in Weeks 1–3). The Evidence block is the one place where the
  assistant's words belong, pasted exactly as it wrote them.

---

## 10. The term, technique by technique

| Week | Deliverable the technique serves | Compulsory technique |
|---|---|---|
| 2 | Proposal Part A, requirements | §4 Cross-examination |
| 3 | Proposal Part B | §3 The hostile reviewer (the investor) |
| 4 | Clickable prototype, test cases from the acceptance criteria | §1 Acceptance criteria first |
| 5 | Design, API contract, server skeleton, login tests | §2 Verify by running |
| 6 | The login by e-mail code, the web login screen | §3 The hostile reviewer (the attacker) |
| 7 | The mobile client, tests, CI | §6 Small diffs |
| 8 | Core feature on all three tiers | §7 Consistency across the tiers |
| 9 | Beta test, bug list, test report | §8 Predicted versus observed |
| 10 | UAT report, submission | §5 Make it cite, applied to your own claims |
| 11 | Release, review fixes | §3 The hostile reviewer (the store reviewer) |
| 12 | Closure, poster | §9 The term's log in retrospect: which error cost the most |

Any other technique is welcome in any week in addition to the compulsory one. The week's
`ai_log_NN.md` scaffold names its technique at the top, and the week's `ASSIGNMENT_NN`
refers to this document. The two human-marked points of every week, the AI log, are read
against this table: the technique of the week, applied, with the evidence pasted. The
group meeting and `group_NN.json` are read alongside it.

---

## 11. What you can do in Week 14 that you could not do in Week 1

Each line below is a claim you can test on yourself, and each one marks a point at which
one of the four people in §0 is separated from the others.

1. Given a product idea, you can state what it must do and what it must not do, as
   numbered requirements with acceptance criteria, and hand those to an assistant *before*
   it writes a single line (§1, Weeks 2–4).
2. You can read a few dozen generated lines and say which requirement each part serves and which
   case it does not handle (§1, §2, Week 5).
3. You can tell a running program from a plausible one, because you ran it, and you can
   produce the output that shows the difference (§2).
4. You can take three strong objections to your own work, answer one of them in the
   document, and show that one of them is wrong by citing a source (§3, Weeks 3 and 11).
5. You can set two assistants against each other and find the one wrong answer, with the
   reason it is wrong taken from your own documents (§4).
6. You can tell a cited fact from an invented one, because you opened the source and dated
   it (§5, Weeks 3 and 10).
7. You can accept the change you asked for and refuse the one you did not, within the same
   diff, and your history shows a week of named changes rather than one dump (§6, the
   weekly commit-discipline point).
8. You can find where three generated tiers disagree with each other, verify what the
   assistant found, and catch what it missed (§7, Week 8).
9. You can write down what will go wrong before five real people test your product, and
   place their list next to yours afterwards (§8, Weeks 9–10).
10. You can keep your users' and classmates' names, numbers and e-mail addresses out of a
    hosted assistant, and keep a key out of a repository, as a habit rather than as a rule
    (§9).
11. You can say which version number and which store rule given to you by an assistant is
    out of date, and where you checked (§9).
12. You can stand in front of an examiner with the application installed from the store and
    answer the question "Why is this here?" for any line of it, because the push was yours
    and the record exists (§9, Weeks 13–14).

The untrained user with an assistant can do none of these things and does not know it.
The engineer without the discipline can do most of them and does not do them. The purpose
of the twelve weeks is to make the right-hand column of §0 the thing you do without
thinking.

---

## 12. The short version

Write the test before the prompt. Run whatever can be run. Ask why it will fail, not
whether it is good. Make two assistants disagree. Make the assistant cite its source, and
open the citation. Change one thing at a time, and read the diff. Put the prediction next
to the result. Write down the decision, paste the evidence, and keep your own life out of
the assistant's hands.

The push is yours, so the code is yours: in the defence, "the assistant wrote it" is not an
answer to "Why is this here?". An assistant that is never caught being wrong is not a good
assistant; it is an assistant that nobody checked.
