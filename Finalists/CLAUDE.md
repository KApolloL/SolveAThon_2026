Apply when working anywhere in Finalists/ (Solve-A-Thon 2026 Final Quest; team project, R and Quarto). Read README.md first, then handoff.md for current status. Reuse patterns from `../QualifierChallenge/` (config file, fact-check script, tool build, site build) instead of reinventing them.

## Problem (released Fri Nov 6; full organizer text in `docs/QUEST_BRIEF.md`)
- Quest: "Federal Funds Matchmaker" for OSBM (NC Office of State Budget and Management). Centralized, AI-assisted workflow that scans federal funding opportunities, classifies them, and matches them to agency strategic goals, statutory authority and program priorities. Humans make the final decision.
- Agency / user: [assumed, confirm at the 6:30 pm discovery workshop] an agency grant coordinator who triages opportunities for one agency. Sponsor is OSBM. Smaller agencies with limited grant capacity miss the most.
- The decision or task the user needs help with: which federal opportunities to pursue, early enough to meet the deadline. Exact decision and action: pending discovery.
- Data sources provided: live Grants.gov or SAM.gov API; NC agency strategic plans from OSBM (links in `docs/QUEST_BRIEF.md`); starter kit and `additional-tools-1.zip` from the organizers (contents not yet inspected). Format, size, license: not yet checked.
- Deliverables required by the organizers: (1) pitch, 6 min plus 2 min Q&A, with brief demo; (2) Solution Design and GenAI Field Notes (user and design notes; GenAI tools, key prompts, at least one place the AI was wrong and how we caught it); (3) repository with a README a state developer can pick up. Product link goes with the slides.
- Hard requirement: working prototype on Azure (provided environment and credits). Must load opportunity data, build agency profiles from real NC strategic plans, score and rank, summarize, and show results in a simple interface. Public or provided data only.
- Presentation format: in person, 6 minutes (including brief demo) plus 2 minute Q&A with judges, per the released brief. The organizer email of 10.22.26 said 5 plus 2; confirm which applies. Slides are built by a teammate's AI agent from our slide brief.
- Hard deadline: slides, field notes and repository submitted through the Final Submission form before Sun Nov 8, 9:00 am; late submissions are not accepted. Presentations 10:00 am to 12:30 pm. Awards end at 2:00 pm.
- Bonus quests (only after the core works): coverage metrics, deadline alerts, user feedback loop. Kent's design for the feedback loop (users rank a sample of grants blind at onboarding, which calibrates criteria weights) and the bonus plan are in `planning/05_user_criteria_and_feedback.md`.
- Schedule and Deloitte training notes live in the vault: `~/Documents/KALNotes/Projects/Competitions/Solveathon/` (`Solveathon.md`, `Solveathon_DeloitteTraining.md`).

## Judging criteria (from the released brief)
- Understand: did we engage real users and let what we learned shape the build?
- Frame: problem and requirements appropriately framed?
- Solve: works properly, and makes effective use of cloud services (Azure)?
- Evaluate: measured our own output, presented failures honestly, defended tradeoffs under questioning?
- Drive Impact: could this pitch win a pilot budget from OSBM? (who uses it, what it replaces, why trust it, pilot shape, scale path)
Named threats to address: false positives, false negatives (recall vs manual monitoring), uneven agency documentation, inconsistent data quality. See `docs/QUEST_BRIEF.md`.

## Conventions
- Every threshold and default lives in `src/R/00_config.R`. Do not hard-code values elsewhere.
- Scripts are numbered in run order. Each reads from `data/` and writes to `data/processed/` or `outs/`.
- `data/raw/` is never modified. Hand-authored tables go in `data/manual/`. API and model responses go in `data/cache/` so reruns are free.
- Presentation numbers come only from verified facts in `src/docs/fact_sheet.md`. Never invent figures. Each fact has a script that reproduces it (like `check_facts.R` in the qualifier).
- If an LLM is used on data, it only labels with quoted evidence. It does not make the final decision.
- State the main weakness of the approach and its tradeoff in writing. The Evaluating criterion requires it.

## Pipeline skeleton
Reusable code is in `src/R`, `src/tool` and `src/tests` (see README.md, "Pipeline skeleton"). Reuse it; do not rewrite it. The criteria table `data/manual/criteria.csv` is the whole method: each row is one measurable rule tied to a data field, with a plain-language `why` and a `source` (a client quote). Change the table, not the code, wherever possible. After any change run `tests/run_tests.R` and `R/check_facts.R`. The toy data in `data/example/` is fake; delete it before submitting.

Decide at the design sprint whether the skeleton fits (`planning/03_problem_types.md`). Use `rank_items()` only if the user's decision is a choice among a list of items. If the problem is another type, keep the plumbing (`read_any`, cache helpers, tests, report, figure export) and write a new core; record what we keep and why in `handoff.md`. Do not bend the problem to fit the ranking code (Deloitte: do not anchor on a method before the problem is understood).

## Planning documents (Discover phase)
`planning/` holds the Friday worksheets: `01_discovery_questions.md` (workshop questions and note-taker sheet), `02_framing_worksheet.md` (user, decision, criteria, options, success test, and the gate), `03_problem_types.md`, `04_data_prep.md` (intake checklist and the caches already in `QualifierChallenge/data/cache/`). Help Kent fill the framing worksheet; do not fill it for him from assumptions. Pulling and merging opportunity data (R/02*, R/03) is allowed before the gate; no analysis, scoring, criteria or profiling for decisions until the gate is ticked.

## Skills
`docs/SKILLS_GUIDE.md` says which installed skill to load for each phase and which to ignore. Follow it: load at most one or two skills per task, use the Default in each row, never stack overlapping skills, and tell Kent the cost before starting a heavy one. Always load `dataviz` before writing chart code and `voice-match` before writing prose Kent will submit. Run `superpowers:verification-before-completion` before claiming anything passes.

## Constraints
- No participant, patient or personal data in any file.
- No API keys in any file. Keys go in `.Renviron` (gitignored).
- Do not edit `.Renviron` or `.RData`.
- Do not re-run outside-service scripts casually. They call out only for uncached items.
- Log every AI use in `AI_USAGE_LOG.md` (tool, what for, what was checked by a human).

## Deloitte method (finalist training, 10.22.26)
Four phases: Discover, Build, Test, Present. Full notes in the vault `Solveathon_DeloitteTraining`.
- Do not open the dataset until the user, the decision and 3 to 5 measurable criteria (each tied to a data field) are written down. Refuse to start analysis before this exists.
- Solve the right problem, not the fanciest model. Start with the user, not the data.
- Offer the client 2 to 3 options (COA) with pros, cons and tradeoffs. Pick the simplest method that works; verify each level before adding complexity.
- Build as filter, score, rank, explain. A teammate must be able to rerun the raw file and get the same result.
- Test: write pass/fail criteria before looking. Unit, integration, then user acceptance. Try to break it. Report failures honestly; a failed test is evidence.
- Present: lead with the answer. Ask, why, how, limits, next step. Tell the client what they need to hear, not what they want to hear.
- Ask probing questions instead of letting the data drive. Note extra context (for example fiscal year runs Oct 1 to Sep 30).

## Teammate sessions (if you are a teammate's Claude)
Kent's session is the one described in "Role of this Claude" below. If the person you are helping is a teammate (Everett, Marco, Matthew, Noah), these rules replace the "does not commit or push" rule:
- Work only on the task brief in `tasks/` they point you to. Write output only to the path the brief lists. Do not edit `src/R`, `src/tool`, `src/tests`, `CLAUDE.md` or `data/raw` unless the brief says to.
- They are new to git. Explain each git step in plain words. You may create a branch named `theirname/short-topic`, commit their changes, and push that branch. Never commit to or push `main`, never merge, never force-push. Tell them to open a pull request on GitHub for Kent to review.
- Never invent numbers or sources. Numbers come from `src/docs/fact_sheet.md` only. Write "not found" when something is missing.
- Log any AI use in `AI_USAGE_LOG.md`. Remind them to check your output themselves.
- Stuck for more than 20 minutes or anything about a merge conflict: stop and tell them to message Kent.
- Use the shared reviewers (agents in `.claude/agents/`, slash commands in `.claude/commands/`) when the brief asks for testing or review. They read `testing/context.md` first.

## Role of this Claude (Kent's session)
This Claude plans and builds the large-scale pieces. Teammates do the smaller tasks (research summaries, hand labels, checks, writing) from briefs in `tasks/`, using UNC PromptLab or no AI. The slides are built by another teammate's AI agent from the brief and figures this Claude produces.

Does:
- Frame the problem with Kent: user, decision, success test, metric.
- Design and build the pipeline, analysis and any tool, in R and Quarto, reusing `../QualifierChallenge/` patterns.
- Maintain `src/docs/fact_sheet.md`, `handoff.md` and `AI_USAGE_LOG.md`.
- Write task briefs for teammates from `tasks/TASK_BRIEF_TEMPLATE.md` when Kent asks for one.
- Produce the slide handoff: `deliverables/slide_brief.md` (outline, one message per slide, exact numbers from the fact sheet, which figure goes where) plus figure files in `outs/figures/`. Charts follow the `dataviz` skill.
- Review our own work harshly (see "Review and Q&A prep").
- Design persona-testing material for teammates (see "Persona testing").

Does not:
- Build the slides, write the AI-usage disclosure, or do small tasks teammates own, unless Kent says so. Spending credits on those is waste.
- Commit, push, branch, merge or touch GitHub (in Kent's session). Suggest a commit message; Kent runs git.
- Decide framing, the user, the metric, or drop or filter data without asking first.
- Invent agency facts, figures, quotes or sources.
- Run unattended. Work only while Kent is at the keyboard. No overnight or background jobs.
- Delete anything. Move to a dated `stale/` folder and say so.

## When to ask versus act
Ask Kent before anything non-trivial: framing, scope, metric, data exclusions, new dependencies, a new external call, restructuring files. Act without asking only on small approved steps (a fix, a rerun from cache, editing a file Kent named). When proceeding past ambiguity, state the assumption in one line. Push back on weak reasoning; be critical, no flattery.

## Models and subagents
- Strongest model (Opus-class): framing, architecture, evaluation design, hard debugging, reviewing the plan, hostile-judge passes.
- Mid model (Sonnet-class): routine code, edits, scripts, tests, figure code, slide brief drafting.
- Cheap model (Haiku-class): file search, "where is X", bulk labeling or summarizing, formatting, reading long documents for extraction.
- Subagents: use them for read-heavy or bulk work so it stays out of the main context. Give each a self-contained brief (paths, what done looks like) and check its result before reporting it as done. Run independent subagents in parallel; run dependent ones in order.
- Escalate to the strongest model only after a mid-tier attempt fails twice or the task is design, not execution.
- Do not read many files in the main thread. Search first, read only the part needed.
- Start a fresh session at a natural breakpoint with `handoff.md` updated, rather than letting one session grow.
- Keep about 25% of credits in reserve for the last 6 hours.

## Subagent playbook (standing authorization from Kent for the cases below)
Agent types available here: `Explore` (broad read-only search), `caveman:cavecrew-investigator` (locate code, returns `path:line`), `caveman:cavecrew-builder` (1 to 2 file edits only), `caveman:cavecrew-reviewer` (one-line diff review), `Plan` (design a plan), `general-purpose` (multi-step research or build), and the project's own `hostile-judge`, `data-critic`, `test-breaker` in `.claude/agents/`. `impeccable-*` agents are for UI polish only. Ignore the academic, understand-anything and kalnotes agents here.
- **Spawn without asking** (read-only): searching files, "where is X", reading long documents for extraction, summarizing raw data files, running a reviewer agent on finished work.
- **Ask Kent first**: any agent that writes files, runs longer than about 5 minutes, calls an outside service or costs money, or any multi-agent Workflow (never start one unless Kent asks for it).
- **Never spawn for**: framing, choosing the user or metric, small edits, anything Kent must decide, or one-file lookups a direct search answers.
- **Model per job**: haiku for search and bulk summaries; sonnet for routine code and figure scripts; the strongest model for `Plan`, design and the three reviewers.
- **Brief every agent** with: the exact paths, the goal, what done looks like, what it must not touch, no commits or pushes, and a short output format. A cold agent knows nothing else.
- **Parallel**: at most 3 at once, independent files only, never two writers on the same files.
- **Check before reporting**: read the agent's result and run `tests/run_tests.R` or `R/check_facts.R` where it touched code or numbers. An agent's report is a claim, not proof.
- **Reviewers**: run `data-critic` after the criteria exist, `test-breaker` before the Saturday 1:00 PM gate, `hostile-judge` on the pitch near the Saturday evening freeze. One run each unless the work changes a lot.
- Teammates run their own sessions; do not spawn agents for their tasks.

## Other AI tools (OpenCode, Codex, Gemini, ChatGPT, PromptLab)
You (Claude) are the main planner and drafter. Other tools do smaller bounded tasks and hand results back to you to polish and check. Rules for them are in `AGENTS.md` (OpenCode and Codex read it automatically); a paste-ready context for chat-only tools is `docs/AI_HANDOFF.md`; the day plan is `docs/RUNBOOK.md`.
- **Hand off** with a task brief (`tasks/TASK_BRIEF_TEMPLATE.md`): exact inputs, one output path, what done means, what not to touch. Tell Kent which tool to use and why.
- **Routing (capabilities not verified):** OpenCode with a free or local model (`qwen2.5-coder:32b`) for small R or JavaScript edits and test boilerplate, one file at a time; Codex or ChatGPT free for a second code opinion and draft prose from the fact sheet; Gemini for reading long agency documents and summaries; PromptLab is the teammates' workbench for research, persona drafts and Q&A practice.
- **Take back** their output from `drafts/<tool>/` or the named path. Before promoting it: run `tests/run_tests.R`, check every number against `src/docs/fact_sheet.md`, make the language plain, and read the code. Their output is a claim, not proof. Log the tool in `AI_USAGE_LOG.md` and note any error they made; the team must name at least one place an AI was wrong.
- **Never** hand them framing, criteria, metric or data-exclusion decisions, and never let two tools edit the same file.

## Evidence and sources
Web lookups are allowed for context (agency, policy, data documentation). Every claim from the web gets a link and stays marked [uncertain] until Kent confirms it. Separate what was verified in a provided file from what is inferred. If corrected, carry the fix forward.

## Data, caching and external calls
Always cache, never re-query. Every external call (API, download, LLM labeling) writes its response to `data/cache/` first and reads from there on reruns. Ask before any new bulk call or any paid API. Do not commit raw downloads over 50 MB; note where they came from in `data/raw/README.md` instead.

## Review and Q&A prep (6 minutes with demo plus 2 minute Q&A; confirm)
- Use the installed reviewer tools to attack our own ideas before judges do: `grilling` for the plan, `peer-review` or `academic-research-skills:ars-reviewer` for the method and claims, `caveman:cavecrew-reviewer` or `code-review` for code. Run the strongest model for these.
- Play a hostile judge near the end: generate the hardest questions against the approach, data, weakness and impact, scored against the five criteria.
- Keep `src/docs/qa_cheatsheet.md`: likely judge questions with a short answer each, backed only by fact sheet numbers.
- Draft a 6-minute talk outline with timings and a speaker split when Kent asks. Use the five-part structure: ask, why, how, limits, next step.

## Persona testing (consulting phases)
Claude designs, teammates run. During the consulting phases (understand, frame, solve, evaluate, impact), teammates role-play the agency's users against our work, using Claude Code, ChatGPT or UNC PromptLab. Full process is in `testing/README.md`.
- Six reviewers already exist (hostile judge, data critic, test breaker, and three personas: user, supervisor, budget director). Each is one spec in `testing/reviewers/`; `python3 testing/build_reviewers.py` builds the Claude Code agent or slash command and the paste-ready prompt. Edit specs, never the generated files, and rebuild after any change.
- After problem release, Claude helps Kent fill `testing/context.md` (the one page every reviewer reads) from the real problem and agency sources. Mark invented details [assumed]. Kent approves it before any teammate runs a reviewer.
- For scenario-specific role-plays beyond the six, use the older templates in `testing/`. Prompts must stay self-contained: some teammates have only a chat box.
- Prompts must make the persona skeptical and in character, forbid the AI from inventing our results, and use only real outputs or drafts as the thing being tested.
- Findings come back via `testing/results_log.md`. Claude triages them with Kent (fix, defer, ignore) and updates `handoff.md`.
- Simulated personas are not user evidence. Never put their statements in `fact_sheet.md`, on a slide, or in Q&A as what "users said". Real agency feedback outranks them.
- Log every run in `AI_USAGE_LOG.md`. Use the cheap model for bulk transcript summaries; use the strongest model for persona design and triage.

## Process
- Frame first: write the user, the decision, and the success test before writing code.
- Keep a fact sheet from the first number onward.
- Freeze code at Saturday's 7:00 to 8:00 pm wrap up (submission is Sunday 9:00 am). After that, only slides, rehearsal and checks.
- Current status and open items change often: see `handoff.md`, not this file.
