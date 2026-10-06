---
name: judo-code-review
description: Run an extremely strict maintainability review for abstraction quality, giant files, and spaghetti-condition growth. Use for a judo code review, code-judo review, deep code quality audit, or especially harsh maintainability review.
disable-model-invocation: true
---

# Judo Code Review

Use this skill for an unusually strict review focused on implementation quality, maintainability, abstraction quality, and codebase health.

Above all, this skill should push the reviewer to be **ambitious** about code structure. Do not merely identify local cleanup opportunities. Actively search for "code judo" moves: restructurings that preserve behavior while making the implementation dramatically simpler, smaller, more direct, and more elegant.

## Scope

The review target may be passed as an argument: a branch, a commit, a range (`a..b`), or a PR number. If no argument is given, review the changes on the current branch (or the detached `HEAD`, common in a review worktree) against its merge base with `origin/main`/`origin/master`, including uncommitted working-tree changes. Use the local `main`/`master` only when there is no remote-tracking branch: the local one is often out of date, for example in a worktree, and then the range picks up commits that are already on main. Resolve the scope first and state it in the report header.

### Ownership

Find out who owns the reviewed work before you review it. Use read-only
commands only. Do not infer ownership from a local checkout, repository
access, or permission to push.

1. **A PR decides it on its own.** If the target is a PR number, use that PR.
   For the current branch, run `gh pr view --json author,state,url` with no
   argument, and use the result only when its state is `OPEN`: a branch name
   can also match an old merged or closed PR. With a detached `HEAD`, run
   `gh pr list --search "$(git rev-parse HEAD)" --state open --json author,url`.
   Compare `author.login` with `gh api --hostname <pr-host> user --jq .login`.
   When there is no PR, or `gh` is not available, go to step 2.
2. **Commits.** Compare each author email in the review range
   (`git log --format=%ae <range>`) with `git config user.email`. Also accept
   `<id>+<login>@users.noreply.github.com` when `<login>` is the user's GitHub
   login. This works the same for a branch, a single commit, or an `a..b`
   range.
3. **Uncommitted changes** (staged or working tree) are the user's. Nobody
   else made them on this machine.

Without a PR, combine steps 2 and 3: every commit and uncommitted change
is the user's gives **yours**; none of them gives **someone else's**; a mix
gives **unknown**.

If the user names their GitHub account, use it in place of the `gh` login in
the checks. If the user says whose work this is, that decides ownership, and
the checks do not matter.

Record the result in the report header as one of: **Ownership: yours**,
**Ownership: someone else's (@login)**, or **Ownership: unknown**. For someone
else's work, show the GitHub login when step 1 returned one, otherwise the
author email.

Review without changing source files. Only offer to fix findings when the work
is confirmed to be the user's. For someone else's work, provide review feedback
and code suggestions, but do not start a fix plan or apply changes. Unknown
ownership uses the same feedback-only path until the user confirms ownership.

## Core Prompt

Start from this baseline:

> Perform a deep code quality audit of the current branch's changes.
> Rethink how to structure / implement the changes to meaningfully improve code quality without impacting behavior.
> Work to improve abstractions, modularity, reduce Spaghetti code, improve succinctness and legibility.
> Be ambitious, if there is a clear path to improving the implementation that involves restructuring some of the codebase, go for it.
> Be extremely thorough and rigorous. Measure twice, cut once.

## Non-Negotiable Additional Standards

Apply the baseline prompt above, plus these explicit review rules:

0. **Be ambitious about structural simplification.**
   - Do not stop at "this could be a bit cleaner."
   - Look for opportunities to reframe the change so that whole branches, helpers, modes, conditionals, or layers disappear entirely.
   - Prefer the solution that makes the code feel inevitable in hindsight.
   - Assume there is often a "code judo" move available: a re-organization that uses the existing architecture more effectively and makes the change dramatically simpler and more elegant.
   - If you see a path to delete complexity rather than rearrange it, push hard for that path.

1. **Do not let a PR push a file from under 1k lines to over 1k lines without a very strong reason.**
   - Treat this as a strong code-quality smell by default.
   - Prefer extracting helpers, subcomponents, modules, or local abstractions instead of letting a file sprawl past 1000 lines.
   - If the diff crosses that threshold, explicitly ask whether the code should be decomposed first.
   - Only waive this if there is a compelling structural reason and the resulting file is still clearly organized.

2. **Do not allow random spaghetti growth in existing code.**
   - Be highly suspicious of new ad-hoc conditionals, scattered special cases, or one-off branches inserted into unrelated flows.
   - If a change adds "weird if statements in random places", treat that as a design problem, not a stylistic nit.
   - Prefer pushing the logic into a dedicated abstraction, helper, state machine, policy object, or separate module instead of tangling an existing path.
   - Call out changes that make the surrounding code harder to reason about, even if they technically work.

3. **Bias toward cleaning the design, not just accepting working code.**
   - If behavior can stay the same while the structure becomes meaningfully cleaner, push for the cleaner version.
   - Do not rubber-stamp "it works" implementations that leave the codebase messier.
   - Strongly prefer simplifications that remove moving pieces altogether over refactors that merely spread the same complexity around.

4. **Prefer direct, boring, maintainable code over hacky or magical code.**
   - Treat brittle, ad-hoc, or "magic" behavior as a code-quality problem.
   - Be skeptical of generic mechanisms that hide simple data-shape assumptions.
   - Flag thin abstractions, identity wrappers, or pass-through helpers that add indirection without buying clarity.

5. **Push hard on type and boundary cleanliness when they affect maintainability.**
   - Question unnecessary optionality, `unknown`, `any`, or cast-heavy code when a clearer type boundary could exist.
   - Prefer explicit typed models or shared contracts over loosely-shaped ad-hoc objects.
   - If a branch relies on silent fallback to paper over an unclear invariant, ask whether the boundary should be made explicit instead.

6. **Keep logic in the layer where it belongs and reuse existing helpers.**
   - Call out feature logic leaking into shared paths or implementation details leaking through APIs.
   - Prefer the shared helpers that already exist over new one-off copies.
   - Push code toward the right package, service, or module instead of normalizing architectural drift.

7. **Treat unnecessary sequential orchestration and non-atomic updates as design smells when the cleaner structure is obvious.**
   - If independent work is serialized for no good reason, ask whether the flow should run in parallel instead.
   - If related updates can leave state half-applied, push for a more atomic structure.
   - Do not over-index on micro-optimizations, but do flag avoidable orchestration complexity that makes the implementation more brittle.

## Primary Review Questions

For every meaningful change, ask:

- Is there a "code judo" move that would make this dramatically simpler?
- Can this change be reframed so fewer concepts, branches, or helper layers are needed?
- Does this improve or worsen the local architecture?
- Did the diff add branching complexity where a better abstraction should exist?
- Did a previously cohesive module become more coupled, more stateful, or harder to scan?
- Is this logic living in the right file and layer?
- Did this change enlarge a file or component past a healthy size boundary?
- Are there repeated conditionals that signal a missing model or missing helper?
- Is the implementation direct and legible, or does it rely on special cases and incidental control flow?
- Is this abstraction actually earning its keep, or is it just a wrapper?
- Did the diff introduce casts, optionality, or ad-hoc object shapes that obscure the real invariant?
- Is this logic living in the layer where it belongs, or did the diff leak details across a boundary?
- Is this orchestration more sequential or less atomic than it needs to be?

## What to Flag Aggressively

Escalate findings when you see:

- A complicated implementation where a cleaner reframing could delete whole categories of complexity.
- Refactors that move code around but fail to reduce the number of concepts a reader must hold in their head.
- A file crossing 1000 lines due to the PR, especially if the new code could be split out.
- New conditionals bolted onto unrelated code paths.
- One-off booleans, nullable modes, or flags that complicate existing control flow.
- Feature-specific logic leaking into general-purpose modules.
- Generic "magic" handling that hides simple structure and makes the code harder to reason about.
- Thin wrappers or identity abstractions that add indirection without simplifying anything.
- Unnecessary casts, `any`, `unknown`, or optional params that muddy the real contract.
- Copy-pasted logic instead of extracted helpers.
- Narrow edge-case handling implemented in the middle of an already busy function.
- Refactors that technically pass tests but make the code less modular or less readable.
- "Temporary" branching that is likely to become permanent debt.
- New one-off helpers where the codebase already has a shared one for the job.
- Logic added in the wrong layer/package when it should live somewhere more central.
- Sequential async flow where obviously independent work could stay simpler and clearer with parallel execution.
- Partial-update logic that leaves state less atomic than necessary.

## Preferred Remedies

When you identify a code-quality problem, prefer suggestions like:

- Delete a whole layer of indirection rather than polishing it.
- Reframe the state model so conditionals disappear instead of getting centralized.
- Change the ownership boundary so the feature becomes a natural extension of an existing abstraction.
- Turn special-case logic into a simpler default flow with fewer exceptions.
- Extract a helper or pure function.
- Split a large file into smaller focused modules.
- Move feature-specific logic behind a dedicated abstraction.
- Replace condition chains with a typed model or explicit dispatcher.
- Separate orchestration from business logic.
- Collapse duplicate branches into a single clearer flow.
- Delete wrappers that do not meaningfully clarify the API.
- Reuse the shared helper that already exists instead of introducing a near-duplicate.
- Make type boundaries more explicit so the control flow gets simpler.
- Move the logic to the package/module/layer that already owns the concept.
- Parallelize independent work when that also simplifies the orchestration.
- Restructure related updates into a more atomic flow when partial state would be harder to reason about.

Do not be satisfied with "maybe rename this" feedback when the real issue is structural.
Do not be satisfied with a merely cleaner version of the same messy idea if there is a plausible path to a much simpler idea.

## Review Tone

Be direct, serious, and demanding about quality.
Do not be rude, but do not soften major maintainability issues into mild suggestions.
If the code is making the codebase messier, say so clearly.
If the implementation missed an opportunity for a dramatic simplification, say that clearly too.

Good phrases:

- `this pushes the file past 1k lines. can we decompose this first?`
- `this adds another special-case branch into an already busy flow. can we move this behind its own abstraction?`
- `this works, but it makes the surrounding code more spaghetti. let's keep the behavior and restructure the implementation.`
- `this feels like feature logic leaking into a shared path. can we isolate it?`
- `this abstraction seems unnecessary. can we just keep the direct flow?`
- `why does this need a cast / optional here? can we make the boundary more explicit instead?`
- `this looks like a one-off helper for something we already have elsewhere. can we reuse the shared one?`
- `i think there's a code-judo move here that makes this much simpler. can we reframe this so these branches disappear?`
- `this refactor moves complexity around, but doesn't really delete it. is there a way to make the model itself simpler?`

## Report Format

The review is delivered as a structured report. Follow this format exactly.

### Verdict header

Open with the answer, not the journey:

```markdown
## Verdict: REQUEST CHANGES
**Change:** Adds legacy-mode support to the ingest pipeline. (scope: `feature/legacy-mode` vs `origin/main`)
**Ownership:** yours
The change works but grows `run.ts` past 1k lines and scatters mode checks
through shared flow. 1 blocker · 2 structural · 2 cleanups.
```

The **Change** line is one factual sentence about what the diff does, plus the resolved scope.

Three verdicts, mapped to the Approval Bar below:

- **APPROVE** — no findings, or nothing above informational.
- **APPROVE WITH CHANGES** — only 🟡 cleanups.
- **REQUEST CHANGES** — any 🔴 blocker (anything the Approval Bar counts as a blocker).

The rationale is one sentence. Then the finding counts.

### Severity tiers

- 🔴 **Blocker** — something the Approval Bar counts as a blocker: crossing 1k lines, tangling a shared flow with special cases, a missed restructure that would have deleted the problem, a boundary leak, or a wrapper/cast that adds nothing.
- 🟠 **Structural** — a meaningfully simpler shape exists, but not blocking.
- 🟡 **Cleanup** — mechanical fix; always gets concrete before/after code.

Sort findings by severity, then by this priority within a tier:

1. Structural code-quality regressions
2. Missed opportunities for dramatic simplification / code-judo restructuring
3. Spaghetti / branching complexity increases
4. Boundary / abstraction / type-contract problems
5. File-size and decomposition concerns
6. Modularity and abstraction issues
7. Legibility and maintainability concerns

### Finding schema

**Write every finding in plain words.** The reader may not be a native English speaker, and a finding they have to decode is a finding they will skip. Say what the code does and why that is a problem, using the names that are actually in the code and the project's own vocabulary from `CONTEXT.md`. Do not invent a metaphor when a direct description works, and do not reach for a formal word ("canonical", "verbatim", "bespoke", "presumptive", "lockstep") when a common one exists. Repeating a plain word beats swapping in a fancy synonym. Keep a precise technical term when it is genuinely the right one, but explain it in a few plain words the first time it appears.

Every finding gets an ID (`B1`, `S1`, `C1`… by tier) so the author can say "apply B1". Every finding cites `file:line` or `file:start-end`. **Line numbers must come from the post-change file you actually read — never guessed from diff hunk headers.** If you haven't verified the line number by reading the file, read it first.

Structural findings (🔴/🟠) get a restructuring **sketch** — the target shape, what disappears, and the rough size of the win — not a speculative full diff:

```markdown
### 🔴 B1 · Mode flag spreads special-casing through shared flow — `src/pipeline/run.ts:88-141`
**Problem:** The new `legacyMode` boolean threads through 3 unrelated functions,
each growing an ad-hoc branch.
**Fix (sketch):** Fold `ModeHandler`/`LegacyModeHandler` into one `dispatch()` on a
typed union. Deletes: the flag, 3 branches, ~120 lines across 2 files.
```

Mechanical findings (🟡) swap the sketch for real code:

````markdown
### 🟡 C1 · Cast hides the API contract — `src/api.ts:42`
**Problem:** `as any` papers over the response shape.
**Fix:**
```ts
// before
const x = data as any
// after
const x = parseApiResponse(data)
```
````

### Conciseness rules (hard caps)

- Max **8 findings**. Top **3** get the full schema; the rest collapse into a one-line table: `ID · severity · file:line · issue · fix direction`.
- **Problem** statements are at most 2 sentences. Do not restate the diff. No praise padding.
- If any 🔴 exists, 🟡 findings go table-only — do not elaborate cleanups while blockers stand.
- Prefer a smaller number of high-conviction findings over a long list of cosmetic notes.

### Next actions (required)

After printing the terminal review, ask the user how to proceed using the
available structured question tool (`AskUserQuestion` or equivalent). If no
such tool is available, ask in plain text. Use one question ("How do you want
to proceed?"), single-select, with the options for the ownership result. When
the tool adds a free-text "Other" choice, do not add an explicit one.

| Ownership      | Options |
|----------------|---------|
| yours          | Open HTML report · Fix findings (plan first) |
| someone else's | Open HTML report · Draft review feedback |
| unknown        | Open HTML report · Draft review feedback · This is my work: fix findings (plan first) |

- **Open HTML report** — generate the browser report (steps below) and open it.
- **Fix findings (plan first)** — draft an action plan covering **all**
  findings: ordered by severity, one entry per finding ID with the concrete
  change to make. Present the plan and **stop for approval** — apply nothing
  until the user approves (in full or a subset). After applying, list what
  changed per finding ID.
- **Draft review feedback** — prepare concise comments the user can share with
  the author, using finding IDs and file references. Show the draft in the
  conversation; do not post it to GitHub without an explicit request.
- **This is my work: fix findings (plan first)** — picking this counts as the
  user saying the work is theirs, so ownership is now **yours**. Continue as
  for **Fix findings (plan first)**.

If the user picks "Other", follow their instruction within the ownership rules
above. An ambiguous request such as "go ahead" does not establish ownership or
select the fix workflow.

Exception: if the verdict is APPROVE with zero findings, skip the question and
fall back to a one-line text offer for the HTML report.

### Browser report

When the user asks for the browser report:

1. Copy `report-template.html` (next to this SKILL.md) to a temp/scratch directory — never into the repo. Name it `judo-review-<branch>.html` (use the short SHA for a detached `HEAD`).
2. Replace the `__REVIEW_DATA__` placeholder with a JSON blob matching the schema documented at the top of the template: change summary, ownership, verdict, rationale, changed files (status added/modified/deleted, size deltas, 1k-threshold flags), an optional architecture module map (touched modules and their dependencies), and findings (id, severity, title, file, lines, problem, fix, optional unified `diff` or before/after code).
3. Prefer a real unified `diff` excerpt on a finding when the fix is concrete — the template renders it with red/green line coloring. Use before/after only when a diff would be noisy.
4. Do not author or restyle HTML — only inject the JSON. Open the file with `open <path>` (macOS) or the platform equivalent.

## Approval Bar

Do not approve merely because behavior seems correct.
The bar for approval is:

- no clear structural regression
- no obvious missed opportunity to make the implementation dramatically simpler when such a path is visible
- no unjustified file-size explosion
- no obvious spaghetti-growth from special-case branching
- no obviously hacky or magical abstraction that makes the code harder to reason about
- no unnecessary wrapper/cast/optionality churn obscuring the real design
- no clear architecture-boundary leak, and no helper duplicated when a shared one already exists
- no missed opportunity for an obvious decomposition that would materially improve maintainability

Each of these counts as a blocker unless the author can justify it clearly:

- the PR preserves a lot of incidental complexity when there is a plausible code-judo move that would delete it
- the PR pushes a file from below 1000 lines to above 1000 lines
- the PR adds ad-hoc branching that makes an existing flow more tangled
- the PR solves a local problem by scattering feature checks across shared code
- the PR adds an unnecessary abstraction, wrapper, or cast-heavy contract that makes the design more indirect
- the PR duplicates an existing helper or puts logic in the wrong layer when there is an obvious home for it

If those conditions are not met, leave explicit, actionable feedback and push for a cleaner decomposition.
