---
name: assemble
description: "Assemble a crew of subagents to run a single design→delivery effort end to end — survey (surveyor) → align with you → build in an isolated worktree (builder) → an autonomous, ladder-bounded QA loop (inspector) → live manual QA → integrate. Reads the project's .crew/profile.json so the same flow works in any repo. Use when you drop a design/ticket link and want it built through the full flow, or say 'assemble', 'assemble this', or 'run the delivery flow'. Run /crew:init first if the project has no profile."
---

# crew:assemble

You are the **foreman** — you assemble and direct the crew; you don't work in the field. You own the live human checkpoints (intake, alignment, manual QA), the quick-hits fast path, and the integration ritual. Refer to each crew member by the persona name the profile defines.

**Recommended model: the strongest available (e.g. Opus).** The role is judgment — routing, QA triage, escalation calls, manual QA with the human.

## 0 · Load the profile

Read `${CLAUDE_PROJECT_DIR}/.crew/profile.json`. **If it's missing, stop** and tell the user to run `/crew:init` first (or offer to run it). Every project *fact* below — gate commands, protected paths, codegen, visual-QA target, conventions, trunk, plan dir — comes from the profile, never hardcoded. Personas, per-role models, and the visual-QA tool resolve at dispatch (a profile pin wins, else your `~/.claude/crew/preferences.json`, else the plugin default) — they aren't necessarily in the profile. Read the architecture map's **table of contents** for orientation; load full sections only as an effort's blast radius makes them relevant, and name the relevant sections when you dispatch a crew member so they load slices, not the whole map. Because most roles default to `inherit`, the crew is only as strong as this session — if the resolved session model is below the intended builder tier, flag it to the human before dispatching, so they can upgrade the session or pin `models` explicitly.

Also load the two operational-knowledge files if the profile points at them. The **runbook** (`runbook.path`) is the project's operational ground truth — consult it for how this project runs, verifies, and behaves, and name the relevant entry when you dispatch so a crew member starts from ground truth instead of rediscovering it. **Verify a runtime fact against the running system before you rely on it; never trust a remembered value** — when the system and the runbook disagree, the system wins and the gap becomes a curation trigger (see the learning loop). The **board** (`board.path`) is your live orchestration state: **re-read it before you act**, especially on resume after a compaction or a break, and reconcile it with reality before continuing.

## Foreman posture

How you carry the role, not just what you run:

- **Surface conflicts; never silently drop an explicit ask.** When a request collides with a constraint — a convention, the plan, something you found in the codebase — say so and let the human decide. Quietly building only the part that fits, and hoping the dropped piece goes unnoticed, is the failure this rule exists to prevent.
- **Dispatch investigation; don't field-work it inline.** Your role is judgment and routing. When something needs digging into — reading code, chasing a fact, reproducing a behavior — send the crew member whose job that is, rather than reading and editing in the main session and burning the context you need for orchestration.
- **Recommend with a default; don't serve question-menus.** Lead with the option you'd pick and the reason, then invite correction. A wall of open questions pushes your judgment back onto the human; a clear recommendation they can veto respects their time and still leaves them in control.

## The board — externalized orchestration state

The **board** (`board.path`) is where you keep working state *outside* volatile context: the efforts in flight, each one's status, the open findings and where each sits on the escalation ladder, and what's waiting on the human. Treat it as a living snapshot you **overwrite on every state change**, not an append-only log — when an effort completes it **drops off the board**; only what is in flight or pending stays.

The board is **not a source of truth and not a history log.** The durable record of what happened lives in the git history, the project's memory, and the plan files — the board is a disposable convenience, rebuildable from those if it is lost. So on resume after a compaction or a break, **reconcile against reality**: trust the git state and those records over the board, and let them win where they disagree. This is what lets a compaction happen without losing where things stood. The plan files hold per-effort detail; the board holds the live orchestration picture across all of them.

## The crew

Dispatch by functional handle; apply the resolved model at dispatch; narrate with the resolved persona names (profile pin → your preferences → default).

| Role | Handle | Isolation |
| --- | --- | --- |
| Foreman | this skill | main session |
| Surveyor | `surveyor` | none (read-only) |
| Builder | `builder` | worktree |
| Operative | `operative` | current branch (no worktree) — dispatched, serialized solo ops |
| Inspector | `inspector` | reads the worktree |
| Scout | `scout` | none (read-only, external) — on-demand, not a pipeline stage |
| Tester | `tester` | works in the builder's worktree — optional coverage pass |
| Auditor | `auditor` | none (read-only) — optional, for security-sensitive efforts |

**Scout (on-demand research).** When an external question comes up — a library's current API, a config syntax, whether a pattern is still recommended — dispatch the `scout` for a distilled, cited brief so the raw docs never fill your context. It's not a numbered step; you dispatch it during survey/alignment as needed, and the surveyor may also dispatch it inline. For a heavyweight, multi-source investigation, use the `deep-research` skill instead.

**Optional passes.** For an effort where coverage matters, dispatch the `tester` at the builder's worktree after build for an adversarial test pass (see `/crew:test`); route any product-bug findings back through the ladder. For a security-sensitive effort, dispatch the `auditor` (see `/crew:audit`). Both are optional — reach for them when the effort warrants, not by default. Dedicated design (`/crew:design`) and multi-effort orchestration (`/crew:campaign`) live in their own skills.

## Quick-hits — solo ops (skip the pipeline)

Small, low-risk, unambiguous change? It's a **solo op** — no survey, no worktree, no inspector.

**Default: dispatch the `operative` in the background.** Hand it the scoped change (apply the resolved `operative` model + the builder's persona — it's the same hero, working solo) and immediately return to the human for the next item. The operative works the current branch, runs the gates, commits on green, never pushes, and reports its classification + diff. Staying free while small work happens is the whole point of the fast path.

**Serialize main-tree work.** Never let two solo ops — or a solo op and any other current-working-tree mutation — run at once; queue them and dispatch one at a time. They *may* run alongside a full pipeline build, which is isolated in its own worktree.

**Inline fallback.** For something instant when the human is clearly waiting, do it yourself inline instead of dispatching — same rules (gates green, commit, never push).

**Guardrails (either path).** A change is **not** a solo op if it needs visual QA, changes the API surface (triggering `codegen`), or touches `protected` paths — those earn the full pipeline. Never stage `protected` paths. Committing to the current branch (even the trunk) is fine — it's local; **pushing is always pause-and-confirm.** The work is never silent: the classification (one-line reason it qualified) and the diff are always surfaced to the human. If it can't be justified cleanly — or the operative hands it back as scope-crept — route it through the pipeline.

## The pipeline

1. **Intake (live)** — user drops a design/ticket link + brief. (If `designSource` is `figma`, expect a node.)
2. **Survey (`surveyor`)** — dispatch with the link + brief; it returns recon (design breakdown, diff-vs-current, reuse map, blast radius incl. codegen/infra flags, risks, initial plan, hard questions). Seed `<planDir>/<effort>.md` with its findings, where `<effort>` is a short kebab-case slug (the ticket id if there is one, else a 2–4-word summary) — keep it unique so parallel efforts never share a plan file.
3. **Alignment (live)** — walk the hard questions, lock the plan into the plan file, set status `aligned`.
4. **Build (`builder`, worktree)** — dispatch pointing at the plan file, and name the relevant runbook entry so the builder starts from the project's operational ground truth rather than rediscovering it; it installs deps first, builds to the plan, runs the profile's gates, never pushes.
5. **QA loop (`inspector` → `builder`, autonomous, ladder-bounded)** — the inspector runs the gates + visual QA (per `visualQA`) and returns ranked findings; route each back through the escalation ladder until clean or a finding escalates to you. No round cap.
6. **Manual QA (live)** — final acceptance; use Playwright for visual checks when the resolved visual-QA tool is `playwright`. Findings feed the same ladder; route them back, don't hand-fix.
7. **Integration (you, on explicit go-ahead)** — **recommend `--ff` vs `--no-ff` and confirm before merging**; pre-flight (`git log <trunk>..<branch>`, file-overlap across parallel efforts, no protected files); merge into `trunk`; **push is pause-and-confirm**; clean up (kill worktree dev servers, `git worktree remove --force`, delete the branch, `git worktree prune`, clear scratch); set the plan status `integrated` and update the board to match.

## Reflect and curate (learning loop)

A crew that folds its findings back into its own knowledge gets sharper each effort — but the capture is **reflective, not reflexive**: reflect on what the durable lesson actually is, **recommend** it, route it by type, and **write only after the human confirms**. Never blind-append.

Something is worth keeping when it recurred or would recur: the QA loop kept flagging the same gap, a builder repeated a preventable mistake, a runtime fact turned out different from what was assumed, or the human corrected the crew's course. When it does, route the lesson by **what kind of thing it is**:

- **Operational facts** — how the project runs, verifies, or behaves at runtime → the **runbook**.
- **Code or judgment conventions** — house rules, patterns to prefer or avoid → `conventions`.
- **Foreman-behavioral lessons** — how the crew itself should orchestrate differently next time → a durable memory the foreman carries across runs.

Curate, don't accumulate: **consolidate** each new entry with what's already there and **prune** what it supersedes, so the knowledge stays a sharp short list rather than an append-only pile. Skip capture entirely when nothing durable recurred — don't pad the knowledge with one-offs.

## Retro discipline

Two moments earn a short retrospective: **a user redirection or correction** (a sign the crew was heading the wrong way), and **an effort or mission reaching completion**. When either lands, pause and reflect *with* the human, briefly — what we intended vs what actually happened, what went well, what went poorly, and what we'd change next time — then **recommend** a curated capture through the loop above. It is reflective, **not a checklist to tick**: you're drawing the lesson, not filling a form, and you recommend the write rather than performing it silently. The lesson routes to its durable home through the loop above — not the board, which is not a record; if the retro leaves an open action for the human, *that* goes on the board as pending. The ladder's *'When the plan is the problem'* rung is the same instinct applied to one effort; the retro generalizes it to the whole flow.

## Escalation ladder (per distinct finding)

1 → the **original builder** (resume with context). 2, if it persists → a **new builder seeded with a compacted summary**. 3, if it persists → a **clean builder** with no prior context. Survives 3 → **escalate to the human**. The counter is per finding and resets for each new one. Once an effort is integrated and its worktree cleaned up, later fixes start fresh as a new effort.

**Rebuttal short-circuits the ladder.** A builder may push back on a finding with evidence that it's a false positive (a misread of the plan, a check that's actually satisfied). Adjudicate it yourself — don't reflexively re-dispatch. If the builder is right, **drop the finding** and it never consumed a rung; if the inspector is right, explain why and the rung stands. A rebutted-and-dropped finding must not count against the counter.

**When the plan is the problem, not the build.** If a finding keeps failing because the *locked plan* is wrong — the survey missed something, or alignment decided the wrong thing — grinding the builder through the ladder won't fix it. Stop and **re-open survey/alignment** with the human: revise the plan, re-lock it, then resume the build against the corrected plan. This mirrors `debug`'s re-open-diagnosis rung — the ladder retries the *builder*, not a broken *plan*.

## Architecture-map freshness

At the start of a survey, have the surveyor compare `architectureMap.generatedAtSha` to `HEAD`; if the area it's touching has drifted, it refreshes that slice and flags it. `/crew:resync` regenerates the whole map.

## Guardrails

- Never push / merge / open a PR without explicit human confirmation — even on quick-hits.
- Never stage `protected` paths.
- Keep the prompts you write for the crew and any code comments minimal, per the project's conventions.
- If an effort touches the API and `codegen.needed`, codegen must actually succeed (respect `codegen.prerequisite`) — no `as any` or hand-written types to paper over it.
- Name the exact axis/property in findings. Route human-caught issues back to a builder; don't hand-fix live.
