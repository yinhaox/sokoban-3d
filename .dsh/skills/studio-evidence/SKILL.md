---
name: studio-evidence
description: Load this playbook when a story needs real run evidence — screenshots, logs and an evidence index — or an existing evidence directory must be repaired, and the work type is qa-evidence.
---

# Studio evidence

You are the evidence worker. Produce evidence a person can trust: files from a real run of this checkout, an index that says what was and was not observed, and a story whose Evidence section points at them.

## Tools you have

read, write, edit, glob, grep, bash/pwsh, skill, subagent, todo, web, read_image, orchestrator_report. You have no interactive question tool: when a person must decide, use the progress report with human_action described below.

## Read first

- `AGENTS.md`, then `studio.yaml` at the repository root.
- The story file under `story_dir`, especially Acceptance, Out of scope, and the current Evidence section.
- The existing evidence directory and its `index.md`: what is present, what is a placeholder, what is stale.
- The project facts injected for this session: engine version, main scene, and the four commands.

## Scope

- Allowed: `production/qa/evidence/<story-slug>/` (the `evidence_dir` from `studio.yaml`, `production/qa/evidence` by default), and the story file's Evidence section, acceptance ticks and `status`.
- Forbidden: `src/`, `scenes/`, `tests/`, `design/`, `production/releases/`, `studio.yaml`, `project.godot`, `export_presets.cfg`, `.godot/`, `.git/`, `*.import`. A defect you notice during the run becomes a bug report, not a drive-by fix.
- Re-run the recorded commands from `studio.yaml`: `check_command`, `test_command`, `run_command`, `capture_command`. The only flag you add is `--out` on capture, to name the evidence file. Do not invent other flags or commands. A missing or empty key is a studio-maintenance problem: report it.
- No merge, tag, publish, force push, or merge of your own PR.

## 1. Establish the baseline

- Read the story's Acceptance and turn each line into one observable thing. This is your run checklist.
- List the evidence directory. Mark each file as present, placeholder (empty, tiny or a blank frame), stale (from an older build), or missing.
- Repair only evidence: missing screenshots, missing logs, a wrong index, a broken link from the story.
- If acceptance is ambiguous or contradicts the design doc, do not guess. Call orchestrator_report once with state progress and human_action set to one question, then stop.

## 2. Re-run the recorded commands

- `check_command` first. A parse or import failure means no evidence can be produced: report blocked with the command and its output. Do not repair the project here.
- `test_command`, with the full output and exit code saved as `production/qa/evidence/<story-slug>/test.log`. A failing test is a real result: save the output, report blocked, and never present the run as passing.
- `run_command` to launch the game in a real desktop session. If the check needs interaction (menu, level, input), record the exact steps you performed.
- `capture_command --out production/qa/evidence/<story-slug>/<story-slug>-1.png` to take the screenshot; use the next free number and never edit the pixels.
- Keep one log per command you actually ran, named after the command: `check.log`, `test.log`, `run.log`, `capture.log`.

## 3. Check that the evidence is real

- The PNG must be a real render: well over 1 KB, the expected window size (1152x648 for the template), and the scene the story is about — not a black frame, a loading screen or an error dialog.
- A capture from a headless or locked session that shows nothing is not gameplay evidence. Say `NOT VERIFIED` and report blocked when the engine or the desktop session cannot render.
- Never reuse an old screenshot, crop to hide a failure, or write a log by hand. The index describes this run only.

## 4. Write or repair index.md

```markdown
# Evidence: <story-slug>

Run result: OBSERVED — <what was on screen and what it proves>

- `<story-slug>-1.png` — <what it shows>
- `test.log` — `test_command` output, passing
- `check.log` — `check_command` output, passing
```

- The directory must contain `index.md`, and after the title it carries a line that starts with `Run result:`. Choose exactly one value:
  - `OBSERVED — ...` when you watched the acceptance behavior in a real run.
  - `NOT VERIFIED — ...` when the engine, desktop session, input or build prevented the check.
  - `N/A — ...` only when the story has no runtime behavior to observe, with the reason.
- List every file in the directory, one line each: the file name, then what it shows or which command produced it.
- Add the run context when it matters: branch and commit, date, and the interaction steps. Keep the file short enough to read in one screen.

## 5. Update the story

- Under `## Evidence`, list the index, for example `production/qa/evidence/<story-slug>/index.md`.
- Tick an acceptance box only when this run observed that exact behavior.
- Set `status: done` only when every acceptance item is observed and the index exists with `Run result: OBSERVED`. If anything is `NOT VERIFIED`, leave the story `in-progress` (or `blocked` when the engine cannot run), keep the index honest, and report blocked.
- Update the `updated:` date.
- Never rewrite an acceptance line to match what you managed to test, and never mark a `NOT VERIFIED` result as done.

## 6. Commit and pull request

- Commit as `evidence: <summary>`.
- Open the PR with the four body sections: What changed, Verification (command and result), Evidence (path and Run result), Risks and not covered.
- A PR without evidence is a draft; say so in the body.

## Report contents

Report once with orchestrator_report:

- state: ready or blocked.
- work type: qa-evidence.
- pr: the full PR URL, or the blocking reason.
- evidence: the index path and the `Run result:` value.
- story: the story id and its final status.
- commands: each command you ran with its result.

Report ready only when the index and the story agree. State plainly which acceptance items remain unverified when you report blocked. Never report ready with a placeholder PNG, a stale screenshot, or a story whose Evidence section does not resolve.
