# Handoff

Where the project stands, so work can continue on any device. Updated at the end of every phase.
The product is **Rflow** (the repository and the Python package keep their names: Rach_Darling_Flow, `sst`).

_Last updated: 2026-10-01_

## Start here (a new session, or the owner's other laptop)

**Where things stand (2026-10-01):**
- **Rflow 1.6.0 is released** (2026-10-01, GitHub Release `v1.6.0`, the website's download): the owner's voice
  pipeline (phase 19: parts transcribed while speaking, dictionary, formatting, a guarded AI cleanup, an always-on
  microphone). 1.5.0 brought speech recognition as building blocks (phases 13-18) and a 90 MB installer. 1.4.0 contained accuracy phases 10-12.
- **On the owner's voice** (150 read sentences, laptop microphone):
  - word errors 9.2% → 7.1%
  - held-out sets 6.7% → **5.4%**, better than Parakeet's own benchmark average of 5.9%
  - names and terms 40% → 24.5%, when Your words holds the names
- The owner **used 1.4.0 for real dictation** on both laptops, and updates to 1.5.0 from the banner. A raw-mode set
  is still to be read.
- **The owner's plan (2026-10-01):** Rflow becomes building blocks. Speech recognition is chosen like the AI cleanup:
  - 13: the building block itself (merged)
  - 14: Whisper turbo on this computer (PR #35)
  - 15: "Scan my computer" (PR #37)
  - 16: cloud speech models (PR #39)
  - 17: your own server (PR #41)
  - 18: Parakeet downloaded on demand, and version 1.5.0 (PR #43)

  Phases 14-18 were merged and released as **v1.5.0** on 2026-10-01; the installer went from 571 MB to 90 MB. The
  correction work (sound-alike fixer, confidence-gated cleanup) comes next. See **Next steps**.

**Read in this order:**
1. This section and **Next steps** (the end of this file).
2. `CLAUDE.md`: the working rules (authorship, no AI attribution, issue → branch → PR, the owner merges).
3. `docs/accuracy.md`: the accuracy plan, the target pipeline, and all measured results.
4. Only when needed:
   - `docs/research/accuracy-report.md`: the full research, with sources
   - `docs/research/notes/`: capture, noise and VAD, ASR models and hotwords, other dictation apps, correction and
     evaluation

**How the owner likes to work** (learned while working together):
- Explain in plain words, big picture first, with a table of results. Say what the owner has to do next as numbered
  steps.
- **Measure first.** An accuracy change is kept only if `sst eval` shows it better on the held-out sets (C-E), with
  the 95% range. Tune on sets A-B only.
- Product and privacy defaults are the owner's decision (e.g. the warm microphone: 5 minutes). Ask with 2-4 clear
  options and a recommendation.
- The owner reviews and merges. When the owner explicitly says to merge or release ("you do", "yes release it"), do
  it: merge stacked PRs in order, retargeting the next one to `main` first. Close issues by hand if a retargeted PR
  didn't close them.
- Long jobs (scoring, sweeps) run in the background; tell the owner what is running and why.

**Not in git, on purpose** (it stays on the laptop that made it):
- `models/`: run `scripts/download_model.py parakeet`. It also fetches `bpe.vocab`, which hotwords need.
- **The owner's voice.** Reading tests are in `%LOCALAPPDATA%\sst\bench` (150 recordings, the baseline for every
  measurement) and dictations in `%LOCALAPPDATA%\sst\recordings`. Settings, Your words, history and stats are in
  `%APPDATA%\sst`. On 2026-10-01 they were packed into `OneDrive\Documents\Rflow-data-2026-10-01.zip` (17 MB, synced by the
  owner's OneDrive) on the first laptop, for the owner to carry over (OneDrive or USB, **never GitHub**). Unzip `bench\` into `%LOCALAPPDATA%\sst\bench\` and
  `settings\` into `%APPDATA%\sst\`. Without them, `sst eval` has nothing to score until the owner reads new sets.
  `asr_cache.json` in each test is only a cache; the key in `gateway.json` (none was set) wouldn't decrypt on another
  laptop anyway (DPAPI).
- The installed app: `Rflow-Setup.exe` from the latest release.

**Gotchas on the Windows dev laptop:**
- **Git Bash heredocs broke** on long Python snippets with quotes and backslashes: edits failed half-way, and once
  wrote backspace characters into a regex. Write the script to a file, or use the editor, instead.
- **The console is cp1252.** `sst eval` now prints `?` for characters it can't show, rather than failing.
- **The first HTTPS connection sometimes stalls** (GitHub, Hugging Face). Use retries: curl `--retry`, or the
  scripts' own retries.
- **Only one Rflow can dictate.** The developer copy (`uv run sst app`) and the installed `Rflow.exe` share the same
  mutex and data folders. Quit Wispr Flow too: it also listens to Ctrl+Win.
- **The developer copy's "Update now" only opens the release page** (by design: it's updated with `git pull`). That
  confused the owner; see Next steps.

## Status

| Phase | What | State |
|---|---|---|
| 0 | Record and transcribe locally: CLI (`sst start`, `sst file`) and web page (`sst web`) | done, on `main` |
| 1 | Dictate into any app with a global hotkey (`sst dictate`) | done, on `main` (PR #2) |
| setup | GitHub CI (lint, tests, CodeQL), Dependabot, templates, CLAUDE.md, this file | done, on `main` (PR #4) |
| 2 | Windows installer (no Python needed), CI app build, release pipeline | done, on `main` (PR #6) |
| 3 | Wispr-style hotkeys: hold Ctrl+Win, Ctrl+Win+Space hands-free, optional Menu key | done, on `main` (PR #8) |
| 4 | A real app: tray icon, recording pill, settings, history, logs (Qt) | done, on `main` (PR #10) |
| 5 | AI text cleanup (model chosen in Settings), key encrypted; one-piece transcription up to 3 min | done, on `main` (PR #12) |
| 6 | **Rflow 1.0**: product name, generic endpoint / key / model, in-app updates, download website | done, on `main` (PR #14), released **v1.0.0** |
| fix | Update checks retry when the first connection stalls | done, on `main` (PR #16), released **v1.0.1** |
| 7 | **Reading test**: accuracy on the user's own voice, per cleanup model; misheard words → Your words | done, on `main` (PR #18), released **v1.1.0** |
| 8 | **The Rflow window**: a complete app like Wispr Flow (Home, Dictionary, Reading test, AI cleanup, Settings), first-run welcome, branded installer | done, on `main` (PR #20) |
| 9 | **AI providers and profiles**: OpenAI, Anthropic, Gemini, Groq, Ollama, vLLM; one setup per person; 1.3.0 | done, on `main` (PR #22), released **v1.3.0** |
| 10 | **Accuracy lab**: five sets of sentences, session notes, audio measurements, `sst eval` with 95% ranges | done, on `main` (PR #24); the owner read all five sets |
| fix | Fairer scoring (contractions, compounds, Ctrl), only names suggested, eval report printing | done, on `main` (PR #25) |
| 11 | **Capture**: WASAPI, warm microphone with lead-in and tail, raw mode, Bluetooth warning, peak to -1 dBFS, retry of empty results | done, on `main` (PR #27) |
| 12 | **Hotwords**: Parakeet listens for Your words (bpe.vocab from NVIDIA's archive, beam search, score 1.0, guard) | done, on `main` (PR #29); phases 10-12 released as **v1.4.0** |
| 13 | **Speech recognition as a building block**: a catalog of speech models, a per-profile choice, background switching, the Speech recognition page | done, on `main` (PR #33) |
| 14 | **Whisper large-v3 turbo on this computer** (faster-whisper), downloaded when chosen, language choice | done, on `main` (PR #35), released **v1.5.0** |
| 15 | **Scan my computer**: hardware, a benchmark, the downloaded models timed, a verdict per model | done, on `main` (PR #37), released **v1.5.0** |
| 16 | **Cloud speech models**: OpenAI, Groq, Google Gemini with the user's key, a warning, a Test, Parakeet as the fallback | done, on `main` (PR #39), released **v1.5.0** |
| 17 | **Your own server for speech**: vLLM, the company gateway, any OpenAI-compatible transcription server; Load models, Test | done, on `main` (PR #41), released **v1.5.0** |
| 18 | **Parakeet downloaded on demand**: a speech step in the welcome, the installer 90 MB instead of 571 MB; version 1.5.0 | done, on `main` (PR #43), released **v1.5.0** |
| 19 | **The voice pipeline** (the owner's plan): always-on mic, chunks while speaking, parallel ASR, merge, dictionary, formatting, guarded LLM | done, on `main` (PR #46), released **v1.6.0** |

Released: v1.0.0, v1.0.1, v1.1.0, v1.3.0, v1.4.0, v1.5.0 and v1.6.0 (GitHub Releases; there is no 1.2.0). Website: https://rachdarlingflow-site.vercel.app (Vercel,
`site/`). The in-app update path is verified end to end: the owner's installed 1.0.0 showed the banner and updated
itself to 1.0.1.

## Continue on another device

```
git clone https://github.com/karthi-ai-engineer/Rach_Darling_Flow.git
cd Rach_Darling_Flow
git config user.name "Karthi27"
git config user.email "karthi.ai.engineer@gmail.com"
gh auth login                                     # as karthi-ai-engineer
uv sync
uv run python scripts/download_model.py parakeet  # ~630 MB + bpe.vocab (10 KB), not in git
uv run pytest                                      # 243 tests
uv run sst app                                     # the developer copy (quit the installed Rflow first)
uv run sst eval --no-cleanup                       # score the reading tests (needs the owner's recordings, above)
```

Then read `CLAUDE.md` (workflow and rules) and pick up at **Next steps** below. Ollama is installed on the first
laptop (useful for phase 13's local AI cleanup); check with `ollama list` on the new one.

## Decisions so far

- **Engine:** Parakeet 0.6B "unified" English, int8, on the CPU via sherpa-onnx 1.13.8. It loads in about 2 s, and a
  3 s clip takes about 0.3 s. `sherpa-onnx-core` has to be listed explicitly, or Windows loads the older
  `System32\onnxruntime.dll` and the model fails.
- **Hotkey Ctrl+Win (phase 3), as in Wispr Flow.** Phase 1 used Ctrl+Alt+D; the owner's muscle memory is Ctrl+Win, and
  Ctrl+Win+D opened new virtual desktops. Modifier-only keys need a low-level keyboard hook (`sst/hotkey.py`), not
  RegisterHotKey:
  - The hook thread only matches keys; the logic is the pure `Matcher` class, which is fully unit-tested.
  - sherpa-onnx releases the GIL while decoding (another Python thread waited at most 21 ms during a 3 s decode), so
    typing never lags during a transcription.
  - Keys sst sends itself carry `dwExtraInfo = OUR_INPUT`, and the hook ignores them. Keys injected by other tools
    (PowerToys remaps) are treated like real ones.
  - A vkE8 "mask" key is sent on press, so releasing Win doesn't open Start (the same trick AutoHotkey uses).
  - Another key during Ctrl+Win means a Windows shortcut such as Ctrl+Win+D or +←/→, so the recording is dropped
    ("interrupt"). Space means hands-free and is hidden from Windows. The key-state tracking is re-checked with
    GetAsyncKeyState, because the hook misses releases on the lock screen.
  - Only one dictation can run (mutex `SST-Dictation-dictate`), and there's a warning if Wispr Flow is running.
- **The dev laptop's PowerToys Keyboard Manager** remaps Menu (0x5D) to Ctrl+Win and the Copilot key (Win+Shift+F23)
  to Ctrl+Win+Space, set up for Wispr Flow. With the default hotkey, both keys therefore work for sst as they are.
  Don't use `--hotkey menu` there: which hook sees the key first depends on start order.
- **Tap = hands-free, hold = push-to-talk** on the same key, split at 0.4 s. Esc cancels, and Esc is only taken from
  other apps while recording.
- **Typing = clipboard + Ctrl+V.** The old clipboard is restored afterwards (every memory-block format) and dictated
  text is kept out of Win+V history. Pasting was chosen over simulated typing because it is instant and editors don't
  auto-close brackets partway through.
- **Long audio is split at pauses into pieces of up to 30 s.** Parakeet crashed in onnxruntime on a 514 s recording.
- **Recordings stop by themselves after 3 minutes** (the owner's choice). 3 minutes transcribes in about 23 s.
- **Recordings are kept** as `.wav` + `.txt` in `recordings/` (git-ignored) to compare engines later. `--no-save` turns
  this off.

## Packaging (phase 2)

- `build_installer.cmd` runs `scripts/build_installer.py` in its own environment, `build\venv`, so it works while the
  dev copy is running. The steps are PyInstaller (one folder, `packaging/sst.spec`), then the model into
  `dist/sst/models` (hard links), then a smoke test (`dist/sst/sst.exe file` must transcribe the model's test WAV),
  then Inno Setup (`packaging/installer.iss`). It takes about 95 s and produces a 500 MB `Setup.exe`
  (710 MB installed). Since phase 18 the model is taken out before Inno Setup: see **Parakeet downloaded on demand**.
- Installs per user into `%LOCALAPPDATA%\Programs\SST Dictation`, so no admin is needed. There is a Start menu
  shortcut, plus optional desktop and start-at-sign-in shortcuts. The model is inside, so it works offline.
- The installed app keeps recordings in `%LOCALAPPDATA%\sst\recordings` and its model next to `sst.exe`
  (see `sst/__init__.py`). Opening it with no arguments starts dictation (`packaging/sst_app.py`).
- sherpa-onnx's `onnxruntime.dll` must stay in `_internal/sherpa_onnx/lib/`. Verified: the installed app loads it
  from there, not the older copy in System32.
- The only DLL the bundle needs from Windows is `propsys.dll`, so no Microsoft C++ runtime install is needed.
- While running, the app holds the mutex `SST-Dictation-running`. Setup and uninstall use it to ask the user to close the app.
- Verified locally: silent install, install over an existing copy, the installed `sst.exe` transcribing, dictation
  mode, and uninstall (nothing left behind).
- The installer is not code-signed, so SmartScreen shows "Windows protected your PC" (click More info, then Run anyway).
  A certificate would fix that.
- Version: `__version__` in `sst/__init__.py` is the only place to change it. A tag `vX.Y.Z` must match it, or the
  Release workflow stops.
- CI: the `Build app (Windows)` job builds `sst.exe` on every PR and runs the smoke test (the model is cached in Actions).
  The Release workflow (tag `v*`, or started by hand) builds `Setup.exe` and publishes it as a GitHub Release (a manual
  run only uploads it as an artifact).
- Inno Setup on the dev laptop is a portable copy in `.tools/innosetup` (git-ignored).

## The tray app (phase 4)

- `sst/app.py` (Qt / PySide6-Essentials, LGPL, bundled as separate DLLs). It has a tray icon and menu (status,
  History, Settings, logs folder, Quit), and the icon turns red while recording.
- The pill is a frameless, topmost, click-through window with `WS_EX_NOACTIVATE`. Checked: a focused window stays
  focused through every pill state, so the paste still goes to the user's app.
- The model loads on a background thread, and the tray icon appears at once. The keyboard hook starts after the model
  has loaded. A 15 ms QTimer pumps the hook events into `Dictation`, and the worker thread reports back through a Qt
  signal.
- `sst/dictate.py` `Dictation` is the one dictation engine, driven by the tray app and by the console command
  `sst dictate`. Its tests feed events with explicit times, so they are exact and fast (no sleeping).
- Settings (`%APPDATA%\sst\settings.json`) are the hotkey, microphone by name, sounds and saving recordings. A damaged
  file falls back to the defaults. History is `%APPDATA%\sst\history.jsonl` (last 200). Logs are
  `%LOCALAPPDATA%\sst\logs\sst.log` (rotating).
- The microphone list is re-read before every recording (~45 ms), so a headset plugged in later, or a new Windows
  default, is picked up. The dev laptop's default mic was Bluetooth earbuds (OnePlus Nord Buds 3r). Bluetooth headset
  mics use a low-quality call mode, so pick the laptop mic in Settings for better accuracy.
- The installer has two programs: `SST Dictation.exe` (tray app, no console; the shortcuts point here) and `sst.exe`
  (CLI).
- "Start with Windows" is on by default. The installer task and the in-app setting share one HKCU Run value with
  `--startup`, which starts quietly. Uninstall removes that value even if it was switched on from the app (verified
  with a throwaway installer).
- Build checks: `SST Dictation.exe --self-test` builds every window off-screen and transcribes once, and the build
  script runs it. The dependency scan of all 92 bundled binaries finds nothing missing on a plain Windows (Qt brings
  its own C++ runtime).
- The installer is 520 MB (Qt added 20 MB), 762 MB installed.
- The owner installed phase 4 on 2026-09-30 and dictated with it (the tray app, pill and History work).

## Accuracy on the owner's voice (first check, 2026-09-30)

- The owner read the "What I need from you" list aloud: 76.5 s, one hands-free dictation in the installed app.
  Compared with that text (148 words):

  | Decoding | Word errors |
  |---|---|
  | as dictated (greedy, cut into 30 s pieces) | 28% |
  | one piece | 24% |
  | beam search | no better |

  Leaving out the owner's own reading changes (skipped or added words), about 13–17% of words are wrong. This model
  scores about 6% on standard English benchmarks.
- Typical errors are tech words and names: commit → clot, "the five PRs" → "a file PR", Claude → cloud, Tamil →
  dropped / "Tamar", polishing → publishing, "tech words" → "that was". One whole sentence was dropped when cut at
  30 s, and decoded correctly as one piece.
- **Next fix:** raise `MAX_PIECE_SECONDS` in `sst/engines/parakeet.py`. 257 s in one piece works; it crashed at 514 s.
- Microphone: none is chosen, so the Windows default is used, which is the Bluetooth earbuds when they are connected.
  2 of that day's 6 recordings were phone quality (no sound above 4 kHz). The long reading was full band, so most
  errors are the model on this voice, not the mic.
- The analysis scripts were ad hoc. Phase 7 replaced them with the reading test (see below).

## Company AI gateway (tested 2026-09-30)

- The owner's company runs an internal, OpenAI-compatible AI gateway (models, chat/completions, responses,
  completions, embeddings, images/generations, audio/transcriptions). Its address is in the owner's own settings
  (`%APPDATA%\sst\gateway.json`), deliberately not in this public repository.
- Auth is the owner's gateway API key, sent as `Authorization: Bearer <key>` or `X-API-Key: <key>`. The key lives only
  in `%APPDATA%\sst\gateway.json`, outside the repository and encrypted with DPAPI (see phase 5). **Never commit it.**
- Task:
  - list the models
  - test only the models hosted on the company's own GPU server, **one at a time** (a small server, with cold starts)
  - measure transcription accuracy and speed on the owner's recordings, and text polish quality and speed
  - pick the best and fastest, then use it in sst
- **Results (2026-09-30).** 24 models: 17 cloud (OpenAI, skipped as asked) and 7 local (`is_cloud: false`), tested one
  at a time:

  | Local model | Speed | First word | Polish (word error 23.6% before) | Transcription |
  |---|---|---|---|---|
  | Qwen/Qwen3-30B-A3B-Instruct-2507-FP8 | **43 tok/s** | 0.14–0.24 s | 22.9% (fixes "commit"; rewords a bit) | not supported |
  | unsloth/Qwen3.8-27B-NVFP4 | 28 tok/s | 0.24–0.35 s | 23.6%; short sentence 20% → **10%** (most faithful) | not listed |
  | Qwen/Qwen3.6-35B-A3B-FP8 | 20 tok/s | 1.3 s | 24.3% | HTTP 500 |
  | Qwen/Qwen-AgentWorld-35B-A3B | 26 tok/s | 0.26 s | 24.3%, identical output: same model as 3.6 | HTTP 500 |
  | Qwen2.5-VL-7B-Instruct-Q4_K_M.gguf | 17.6 tok/s | 0.29 s | 25.0% (kept "clot") | not listed |
  | qwen3, sensenova-u1.5 | – | – | "Backend unavailable" (switched off; retried after 90 s) | – |

- **No local model transcribes speech.** Only the cloud `whisper-1` does. Keep Parakeet on the laptop for
  speech-to-text. vLLM can serve Whisper, so IT could add `whisper-large-v3-turbo` locally; worth asking.
- **Polish:**
  - With the owner's word list in the prompt, the LLMs fix names that sound like a vocabulary word ("STD" → "SST",
    "hashtag 2" → "#2", "clot" → "commit").
  - They can't bring back words the recognizer dropped, and they don't fix "cloud" → "Claude" when "cloud" also
    makes sense.
  - A typical one-sentence dictation polishes in 0.5–0.7 s; the 76 s reading takes 4–5 s.
- **Connection quirk:** from Python (not curl) the first connection to the gateway sometimes stalls. Use a 4 s
  connect timeout with retries, keep the connection alive, and warm it up at start. `trust_env=False`, since it's
  internal.
- The test scripts were ad hoc (httpx, one model per run). The reading test (phase 7) now compares the cleanup models
  on the owner's own recordings, one model at a time.

## Text cleanup (phase 5)

- (Phase 6 made this generic: see below. The owner uses these two models as model and backup.)
- The owner's decision: in Settings, choose **1. `unsloth/Qwen3.8-27B-NVFP4`** (best quality) or **2.
  `Qwen/Qwen3-30B-A3B-Instruct-2507-FP8`** (fastest), or Off. Saving activates it from the next dictation. Only the
  model changes; everything else stays the same.
- `sst/gateway.py`, standard library only (http.client, no proxy):
  - `Polisher.polish(text)` never raises. Each dictation gets 2 s plus 0.04 s per word to answer.
  - The other model is tried after an HTTP error. A timeout gives the heard text; there's no second wait.
  - An unreachable gateway (e.g. at home) is skipped for 60 s.
  - An implausible answer (much shorter or longer) is not used.
  - `<think>` tags and wrapping quotes are removed.
  - Connects with a 1.5 s timeout and 3 tries (the first-connect stall), keeps the connection alive, and
    `prepare()` connects when recording starts.
- `Dictation.cleanup` is swapped by the app on Save. The state `typed_raw` shows an amber pill, "Typed as heard",
  plus at most one tray notification per 10 minutes. History stores `heard` next to `text`.
- The key lives in `%APPDATA%\sst\gateway.json` (Settings edits it; masked field; "Test" button). It is never in git
  or the logs (`GatewayConfig.__repr__` masks it).
- On disk it is `api_key_protected`, encrypted with Windows DPAPI for the signed-in user: only that user on this laptop
  can decrypt it. CodeQL flagged the first version, which stored it as plain text. A plain `"api_key"` typed into the
  file by hand is encrypted on first load. A key that can't be decrypted (copied from another laptop) is dropped,
  and the user is asked to enter it again.
- Settings has a Settings button in the History window too; a tray click opens History, and the owner looked
  for the options there. `sst.exe` without arguments starts the tray app, because an old taskbar pin to `sst.exe`
  opened a console that said "already running".
- The system prompt: fix recognition errors using the user's vocabulary, add punctuation and capitals, remove
  fillers, keep the wording, don't answer. Settings' "Your words" feed the vocabulary.
- Against the real gateway:

  | | First cleanup | Next dictation | Connect |
  |---|---|---|---|
  | Model 1 | 1.12 s | 0.64 s | 1.6 s, while speaking (the stall happened and was hidden) |
  | Model 2 | 0.67 s | 0.35 s | 0.05 s |
  | Fallback (switched-off `qwen3` chosen) | 1.17 s via model 1 | | |

  "STD dictation" → "SST Dictation", "pr's" → "PRs", and fillers were removed.
- `MAX_PIECE_SECONDS` is 180: a whole dictation (max 3 min) is transcribed in one piece.
- Tests: 94. `tests/test_gateway.py` runs a fake gateway on localhost (good, error, slow, unreachable, implausible
  answers, keep-alive, fallback).

## Rflow 1.0 (phase 6)

- **Name.** Rflow is the tray app `Rflow.exe`, and the command-line tool is `rflow-cli.exe` (Windows ignores case, so
  the two names must differ). The installer is `Rflow-Setup-<ver>.exe`. The installer keeps the same AppId, so SST
  Dictation installs upgrade in place: their folder and their Settings > Apps entry stay. `[InstallDelete]` removes the
  old `SST Dictation.exe` / `sst.exe` and the old shortcuts, and `[Registry]` deletes the old "SST Dictation" Run value.
  The mutexes keep their old names (`SST-Dictation-running`, `SST-Dictation-dictate`), so new installers still detect a
  running old version. Data folders stay `%APPDATA%\sst` and `%LOCALAPPDATA%\sst`.
- **Generic cleanup.** The code has no company defaults. Settings > "Text cleanup with an AI model" has:
  - an on/off switch
  - Endpoint and API key (optional, e.g. for Ollama; no empty Bearer header is sent)
  - "Load models" (`Polisher.models()`: GET /models; models marked `is_cloud: false` are listed first)
  - Model and Backup model (editable combos: pick one or type a name), and Test

  `Settings.cleanup` / `cleanup_model` / `cleanup_fallback`: an old settings file that has a model but no `cleanup`
  key loads with cleanup on. The owner's backup model has to be picked once in Settings, since the fixed pair of models
  is gone.
- **In-app updates** (`sst/updates.py`):
  - The installed app checks `api.github.com/.../releases/latest` 20 s after start and then every 6 h; the tray menu
    has "Check for updates". A newer tag with the assets `Rflow-Setup.exe` and `Rflow-Setup.exe.sha256` shows a blue
    banner in the window (What's new / Update now), a tray notification (clicking it opens the window), and a menu item.
  - The installer is downloaded to `%TEMP%\Rflow-update`. Only GitHub hosts are accepted after redirects, and the
    SHA-256 must match, or the file is deleted.
  - Then the app releases its `SST-Dictation-running` mutex (otherwise setup stops at AppMutex) and starts setup with
    `/SILENT /SUPPRESSMSGBOXES /NORESTART /UPDATE=1`, then quits. setup's `[Run]` entry with `Check: IsInAppUpdate`
    starts the new Rflow.
  - A source checkout doesn't check for updates; "Update now" there only opens the release page.
- **Release workflow:** it copies the build to `dist/release/Rflow-Setup.exe`, writes `Rflow-Setup.exe.sha256`
  (sha256sum), and publishes both to the GitHub Release "Rflow vX.Y.Z" (the tag must equal `sst.__version__`).
  `releases/latest/download/Rflow-Setup.exe` is the stable download link.
- **Website:** `site/index.html` is a single static page with screenshots in `site/img` (rendered from the real
  widgets, generic example settings) and `favicon.ico`. It works in dark and light mode, and at phone width (checked:
  no horizontal overflow at 390 px). The download button links to the stable link, and a script shows the latest
  version, size and date from the GitHub API. Vercel: import the repo with **Root Directory `site`**, Framework
  "Other", and no build command.
- **Public repo:** the company gateway's hostname and IP were removed from the code and the docs. Older commits in the
  git history still contain the hostname; removing it would mean rewriting published history. That is the owner's
  decision, and so is whether the repo stays public.
- The Settings screenshot exposed a layout bug: a long word-wrapped QLabel inside a QFormLayout overlapped and got
  clipped. The text is now one short line, with the details in a tooltip.

## Reading test (phase 7)

- Tray menu → "Reading test..." opens `ReadingTest` (`sst/app.py`). It shows one of the 30 sentences in `sst/bench.py`
  (everyday dictation with the owner's kind of words: GitHub, pull request, merge commit, branch, Rflow, Parakeet,
  Vercel, Tamil, Japanese, Teams, CodeQL, Karthi, numbers). It has Record / Stop (Space too), Redo, Back / Next and a
  live level. It records with the microphone chosen in Settings, and rejects recordings under 0.5 s.
- Each recording is saved as `NN.wav` + `NN.txt` (the sentence) in `%LOCALAPPDATA%\sst\bench\<date_time>`. Closing the
  window halfway loses nothing: the next "Reading test..." continues the newest folder while it has sentences left
  (`bench.unfinished()`).
- **Score** (`bench.score()`, on a thread):
  - Transcribes every recording with Parakeet first, then cleans up all the texts with the cleanup model, then with the
    backup model, one request at a time and with no fallback, so each model is measured on its own.
  - Word error rate = (substituted + missing + extra words) / words in the sentence. `bench.words()` makes the
    comparison fair: case, punctuation and hyphens don't count, "70" equals "seventy", ok = okay.
  - The alignment is Levenshtein; among equally short alignments it pairs words that look alike, so "Tamil → Tamar" is
    listed, not "Tamil → please".
  - Writes `results.json` and `report.md` next to the recordings.
- The results page shows a table per setup (errors, wrong / total, seconds per sentence; the best in bold) and the most
  misheard words. Suggested words (misheard, not common words, spelled as in the sentence) can be ticked and added to
  Your words, which activates them at once, and then **Score again** shows the difference.
- `sst bench <folder> [--model <name>]...` (`rflow-cli bench` when installed) re-scores a folder from the command line,
  by default with the models in Settings.
- `ParakeetEngine.transcribe` has a lock now: dictating while the test scores must not use one recognizer from two
  threads.
- The installed app deletes `%TEMP%\Rflow-update` (the downloaded installer, 500 MB) 60 s after it starts.
- A dry run on the model's test WAV against the gateway (both models, one at a time): 0% errors for every setup;
  Qwen3.8-27B 2.75 s (cold), Qwen3-30B 0.90 s per sentence. The owner's real run is still to come.
- Not done in this phase: trimming silence (VAD) and a Whisper comparison. The owner's reading test results should
  decide whether they're worth it.

## The Rflow window (phase 8)

- The owner's request: Rflow should open as a complete application, like Wispr Flow, so that people who download it
  from the website or a link can set it up and change everything inside the app.
- `sst/window.py`, `MainWindow`: a sidebar (Home, Dictionary, Reading test, AI cleanup, Settings; the status and the
  version at the bottom) and a page stack. It is native Qt with one stylesheet (`stylesheet(theme)`, the website's
  colours) that follows Windows' light/dark mode (`styleHints().colorSchemeChanged`). An embedded browser
  (QtWebEngine) would have added ~150 MB and a slower start for the same look. The icons come from Windows' own icon
  font (Segoe Fluent Icons, or MDL2 Assets on Windows 10). The checkbox tick and the dropdown arrows are small PNGs in
  `sst/static/ui`, drawn by `scripts/make_ui_images.py`, because a Qt stylesheet can only show images from files.
- The window keeps no state. It calls the app: `TrayApp` in `sst/app.py` (`apply_settings`, `save_cleanup`,
  `add_words`, `remove_word`, `score_reading`, `finish_welcome`, `window_closed`, updates), or `PreviewApp` in the
  self-test, the tests and `scripts/make_site_screenshots.py`. Settings apply at once; AI cleanup has a Save button,
  because a half-typed endpoint or key shouldn't be used.
- **Home:**
  - a greeting and how to dictate with the chosen key
  - the stats: words this week and in total, words per minute, day streak. `Stats` in `sst/settings.py`, file
    `%APPDATA%\sst\stats.json`, updated on every dictation; `Dictation.on_result` now also gives the recording's
    length. The first time, it starts from the history, which has no lengths, so words per minute is shown after half
    a minute of new dictation.
  - the recent dictations grouped by day, with copy buttons
- **Dictionary:** Your words, with add (comma-separated) and remove. It says so when AI cleanup is off.
- **Reading test:** the phase 7 test, now a page (`ReadingTestPage`), with a "New test" button. Leaving the page stops a
  recording. Space records only while the test has the focus (`WidgetWithChildrenShortcut`).
- **Settings:** key, microphone with a live level (`MicrophoneBox` + `audio.LevelMeter`), beeps, keep recordings, start
  with Windows, check for updates, logs, website, report a problem.
- **Welcome** (first run, `Settings.welcomed` false): step 1 the microphone with its level; step 2 try a dictation in a
  text box (the real dictation pastes into it); step 3 optional AI cleanup. Existing users see it once too, since
  their settings file has no `welcomed` yet.
- **Opening Rflow again** (Start menu, desktop) shows the running window: the running app listens on the local pipe
  `Rflow-window-<user>` (`QLocalServer`), and a second start (`show_running_window()`) asks it to open and exits.
  `--startup` (sign-in) starts with only the tray icon. Closing the window hides it; the first time, a notification
  says that Rflow keeps running (`Settings.told_about_tray`).
- **Audio fix:** `Recorder.start()` re-reads the device list by restarting PortAudio, which closes every open stream. With
  a level meter open, a dictation starting would have pulled the rug from under it (and the reading test's recorder
  had the same risk). `audio._open_streams` now counts open streams, and the list is only re-read when none is open.
- **Installer:** Rflow-branded wizard pictures in `packaging/images` (`scripts/make_installer_images.py`, BMP at
  100–200% scaling), the welcome page switched on, and texts that say what Rflow does and that it opens after Finish.
  Only options every Inno Setup 6 knows are used: the CI build machine's copy is preinstalled, and its version isn't
  pinned.
- **Website:** `site/img/app.png` (Home), `settings.png` (AI cleanup) and the new `welcome.png` are rendered from the
  real window by `scripts/make_site_screenshots.py`, with generic example data. There is a new section, "A real app,
  not just a tray icon".
- Tests: 156. `tests/test_window.py` builds every page with `PreviewApp`. `tests/test_app.py` runs the real `TrayApp`
  with the settings in memory, a fake model and a fake keyboard hook: loading, a dictation shown on Home, a key
  change applied at once, words added, close to tray, and a second start showing the window.
- Checked visually: every page rendered with Windows fonts, light and dark, at 1000×700 and at the minimum 780×540. That
  caught history cards drawn over the page (removed widgets are only deleted later, so `clear()` hides them first),
  checkboxes without a box, and native-looking dropdown arrows.

## AI providers and profiles (phase 9)

- The owner's request: people use different AI services (OpenAI, Anthropic, Gemini, Groq, Ollama, vLLM...), so the AI
  cleanup offers them by name. Also profiles (e.g. Karthi, Rahul), each person with their own setup.
- **Providers** (`sst/gateway.py`, `PROVIDERS`): OpenAI, Anthropic, Google Gemini, Groq, Ollama (on this computer), and
  vLLM or another OpenAI-compatible server. Each entry says its usual address, which API it speaks, whether it needs a
  key, whether it's the user's own server (then the address can be edited), where to get a key, and a model hint. Each
  provider gets the request it understands (`Polisher._body`):
  - **Anthropic:** `/messages` with `x-api-key` and `anthropic-version`, the system prompt as `system`, and the answer
    from the `content` blocks. Its model list is `/models?limit=1000`.
  - **OpenAI:** `max_completion_tokens`, since its newest models refuse `max_tokens`. Reasoning models (o-series,
    gpt-5) get no temperature and room to think; they are usually too slow for dictation anyway. No
    `chat_template_kwargs`: OpenAI refuses fields it doesn't know.
  - **Gemini** (its OpenAI-compatible endpoint): no token limit, because its "thinking" counts against it and would
    cut the answer short. Its model ids lose their `models/` prefix.
  - **Groq:** the plain OpenAI format.
  - **Ollama and vLLM:** also `chat_template_kwargs: {enable_thinking: false}` (Qwen3 on the company gateway).
  - Error messages are read from `error.message` for every provider.
  - "Load models" leaves out models that don't write text (whisper, tts, embeddings, images, moderation...).
- **GatewayConfig** has `provider` and `others` (the other providers' address and key, encrypted too), so switching
  back and forth loses nothing. An old file with only an address gets its provider from the address
  (`provider_for`): the owner's company gateway becomes "vLLM or another OpenAI-compatible server", with the same
  address, key and model. That was checked against the real files, and a real request through the new code worked
  (Qwen3.8-27B, 2.3 s).
- The **AI cleanup page** has a provider dropdown. The address row appears only for Ollama and vLLM, and "Get a key"
  only for the cloud providers. A new user starts with OpenAI selected.
- **Profiles** (`sst/settings.py`, `Profiles` in `%APPDATA%\sst\profiles.json`): each profile has its own
  `settings.json` (key, microphone, words, cleanup model, welcome...), `gateway.json` (provider and keys),
  `history.jsonl`, `stats.json` and reading tests. The first profile (`default`) keeps the files where they were
  before profiles: nothing moves, and an older Rflow still reads them. The others live in
  `%APPDATA%\sst\profiles\<id>` and `%LOCALAPPDATA%\sst\bench\profiles\<id>`. `bench.unfinished()` only counts
  date-named test folders, so the `profiles` folder doesn't confuse it.
- **In the window:** a profile button under the logo (a menu to switch, "New profile...", "Manage profiles") and a
  *Profiles* page (rename in place, switch, delete with a question, create). The Home greeting uses the name, and the
  welcome asks for it. Switching (`TrayApp._activate_profile`) loads the other files, applies the key, microphone
  and cleanup at once, and builds the window again, since every page shows the profile's own data. The profile in
  use and the first profile can't be deleted.
- `sst bench` uses the profile in use.
- Tests: 191. Every provider's request format against the local fake, Anthropic's errors and models, the model filter,
  `provider_for`, the encrypted `others`. Profiles: files, ids, round trip, removal, damaged files. The window: each
  provider's fields, switching providers keeping keys, the profile button, the greeting, the Profiles page, the
  welcome's name. The real TrayApp: creating Rahul (welcome, empty words, own key) and switching back to the first
  profile's words and key.
- **Not tried for real:** OpenAI, Anthropic, Gemini and Groq with real keys (only against the fakes, which check the
  request format). The owner, or anyone with a key, should press Test once for each.

## Accuracy lab (phase 10)

- The owner's decision: work on accuracy before phases 10/11 of the old roadmap, and first on everything before the
  speech recogniser, so that a better model later gains even more. The research (papers, sherpa-onnx / NeMo sources,
  Handy, OpenWhispr, VoiceInk and others, measurements on the dev laptop) is summarised in `docs/accuracy.md`, with the
  target pipeline and phases 11-13. Main findings:
  - The 24% is mostly names and terms, plus the capture path, not the model.
  - Neural denoising makes modern models worse.
  - sherpa-onnx 1.13.8 can bias Parakeet towards Your words (hotwords), but it needs a `bpe.vocab`, which the model
    download doesn't include.
- This phase is only the measuring stick; dictation is unchanged. With 30 sentences (~360 words) the noise is about
  ±2.3 points, too much to see a 2-3 point change.
- **Sets** (`sst/bench.py`): `BLOCKS` A-E, 30 sentences each. A is the old list (old tests stay comparable, and old
  folders without notes count as A). A-B are for tuning, C-E the held-out test. Some sentences use cloud, clot and
  publishing literally. `TERMS` are the names and tech terms, scored apart.
- **Sessions:** each test folder gets `session.json` (set, microphone chosen, device and host API from
  `Recorder.describe()`, rate, version) with its first recording. A new test reads the set read completely the fewest
  times (`next_block`). Fillers (um, uh) no longer count as errors.
- **Audio measurements** (`audio.measure`): the speech level (loudest 5% of 20 ms frames), noise (quietest 10%), peak,
  clipped share, and the 4-7 kHz level against 0.3-3 kHz on speech.
  - Flags: narrowband below -45 dB, quiet below -45 dBFS, noisy below 15 dB SNR, clipped over 0.1%.
  - On the model's test WAV the high band is -30 dB, and -106 dB after a 300-3400 Hz filter.
- **`sst eval`** (`sst/evaluate.py`; `sst bench` is an alias; `rflow-cli eval` when installed):
  - Replays the tests (all of the profile's by default) through `Pipeline`s: recognition alone, `--degrade narrowband`
    / `gain:<dB>`, and each cleanup model.
  - Reports: word and character errors, names-and-terms errors, other-word errors, and terms put in where something else
    was said.
  - A paired bootstrap (1000 draws within each session, fixed seed) gives each setup a 95% range and a verdict against
    the first: better or worse only when the whole range is on one side of zero.
  - The tuning and test sets and each microphone are reported apart, with time p50/p95.
  - Recognition is cached in each test's `asr_cache.json`, keyed by `engine.signature` (model and decoding), the
    degradation and the WAV's hash. Phase 12 must change the signature when the decoding changes.
  - Several tests: the report goes to `bench\summary`.
- **The page:** "Set C · sentence 3 of 30", Score (this test) and Score all tests. The results show the 95% range, the
  verdict, names and terms, and plain microphone warnings. The buttons sit in two rows so the page fits the window's
  smallest size (checked in both themes).
- Checked with the real model: `sst eval --degrade narrowband --degrade gain:-30` on the model's test WAV gave 0% for
  all three, and the second run came from the cache. That is one clean clip, so nothing about the owner's voice yet.
- Tests: 211.

## The owner's baseline (after phase 10)

- All five sets read on 2026-09-30 with the laptop microphone (Intel Smart Sound array, Windows default). Set A was read
  with the old reading test (no session.json: counted as set A, microphone "unknown"). Set B was read while Bluetooth
  headphones were connected; the laptop microphone still recorded.
- With the fairer scoring: **9.2%** word errors (7.1-11.6%); test sets C-E 6.7%; names and terms 40% (41 of 102); other
  words 7.5%. Narrowband (phone quality, simulated) costs +3.4 points (+1.4 to +5.5), and names go to 50%.
- Set B lost 5 first words and 2 sentences decoded to nothing, although the speech is in them (raised 4 times, or cut
  in halves, they decode). The other sets had neither.
- About a quarter of every recording is exact digital zeros, and a quiet room measured -91 dBFS: Windows or the Intel
  driver gates and suppresses noise on this microphone.

## Capture (phase 11)

- `Recorder` (`sst/audio.py`):
  - Records through WASAPI at the device's own rate (48 kHz on the laptop; the engine resamples), mono via
    `auto_convert`. It falls back to the old MME way if WASAPI fails. Names saved by MME (cut at 31 characters) match
    the start of the WASAPI name.
  - `warm_seconds`: stays open after a recording (the app: 300 s, the owner's choice) and keeps the last
    `PREROLL_SECONDS` (0.4) before `start()`. `tick()` closes it when idle. A call-quality microphone
    (`call_quality()`: WASAPI rate of 16 kHz or less, or "Hands-Free" in the name) is never kept open.
  - `stop_later()` returns a `Take` at once; the audio thread adds the `tail` (0.3 s) and `Take.audio()` waits for it.
    `Take.seconds` leaves out the lead-in, so a quick accidental tap is still ignored.
  - `raw=True` sets `AUDCLNT_STREAMOPTIONS_RAW` through sounddevice's private `_streaminfo`, and falls back to
    Windows mode if the driver refuses. On the laptop: cold open 287 ms; warm start instant; a quiet room -91 dBFS
    processed, -60 dBFS raw.
- `audio.condition()`: DC offset removed and the peak raised to -1 dBFS before the engine. `ParakeetEngine` also
  decodes audible audio that came back empty again in two halves. Its signature says so (`|peak-1|retry`), so the
  bench doesn't reuse older cached text.
- Dictation hands the take to the worker (the hotkey thread never waits) and ticks the recorder. The reading test
  records the same way (its Stop doesn't freeze the window), closes the microphone when the page is left, and notes
  the mode. `sst eval` reports raw recordings as "<device> (raw)".
- Settings: "Keep the microphone ready for 5 minutes after dictating" (on), "Turn off Windows' voice effects for this
  microphone" (off), and an amber warning under the microphone choice for a Bluetooth headset.
- Result: the owner's 150 sentences went from 9.2% to **8.2%**, with no empty results.
- Not measured yet: whether the warm microphone and the tail remove the lost first and last words (needs new
  recordings), and raw against Windows mode.
- Tests: 235.

## Hotwords (phase 12)

- **The vocabulary:** sherpa-onnx needs the model's word pieces with scores (`bpe.vocab`) to spell Your words in them,
  and its model download doesn't have it. NVIDIA's `parakeet-unified-en-0.6b.nemo` on Hugging Face is a 2.5 GB tar;
  `scripts/download_model.py` reads its tar headers with HTTP range requests and fetches only
  `*_tokenizer.vocab` (10 KB, sentencepiece `piece<TAB>score`). It keeps it as `bpe.vocab` only if its pieces equal
  `tokens.txt` in order (1024 pieces + `<blk>`: they do). The installer takes every file of the model folder, so
  it ships. CI's model cache key is the script's hash, so it refetches.
- **`ParakeetEngine`** (`sst/engines/parakeet.py`):
  - With a matching `bpe.vocab`: `modified_beam_search`, 4 paths, `modeling_unit="bpe"`, `hotwords_score=1.0`.
    `engine.words` (Your words, set by `TrayApp._apply_cleanup` and by `sst eval`) go to each recording as
    `create_stream(hotwords="A/B")`, so a new word works at once.
  - Without it, greedy as before, with a warning in the log.
  - `runaway()`: a boosted word twice in a row means boosting went wrong, and that recording is decoded again without
    the words.
  - `signature` is a property: model, decoding, a hash of the words, and the preparation.
- **The owner's reading test** (150 sentences), words = 31 names and terms from `bench.TERMS`:
  - errors 8.2% → **7.1%**
  - test sets 6.0% → **5.4%**
  - names 41% → **24.5%**
  - other words 6.4% → 6.1%
  - names put in wrongly: 2 (1 "Claude")

  With the owner's actual Your words (Parakeet, Vercel): 8.1%. **The gain comes from the words in Your words.**
- **Strength sweep** (tuning / test / names put in wrongly):
  - 0.5: 9.8% / 5.7% / 2
  - **1.0: 9.3% / 5.4% / 2**
  - 1.5: 10.0% / 5.2% / 13
  - 2.0: 14.0% / 6.9% / 58
  - 2.5 repeats "Claude Claude Claude" and 4.0 falls apart. The guard (then comparing with greedy) made no difference
    at 1.0.
- **Speed:** 161 s of speech in 14.8 s (greedy 13.7 s); the sample WAV in 0.46 s (0.34 s). Beam search without words:
  8.5% against greedy's 8.2% (noise).
- The Dictionary page says that speech recognition listens for Your words, and to add names and terms, not everyday
  words.
- `sst eval --words "A,B"` tries other words, and `--no-words` uses none.
- Tests: 243.

## Speech recognition as a building block (phase 13)

- **The owner's plan (2026-10-01):** Rflow should be building blocks. Parakeet is the base, but people want their own
  speech model, just as they choose their own AI cleanup model. The four steps:

  | Phase | Step | Notes |
  |---|---|---|
  | 13 | The building block itself | this phase |
  | 14 | Whisper large-v3 turbo on this computer | downloaded when chosen; Rflow picks the best way to run it (sherpa-onnx or faster-whisper: measure both) |
  | 15 | "Scan my computer" | disk, memory, processor, graphics card, and a short speed test per model; then a suggestion per model and one-click download |
  | 16 | Cloud and server speech models | OpenAI, Gemini, Groq, vLLM, the company gateway (`whisper-1` is on it) |

  The owner's decisions:
  - Local Parakeet stays the default; cloud speech is opt-in, with a warning that the voice leaves the computer. The
    company gateway counts as the owner's own AI: no warning needed there.
  - Start with only Parakeet and Whisper turbo locally.
  - Parakeet stays inside the installer for now (on demand later).
- **The catalog** (`sst/engines/__init__.py`): `SPEECH_MODELS` lists each model's where (`WHERE`: on this computer,
  cloud, own server), languages, size and what it's good at. `ready` marks what this version can load; the others
  show as "Coming soon". `usable(key)` turns a setting into a loadable model (the default for unknown or not-ready
  keys, e.g. a setting from a newer version).
- **An engine has:**
  - `name` (its catalog key) and `title` (what reports call it: "Parakeet alone")
  - `signature`
  - an optional `words` list, and `transcribe()`
- **Per profile:** `Settings.speech_model` (default `parakeet`; old files get it).
- **Switching** (`TrayApp._load_speech` / `_on_loaded` / `_on_failed`):
  - The chosen model loads on a thread, and the status says "Loading <model>...".
  - Dictation keeps the model it has until the new one is ready, then gets it with Your words.
  - A model that's no longer wanted when it finishes loading is dropped.
  - A failed load keeps the old model and says so.
  - Switching profiles loads the other profile's model.
- **The Speech recognition page** (`SpeechPage`) sits in the sidebar between Dictionary and AI cleanup. Its tabs are
  On this computer / Cloud / Your own server. Each model has a card with an "In use" or "Use this model" button. The
  "Scan my computer" card and the Cloud and server tabs said "Coming in the next update" (filled in by phases
  15-17). The tray menu has "Speech recognition" too.
- `sst eval` (and the reading test) name the model in use ("Parakeet alone"). By default, `sst eval` uses the
  profile's own speech model; `--engine` picks another.
- Tests: 254. Among them, the real TrayApp switching to a second model in the background (Your words carried over),
  a failed switch, a model this version can't load, and profiles with different models.

## Whisper on this computer (phase 14)

- **Measured first** on the owner's 60 recordings on the second laptop:
  - the laptop: i5-1334U, 32 GB, Intel Iris Xe, no NVIDIA card
  - the sets: set A from the old capture (4 narrowband recordings) and set B from 1.4.0
  - the method: `sst.evaluate`, every model bare (no Your words)

  | Speech model | All 60 | Set B | Set A | Names | Per sentence |
  |---|---|---|---|---|---|
  | Parakeet | 20.2% | 12.5% | 27.3% | 46% | 1.2 s |
  | Whisper turbo, sherpa-onnx (greedy) | 22.5% | 13.3% | 31.1% | 29% | 5.9 s (p95 18 s) |
  | Whisper turbo, faster-whisper, beam 5, 4 threads | 18.1% | 10.7% | 24.9% | 24% | 16.3 s |
  | Whisper turbo, faster-whisper, greedy, 8 threads | **17.5%** | **10.0%** | 24.5% | 29% | 10.7 s |

  The ranges overlap, with only 60 sentences. Other programs kept the processor about 50% busy, so the times vary
  (one 7 s clip later took 26 s).
- **The owner's decision:** faster-whisper. It's the most accurate, can use an NVIDIA card, and adds about 100 MB of
  program files. Parakeet stays the default for English: Whisper always processes 30 s windows, which makes short
  dictations slow on a processor.
- **`sst/engines/whisper.py`, `WhisperEngine`:**
  - CTranslate2 int8 on the processor (`cpu_threads` up to 8); float16 on an NVIDIA card when
    `ctranslate2.get_cuda_device_count()` finds one and NVIDIA's cuBLAS/cuDNN load, else the processor
  - greedy decoding, no VAD, no timestamps; Your words as `hotwords`
  - `language`: "" = detected, or a code from `LANGUAGES`, from `Settings.speech_language`, changed without reloading
  - audio goes through `audio.condition()`, then `audio.resample()` to 16 kHz (FFT method, numpy only)
  - `signature` includes the model revision, device, language and words
- **`sst/downloads.py`:**
  - pinned files (`whisper.MODEL`: `dropbox-dash/faster-whisper-large-v3-turbo` at `0a363e9`, 5 files, 1.62 GB,
    each with its SHA-256) into `%LOCALAPPDATA%\sst\models` (`DOWNLOADS_DIR`, shared by the installed app and the
    source checkout)
  - a `.part` file resumed with HTTP Range after a broken connection; 4 attempts against the first-connection stall
  - only Hugging Face hosts after redirects (`huggingface.co`, `*.hf.co`)
  - cancel keeps the part; `complete.json` is written last
  - checked for real: a download broken off at 1.4 GB was resumed from Hugging Face and verified
  - The repo was renamed from `mobiuslabsgmbh/...`; Hugging Face redirects the old name.
- **The app:** `TrayApp.download_speech_model` / `cancel_download` / `remove_speech_model` / `set_speech_language`,
  on a thread with progress signals, one download at a time.
  - When the download finishes, the model is chosen and loads in the background (phase 13's switch).
  - A model in use or chosen can't be removed.
  - `usable()` falls back to Parakeet when the chosen model isn't downloaded (removed, or another laptop).
- **The page:** each model is a `_ModelCard`:
  - Download and use (1.6 GB), then the progress (percent and GB), Cancel, Use this model, Remove download
  - the language row ("Language it listens for") once Whisper is downloaded
  - the summary says it takes several seconds per sentence without an NVIDIA card
- **Packaging:**
  - faster-whisper, CTranslate2 (its DLLs collected), tokenizers, huggingface_hub and PyAV are bundled
  - faster-whisper's `onnxruntime` dependency (only for its VAD) is excluded, so sherpa-onnx's stays the only
    `onnxruntime.dll`
  - the self-test imports `ctranslate2` and `faster_whisper`
  - NOTICES.txt lists the new licences (FFmpeg in PyAV is LGPL, as separate DLLs)
- **Notes:**
  - faster-whisper's own `decode_audio` breaks with PyAV 15+ (`metadata_errors`); Rflow doesn't use it.
  - `huggingface_hub` stalled for 23 minutes on the first-connection stall during the experiments, which is why
    Rflow downloads with its own code.
- **Tests:** 271, and `tests/conftest.py` gives every test an empty download folder (`whisper_downloaded` fakes an
  installed model). They cover:
  - the downloader against a local fake server: download and check, resume, a damaged file, cancel and resume,
    HTTP errors not retried, allowed hosts, remove
  - the engine with a fake faster-whisper: 16 kHz, language, words, no NVIDIA libraries, signature
  - the app's download flow: done and used, cancelled, failed, remove rules
  - the card's states

## Scan my computer (phase 15)

- **`sst/scan.py`** reads the computer through Windows itself (no new dependency, no PowerShell):
  - memory (`GlobalMemoryStatusEx`)
  - free disk where models are downloaded
  - the processor's name (registry) and physical cores (`GetLogicalProcessorInformationEx`)
  - the display adapters (the display class key in the registry)
  - whether Whisper can use an NVIDIA card: `ctranslate2.get_cuda_device_count()` and `cublas64_12.dll` loading
- **A one-second benchmark:** GFLOPS of a float32 768x768 matrix multiply on all cores.
- **The reference laptop** (i5-1334U, measured 2026-10-01; `REFERENCE_SCORE`, `SECONDS`, `MEMORY_GB`):

  | | Benchmark | Seconds for the 7.4 s sample sentence | Memory once loaded |
  |---|---|---|---|
  | The laptop | 197-247 GFLOPS (others were using the processor); 228 used | | |
  | Parakeet | | 0.9-1.0 s | 1.0 GB |
  | Whisper turbo (int8, processor) | | 9-20 s; 10 used | 3.3 GB |

- **`judge()`:**
  - Measured seconds win; otherwise the reference seconds are scaled by the benchmark. Whisper with usable CUDA is
    estimated at 1 s.
  - Levels:
    - "no" when memory is below the model's need plus 2.5 GB, or the disk can't take a download
    - fast: up to 2 s
    - usable: up to 5 s
    - slow: beyond that
  - The quickest fast model is "recommended", with Parakeet first among equals.
  - Too little free memory adds "close some programs first".
- **The app:** `TrayApp.scan_computer()` runs on a thread, with progress in the card. It times each downloaded model
  on Parakeet's own test recording (`test_wavs/0.wav`):
  - the model in use as it is
  - others loaded for it if free memory allows

  The result is kept in `%APPDATA%\sst\scan.json` (the computer's, not a profile's) and shown on the next start.
- **The page:** the scan card shows "Scan my computer" / "Scan again" and "Last scan: ...". Then "This computer:
  ..." and a line per model: an icon, the level's words, the speed, and the hint "Choose it for other languages, or
  on a computer with an NVIDIA card" for a slow Whisper.
- **On the second laptop:** Parakeet recommended (0.9 s, measured), Whisper slow (19.8 s, measured).
- **Tests: 283.** They cover the rules (reference laptop, faster and slower processors, an NVIDIA card, memory and
  disk, free memory), reading this computer, the benchmark, save and load, the card's states, and the real TrayApp
  scanning with the model in use timed.

## Cloud speech models (phase 16)

- **`sst/engines/cloud.py`:** `CLOUD` lists the providers and their models (the first is the default; the box takes
  any other name):

  | Provider | Request | Models |
  |---|---|---|
  | OpenAI | multipart `POST /v1/audio/transcriptions`, `Authorization: Bearer` | gpt-4o-mini-transcribe, gpt-4o-transcribe, whisper-1 |
  | Groq | the same, at `api.groq.com/openai/v1` | whisper-large-v3-turbo, whisper-large-v3 |
  | Google Gemini | `POST /v1beta/models/<model>:generateContent`, `x-goog-api-key`, the WAV inline (base64) with an instruction to write down exactly what is said | gemini-flash-lite-latest, gemini-flash-latest, gemini-3.5-flash-lite, gemini-3.6-flash |

  - The recording goes as a 16 kHz 16-bit WAV (32 KB a second; 3 minutes is 5.8 MB, under every provider's limit).
  - Hints: the chosen language (OpenAI's `language`, or named in Gemini's instruction) and Your words (OpenAI's
    `prompt`, or in Gemini's instruction). Gemini's thinking parts are left out of the text.
  - The connection opens while the user speaks (`prepare()`), with a 1.5 s connect timeout and 3 tries (the
    first-connection stall), kept alive.
- **Never losing a dictation:** when the provider fails (HTTP error, no answer in time, unreachable), Parakeet
  transcribes the same recording on this computer, and `last_error` says why. The dictation then reports
  `typed_local`: the pill says "Typed with Parakeet (cloud unavailable)", and a notification comes at most every 10
  minutes. An unreachable provider is skipped for a minute, so being offline costs one wait. Parakeet is the one
  already in memory when the user switched from it; otherwise it loads at the first failure (a cloud-only user stays
  light).
- **Keys:** one per provider, shared with AI cleanup and encrypted with DPAPI in the profile's `gateway.json`
  (`GatewayConfig.key_for`, `with_key`, `entries`). The AI cleanup page now builds its result from the saved keys, so
  saving it never drops a key saved on the speech page, and each page shows a key changed on the other (unless one is
  being typed).
- **Settings:** `speech_model` is `openai`, `groq` or `gemini`; `speech_cloud_models` keeps each provider's model.
  `usable()` falls back to Parakeet when a cloud model has no key, so a lost key never stops Rflow.
- **The page:** the Cloud tab has a card per provider:
  - what it is, "Nothing to download", and the warning "Your voice is sent to <provider> each time you dictate"
  - the API key with "Get a key", the model, the language
  - Test: Parakeet's sample sentence through the provider, with the time and the text
  - "Use this model" asks first (the voice leaves the computer); while in use, "Save" appears when the key or model
    changes, and applies without a reload

  The status line says "speech: <provider> <model>" when the model isn't Parakeet.
- **Scoring:** `sst eval --engine openai` (or groq, gemini) and the Reading test score through the provider, without
  the Parakeet fallback, so a failure shows. A rate limit (HTTP 429) is waited out (10, 20, 30, 60 s), and the cache
  is now saved even when a run stops halfway. `sst eval --engine whisper-turbo` no longer fails on `engine.biased`.
- **Not yet tried against the real providers:** only against a local fake speaking both formats. The owner presses
  Test with their own key. (Google's OpenAI-compatible address, `.../v1beta/openai`, has no `/audio/transcriptions`:
  it answers 404, which is why Gemini gets its native `generateContent` request.)
- **Tests: 309.** They cover each provider's request (fields, headers, the WAV, the hints), errors, the fallback
  (loaded once, Your words passed on), the one-minute skip, a slow answer, the rate-limit wait, the kept connection,
  Test, keys never in `repr`, the signature, the catalog, key sharing and saving, the dictation's `typed_local`, the
  cards (the question, Save, Test), and the real TrayApp switching to a cloud model and back.

## Your own server for speech (phase 17)

- **The engine** is the cloud one (`CloudEngine`) with the provider `SERVER` (`sst/engines/cloud.py`): OpenAI's
  multipart `/audio/transcriptions` at the user's address, with `Authorization: Bearer` only when a key is set (vLLM
  often needs none). `REMOTE` = the cloud providers plus the server: everything that falls back on Parakeet.
  - `models()` (GET `/models`) lists the speech models first (`SPEECH`: whisper, transcribe, asr, parakeet, canary,
    voxtral...), then the rest, since a gateway lists its chat models too.
  - `set_url()` takes a new address from the next request on, so the window never waits for a dictation.
  - The signature includes a hash of the address: another server may give other text for the same model name.
- **Storage:** the address and key are kept under `SPEECH_SERVER` (`"speech-server"`) in the profile's
  `gateway.json`, encrypted like the others, **apart from AI cleanup's own server**. The two may differ (e.g. a
  company gateway for cleanup and Speaches on this computer for speech), and changing one never breaks the other.
  The model is `Settings.speech_server_model`. `usable()` needs an address.
- **The page:** the "Your own server" tab has one card:
  - Address, API key (optional), Load models, Model, Test, Language
  - a new card starts from AI cleanup's own server ("vLLM or another OpenAI-compatible server", e.g. the company
    gateway) and says so
  - "Use this model" asks nothing (the owner counts their own and their company's server as their own); the card
    says that the voice goes to the server, and Parakeet takes over when it can't be reached
  - while in use, "Save" applies a changed address, key or model without a reload
- **The company gateway:** its `whisper-1` transcribed on 2026-09-30 (see **Company AI gateway**). The owner tries it
  from the card: Load models → whisper-1 → Test.
- **Also:** the chosen segment tab (On this computer / Cloud / Your own server) is no longer bold, which clipped
  "Your own server".
- `sst eval --engine server` scores through the server, without the fallback.
- **Tests: 317.** They cover the request without and with a key, the address required, Load models' order, a new
  address used from the next request, the catalog, the separate storage, the TrayApp switching address without a
  reload and back to Parakeet when the server is removed, and the card (prefilled from AI cleanup's server, Load
  models, Test, Use, Save).

## Parakeet downloaded on demand (phase 18)

- **Where Parakeet comes from:** `csukuangfj2/sherpa-onnx-nemo-parakeet-unified-en-0.6b-int8-non-streaming` on Hugging
  Face (the sherpa-onnx author's copy), revision `8c3a10fb`, pinned in `sst/engines/parakeet.py` (`MODEL`):
  - the encoder, decoder, joiner and tokens.txt, plus NVIDIA's model card (bias, explainability, privacy, safety)
  - 663 MB, every file's SHA-256 checked
  - byte for byte the files Rflow 1.4 installed: the same hashes, and the same folder name, so the eval cache still
    applies
  - Downloaded through `sst.downloads` like Whisper (resume, cancel, retries), into
    `%LOCALAPPDATA%\sst\models`. Tried for real on 2026-10-01: 663 MB in 370 s, then the sample transcribed with
    hotwords on.
- **Comes with Rflow:**
  - `sst/static/parakeet/bpe.vocab`: 10 KB, cut from NVIDIA's 2.5 GB `.nemo`; the hotwords need it, and the
    Hugging Face copy lacks it. `.gitattributes` keeps it byte-exact (`*.vocab -text`), because sherpa-onnx parses it.
  - `sst/static/sample.wav`: the sample sentence for the scan and the cloud and server Tests; a LibriVox reading, see
    NOTICES.
- **Found first next to the program** (`parakeet.find_model()`): `MODEL_DIR` is where Rflow 1.4 and older installed
  it, or the source checkout's `models/`.
  - An update keeps it: the installer's `[InstallDelete]` only removes `_internal`, so `{app}\models` stays.
  - `SpeechModel.found` counts it as installed, and "Remove download" only shows for a real download.
- **No speech model yet** (a new install that hasn't chosen one): `usable()` returns `""`.
  - The app starts without dictation, and the status says "Choose a speech model to start dictating".
  - A welcomed user is told once.
  - Dictation starts as soon as Parakeet is downloaded (`_on_download_done` also calls `_load_speech`, since
    `parakeet` is the default setting) or a cloud or server model is chosen.
- **The welcome** has a new step 2, "How Rflow recognises your speech":
  - "Download Parakeet (663 MB)", with progress and Cancel ("Meanwhile, choose your microphone")
  - or "Use a cloud model or your own server instead", which finishes the welcome on the Speech recognition page

  Step 4 ("Try it") waits for it.
- **Without Parakeet:**
  - The cloud and server cards say "Download Parakeet too ... to have it type when ... can't be reached", instead
    of promising it.
  - A failed transcription keeps the recording (`recordings`), and the error says so.
- **The installer:** `build_installer.py` links the model in for the smoke test (rflow-cli transcribes the sample;
  `Rflow.exe --self-test` transcribes it when it finds the model), then takes it out before Inno Setup. Solid LZMA2
  now (many small files).

  | | Installer | Installed |
  |---|---|---|
  | 1.4.0 | 571 MB | ~900 MB |
  | 1.5.0 | 90 MB | 288 MB, plus 663 MB once Parakeet is downloaded |

  CI still downloads the model with `scripts/download_model.py` for the smoke test.
- **The website and the installer's text** no longer say the model is included or that no internet is needed. They
  describe the choice, Whisper's languages, and what goes where (FAQ "Is my voice sent anywhere?").
- **Version 1.5.0** (`sst/__init__.py`): phases 14-18.
- **Not removed on uninstall:** downloaded models stay in `%LOCALAPPDATA%\sst\models` (shared with the source
  checkout), like the settings.
- **Tests: 330.** They cover the pinned download, Parakeet found next to the program or downloaded, no model at all,
  the bundled vocabulary (no CR) and sample, a new install starting without a model then downloading Parakeet, a
  cloud-only start, the welcome's step, the pages without Parakeet, the kept recording, and the fallback's message.

## The voice pipeline (phase 19, the owner's plan of 2026-10-01)

The owner wrote the plan in `appropriate_plan.txt` (repository root, not in git): dictation as separate stages with
contracts. It is built as written, with the deviations below, each backed by a measurement or a reason.

```
mic (always on, 2 s pre-roll in RAM) -> session -> VAD -> chunker (1.2 s pause / 20 s max, 1 s overlap at the max)
-> bounded parallel ASR (retry, sanity check, Parakeet fallback) -> ordered results -> overlap merge
-> dictionary -> formatting -> LLM polish -> guard -> FinalText -> the existing paste
```

| Stage | Where | What it does |
|---|---|---|
| Contracts, config | `sst/pipeline/contracts.py` | the objects passed between stages; every tunable value (`VoiceConfig`) |
| Capture | `sst/audio.py` `Recorder` | always-on (`keep_open`, `warm_seconds = inf`), `preroll_seconds` 2 s for dictation, `current_take` for live feeding |
| Ring, VAD, chunker | `sst/pipeline/audio_stream.py` | `RingBuffer` (monotonic index), energy VAD with adaptive floor and hysteresis, `Chunker`, `trim_preroll` |
| ASR | `sst/pipeline/asr.py` | `EngineBackend` (any engine), `ASRScheduler` (bounded pool, per-session ordering, retry by error class with backoff and jitter, `ASRValidator` suspicion score, fallback), fail closed (`SessionFailed`) |
| Word times | `sst/engines/cloud.py`, `parakeet.py`, `whisper.py` | `transcribe_chunk()` -> `RawTranscript` with words: Gemini 3.5 Transcribe (`audioTranscriptionConfig`, verbatim, `wordTimestamp`), whisper-1 / Groq `verbose_json`, Parakeet token times, faster-whisper words; a connection pool for parallel requests; the Files API for audio over 14 MB |
| Merge | `sst/pipeline/merge.py` | boundary-only: timestamps, exact, normalized, fuzzy; keeps both when unsure; partial words at a forced cut |
| Dictionary | `sst/pipeline/dictionary.py` | SQLite per profile (`dictionary.db`): terms, sound-alikes, AUTOMATIC / CAREFUL / HINT_ONLY, phrase and fuzzy matching with an ordinary-word guard (`sst/static/common_words.txt`); Your words mirrored in |
| Learning | `sst/pipeline/learning.py` | correction events from Home's ✎; a suggestion after the same correction twice; Add / Dismiss on the Dictionary page |
| Formatting | `sst/pipeline/formatting.py` | numbers, ordinals, dates, times, money, percentages, units, versions, emails, URLs; prose stays ("two options") |
| LLM | `sst/pipeline/polish.py` | `POLISH_PROMPT` (strict); `GatewayLLM` wraps the AI cleanup provider; only the terms present are listed |
| Guard | `sst/pipeline/guard.py` | protected entities, negation, speech act, substitutions, added/removed words; the formatted text is typed when it rejects |
| Orchestrator | `sst/pipeline/session.py` | `Session` (feed / finish / result, state machine, metrics), `VoicePipeline`, `LazyBackend`, the debug folder |
| Dictation, app | `sst/dictate.py`, `sst/app.py` | a session per key press fed by `_Feeder`; `retry_last()`; the pipeline rebuilt when the model or cleanup changes |

- **Deviations from the plan:**
  - Audio stays at the microphone's rate inside a session and is resampled to 16 kHz per chunk. A streaming
    resampler would smear chunk boundaries; the result is the same.
  - **No overlap after a pause cut.** The cut sits 0.3 s after the last word, so a 1 s overlap reached back into it.
    On the owner's recordings Parakeet then decoded the next part to nothing. The overlap stays at the 20 s maximum,
    where words can be cut.
  - **A pause ends a part only after 0.4 s of its own speech** (`min_cut_speech_ms`). A breath or a word's tail alone
    made Parakeet hear "Yeah."; it now stays with its neighbour.
  - **Before failing closed, Dictation transcribes the whole recording in one piece** (as before the pipeline) and
    runs the text stages on it. That text is complete, so it isn't a text with a hole in it. Only if that fails too
    is nothing typed; the recording is kept, and the tray's "Retry the last dictation" tries again.
  - After a pause cut the session merges without an overlap, even when an engine gives no word times.
- **Gemini:** `gemini-3.5-transcribe` is the default Gemini speech model. It runs VERBATIM, and `timestamp_mode`
  "timestamps" asks for word times; "vocabulary" sends Your words instead, since Google says the two can't be
  combined. Google doesn't fully document the REST response, so the parser accepts several shapes; it is tested
  only against fakes so far.
- **The microphone is on while Rflow runs (default, the plan's locked spec).** Only the last 2 s are kept, in RAM.
  Windows shows the microphone icon. It is never kept open for Bluetooth headsets. Settings can turn it off.
- **Settings:**
  - "Keep the microphone on while Rflow runs"
  - "Write numbers, dates, times and money as such"
  - "Voice pipeline" (off: the classic whole-recording path)
  - "Keep each dictation's steps for troubleshooting" (`%LOCALAPPDATA%\sst\debug\<session>`)
- **The Dictionary page:** "When Rflow writes ... write instead ..." adds a sound-alike, which always applies. Each
  word shows what it is also heard as, and suggestions from corrections appear at the top.
- **Measured on the owner's voice** (12 reading-test sentences from this laptop joined into one 100 s dictation:
  every third with a real pause, the others run together; local Parakeet, one part at a time):

  | | Words wrong | Parts |
  |---|---|---|
  | The whole recording at once (before) | 23 of 166 (13.9%) | 1 |
  | The pipeline | **20 of 166 (12.0%)** | 9 (2 cut at the maximum, 6 at pauses, the end) |

  The overlap of the two forced cuts was merged without duplicates. Script: `real_pipeline.py` in the session's
  scratchpad (not in git); it reads the reading tests in `%LOCALAPPDATA%\sst\bench`.
- **Known limitations:**
  - A quiet phrase after a mid-sentence pause ("...credit card | tomorrow morning") was still dropped. The energy
    VAD heard too little of it to cut there, and Parakeet drops a quiet phrase before louder speech. A model VAD
    (Silero via sherpa-onnx) is the likely fix.
  - At a forced cut the merge keeps the earlier part's version of the overlap words, which had less context
    ("went up against" where the next part heard "went up again"). Preferring the next part's words in the second
    half of the overlap is worth trying.
  - The fuzzy dictionary is English (ASCII), and so are the guard's question and correction rules. Rejections only
    mean the formatted text is typed.
  - Learning only sees corrections made with Home's ✎, not edits in the target app.
- **Tests: 1525.** Every stage has its own file (`tests/test_pipeline_*.py`, `tests/test_engine_words.py`), plus
  end-to-end sessions with synthetic speech and fake engines (`tests/test_pipeline_session.py`).

## Text never said (fixed 2026-10-02)

The owner saw words they hadn't said, at the end of dictations ("…version installer. Commit tray app pill. Let's move
stand meeting Thursday morning.") and once a rewritten opening ("Under some protocol, that's not a big deal."). Speech
model: Gemini `gemini-flash-lite-latest`, with the 20 Your words in its instruction.

- **Evidence** (40 pipeline dictations, each replayed locally through Parakeet; nothing sent anywhere):
  - Gemini invented the words; they weren't in the audio. In 7 of 40 dictations its text had list words that Parakeet
    didn't hear; the AI cleanup only passed them on.
  - The leaked text is the Your-words list itself, in its saved order.
  - The trigger is a last part with little speech: 5 of 5 with 1.4 s or less of their own speech got the list, 0 of 5
    with 2.1 s or more. Those parts held mostly the repeated overlap, the release click and Rflow's own stop beep.
  - "Under some protocol…" was the owner's own speech ("And some of the words are not being…"): a 1.8 s mid-sentence
    pause cut a 2.5 s fragment, which Gemini rewrote without its context.
  - The 2 s pre-roll did not leak. Rflow's 880 Hz start beep was in 39 of 40 recordings, louder than the voice.
- **Fixes:**
  - Only names and terms go to speech models as hints, and to the guard as protected terms (`speech_hints`): 16 of
    the 20 words were everyday words. The Dictionary page marks everyday words.
  - The Gemini instruction calls the hints a spelling reference, never to be written unless spoken.
  - A transcript with three or more hint words in a row, in the list's order (`hint_echo`), is transcribed again
    without hints; that transcript is used when the words disappear.
  - A last part with under 2 s of its own speech goes again with the part before it, as one chunk that replaces it
    (`min_alone_speech_ms`, `AudioChunk.replaces`).
  - A pause cuts only after 4 s of a part's own speech (`min_cut_speech_ms`, was 0.4 s).
  - The stop beep plays after the tail is recorded; the start beep is filtered out (`_ToneNotch`, 880 Hz, 0.6 s).
  - The fallback, Retry and saved recording leave out the pre-roll the session trimmed. The tail is no longer copied
    into the next pre-roll. The classic path keeps its 0.4 s pre-roll. The guard accepts either apostrophe and a
    capital at a sentence start.
- **Measured:**
  - On the 45 recordings, short parts (< 4 s) sent alone in multi-part dictations went from 9 to 1, and that one has
    2.1 s of speech. The owner's example now has 2 parts (0-18.3 s, 17.3-27.2 s) instead of 3.
  - The 12-sentence real-voice check (local Parakeet): 22 of 166 words wrong (13.3%), against 20 before and 23 for
    the whole recording at once. A 3 s pause threshold gave the same.
- **Owner's choice, recommended:** Speech recognition → Google Gemini → model `gemini-3.5-transcribe`. It is Google's
  dedicated speech model, takes no free-text prompt, and is the more accurate one. The `-latest` alias may now point
  to a Flash-Lite reported to transcribe dictation worse. Also remove the everyday words from the Dictionary.

## This laptop's first reading test (2026-10-01, Rflow 1.4.0)

- **The setup:** set B, the laptop microphone (Realtek, WASAPI, 48 kHz), Windows mode, warm microphone.
  - Speech level -37 dBFS, signal to noise 23 dB, full band.
  - **No first words lost (0 of 30):** the warm microphone works. On the other laptop set B lost 5.
  - No last word was cut off.
- **Results** (30 sentences, so about ±4 points):

  | Setup | Word errors | Names and terms |
  |---|---|---|
  | Parakeet, no words | 12.5% | 44% |
  | Parakeet, this laptop's Your words | 12.0% | 44% |
  | Parakeet, the 37 names and terms (`bench.TERMS`) | 11.8% | 36% |
  | **Parakeet + the company's Qwen3.8-27B cleanup** | **8.7%** | 24% |

  The cleanup is clearly better: -3.3 points, range -5.7 to -1.3.
- **This laptop's Your words** held mostly everyday words, from the old reading test's suggestions (version,
  installer, tray, app, move, stand, meeting, morning, after...). The owner was told to keep only names and terms.
- **Names still wrong with the names list:** Parakeet → parquit, Ollama → olama, Qwen → current, Groq → grok,
  PowerToys → power toys, Vercel → vessel, commit → comet, PyInstaller → py install. That is the correction fixer's
  ground.

## Correction groundwork, for after the building blocks (experiments on 2026-10-01, nothing merged)

These were scratch scripts, not in git. The findings:

- **Word confidence exists.** With beam search, `stream.result` has `tokens`, `timestamps` and `ys_log_probs` (one per
  word piece; a piece starting with a space starts a word). A word's confidence = the lowest probability of its
  pieces. On the owner's 150 sentences (with 31 names as hotwords, 1912 words heard, 6.1% wrong):

  | Confidence | Words | Wrong |
  |---|---|---|
  | 0.97 or more | 1113 (58%) | 1.8% |
  | 0.90-0.97 | 210 | 9.5% |
  | 0.70-0.90 | 259 | 10.0% |
  | 0.50-0.70 | 202 | 12.9% |
  | 0.30-0.50 | 105 | 21.0% |
  | below 0.30 | 23 | 8.7% (hotword-boosted pieces can have a low model probability and still be right) |

  - Good for skipping correction when every word is at least 0.97.
  - Weak as a detector of wrong words: flagging below 0.7 catches 43% of the errors, and 85% of the flagged words are
    right.
- **Errors left after hotwords** (135):
  - 70 ordinary substitutions: the/a, test/tests, note/notes, and some reading variations
  - 27 names: Ollama → olama ×2, onnx → onix ×2, Parakeet → parkit / parkeet / parketh / rakit, Qwen → quinn /
    quin / coin, Groq → grog / grok / how, Vercel → versal, PowerToys → powertise, Haiku → high
  - 19 dropped words and 19 extra words
- **Sound-alike fixer prototype:**
  - Spans of 1-3 low-confidence words, compared with Your words by letter edit distance, halved when a rough sound
    key matches.
  - Results:
    - similarity 0.8, confidence below 0.9: 7.1% → 7.0%, names 24.5% → **14.7%**, names put in wrongly 2 → 7
    - similarity 0.9: 6.9%, names 19.6%, 3 put in wrongly
    - 0.7 or looser: much worse ("in the" → "Inno", "a real" → "Rahul")
  - Its fixes: Olama → Ollama, Parkit / Parkeet / Parketh → Parakeet, PowerTise → PowerToys, Sherpa Onix →
    sherpa-onnx, Grok → Groq, "i installer" → PyInstaller.
  - Its harm: "installer" → "PyInstaller" (×3), "open a" → "OpenAI", "the cloud version" → "Claude", "Anthropic key"
    → "Anthropic".
  - **To build it properly:**
    - never change an ordinary English word; this needs a word list, e.g. SCOWL (permissive licence), or Windows'
      spell-checker API
    - never join a span that holds a word already in Your words
    - never join function words (a, the, in, on...)
    - tune on sets A-B, judge on C-E
- **AI cleanup only when unsure** (not started): send a sentence to the LLM only when a word is below about 0.9. Mark
  the uncertain words, and give only the words from Your words that sound like them. Reject answers that change too
  much. Research: `docs/research/notes/post_asr_and_evaluation.md` (whole-transcript LLM correction doubled word
  errors on Parakeet output in one study).

## Known limitations

- Apps running as administrator don't receive the text, because Windows blocks input from normal programs into them.
- Ctrl+Win isn't sent through the real hook in automated tests (Wispr Flow on the dev laptop would react). The hook
  plumbing is tested with the Menu key, Esc and Ctrl+Alt+X, and Ctrl+Win by the Matcher unit tests. The owner
  confirmed that Ctrl+Win dictation works in the installed app.
- English only. The cleanup can't bring back words the recognizer dropped, and it leaves real words that are wrong
  in context ("charted" for "chatting", "cloud" for "Claude").
- The console command (`sst dictate`) has no cleanup; the tray app does.
- The installer isn't code-signed, so SmartScreen warns on the first install. In-app updates don't trigger it, because
  a file downloaded by the app isn't marked as coming from the internet.
- The Python client's first connection to the company gateway, and sometimes to GitHub, stalls on the dev laptop. The
  clients use short connect timeouts with retries (`sst/gateway.py`, `sst/updates.py`, `sst/engines/cloud.py`).
- A cloud speech model sends the voice to the provider; the window says so and asks before one is used.

## Next steps

1. **Owner: update to 1.5.0 and try it** (released 2026-10-01; 91 MB, SHA-256 `c05c7c81...` checked by the updater):
   - Open the installed 1.4.0: the banner offers 1.5.0 (or Settings → Check for updates) → Update now. Expected: no
     Parakeet download (it stays next to the program), the same settings, words and history.
   - Speech recognition → Whisper turbo → "Download and use (1.6 GB)"; dictate in English, and in Tamil with the
     language set; switch back to Parakeet; press "Scan my computer".
   - Cloud → a provider you have a key for (Groq has a free tier) → paste the key → Test → Use this model → dictate;
     then turn Wi-Fi off and dictate: Parakeet should type it, and say so.
   - Your own server → it is filled in from AI cleanup's server, or enter the company gateway → Load models →
     whisper-1 → Test → Use this model → dictate.
   - Later, the new-install path: on another Windows account, install from the website; the welcome asks how to
     recognise speech → Download Parakeet → dictate when it's done.

   The release was made with the stacked-merge recipe: #35 into `main`, then #37, #39, #41 and #43, each retargeted
   to `main` first; CI green on `main`; then the tag. This laptop's global git config signs tags
   (`tag.gpgsign`), so a tag needs `-m`.
2. **Owner: try the voice pipeline** (phase 19, released as 1.6.0: update from the banner; the download is the
   ~90 MB installer, nothing else):
   - dictate a long paragraph with pauses: the text should arrive soon after you let go
   - say "twenty five percent" and "October first at three thirty pm"
   - add a sound-alike on the Dictionary page
   - correct a dictation twice with ✎ on Home and accept the suggestion
   - with AI cleanup on, try a sentence with a number; turn "Keep each dictation's steps" on for a while and look at
     `%LOCALAPPDATA%\sst\debug`

   Then tune with the debug folder (plan §108: audio, VAD, chunk boundaries, ASR, merge, dictionary, formatting, LLM,
   guard, in that order).
3. **The building-block plan is built** (phases 13-18; see **Speech recognition as a building block**). Possible
   later: Whisper's runtime on demand too (installer ~50 MB), and the website's screenshots of the new pages.
3. **The owner, meanwhile:**
   - Keep only names and terms in Your words.
   - Read a set with Settings → "Turn off Windows' voice effects" on (raw mode). Set B in Windows mode was read on the
     second laptop on 2026-10-01.
   - On the second laptop, the other laptop's 150 recordings are missing: copy the data zip (see **Start here**).
4. **Correction, after the building blocks, chosen by what goes wrong in real dictation** (see **Correction
   groundwork**):
   - names still wrong → the sound-alike fixer with an ordinary-word guard
   - small words wrong → AI cleanup only when unsure (Ollama locally, or the owner's provider)
   - both mediocre → compare a stronger model (Qwen3-ASR or Canary via sherpa-onnx) on the same recordings
   - later: learn from the owner's edits after pasting
5. **A small fix:** in the developer copy, the update banner should say "you run Rflow from its source: update with
   git pull; download the installer for the app", not offer "Update now" (`TrayApp.start_update`, `sst/app.py`).
6. **Then the features paused for accuracy:**
   - text without the AI endpoint: fillers, "new line", spacing and capitals from the text before the cursor,
     snippets
   - command mode ("make this formal" on selected text) and a style per app
7. **Later:**
   - code signing (removes the SmartScreen warning)
   - a "paste last transcript" hotkey
   - the bench: resampling whole sessions, and substitutions / deletions / insertions counted apart
8. With a key for OpenAI, Anthropic, Gemini or Groq: press Test once on the AI cleanup page, and for OpenAI, Gemini
   or Groq on the Speech recognition page's Cloud tab (they were only tested against the local fakes).
9. Waiting on the owner:
   - the apps used most
   - code-signing budget
   - the git history question above
