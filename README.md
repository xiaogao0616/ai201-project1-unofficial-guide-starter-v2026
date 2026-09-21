# The Unofficial Guide

Name: Xiangyi Gao
Corpus: campus_life

> **This file is your submission.** Fill it in as you go — most sections get
> written during the milestone that produces them, not at the end.
>
> How the starter works, and every command you'll need, is in `RUNNING.md`.
> Leave that file alone.
>
> **Paste everything as text.** No screenshots, no video. A typed table gets
> full credit; a picture of the same table gets none.
>
> Delete these instruction blocks as you replace them. The `<!-- -->` comments
> are notes to you and don't show up when the page renders — you can leave them
> or remove them.

---

# Unit 1

## What This Does

The Unofficial Guide is a retrieval-based question-answering system using the `campus_life` corpus of 88 short documents. It answers questions about campus policies, course assessments, library hours, housing, and other topics covered by those documents. The system retrieves document chunks and asks a language model to answer using only those excerpts, with source filenames. A relevance gate stops questions whose best retrieval distance exceeds the cutoff; this reduces unsupported answers but does not guarantee that every accepted question is answerable.

## Milestones 1 and 2 — Setup and Evaluation Targets

**Milestone 1:** I selected `campus_life` and indexed 88 documents containing 27,908 characters. The starter produced 88 chunks, averaging 317 characters, with a minimum of 178 and a maximum of 549. This showed that the starter's 800-character windows kept these short documents intact. Before replacing the chunker, I also ran the separate `advice_threads` sample command and recorded its total of 26 chunks.

**Milestone 2:** I wrote five factual test questions in `questions.py`, covering major declaration, printing credit, study abroad applications, CS 340 exams, and library hours, each with an `expects` phrase. I retained five `OUT_OF_SCOPE` questions for testing refusals. My five targets are recorded in `criteria.md`: answer-containing retrieval for at least 4 of 5 questions, a source for every answer, refusal of at least 4 of 5 out-of-scope questions, chunk lengths of 100–500 characters, and the expected phrase in at least 4 of 5 final answers. These are targets, not claims that all five criteria have passed the Unit 2 evaluation.

## Chunking Strategy

**Chunk size:** Up to 500 characters for the current campus_life corpus. Posts of 500 characters or fewer remain intact. Longer posts are split at paragraph boundaries.

**Overlap:** No fixed character overlap. For split posts, the title is repeated at the beginning of each subsequent chunk to preserve context.

The campus_life corpus contains 88 short documents, averaging about 317 characters each. Most posts already describe one topic, so I keep them intact rather than splitting them unnecessarily. Two housing posts exceeded 500 characters and contained clear paragraph breaks, making paragraph-based splitting suitable.

My function, `chunker.py::split_documents`, combines consecutive paragraphs until adding another would exceed 500 characters. It then starts a new chunk with the same title, so details such as laundry costs remain associated with the correct residence hall.

The starter produced 88 chunks, ranging from 178 to 549 characters. My strategy produced 90 chunks, averaging 310 characters, with a minimum of 170 and a maximum of 461. A check of all chunks found no violations of my 100–500 character criterion.

This strategy assumes that a long post begins with a title and has short paragraphs, as observed in the two long housing posts. It does not yet handle a single paragraph that is too long to fit with the title.

## Sample Chunks

**Chunk 1** — source: `admin_add_drop_deadline.txt#0` — produced by: `chunker.py::split_documents`

```text
On the add/drop deadline

You can add a course through the end of the second week. Dropping is a longer window — through the end of week six — but a drop after week two shows as a W on your transcript. Nothing anywhere on the registrar's site says this plainly, and students find out from each other.
```

**Chunk 2** — source: `course_biol_160_exams.txt#0` — produced by: `chunker.py::split_documents`

```text
BIOL 160 Cell Biology — assessment

Four unit tests and a cumulative final. Not curved.

The unit tests come fast, roughly every three weeks; falling behind once is very hard to recover from.
```

**Chunk 3** — source: `course_math_220_exams.txt#0` — produced by: `chunker.py::split_documents`

```text
MATH 220 Linear Algebra — assessment

Two midterms and a cumulative final. Curved to a b- median.

The problem sets are the course; the lectures make sense afterwards rather than during.
```

**Chunk 4** — source: `dining_the_ridgeway_cafe.txt#0` — produced by: `chunker.py::split_documents`

```text
The Ridgeway Café

Second-year here. Wait times: 10 to 15 minutes at 12:30, none after 2:00. The thing worth going for is the only place on campus with real espresso. The thing to know is that seating is tight; about 40 seats for a building of 900.

Hours are 7:00am to 4:00pm weekdays only. Costs declining balance only, no meal swipes.
```

**Chunk 5** — source: `housing_morrow_house.txt#0` — produced by: `chunker.py::split_documents`

```text
Morrow House — what it's actually like

Just finished a year in this building. Built 1954, partially renovated 2008. Rooms are singles and doubles, hall bathrooms.

The good: cheapest housing tier by about $900 a year, and the singles are real singles.

The bad: known damp problem on the ground floor; two rooms were taken offline in 2024.

Laundry costs $1.50 wash, $1.25 dry, coin or card. On noise: loud until about 1am on weekends, no enforced quiet hours.
```

## Sample Answer

**Question:** How many exams does CS 340 have?

**Answer:**

```text
CS 340 has one midterm and a final.

Sources: `course_cs_340_exams.txt` and `course_cs_340.txt`
```

**My relevance cutoff:** `0.6` (the starter value, retained after measurement).

The five in-corpus questions had best distances from 0.3075 to 0.3926. The five out-of-scope questions had best distances from 0.8246 to 0.9340. The cutoff of 0.6 falls between these groups: all five in-corpus questions passed the gate, and all five out-of-scope questions were blocked. These results support keeping 0.6 for this test set, but do not establish how well it handles unseen questions, especially campus-related questions that the documents do not answer.

I retained the five-result retrieval setting. I inspected the assembled prompt and grounding instruction with `--show-prompt`: it requires using only the provided documents, admitting missing information, and naming source files. In the CS 340 example, the answer used the correct course's exam information despite CS 210 excerpts also appearing in the prompt. I left the grounding instruction unchanged after this check.

| Question | In corpus? | Best distance |
|---|---|---|
| By when must students declare their major? | Yes | 0.3871 |
| How much campus printing credit does each student receive? | Yes | 0.3758 |
| When should students apply for a study abroad program? | Yes | 0.3339 |
| How many exams does CS 340 have? | Yes | 0.3075 |
| What are the library's hours during the term and during reading week? | Yes | 0.3926 |
| What is the capital of Mongolia? | No | 0.8246 |
| How do I change the oil in a diesel engine? | No | 0.9340 |
| Who won the 1994 World Cup? | No | 0.8859 |
| What is the recommended dosage of ibuprofen for a headache? | No | 0.8442 |
| How do I write a for loop in Rust? | No | 0.8960 |

**Out-of-scope check:**

```text
Question: What is the capital of Mongolia?
(best distance 0.825, cutoff 0.6)

I don't have enough information about that.

0 model calls this session
```

## How I Used AI

<!-- Two specific moments. For each: what you asked for, what came back, and
     what you changed about it.

     "I asked Claude to write the chunking function from my notes. It ignored
     the overlap, so I added that myself" is the level of detail we're after.
     "I used AI to help me code" is not.

     Milestone 5. -->

**1.**

**2.**

<!-- ── Stretch features ─────────────────────────────────────────────────────
     Doing one? Say so here BEFORE you start. A feature this README never
     claims earns nothing.
     ───────────────────────────────────────────────────────────────────────── -->

---

# Unit 2

<!-- These sections get ADDED to what's already above. Don't delete or rewrite
     unit 1 — the point is that someone can see what you said before you knew
     how it went. -->

## Run Log — Before

<!-- Your five criteria, three runs each. `python run_eval.py --label before`
     runs the questions, puts the OUT_OF_SCOPE ones through the gate, and
     writes it all into results/ for you. Targets come from criteria.md; the
     verdict column is your call.

     Criterion 3 is measured in one deterministic pass rather than three, so
     the same number goes in all three run columns. That's correct, not lazy.

     Milestone 1. -->

| Criterion | Target | Run 1 | Run 2 | Run 3 | Verdict |
|---|---|---|---|---|---|
| 1. Retrieved chunk contains the answer | 4 of 5 |  |  |  |  |
| 2. Every answer names a source | 5 of 5 |  |  |  |  |
| 3. Gate stops out-of-corpus questions | 4 of 5 |  |  |  |  |
| 4. | | | | | |
| 5. | | | | | |

<!-- Underneath, paste the REAL output for each criterion from one of your
     runs — the actual text your system produced, not a description of it.
     Name the file and function that produced it. -->

## Verdicts

<!-- MET or MISSED for each of the five, against the target you wrote last
     unit — not a new one. Plus a sentence on how you decided. That sentence
     matters most where it was close.

     If your target said 4 of 5 and your runs came out 4, 3, 4, that's a MISS.
     The target has to hold, not show up occasionally.

     Milestone 2. -->

| # | Criterion | Verdict | How I decided |
|---|---|---|---|
| 1 |  |  |  |
| 2 |  |  |  |
| 3 |  |  |  |
| 4 |  |  |  |
| 5 |  |  |  |

## Diagnoses

<!-- For each miss: which stage caused it, and how. The stage alone isn't
     enough — you need the mechanism.

     Not a diagnosis: "Question 3 didn't work."
     A diagnosis:     "Question 3 asks about laundry costs. The answer is in
                       one sentence that got split across two chunks, so
                       neither chunk on its own contains it."

     The five stages: loading → chunking → embedding → retrieval → generation.

     Look for a pattern. If three misses all ask about numbers, that's one
     problem, not three.

     Missed nothing? Say so, then say honestly whether your targets were set
     low, and which one you'd tighten and to what.

     Milestone 3. -->

## The Improvement

**What I changed:**

**Why I picked it:**

<!-- Connect it to a specific diagnosis above in one sentence. If you can't,
     you picked a fix because it sounded impressive. -->

### Run Log — After

<!-- Same format, same five criteria, three runs each.
     `python run_eval.py --label after` -->

| Criterion | Target | Run 1 | Run 2 | Run 3 | Verdict |
|---|---|---|---|---|---|
| 1. Retrieved chunk contains the answer | 4 of 5 |  |  |  |  |
| 2. Every answer names a source | 5 of 5 |  |  |  |  |
| 3. Gate stops out-of-corpus questions | 4 of 5 |  |  |  |  |
| 4. | | | | | |
| 5. | | | | | |

**Did it help?**

<!-- Say plainly whether it did, and how you know. If it made things worse,
     say that — a change that backfired, honestly reported, earns full credit
     and is more interesting than one that worked. What matters is that you can
     tell.

     Milestone 4. -->

## What's Still Broken

<!-- For each criterion still missed after your fix: what you'd do about it,
     and why you stopped where you did.

     "I ran out of time" is fine if it's true. Pretending nothing is left is
     not.

     Milestone 5. -->

## What I'd Do Differently

<!-- Knowing what you know now — which of your five criteria would you write
     differently, and why?

     Milestone 5. -->
