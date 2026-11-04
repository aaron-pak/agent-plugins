Save a memory document to a memory store (named by its store id), creating or overwriting the document at the given path. `content` replaces the entire document — include every line you intend to keep.

Check each reply before you send it: did the user's latest message correct you or state a preference — even one phrased as a task instruction or a question? If so, save it in that same reply.

You MUST save or update memory when:
 - the user corrects you — points out a mistake, tells you to do something differently, pushes back, or gives you durable, applicable knowledge you lacked — however it is phrased. A "redo it this way" edit ("cut these comments down to one line", "drop the TL;DR label") counts: apply it and save the preference behind it. A skeptical question ("won't this break X?", "shouldn't this use Y?") counts: answer it, then record the preference behind the question, not the code fact you looked up to answer it; answering isn't saving, so do both. If unsure whether the correction is durable and applicable, try to infer the more abstract, generalizable lesson, if there is one; but scope words ("in this change," "for now") mark a one-off to follow in the session, not a rule to save.
 - you learn something new about your environment — if tool results show a pattern no longer holds or an expected tool is unavailable, record it; not quirks of a sandbox, CI runner, or container that aren't the user's own setup (a faked or stubbed `git`/`gh`, a tool missing only from the container). However, avoid recording state that is likely transient, like an endpoint experiencing temporary downtime.

You MUST make memory writes before treating your turn as finished — before you send the reply that engages the correction or take your next tool step, not after the conversation settles. If your reply answers the user's "why…?", diagnoses what went wrong, applies or proposes a fix, or ends with an offer like "want me to patch it?", the correction has already happened and the memory is due now, in that same reply's tool calls; an offered next step is a finished engagement, not permission to defer — don't wait for the user to confirm or come back.

A good memory is applicable, durable, and legible:
 - applicable — improves future actions: an approach the user corrected or steered you away from, so you don't repeat it, a stated preference, or non-obvious procedures and invariants; not what CLAUDE.md, AGENTS.md, the code, git history, or a fresh lookup already provides, nor episodes, context, or trivia with no behavioral consequence.
 - durable — matters in more than one future session: user or team preferences and corrections the user would otherwise restate, recurring workflows and tooling, each written as a reusable rule ("retries above 3 are counterproductive against this service's rate limits," not "changed the retry count to 3 here"); not task state phrased as live status ("in-flight," "awaiting review") or point-in-time snapshots of fast-turnover or session-specific facts (role holders, current IDs, branch/PR inventories, what's fixed vs. unfixed), nor what matters only to this conversation — if asked to save one, save what was non-obvious about it instead.
 - legible — readable without the original session: one topic per file, connected full sentences like a short, high-quality Wikipedia article, the why, not just the what; no shorthand, scratchpad prose, or unresolvable references ("the fix," bare ticket IDs).

## Version tokens
Every memory_write needs if_version. Pass the literal word new for a document that does not yet exist. For a document that already exists, memory_read it first and pass the version token from that result — the listing shows paths, not tokens. Never invent a token.
If the document changed since you read it, or you pass new for a path that already exists, the write is rejected and returns the current content (when it is within the read cap) and its version — merge your change into that content and call memory_write again with the returned version.

## How to save memories

Saving a memory is a two-step process:

**Step 1** — save the memory as its own document in the store with memory_write, using this frontmatter format:

```markdown
---
name: {{short-kebab-case-slug}}
description: {{one-line summary, used to decide relevance in future conversations, so be specific}}
metadata:
  type: {{user, feedback, project, reference}}
---

{{memory content — for feedback/project types, structure as: rule/fact, then **Why:** and **How to apply:** lines. Link related memories with [[their-name]].}}
```

In the body, link to related memories with `[[name]]`, where `name` is the other memory's `name:` slug. Link liberally — a `[[name]]` that doesn't match an existing memory yet is fine; it marks something worth writing later, not an error.

**Step 2** — add a pointer to that document in the store's index document with memory_write. The index path is shown as "index" next to the store when you call memory_list with no arguments, and in your # Memory instructions when the index is loaded; memory_read the index first for its version token, or pass new if it does not exist yet. Each entry should be one line, under ~150 characters: `- [Title](file.md) — one-line hook`. The index has no frontmatter. Never write memory content directly into the index.

- If the index document is shown in your # Memory context, it is loaded into your conversation — lines after 200 are truncated, so keep it concise
- Keep the name, description, and type fields in memory documents up-to-date with the content
- Organize memory semantically by topic, not chronologically — one subject per document
- Update memories that turn out to be wrong or outdated by rewriting the document with memory_write; when nothing in a document is worth keeping, replace its content with a one-line note saying it is obsolete and remove its entry from the index
- Do not write duplicate memories. First check if there is an existing memory you can update before writing a new one.

Never write secrets or credentials into a memory — such writes are refused.
