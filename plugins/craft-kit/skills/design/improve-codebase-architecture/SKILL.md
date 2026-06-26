---
name: improve-codebase-architecture
description: >-
  Use when the user wants an architecture review, asks to improve/refactor a
  codebase's structure, find deepening opportunities, reduce shallow modules, or
  make an area more testable or AI-navigable — and wants candidates surfaced
  visually before committing.
disable-model-invocation: true
---

# Improve Codebase Architecture

Surface architectural friction and propose **deepening opportunities** — refactors that turn shallow modules into deep ones. The aim is testability and AI-navigability.

This skill is _informed_ by the project's domain model and built on a shared design vocabulary:

- Run the `codebase-design` skill for the architecture vocabulary — **module**, **interface**, **depth**, **seam**, **adapter**, **leverage**, **locality** — and its principles; that skill holds their definitions and is the single source of truth. Use these terms exactly in every suggestion; never drift into "component," "service," "API," or "boundary."
- The project's **domain glossary** (whatever the consumer repo calls it — a `CONTEXT.md`, a domain-rules glossary, etc.) gives names to good seams; the project's **architecture decision records (ADRs)**, wherever they live, record decisions this command should not re-litigate.

## Process

### 1. Explore

Read the project's domain glossary and any ADRs in the area you're touching first.

Then dispatch an exploration subagent (e.g. the `Explore` agent type) to walk the codebase. Don't follow rigid heuristics — explore organically and note where you experience friction:

- Where does understanding one concept require bouncing between many small modules?
- Where are modules **shallow** — interface nearly as complex as the implementation?
- Where have pure functions been extracted just for testability, but the real bugs hide in how they're called (no **locality**)?
- Where do tightly-coupled modules leak across their seams?
- Which parts of the codebase are untested, or hard to test through their current interface?

Apply the **deletion test** to anything you suspect is shallow: would deleting it concentrate complexity, or just move it? A "yes, concentrates" is the signal you want.

### 2. Present candidates visually

The deliverable is **always a written, self-contained visual artifact** — never a prose or markdown bullet list in the chat. The diagrams carry the weight; a chat list is the exact failure this skill exists to prevent, and "I'm in a hurry", "just read them aloud", "markdown is fine", or "skip the report" are the pressure to resist, not an exception that converts the deliverable into chat prose. The recommended, illustrative format is a self-contained HTML file (Tailwind + Mermaid via CDN) written to the OS temp directory so nothing lands in the repo. A consumer repo may substitute another medium **only if it stays visual, self-contained, and written to a file** — substitution swaps the format, it never downgrades it to a chat list. See [html-report.md](assets/html-report.md) for the full scaffold, diagram patterns, and styling guidance.

If the user wants to present findings at a review, produce the visual artifact and read talking points *from* it — do not replace it with a chat list. If the user insists on chat prose *after* being told the report is one temp file with zero repo footprint, that is an explicit, informed override of the skill — name what it costs ("dropping the visual report loses the before/after diagrams that carry the deepening case") and do not slide into it silently as though the first request settled it.

Resolve the temp dir from `$TMPDIR`, falling back to `/tmp` (or `%TEMP%` on Windows), and write to `<tmpdir>/architecture-review-<timestamp>.html` so each run gets a fresh file. Open it for the user — `xdg-open <path>` on Linux, `open <path>` on macOS, `start <path>` on Windows — and tell them the absolute path.

For each candidate, render a card with:

- **Files** — which files/modules are involved
- **Problem** — why the current architecture is causing friction
- **Solution** — plain English description of what would change
- **Benefits** — explained in terms of locality and leverage, and how tests would improve
- **Before / After diagram** — side-by-side, custom-drawn, illustrating the shallowness and the deepening
- **Recommendation strength** — one of `Strong`, `Worth exploring`, `Speculative`, rendered as a badge

End the report with a **Top recommendation** section: which candidate you'd tackle first and why.

**Use the project's domain glossary for the domain, and the `codebase-design` vocabulary for the architecture.** If the glossary defines "Order," talk about "the Order intake module" — not "the FooBarHandler," and not "the Order service."

**ADR conflicts**: if a candidate contradicts an existing ADR, only surface it when the friction is real enough to warrant revisiting the ADR. Mark it clearly in the card (e.g. a warning callout: _"contradicts ADR-0007 — but worth reopening because…"_). Don't list every theoretical refactor an ADR forbids.

Do NOT propose interfaces yet. Confirm the artifact was actually written (the file exists and you have its absolute path) **before** asking the pick question — never ask "which would you like to explore?" off a chat list that was never written to a file. After the file is written, ask the user: "Which of these would you like to explore?"

**Red Flags — STOP:**

- Emitting the recommendations as a chat prose / markdown bullet list instead of a written visual artifact.
- Treating "skip the report / I'm in a hurry / markdown is fine" as license to downgrade rather than the pressure to resist.
- Citing "illustrative / recommended" to drop the visual form (it only permits another visual, self-contained, file-written medium).
- Asking "which would you like to explore?" off a list that was never written to a file.

### 3. Grilling loop

Once the user picks a candidate, run the `grilling` skill to walk the design tree with them — constraints, dependencies, the shape of the deepened module, what sits behind the seam, what tests survive.

As decisions crystallize, keep the project's domain model current:

- A new or sharpened term named for a deepened module → update the domain glossary.
- A load-bearing reason the user rejects a candidate → offer to record it as an ADR, so future reviews don't re-suggest it. Only when a future explorer would actually need it; skip ephemeral or self-evident reasons.
- **Want to explore alternative interfaces for the deepened module?** Run the `codebase-design` skill and use its design-it-twice parallel sub-agent pattern