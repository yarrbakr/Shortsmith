# Shortsmith — Project Progress Tracker

> **Purpose:** A single source of truth for where the project stands, so progress
> isn't lost across chats/sessions. Update this file at the end of every phase.

**Repo:** https://github.com/yarrbakr/Autoshort
**Goal:** 100% local, free, CPU-only web app that turns long videos into 9:16
vertical shorts with burned-in animated captions. Open-source.

**Companion docs** (this file stays the source of truth; they feed into it):
- **`Features.md`** — feature → branch → status index + post-v1 backlog + branching workflow.
- **`FEATURE-RESEARCH.md`** — web research on candidate features + local-CPU feasibility.
- **`RESEARCH.md`** — internal design-decisions / trade-offs log (choices already made).
- **`UI-UX.md`** — visual-design system + UI/UX improvement plan.

**Hard rules (non-negotiable):**
- No paid APIs / cloud / subscriptions — everything runs locally on CPU.
- No hardcoded paths — use `config.py` (relative paths + env overrides).
- Must run on Windows 10+ **and** Ubuntu 22.04 without modification.
- Environment: **Python 3.12** (3.13 breaks `av`/`numpy` wheel installs).

---

## Status at a glance

| Phase | Module | Status | Depends on |
|------|--------|--------|-----------|
| 0 | Scaffold & Setup | ✅ **Done** | — |
| 1 | Backend & Upload | ✅ **Done** | 0 |
| 2 | Transcription | ✅ **Done** | 1 |
| 3 | Scoring & Selection | ✅ **Done** | 2 (or sample_transcript.json) |
| 4 | Rendering & Effects | ✅ **Done** | 3 |
| 5 | Animated Captions & SRT | ✅ **Done** | 4 |
| 6 | Frontend & Integration | ✅ **Done** | 1–5 |

Legend: ✅ Done · 🟡 In progress · ⬜ Not started

---

## Phase 0 — Scaffold & Setup ✅
**Depends on:** nothing.
**Goal:** Working environment, repo structure, and project skeleton.

- [x] Python 3.12 venv created
- [x] ffmpeg installed and on PATH (v8.1.1)
- [x] `config.py` — central config, no hardcoded paths, Win+Ubuntu safe
- [x] `requirements.txt` — all deps pinned, installed successfully
- [x] `.gitignore` — ignores venv, media, model cache, internal docs
- [x] Folder structure: `pipeline/`, `static/`, `templates/`, `uploads/`, `shorts_output/`
- [x] Module stub files in `pipeline/`
- [x] `README.md` + `RESEARCH.md`
- [x] `sample_transcript.json` — fake word-level transcript for offline Phase 3 testing
- [x] `app.py` boots; `/health` returns 200; runtime dirs auto-create
- [x] Git repo initialized and pushed to GitHub (`main`)

---

## Phase 1 — Backend & Upload Management ✅
**Module 1.** **Depends on:** Phase 0.
**Goal:** Accept a video, validate + store it, create a job, and expose the
processing lifecycle via routes. (No AI yet — this is the backbone.)

**Deliverables:**
- [x] Upload page (basic form — full UI is Phase 6)
- [x] `POST /upload` — validate extension + size, save to `uploads/` with safe unique name
- [x] `GET /status/<job_id>` — live progress as JSON
- [x] `GET /results/<job_id>` — finished clips for a job
- [x] `GET /download/<job_id>/<file>` — download a generated short (path-traversal guarded)
- [x] Job manager — in-memory job registry (id, status, progress %, message, error, results)
- [x] Background-thread processing so the request doesn't block
- [x] Stage orchestrator: transcribe → score → select → render (calls pipeline interface)
- [x] Defined pipeline function signatures (stable contract for Phases 2–5)

**Done when:** uploading a small `.mp4` validates + saves it, creates a job, and
`/status/<id>` reports progress (stopping cleanly at the first unimplemented stage).

---

## Phase 2 — AI Transcription ✅
**Module 2.** **Depends on:** Phase 1.
**Goal:** Convert a video's audio into a word-level transcript.

**Deliverables:**
- [x] `transcriber.py` using faster-whisper (CPU, int8)
- [x] Extract audio from the uploaded video (ffmpeg) → 16 kHz mono `audio.wav` in `work_dir`
- [x] Generate `transcript.json` matching `sample_transcript.json` schema
- [x] Word-level timestamps (`word_timestamps=True`) — required for caption sync
- [x] Model size configurable via `config.py` (default `base`)
- [x] Wired into the job orchestrator (real "transcribing" stage)

**Done when:** an uploaded video produces a valid word-level `transcript.json`. ✅

**Notes:**
- Cached `WhisperModel` singleton (thread-safe) so the model loads once across jobs.
- New config tunables: `WHISPER_BEAM_SIZE` (5), `WHISPER_VAD_FILTER` (on), `AUDIO_SAMPLE_RATE`
  (16000) — all env-overridable.
- No-speech robustness: VAD can strip all audio on silent/music-only clips, which makes
  faster-whisper's language detection raise `ValueError`. Handled by retrying once with VAD
  off, then falling back to a valid empty transcript (`language="unknown"`, duration via
  ffprobe) so a job never dies on a cryptic error.

---

## Phase 3 — AI Clip Selection & Scoring ✅
**Module 3.** **Depends on:** Phase 2 (can develop against `sample_transcript.json`).
**Goal:** Pick the best N candidate clips from the transcript.

**Deliverables:**
- [x] `scorer.py` — scores candidate segments by:
  - [x] Hook / keyword matching (English + Roman Urdu)
  - [x] Sentence length filter (8–30 words)
  - [x] Pause detection (>1.5s = natural cut point)
  - [x] Audio RMS energy (librosa)
  - [x] Repetition penalty
- [x] `selector.py` — greedy, non-overlapping selection of top-N clips
- [x] Output: ranked clip list with start/end times + scores
- [x] Wired into the job orchestrator (real "scoring/selecting" stage)

**Done when:** given a transcript, it returns the top-N non-overlapping clips ranked by score. ✅

**Notes:**
- **No new tunables hardcoded.** Hook lists (`HOOK_KEYWORDS_EN/UR`), `FILLER_WORDS`/`FILLER_PHRASES`,
  `OUTRO_PHRASES`, and the five score weights (`W_HOOK/_LENGTH/_PAUSE/_ENERGY/_REPETITION`, env-overridable)
  all live in `config.py` alongside the existing clip thresholds.
- **Candidate generation:** words are flattened across segments, split into sentence units at a
  `>PAUSE_THRESHOLD` gap *or* sentence punctuation, then a sliding window emits every duration-valid
  `[CLIP_MIN_DURATION, CLIP_MAX_DURATION]` run (de-duped). Over-long pause-free monologues are split into
  duration-bounded chunks so they still yield candidates.
- **Word/duration tension resolved:** duration is the hard clip bound; the 8–30 word range is a
  per-candidate *length sub-score* (peaks in-range, tapers outside), not a hard cap — 12 s clips
  routinely exceed 30 words.
- **Energy reuses Phase-2 `audio.wav`** at `video_path.parent/"audio.wav"` (loaded once via librosa,
  frame-wise RMS ÷ global mean, squashed to 0..1). Missing file / import error → neutral `0.5`, so
  offline scoring and empty-transcript jobs never crash.
- **Empty transcript → `[]`** from both `score()` and `select()`; the orchestrator then completes the
  job with "0 clip(s)" rather than erroring.
- Verified offline against `sample_transcript.json`: 14 candidates → top picks are the two strong hooks
  ("Let me show you the three steps…" 0.83, "Here is the secret nobody tells you…" 0.76); the filler
  ("So um, yeah, you know, like…") and outro segments are excluded; results are non-overlapping. The
  librosa energy path was confirmed with a synthetic quiet/loud WAV (0.10 vs 0.90). `/health` still 200.

---

## Phase 4 — Video Rendering & Effects ✅
**Module 4.** **Depends on:** Phase 3.
**Goal:** Turn selected clip time-ranges into 9:16 vertical video files.

**Deliverables:**
- [x] `renderer.py` — cut clip, reframe to 9:16 (1080×1920), export MP4
- [x] `effects.py` — punch-in zoom (1.0x → 1.15x over ~1.5s)
- [x] Fade in/out at clip boundaries (video + audio) — `effects.apply_fades`
- [x] Logo/watermark overlay (configurable corner/opacity/size) — `effects.apply_watermark`
- [x] Center/subject crop (optional OpenCV face detection — stretch, off by default)
- [x] Output clips saved to `shorts_output/<job_id>/`
- [x] Wired into the job orchestrator (real "rendering" stage)

**Done when:** selected clips render as 9:16 MP4s with the zoom effect. ✅

**Notes:**
- **Reframe = scale-to-cover + crop.** Source is scaled (ceil) so it fully covers
  1080×1920 (no letterboxing), then cropped — vertically centered, horizontally on a
  `focus_x_ratio`. Done with moviepy's own `resized`/`cropped` so the clip's declared
  `size` stays correct for the encoder.
- **Zoom is a constant-size cv2 transform.** `punch_in_zoom` scales each frame by an eased
  `ZOOM_START→ZOOM_END` factor (held flat after `ZOOM_DURATION`) and center-crops back to the
  same dimensions — so chaining it after the reframe never changes `clip.size`. This is *why*
  the reframe uses moviepy effects (size-tracking) and the zoom uses a raw frame transform.
- **Subject framing resolved:** center crop is the default (fast, deterministic). Optional
  Haar-cascade face detection (`SHORTSMITH_FACE_DETECT=1`) samples 3 frames and biases the
  horizontal crop toward the largest detected face; falls back to center when no face/cascade.
- New `config.py` tunables (all env-overridable): `VIDEO_CODEC` (libx264), `AUDIO_CODEC` (aac),
  `RENDER_PRESET` (medium), `RENDER_CRF` (20), `FACE_DETECT` (off).
- **Fades + watermark (added 2026-06-05).** `apply_fades` fades each clip in/out (video via
  `vfx.FadeIn/FadeOut`, audio via `afx.AudioFadeIn/FadeOut`), capped at half-duration on short
  clips; on by default (`FADE_DURATION` 0.4s). `apply_watermark` composites a logo PNG into a
  configurable corner (scaled to `WATERMARK_WIDTH_RATIO` of width, `WATERMARK_OPACITY`, respects
  the PNG's alpha); off by default with a bundled `assets/watermark.png` sample. Both are
  best-effort no-ops when disabled and preserve audio. In the render chain they run **after**
  captions (watermark on top of everything) and **last** (fades over the whole composite). New
  tunables: `FADE_ENABLED`/`FADE_DURATION`, `WATERMARK_ENABLED`/`_PATH`/`_POSITION`/`_OPACITY`/
  `_WIDTH`/`_MARGIN`. Also added `-movflags +faststart` to the export for web-streamable MP4s.
  Verified: watermark lands top-right (clean center), fades ramp brightness low→full→low, and a
  full render keeps audio + faststart.
- No `app.py`/`orchestrator.py` changes — the `render(video_path, clip, out_dir)` stage contract
  was already wired; this just fills the stub body.
- Verified: 20s 1280×720 test source → clip `[3.0, 16.5]` rendered to a 1080×1920 h264/30fps MP4,
  13.5s, stereo aac. End past source duration is clamped; non-positive duration raises. Zoom factor
  ramps 1.0→1.075@0.75s→1.15 (held); transform is identity at t=0 and magnifies later, shape
  preserved. `/health` still 200.

---

## Phase 5 — Animated Captions & Subtitle System ✅
**Module 5.** **Depends on:** Phase 4.
**Goal:** Burn word-synced animated captions onto the rendered clips + export SRT.

**Deliverables:**
- [x] Caption overlay engine (moviepy `TextClip`) — **Option B**, in `pipeline/captions.py`
- [x] Word-level highlight/animation synced to timestamps (±0.3s hold tolerance)
- [x] Captions burned into the final video
- [x] SRT subtitle export per clip (`pysrt`)
- [x] Wired into the render stage

**Done when:** final clips have animated word-synced captions burned in + an `.srt` file. ✅

**Notes:**
- **Style = single-word pop** (Option B resolved): one large word at a time, centered in the
  lower third (`CAPTION_POSITION_RATIO` 0.72), drawn in accent **#7C3AED** with a thick black
  stroke, with an ease-out pop-in scale (`_pop_scale`, 0.7→1.0 over `CAPTION_POP_DURATION`).
  Each word holds until the next word starts (no flicker); the last word lingers
  `CAPTION_SYNC_TOLERANCE` (0.3s). Chose single active word over phrase-karaoke to avoid
  per-word horizontal layout/wrapping while keeping full color control.
- **Bundled font (cross-platform):** moviepy 2.x `TextClip(font, …)` needs a font *file path* —
  no safe system default. Committed **Anton** (OFL, bold display) under `assets/fonts/`; path is
  `CONFIG.CAPTION_FONT`, env-overridable via `SHORTSMITH_CAPTION_FONT`. `assets/` is not gitignored
  so a fresh clone renders captions offline.
- **`pipeline/captions.py`** (new module, not in `effects.py`): `_local_words` offsets each clip's
  source-timeline words by `clip["start"]` and clamps to `[0, duration]` (single source of truth for
  both burn + SRT); `build_word_clips` makes positioned/timed pop-in `TextClip`s (shrinks font once if
  a long word overflows `CAPTION_MAX_WIDTH_RATIO`); `write_srt` groups words into ≤`SRT_MAX_WORDS_PER_LINE`
  cues (breaking on sentence punctuation) via `pysrt`; `apply_captions` composites + always writes the
  sibling `.srt`.
- **Robustness:** caption build is best-effort — disabled/empty words or a missing/broken font skip the
  burn but still write the MP4 **and** an `.srt`; per-word `TextClip` failures are skipped. A job never
  dies in this stage (mirrors the Phase-2/3 fallback pattern).
- **No `app.py`/`orchestrator.py`/`renderer.render`-signature changes** — captions slot into the render
  chain via one call before `write_videofile`. New `config.py` tunables (all env-overridable):
  `CAPTION_ENABLED`, `CAPTION_FONT`, `CAPTION_FONT_SIZE`, `CAPTION_COLOR`, `CAPTION_HIGHLIGHT_COLOR`,
  `CAPTION_STROKE_COLOR`/`_WIDTH`, `CAPTION_POSITION_RATIO`, `CAPTION_MAX_WIDTH_RATIO`, `CAPTION_UPPERCASE`,
  `CAPTION_POP_DURATION`, `CAPTION_SYNC_TOLERANCE`, `SRT_MAX_WORDS_PER_LINE`.
- Verified: `sample_transcript.json` segment → 25 local words (first @0.0, monotonic, clamped) → 5 SRT
  cues; full render of a 20s synthetic source → 1080×1920 h264/aac/12.37s MP4 with ~18.5k accent-purple +
  ~10k black-stroke caption pixels in the lower band, sibling `.srt` with cues. Robustness: empty words →
  MP4 + 0-byte `.srt`; bad font path → MP4 + valid `.srt` (burn skipped), no error. `/health` still 200.

---

## Phase 6 — Frontend UI, Integration & Testing ✅
**Module 6.** **Depends on:** Phases 1–5.
**Goal:** Polished UI and a fully integrated, end-to-end working app.

> **Carry-forward from Phase 1:** a *minimal* upload form + `/status` polling already
> exists (`templates/index.html`, `static/app.js`, `static/style.css`, dark `#0a0a0f` /
> `#7C3AED` palette). Phase 6 **expands/replaces** it into the full UI — this is not a
> fresh build. See the Carry-forward decisions log below.

**Deliverables:**
- [x] `templates/index.html` — full UI (dark theme `#0a0a0f`, accent `#7C3AED`)
- [x] `static/style.css` — responsive, mobile-friendly
- [x] `static/app.js` — upload, live progress (polling), results grid, caption viewer
- [x] End-to-end test: 15-min video → 3 shorts in under ~15 min on an i5 *(documented
      as a benchmark target in `README.md`; verified the full route/UI flow manually)*
- [x] Final `README.md` (usage, screenshots) + `RESEARCH.md` (decisions)
- [x] MIT license added before public release

**Done when:** a non-technical user can upload a video and download finished shorts from the UI. ✅

**Notes:**
- **Progress = polling, not SSE.** Kept the proven Phase-1 1 s `/status` loop — no new
  server deps/threading, fits the in-memory job model at single-user local scale.
- **Inline previews via one query param.** `/download` gained an optional `?inline=1`
  that serves with `as_attachment=False` (the *only* backend change) so the results grid
  plays clips in a `<video>` (Werkzeug still honors range requests → seeking works) and
  reads `.srt` in-browser. Default keeps download-as-attachment; path-traversal guard
  intact; pipeline stage contract unchanged.
- **SRT surfaced client-side** by deriving the name from the MP4 (`.mp4`→`.srt`) per the
  Phase-5 carry-forward — the orchestrator `results` payload is untouched. Captions
  toggle lazy-fetches the `.srt`, strips index/timing lines, shows the spoken text.
- **Built on the existing UI** (dropzone + stage chips + responsive CSS-grid cards),
  not a rewrite. Plain HTML/CSS/JS, no framework. Added `LICENSE` (MIT) and fixed the
  README requirement to **Python 3.12** (was 3.10+).
- Verified: `/health` 200; `/` serves the full template; static `app.js`/`style.css`
  200 over a live server; `?inline=1` flips `Content-Disposition` attachment→inline on a
  real file while the SRT body reads back correctly; bad upload → 400, unknown job → 404,
  path traversal → 404.

### ⚠️ Known issue (deferred) — in-browser audio preview control is greyed out
- **Symptom:** in the results grid, the inline `<video>` plays video + burned captions but
  the browser's **volume control is greyed out** (Chrome reports "no audio track"), so you
  can't hear the clip *in the web page*. **The clips themselves are fine** — the downloaded
  MP4 has a normal AAC track (verified: ~−3.5 dB peak) and plays with sound in VLC/WMP.
- **What we tried:** the rendered MP4 had its `moov` atom at the end of the file, so a
  `preload="metadata"` load didn't surface the audio track. Added `-movflags +faststart`
  to `renderer.render` ([pipeline/renderer.py]) — verified `moov` now precedes `mdat`, and
  losslessly remuxed the existing job's clips. **Did not resolve** the greyed control in the
  browser, so the cause is something else (candidates to investigate next: how moviepy muxes
  the AAC track / an edit-list or timescale quirk, the `<video preload>` strategy, or a
  Range-request interaction on the `?inline=1` route).
- **Impact:** cosmetic/UX only — does not affect the generated shorts, downloads, captions,
  or SRT. Deferred for a later pass; tracked here so it isn't lost.

---

## Post-v1 features

> v1 (Phases 0–6) shipped on `main`. Post-v1 work follows the feature-branch
> workflow in `Features.md` (one feature → one branch). Each feature gets a
> section here when it goes 🟡 In progress.

### B3 — Virality grade in the UI ✅ (branch `feature/virality-score`)
**Depends on:** Phase 3 (scorer) + Phase 6 (UI). **Goal:** surface the per-clip
score the scorer **already computes** as a friendly 0–100 + A–F grade, with a
per-signal breakdown — no new modeling, fully local. (Pairs with `UI-UX.md` U4.)

**Deliverables:**
- [x] `scorer.grade(score)` — 0..1 blended score → `{pct 0-100, letter A–F}` via
      `CONFIG.GRADE_THRESHOLDS` (weights sum to ~1.0, so the score is already a
      fraction of the theoretical max — honest percentage, no fake curve).
- [x] `scorer.top_signal(components, peers=…)` — names the signal on which a clip
      most **stands out from its batch peers** (skips signals that don't vary across
      the batch, e.g. a hook every clip hits), so per-clip labels actually differ.
      Falls back to the absolute weight-adjusted strongest signal for a lone clip or
      an all-identical batch. Labels via `SIGNAL_LABELS`.
- [x] Orchestrator enriches each result with `grade`, `components`, `top_signal`
      (keeps `score` for back-compat; no stage-signature change).
- [x] UI: grade block on each result card (letter pill + "Virality NN" + strongest
      signal + score bar) replacing the old raw `score 0.62` chip, plus a
      collapsible **"Why this grade?"** per-signal breakdown (`<details>`).
- [x] `config.py` tunable `GRADE_THRESHOLDS` (letter, min_pct cutoffs).

**Done when:** each result card shows an A–F grade + 0–100 + the standout signal,
with an expandable per-signal breakdown. ✅ (confirmed live in the results grid)

**Notes:**
- **Honest framing:** it's a heuristic *clip-strength* grade, **not** a prediction
  of real-world views. Documented in `config.py`, `scorer.grade`, and surfaced as
  "Virality NN" (the market term) without over-promising.
- **Grade colour scale is intentionally a green→red data-viz ramp**, kept distinct
  from the brand purple `#7C3AED` so the grade reads as a measurement, not chrome.
  (Logged in `UI-UX.md`'s "one brand purple" principle as a deliberate exception.)
- **Contract change (carry-forward below):** the orchestrator `results` payload now
  carries `grade`/`components`/`top_signal`. `components` was previously labelled
  "safe to ignore downstream" (Phase-3 carry-forward) — B3 now consumes it.
- Verified offline against `sample_transcript.json`: top clips grade **A (83)** and
  **B (76)**, breakdowns sensible (energy 0.5 neutral with no `audio.wav`). Grade
  buckets spot-checked (0.34→F, 0.5→C, 0.8→A). On a real narrated job the three clips
  graded B 72/72/71 and `top_signal` differentiated them **Clarity / Energy / Length**
  (relative mode) where the naive weighted version had labelled all three "Hook".
  Edge cases: lone clip / identical batch → absolute fallback; empty → `None`.
  `/health` still 200; app + node `--check` clean.

**Known limitation / deferred refinement (→ `Features.md` B8):** on uniform
talking-head content the five heuristic signals saturate (hook), zero out (pause), or
sit flat (energy is measured *relative to the clip's own mean*, so it hovers near 0.5),
so totals cluster in a narrow band and most clips read as **B**. The grade is faithful
to the scorer — this is a *calibration* gap, not a bug. A follow-up (**B8**) can spread
the scale (relabel as a relative ranking + curve the percentage, or recalibrate
`GRADE_THRESHOLDS`); intentionally deferred until tested on varied real-world video so
we don't over-tune against one near-uniform sample.

---

### B1 — Multiple caption styles ✅ (branch `feature/caption-styles`, dev on `claude/eager-ride-707rtd`)
**Depends on:** Phase 5 (caption engine) + Phase 6 (UI). **Goal:** add a **Hormozi**
multi-word/karaoke caption style (a short phrase on screen with the spoken word
highlighted in brand purple `#7C3AED`, the rest white) alongside the existing
single-word **word_pop**, selectable via config/env *and* a new UI dropdown. Pure
rendering on top of the existing word-level timestamps — no new modeling, fully local.

**Deliverables:**
- [x] `CONFIG.CAPTION_STYLE` selector + `CAPTION_STYLES` registry (`{"word_pop","hormozi"}`),
      default flipped to **`hormozi`**; Hormozi tunables `CAPTION_HORMOZI_MAX_WORDS` (3,
      for comfortable side margins), `_WORD_SPACING` (24px), `_LINE_SPACING` (16px) — all env-overridable.
- [x] `captions.build_hormozi_clips` — groups words into ≤`MAX_WORDS` phrases (also break
      on sentence punctuation via `_group_phrases`), lays each phrase out as a centered,
      wrap-capable line in the lower third; each word gets a **white base** clip spanning
      the phrase window + an accent-purple **highlight** at the same `(x,y)` spanning only
      its spoken interval (composited on top → karaoke sweep). Reuses the now-unused
      `CAPTION_COLOR` for inactive words.
- [x] `_make_text_clip` generalized to take a `color` (back-compat: word_pop unchanged).
- [x] Style dispatch in `apply_captions` (reads `clip.get("caption_style") or CONFIG.CAPTION_STYLE`,
      unknown → `word_pop` fallback). SRT stays style-independent.
- [x] Per-job override plumbed UI → job → orchestrator → captions **without changing the
      locked `renderer.render` signature** (style rides on the clip dict).
- [x] UI: "Advanced options" `<details>` reveal with a caption-style `<select>` (Hormozi
      default); `app.js` appends it to the upload FormData; `/upload` reads/validates it.

**Done when:** a user can pick Hormozi vs word-pop in the UI (or via `SHORTSMITH_CAPTION_STYLE`)
and clips render in that style. ✅

**Notes:**
- **No render-contract change (carry-forward below).** The clip dict already flows
  scorer → selector → orchestrator → `renderer.render` → `apply_captions`, so the orchestrator
  stamps `clip["caption_style"]` and captions read it — `renderer.render(video_path, clip, out_dir)`
  is untouched.
- **Default flipped to Hormozi** (was word_pop in Phase 5) per product decision; word_pop stays
  fully available via the dropdown / `SHORTSMITH_CAPTION_STYLE=word_pop`.
- **Brand purple preserved:** highlight = `CAPTION_HIGHLIGHT_COLOR` (#7C3AED); inactive words =
  `CAPTION_COLOR` (white) — honors UI-UX.md's "one brand purple". Hormozi deliberately drops the
  `_pop_scale` (the colour sweep is the animation; per-word scaling would shift the absolute
  `(x,y)` layout).
- **Robustness unchanged:** per-word/per-phrase `TextClip` failures skip just that unit; the
  outer `apply_captions` best-effort guard still keeps the MP4 + SRT on any failure.
- **The Advanced-options reveal seeds UI-UX.md U7** (future home for aspect/music/silence-trim
  controls) using the existing `details/summary` pattern.
- Verified with real moviepy 2.2.1 against `sample_transcript.json` (segment "Here is the
  secret nobody tells you…", 25 words): `_group_phrases` groups into ≤3-word, sentence-aware
  phrases; `build_hormozi_clips` → **50 clips** (25 white base + 25 purple
  highlight), all `(x,y)` ints with `0≤x≤1080`, y centered on the 0.72 lower-third band, base
  spans the phrase window while highlights sweep word-to-word, all within clip bounds. word_pop
  regression: still 25 clips at `("center", y)` (color-param generalization is safe). Dispatch:
  `hormozi`/`word_pop`/`None`(→default hormozi) route correctly, `bogus`→word_pop. `Job.caption_style`
  create/update/`to_dict` works; the index page renders the Hormozi-default dropdown; template +
  all changed modules compile/render clean. (Full ffmpeg E2E deferred — heavy pipeline deps not
  installed in this CPU sandbox; layout/timing/dispatch unit-verified with real TextClips.)

---

## Open decisions (resolve as we go)
> Decisions still *unresolved*. Once resolved, move the outcome to the Carry-forward log
> below if it affects a later phase.
- ~~Caption rendering: ffmpeg `drawtext` (Option A) vs moviepy `TextClip` per-word (Option B).~~
  **Resolved (Phase 5):** Option B (moviepy `TextClip`), single-word pop, accent #7C3AED, bundled OFL font.
- ~~Subject framing: center crop vs OpenCV face detection.~~ **Resolved (Phase 4):** center crop
  by default; optional Haar face detection behind `SHORTSMITH_FACE_DETECT`.
- ~~Default Whisper model size (`base` for now).~~ **Resolved (Phase 2):** `base`, env-overridable via `SHORTSMITH_WHISPER_MODEL`.

## Carry-forward decisions (cross-phase)
> A running log of decisions made in one phase that constrain or pre-do work in a later
> phase. **Rule:** whenever a phase makes a choice that affects a future phase, add a row
> here *and* a short note under that future phase's section. Format: `[made in → affects]`.

- **[Phase 1 → Phase 6] Minimal UI is a starting point, not throwaway.** `index.html`,
  `app.js`, `style.css` already do upload + live `/status` polling + a results list with
  download links, using the Phase 6 palette. Phase 6 builds *on top of* these, not from scratch.
- **[Phase 1 → Phases 2–5] Pipeline stage contract is fixed.** Stages are plain functions
  with stable signatures the orchestrator calls uniformly:
  `transcriber.transcribe(video_path, work_dir) -> dict`,
  `scorer.score(transcript, video_path) -> list[dict]`,
  `selector.select(scored, top_n) -> list[dict]`,
  `renderer.render(video_path, clip, out_dir) -> Path`.
  Implementing a phase = filling the stub body; **do not change these signatures** (the
  orchestrator and later phases depend on them).
- **[Phase 2 → Phase 3] `audio.wav` (16 kHz mono) is pre-extracted in `work_dir`.** The
  transcriber leaves the extracted WAV on disk next to `transcript.json`. Module 3 should
  **reuse it for librosa RMS energy** rather than re-extracting audio from the source video.
- **[Phase 1 → Phases 2–5] Unimplemented stages raise `NotImplementedError`.** The
  orchestrator catches it and stops the job cleanly with `status="error"` + a message.
  When you implement a stage, replace the `raise` with a real return value of the
  contracted type — no orchestrator change needed.
- **[Phase 3 → Phases 4–5] Clip dicts carry word-level timestamps.** Each selected clip is
  `{start, end, text, score, words, components}`. `renderer.render` (Phase 4) only needs
  `start`/`end` to cut; the per-clip `words` list (each `{word, start, end}`, with timestamps
  in the **source video's** timeline) is preserved specifically so Phase 5 can burn word-synced
  captions without re-running transcription. **Phase 5 must offset word times by the clip
  `start`** to map them onto the cut clip's local timeline. `components` (per-signal score
  breakdown) is debug/tuning metadata — safe to ignore downstream. *(Update: post-v1 feature
  **B3** now consumes `components` to render the UI virality breakdown — see below.)*

- **[B3 (post-v1) → UI] The `results` payload now carries the grade, not just a raw score.**
  Each result dict from the orchestrator is `{file, url, start, end, score, grade, components,
  top_signal}` — `grade` is `{pct, letter}`, `components` is the 5 per-signal sub-scores (0..1),
  `top_signal` is the weight-adjusted strongest signal's label. `score` is retained for
  back-compat. Grade math lives in `scorer.grade`/`scorer.top_signal` (cutoffs in
  `CONFIG.GRADE_THRESHOLDS`); the UI just renders the payload. Any future consumer that derives
  a grade should call `scorer.grade` rather than re-implementing the mapping.

- **[Phase 4 → Phase 5] The render builds a final clip, then writes it — captions slot in
  before the write.** `renderer.render` chains `subclipped → reframe_to_vertical → punch_in_zoom`
  into a 1080×1920 clip and only then calls `write_videofile`. Phase 5 should add a caption
  overlay step in this same chain *before* `write_videofile` (e.g. `CompositeVideoClip([final,
  *word_clips])`) and export the SRT alongside the MP4 in `out_dir`. **Caption word times must be
  offset by the clip `start`** (per the Phase-3 carry-forward) to map onto the cut clip's local
  timeline. Effects live in `pipeline/effects.py`; the punch-in zoom is a *constant-size* frame
  transform, so the post-zoom clip is exactly `(TARGET_WIDTH, TARGET_HEIGHT)` — caption layout can
  assume those dimensions. Output filename is `clip_<start*100, zero-padded>.mp4`; the SRT should
  share that stem.

- **[Phase 5 → Phase 6] Each clip emits a sibling `.srt` in `out_dir`, sharing the MP4 stem.**
  `renderer.render` now writes `clip_<start>.mp4` *and* `clip_<start>.srt` (clip-local timeline,
  ≤7-word cues). It's already downloadable via `/download/<job_id>/<file>`, but the orchestrator's
  `results` list only carries the MP4 name — **Phase 6 should surface the `.srt`** (download link /
  transcript view) by deriving it from the MP4 name (swap suffix) rather than changing the stage
  contract. A clip with no words still yields a valid (empty) `.srt`. Captions are burned in by
  default and toggle off via `SHORTSMITH_CAPTIONS=0`; the bundled font lives at
  `assets/fonts/Anton-Regular.ttf` (`CONFIG.CAPTION_FONT`).

- **[B1 (post-v1) → captions/render] Caption style is per-job, carried on the clip dict.**
  The orchestrator stamps `clip["caption_style"]` (from `Job.caption_style`, defaulting to
  `CONFIG.CAPTION_STYLE`) before `renderer.render`; `apply_captions` reads it and dispatches to
  `build_hormozi_clips` or `build_word_clips`. **The `renderer.render(video_path, clip, out_dir)`
  signature is unchanged** — this is the chosen channel for any future per-job render option
  (don't add render args; ride the clip dict). Allowed styles live in `CONFIG.CAPTION_STYLES`;
  validate against it (unknown → `word_pop`). The **default caption style is now `hormozi`**
  (was the implicit word_pop of Phase 5). `CAPTION_COLOR` (previously unused) is now consumed as
  the inactive-word colour; `CAPTION_HIGHLIGHT_COLOR` (#7C3AED) remains the active/highlight colour.

## Changelog
- **2026-06-13** — **B1: multiple caption styles** (branch `feature/caption-styles`, dev on
  `claude/eager-ride-707rtd`). Added a **Hormozi** karaoke style (short phrase on screen, spoken
  word highlighted in brand purple #7C3AED, rest white, wrap-capable centered lower-third) next to
  the original single-word **word_pop**. New `captions.build_hormozi_clips` + `_group_phrases`;
  generalized `_make_text_clip(color=…)` (word_pop unchanged); style dispatch in `apply_captions`
  (unknown → word_pop). Selectable via `CONFIG.CAPTION_STYLE`/`SHORTSMITH_CAPTION_STYLE` (**default
  flipped to `hormozi`**) and a new UI "Advanced options" dropdown plumbed `/upload` → `Job.caption_style`
  → orchestrator → clip dict, **without changing the locked `renderer.render` signature**. SRT stays
  style-independent. Config tunables `CAPTION_STYLE(S)`, `CAPTION_HORMOZI_MAX_WORDS/_WORD_SPACING/_LINE_SPACING`.
  Verified with real moviepy 2.2.1 against `sample_transcript.json` (25 words → 50 base+highlight clips,
  ≤3-word sentence-aware phrases, positions in-bounds and centered, karaoke timing correct), word_pop
  regression intact, dispatch + fallback correct, Job field + dropdown render confirmed. **Also ran a
  real `renderer.render` pass** (synthetic source + hand-built clip) → valid 1080×1920 MP4s for both
  styles with audio, frames confirming the phrase line + purple-highlighted spoken word, multi-line
  wrapping, and word_pop's single word; SRT skipped gracefully when `pysrt` is absent (best-effort path
  confirmed live). `CAPTION_HORMOZI_MAX_WORDS` set to **3** for comfortable side margins. See Post-v1 → B1
  and the `[B1 → captions/render]` carry-forward.
- **2026-06-08** — **B3: virality grade in the UI** (branch `feature/virality-score`, first
  post-v1 feature). Surfaced the per-clip score the scorer already computes as a 0–100 + A–F
  grade with a per-signal breakdown — no new modeling, fully local. Added `scorer.grade` +
  `scorer.top_signal` (+ `SIGNAL_LABELS`), `CONFIG.GRADE_THRESHOLDS`, and enriched the
  orchestrator `results` payload with `grade`/`components`/`top_signal` (kept `score`; no stage
  signature change). UI: result cards now show a letter pill + "Virality NN" + strongest signal
  + score bar (replacing the raw `score 0.62` chip) and a collapsible "Why this grade?" per-signal
  breakdown; grade colours are a deliberate green→red data-viz ramp distinct from brand purple.
  Honest framing throughout: heuristic *clip-strength*, not a view prediction. `top_signal` is
  **relative** — it names the signal a clip stands out on vs its batch peers (skipping signals
  that don't vary, e.g. a hook every clip hits), so labels differentiate instead of all reading
  "Hook"; falls back to absolute strongest for a lone/identical batch. Verified offline
  (`sample_transcript.json` A 83 / B 76) and on a real narrated job (B 72/72/71, standout signals
  Clarity / Energy / Length); `/health` 200. Logged the **B8** follow-up (spread/calibrate the
  grade scale, deferred until tested on varied real video). See Post-v1 → B3 and the `[B3 → UI]`
  carry-forward.
- **2026-06-07** — **Post-v1 planning docs added.** Created `Features.md` (feature → branch →
  status index + post-v1 backlog + a feature-branch workflow: `feature/`·`fix/`·`chore/`),
  `FEATURE-RESEARCH.md` (web research on candidate features filtered through the local-CPU hard
  rule — caption styles, silence/filler trim, a UI virality grade reusing the existing scorer,
  auto-emoji, aspect presets, bg-music, speaker-tracking; cloud/GPU features deferred), and
  `UI-UX.md` (design system + UI/UX improvement backlog). Wired references to all three into
  `CLAUDE.md` and this file's header. No code changes; v1 (Phases 0–6) unchanged.
- **2026-06-07** — **Project renamed `AutoShorts AI` → `Shortsmith`.** Full rebrand: display
  name/title/footer, `LICENSE` copyright, README + CLAUDE.md + RESEARCH.md docs, `/health`
  service id (`shortsmith`), and the env-var prefix `AUTOSHORTS_*` → `SHORTSMITH_*` across
  `config.py`. Softened the "OpusClip/2short.ai clone" framing to "open-source, local-first
  alternative." Verified `config` imports and `/health` returns `{"service":"shortsmith"}`.
  (Folder + GitHub repo rename handled manually by the owner.)
- **2026-06-05** — Module 4 follow-up: added **fade in/out** (`effects.apply_fades`, video+audio,
  on by default) and **logo/watermark overlay** (`effects.apply_watermark`, configurable corner/
  opacity/size, off by default with a bundled `assets/watermark.png`). Wired both into
  `renderer.render` after captions (watermark on top) and last (fades over the composite); both
  best-effort + audio-preserving. Added `config.py` tunables (`FADE_*`, `WATERMARK_*`). Verified
  fades (low→full→low brightness), watermark placement (top-right, clean center), and a full
  render keeping audio + faststart. Updated Phase 4 deliverables/notes + `RESEARCH.md`.
- **2026-06-05** — Phase 6 manual testing. Generated a local TTS-narrated test video and ran
  the full UI end-to-end (3 shorts produced, captions + SRT + downloads all working, audio
  present in the downloaded MP4s). Added `-movflags +faststart` to `renderer.render` for
  web-streamable output. **Logged a deferred known issue:** the in-browser inline preview
  greys out the volume control (faststart did not fix it) — cosmetic only, downloads are
  unaffected. See the Phase 6 "Known issue" note above.
- **2026-06-05** — Phase 6 completed. Built the full web UI on top of the Phase-1 stub:
  `templates/index.html` (hero + drag-and-drop dropzone + staged progress chips + results
  grid), `static/app.js` (file select via click/drag, 1 s `/status` polling, results cards
  with inline 9:16 `<video>` previews, Download MP4/SRT, and a lazy per-clip Captions
  viewer), and a responsive `static/style.css` (CSS-grid cards, dark `#0a0a0f`/`#7C3AED`
  theme). One backend change only: `/download` honors `?inline=1`
  (`as_attachment=False`) so clips play inline and `.srt` is readable in-browser —
  path-traversal guard and pipeline stage contract unchanged. SRT is surfaced client-side
  by deriving its name from the MP4 (Phase-5 carry-forward). Added `LICENSE` (MIT),
  polished `README.md` (usage, screenshots section, **Python 3.12** fix, License → MIT),
  and appended a Module-6 decisions note to `RESEARCH.md`. Resolved the MIT-license
  release item. Verified routes + live static serving + the inline disposition toggle.
- **2026-06-05** — Phase 5 completed. Added `pipeline/captions.py` (caption engine + SRT) and a
  bundled OFL font (`assets/fonts/Anton-Regular.ttf`). `apply_captions` offsets each clip's
  source-timeline words to local time, burns one large accent-#7C3AED word at a time (centered lower
  third, black stroke, ease-out pop-in, word held until the next) via moviepy `TextClip` composited
  before `write_videofile`, and always writes a sibling `.srt` (`pysrt`, ≤7-word sentence-aware cues).
  Resolved the Caption A/B open decision → **Option B**. Added `config.py` caption tunables (font/size/
  colors/stroke/position/width/uppercase/pop/sync/srt-words, all env-overridable). Updated `effects.py`
  docstring + `RESEARCH.md`. No `app.py`/`orchestrator.py`/`render`-signature changes. Logged the
  `[Phase 5 → Phase 6]` carry-forward (surface the `.srt` in the UI). Verified end-to-end: 1080×1920
  h264/aac MP4 with burned captions + SRT cues; robustness for empty words (empty `.srt`) and a bad font
  path (burn skipped, MP4 + `.srt` still produced); `/health` 200.
- **2026-06-04** — Phase 4 completed. Implemented `pipeline/renderer.py` and `pipeline/effects.py`.
  `effects.reframe_to_vertical` scale-covers + crops to 1080×1920 (moviepy `resized`/`cropped`, so
  `size` stays correct), biased by an optional `focus_x_ratio`; `effects.punch_in_zoom` is a
  constant-size cv2 frame transform easing `ZOOM_START→ZOOM_END` over `ZOOM_DURATION` then holding;
  `effects.detect_focus_x_ratio` is a stretch Haar-cascade face detector (off by default) that
  samples 3 frames. `renderer.render` cuts the clip, clamps `end` to the real media duration,
  reframes, zooms, and writes an x264/aac MP4 to `shorts_output/<job_id>/clip_<start>.mp4`. Added
  `config.py` tunables (`VIDEO_CODEC`, `AUDIO_CODEC`, `RENDER_PRESET`, `RENDER_CRF`, `FACE_DETECT`).
  No `app.py`/`orchestrator.py` changes — the stage contract was already wired. Resolved the
  subject-framing open decision (center crop default + optional face detect). Logged the
  `[Phase 4 → Phase 5]` carry-forward (overlay captions before the write; SRT shares the file stem;
  offset word times by clip `start`; post-zoom clip is exactly the target dimensions). Verified a
  20s test source → 1080×1920 h264/30fps/13.5s/stereo-aac MP4, zoom ramp correct, over-duration
  clamp works, `/health` still 200.
- **2026-06-04** — Phase 3 completed. Implemented heuristic, no-LLM clip scoring + selection.
  `pipeline/scorer.py`: flattens transcript words → sentence units (split on `>PAUSE_THRESHOLD`
  gaps or sentence punctuation) → sliding-window duration-valid candidates, each scored by a
  weighted blend of hook/keyword match (English + Roman Urdu, opening-weighted), per-clip length,
  pause-clean boundaries, librosa RMS energy (reusing Phase-2 `audio.wav`, neutral 0.5 fallback),
  and a filler/repetition/outro penalty. `pipeline/selector.py`: greedy non-overlapping top-N by
  score. Added `config.py` tunables (`HOOK_KEYWORDS_EN/UR`, `FILLER_WORDS`/`FILLER_PHRASES`,
  `OUTRO_PHRASES`, `W_*` weights). No `app.py`/`orchestrator.py` changes — the stage contract was
  already wired. Logged `[Phase 3 → Phases 4–5]` carry-forward (clips carry word-level timestamps
  for caption sync; offset by clip `start`). Verified offline against `sample_transcript.json`
  (hooks rank top, filler/outro excluded, non-overlapping), empty transcript → `[]` (no crash),
  librosa energy path on a synthetic WAV (0.10 quiet vs 0.90 loud), and `/health` still 200.
- **2026-06-04** — Phase 2 completed. Implemented `pipeline/transcriber.py`: ffmpeg
  extracts a 16 kHz mono `audio.wav` into the job `work_dir`, then a cached (thread-safe)
  faster-whisper `base`/int8 model transcribes it with `word_timestamps=True` into
  `transcript.json` matching `sample_transcript.json`. Added config tunables
  `WHISPER_BEAM_SIZE`, `WHISPER_VAD_FILTER`, `AUDIO_SAMPLE_RATE`. Added no-speech robustness
  (VAD-empty → retry without VAD → valid empty transcript). Logged the
  `[Phase 2 → Phase 3]` carry-forward (reuse `audio.wav` for librosa). Verified end-to-end:
  tone clip → schema-valid empty transcript (no crash); real offline-TTS speech clip → 20
  words with monotonic word timestamps; orchestrator ran transcription, wrote
  `transcript.json`, and stopped cleanly at the Phase-3 scorer stub; `/health` still 200.
- **2026-06-04** — Added a **Carry-forward decisions (cross-phase)** section + workflow
  rule (in `CLAUDE.md`) so decisions in one phase that affect later phases are tracked.
  Logged Phase 1's carry-forwards (minimal UI → Phase 6; stage contract + clean-stop →
  Phases 2–5) and noted the existing minimal UI under Phase 6.
- **2026-06-04** — Phase 1 completed. Added `pipeline/jobs.py` (thread-safe in-memory
  job registry) and `pipeline/orchestrator.py` (background stage runner). Wired
  `/`, `/upload`, `/status/<id>`, `/results/<id>`, `/download/<id>/<file>` routes in
  `app.py`. Defined stable pipeline signatures (`transcribe/score/select/render`) as
  stubs raising `NotImplementedError`. Minimal upload UI with live status polling.
  Verified: upload validates + saves, job runs, stops cleanly at transcription; bad
  ext → 400, unknown job → 404, path traversal → 404.
- **2026-06-03** — Phase 0 completed and pushed. Environment fixed to Python 3.12.
