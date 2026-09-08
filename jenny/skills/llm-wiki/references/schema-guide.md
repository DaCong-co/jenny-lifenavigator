# AGENTS.md Schema Guide

`AGENTS.md` is the **instructions file** for a single wiki (`wikis/<name>/AGENTS.md` — not to be confused with the workspace-root `AGENTS.md`). It tells the LLM agent the scope, conventions, current state, and open questions. A session starts by reading `wikis/_index.md` to pick the target wiki, then this schema together with that wiki's `wiki/index.md`.

## Why it matters

Without a schema, the LLM creates inconsistent page names, overlapping articles, and drifts from the wiki's intended scope. With a well-maintained schema, the LLM becomes a disciplined, consistent wiki maintainer.

**Co-evolve it with the wiki** — update after every major compile, ingest batch, or structural change.

## Full template

```markdown
---
summary: <one-line scope — shown next to this wiki in wikis/_index.md>
---

# <Topic Title> Knowledge Base

> Schema document — read at session start together with this wiki's wiki/index.md
> and the workspace wikis/_index.md registry.
> This wiki is isolated: never wikilink into another wiki (cross-wiki refs go via _index.md).

## Scope

What this wiki covers:
- <bullet list of included areas>

What this wiki deliberately excludes:
- <bullet list of out-of-scope areas>

## Operations

This wiki follows the llm-wiki skill's five operations: `compile`, `ingest`, `query`, `lint`, `audit`.
Every operation appends an entry to `log/YYYYMMDD.md`.

## Naming conventions

### Pages
- **Concept pages** (`wiki/concepts/`): Title Case noun phrases. E.g., "Market Making Strategy", not "market making" or "MarketMakingStrategy".
- **Folder-split concepts** (`wiki/concepts/<topic>/`): used when a topic would exceed ~1200 words as a single page. Contains `index.md` + one file per aspect.
- **Entity pages** (`wiki/entities/`): Proper names. E.g., "Andrej Karpathy", "Obsidian", "Avellaneda-Stoikov Model".
- **Summary pages** (`wiki/summaries/`): kebab-case source slug. E.g., "karpathy-llm-wiki-gist".

### Wikilinks
- Always use `[[Page Title]]` — exact page title, case-sensitive.
- For folder-split pages, link to the index: `[[concepts/Foo/index|Foo]]`.
- Link the first mention of every entity or concept. Do not link the same page more than twice per article.
- **Intra-wiki only.** Every `[[Target]]` must resolve inside this wiki. Never link into another wiki; to reference one, mention it in prose and point at `wikis/_index.md`. `lint` reports cross-wiki links as dead.

### Frontmatter
Every wiki page has YAML frontmatter:
```yaml
---
title: <Page Title>
type: concept | entity | summary
created: YYYY-MM-DD
updated: YYYY-MM-DD
sources: [list of raw/ slugs this page draws from]
tags: [relevant tags]
---
```

### Diagrams and formulas
- All diagrams are **mermaid**. No ASCII art.
- All formulas are **KaTeX** (inline `$...$` or block `$$...$$`).

### Raw file policy
- Small text sources → copy into `raw/<subfolder>/`.
- Large binaries → create a pointer file at `raw/refs/<slug>.md` with `kind: ref` frontmatter and an `external_path` field. Do not copy the binary.

## Current articles

> **The article list lives in `wiki/index.md`, not here.** Keep a pointer, not a copy:
> see that wiki's map for what exists.

<!-- Measured 24/08 on a real project: 4,381 of 7,161 chars of an AGENTS.md — 61% — were an
     article list duplicating the map's job. AGENTS.md is injected into the prompt of EVERY turn
     unfiltered, while the map is injected up to a cap, so the duplicate is the copy that is
     never trimmed: the prompt carries a truncated map plus an untruncated second index of the
     same pages. Worse, the map is the file the gardener curates and the lint's dead-link pass
     walks; an entry here naming a deleted page is checked by nobody. The lint reports a list
     that grows back (pass 18). -->

### Summaries
- [[summaries/<slug>]] — source title (date)

## Open research questions

- <Questions that should drive future ingest/query work>
- <Things the wiki currently doesn't cover well>
- <Contradictions or gaps noticed between articles>

## Research gaps

Sources to ingest:
- [ ] <URL or paper title> — why it's relevant

## Audit backlog

Count of open audits per target (filled in after running `audit_review.py --open`):
- <file> — N open
- ...

## Notes for the LLM

<Any special instructions: tone, depth level, language (zh/en), how to handle contradictions, etc.>
```

## What makes a good schema

**The `summary:` frontmatter field** is the one-liner shown next to this wiki in the workspace `wikis/_index.md` registry. Keep it to a single sentence describing the wiki's scope; `reindex_wikis.py` reads it verbatim. If it's left as the placeholder, the registry falls back to the first `## Scope` bullet.

**Good scope definition** prevents sprawl. A wiki about "LLM memory techniques" should exclude "LLM training" even though they're related.

**Explicit naming conventions** keep wikilinks from breaking. If you decide concept pages use Title Case, enforce it — a broken wikilink is an orphan.

**Knowing what already exists** prevents the most common error: creating duplicate articles with slightly different names. That list is `wiki/index.md`, which is read at session start and on every turn — so keep it there and keep it current, rather than maintaining a second copy in this file that nothing checks.

**Open research questions** give the LLM direction. Without them, the LLM defaults to ingesting the most obvious sources and missing your actual questions.

**Audit backlog** surfaces what the human has flagged as wrong. The AI should glance at it at the start of every session to decide whether to run an `audit` op before ingesting new material.

## Update cadence

- After every new concept page: add it to `wiki/index.md` (the map), not to this file.
- After every ingest batch: update "Sources to ingest" checklist.
- After every lint pass: update "Research gaps".
- After every audit pass: refresh the "Audit backlog" counts.
- Monthly: review scope, prune stale research questions.

