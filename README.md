# The Unofficial Guide

<!-- Replace this line with your name and which corpus you picked. -->

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

<!-- Three or four sentences. Which corpus you picked, and the kinds of
     questions your system answers. Write it for someone who has never seen
     this repo.

     Milestone 5. -->

## Chunking Strategy

**Chunk size:** 250 body characters maximum, 90 minimum, produced by
`chunker.py::split_documents`. "Body" means the text under the title line — the
title is repeated into every chunk and doesn't count against the budget. Real
output: 134 chunks from 88 documents, 217 characters on average, shortest 103,
longest 397.

**Overlap:** none. The title line is repeated instead.

The starter's 800-character window made 88 chunks out of 88 documents — it
never cut anything, because the longest document in `campus_life` is 549
characters and the average is 317. That isn't a bug, it's the finding: for these
documents, one post already is one chunk. The question is whether that's right,
and for about half of them it isn't. Kestrel Commons is one paragraph about
queues and stir-fry and a second about opening hours and the price of a swipe.
As a single chunk it matches a question about hours weakly and a question about
queues weakly. So: **split on paragraph breaks**, which in this corpus are where
the thoughts change.

Paragraph splitting alone would have been worse than what I started with. There
are 183 body paragraphs and 99 of them are under 120 characters — splitting on
every break turns half the index into fragments like *"Expect 4 hours a week
outside class."* So paragraphs are **packed**: they accumulate until the body
passes 250, and anything left under the floor merges back into the chunk before
it instead of being emitted alone. 250 because the median paragraph is 112
characters, so 250 holds the common two-short-paragraph case together while
still cutting a document that holds two separate thoughts. No paragraph is ever
cut open — the longest one in the corpus is 373 characters, and there is a hard
ceiling of 600 above which a paragraph would be split on sentence boundaries,
which never fires here.

**Overlap is zero, and that's a change from the starter's 120.** Overlap exists
to heal a cut that lands mid-sentence. My chunker only cuts at paragraph breaks,
so there is no cut to heal, and character overlap would drag a half-sentence
from the next paragraph onto the end of every chunk. What neighbouring chunks
share instead is the title line, because that is the context that actually goes
missing when you split one of these documents.

**The title line on every chunk is the part I'd defend hardest.** The seven
laundry documents are word-for-word identical apart from their first line and
one price line — *"There are eight washers and six dryers for the building,
which is the wrong ratio"* appears in all seven, verbatim. Take the second
paragraph of one of them on its own and nothing in the text says which building
it is. Not for a reader, and not for an embedding. The same is true of the 21
housing documents and the 27 course documents, which follow templates just as
closely.

**I changed my mind once, and the first version was wrong in an instructive
way.** I set the floor at 120 characters, ran it, and Kestrel Commons came out
whole — the exact document I'd written the splitter for. Its second paragraph is
101 characters, under the floor, so the "no orphan tails" rule glued it back on.
The floor was doing the opposite of its job: it was meant to stop fragments, and
instead it was swallowing complete thoughts. *"Hours are 7:00am to 9:00pm
weekdays, 9:00am to 8:00pm weekends. Costs one meal swipe, or $12.50 cash."* is
two complete sentences and answers a real question. Reading the paragraphs by
length showed the line sits lower than I guessed: under 60 characters they're
one-liners with no retrievable signal alone, and by 90 they're reliably two full
sentences. The floor moved to 90 and the corpus went from 111 chunks to 134.

There was also a measurement bug behind it. I was counting a group's length as
the sum of its paragraphs plus two characters per paragraph for the blank-line
join, which over-counts a single-paragraph group by two — a 119-character
paragraph measured as 121 and cleared a 120 floor it should have failed. The
length is now computed from the joined string, the thing actually being stored.

## Sample Chunks

### Chunk 1 — A document that came apart — the queue half

`source: dining_kestrel_commons.txt#0` · `produced by: chunker.py::split_documents`

```
Kestrel Commons

I'm a junior and I've done this twice now. Wait times: 20 to 25 minutes between 12:15 and 1:00, under 5 minutes before 11:45. The thing worth going for is the stir-fry station, made to order. The thing to know is that the salad bar wilts after 1:30.
```

### Chunk 2 — The other half of the same document

`source: dining_kestrel_commons.txt#1` · `produced by: chunker.py::split_documents`

```
Kestrel Commons

Hours are 7:00am to 9:00pm weekdays, 9:00am to 8:00pm weekends. Costs one meal swipe, or $12.50 cash.
```

### Chunk 3 — Why the title line is repeated

`source: housing_aldridge_hall_laundry.txt#0` · `produced by: chunker.py::split_documents`

```
Laundry in Aldridge Hall

Machines take $1.75 wash, $1.50 dry, card only. There are eight washers and six dryers for the building, which is the wrong ratio and means the dryers back up on Sunday evenings.
```

### Chunk 4 — A one-line paragraph packed with its neighbour

`source: course_econ_101.txt#0` · `produced by: chunker.py::split_documents`

```
ECON 101 Introduction to Economics

Took this last spring. Format is large lecture, 300 people, with small discussion sections. Assessment: two midterms and a final, all multiple choice. Curved, and generously.

Expect 4 hours a week outside class.
```

### Chunk 5 — A document left whole

`source: admin_housing_lottery.txt#0` · `produced by: chunker.py::split_documents`

```
On the housing lottery

The housing lottery is not random in the way most people assume. Rising sophomores get a number drawn at random, but juniors and seniors are ordered by accumulated credit hours first, and only tie-break randomly. That means a senior who took summer courses reliably beats a senior who didn't. Numbers come out the second week of March and selection runs over four evenings.
```

## Sample Answer

<!-- One complete question and answer, pasted as text, with the source line
     visible. Milestone 4. -->

**Question:**

**Answer:**

```
```

**My relevance cutoff:**

<!-- The number you set in config.py, and how you got there.

     You ran five questions your corpus covers and the five in OUT_OF_SCOPE
     that it clearly doesn't, and wrote down the best distance for each. What
     did those two groups look like? Where was the gap? Put the actual numbers
     here — the table below wants all ten rows.

     Milestone 4. -->

| Question | In corpus? | Best distance |
|---|---|---|
|  |  |  |

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
