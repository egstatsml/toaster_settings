---
name: ask
description: Ask which skill or flow fits your situation. A router over the skills in this repo.
disable-model-invocation: true
---

# Ask

You don't remember every skill, so ask.

Before stating what a skill does or recommending a step be skipped, read that skill's SKILL.md: the summaries here are for orientation only.

A **flow** is a path through the skills. Most paths run along one **main flow**, and two **on-ramps** merge onto it. Everything else is standalone, or a vocabulary layer that runs underneath.

Plans and tickets are markdown files in the repo being worked on: a spec at `plans/<slug>/spec.md`, one ticket per file at `plans/<slug>/tickets/NN-<slug>.md`, each with a `Status:` line. There is no issue tracker and no pull request step.

## The main flow: idea → code you trust

The route most work travels. You have a research idea (a model, an experiment, a pipeline, an evaluation) and want the code for it built.

1. **`/grill-with-docs`** sharpens the idea by interview: the research question, the hypothesis, the data and splits, the baselines, the metrics, the compute. Start here whenever you are **working in a repo**: it's stateful, retaining what it learns in `GLOSSARY.md` and ADRs. (No repo? Use `/grill-me` instead, covered under Standalone. Both run the same `/grilling` primitive.)
2. **Branch: can you settle every question in conversation?** If a question needs a runnable answer (does this idea learn at all on a toy problem, what does this data actually look like, does this loss behave on edge cases), detour through **`/prototype`**: a throwaway script or notebook that answers it. Fold the verdict back into the conversation before moving on.
3. **Branch: is this a multi-session build?**
   - **Yes** → **`/to-spec`** (turn the thread into `plans/<slug>/spec.md`), then **`/to-tickets`** to split it into tracer-bullet tickets under `plans/<slug>/tickets/`, each declaring its **blocking edges**. Then **`/implement`** per ticket, blockers first, **`/clear`ing context between each one**. Each ticket is self-contained, so the last one's context is disposable.
   - **No** → **`/implement`** right here, in the same context window.

   Either way, the code gets built by driving **`/tdd`** (one red-green slice at a time: data contracts, known-answer losses and metrics, overfit-one-batch) and closes out with **`/code-review`**, a two-axis review (Standards + Spec) of the diff that also checks for the mistakes that silently invalidate results (leakage, wrong split, train/eval mode, silent broadcasting). Reach for **`/tdd`** on its own when you just want to build a concrete behaviour test-first without a full spec, and **`/code-review`** on its own whenever you want to review a branch against a fixed point.

   The skills stop at code that is verified on small inputs. Launching the real training runs and sweeps is yours.

4. **`/retro`** closes the loop. After a build, and especially one that went sideways, it looks back over the session and suggests changes to the agent's **environment**, not the code: navigation pointers, automated checks, the coding standards `/code-review` enforces, steering files, tooling. The next build then starts from a better environment.

### Context hygiene

Keep steps 1–3 in **one unbroken context window** (don't compact or clear until after `/to-tickets`) so the grilling, spec, and tickets all build on the same thinking. Each `/implement` then starts fresh, working from the ticket. Run `/retro` in the session it's looking back on, before you clear; after clearing, point it at that session's log instead.

The limit on this is the **smart zone**: the window (~150k tokens on state-of-the-art models) within which the model still reasons sharply. If a session approaches it before `/to-tickets`, don't push on degraded; `/compact` at the nearest phase boundary and carry on (see Phase boundaries).

## On-ramps

A starting situation that generates work, then merges onto the main flow.

- **Something's broken** → **`/diagnosing-bugs`**. For the hard ones: the NaN that appears at step 40k, the model that won't learn, the result that won't reproduce, the throughput regression. It refuses to theorise until it has a **tight feedback loop** (one command that already goes red on *this* bug, usually a tiny training run or a replayed batch), then fixes with a regression test. Once the fix is in, run **`/retro`** in the same session to ask what would have prevented the bug; where the real finding is that there's no good seam to lock it down, that's a job for **`/improve-codebase-architecture`**.

- **You need to know what the literature or a library says** → **`/research`**. It sends a **background agent** to read **primary sources** (the paper and its appendix, the reference implementation, the library's docs for your pinned version) and leaves a cited Markdown file next to the plan. Keep working while it reads. Take the file into the main flow at `/grill-with-docs`, since research feeds the thinking rather than replacing it.

## Codebase health

Not feature work, just upkeep. Research code accretes fast: copy-pasted training loops, a flag per experiment, scripts that import from scripts.

- **`/improve-codebase-architecture`** runs whenever you have a spare moment to keep the codebase good for agents (and you) to operate in. It surfaces **deepening opportunities**; picking one _generates an idea_ you can take into the main flow at `/grill-with-docs`. It's the survey that finds the candidates; **`/codebase-design`** (below) is the bench you design the chosen one on.

## Vocabulary underneath

Two model-invoked references that run *beneath* the other skills, each the single source of truth for its vocabulary. Reach for them directly when the **words**, not the process, are the problem; or let the skills above pull them in.

- **`/domain-modeling`**: sharpen the project's *domain* language: challenge a fuzzy term, resolve an overloaded word ("step" meaning an optimiser step and an environment step), record a hard-to-reverse decision (an evaluation protocol, a split strategy) as an ADR. It's the active discipline `/grill-with-docs` drives to keep `GLOSSARY.md` a clean glossary.
- **`/codebase-design`** is the deep-module vocabulary (module, interface, depth, seam, adapter, leverage, locality) for designing a module's *shape*: a lot of behaviour behind a small interface at a clean seam. `/tdd` and `/improve-codebase-architecture` both speak it.

## Phase boundaries

A **phase** is a chunk of work inside a session: the grilling, the implementation, the debugging. At the **boundary** between two of them you have five options:

- **Continue**: stay put. Costs nothing, loses nothing.
- **`/clear`**: empty the window, when nothing here matters to what's next.
- **`/handoff`** writes a portable markdown file. Narrow: only for a **new harness**, a **new directory** (a prototype in its own folder, a cluster checkout), a **collaborator**, or forking a side task **mid-phase**. What it buys is portability.
- **Subagent**: send a tightly-scoped task to its own window and get a report back.
- **`/compact`** compresses this context and seeds a fresh session with it. The **default**, at the bottom of the tree rather than the first reach.

Read [PHASE-BOUNDARIES.md](PHASE-BOUNDARIES.md) for the ordered tree: the five questions, the reasoning behind each branch, and why the primary-source cost makes **Continue** the one to rule out first. Make the decision **at** a boundary; mid-phase, continue or split the rest into subagents.

## Standalone

Off the main flow entirely.

- **`/grill-me`**: the same relentless interview as `/grill-with-docs`, but **stateless**: it saves nothing and builds no `GLOSSARY.md`. Reach for it when there is no repo under the idea (an experiment design you're still sketching, a paper outline). In a repo, `/grill-with-docs` runs the same interview and leaves a paper trail.
- **`/grilling`** is the interview primitive itself: rounds, the frontier, facts are the agent's job and decisions are yours. `/grill-me` and `/grill-with-docs` are the two named ways in, and `/improve-codebase-architecture` runs it internally.
- **`/prototype`** is throwaway code that answers one question: does this idea learn at all on a toy problem, what does this data look like, does this logic behave on the awkward cases. The verdict goes into the plan, and the prototype is kept on a `prototype/<name>` branch out of main. It's the detour in step 2 of the main flow, but reach for it any time a question is hard to settle on paper.
- **`/wait-what`** is the corrective for a message that didn't land. Use it mid-conversation, inside any other skill, and the agent re-pitches what it just said with the context you were missing, in plain English, using the `GLOSSARY.md` vocabulary.
- **`/writing-for-agents`** is the reference for writing documents agents consume: skills, CLAUDE.md/AGENTS.md, pointed-at docs.
