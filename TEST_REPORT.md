# Codey 0.1.9 Test Report

Date: 2026-07-02
Environment: Windows / Edge CDP reuse path / DeepSeek, MiMo, Qwen tabs open

## 0.1.9 Bounded Provider Recovery

The three provider drivers now read their normal selectors from one validated,
versioned local profile. If those selectors stop matching, a bounded discovery
layer scores only composer controls and DOM regions changed after submission.
Actionable learned selectors must resolve to one visible control, and Codey
persists them only after observing successful input, submission, or answer
reading. Two failed validations remove a learned record. Optional learning
storage is atomic and cannot fail an otherwise successful provider operation.

Verification:

| Flow | Result |
|---|---|
| Full unittest suite | 277 passed |
| Provider-focused tests | 51 passed |
| Real Edge UI E2E | All 9 checks passed; UI unchanged |
| Normal DeepSeek / Qwen / MiMo tasks | Passed in 5 / 4 / 4 turns |
| Forced DeepSeek core-selector failure | Recovered; input, send, and answer records verified |
| Forced Qwen core-selector failure | Returned `RECOVERY_OK`; all three records verified |
| Forced MiMo core-selector failure | Returned `RECOVERY_OK`; all three records verified |
| Optional storage failure | Did not interrupt the successful provider operation |
| Syntax and patch checks | Passed |

The recovery scope remains deliberately small. It does not bypass login or
CAPTCHA challenges, click low-confidence controls, retain page DOM, or add any
new interface concept. Human one-click teaching remains the final fallback.

## 0.1.8 Hidden Local Continuity

Version 0.1.8 added three bounded, invisible continuity mechanisms:

- Project Facts records only successful controlled `run` commands and injects
  them into later tasks for the same project.
- Conversation persistence stores one compact factual snapshot for each recent
  chat, so a restarted Codey process opens a fresh provider chat with a silent
  handoff instead of losing the task state.
- Durable Snapshot atomically stores the non-Git recovery baseline before a
  project write, retains expected after-content hashes for conflict detection,
  and deletes the record after a successful restore.

The three mechanisms share only a small atomic JSON writer. They use separate
files and retention rules, and none adds a UI control, banner, or status message.
Git projects continue to use Git and do not persist a recovery snapshot.

Verification:

| Flow | Result |
|---|---|
| Full unittest suite | 260 passed |
| Abrupt child-process exit | Facts, conversation, diff, and restore survived |
| Snapshot save failure | Project write was blocked |
| Manual edit after Codey write | Restore conflict preserved user content |
| Missing post-write hash after an interrupted write | Restore refused to overwrite current content |
| Chat deletion racing a late save | Deleted context stayed deleted |
| Non-Git project initialized as Git | Old tracker persistence was disabled; stale references could not recreate recovery |
| Real Edge UI E2E | Passed; UI unchanged, diff and restore passed |
| DeepSeek / Qwen / MiMo edit matrix | Passed in 5 / 4 / 4 turns |
| Independent provider verification | All three unittest fixtures passed |

The live provider run also emitted Node's existing `DEP0169` warning from the
browser automation runtime. It did not affect any provider result and is not
introduced by the local continuity code.

## 0.1.7 Maintainability Refactor

The agent now produces one structured `RunEvent` stream. CLI logs, review
context, SSE updates, and the UI are projections of that stream; the UI no
longer parses human log strings. Local tools return structured `ToolOutcome`
values, so check success and exit codes are not inferred from display text.
Task orchestration moved from the HTTP handler module into `task_runner.py`.

No legacy `agent.tool_*` wrappers were retained solely for tests. Tests now
exercise `tool_runtime.py` directly.

Follow-up regressions cover successful empty-file reads, no-op writes and
edits, and the absence of the legacy string `log` SSE path. A successful tool
call now counts as progress only when `ToolOutcome.changed` is true.

Verification after the refactor:

| Flow | Result |
|---|---|
| Full unittest suite | 224 passed |
| Real Edge UI E2E | Pass, including diff, restore, and shell denial |
| DeepSeek / Qwen / MiMo edit matrix | Pass, 5 / 4 / 4 turns |
| DeepSeek / Qwen / MiMo create matrix | Pass, 4 / 4 / 3 turns |
| Three writer/reviewer pairs | All approved |
| DeepSeek / Qwen / MiMo self-bootstrap | Pass, 5 / 5 / 6 turns |
| Same-model chat continuation | Marker preserved |
| DeepSeek to Qwen handoff | Marker and decision preserved |

Every live project smoke used a temporary directory and independent
post-agent verification. Every bootstrap smoke repaired a temporary Codey
copy and then passed all 219 tests.

## 2026-06-30 End-to-End Coverage

The UI now has a repeatable browser E2E test that launches real headless Edge
against the real local HTTP/SSE server. A deterministic provider drives the
agent so the test can assert the complete product flow without depending on
model variability:

- add a project through the UI
- select a provider
- submit a task and receive SSE updates
- write a file and run its test
- display review and task receipt status
- open and expand the diff drawer
- restore the snapshot and verify the file is removed
- deny a shell approval request and verify no command is executed
- capture screenshots for the completed and restored states

```text
python -B tools/ui_e2e.py --artifacts .e2e-artifacts --json
PASS
```

The live smoke runner now supports a three-provider matrix and independently
verifies the temporary project after the agent finishes. A model returning
`done` is no longer enough to pass: Codey separately executes a functional
assertion and the fixture's unittest suite.

```text
python -B tools/live_smoke.py --provider all --case edit --port 9222 --max-turns 10 --json
DeepSeek: PASS (5 turns)
Qwen: PASS (4 turns)
MiMo: PASS (4 turns)

python -B -m unittest
Ran 224 tests
OK
```

The browser E2E exposed raw JSON protocol payloads and routine `[agent]` logs
in the chat stream. The UI now keeps those internal details out of the chat
and shows only turn dividers, tool rows, review state, and the final receipt.

## 0.1.6 Update

Version `0.1.6` adds a hidden, provider-neutral context handoff:

- one lightweight token estimate for every model
- a soft rollover point near 150k estimated tokens and a 200k hard budget
- one final hidden model turn that returns a bounded factual JSON summary
- a fresh model chat seeded with that summary
- local-fact fallback when summarizing fails
- no budget reset until the fresh chat's first handoff message succeeds
- no new UI controls, context meter, command, or compression notice

Automated verification:

```text
python -B -m unittest
Ran 210 tests
OK
```

Live verification:

| Flow | Result |
|---|---|
| DeepSeek chat summary -> fresh chat | Preserved two decisions |
| Qwen chat summary -> fresh chat | Preserved two decisions |
| MiMo chat summary -> fresh chat | Preserved two decisions |
| Qwen project summary -> fresh chat | Three edits completed; 3 tests passed |
| Qwen empty response recovery | Regenerated once and continued normally |

All project live tests used temporary directories. The main repository was not used as a model editing target.

## Previous 0.1.4 Update

Version `0.1.4` adds compact task receipts in the chat stream:

```text
DONE · 2 files changed · checks passed · restore available        View diff
```

The receipt is built from local facts, not model prose:

- changed file count comes from Git or snapshot changes
- `checks passed` comes from a successful local `run`
- `restore available` appears only for snapshot changes that can be restored
- `View diff` reuses the existing right-side changes drawer

Verification:

```text
python -B -m unittest
Ran 183 tests
OK

python -B -m unittest tests.test_receipt tests.test_agent tests.test_server tests.test_ui
Ran 82 tests
OK
```

Manual UI preview used a temporary local server that exercised the real send/SSE path. The chat showed the receipt line, `View diff` opened the drawer, and expanded diffs showed red/green lines with line numbers.

The 0.1.3 live provider smoke below remains the latest full DeepSeek/MiMo/Qwen live smoke pass.

## Scope

This pass reviewed Codey as a product system, not only as a unit-tested library:

- code elegance and duplication
- local unit tests
- single-model live smoke
- two-model writer/reviewer live smoke
- single-model self-bootstrap on a broken temporary Codey copy
- two-model self-bootstrap on a broken temporary Codey copy

All bootstrap tests used temporary copies. The main repository was not used as the repair target.

## Code Review

The current architecture is still reasonably clean:

- `agent.py` remains provider-independent.
- web page selectors stay isolated in provider drivers.
- two-model review lives in `review.py` and `task_runner.py`, without adding a group-chat UI.
- snapshot diff / restore stays separate in `changes.py`.

I did not extract the repeated `_visible_locator` helpers from MiMo and Qwen. They look similar, but keeping provider DOM code local is currently more robust: if one website changes, the repair stays in one adapter.

Small issues found and fixed:

- Qwen could edit a file and then try to finish without running tests, even when the task explicitly requested tests.
- Qwen could still echo website-side "tool does not exist" noise.
- MiMo could produce invalid JSON when an `old_string` contained unescaped quotes.

Fixes:

- `agent.py` now requires a successful `run` after file writes when the user asked for verification.
- `json_codec.py` now states earlier and more explicitly that tool names are local-runner JSON commands, not website tools.
- `json_codec.py` now reminds models to escape JSON strings correctly, or use full-file `content` when exact replacement strings are hard to escape.
- Added `tools/bootstrap_smoke.py` so self-bootstrap checks are repeatable.

## Local Tests

```text
python -B -m unittest
Ran 176 tests
OK
```

`git diff --check` passed.

## Live Smoke

| Mode | Result | Notes |
|---|---:|---|
| DeepSeek single create | Pass | Created code and tests, ran unittest, finished cleanly |
| MiMo single edit | Pass | Fixed bug, ran unittest, no upload-button misclick |
| Qwen single edit | Pass | After protocol fix, no "tool does not exist" noise; ran unittest before done |
| DeepSeek writer + MiMo reviewer | Pass | Writer fixed bug; reviewer approved |
| MiMo writer + DeepSeek reviewer | Pass | Reverse pair approved |
| Qwen writer + DeepSeek reviewer | Pass | Qwen entered review chain cleanly |

## Bootstrap Smoke

Bug injected into temporary Codey copies:

```text
difflib.unified_diff(after_lines, before_lines, ...)
```

Expected fix:

```text
difflib.unified_diff(before_lines, after_lines, ...)
```

| Mode | Result | Turns | Final full tests |
|---|---:|---:|---:|
| DeepSeek single | Pass | 5 | 160 OK |
| MiMo single | Pass | 5 | 160 OK |
| Qwen single | Pass | 5 | 160 OK |
| DeepSeek writer + MiMo reviewer | Pass | 5 | 160 OK |
| MiMo writer + DeepSeek reviewer | Pass | 5 after prompt fix | 160 OK |
| Qwen writer + DeepSeek reviewer | Pass | 5 | 160 OK |

## Does Two-Model Help?

For this specific injected bug, single-model repair was already strong: all three models fixed it in about five turns. The two-model path did not reduce writer turns because the bug was simple and tests were clear.

The advantage is confidence and failure recovery:

- reviewer sees the actual diff, not just the writer's summary
- reviewer can catch concrete mistakes before the user accepts the result
- if reviewer is unavailable, Codey falls back to single-model mode
- no extra UI switch is exposed to beginners

So the two-model feature is useful, but it should stay quiet and automatic. It is a safety layer, not a new product surface.

## Residual Risks

- Web pages can change DOM structure and break provider drivers.
- DeepSeek sometimes adds prose before JSON; the parser tolerates this.
- Web models can still be verbose or choose larger edits than a human would.
- Functional UI assertions and screenshot capture are automated, but there is
  no pixel-diff visual regression baseline yet.

## Release Notes

Version `0.1.3` is a durable model-browser release:

- model Edge/CDP browser is treated as long-lived user state
- Codey UI restarts do not intentionally close the model browser
- provider connections first reuse existing CDP browsers and model tabs
- if no usable CDP browser exists, Codey opens a new one automatically
- the last working CDP port is saved for quiet reuse after process restart
- no extra UI notification is shown for this recovery path

Version `0.1.2` was a usability and provider-status release:

- live green/gray model availability dots
- UI sends can still auto-open missing model pages
- connected models turn green after successful attach/open
- composer now uses Enter to send and Shift+Enter for newline
- root `DESIGN.md` is the single UI design source
