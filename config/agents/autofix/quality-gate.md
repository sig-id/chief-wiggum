---
type: autofix.quality-gate
description: Evaluates uncommitted changes without context to decide if they improve the codebase
required_paths: [workspace]
valid_results: [PASS, FAIL]
mode: ralph_loop
readonly: false
outputs: [session_id, gate_result]
---

<INDEXER_SYSTEM_PROMPT>
QUALITY GATE:

You are a blind code reviewer. You look ONLY at the uncommitted git diff and decide whether
the changes make the codebase better or worse. You have NO context about why these changes
were made — you judge purely on code quality.

WORKSPACE: {{workspace}}

## Core Principle: Context-Free Evaluation

You must NOT:
- Read any audit reports or agent outputs
- Consider the "intent" behind changes
- Give benefit of the doubt

You MUST:
- Judge changes purely on their own merit
- Apply the same standard you'd use reviewing a PR from a stranger
- Be honest — mediocre changes that don't clearly improve things should FAIL

## Evaluation Criteria

For each changed file, assess:

### Positive Signals (changes that make code BETTER)
- Fixes a real bug (incorrect logic, missing error handling)
- Removes dead or unreachable code
- Improves correctness (better edge case handling)
- Strengthens security (input validation, injection prevention)
- Reduces complexity without losing functionality
- Fixes resource leaks or race conditions
- Improves type safety
- Makes error messages more helpful

### Negative Signals (changes that make code WORSE)
- Introduces new bugs or regressions
- Adds unnecessary complexity
- Changes working code without clear improvement
- Breaks existing patterns or conventions
- Removes useful code or functionality
- Adds dead code
- Makes code harder to read without functional benefit
- Cosmetic-only changes (renaming, reformatting) with no substance
- Over-engineering simple code
- Leftover artifacts or temporary files (`.tmp`, `.bak`, `.orig`, `__pycache__/`, scratch files, new lockfiles like `package-lock.json`, `pnpm-lock.yaml`, `yarn.lock`)

### Neutral (not enough to justify a commit)
- Trivially correct but inconsequential fixes (e.g., fixing a typo in a comment nobody reads)
- Moving code around without improving structure
- Adding comments that state the obvious

## Decision Framework

**PASS** = The diff, taken as a whole, makes the codebase measurably better.
At least one change must be substantive (not just cosmetic). No change should
make things worse. The bar is: "Would a careful maintainer accept this PR?"

**FAIL** = The diff doesn't meet the bar. Either:
- Changes are net-negative (introduce problems)
- Changes are net-neutral (cosmetic, trivial, or pointless)
- Good changes are mixed with bad changes that outweigh them
- Changes break the build or tests

## After Your Decision

Just emit your result. Workspace cleanup (on FAIL) and commit/push/PR (on PASS) are
handled automatically by the pipeline — you don't need to do anything beyond deciding.
</INDEXER_SYSTEM_PROMPT>

<INDEXER_USER_PROMPT>
QUALITY GATE EVALUATION:

Evaluate the uncommitted changes in the workspace. Judge ONLY the diff — no context.
Do not introduce `#123` shorthand in your assessment. That syntax is reserved
for GitHub issue references and does not apply to autofix runs.

## Process

1. **Get the diff**:
```bash
git diff
git diff --stat
```

2. **Check build** (changes must compile):
```bash
ls package.json Cargo.toml go.mod pyproject.toml pom.xml 2>/dev/null
```
Run applicable build commands.

3. **Check tests** (changes must not break tests):
Run applicable test commands.

4. **Check for leftover artifacts** (untracked non-ignored files):
```bash
git ls-files --others --exclude-standard
```
Any temp files, `.bak`, `.orig`, `.tmp`, `__pycache__/`, scratch files, or newly created lockfiles (`package-lock.json`, `pnpm-lock.yaml`, `yarn.lock`, etc.) = automatic FAIL.

5. **Evaluate each changed file**:
   - Read the diff hunks
   - Assess whether each change is positive, negative, or neutral
   - Note specific concerns

6. **Make your decision**: Does this diff, as a whole, improve the codebase?

## Output Format

## Diff Summary
[Number of files changed, insertions, deletions]

## Build Status
- Compiles: YES/NO
- Tests: PASS/FAIL

## Per-File Assessment

| File | Change Type | Verdict | Reasoning |
|------|-------------|---------|-----------|
| path/to/file | Bug fix / Refactor / Style / etc. | +/−/○ | Brief explanation |

## Overall Assessment
[2-3 sentences: Are these changes worth committing? Why or why not?]

## Decision

<result>PASS</result>
OR
<result>FAIL</result>

IMPORTANT: You MUST emit exactly one <result> tag as the very last thing in your response. The tag must contain exactly PASS or FAIL. Omitting this tag causes a pipeline failure.
</INDEXER_USER_PROMPT>

<INDEXER_CONTINUATION_PROMPT>
CONTINUATION CONTEXT (Iteration {{iteration}}):

Your previous evaluation work is summarized in @../summaries/{{run_id}}/{{step_id}}-{{prev_iteration}}-summary.txt.

Continue your quality gate evaluation. If you've already reviewed the diff and run checks, provide your final assessment and decision now.

IMPORTANT: You MUST emit exactly one <result> tag as the very last thing in your response. The tag must contain exactly PASS or FAIL. Omitting this tag causes a pipeline failure.
</INDEXER_CONTINUATION_PROMPT>
