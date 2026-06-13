# Build status

## v0.2 — device fabric + lab assistant (branch `feat/distributed-fabric`)

The distributed expansion is in and **verified on the CPU build**:

- **Schema v2** (`edge_devices`, `instruments`, `measurements`, `lab_sessions`, `lab_session_steps` +
  edge-clip columns on `events`), migrated idempotently via guarded `ALTER`s.
- **Device fabric** (`src/fabric`, `pm_fabric`) bridges edge devices onto the EventBus + schema; MQTT is
  optional (`POLYMATH_USE_MQTT`, off by default) and the HTTP ingest plane works with no broker.
- **Hub modules**: network (satellite) audio source, the `read_instrument`/`record_measurement` +
  4 lab-session tools, an interactive **Lab Guide** persona, event/clip retention sweep, and a touch
  **panel mode** (`Hearth.exe --panel`).
- **Mobile app** (`app/`) builds clean (`npm run build`): chat-first home, direct-to-camera path, and new
  Devices / Instruments / Lab-Session / clip-browser screens.
- **Edge firmware** (`firmware/`): shared `common` lib + 5 camera tiers, voice satellite, and the HMM lab
  module, all to the [`FABRIC.md`](FABRIC.md) contract (compiled per-board with PlatformIO/ESP-IDF/CanMV —
  not built in CI here).
- **`ctest`: 14/14 green** on the CPU build — the original 11 plus **fabric, instruments, lab_session**.
  All 14 desktop QML views (incl. PanelMode and the new Lab cockpit) render in the offscreen
  `capture_views` harness, in both populated and `--empty` first-run states.
- **Both builds link the new code:** the CPU build (VS generator) and the **CUDA build** (Ninja +
  portable CUDA, through the `C:\pm` no-space junction) both compile `pm_fabric` + the gateway/lab/
  instrument additions and link `Hearth.exe` (157/157, exit 0).
- **Mobile app** verified in a browser preview: chat-first home, the new Edge Devices / Instruments /
  Lab Session screens render coherent empty + graceful error states, and a React error boundary keeps a
  screen crash from blanking the app.

---

## v0.1 baseline

Both builds are verified: **they compile, link, run the tests, and launch.**

- **CPU build** — `build/cpu` (Visual Studio 2022 generator). Reproduced by
  [`scripts/build-cpu.ps1`](../scripts/build-cpu.ps1).
- **GPU / CUDA build** — `build/cuda` (Ninja generator + portable CUDA 13.2 toolkit,
  `sm_86`). Reproduced by [`scripts/build-gpu.ps1`](../scripts/build-gpu.ps1).
  **GPU inference is verified end-to-end (token generation on the RTX 3080 Ti).**

`Hearth.exe` is built with MSVC 2022 + Qt 6.6.3 + OpenCV 4.9 + ONNX Runtime 1.17
(CPU) + llama.cpp/whisper.cpp built from source, and confirmed at runtime to:

- open the database (static sqlite3), start all **8 service threads**
  (Inference, Scheduler, Memory, Proactive, Agent, Idle, Vision, Audio),
- auto-register + load the **Gemma 3n E4B** Fast model, seed + load the modular
  personalities (Marcus Aurelius, Ada Lovelace),
- open the microphone (16 kHz mono capture, whisper ASR transcribing), detect Piper TTS,
- register all **16 agent tools**, load the YOLOv8n / SCRFD / ArcFace ONNX models,
- load the Qt Quick GUI scene and run the event loop,
- degrade gracefully when models/CUDA are absent — **no crashes**.

`ctest` green: **11/11 suites** on both the CPU and CUDA builds — core, tools, audio, agent, vision,
inference, memory, privacy, integration, ui, phase2. The DB is **encrypted at rest** (SQLCipher/AES,
per-install OS-protected key) — confirmed active at runtime. See [`SHIP.md`](SHIP.md).

## GPU build — what was verified (headless, `QT_QPA_PLATFORM=offscreen`)

Observed in `data/logs/polymath.log` and the engine's stderr on an RTX 3080 Ti 12 GB
(driver 596.36):

```
VramBudget: CUDA device 12287 MiB total, 11100 MiB free, budget 8192 MiB
InferenceManager starting (CUDA=true)
LlamaBackend loaded 'gemma-3n-E4B-it-Q4_K_M' role=0 n_ctx=8192 ngl=999 (~5352 MiB)
llama_kv_cache:  CUDA0 KV buffer size = 256.00 MiB
sched_reserve:   CUDA0 compute buffer size = 516.00 MiB   (Flash Attention enabled)
InferenceManager: Fast model resident
```

- **GPU detected**, the Fast model offloads **all** layers (`ngl=999`, ~5.3 GB resident),
  KV-cache + compute graph live in `CUDA0` VRAM. All 8 services start; whisper ASR runs;
  the process is stable (ran headless, killed after ~50 s, no crash).
- **Generation smoke test** (`llama-bench -m gemma-3n-E4B -ngl 999 -p 16 -n 16`):

  | model | backend | ngl | test | t/s |
  |-------|---------|-----|------|-----|
  | gemma3n E4B Q4_K_M | **CUDA** | 999 | pp16 | 446 |
  | gemma3n E4B Q4_K_M | **CUDA** | 999 | tg16 | **108** |

  108 tok/s generation on GPU (vs. ~10–20 on CPU) confirms the ggml-cuda path produces
  tokens. **This is the end-to-end GPU verification.**
- **ONNX Runtime stays on CPU** by design: we ship the CPU ORT package, so the YOLO/face
  detectors log a harmless `onnxruntime_providers_shared.dll … error 126` and fall back to
  CPU. The CUDA build accelerates **llama/whisper (ggml-cuda)**; perception ONNX is CPU.

## How it was built (reproducible)

```powershell
git submodule update --init --recursive   # or scripts/setup-dev.ps1
pwsh scripts/build-cpu.ps1                 # configures + builds build/cpu
pwsh scripts/fetch-models.ps1              # download the default local models
pwsh scripts/build-gpu.ps1                 # configures + builds + deploys build/cuda (CUDA)
```

`build-gpu.ps1` assumes the CPU prereqs exist (Qt/OpenCV/ONNX + the small vcpkg libs +
the portable CUDA toolkit under `build/deps/cuda/toolkit`). It builds through a no-space
NTFS junction (`C:\pm` → repo) because **nvcc cannot tolerate a space anywhere in its
paths** and the repo lives in `…\Home Assistant`. See `BUILD.md`.

## Module status

| Module | Status |
|--------|--------|
| core, inference, audio, vision, scheduler, memory, agent, personality, ui/app | ✅ compile + link; verified at runtime (CPU **and** CUDA) |
| inference (llama.cpp ggml-CUDA) | ✅ GPU offload verified — Gemma 3n E4B at 108 tok/s on `sm_86` |
| VLM (mtmd / `describeImage`) | ✅ built (`LLAMA_BUILD_TOOLS/COMMON=ON`); `mtmd.dll` linked + deployed |
| Piper TTS | ✅ drives the prebuilt `piper.exe` via QProcess (detected at runtime) |
| ESP32-CAM firmware | ✅ complete (compile in Arduino IDE) |
| Mobile companion | ✅ wired in — `pm_gateway` (QHttpServer+QWebSocket on `0.0.0.0:8765`, device-token auth) inside `Hearth.exe`; `app/` PWA (Capacitor/React) + `cloud/relay/` (opt-in). Desktop **Settings ▸ Mobile Access** pairing QR. Verified: `/api/v1/status`→200, protected routes→401. |
| tests | ✅ 11/11 ctest suites green (CPU + CUDA): core, tools, audio, agent, vision, inference, memory, privacy, integration, ui, phase2 |
| at-rest encryption | ✅ ACTIVE — vendored SQLCipher 4.6.1 + OpenSSL; per-install DPAPI-protected key; plaintext→encrypted migration |
| packaging | ✅ portable zips + Inno Setup installers compile for CPU & CUDA (`docs/SHIP.md`) |

## Models

`scripts/fetch-models.ps1` downloads the default local set into `data/models/`. All present
and loaded at runtime: Gemma 3n E4B (Fast), Gemma 3 27B (Heavy), Gemma 3 4B + mmproj (VLM),
EmbeddingGemma, whisper base/tiny, Piper voices, Silero VAD, openWakeWord, SCRFD, ArcFace,
and **yolov8n.onnx** (person detection — sourced from a GitHub mirror since the HF
Xenova/onnx-community mirrors now 401; the detector confirms `in=images out=output0 640x640`).

## Honest remaining notes

1. **Perception on GPU.** YOLO/SCRFD/ArcFace run on CPU (CPU ORT package). To accelerate
   them, drop in the CUDA ORT package + `onnxruntime_providers_cuda.dll`; the code already
   requests the CUDA EP and falls back cleanly.
2. **Heavy model on a 12 GB card.** Gemma 3 27B Q4 (~16 GB) still partial-offloads; the
   VramBudget manager trims `n_gpu_layers` to fit. Fast/VLM/Embedding fit comfortably.
3. **Packaging.** DONE — `scripts/package.ps1 -Flavor {cpu,cuda}` produces portable zips and the
   Inno Setup installers compile for both flavors (`dist/Hearth-0.1.0-win64-{cpu,cuda}-Setup.exe`).
   Bundles ship without models; the first-run wizard fetches them. Remaining ship TODOs (code
   signing, a clean-VM smoke pass) are tracked in [`SHIP.md`](SHIP.md).

## Notes from the bring-up

The compiler/linker/runtime surfaced (and we fixed) real issues — see the `Build bring-up`
commit and the **KEY GOTCHAS** in `BUILD.md`. The CUDA-specific ones:

- **nvcc + MSVC `/flag` leak.** A global `add_compile_options(/utf-8 /MP /EHsc /Zc:char8_t-)`
  reaches CUDA compiles verbatim (CMake does not wrap COMPILE_OPTIONS in `-Xcompiler`), and
  nvcc misparses a `/flag` as an input file → *"nvcc fatal: A single input file is required
  for a non-link phase."* Fixed by gating the flags with `$<COMPILE_LANGUAGE:…>` so they
  never reach `.cu` files.
- **char8_t split in the llama tree at C++20.** Our global C++20 standard leaked into the
  vendored engines: `llama-chat.cpp` uses `u8""` as `const char*` (needs char8_t **off**)
  while `common/`'s nlohmann/json uses `std::u8string` (needs it **on**) — irreconcilable.
  Fixed by compiling third_party at its native **C++17** (no char8_t at all); our modules
  stay C++20.
- **nvcc + spaces.** Build through the `C:\pm` junction (no admin needed).
- **Runtime DLLs windeployqt misses.** `Hearth.exe` also needs `fmt.dll`, `spdlog.dll`
  (vcpkg), `opencv_videoio_ffmpeg490_64.dll`, and the CUDA `cudart/cublas/cublasLt 64_13`
  DLLs next to the exe; without them the loader hangs before `main()`. `build-gpu.ps1`
  deploys all of these.
