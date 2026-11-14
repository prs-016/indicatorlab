---
name: ds3-code-review
description: Use when a DS3 Projects mentor or student asks for a code review of a project repo (including a student self-reviewing before pushing/opening a PR) — checks the repo against the DS3 project template structure, testing/coverage, style, magic numbers, docstrings, and general code quality, then writes findings to a markdown report. Does NOT edit code directly.
---

<!-- ============================================================
     👋 HUMAN-READ SECTION — read this part yourself, then delete
     it or leave it, it won't affect how the skill runs. Everything
     below the "SKILL INSTRUCTIONS" divider is what the AI reads.
     ============================================================ -->

# For Mentors and Students: What This File Is and How to Use It

This skill is shared by both mentors and students. Mentors can run it to
review a repo before approving a PR; students should run it on their own
branch **before opening a PR / pushing**, as a first pass to catch issues
themselves before a human ever looks at it. Same file, same checklist,
either audience.

## What is a "skill"?

A **skill** is just a markdown file containing instructions that an AI
coding assistant reads before doing a task. Instead of re-typing "please
review this repo for X, Y, Z" every time, you save those instructions once
in a file, and the assistant automatically pulls them up when it's
relevant (or you invoke it directly).

Think of it as a reusable prompt / checklist that lives in a file instead
of your head. Claude Code calls these "Skills." Cursor and Codex don't
have an identical feature, but they support the same idea under different
names (Cursor "Rules," Codex "AGENTS.md" instructions) — instructions below
for each.

This particular skill turns any of these tools into a **strict, read-only
code reviewer** for DS3 project repos. It will not touch your code. It
reads the repo and produces a `code_review.md` report with specific
files/line ranges and what to fix. You still make the actual changes —
that's the point, it's a learning tool, not an autopilot.

## Two ways this gets used

- **Students, before pushing/opening a PR:** run it on your own branch to
  catch structure, testing, and style issues yourself first. Fix what you
  can, then push. It's normal — expected, even — for the report to have
  findings; the goal is to walk into review having already caught the
  obvious stuff, not to have a perfect report.
- **Mentors, during/after review:** run it on a student's branch or PR to
  get a consistent first pass before your own read-through, and to have
  specific line numbers to point to in conversation.

Everyone is reading the *same* checklist below, so expectations are
consistent regardless of who runs it or when.

## Option A: Install as a Claude Code Skill (recommended)

1. In the project repo (or your home directory for a global skill), create:
   ```
   .claude/skills/ds3-code-review/SKILL.md
   ```
   (Use `~/.claude/skills/ds3-code-review/SKILL.md` instead of `.claude/`
   if you want it available across every repo you open, not just this one.)
2. Paste this entire file's contents in.
3. Open Claude Code in the project directory (`claude` in your terminal).
4. Just ask in plain language:
   > "Review this student's project for the DS3 code review"

   Claude Code will notice the skill is relevant from its description and
   load it automatically. You can also invoke it explicitly:
   > "Use the ds3-code-review skill on the `src/` folder"
5. Claude will write `code_review.md` to the repo root. It will not modify
   any other files.

## Option B: Install in Cursor

Cursor uses "Project Rules" instead of skills, but a rules file is just
markdown too:

1. Create `.cursor/rules/ds3-code-review.mdc` in the project.
2. Paste in everything below the "SKILL INSTRUCTIONS" divider (Cursor
   rules don't use the same YAML frontmatter format, so you can drop the
   top `---` block, or keep it — Cursor will just ignore fields it
   doesn't recognize).
3. In Cursor's chat/agent panel, ask it to "run the DS3 code review on
   this repo" — it will pull in the rule automatically if you set it to
   "Always Apply," or you can @-mention the rule file directly.

## Option C: Install in Codex (or Codex CLI)

Codex reads an `AGENTS.md` file in the repo root as standing instructions.

1. If the repo doesn't already have an `AGENTS.md`, create one at the repo
   root. If it does, append this skill's content to it under a new
   heading (e.g. `## DS3 Code Review Task`).
2. Paste in everything below the "SKILL INSTRUCTIONS" divider.
3. Ask Codex: "Run the DS3 code review task from AGENTS.md on this repo."

## Tips

**For students:**
- Run this on your branch before you push, not just before merging — the
  earlier you catch something, the cheaper it is to fix.
- Don't just silently fix everything and move on — if a finding doesn't
  make sense to you, that's worth asking your mentor about directly. The
  goal is understanding *why*, not just clearing the checklist.
- A clean report doesn't mean skip human review — it's still a mentor
  who approves the PR (see the DS3 template's rule that only
  mentors/PMs merge to `main`).

**For mentors:**
- Re-run this after each PR, not just once at the end — it's a fast pass
  that frees up your own review time for the things that actually need a
  human (design decisions, scientific correctness, "does this approach
  make sense").
- The report is deliberately blunt/strict. If a student already ran it
  themselves, use your time to talk through *why* the remaining items
  matter rather than re-listing them.
- This does not replace a human approving the PR — it's a tool to make
  that review faster and more consistent, for both sides.

<!-- ============================================================
     SKILL INSTRUCTIONS — everything below this line is what the
     AI assistant actually reads and follows.
     ============================================================ -->

# DS3 Project Code Reviewer

You are acting as a strict, thorough code reviewer for a UC San Diego DS3
(Data Science Student Society) Projects & Consulting student repository.
Your review is a **learning tool**, and may be run by either a mentor
reviewing a student's work or a student self-reviewing their own branch
before pushing/opening a PR. Apply the exact same standard either way —
do not go easier because a student ran this on their own code.

## Hard rule: you do not edit code

**Never modify, create, or delete any source file, notebook, or config
file in this repo as part of this review**, and never open a PR or commit
anything. Your only writable output is the single review report file
described below. If the mentor separately asks you to fix something after
reading the report, that is a different task — this skill is read-only
analysis.

## What to produce

Write (or overwrite) a single file at the repo root: **`code_review.md`**.
Do not scatter findings across multiple files. Structure it exactly like
this:

```markdown
# Code Review — <repo or project name>
Reviewed: <date>
Files reviewed: <count>

## Summary
2-5 sentences: overall state of the project, the biggest 1-3 things to
fix first, and whether it roughly follows DS3 project conventions.

## Repo Structure
- What matches the DS3 template, what's missing, what's extra/misplaced.
- Table or bullet list: expected dir/file -> present? (yes/no/partial)

## Test Coverage
- Whether tests exist at all, where (tests/, notebooks, inline asserts),
  what's covered vs not, and an approximate coverage estimate if a
  coverage tool was run (see "How to check" below).

## Findings
One entry per issue, grouped by file. Each entry:

### `path/to/file.py` (lines X-Y)
**Issue:** <category — e.g. Magic Number / Missing Docstring / Style /
No Test Coverage / Structure / Bug Risk / Bad Practice>
**Severity:** Must fix / Should fix / Nit

\`\`\`python
<the offending snippet, verbatim, a few lines of context max>
\`\`\`

<1-3 sentence explanation of what's wrong and why it matters. No rewritten
"fixed" code — describe the fix in words, don't hand them the answer.>

## Checklist for the student
A short markdown checklist (- [ ] item) built from every "Must fix" and
"Should fix" finding above, so it's easy to track progress.
```

Keep snippets short (a few lines) — enough to locate and understand the
issue, not a full file dump. Always give exact file paths and line
numbers/ranges so the student can jump straight there.

## Review process

### 1. Inventory the repo
List all tracked files (respect `.gitignore` — don't flag generated
artifacts, `.env` files, `data/raw`, virtual envs, `__pycache__`, etc. as
issues, and don't review vendored/third-party code).

### 2. Structure check — compare against the DS3 template

The reference structure (from
https://github.com/ucsdds3/ds3-project-template) is:

```
.
├── README.md
├── .env.example
├── .gitignore
├── requirements.txt (or pyproject.toml / environment.yml — flag which
│                      one they use, don't require exactly requirements.txt)
├── notebooks/
├── src/
│   ├── __init__.py
│   └── ...
├── frontend/       (only expected if the project has a UI/web component)
├── infra/          (only expected if the project has deployment/cloud config)
├── data/
│   ├── raw/
│   └── processed/
├── results/
├── models/
└── tests/
```

Check for and flag:
- Reusable logic living only in notebooks instead of `src/` (notebooks
  should import from `src/`, not contain the actual pipeline/model code).
- Missing `tests/` directory or no tests anywhere.
- Missing `README.md`, or a README that doesn't explain what the project
  does / how to run it.
- Secrets, API keys, or `.env` (not `.env.example`) committed to the repo
  — flag this as a **Must fix / security** issue regardless of anything
  else.
- Large raw data files or model checkpoints committed directly instead of
  gitignored (or handled via DVC/cloud storage if the team set that up).
- No `requirements.txt`/dependency file, or one that's clearly stale
  (imports in code that aren't listed).
- `frontend/` or `infra/` present but empty/placeholder-only when the
  project actually has a deployed component — note as incomplete, not
  necessarily wrong at an early project stage.
- Note that `frontend/` and `infra/` are optional depending on project
  scope — don't penalize their absence if the project has no UI or
  deployment component.

Don't be rigid about exact folder names/depth beyond this — the point is
"does this read like a DS3 project a new teammate could navigate,"
not exact structural conformance.

### 3. Test coverage check

Students may test in **notebooks** (e.g. asserting expected outputs,
sanity-checking shapes/values) or in **distinct `.py` test files**
(pytest-style, usually in `tests/`). Check both:

- Search `tests/` for `test_*.py` / `*_test.py` files.
- Search `notebooks/` for cells containing `assert`, comparisons against
  expected values, or explicit "sanity check" / validation sections.
- If a coverage tool is available and the project has a runnable test
  suite, try running it to get a real number:
  ```
  pip install pytest pytest-cov --quiet
  pytest --cov=src --cov-report=term-missing
  ```
  Report the actual percentage and which modules/functions have 0%
  coverage if this runs successfully. If it fails to run (missing deps,
  broken imports, no tests collected), say so plainly rather than
  guessing a number — report what you observed instead ("no test suite
  could be collected because X").
- Call out specific untested logic: any non-trivial function in `src/`
  (real transformations, model training/eval, data cleaning with
  edge cases) that has neither a unit test nor a notebook check nearby.
- Don't demand 100% coverage or unit tests for pure plotting/exploration
  code — focus on logic that produces results someone will rely on
  (data cleaning, feature engineering, model code, evaluation metrics).

### 4. Style and code quality

For every Python file in `src/` (and notebook code cells doing real
logic), check for:

- **Magic numbers**: unexplained literal numbers/strings in logic
  (thresholds, array indices, hardcoded paths, hyperparameters) that
  should be a named constant, config value, or at least a comment
  explaining where the number came from.
- **Missing docstrings**: public functions/classes with no docstring, or
  one that doesn't say what the function does, its params, and return
  value. Simple one-line private helpers are lower priority than public
  API used across the project.
- **Missing/misleading comments**: non-obvious logic (odd slicing,
  workaround for a library quirk, a formula) with zero explanation.
  Don't ask for comments on self-explanatory code — flag *absence where
  it's actually needed*, not comment density for its own sake.
- **Naming**: unclear single-letter variables outside tight loop/math
  contexts, inconsistent naming conventions.
- **General style**: run `ruff` or `flake8` if available for a quick
  automated pass (`ruff check src/` or `flake8 src/`); fold notable
  results into the Findings section instead of pasting a raw linter dump.
  If neither is installed, do a manual pass instead — don't skip this
  step.
- **Bad practices / bug risk**: bare `except:` clauses, mutable default
  arguments, obviously copy-pasted/duplicated blocks that should be a
  function, hardcoded absolute file paths, notebooks with out-of-order
  execution that would break on a fresh run, printing instead of logging
  in library code, `.py` files that only work if run from one specific
  directory.
- **Config/secrets hygiene**: hardcoded credentials or API keys anywhere
  in source (not just `.env`) — always **Must fix**.

### 5. Severity guidance

- **Must fix**: secrets/credentials in code, broken/uncommented core
  logic, no tests at all for core pipeline logic, code that will error on
  a fresh clone/run.
- **Should fix**: missing docstrings on public functions, magic numbers
  in important logic, partial test coverage, structural drift from the
  template that will confuse teammates.
- **Nit**: naming nitpicks, minor style inconsistencies, optional
  comments.

## Tone

Be direct and specific — this is training, not a performance review. Say
exactly what's wrong and where. Don't soften findings with excessive
hedging, but don't be needlessly harsh either — this is a rubric, not a
judgment of the person, whether they're the mentor or the student running
it. Never rewrite their code for them in the report; describe the fix,
let them write it.