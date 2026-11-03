# Rukoo Voice agent guide

This file adds to the [root AGENTS.md](../AGENTS.md) for work in `voice/`. The root rules for pull requests, commits, issues, public evidence and `tmp/` apply here too. The Electron parts of the root file, such as `npm start`, `SEM_DATA_DIR`, Playwright and the i18n catalogs, apply to Rukoo's side of the bridge, not to Voice itself.

## Project intro

Rukoo Voice is push-to-talk dictation plus the meeting recorder for Rukoo. It replaces [Ownkey for Windows](https://github.com/MajesteitBart/ownkey-windows). Voice records and transcribes. Rukoo shows the meeting and runs the user's agent. [README.md](README.md) describes the design and the decisions made so far.

When a design decision changes, update README.md in the same PR.

## Build and test

Voice is a Rust workspace in this folder. Run cargo from `voice/`. The local speech worker links sherpa-onnx statically; its build downloads a 123 MB archive once per target folder, unless `SHERPA_ONNX_ARCHIVE_DIR` points at a folder that already holds `sherpa-onnx-v2.0.1-win-x64-static-MT-Release-lib.tar.bz2`.

- Everything, as Windows CI runs it: `cargo fmt --all --check`, `cargo clippy --workspace --all-targets -- -D warnings` and `cargo test --workspace`.
- The two recorder tests this file requires: `cargo test -p voice-recorder --test crash`.
- The screen process's crash tests: `cargo test -p voice-screen --test crash`. Each test runs the real recorder and the real screen process on a synthetic screen with Microsoft's software encoder, as Windows CI does; the test binary plays both programs through `VOICE_SCREEN_TEST_ROLE`. `VOICE_SCREEN_TEST_SPEC_EXTRA=warp` runs them on WARP, the software graphics device of a CI runner, and `VOICE_SCREEN_TEST_ORPHAN_MS` shortens the 60 s rule that stops a screen process without a recorder.
- `cargo test -p voice-screen --test crash -- --ignored` needs a hardware H.264 encoder. `hard_kill_with_hardware_encoder` hard-kills the screen process on the GPU path; run it again with `VOICE_SCREEN_TEST_SIZE=1440x2560` for a portrait monitor. `spike_hardware_encoder_scales_large_monitors` checks the sizes the encoder takes. `spike_real_capture_cadence` captures the real screen, so it skips itself unless `VOICE_SCREEN_TEST_REAL_SCREEN=1` and `VOICE_SCREEN_TEST_REAL_DIR` names a scratch folder under `tmp\`; cover every display with demo windows first.
- Linux CI runs `cargo test -p voice-protocol -p voice-audio -p voice-recorder -p voice-core -p voice-bridge -p voice-meetings -p voice-screen-files`.
- The local model tests in `voice-local` load Orukeet read-only from Ownkey's model folder when it exists, or from `RUKOO_VOICE_TEST_ORUKEET`, and skip otherwise. `RUKOO_VOICE_TEST_SPEECH` names the WAV they transcribe.
- `cargo test -p voice-input -- --ignored` runs the tests that use the real clipboard and send keys. Run them only on a desktop nobody is using, such as a VM.
- The pill and Settings pages run without Voice on mock data: `node voice/ui/dev/serve.js`, then open the address it prints. `node voice/ui/dev/screenshots.js tmp/voice-ui-shots` captures every state, and `node voice/ui/dev/check.js` checks their behavior.
- Rukoo's side: `node --test test/voice-*.test.js test/agent-tools-meeting.test.js`, and `npx playwright test test/e2e/meeting.spec.js` for the meeting view.
- Rukoo against Voice's real bridge server: `RUKOO_VOICE_INTEROP=1 node --test test/voice-interop.test.js`, which builds and runs `voice-bridge`'s `serve` example.
- Speaker labels against the real runtime and model: `powershell -File voice\scripts\speaker-assets.ps1 -Out tmp\speaker-assets` fetches the published NeMo runtime, the Nemotron model and the AMI excerpt, checks their hashes and prints three variables. With `RUKOO_VOICE_TEST_NEMO_DIR`, `RUKOO_VOICE_TEST_NEMOTRON` and `RUKOO_VOICE_TEST_AMI` set, `cargo test -p voice-speakers --test runtime` and `cargo test -p voice-meetings --test speakers_ami` run instead of skipping. `RUKOO_VOICE_TEST_AMI` alone is enough for the AMI oracle check in `speakers_ami`. Until the runtime is published, point `RUKOO_VOICE_TEST_NEMO_DIR` at a local build (`voice/nemo-runtime/README.md`). Windows CI fetches the same assets and sets the variables for what it found. A test without its assets returns early and libtest reports it as passed, so CI warns when an asset is missing, and fails once the runtime is published.
- The speaker label scorer: `voice-meetings/tests/common/score.rs` and `voice/scripts/lib/speaker-score.mjs` both pass `voice/fixtures/speaker-score-vectors.json`; `node --test test/voice-speaker-score.test.js` runs the JavaScript side.
- Pins that must agree: `voice-speakers/tests/assets.rs` and `voice-core/tests/models.rs` fail when `speaker-assets.ps1` downloads another Nemotron than `ModelSpec::nemotron()`. `voice/fixtures/binarizer-vectors.json` comes from Ownkey's binarizer: regenerate it with `py -I voice/scripts/binarizer-vectors.py` (Python with NumPy 2), never by hand.
- `voice-speakers` is Windows-only and isn't in the Linux list; its tests expect the worker's refusal on other systems.

## Run

`cargo build -p voice-app -p voice-recorder -p voice-local -p voice-speakers -p voice-screen` puts `rukoo-voice.exe`, `rukoo-voice-recorder.exe`, `rukoo-voice-local.exe`, `rukoo-voice-speakers.exe` and `rukoo-voice-screen.exe` together in `target\debug`; the app finds the other four next to itself. Set `SHERPA_ONNX_ARCHIVE_DIR` first, as above. Tauri embeds `voice/ui` when it compiles, so a page change needs a rebuild.

- A development copy: set `RUKOO_VOICE_DATA_DIR` to a scratch folder under `tmp\` and `RUKOO_VOICE_BRIDGE` to a discovery file path, then run `target\debug\rukoo-voice.exe`. It uses F13 and F14, never imports Ownkey on its own and never starts at login. Its log is `<data folder>\logs\app.log`. It transcribes with Orukeet from Ownkey's model folder, read only; the first meeting window hashes the model once and keeps a stamp in `<data folder>\models`.
- No microphone or speakers needed: `RUKOO_VOICE_TEST_SOURCES="mic=file:<you.wav>,loop,call=file:<them.wav>,loop"` makes the recorder play WAV files in real time instead (`synthetic:tone:440` works too). Only a development copy reads it.
- No screen to show: `RUKOO_VOICE_TEST_SCREEN="synthetic:1920x1080,change-every=10000,text=Slide"` makes the screen process record a synthetic screen whose slides read "Slide 1", "Slide 2" and so on, with the options of the `--test` table in [RECORDING.md](RECORDING.md). `RUKOO_VOICE_TEST_MONITOR=\\.\DISPLAY2` pins the monitor every screen process records; when that monitor isn't there, the screen process exits instead of recording another one. Only a development copy reads either. Without them, a meeting set to frames or video records the real screen.
- Pair it with a development Rukoo: start Rukoo with `SEM_DATA_DIR` under `tmp\`, the same `RUKOO_VOICE_BRIDGE` and `ELECTRON_RUN_AS_NODE` removed.
- Speaker labels need the NeMo runtime. Voice looks for it in a fixed order: `RUKOO_VOICE_NEMO_DIR` (a development copy only), then `nemo_speech\` next to the exe, checked against `voice/nemo-runtime/manifest.json`, then the installed Ownkey's `nemo_speech\`, read only, when its DLLs match Ownkey's known hashes and Ownkey's Visual C++ runtime is in the folder above it, which the worker then also searches for the DLLs' imports. For work on this PC point `RUKOO_VOICE_NEMO_DIR` at a local build, and `LOCALAPPDATA` at a folder under `tmp\` when a run must not read Ownkey's folders. `RUKOO_VOICE_TEST_NO_SPEAKERS=cpu`, `runtime` or `model` makes a development copy behave as if that part were missing. A development copy logs how long the speaker worker's calls take, on stderr as `voice-meetings: <meeting>: speaker worker ...`: a summary each minute, every call slower than 1 s, and a failed call with the 20 calls before it, so a worker that slows down under load can be told from one that hangs.
- `--dev-hooks <folder>` lets a script drive a development copy without the tray or the keyboard: it writes `request.json` with `status`, `start_meeting`, `stop_meeting`, `pill_screen_click` (what the pill's screen button does) or `capture` (the pill and Settings at a page, from WebView2) and reads `reply-<id>.json`.
- The live paired run is the acceptance test for meetings: `node voice/scripts/live-meeting.mjs`, or with `--skip-build` after a build. It builds into `CARGO_TARGET_DIR` when that is set and runs the programs from there, debug builds unless `--release` is given. It makes SAPI speech, runs Voice and a hidden Rukoo on the demo account, and checks passages on both tracks before the stop, the pill, Rukoo's window protection, frames with their text in Rukoo while it records, a killed screen process, a Voice restart mid-meeting, a killed recorder, the video files' fragments, processing then done, `meeting.get`, and a meeting started from Voice. It takes under two minutes after a build and stops every process it started by process id. The report is `tmp\live\<time>\report.json`, with counts and the demo strings that matched but never the text read from a frame, and the captures go to `tmp\live-shots\`. Voice's pill and Settings show on the desktop while it runs, without taking focus.
  - `--screen off|frames|video` sets Voice's default screen mode for the run, `frames` unless given; one more meeting from Rukoo asks for video. The screen is the synthetic one of `RUKOO_VOICE_TEST_SCREEN`, so a default run captures nothing of the desktop.
  - `--real-screen` records the real displays. The script covers every display with a demo window, a slide window on one and an always-on-top cover on the others, pins the slide display with `RUKOO_VOICE_TEST_MONITOR`, and stops, deletes the meeting's `screen` folder and fails when the recording starts on another display. Notifications can still draw above the demo windows, so the run deletes its Voice data folder and Rukoo profile at the end and takes no captures of the meeting view. Run it only when nobody uses the desktop.
  - `--real-screen --choose-monitor=\\.\DISPLAY2` (or `DISPLAY2`, since Git Bash drops the leading backslash) checks that Voice records the display of the window in front, then switches from the pill and from Rukoo's header. `--real-screen --visible-rukoo` puts Rukoo's window over half the slide and checks the first frame of a meeting from Voice with Rukoo's hide-from-capture switch off and on.
  - `--measure=screen` measures CPU and GPU of Voice's processes in four 10-minute meetings with live transcription, with `voice/scripts/measure.ps1`, in a release build: screen off, frames and video on a synthetic screen the size of the main display, then video at the other display's size. The synthetic screen shows a new slide every 10 s, so nothing shows on the desktop and the run can go while someone works. `--measure=screen --real-screen` measures on the demo slide display instead, with slides, a scrolling page and a still screen, and needs the desktop to itself like every real-screen run. `--seconds=<n>` shortens each meeting for a trial. Live speaker labels are off in these meetings, so the screen's cost stands alone; with `--speakers` they are on, the call is the AMI excerpt and the speaker worker is measured too.
  - `--speakers` plays the AMI excerpt as the call (`speaker-assets.ps1` fetches it into `tmp\speaker-assets`) and adds the speaker checks: three call speakers in Rukoo before the stop, a name on MEE071's id that stays through a killed speaker worker and the Voice restart, at least 90% of the call's passage time to the right speaker, and no passage moved between ids. The runtime is `RUKOO_VOICE_NEMO_DIR`, else `tmp\speaker-assets\nemo_speech`, else Voice's own lookup. It combines with `--screen`, so `--speakers --screen frames` checks labels and frames in one meeting, but not with `--real-screen`, whose slides follow the SAPI call.
  - `--speakers=cpu`, `runtime` or `model` runs a short meeting with `RUKOO_VOICE_TEST_NO_SPEAKERS` set: the call stays `call-1`, Settings gives that reason, and its Speaker labels page is captured.
  - `--measure=speakers` measures labels on and off: the worker's `--self-test` real-time factor, then two meetings in fresh data folders with CPU per process by pid, the worker's peak memory and the call passages' latency. `--minutes=<n>` sets their length (default 5); 21 or more makes the labels-on meeting the compaction check as well. Use `--release` for numbers.
- `--fake-engine[=idle|meeting|dictation|cycle|first-run]` runs the windows against scripted states, and `--self-test <folder>` with it captures both pages in both themes and languages. Both refuse to run without `RUKOO_VOICE_DATA_DIR`.

## Package

`powershell -File voice\scripts\package.ps1` builds the five release programs, adds the NeMo runtime as `nemo_speech\` and writes `voice\target\package\Rukoo-Voice-Setup-<version>.exe`, a per-user installer into `%LOCALAPPDATA%\Programs\Rukoo Voice`, plus `Rukoo-Voice-Portable-<version>.zip` and `SHA256SUMS.txt`. It needs Node for `npx`, 7-Zip and the Visual Studio C++ build tools. Its cargo target folder must be on the checkout's drive: Tauri's bundler loses the drive letter of sidecar paths on another drive, so `package.ps1` stops before building. It checks the installer by unpacking it, never by installing it: an installed Voice answers Right Alt and Right Ctrl, the same keys as the installed Ownkey. It also checks that `rukoo-voice-screen.exe` doesn't import Media Foundation, and its hooks test runs a recorder and a screen process on synthetic sources.

After a dependency change it stops until you run it once with `-UpdateNotices` and commit the updated `THIRD_PARTY_NOTICES.md`. The icons come from `voice/crates/voice-app/icons/mark.js`; `npx electron voice/crates/voice-app/icons/make-icons.js` renders them again.

The runtime has to be published first: until `voice/nemo-runtime/manifest.json` names its archive, `package.ps1` stops with "Publish the NeMo runtime first". `voice/nemo-runtime/build.ps1` builds the runtime, `pack.ps1` zips it and writes the manifest that pins it, and `voice/nemo-runtime/README.md` says how a workflow artifact becomes the published prerelease. To check a package before that, pass `-RuntimeManifest` with the manifest `pack.ps1` wrote and a `file:///` archive URL; the programs then compile in that manifest, so such a package is for testing only.

Releases: bump the workspace version in `voice/Cargo.toml`, merge, then push a `voice-v<version>` tag from main. `.github/workflows/voice-release.yml` attaches the installer, the zip and the checksums to a draft release that is never marked Latest. 0.1 is unsigned, so SmartScreen warns about the installer.

## What makes this project special?

- **A meeting can't be repeated.** Losing a recording is the worst failure Voice can have. The crash safety rules in README.md are hard requirements. The recorder never depends on transcription, the UI or Rukoo. A hard kill at any moment leaves files that open. Two CI tests prove it: one hard-kills the recorder halfway through a meeting, the other removes the microphone during one, and both check that the timeline is complete up to that point. Add them with the first recorder code, and don't merge recorder changes without them.
- **The key has to let go and the pill has to appear.** Three Ownkey fixes were about this: ownkey-windows #11 fixed recording that stuck after a lost key release, #13 a pill that vanished after a display change, #14 a pill that opened underneath other windows. A missed key-up must never leave recording on. The pill never takes focus and shows above other windows.
- **Voice and Rukoo share one protocol.** The bridge's events, commands and discovery file are implemented on both sides: here and in Rukoo's main process (`src/main/`). A change on one side needs the matching change on the other in the same PR, with the protocol version raised when old peers would misread it. Keep the spec in `voice/PROTOCOL.md` and give both sides tests that read the same fixtures, the way Android and desktop share `test/fixtures/account-vectors.json`.
- **Data goes only where the user sent it.** Voice keeps Ownkey's promise: no telemetry, no account and no relay. Audio and text go to the provider the user configured or stay on the computer, and a local model never falls back to the cloud. The only other destinations are the user's own bucket and the opt-in update check.
- **Everyone in the call is a third party.** People in a meeting can say anything, including instructions aimed at an agent. Voice never acts on what it hears in a meeting. Rukoo hands the transcript to the agent as untrusted content.

## A note from the maintainer

Ownkey for Windows is the reference for behavior that already works: providers, text cleanup, pinned and checked models, the meeting store and the consent rules. Port the behavior, not the structure. Read the [Ownkey repository](https://github.com/MajesteitBart/ownkey-windows), including its AGENTS.md, before changing hotkeys, text insertion or model loading here. Its fixes record why things are the way they are.

## The ways to hurt yourself

The installed Ownkey runs every day on the maintainer's Windows PC as `Ownkey.exe` and `ownkey-overlay.exe`, next to the installed Rukoo. Most dangers come from a dev copy of Voice touching their state.

- **Don't stop, restart or replace the installed Ownkey or Rukoo.** Never kill a process by image name. Stop only processes you started, by PID.
- **Don't answer Ownkey's hotkeys.** Ownkey listens on Right Alt and Right Ctrl, so a dev Voice on the same keys types every dictation twice. Use F13 and F14 in dev configs.
- **Read Ownkey's settings, never write them.** `%APPDATA%\Ownkey\config.json` holds the maintainer's API keys. Voice's import only reads it. Test the import against a copy.
- **Share Ownkey's models, don't delete them.** Voice reuses the models in `%LOCALAPPDATA%\Ownkey\models`: Orukeet is 487 MB and Nemotron 107 MB. Removing a model in Voice removes it for the installed Ownkey too.
- **Leave the real meeting library alone.** `%LOCALAPPDATA%\Ownkey\meetings` holds real recordings. Work on copies in a temp folder only.
- **Pair dev copies with each other, not with the installed apps.** A dev Voice that writes the default discovery file is found by the installed Rukoo, and a dev Rukoo finds the installed Voice. The discovery file location must be overridable from the first version, so a dev Voice pairs with a Rukoo started with its own `SEM_DATA_DIR`. Ownkey had this problem with its overlay port: a dev backend sent its states to the installed overlay.
- **A screen recording shows everything on that monitor.** That includes mail, notifications and chats. Test screen recording on a monitor with demo data. Real audio, transcripts, frames, video and speaker names never go into the repo, a PR or an issue.

## Test data

- The 60-second AMI meeting excerpt that ships with NeMo-Speech.cpp has three speakers. Use it for speaker labels. `speaker-assets.ps1` fetches it with the hashes in `voice/fixtures/ami/manifest.json`; the audio is never committed.
- For an end-to-end meeting test, play the AMI excerpt out loud as call audio while Voice records. Check that passages and speaker labels arrive in Rukoo during the recording, not only after Stop.
- To reproduce a bug with real audio, copy the whole meeting library to a temp folder and point the dev copy at that folder.

## Pull requests and releases

- Follow the root rules for branches, commits and PR descriptions. A Voice PR says on which operating systems someone ran the change, separately from what CI ran.
- Voice has its own version. Tag its releases `voice-v<version>`, never `v<version>`. Rukoo's update check reads every release in this repository and treats a `vX.Y.Z` tag as a Rukoo version.
- Publish Voice releases without GitHub's "Latest" label. The root README's download link points to the latest release, and that has to stay Rukoo.
- Voice's opt-in update check reads only `voice-v` tags.

## Where code lives

- `voice/README.md`: the design and the decisions so far.
- `voice/AGENTS.md`: this file.
- `voice/PROTOCOL.md`: the bridge between Voice and Rukoo. `voice/fixtures/protocol-vectors.json` holds the examples both sides test against.
- `voice/RECORDING.md`: the meeting folder the recorder writes: segments, the timeline and the control port. It also describes the `screen/` folder and the screen process.
- `voice/crates/`:
  - `voice-recorder`: the recorder process, `rukoo-voice-recorder`, and its crash tests. It captures and writes to disk and does nothing else.
  - `voice-screen`: the screen process, `rukoo-voice-screen`, and its crash tests. It records one monitor into the meeting's `screen/` folder: frames with their text, and video. It runs on Windows only.
  - `voice-screen-files`: the `screen/` folder's format, shared by the screen process, the app and the tests: the journal, the meeting clock, the frame and drop rules, MP4 fragments and the clips `clip.get` cuts. It builds on every platform.
  - `voice-audio`: resampling to 16 kHz and the crash-safe WAV segments.
  - `voice-meetings`: the meeting library, transcript.db and the live transcription that follows the recorded files.
  - `voice-protocol` and `voice-bridge`: the bridge's messages and checks, the event log, the discovery file and the WebSocket server.
  - `voice-core`: Settings, the Ownkey import, text cleanup, providers, the local model client and the update check.
  - `voice-local`: the local speech worker, `rukoo-voice-local`, which runs Orukeet in its own process.
  - `voice-speakers`: the speaker worker, `rukoo-voice-speakers`, which loads NeMo-Speech.cpp and turns call audio into speaker probabilities. The labels themselves are made in `voice-meetings`.
  - `voice-input`: Windows hotkeys, text insertion and selection capture.
  - `voice-engine`: dictation, the pill's state, Settings and the meeting controller behind one API.
  - `voice-app`: the Tauri app, `rukoo-voice`: windows, tray and the native stop button.
- `voice/nemo-runtime/`: the pinned NeMo-Speech.cpp runtime: its manifest, build and pack scripts. `.github/workflows/voice-nemo-runtime.yml` builds it.
- `voice/ui/`: the pill and Settings pages in plain HTML, CSS and JavaScript. `API.md` lists every command and event between the pages and the app.
- Rukoo's side of the bridge is in `src/main/voice/`. The meeting view is `src/renderer/meeting.js`, and the agent's meeting tools are in `src/main/agents/tools.js`.

## Taste

Voice belongs to the Rukoo family. Start Settings and the pill from the tokens in [rukoo-design](../.agents/skills/rukoo-design/SKILL.md), and show the result in screenshots on the issue, as the root file asks.
