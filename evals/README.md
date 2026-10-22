# Evals

A small, reproducible before/after of what the skill changes in a coding agent.

- `tasks/` holds nine tiny repositories, each with a `TASK.md` whose front matter lists the files the request should touch and whose body is the request in a stakeholder's voice. Task 09 is the release-notes task: it has no git history, so its input is `CHANGES.md`, a commit list in the same shape as `git log`, and its deliverable is `RELEASE_NOTES.md`.
- `run.sh` runs every task twice with Claude Code in headless mode: `bare` (nothing installed) and `skill` (this skill copied into `.claude/skills/`). Only project settings are loaded, so the machine's own CLAUDE.md and skills cannot leak into the bare condition. Each run's final message, commit message and changed files land in `results/<task>/<condition>/`, and `RELEASE_NOTES.md` is copied there too when the task writes one.
- `score.mjs` applies five yes/no heuristics and prints the table in `RESULTS.md`. Task 09 has two more, `releaseNotesClean` (no commit-type prefix, identifier, file path, docs line or version bump) and `noUnmeasuredEffect` (no speed word and no percentage). They apply to that task only, read `RELEASE_NOTES.md`, and print in their own table. Task 09 declares `kind: notes` in its `TASK.md`, so the five core metrics skip it (it commits nothing), and it is not part of the eight-task tables in `RESULTS.md`, `RESULTS-models.md` or the comparison; those tables count only the other tasks, so they read the same with task 09 present.
The two release-notes heuristics are regular expressions over the words of the notes. They miss paraphrases (a speed claim written as "fast", "quickly", "snappy" or "lighter" passes), and they flag an honest line that uses a banned word, so a line that says the effect was not measured is exempted; a line that carries both an exemption phrase and a claim is exempted whole. With `PE_EVAL_RUNS=3` each arm runs three times per task, results land in `run-N/` directories, and the table gains a seeded bootstrap interval on the mean per-task delta.
- `judge.mjs` asks a model which of the two commit messages is truer to the diff, in a random order per pair; it prints the pair count and cost and runs nothing without `--yes`.
- `BENCHMARK.md` is the design for a fifty-diff measurement on public commits. Design only.

```
sh evals/run.sh                        # prints the plan and the cost, runs nothing
sh evals/run.sh --yes                  # 16 headless runs into evals/results-<timestamp>
PE_EVAL_RUNS=3 sh evals/run.sh --yes   # 48 runs
PE_EVAL_SKILL=customer-block sh evals/run.sh --yes   # the skill arm installs only that skill
PE_EVAL_SKILL_PATH=/abs/dir sh evals/run.sh "" skill --yes   # install a skill from outside this repository
PE_EVAL_BUDGET_USD=5 sh evals/run.sh --yes   # never start a run that could take the spend past $5 (exit 3)
node evals/by-model.mjs <results-dir>...   # one section per model, never averaged
sh evals/run.sh --yes --overwrite      # replace the published run in evals/results
node evals/score.mjs                   # table, per-task rows, and every failing cell
node evals/score.mjs evals/results-... # score your own run instead
node evals/judge.mjs                   # pair count and cost; add --yes to judge
```

Three things make a rerun comparable with the published one. The model is pinned to
`claude-opus-5` in `run.sh`, because an unpinned run silently compares against whatever
the CLI defaults to that week; override it with `PE_EVAL_MODEL`. The `claude --version`
string and the requested model are written into every `meta.json`, so a result carries
the versions that produced it. And a rerun writes to `evals/results-<timestamp>` rather
than over `evals/results`, which holds the run the table in `RESULTS.md` is built from.

`PE_EVAL_SKILL` names one directory under `skills/` for the skill arm to install instead of the
core pack, so `customer-block`, `done-means-observed` and `release-notes` can be measured on their
own. `meta.json` records it as `skill`, and `score.mjs` refuses to put runs of different skills in
one table. Runs recorded before `meta.json` named the skill count as `product-engineer`.

`node evals/score.mjs --failures` prints every cell that failed together with the
evidence: the commit line that had no block, the sentence that carried a bare number,
the files a run touched that the task did not list.

The heuristics are regular expressions over the agent's own words and `git diff --name-only`. They are cheap and blunt on purpose; `RESULTS.md` lists what they miss.
