# 009 Run Prompt Candidate Build

## Summary

Built `tools/codex/run_prompt.py` as a thin V1 runner candidate that resolves one prompt, runs `codex exec` from the repo root, captures `--output-last-message`, captures stderr and return code, writes one V1 execution-record markdown file into `notes/`, prints that path, and exits with the subprocess return code.

## Preserved From `baby_run_prompt.py`

- Kept repo-root discovery via `Path(__file__).resolve().parents[2]`.
- Kept prompt resolution behavior for absolute paths, repo-relative paths, `codex_prompts/` paths, and unique prefix matches.
- Kept direct `subprocess.run(...)` execution of `codex exec`.
- Kept `--output-last-message` capture through a temp file.
- Kept the requirement that `codex_prompts/` and `notes/` already exist.
- Kept one markdown artifact per run in `notes/`.
- Kept printing the written artifact path and returning the subprocess exit code.

## V1 Changes

- Switched artifact output from the old success/failure note format to a V1 execution record.
- Separated execution facts from review facts.
- Initialized review fields with `review_status: UNREVIEWED` and blank manual review fields.
- Added the manual failure-analysis section with blank fields.
- Added the minimum resource/cost fields:
  - `elapsed_seconds`
  - `final_output_char_count`
  - `stderr_char_count`
- Set `execution_status` strictly from subprocess exit code:
  - `0 -> EXECUTED`
  - non-zero -> `EXECUTION_FAILED`
- Recorded `prompt_file` as repo-relative when possible.
- Updated the runner identity field to `tools/codex/run_prompt.py`.

## Collision Rule

Run identity uses second-precision UTC timestamps in the base form:

- `<prompt_stem>__<started_at_utc>`

If `notes/<run_id>.md` already exists, the runner appends a numeric suffix:

- `__2`, `__3`, and so on

This keeps the V1 identity scheme small while avoiding same-second filename collisions.

## Deferred

- Review write-back
- Queue progression logic
- Dependency handling
- Retry orchestration
- Broader CLI redesign
- Multi-module refactor
- JSON sidecars, databases, or any other persistence layer

## Validation

Executed:

- `python3 tools/codex/run_prompt.py codex_prompts/001_smoke_test_pipeline.md`

Outcome:

- The runner resolved the sample prompt and wrote [001_smoke_test_pipeline__20260415_233343.md](/data/git/handson-ml3/notes/001_smoke_test_pipeline__20260415_233343.md).
- The record filename follows the V1 naming rule: `<prompt_stem>__<started_at_utc>.md`.
- The record includes run identity, execution facts, review facts, failure analysis, resource/cost facts, prompt text, Codex final output, and stderr.
- `review_status` starts as `UNREVIEWED`.
- `execution_status` is derived only from the subprocess result. In the validation run it was `EXECUTION_FAILED` because `codex exec` exited `1`.
- `tools/codex/baby_run_prompt.py` remained unchanged. `git diff -- tools/codex/baby_run_prompt.py` returned no diff.

Validation note:

- The sample run did not execute successfully inside `codex exec` because Codex session initialization failed with `Read-only file system (os error 30)`.
- That environment failure still validated the required V1 failure-path behavior: the new runner wrote the execution record, captured stderr, printed the record path, and exited with the subprocess return code.
