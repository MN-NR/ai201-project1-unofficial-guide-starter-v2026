# Acceptance criteria — The Unofficial Guide

Five criteria that say what "working" means for this system, written in unit 1
**before** any results existed.

An acceptance criterion names a target: a number, a count, a rate, or something
a person could plainly observe. *"Retrieval works"* is an opinion. *"For at
least 4 of my 5 test questions, the top results include a chunk containing the
answer"* is a criterion.

Under each one, write a sentence or two on **why that target** and not a
stricter or looser one. A reason that says something about your corpus or your
pipeline earns credit; *"80% seemed reasonable"* does not.

> Missing your own targets next unit costs you nothing. Setting a target so
> easy you can't miss it does.

---

## 1. Retrieved chunks contain the answer

For at least 4 of my 5 test questions, the retrieved chunks include one that
contains the answer.

**Why this target:**
My questions cover transport, accessibility, seasons, and walking, and several
of the guides reuse the same town names and regional terms. I chose 4 of 5
because the system should retrieve the correct section most of the time while
allowing for one question whose wording matches several related guides.

---

## 2. Every answer names a source

Every answer the system produces names at least one source document.

**Why this target:**
Every retrieved chunk keeps its source filename, so the model has the
information needed to cite a source for every answer. I chose all answers
rather than 4 of 5 because an uncited travel answer cannot be checked against
the guide and should not be treated as successfully grounded.

---

## 3. The relevance gate stops out-of-corpus questions

When I ask a question my documents clearly don't cover, the relevance gate
stops it and the system returns "I don't have enough information about that" —
in at least 4 of 5 tries.

<!-- The five questions are the ones in `OUT_OF_SCOPE` at the bottom of
     `questions.py`, and `run_eval.py` puts them through the gate and writes
     what happened into your run log. Swap them for your own if you'd rather —
     just keep five of them, or the "4 of 5" above has nothing to be 4 of. -->

**Why this target:**
The five out-of-scope questions concern topics far outside regional travel, so
the gate should reject nearly all of them. I chose 4 of 5 instead of all five
because semantic retrieval can occasionally match a generic word or phrase in
an unrelated question even when the documents do not contain its answer.

---

## 4. Something about your chunks

<!-- YOU WRITE THIS ONE.

     How would you know if your chunks were the right size? Name something
     countable or observable.

     Examples of the right shape — don't copy these, they should come from
     what you actually saw in Milestone 3:
       - "At least 4 of 5 sampled chunks read as a complete thought, with no
          sentence cut in half at either end."
       - "No chunk is shorter than 200 characters, since anything below that
          in my corpus turned out to be a heading with no content under it." -->

At least 4 of 5 sampled chunks begin and end with complete sentences and
contain either a section heading or an explicit place name that identifies the
chunk's subject.

**Why this target:**
All five chunks I inspected from the fallback chunker had a sentence fragment
at one or both boundaries, including endings such as "15-", "mino", and
"grou". I chose 4 of 5 because the city guides are organized into sections
and paragraphs, so a paragraph-aware chunker should preserve context while
allowing for one unusually long or difficult section.

---

## 5. Your choice

<!-- YOU WRITE THIS ONE TOO.

     Pick something you actually care about getting right. It could be about
     speed, about refusals, about a particular kind of question your corpus
     handles badly, about source attribution being correct rather than merely
     present — anything, as long as it names a number or an observable
     outcome. -->

For at least 4 of my 5 test questions, every source named in the answer is one
of the retrieved source documents and contains the fact used in the answer.

**Why this target:**
Criterion 2 checks only whether a source name is present, but a citation is
useful only when it actually supports the answer. I chose 4 of 5 because facts
about the same town can appear in several regional guides, which makes one
source-attribution mistake possible while still requiring reliable citations
for most questions.

---

<!-- ─────────────────────────────────────────────────────────────────────────
     UNIT 2 — read this before you change anything above.

     If a criterion turns out to be BROKEN rather than merely unmet, you can
     revise it, and that earns credit. But never delete or edit the original
     line. Add the revision underneath it, like this:

         ## 1. Retrieved chunks contain the answer

         For at least 4 of my 5 test questions, the retrieved chunks include
         one that contains the answer.

         **Why this target:** ...

         > **Revised in unit 2:** For at least 4 of 5 questions, the top three
         > results contain the answer.
         >
         > **Why revised:** I couldn't judge "the chunks include one that
         > contains the answer" the same way twice — I scored two questions
         > differently on Monday than on Wednesday. The new version is
         > something I can actually check.

     That's a revision because the criterion couldn't be MEASURED.

     Lowering a target because you missed it is not a revision, and it costs
     you the point:

         ✗ "I said 4 of 5 but got 2 of 5, so 2 of 5 is more realistic."

     A number you missed stays where it is, gets diagnosed, and gets a fix
     attempted. That's where the points are.

     The whole reason the originals stay visible is so someone can see what you
     said before you knew the answer.
     ───────────────────────────────────────────────────────────────────────── -->
