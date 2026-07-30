# ADB Android Environment Bridge

Controls an Android emulator (Genymotion) or a physical device through adb, and
exposes an HTTP protocol to the benchmark that is **fully compatible with the
MobileGym bridge**. The Aiden Go agent is unaware of the device implementation —
it still only uses `--environment-bridge-mode` to forward tool calls.

```text
benchmark/runner (test orchestration)
  ↓ /api/chat
Aiden Go Daemon (environment-bridge mode)
  ↓ POST /api/tools/{tool}         ← tool calls (screenshot / touch_gesture / ...)
ADB Android Bridge (this module, local Python process)
  ↓ adb -s <serial> shell input ...
Android emulator / physical device
```

Differences from MobileGym: MobileGym runs in Docker and supports multiple
concurrent environments; the ADB bridge is a **local process driving a single
device** (`/api/concurrent` is always 1) and needs no Docker.

## Prerequisites

1. **adb available**: `adb` on `PATH` (or pass `--adb-path`), and `adb devices`
   shows the target device:

   ```text
   $ adb devices
   List of devices attached
   127.0.0.1:6555	device        # Genymotion (default)
   emulator-5554	device        # this is what an official AVD looks like
   XXXXXXXX	device            # a USB physical device
   ```

   ⚠️ The default serial is Genymotion's `127.0.0.1:6555`. For an AVD or a
   physical device you must pass `--adb-serial <serial>` explicitly (or set the
   `ANDROID_SERIAL` environment variable).

2. **Python dependencies**: just run under `uv` from the `benchmark/` directory
   (Pillow is used for screenshot compression and is already in
   `pyproject.toml`).

3. **agent config**: the Go daemon needs your own config directory (LLM provider
   and API key); see `benchmark/config/agent.toml.template`. The repo contains no
   secrets.

## Quick start

### Option 1: CLI (recommended)

```bash
cd benchmark

# 1. Start the bridge (background process; prints environment_url and more)
uv run python -m runner start-adb-android-env \
  --adb-serial 127.0.0.1:6555 \
  --bridge-port 8899

# 2. Start the agent daemon (Docker container; builds the image automatically)
uv run python -m runner start-agent-daemon \
  --environment-bridge-endpoint http://127.0.0.1:8899

# 3. Run the benchmark (take --agent-url / token from step 2's output).
#    This command enables the judge — export OPENROUTER_API_KEY first;
#    see the "Judging" section. Append --no-judge to only exercise the pipeline.
uv run python -m runner run \
  --suite suites/adb_android_basic.json \
  --agent-url http://127.0.0.1:<agent-port> \
  --environment-url http://127.0.0.1:8899 \
  --benchmark-task-id cli-task \
  -v
```

Stop the bridge with the `stop_command` (`kill -TERM <pid>`) printed by step 1.

### Option 2: Manual startup (when debugging the Go daemon)

```bash
# 1. Start the bridge as a foreground process
cd benchmark
uv run python -m adbandroid.scripts.start_bridge \
  --adb-serial 127.0.0.1:6555 \
  --bridge-port 8899

# 2. Run the daemon locally (the daemon and the runner must use the SAME benchmark-task-id)
cd ../src/agent
go run ./cmd/daemon \
  -config <your config directory> \
  --environment-bridge-mode \
  --environment-bridge-endpoint http://127.0.0.1:8899 \
  --environment-bridge-tools "screenshot,touch_gesture,keyboard_text,keyboard_tap,enter_text,mouse_click,mouse_move,mouse_scroll,quick_action" \
  --benchmark-task-id cli-task

# 3. Run the benchmark (same as Option 1 step 3, with --benchmark-task-id cli-task)
```

### Option 3: WebUI

```bash
cd benchmark
uv run python -m runner webui
```

In the browser: pick a suite → Run → in the environment dialog switch to the
**ADB Android** tab → fill in the serial → Start → select that environment →
Run. The WebUI starts/stops the bridge process and, after a restart, can recover
a still-running bridge via its pidfile + a `/health` probe.

## Judging

The judge scores each task's rubric item by item using the pre/post screenshots
and the trace (e.g. "did Settings actually open?", "was the alarm count
correct?"), over an OpenRouter-compatible endpoint. The judge model is
completely independent of the agent-under-test model (the agent model is set in
`agent.toml`).

- **`--no-judge`**: no judging; rubrics record 0/N and pass/fail depends only on
  the hard assertions (an action ran, no timeout). Good for first verifying that
  the pipeline works end to end.
- **Judge enabled** (the default for `run`, i.e. without `--no-judge`): you must
  provide `OPENROUTER_API_KEY`, otherwise it fails with
  `missing env var OPENROUTER_API_KEY`.

```bash
cd benchmark
export OPENROUTER_API_KEY=sk-or-...

uv run python -m runner run \
  --suite suites/adb_android_basic.json \
  --agent-url http://127.0.0.1:<agent-port> \
  --environment-url http://127.0.0.1:8899 \
  --benchmark-task-id cli-task \
  --judge-model anthropic/claude-sonnet-4-6 \
  -v
```

`--judge-model` can be omitted (default `anthropic/claude-sonnet-4-6`); pass an
OpenRouter model name to use a different judge model.

> The correctness of the multi-step tasks (count alarms in Clock / check WiFi /
> open the app drawer) can only be verified by the judge; under `--no-judge`
> their rubrics are always 0/N.

### Re-scoring existing results (rejudge)

After a `--no-judge` run, the pre/post screenshots and the trace are already
saved in the run directory, so you can re-score **without re-running the
device**:

```bash
export OPENROUTER_API_KEY=sk-or-...
uv run python -m runner rejudge \
  --run-dir runs/<that run's directory> \
  --judge-model anthropic/claude-sonnet-4-6
```

This saves a full round of device operations when tuning rubric wording, or when
you ran `--no-judge` first to verify the pipeline and want to score afterward.

## Test suite

`benchmark/suites/adb_android_basic.json`, 8 tasks:

- Basic capabilities (5): screenshot, go Home, open Settings, swipe, enter
  English text.
- Multi-step tasks (3, ported from mobilegym_basic): count alarms in Clock,
  check WiFi status, open the app drawer.

Note: `required_tools` for the action tasks is intentionally left empty — every
action tool on the daemon already returns a post-action screenshot, and the
agent may reach the same outcome with either `quick_action` or `touch_gesture`.
The correctness of the multi-step tasks is judged mainly by the rubric; under
`--no-judge` the hard assertions can only check "an action ran and it did not
time out".

## HTTP protocol

Consistent with the MobileGym bridge (both the runner and the Go agent integrate
against this):

| Endpoint | Description |
|---|---|
| `GET /health` | Returns 200 when the device is online; 503 when adb is unreachable |
| `GET /api/concurrent` | `{"ok":true,"data":{"concurrent":1,...}}`; always 1 for a single device |
| `GET /api/screen` | Current screenshot (no setup required; used by the runner for pre/post capture) |
| `POST /api/setup` | Reset to home + create an episode; single-device ownership keyed on the `benchmark-task-id` header |
| `POST /api/release` | Release the task id's ownership |
| `GET /api/tools` | Tool catalog |
| `POST /api/tools/{tool}` | Tool invocation (the Go agent's forwarding entry point) |

Task-routing semantics (single-device variant, aligned with MobileGym's
single-env behavior):

- **Empty `benchmark-task-id`**: falls straight through to the one device state
  without an ownership check (the WebUI serial path relies on this, because the
  daemon's tool calls carry no such header).
- **With a task id**: the first setup takes ownership; the same id is idempotent;
  a different id returns `429 no_bridge_env_available` until the owner releases.

## Tools and coordinates

The tools match MobileGym: `screenshot` `touch_gesture` `keyboard_text`
`keyboard_tap` `enter_text` `mouse_click`
`mouse_move` `mouse_scroll` `quick_action`.

Coordinate spaces (`coord_space`):

- `normalized` (default): 0-1000 → converted to pixels via `adb shell wm size`
  (Override wins over Physical).
- `absolute`: 0-32767 (HID space) → pixels.
- `auto`: only accepts 0-1000, errors when out of range (same as MobileGym).
- `pixel`: real pixel coordinates additionally supported by the ADB bridge; must
  be requested explicitly and is clamped to the screen bounds.

`quick_action` (`platform=android`): `back` / `home` / `app_switch` / `send` /
`open_settings` (`am start -a android.settings.SETTINGS`) / `notification_center`
/ `control_center` / `dismiss_panel` (the `cmd statusbar` family, falling back to
a gesture on failure). Pass `{"list": true}` to see the full catalog.

## Known limitations

- **Text input is English-only**: `adb input text` cannot type Chinese/IME
  composed text; non-ASCII returns an explicit error, and a literal `%s` in the
  text is typed as a space (the `input text` escaping convention). Chinese input
  would need a clipboard/IME approach, not yet implemented.
- **Single-device, serial**: one bridge drives one device and does not support
  concurrent tasks. For multiple devices run multiple bridge instances (different
  ports + different serials).
- **`keyboard_tap` does not support ctrl/alt/shift combos**: adb has no reliable
  way to inject them, so such combos are rejected with an error rather than
  silently executing a different key. `hold_ms` is accepted but ignored — adb
  `input keyevent` cannot hold a key for an arbitrary duration.
- After an action the bridge waits 0.6s before taking the screenshot
  (`DEFAULT_ACTION_SETTLE_SEC`); on slow emulators a transition animation may
  still be in flight, and the agent can call `screenshot` again to confirm.

## Troubleshooting

| Symptom | Cause / fix |
|---|---|
| `/health` returns 503 `device_unavailable` | Check with `adb devices` that the serial is correct and the state is `device` (not `offline`/`unauthorized`) |
| Startup reports `adb binary not found` | adb is not on `PATH`; pass `--adb-path /path/to/adb` |
| A tool call returns 429 `no_bridge_env_available` | The device is owned by another task id: make sure the daemon and the runner use the same `--benchmark-task-id`, or call `/api/release` |
| A tool call returns 409 `no_active_episode` | `/api/setup` was not called first (the runner does this automatically; when debugging with curl you must setup first) |
| A screenshot raises a Pillow-related ImportError | The venv install is corrupt; `uv sync --reinstall-package pillow` |

Unit tests (no real device needed):

```bash
cd benchmark
uv run pytest tests/test_adbandroid_bridge.py tests/test_adbandroid_tools.py
```
