---
name: scientific-method-debugging
description: Use when debugging a failure that requires runtime observation before forming causal hypotheses.
---

# Empirical Debugger

You are debugging a failure. The single rule that overrides everything else:

**Make the system show you what's happening. Then form fine-grained hypotheses. Never the other way around.**

---

## The mindset

Reasoning about code in your head is unreliable. The running system is the source of truth. Your job is to find the fastest way to get the system to reveal the root cause — not to think hard enough that you can figure it out without running anything.

---

## Step 1 — Form a coarse hypothesis to guide where you look

Before instrumenting anything, it is fine — and useful — to have a rough idea of which part of the system is involved. This is not a hypothesis about *what* is wrong, but about *where to look*:

- "The bug is somewhere in the server-side annotation pipeline"
- "The classify function may be returning the wrong tag"
- "The data might be wrong by the time it reaches the DB"

This coarse hypothesis guides where you instrument. It does not commit you to an explanation. You will discard or revise it as soon as the data says otherwise.

---

## Step 2 — Observe before hypothesizing about causes

Ask: *"What does the system actually produce at each stage of the area I'm examining?"*

Get that data first. The right tool depends on the problem:
- Server-side pipeline bug → add logging at every intermediate variable and ask the user to trigger the failure
- Client-side UI bug → open Chrome, check the console and network tab
- Wrong DB state → query the table directly
- Unexpected function output → write a quick test or REPL snippet
- API contract mismatch → curl the endpoint and inspect the raw response

**Instrument broadly within your coarse hypothesis scope.** If you are not sure whether a variable matters, observe it anyway. Selective instrumentation based on a hunch is just theorizing with extra steps.

**Ask the user to run it** when you can't trigger it yourself. Give them exactly what to do.

---

## Step 3 — Fine-grained hypotheses from data

Only after you have observed actual output:

1. List every anomaly you see. Each anomaly is a hypothesis candidate.
2. For each hypothesis: what is wrong, where in the pipeline did it go wrong, and what would the correct value be?
3. For each hypothesis: can you verify or reject it from data you already have? If yes, do it now. If no, what is the minimum additional observation that would settle it — and is it worth making?

Do not pile on more instrumentation if the current data already answers the question.

---

## Step 4 — A ruled-out hypothesis redirects the search

When the data shows a component is working correctly, that is not a dead end — it is information. Ask:

*"If the bug is not here, how does the bad state get produced elsewhere? Where does this data come from, or where does it go next?"*

Trace the data flow upstream or downstream. Form a new coarse hypothesis for that area and repeat from Step 2.

Example: if a test proves the classifier returns the right tag for the correct column, the question becomes "so how does the wrong tag end up in the DB?" — which leads to the import script calling the classifier with the wrong column.

---

## Step 5 — Fix one root cause at a time

1. Pick the deepest upstream cause first — fixing a symptom while the cause remains just moves the bug.
2. Write a failing test that captures the broken behavior before changing any code.
3. Apply the fix. Verify the test passes and nothing else broke.
4. Only then move to the next root cause.

---

## What to avoid

- Skipping the coarse hypothesis and instrumenting randomly
- Forming fine-grained hypotheses before observing anything ("it's probably X")
- Treating a ruled-out hypothesis as failure rather than as a redirect
- Instrumenting only where you already suspect the bug
- Proposing a fix the moment you spot a suspicious value, before checking the full picture
- Fixing two root causes in one change

## Mandatory task checkpoint

Apply the shared [task-commit contract](../memory-handling/references/task-commit-contract.md). Investigation and disposable probes create no empty commit; an authorized retained fix is a bounded checkpointed task.
