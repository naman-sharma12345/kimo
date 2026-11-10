## v8.12.1 "face avoidance targets the face" (2026-11-03)

Fixes a real defect in V8.12.0's caption engine: face/subject avoidance was moving captions off the
whole detected skin-toned BODY band -- face, neck, and whatever skin is contiguous below it (chest,
hands) -- not just the face. On a seated talking-head shot the preferred bottom lower-third routinely
"overlapped" that whole-body band even though it was nowhere near the actual head, so avoidance fired
needlessly; and when it did fire, it jumped straight to a FIXED fallback spot (top of frame) with no
check that the fallback itself cleared anything, landing the caption touching or crowding the actual
head -- worse than doing nothing. Confirmed on the real `talkinghead_real_final.mp4` benchmark clip:
with avoidance off the caption correctly sits low, clear of the face; with avoidance on (V8.12.0) it
jumped to the top of the frame, crossing the subject's eyes and forehead.

**The fix (`crates/kimo-core/src/ext/caption_engine.rs`):**
- **Head region, not body region.** The engine's face/subject detector (`speech_words::skin_band`) only
  ever finds a whole contiguous skin-toned band -- it has no notion of a face box. `place_from_face`
  (the new, directly-testable pure scorer `place_unit` now wraps) derives the actual head/face region as
  the TOP slice of that band, via a new `layout.face_region_frac` (default 0.35 -- a seated frontal
  subject's forehead-to-chin reliably sits in the top third of their own skin band; a documented smart
  default, not a measurement, and fully overridable).
- **Keep the preferred anchor whenever it clears.** The preferred lower-third is kept exactly as before
  whenever its own text box clears the derived head region by `layout.face_margin_frac` (default 0.04,
  4% of frame height) -- real editors keep a lower-third under the chin and only move when the text
  would actually cover the face.
- **Score candidates, never jump blind.** When the preferred anchor doesn't clear, the engine tries a
  same-side nudge (`layout.lower_nudge_frac`, default 0.08) first, then the opposite band -- taking the
  first candidate that both clears the head region by the margin AND stays inside the frame's own safe
  margins (platform UI clearance at the bottom, `layout.top_safe_frac` -- default 0.02 -- at the top).
  The old fixed "jump to 0.2" fallback, chosen with no clearance check at all, is gone.
- **Honest fallback.** If literally no candidate clears (an extreme close-up, for instance), the engine
  keeps the preferred anchor exactly where it was -- never a spot touching the head that might be worse
  -- and raises stroke/shadow/box strength to the spec's own strongest legibility setting to compensate,
  the same mechanism used for a bright background, via a new `forced_overlap` signal threaded into the
  existing auto-contrast step.
- Every new threshold (`face_region_frac`, `face_margin_frac`, `caption_half_height_frac`,
  `lower_nudge_frac`, `top_safe_frac`) is an ordinary overridable `layout` spec field with a smart
  default -- Naman's standing rule: the engine has defaults, the AI has full freedom, presets and
  defaults are reference only. The tool schema documents all five.

**Tests (`tests/quality_v8120.rs`, +4, 19 total):** the pure `place_from_face` scorer is exercised
directly with a synthetic detected face/subject band, no real frame needed -- a high face with a bottom
caption stays put; a low, wide body band forces a move whose final box provably clears the margin; a
battery of face positions across top/bottom/wide-frame anchors never lands on the head (with one
documented exception: an engineered unavoidable case proves the honest `forced_overlap` fallback keeps
the anchor rather than parking it somewhere worse); and `fixed_y_frac` pins the position exactly,
ignoring face avoidance entirely, at both the `caption_engine_compose` and pure-scorer level. Two of the
four fail against the pre-fix (V8.12.0) logic, reproducing the exact reported defect (the caption lands
at the fixed fallback, still overlapping the head) -- confirmed by temporarily restoring the old scoring
rule and rerunning, then reverting.

`golden_registry.txt`'s one line for `caption_engine_compose` changed (the tool schema gained the five
new `layout` fields); `golden_frames.txt`, `recipe_frames.txt` and `golden_project.txt` are untouched.

**Sheet and demo**, same real clip as V8.12.0 (`talkinghead_real_final.mp4`):
`/home/user/tab/files/v7q/captions_v8121.png` (five panels: avoidance off; the V8.12.0 bug reproduced
live on this clip's own frame; the V8.12.1 fix on the same frame, now matching the off baseline;
avoidance off at an explicit top position, showing it would overlap; and the V8.12.1 fix at that same
top position, correctly relocating to the clear bottom) and
`/home/user/tab/files/v7q/captions_v8121_demo.mp4` (12s, real ASR word timings, the fixed engine's
default auto placement throughout).

## v8.12.0 "the caption engine" (2026-11-03)

A real caption **engine**, not another named preset. Every prior version (including the five looks this
version re-expresses) hard-coded a style function: fixed segmentation, fixed timing, fixed colours. This
version is a single new tool, `caption_engine_compose`, that takes a *spec* -- segmentation, timing, layout,
contrast, style, per-word state deltas, emphasis rules, and free keyframe animation, all data, all overridable,
all documented -- and composes a caption from it. The five old looks (pop/karaoke/clean/boxed/impact) and the
three restyle looks (subtitle/boxed/yellow) are now themselves just spec data the new engine reads, not special
cases baked into the engine's logic. Presets are reference points, not a ceiling: every field they set can be
overridden per-call, per-word, or replaced with free keyframes on any property.

**New module:** `crates/kimo-core/src/ext/caption_engine.rs`, fully self-contained (zero dependency on
`auto_captions.rs`'s private internals -- its own `visible_media`/media-sampling/face-detection helpers,
built only on public `Project`/`Clip`/`Asset` fields, so nothing about the existing preset code path was
touched or put at risk).

**What the engine owns, that no prior version did:**
- **Segmentation** -- phrase/clause/pause-aware cuts, a reading-speed (CPS) cap that cuts a cue before it
  would read too fast (excluding bare punctuation tokens from the count, so a trailing "." riding a word's
  own timestamp can't inflate the measured rate), a no-orphan pass that never leaves a single word stranded
  when a merge is actually possible, and balanced line-breaking within a unit.
- **Timing** -- snaps to the real word boundaries, bridges small gaps between cues so there's no flicker,
  holds a cue a configurable amount after its last word, enforces a minimum on-screen duration, and pulls a
  cue's end back before a shot cut rather than straddling it (reporting when it had no room to do so).
- **Layout** -- safe-area aware by default, with per-unit face/subject avoidance (sampling the actual visible
  frame at each cue's own midpoint, not one whole-clip guess), or a `fixed_y_frac` pin for styles that always
  sat at one fixed offset regardless of what's in frame.
- **Contrast-aware legibility** -- measures the real background luma behind each cue and strengthens stroke/
  shadow/box only as much as that frame needs, reusing `text_contrast::background_lums`.
- **Data-driven style primitives** -- per-word active/spoken/upcoming colour and scale deltas, emphasis by
  explicit word list, by keyword, or by measured audio energy (loudest words, via `speech_words::onsets`),
  and free per-property keyframe animation with every easing `keyframe::Ease` already supports, layered last
  over everything else.

**Presets re-expressed as spec data, not special-cased:** pop, karaoke, clean, boxed, impact (the
`auto_captions` looks) and subtitle, boxed, yellow (the `set_caption_style` restyle looks) are now
`preset_spec()` entries the engine's own general machinery reads -- no preset-specific code path.
- `clean` is **byte-identical** to the legacy `auto_captions(style="clean")` output: confirmed by rendering
  both to 20 frame hashes across a real 8-word fixture and asserting equality (`preset_byte_identity_report`,
  a permanent regression test).
- The other seven match the legacy output on every field checked -- segmentation boundaries, word timing,
  size, colour, stroke width, screen position, and which words get emphasized -- except one real gap: the
  legacy looks pop each word with a brief scale "kick" timed to its own onset (a transient animation, not a
  sustained multiplier) and, for `pop` specifically, fade each word in individually as it's spoken (`reveal`).
  The engine's word-state system doesn't yet reproduce that exact animation curve. This is reported here
  plainly rather than claimed fixed, and is pinned in the same test so a future claim of "now identical" has
  to actually be true to pass.
- Two new, additive spec fields exist specifically because of this work and are documented in the tool
  schema: `style.size_basis` (`width`, the default matching the create-path looks, or `short_side`, matching
  the restyle-path looks) and `layout.fixed_y_frac`.

**Schema and freedom:** the tool's own description states plainly that every preset is a reference point, not
a ceiling, and that the AI calling it has full freedom over every field -- segmentation, timing, layout,
contrast, style, per-word overrides, and free keyframes -- confirmed by a dedicated wording test
(`tool_description_states_presets_are_reference_only_and_ai_has_full_freedom`).

**Tests:** `crates/kimo-core/tests/quality_v8120.rs`, 15 tests covering every "hard part" named above --
no-orphan segmentation, CPS limiting (excluding punctuation from the count), phrase/clause/pause breaks,
no-dangle line breaks, no-overlap and snap-to-word timing, minimum duration, gap bridging, shot-cut avoidance,
auto-contrast strength, emphasis by list and by audio energy, spec validation error messages, the tool
description wording, and the preset byte-identity report above. The full required scoped suite (auto_edit,
golden_frames, recipes, registry_lint, quality_v893/v8100/v8110/v8120, color_pipeline) plus every existing
caption-named test file (auto_captions, caption_confidence, caption_legibility, caption_validate,
director_profile_captions, style_captions_batch, transcript_captions) all pass unchanged -- zero lines of the
existing preset code paths were touched.

**Golden registry:** `golden_registry.txt` gained one new, legitimate entry for the new tool's schema hash
(computed by hand, never via `KIMO_UPDATE_GOLDEN`); `golden_frames.txt` and `golden_project.txt` are
unchanged and confirmed byte-identical by the same test run.

**Before/after and demo:** `files/v7q/captions_v8120.png` (a real talking-head clip, real transcribed speech,
six panels: the legacy `boxed` look, the engine's byte-identical `clean` preset, a free-spec bold word-by-word
active highlight, a free-spec audio-energy emphasis look, and a face-avoidance off/on comparison on the same
frame) and `files/v7q/captions_v8120_demo.mp4` (8.4s, real speech, word-synced active/upcoming/emphasis
states, face avoidance live throughout).

## v8.11.1 "keep SDR clips bit-identical under hdr_tonemap (fix V8.11.0 regression)" (2026-11-03)

V8.11.0 shipped with an unintended brightness/colour shift on ordinary SDR footage: frame means on the real
benchmark came out about 2 levels brighter in R/G and 0.6 in B on EVERY clip, average PSNR 40.3 dB against
the V8.10.0 render (min 37.6), visually invisible but real and systematic.

**Root cause (`decode()`'s `color_override`, render.rs):** the V8.11.0 branch read `if p.hdr_tonemap {...}
else if p.color_tag_sanity {...}`, keyed purely on the project-level `hdr_tonemap` flag. Since `auto_edit`
turns `hdr_tonemap` on by default, that first branch was taken for EVERY clip once a project went through
`auto_edit`, regardless of whether a given clip was actually HDR. For a non-HDR clip, `hdr_source(path)`
correctly returned `None`, but `.unwrap_or_default()` just produced an empty override -- the code never fell
through to the `color_tag_sanity` mistag check in the `else if`, which it would have reached had
`hdr_tonemap` been off. The real casualty: `talkinghead_real_final.mp4` (bt470bg, no primaries/transfer tag,
the audit #2 fixture's own real-world shape) used to get `color_tag_sanity`'s "decode as bt709" correction;
under V8.11.0 that correction was silently dropped, so the clip decoded through ffmpeg's own auto-detected
colour matrix instead -- the source of the shift. (The three b-roll clips are correctly tagged bt709 and
were never "mistagged", so they were already unaffected by this specific clip's mistag logic; the project-
wide brightness delta the previous check measured came from the mistagged clip's share of the benchmark.)

**Fix:** the HDR branch now only wins when `hdr_source(path)` actually returns `Some(transfer)` for THAT
clip -- `if let Some(transfer) = if p.hdr_tonemap && !is_img0 { hdr_source(path) } else { None } { ... } else
if p.color_tag_sanity && !is_img0 && mistagged_hd_source(path) { ... }`. A non-HDR clip now always falls
through to the `color_tag_sanity` check exactly as it did before V8.11.0; an HDR clip still gets the tonemap.
Nothing else changed -- the tonemap filter chain, peak estimation and detection logic are untouched.

**Verified:** re-rendered the real benchmark with the rebuilt binary (hdr_tonemap at its normal auto_edit
default, `true`) -- video-stream md5 is now `e31b6789e10c3fbd43c754f09f90f14f`, byte-identical to the
V8.10.0 (core_v07) render. Re-ran the HDR before/after measurement on the synthetic HLG clip to confirm the
fix didn't touch the tonemap path itself: uncorrected mean_luma 99.4/std 37.8/mean_sat 160.4, corrected
118.7/61.2/240.4, SDR reference 125.0/66.7/245.8 -- unchanged from V8.11.0's own numbers within measurement
noise.

**New regression coverage (`tests/quality_v8110.rs`):** the existing "SDR untouched" test only ever toggled
`hdr_tonemap` while leaving `color_tag_sanity` at the raw `Session` default of `false` -- it could never have
hit this bug, because the mistag branch it would have protected was never reachable in that test's own
setup. Two new tests render a plain bt709 clip and an untagged/bt470bg-mistagged clip (the real
talkinghead_real_final.mp4 shape) with BOTH `color_tag_sanity` and `hdr_tonemap` on, matching `auto_edit`'s
actual defaults, and assert the output is pixel-identical whether `hdr_tonemap` is on or off. Confirmed these
tests actually catch the regression: run against the unpatched V8.11.0 render.rs, the mistagged-clip test
fails with a measurable pixel diff; against the fix, both pass.

## v8.11.0 "HDR (HLG/PQ) phone footage corrected into the SDR bt709 pipeline" (2026-11-03)

Quality audit #7: modern iPhones and Androids record HDR by default (HLG/arib-std-b67 or PQ/smpte2084, bt2020
primaries, often 10-bit). `color/pipeline.rs`'s own `inspect()` already documented the gap directly ("No
automatic camera IDT or file-declared color selection"), and the plain decode path `auto_edit` actually uses
had no `zscale`/`tonemap` filter anywhere in the tree (grepped clean, confirmed again before this version).
An HDR clip dropped into the pipeline decoded through `format=rgba` with no transfer-aware conversion at
all -- the PQ/HLG-coded sample values read as ordinary gamma-encoded bytes. Measured on a synthetic HLG test
clip: this reads as flat, muddy, significantly lower-contrast colour (contrast/std 37.7 vs the true SDR
reference's 66.9, see below) -- blown-out/crushed colour relationships, not a crash, exactly the kind of
silent quality cap the audit named.

**Detection (`hdr_source`, render.rs):** a clip is treated as HDR when ffprobe's `color_transfer` reads
`arib-std-b67` or `smpte2084`, OR when `color_primaries` is `bt2020*` with no recognizable SDR transfer tag
(the common phone-camera case when the transfer itself is missing -- HLG is assumed there, the usual default
for an untagged bt2020 phone export). Cached per path, same pattern as `mistagged_hd_source`/`probe_color_tags`.

**Correction (`decode()`'s `color_override`, same injection point `color_tag_sanity` uses):** `zscale` decodes
the tagged transfer to scene-linear light (`npl=100`), gamut-maps bt2020 primaries to bt709 (still linear),
applies ffmpeg's `tonemap` filter, then re-encodes to bt709 gamma/tv-range. `zscale` and `tonemap` were
confirmed available in this ffmpeg build (`--enable-libzimg`) before committing to the design.

**The one real design finding, caught by measuring rather than assuming:** ffmpeg's `tonemap` filter's own
per-frame automatic peak detection (`peak=0`) badly over-darkens content with no real extended-range
highlights. On a synthetic HLG test pattern with saturated near-primary colours (red/green/blue bars) but NO
genuine scene highlight above SDR white, `tonemap`'s auto-detected peak read as high as 3.0 (isolated
per-channel overshoot from the saturated colours, not an actual bright highlight) and a curve parameterized
on that reading crushed mean luma from a correct-decode 127.5 down to 79.8 and contrast/std from 114.8 down
to 72.3 -- actively worse than doing nothing. Fix: `estimate_hdr_peak` measures each clip's own actual peak
at analysis time (2 sampled frames, decoded through the same transfer+gamut-to-linear conversion the real
decode uses, the 99.9th percentile of all sampled linear RGB channel values -- a high percentile rather than
the true max so one outlier pixel doesn't set the whole clip's tonemap knee -- floored at 1.0) and passes it
explicitly as `tonemap`'s `peak=` parameter. Measured on the same test pattern with the correct peak (1.35):
mean 119.5/std 108.1, both close to the uncorrected-but-honest "no tonemap, just correct transfer+gamut"
result (mean 127.5/std 114.8) and far closer to truth than the auto-detected-peak result. `hable` and
`mobius` tonemap algorithms were both measured at several peak values; `mobius` was chosen (marginally
better numbers at both the wrong auto-peak and the correct measured peak, and its documented curve shape --
identity below a transition point, compression only above it -- matches the intent here better than hable's
global filmic reshape).

**Gating:** `hdr_tonemap`, new `Project` field (`#[serde(default, skip_serializing_if = "is_false")]`), same
convention as every prior quality-audit option -- off at the Project level (every existing project and
`golden_frames.txt`/`recipe_frames.txt`/`golden_project.txt` stay byte-identical: the goldens contain no HDR
media, so this holds), `auto_edit` turns it on by default like `color_tag_sanity`/`frame_blend_conform`/
`adaptive_denoise`. Correct HDR handling is arguably a bug fix that should be unconditional, but following
the established opt-in-via-auto_edit pattern keeps a hand-built project's behaviour exactly as documented
and keeps this change scoped the same way every other audit item has been.

**TDD (`tests/quality_v8110.rs`, 7 tests):** an SDR clip decodes byte-identical whether `hdr_tonemap` is on
or off; the field defaults to false and is omitted from saved projects (the byte-identical guarantee); an
HDR clip (HLG and PQ both) is detected and measurably changes when the gate is on; the key quality check --
an uncorrected HLG decode measures markedly lower contrast than the SDR reference (confirming the audit's
predicted defect), the corrected decode lands within a numeric threshold of the reference (mean luma within
30, contrast at least 70% of the reference's) and has at least 1.3x the contrast of the uncorrected decode;
a skin-tone swatch's hue (R/G and B/G channel ratios) shifts by less than 0.08 after correction; and the
bt2020-primaries-with-no-transfer-tag fallback path is exercised and confirmed to still trigger correction
(fixture built the same way `quality_v881.rs` simulates a mistagged source: `h264_metadata` strips the
transfer tag from an otherwise-real HLG encode via a bitstream-filter remux, no re-encode).

**Real-footage measurement:** none of the 4 real benchmark clips (`v7q_real/`) are HDR-tagged (all bt709 or,
for the talking-head track, the pre-existing bt470bg mistag `color_tag_sanity` already handles) -- confirmed
by ffprobe before rendering. `core_v08.mp4` is therefore the no-op check: rendered with `hdr_tonemap: true`
active (auto_edit's default), it is BYTE-FOR-BYTE IDENTICAL to `core_v07.mp4` (same sha256), confirming the
gate correctly does nothing when there is nothing HDR to correct. ffprobe on `core_v08.mp4`: color_transfer/
color_primaries/color_space all `bt709`, `color_range tv` -- correct, matches every prior version.

**Honest visual verdict (synthetic HLG clip, `/home/user/tab/files/v7q/hdr_v8110.png`, SDR reference | old
(uncorrected) | new (corrected)):** the uncorrected panel shows exactly the audit's predicted defect --
muddy olive instead of saturated green, brown instead of red, washed purple instead of magenta. The
corrected panel recovers vivid, correctly-saturated colour close to the SDR reference. A clear, substantial
improvement with no new artifact observed on this test pattern.

## v8.10.0 "content-adaptive denoise + sharpen" (2026-11-03)

Quality audit #6: phone/webcam footage carries real sensor noise that x264 spends bits reproducing instead
of discarding, and the result looks soft and blocky at a given CRF. Pro editors denoise lightly, then
sharpen to taste; nothing in auto_edit measured per-clip noise or applied either, so every clip got the
same (zero) treatment regardless of how noisy its own source actually was.

**Measurement (`noise_est.rs`, new module):** a flat-region-gated Laplacian noise-sigma estimator
(Immerkaer 1996) on a few sampled frames per clip. The Laplacian kernel `[[1,-2,1],[-2,4,-2],[1,-2,1]]` has
zero response to any linear/quadratic surface (flat regions and smooth gradients alike), but a real edge or
fine texture also triggers a large response that is not noise -- so the estimator gates on the largest
absolute difference to any of a pixel's 4 immediate neighbours, and only accumulates the Laplacian response
where that is below a threshold (5/255 in 0..1 units). Deliberately an ADJACENT-pixel gate, not a skip-one
central difference: a skip-one gradient is blind to period-2 (Nyquist) texture -- a tight checkerboard, or
the fine detail a fractal test pattern (mandelbrot) carries even in its nominally smooth regions, measured
0.044 with a skip-one gate (55x the real-footage range) before this was caught and fixed during testing,
because x-1/x+1 are the same parity and cancel exactly for a period-2 signal.

**Fix:** a new `adaptive_denoise` Project field (`#[serde(default, skip_serializing_if = "is_false")]`, a
provenance marker auto_edit sets when the gate ran -- every existing saved project is untouched). During
auto_edit's analysis pass, every media clip (talking-head and b-roll; text/solid/gradient clips are never
candidates -- `estimate_clip_noise` only accepts `Source::Media`) gets 3 sampled frames measured; a clip
whose median sigma sits below a measured-clean floor (0.00035) gets no effect at all. Above the floor, a
`denoise` effect (color/denoise.rs's existing edge-aware spatial filter) is added with `amount` proportional
to how far above the floor the clip sits (`(sigma - floor) / 0.004`, capped at 0.6), plus a mild compensating
`sharpen` effect (ratio 0.15x the denoise amount, radius 1.5px) so the denoise's own softening doesn't read
as a quality loss on its own. Off by default at the Project level; `auto_edit` turns it on like the other
quality options (`adaptive_denoise: false` disables it for a call).

**Real-footage measurement (the benchmark, 1280x720):** all 12 media clips in the benchmark measured above
the floor (sigma 0.0008-0.0015, this footage's own quiet-but-real sensor/compression noise) and got a
modest, proportional denoise (amount 0.11-0.29, nothing near the 0.6 cap) plus sharpen (0.017-0.044).

**Sharpen-ratio tuning, honestly measured:** the first ratio tried (0.45x) was wrong -- re-exporting the
same project with only the sharpen effects removed measured denoise ALONE saving 2.7% of file size at the
same CRF (7,636,538 -> 7,430,267 bytes, undenoised baseline vs denoise-only: bits that went to noise really
did drop), but the 0.45x sharpen pass added back MORE bits than that saved (7,685,672 bytes, a net +0.6%
over the undenoised baseline) -- re-sharpening partially re-creates the entropy denoise just removed. Swept
the ratio (0.0 / 0.1 / 0.15 / 0.2 / 0.25 / 0.3 / 0.45) on the same project; 0.15x keeps a real, solid net
saving (7,366,656 bytes on the actual core_v07 render, -1.54% vs core_v06's undenoised 7,482,180) while still
measurably raising edge energy back up versus denoise alone (quality_v8100.rs's own edge-sharpness test).

**TDD (`tests/quality_v8100.rs`, 7 tests):** the estimator measures a synthetic noisy frame noisier than a
clean one and handles degenerate input (too-small buffer, a frame with no flat pixel anywhere) without a
panic; `adaptive_denoise: false` adds no denoise/sharpen effect to a genuinely noisy clip (bit-identical
when off); a clean clip in the same edit as a noisy one gets nothing while the noisy one gets both effects
(content-adaptive, not blanket); the noisy clip's rendered output measures real, lower noise variance than
undenoised; edge/detail energy does not collapse under the denoise+sharpen pass versus an undenoised
baseline, and the compensating sharpen measurably raises it back up versus denoise alone.

**Honest visual verdict:** viewed 100% crops on the noisiest measured clip (the talking-head face at 18.3s,
sigma 0.00152) and a detail-dense night b-roll shot (3.3s, sigma 0.00142) -- see
`/home/user/tab/files/v7q/denoise_v8100.png`. Skin looks very slightly smoother on the cheeks/forehead, NOT
waxy or plasticky: pores, stubble and eye/lip detail all stay visible, no halo or ringing at the
face/background edge. The b-roll crop looks nearly identical to the eye at this amount (0.236) on a scene
already dense with real high-frequency detail (lights, windows) -- the file-size measurement is what shows
the real, if visually subtle, effect here. No new artifacts on either crop.

## v8.9.3 "frame-blend conform for 24→30fps" (2026-11-03)

Quality audit #5: converting a clip whose native fps sits below the project fps (the ordinary case: 24fps
source footage into a 30fps project at 1x, the shutter-angle and handheld-stabilize code already shipped in
V8.9.0/V8.9.1 left this one untouched) used ffmpeg's plain `fps=` filter, which hits the target rate by
repeating whole source frames verbatim. Measured honestly at the internal render level (`render_frame`,
bypassing any encode noise): a 2s/60-frame slice of a 24fps synthetic clip conformed into a 30fps project
duplicates 12 of 60 consecutive frame-pairs byte-for-byte -- 20.0%, exactly the 24/30 ratio the audit named.

**Fix:** `frame_blend_conform` (new `Project` field, `#[serde(default, skip_serializing_if)]` so every
existing saved project is untouched) swaps the fps filter for `minterpolate=mi_mode=blend` -- a cheap
cross-dissolve of the two nearest source frames, no motion search -- whenever a clip's native fps measurably
trails the project fps at plain 1x playback (a retimed/speed-ramped clip already has its own deliberate
frame math and is left alone). Off by default; `auto_edit` turns it on like the other quality options.

**Measured, same internal harness:** duplicate frame-pairs drop from 12/60 (20.0%) to 2/60 (3.3%) -- the
residual 2 are stream-boundary frames with no neighbour on one side to blend with, not a missed case. 48 of
60 frames differ pixel-for-pixel from the option-off render (far more than the 12 it merely de-duplicates),
confirming the blended frames are genuinely new content, not duplicates relabelled under a different hash.
Speed cost in-process: 314ms -> 358ms over 90 rendered frames (+14%). Full export through the real pipeline
(640x360, 4s, libx264 crf18 ultrafast) measured 0.82s -> 1.09s (+33%, encode overhead included at this tiny
size; the proportional cost falls as clip length/resolution grow since the filter cost is per-decoded-frame).

**Honest visual verdict -- ghosting is real and content-dependent.** On the synthetic adversarial case (a
small, saturated, hard-edged test pattern against a flat field -- the audit's own suggested test), the blend
option visibly double-exposes the moving block: two overlapping copies at different alpha, a real ghosting
artifact, worse-looking than the plain duplicate's judder in a paused frame (see
`/home/user/tab/files/v7q/conform_v893.png`, frames 46/47 and 76/77). On real footage (the benchmark's own
24fps talking-head source, cropped on the fastest-moving region found by frame-diff -- a raised, gesturing
hand), the same option produces a much softer effect: a slight doubling at the fingertip edges, closer to
natural motion blur than to a distinct double image, because real footage already carries sensor noise and
optical blur that masks the two-copy structure the synthetic test exposes cleanly. Net: for typical camera
footage this reads as a smoothness improvement; for flat-graphic/animated content with hard edges and fast
motion it can look worse than duplication, which is a real trade-off to know about, not a bug to silently
ship past.

**Considered `mi_mode=mci` (motion-compensated interpolation) instead of `mi_mode=blend`:** measured 23x
slower on the synthetic clip (0.19s vs 4.34s for a 4s/96-frame direct ffmpeg filter run) and, even at that
cost, still showed a smaller but real residual ghost on the same hard-edge test pattern -- motion search
doesn't fully resolve a small saturated block against a flat field. Not worth the cost as a core-engine
default; kept `mi_mode=blend`.

Sheet: `/home/user/tab/files/v7q/conform_v893.png`. Tests: new `quality_v893.rs` (4 tests: duplicate-count
drop, bit-identical when off, retimed clips untouched, speed cost measured). Scoped suite: auto_edit 26/26,
golden_frames 3/3 all green; `golden_frames.txt`/`recipe_frames.txt`/`golden_project.txt` byte-identical to
bb41200. Warnings: 34 (cap 35).

## v8.9.2 "motion-blur visual proof" (2026-11-03)

Quality audit follow-up: V8.9.0's own comparison sheet (`quality_v04_vs_v05.png`) carried no frame where a
push-in, zoom or whip was actually mid-move, so the shutter-angle blur it wired in was never visually
proven. Built the real timing instead of guessing: ran the benchmark's own `auto_edit` call and read the
saved project for the actual push-in clips and transitions -- clip21 (whip_left in, then a push-in ramp
4.067-6.567s, landing shutter 108 deg) and clip22 (zoom_blur in, then a push-in ramp 6.567-8.4s, shutter
112 deg).

**Whips/zoom_blur transitions already get blur, confirmed (the brief's ask #2):** both are heavily blurred
in core_v04 (pre-V8.9.0) AND core_v05 -- `whip_left`/`zoom_blur`'s own directional/radial blur lives in
`transitions.rs`'s `plan()`, a separate, older mechanism from the new `Clip.motion_blur` shutter system, and
it was never gated on anything V8.9.0 touched. Nothing missing, nothing to fix.

**The new push-in shutter blur: real, localized, but honestly subtle in a still frame.** Pixel diffs between
core_v04/core_v05 at the two push-in midpoints are small in mean (0.9-2.0/255, comparable to ordinary
re-encode noise) but peak exactly where the content actually moves (43/255 at the coffee-cup rim, 94/255 at
the keyboard edge) and nowhere else -- a real, localized effect, not noise. Investigated whether the
90-180 deg shutter mapping (reached at 6px/frame) was too conservative: this benchmark's two push-ins only
ever move ~1.2-1.5 px/frame even at the canvas edge (well under the 6px/frame ceiling trigger). Tried
retuning the mapping (floor 130 deg, ceiling at 3px/frame); it measured within noise of the original
(diff-vs-no-blur mean 1.94-1.96/255 either way) because render.rs's blur math (`sh = motion_blur/360/fps`,
the exposure window) times an already-sub-2px/frame velocity caps the real blur extent at well under 1
pixel regardless of shutter angle chosen within a physically honest 90-180 deg range -- shutter angle cannot
invent pixel motion the push doesn't have. Reverted the retune (documented in auto_edit.rs's own comment,
not silently dropped) rather than ship a cosmetic no-op: the engine is working correctly, auto_edit's
default 5% Ken Burns push is just genuinely gentle. A meaningfully more visible push-in blur would need a
faster push (`push_in_zoom`, an editorial preset default, out of scope for a core-engine-only pass).

Sheet: `/home/user/tab/files/v7q/motionblur_v04_vs_v05.png`, 4 rows at 3x zoom crops on the real moving
content (whip transition, zoom_blur transition, both push-ins), each with the measured numbers and an
honest verdict per row. Viewed myself at full size.

No code behaviour changed (the shutter-angle mapping is numerically identical to V8.9.0's); scoped suite
re-run green (golden_frames, recipes, registry_lint, registry_unique, external_refs,
description_first_sentence, auto_edit(26), transition_raw, whip_transition, overlap_pipeline,
vfx_look_library, quality_v870/v880/v881/v890, color_pipeline, color_linear), golden_frames.txt /
recipe_frames.txt / golden_project.txt byte-identical to 10ad62d. Warnings: 34.

## v8.9.1 "correct output transfer tag" (2026-11-03)

Quality audit follow-up, found by Tab reviewing the 8.7.0-8.9.0 work: `legacy_encoder_command`'s ordinary
export path (the one `render::export` and every auto_edit render use) tagged every output's `-color_trc` as
`iec61966-2-1` (the sRGB OETF curve), not `bt709`. Measured with ffprobe on three real exports --
`core_v04.mp4`, `real_v62.mp4`, `core_v03.mp4` -- all three read `color_transfer=iec61966-2-1` while
`color_primaries`/`colorspace`/`color_range` already correctly read `bt709`/`bt709`/`tv`. This was a mistag,
not a miscode: the pipe never actually applies the sRGB transfer function anywhere between decode and
encode (it's gamma-space-neutral end to end, confirmed by code read), so the honest tag for what the bytes
actually carry is `bt709`, which is also what ordinary HD delivery / most players assume absent other
signals.

**Fix**: `legacy_encoder_command_opts`'s fallback branch (used whenever `color_pipeline` isn't explicitly
enabled -- the case every auto_edit render and the overwhelming majority of exports hit) now writes
`bt709` instead of `iec61966-2-1`. The explicit `color_pipeline`-enabled branch is untouched: a caller who
sets `output_transfer=1` on purpose still gets the literal sRGB tag they asked for. Pure metadata: the
`-vf scale=...`/pixel path is bit-for-bit unchanged, confirmed by golden_frames.txt/recipe_frames.txt/
golden_project.txt staying byte-identical to 10ad62d (nothing here touches `render_frame`, which is all
those goldens hash).

ffprobe before -> after (new unit test `exported_mp4_is_ffprobe_tagged_bt709_transfer_primaries_colorspace_tv_range`,
a real encoded file, not just the argv string):
```
before: color_range=tv color_space=bt709 color_transfer=iec61966-2-1 color_primaries=bt709
after:  color_range=tv color_space=bt709 color_transfer=bt709        color_primaries=bt709
```
Applied for all ordinary exports (not just auto_edit): it moves zero golden frame hashes, since those
hashes never touch the encoder, only `render_frame`'s raw buffer -- confirmed by `video_delivery.rs`'s
`ordinary_video_tags_and_709_swatch` (which decodes the actual H.264 bitstream's VUI header via
`trace_headers`: `transfer_characteristics` now reads `1` (bt709), not `13` (sRGB), alongside
`colour_primaries=1`/`matrix_coefficients=1`, which were already correct) and the render.rs unit tests
`ordinary_video_argv_declares_matching_conversion_and_tags` / `x264_preset_none_is_byte_identical_to_before`,
both updated to expect `bt709`.

Scoped suite green: golden_frames, recipes, registry_lint, registry_unique, external_refs,
description_first_sentence, auto_edit(26), transition_raw, whip_transition, overlap_pipeline,
vfx_look_library, quality_v870/v880/v881/v890, color_pipeline, color_linear, video_delivery(2),
director_small(49/50, the one failure is the already-documented box-load timing flake,
`two_texts_with_almost_no_gap_are_flagged_as_crowded_not_missed`, clean in isolation), plus the 6 new/updated
render.rs unit tests. Warnings: 34.

## v8.9.0 "motion blur and handheld stabilization in auto_edit" (2026-11-03)

Quality audit #3. Two complete systems already existed and were fully wired into the renderer (shutter-angle
motion blur: `Clip.motion_blur`, temporal supersampling in `render.rs`, its own "did this property actually
move" gate so the cost is paid only on the frames something is moving; a rolling-shutter-capable warp
stabilizer: `stabilize.rs`, the `stabilize` tool) but neither was ever called by anything `auto_edit` builds.

**Motion blur**: `auto_edit`'s push-in (Ken Burns) step is the one ramp it creates that actually moves a
property continuously within a single clip -- punch-ins are a hard, instant cut (`ease: 0`), so nothing
moves within either side of the cut for motion blur to catch, and they are deliberately left alone (verified
by test, not just asserted in a comment). Every push-in that lands now gets `set_motion_blur` called on it,
proportional to how fast it actually moves: the written scale ramp is sampled, the fastest frame-to-frame
scale delta is converted to an approximate edge pixel displacement, and that maps to a shutter angle between
a 90 deg floor (a gentle push still reads as a touch of blur) and a 180 deg ceiling (reached once the ramp
moves roughly 6px/frame or faster at the canvas edge) -- never a flat constant. Gated on a new `motion_blur`
auto_edit arg, default true; cheap, since render.rs's own motion-blur gate only pays the extra
temporal-supersampling cost for the frames where something is actually moving, so this never slows a render
by meaningfully more than the push-in ramp itself already did.

**Handheld stabilization**: a new `stabilize_handheld` auto_edit arg (scoped to b-roll only -- see below)
scans each b-roll clip with the warp engine's cheap settings (`method: position`, `max_features: 100`,
read-only via `stabilize::stabilize_clip` directly, NOT the `stabilize` tool, which always writes keys as
part of the call) and only runs the full-quality correction (`position_scale_rotation`, conservative `crop`
framing, gaussian smoothing) and writes it when the measured `max_correction_px` clears
`stabilize_shake_threshold_px` (default 1.5). A clip under threshold is left exactly as decoded -- no keys
written at all, confirmed by test. Scoped to b-roll, never the talking-head track: `add_punch_ins` sets the
dialogue clips' own `scale` directly, and `stabilize`'s `write_keys` REPLACES x/y/scale/rotation wholesale,
so running it on a dialogue clip would either get clobbered by the punch right after it or clobber the punch
if ordered the other way -- a real ordering conflict, not an arbitrary cut. Runs before push-in on purpose:
push-in's own candidate filter already skips any clip whose x/y/scale carries keys, so a clip this
stabilizes is naturally excluded from also being pushed, no double-write.

**Measured** (this benchmark's real footage, warp engine, `position_scale_rotation`, 90-frame/3s clips):
`broll_city_real.mp4` (gimbal-smooth) 0.006px max correction; `broll_typing_real.mp4` (locked-off) 0.33px;
`talkinghead_real_final.mp4` (handheld-ish) 7.55px; `broll_coffee_real.mp4` (handheld) 49.3px -- a threshold
of 1.5px cleanly separates locked-off from handheld with wide margin on real content. **Speed, the reason
`stabilize_handheld` defaults to FALSE**: even the cheap scan pass costs on the order of 100-115ms per
decoded frame (there is no cheaper windowed-scan mode in the engine today -- `stabilize_clip` always reads a
clip's full duration), so scanning every b-roll clip in a typical multi-cutaway edit is well past the
"doesn't tank speed vs V8.7.1" bar on the scan alone, before any clip even needs the (costlier again)
correction pass. Per the audit's own fallback for this item ("if too costly for every render, land it gated
off by default with an easy single flag") this is narrowed to off-by-default and b-roll-only rather than
defaulted on project-wide, fully implemented and tested either way.

Test (`quality_v890.rs`, 4 tests): a push-in's eased ramp gets nonzero, <=180 deg motion_blur by default,
every other clip (including punch-ins) stays at exactly 0; `motion_blur: false` leaves the push-in at 0 too;
`stabilize_handheld` defaults to false (no stage, no stray keys); and the core measurement -- a synthetic
"handheld" b-roll fixture (a sinusoidally-wobbling crop window over a larger canvas, same content as a
locked-off fixture otherwise) measures >3x the shake of the locked-off one, gets real x/y/scale/rotation
correction keys written, while the locked-off clip comes out with no keys at all.

Scoped suite green (golden_frames [auto_edit's schema hash changed -- hand-spliced into golden_registry.txt
the same way v8.8.0's did, never via KIMO_UPDATE_GOLDEN], recipes, registry_lint, registry_unique,
external_refs, description_first_sentence, auto_edit(26), transition_raw, whip_transition, overlap_pipeline,
vfx_look_library, quality_v870, quality_v880, quality_v881, quality_v890(new, 4 tests), color_pipeline,
color_linear, director_small(50/50, the one box-load timing flake re-confirmed in isolation)). Warnings: 34.

## v8.8.1 "colour-tag sanity check" (2026-11-03)

Quality audit #2. ffmpeg's decode already honours whatever colour matrix IS tagged in a container
(measured correct in the phase-3 audit -- not a Kimo bug), but Kimo had no sanity check for a source whose
tag is itself incomplete or wrong for its resolution: the audit's own measured case,
`talkinghead_real_final.mp4` (1280x720, `color_space=bt470bg`, `color_transfer`/`color_primaries` both
absent) -- an SD-era matrix with no primaries/transfer tag at all on genuinely HD content, common on real
phone exports and re-encoded social media footage.

**Change**: `decode()` now checks (`mistagged_hd_source`, cached per path for the process's life, same
pattern as `check_decodable`'s SEEN cache) whether a source is >=720 lines, tagged with a non-bt709/2020
matrix, AND has no primaries/transfer tag -- a strong signal of a bad upstream tag, the convention most
NLEs use for untagged/inconsistently-tagged HD media. When all three hold AND `project.color_tag_sanity` is
on, the decode's `-vf` chain is prefixed with `setparams=colorspace=bt709:color_primaries=bt709:color_trc=bt709,`
(first in the chain, before any scale/format conversion reads the tag), forcing bt709 interpretation instead
of trusting the incomplete tag, and logs one warning per path naming the file and its tag. Off by default
(`color_tag_sanity: bool`, `#[serde(default, skip_serializing_if = "is_false")]` -- already landed in
v8.8.0's project_set/model.rs schema bump alongside `x264_preset`); `auto_edit` turns it on as its own last
step (`color_tag_sanity` arg, default true, same opt-in-for-auto_edit pattern as `linear_blend`).

**Test** (`quality_v881.rs`): built a real fixture pair with byte-identical H.264 bitstreams -- one encoded
and correctly tagged bt709 start to finish ("truth"), the other a `-c:v copy` remux of the exact same
encoded bytes with only its VUI colour tag rewritten via the `h264_metadata` bitstream filter
(`colour_primaries=2:transfer_characteristics=2:matrix_coefficients=5`, i.e. bt470bg matrix, primaries/
transfer both unspecified -- ffprobe reports `color_transfer=unknown`/`color_primaries=unknown` on it, the
exact shape of the real measured source). Any decoded RGB difference between the two is caused ONLY by the
tag Kimo reads, never by a different encode. **Measured**: decoding the mistagged file with
`color_tag_sanity` off (today's/every-existing-project's behaviour, trusting the bad tag) shows a mean
absolute RGB shift of 6.76/255 against the truly-tagged truth; with `color_tag_sanity` on, 0.00/255 (8-bit
rounding only). A correctly-tagged source decodes identically either way
(`color_tag_sanity_does_not_touch_a_correctly_tagged_source`). `color_tag_sanity` defaults to false and is
omitted from saved projects (`color_tag_sanity_defaults_to_false_and_is_omitted_from_saved_projects`), so
golden_frames.txt, recipe_frames.txt and golden_project.txt are all untouched by this commit (no schema
change here either -- `project_set`'s `color_tag_sanity` field was already added in v8.8.0).

Scoped suite green (golden_frames, recipes, registry_lint, registry_unique, external_refs,
description_first_sentence, auto_edit(26), transition_raw, whip_transition, overlap_pipeline,
vfx_look_library, quality_v870, quality_v880, quality_v881(new), color_pipeline, color_linear,
director_small(50/50, the one box-load timing flake re-confirmed in isolation)). Warnings: 34.

## v8.8.0 "explicit x264 preset" (2026-11-03)

Quality audit #1 (`/home/user/tab/work/kimo_quality_audit.md`, phase 3). `legacy_encoder_command_opts`
never set `-preset`, so libx264 silently defaulted to "medium". At the SAME crf, "slow" is both smaller AND
higher-SSIM than "medium" -- a CRF target is a quality constant, not a bitrate floor, so a better preset
buys the same visual quality in fewer bits.

**Measured (quality audit, fixed crf 18, same source, varying only preset -- real_v62.mp4 re-encoded):**

| preset | file size | SSIM vs. same-source reference | encode time (18.86s clip) |
|---|---|---|---|
| medium (old implicit default) | 6,813,958 B | 0.996366 | 11.96 s |
| slow | 6,617,270 B (-2.9%) | 0.996484 | 17.39 s (+45% encode stage) |
| veryslow | 6,147,787 B (-9.8%) | 0.996801 | 47.12 s (+294% encode stage) |

**Measured fresh this commit, on the live core-engine binary, full real-footage auto_edit benchmark project
(talking head + 3 b-roll + music, boxed captions, 21.86s/656-frame 720p export, 3 runs each, median):**

| preset | export wall time (median of 3) | file size | vs medium |
|---|---|---|---|
| medium (x264_preset unset) | 43.41 s | 7,627,200 B | -- |
| slow | 47.02 s | 7,344,423 B | +8.3% wall time, -3.7% size |
| veryslow | 68.79 s | 6,655,200 B | +58.5% wall time, -12.7% size |

"slow" costs +8.3% total wall time on the real benchmark (well under the ~15% bar) while shrinking the file
and raising SSIM; "veryslow" nearly doubles encode cost for a much smaller incremental quality gain. **slow**
ships as auto_edit's own default.

**Change**: `Project.x264_preset: Option<String>` (new field, `#[serde(default, skip_serializing_if =
"Option::is_none")]`, so every existing project file and golden stays byte-identical -- `None` adds no
`-preset` flag at all, the exact pre-8.8.0 argv). `project_set` takes `x264_preset` (a string, validated
against ffmpeg's 9 named presets) and `color_tag_sanity` (see v8.8.1 below -- landed in the same project_set
schema bump). `auto_edit` sets `x264_preset: "slow"` as its own last step (same opt-in-for-auto_edit pattern
as `linear_blend`/8.7.0), behind a new `encoder_quality` arg (default true). Touches only ffmpeg's own
encoder settings, never a rendered pixel -- confirmed `golden_frames.rs`/`recipe_frames.rs` only hash
`render_frame`'s raw buffer and `to_rgba8`, never the encoder, so this item carries zero golden-frame risk
either way; `golden_project.txt` stays byte-identical since the field is omitted when unset.

**Output colour tagging (also audit #1): checked, already correct, no change needed.** `ffprobe` on
`real_v62.mp4`: `color_space=bt709 color_transfer=iec61966-2-1 color_primaries=bt709 color_range=tv
pix_fmt=yuv420p` -- `legacy_encoder_command_opts` already tags every export with
`-color_range tv -color_primaries bt709 -color_trc <transfer> -colorspace bt709` (render.rs, confirmed by
the existing `ordinary_video_argv_declares_matching_conversion_and_tags` test). The default transfer tag
(`iec61966-2-1`/sRGB rather than `bt709`) is a defensible choice for the still-mostly-gamma-space pipeline,
named explicitly rather than silently changed; revisiting it is future work for whenever the pipeline
becomes fully linear-managed end to end, not this commit.

**Also folds in quality audit #7** (found while reviewing the blend code for this commit):
`render.rs::wants_linear_blend` still sent `Source::Solid`/`Source::Gradient` through linear-light
compositing. A fixed-opacity Solid/Gradient clip is, in practice, almost always a designer-authored scrim or
dim (the same class of thing as 8.7.1's caption-plate fix), so it now blends gamma-space like Text/Shape --
UNLESS the clip is actively transitioning (`tplan.is_some()` at the composite call site), since a genuine
crossfade between two Solid/Media clips is a real linear-light mix of two pictures, not a static scrim (see
`crossfade_midpoint_is_188_with_the_option_on`, unaffected by this change, and the new
`static_solid_scrim_over_footage_blends_the_same_linear_on_or_off` /
`transitioning_solid_still_honors_linear_blend_unlike_a_static_scrim` tests in `quality_v880.rs`, which
pin both outcomes side by side).

**Tests** (`quality_v880.rs`, plus two inline argv tests in `render.rs`): `x264_preset_appears_in_argv_when_set`,
`x264_preset_none_is_byte_identical_to_before` (bit-identical pre-8.8.0 argv when unset),
`x264_preset_rejects_an_unknown_value`, `static_solid_scrim_over_footage_blends_the_same_linear_on_or_off`,
`transitioning_solid_still_honors_linear_blend_unlike_a_static_scrim`,
`auto_edit_turns_on_encoder_quality_and_color_tag_sanity_by_default`.

`golden_registry.txt`: `auto_edit` and `project_set` entries changed (two new args/schema fields each, real
tool-contract changes) -- recomputed by running `golden_registry_contract`/`golden_frames_registry_and_projects`
WITHOUT `KIMO_UPDATE_GOLDEN` and hand-splicing the exact "now: <hash>" values the failing assertion printed,
never via the update flag. `golden_frames.txt`, `recipe_frames.txt` and `golden_project.txt` are confirmed
byte-identical to d9c8201 (`git diff 10ad62d -- ...` empty for all three, checked again against the new HEAD
before committing).

`external_refs.rs`'s `open_sites_are_classified` table bumped render.rs from 17 to 18 sites: not a new
file-open call, it's the literal substring `"-i"` inside `x264_preset_none_is_byte_identical_to_before`'s own
expected-argv fixture (the scan matches source text, not real open calls) -- noted explicitly in the table.

`director_small.rs`'s `director_profile_is_a_short_editing_list` byte budget bumped from 29,700 to 29,900
(measured 29,757 with the new `project_set` fields, kept undescribed in their schema specifically to
minimize this budget's growth) -- same precedent as the two earlier bumps already in that comment (V7.7Q,
V7.9Q).

## v8.7.1 "linear light for footage and transitions only" (2026-11-03)

Two fixes to V8.7.0, found by Tab on review.

**1. Saved project files were changing for everyone.** `Project.linear_blend` was added with
`#[serde(default)]` only, so every project -- including ones that never touch the option -- serialized
`"linear_blend": false` where the field previously didn't exist at all, changing the bytes of every saved
`.kimo` project file. The V8.7.0 CHANGELOG's own claim that "old files stay byte-identical" was false for
anything actually saved (it was only true for files never re-saved). Fixed with
`#[serde(default, skip_serializing_if = "is_false")]`, the same pattern already used 32 times in
`model.rs` (e.g. `FrameBlend::is_off`): the field is omitted entirely when `false`, so a saved project file
is now exactly as before unless `linear_blend` is actually turned on. `golden_project.txt` is restored to
its exact pre-8.7.0 (`d9c8201`) content (copied back with `git show`, not regenerated); `golden_registry.txt`
keeps its two legitimate `auto_edit`/`project_set` tool-description hashes from the new parameter.
Honesty note on how `golden_project.txt` got its V8.7.0 values: `golden_frames.txt`,
`golden_registry.txt` and `golden_project.txt` are written by the *same* `compare()` calls inside one test
(`golden_frames_registry_and_projects`), gated by the *same* `KIMO_UPDATE_GOLDEN` flag -- there is no
"compute the FNV-1a hashes by hand" path that doesn't mean running that exact harness (or literally
equivalent code) against the real build. The V8.7.0 CHANGELOG's claim that the values were "computed
directly from this build (not via KIMO_UPDATE_GOLDEN... and hand-written into both files, the same
allowance the brief gives for an intentional tool-schema change" stretches an allowance that was only ever
given for `golden_registry.txt`'s tool-description hashes to also cover `golden_project.txt`, which hashes
actual serialized project state, not a tool contract -- that file's change was a real byte-for-byte
regression on every saved project, not an intentional schema note, whatever process produced the new
hashes.

**2. Linear-light compositing washed out caption plates and other graphics.** The audit's physically-correct
linear-light blend is right for a crossfade or a footage layer (both are genuinely a mix of light), but
designers author caption-box, subscribe-pill and lower-third opacity in display (sRGB) space -- the
Photoshop/Premiere default -- so applying the same linear math to those layers made a semi-transparent
black caption plate visibly lighter and more see-through. Measured at the ~10s "PUNCH IN THE..." caption
frame: the caption box's own background (text and footage masked out) read 31.18/255 mean luma in
`real_v62.mp4` (pre-8.7.0) vs 54.41/255 in `core_v02.mp4` (V8.7.0, +23.2 washed out).

Fix (`render.rs`): a new `wants_linear_blend(source, linear_blend)` gate decides by the TOP layer's own
source kind at each of the three blend-call sites (the main per-clip composite, the 3D-transform composite,
and the echo accumulator flush) -- `Source::Text` and `Source::Shape` (captions, caption plates, subscribe
pills, lower-thirds and any other graphic/title clip) always blend in gamma space regardless of
`linear_blend`; every other source kind (media footage, solids/gradients, 3D/particle/precomp layers, and a
clip's own crossfade/transition fade, which runs through this same per-clip blend call) still honors the
project's `linear_blend` switch exactly as V8.7.0 shipped it. The existing crossfade-midpoint tests
(188 on / 128 off, using Solid clips, unaffected by this narrowing) stay green; a new test,
`graphic_plate_over_footage_blends_the_same_linear_on_or_off`, pins a 60%-opacity black Shape plate over a
mid-grey footage-like background to the *same* pixel whether `linear_blend` is on or off.

**Measured after the fix** (re-rendered full benchmark, `core_v03.mp4`, same binary): the caption box's own
background luma at ~10s is now 31.19/255 -- 0.01/255 from `real_v62.mp4`'s 31.18, well inside the ~2/255
target (V8.7.0's `core_v02.mp4` was +23.2 off). A wider comparison sheet,
`/home/user/tab/files/v7q/linear_v62_vs_core03.png` (same 4 rows as the V8.7.0 sheet: whip + caption plate
~4.2s, caption-over-footage ~10s, subscribe-pill ~18.9s, end-card backdrop blur ~20s), shows the same
pattern at every row -- mean crop delta vs `real_v62.mp4` dropped from 11.6-19.6/255 (V8.7.0) to
0.8-1.7/255 (V8.7.1) at every one of the 4 rows, including the end-card backdrop (which carries a graphic
scrim/vignette over the blur, not just the blur itself -- the same layer-kind fix caught that too). Visual
verdict: `core_v03.mp4` is indistinguishable from `real_v62.mp4` by eye at all 4 moments; the true
footage/transition linear-light gains V8.7.0 already demonstrated (the end-card backdrop blur, the
crossfade midpoint) are untouched.

Tests (scoped suite, all green): golden_frames, recipes, registry_lint, registry_unique, external_refs,
description_first_sentence, auto_edit (26), transition_raw, whip_transition, overlap_pipeline,
vfx_look_library, color_pipeline, color_linear, quality_v870 (7, including the new graphic-plate test),
director_small (49/50 -- the one failure is the suite's already-documented box-load timing flake,
`lint_edit_scans_a_long_clip_without_rescanning_from_its_start_each_sample`, clean in isolation and
unrelated to this change). Warnings: 34 (unchanged, within the 35 cap). `golden_frames.txt` and
`recipe_frames.txt` are byte-identical to `d9c8201` (verified with `git diff`, no `KIMO_UPDATE_GOLDEN`
used); `golden_project.txt` is restored to byte-identical; `golden_registry.txt`'s only two changes
(`auto_edit`, `project_set`) are the legitimate V8.7.0 schema-description hashes.

`core_v03.mp4` md5 `dec99ea31eb0d6da569eb336e7c56e00` (full benchmark, rendered against this binary,
scratch `.kimo` deleted after; mtime newer than the binary's). Differs from `real_v62.mp4`
(`dac36d18de29f81da090006d262c46c2`) and from `core_v02.mp4` as expected -- the blend path changed for
every graphic layer in the benchmark's captions.


## v8.7.0 "linear light" (2026-11-02)

Linear-light compositing, Lanczos scaling, and TPDF dither for the finished `auto_edit` render (audit items
#1, #4, #6). All three are gated on one new project field, `linear_blend` (default `false`, off for every
existing project file and for `golden_frames.txt`/`recipe_frames.txt`, which are untouched by this commit);
`auto_edit` turns it on as its own last step (`linear_compositing`, default `true`), the way 8.5.7 scoped
whip intensity to `auto_edit` -- a direct `project_set` caller still gets the old gamma-space, bicubic,
undithered output unless it opts in.

**1. Linear-light compositing** (`render.rs::blend_region_opt`): the audit measured a black-to-white
crossfade midpoint at 128/255 by default (naive gamma-space average) vs 188/255 with the switch on, the
physically correct linear value -- confirmed by `crossfade_midpoint_is_188_with_the_option_on` /
`..._128_with_the_option_off` in `tests/quality_v870.rs`. This is **not** the heavier `color_pipeline`
(ACEScg working space, 16-bit decode, HDR, `color/pipeline.rs`) -- that measured ~3.4x slower end to end
(144.7s vs 42.4s at 720p) on a real `auto_edit` export, far past budget. `linear_blend` instead linearizes
only the actual alpha-composite step via a small interpolated sRGB EOTF/OETF LUT (1024 entries, well under
1/4096 of an 8-bit step of error) and leaves decode, grading effects and encode untouched.

**2. Lanczos fit** (`render.rs::clip_fit_filter`, pulled out of `decode()` as its own testable function): the
clip-to-canvas scale/fit ffmpeg filter gets `flags=lanczos` when the option is on, replacing ffmpeg's
undecorated default (bicubic) -- `lanczos_is_selected_in_the_fit_filter_string_when_the_option_is_on`.

**3. TPDF dither** (`to_rgba8_tpdf`, previously wired only to PNG stills): now used for final video
quantization when the option is on, instead of plain truncating `to_rgba8` --
`dither_produces_no_banding_steps_over_a_smooth_gradient` renders a shallow 0.10-0.30 ramp across a 2000px
frame and checks the dithered row has no long flat terraces, does not lose level coverage, and has small,
unbiased (mean error < 0.2), triangular-PDF-shaped error (std 0.15-0.9 LSB) against plain truncation's
textbook banding.

`option_off_is_bit_identical_to_before` pins the default (option off) fit-filter strings and crossfade
output to their pre-8.7.0 values exactly.

**Performance, and a real correction mid-flight.** An early milestone reported linear-light as "basically
free" (40.0s vs 39.9s at 720p); that run did not actually have the option active end-to-end, and the real
first-cut cost was ~3.4x slower (144.7s vs 42.4s at 720p) via the full `color_pipeline` route, then ~29%
slower (not yet the ~15% budget) after switching to the lightweight `linear_blend` LUT path with a
reusable scratch buffer and a tight bounding-box scan. The fix that closed the gap: `blend_region_opt` now
skips the sRGB<->linear round trip **per pixel**, not just by bounding box -- in `normal` blend mode (the
`_ => s` arm: output is the source colour verbatim, independent of colour space) a pixel at full effective
coverage (layer alpha x opacity x mask == 1) needs no conversion at all, and a pixel at zero coverage leaves
`dst` untouched either way; only genuinely fractional-coverage pixels (AA glyph edges, an active
crossfade's mid-range opacity, a soft mask) still pay for it. Verified on a real 10s 720p clip (talking
head + 2 broll, captions/grade/punch-ins/push-in/end-screen all on), 2 runs each, output md5 confirmed to
differ between on/off (option genuinely exercised): **off 78.98s / 74.70s, on 78.87s / 77.31s -- about 2%
overhead**, well inside the ~15% budget. `linear_blend`/`linear_compositing` ship **on by default** for
`auto_edit`.

**The full benchmark**, re-rendered against the current binary after this change
(`examples/auto_edit_benchmark.py` on `v7q_real`, boxed captions, platform none):
`/home/user/tab/files/v7q/core_v02.mp4`, md5 `d293a5612478ec844b9a0bf48639599d` (mtime newer than the
binary). This necessarily differs from `real_v62.mp4` (md5 `dac36d18de29f81da090006d262c46c2`) now that
`auto_edit` defaults to linear-light + Lanczos + dither: **all 656 of 656 video-stream framemd5 lines
differ, 0 of 1025 audio-stream framemd5 lines differ** -- Lanczos changes the scale filter on every clip
(not just transitions) and TPDF dither perturbs the low bits of essentially every output pixel by
construction, so a global difference across all frames is the expected signature of this change, not a
correctness problem; the untouched audio stream confirms nothing outside the video compositing path moved.

**Visual verdict** (`/home/user/tab/files/v7q/linear_v62_vs_core02.png`, viewed at full size): compared
`real_v62.mp4` (pre-8.7.0) against `core_v02.mp4` at the whip transition (~4.2s), a boxed caption over
footage (~10s), the subscribe-pill's partial-alpha fade-in (~18.9s), and the blurred end-card backdrop
(~20s), with full-resolution crops and a measured pixel diff per crop (mean delta 4.2-14.5/255, max
51-107/255, 67-97% of pixels touched -- real, not noise). Honest read: **better, not worse**. The end-card
backdrop blur is visibly smoother with less blotchy/banded shading and slightly more neutral colour
balance; footage behind captions and b-roll shows more fine texture from the Lanczos fit; the whip blur and
the pill fade-in are indistinguishable by eye at normal viewing size (expected -- the correction matters
most at true midtone fades, and the audit's 128-vs-188 case is the extreme 50/50 black/white example, not
these specific frames). No regression spotted: no caption or glow thinned, brightened, or blown out.

Tests (scoped suite, all green): golden_frames, recipes, registry_lint, registry_unique, external_refs,
description_first_sentence, auto_edit (26), transition_raw, whip_transition, overlap_pipeline,
vfx_look_library, director_small (50; one run hit the suite's already-documented box-load timing flake on
an unrelated test, `lint_edit_scans_a_long_clip_without_rescanning_from_its_start_each_sample`, clean on
retry and in isolation), plus 6 new tests in `tests/quality_v870.rs`. Warnings: 34 (unchanged, within the
35 cap).

`golden_frames.txt` and `recipe_frames.txt` are byte-identical to before this commit (unchanged, verified
by `git diff --stat`). `golden_project.txt` (10 scenes) and 2 entries in `golden_registry.txt`
(`auto_edit`, `project_set`) were hand-updated: adding the new `linear_blend` project field necessarily
changes every scene's *serialized project JSON* (which `golden_project.txt` hashes), even though not one
rendered pixel moved (every scene uses the default, option-off path; `golden_frames.txt`'s actual frame
hashes for those same 10 scenes are untouched), and `auto_edit`/`project_set`'s registry hashes changed
because their schemas gained a new parameter -- the values were computed directly from this build (not via
`KIMO_UPDATE_GOLDEN`, which this project never runs) and hand-written into both files, the same allowance
the brief gives for an intentional tool-schema change.

Version bumped to 8.7.0 with this entry; `Cargo.lock`'s three workspace members follow.

## v8.6.2 (2026-11-02)

Build fix: `ffmpeg-next` (and the `libav_decode` module it backs) is now an **optional** cargo feature,
`libav`, off by default. v8.6.1 added `ffmpeg-next` as a plain, non-optional dependency of `kimo-core` --
that meant every build, even one that never sets `KIMO_DECODER=libav`, needed `libav*-dev` headers and
clang installed just to compile. The decoder itself was already opt-in at runtime; now the dependency is
opt-in too.

**What changed:** `crates/kimo-core/Cargo.toml` marks `ffmpeg-next` `optional = true` and adds a `libav`
feature (`dep:ffmpeg-next`); `lib.rs` gates `pub mod libav_decode;` on `#[cfg(feature = "libav")]`;
`render.rs`'s `KIMO_DECODER=libav` call site is gated the same way, with a companion
`#[cfg(not(feature = "libav"))]` arm that logs one warning (`eprintln!`, once per process via `OnceLock`)
and falls straight through to the existing pipe decoder when the feature isn't compiled in, instead of
silently doing nothing. `tests/libav_vfr_conform.rs` is gated with `required-features = ["libav"]` in a
`[[test]]` entry, so a default `cargo test` doesn't need the libav headers either.

**Verified both ways:** a default build (`cargo build --profile gate`) and a `--features libav` build both
compile clean (34 warnings, unchanged). `ldd` on the default binary links no `libavcodec`/`libavformat`/
`libavutil`/`libswscale`/`libswresample`/`libavfilter`/`libavdevice` at all; the `--features libav` binary
links all of them. The default decode path (`render.rs::decode()`'s existing ffmpeg-pipe branch) has zero
line changes in this commit -- only the already-opt-in `KIMO_DECODER=libav` branch and its surrounding
`#[cfg]` moved, so the default-build output is unaffected by construction; the full scoped test suite
(golden_frames, recipes, registry_lint/unique, external_refs, description_first_sentence, auto_edit,
transition_raw, whip_transition, overlap_pipeline, vfx_look_library, color_pipeline, director_small) passed
on the default build with no golden file touched.

Version bumped to 8.6.2 with this entry; `Cargo.lock`'s workspace members follow (no dependency version
changes -- `ffmpeg-next` was already resolved in the lockfile from 8.6.1, this just makes it optional).

## v8.6.1 (2026-11-02)

Phase 1b: an in-process libav decoder (the `ffmpeg-next` crate, pinned to 5.1.1 to match this box's
ffmpeg 5.1.9), behind `KIMO_DECODER=libav`. The default stays the ffmpeg-CLI pipe in `render.rs::decode()`
-- this is kept **opt-in**, not the default, because it is not faster here (see MEASURED below); the
brief's own rule was to default it only if it proved both correct and faster, and it is only the first.

**What it is** (`crates/kimo-core/src/libav_decode.rs`): one long-lived `LibavDecoder` per source path,
pooled process-wide and reused across an export's whole batch sequence -- opened once, seeked only when a
request goes backward, decoding forward from wherever it already is otherwise (no ffmpeg process respawned
per window, unlike the pipe path at render.rs:202). Frame-accurate seek (seek to the keyframe at/before the
target, flush, decode-forward) and CFR conform (map each output tick to the right source frame when the
source's own rate doesn't match the project's) via swscale (BICUBIC, matching the `scale` filter's own
default) plus a hand-written centre-crop/pad matching `decode()`'s `fitf` stretch/cover/contain modes
exactly. Scope: ordinary 8-bit video at constant speed 1.0, not time-remapped, not reframe-active, not a
still image or EXR/TIFF/kimopx, color_pipeline disabled (`libav_decode::supported()` is the one source of
truth for this; `decode()` checks it and falls straight through to the existing pipe path on anything
outside it, or on any libav error -- this can never make an export fail that would otherwise have
succeeded).

**Correctness, proven two ways:**
- A genuinely variable-frame-rate fixture built by the test itself (6 distinctly-coloured frames at
  irregular real timestamps: 0 / 0.52 / 0.60 / 0.92 / 1.12 / 1.52s), conformed to a 10fps CFR project and
  compared frame-for-frame against the existing ffmpeg-pipe decode: **max pixel delta 0, mean 0.0000** over
  311,296 bytes (`tests/libav_vfr_conform.rs`). Getting this exactly right took one real fix: the first
  version picked, for each output tick, whichever source frame was nearest to that tick's raw time --
  wrong, and it disagreed with the pipe path at 2 of 19 ticks (max channel delta 255, a genuine wrong-frame
  pick). The actual rule ffmpeg's own `fps` filter applies holds each source frame from the output tick
  *its own* pts rounds to (`round(pts * fps)`) until the next frame's rounded tick -- a source-frame-driven
  rule, not a per-tick-nearest one. Once that was the rule, the fixture matched exactly.
- The real montage benchmark, decoded output compared via `ffmpeg`'s `psnr` filter: 526 of 656 frames
  within noise of PSNR 48-57dB against the pipe path's own encode (the rest exactly inf/identical) -- the
  same class of "ordinary encoder lookahead/mb-tree ripple" already documented for earlier 8.5.x commits,
  not a decode discrepancy.

**MEASURED (median wall time unless noted, same benchmark project as v8.6.0's table):**
- 720p: 39.7-41.4s with `KIMO_DECODER=libav` vs 37.5s for v8.6.0's overlap pipeline alone -- *slower*,
  despite higher average core usage (2.85-2.89 vs 2.22-2.23).
- 1080p: 97.4s vs 96.5s -- a wash either way.

Root cause, as best understood: libavcodec's own frame-threading was enabled explicitly
(`set_threading(Frame, available_parallelism())`), which closed some of an earlier, worse gap (41.8-43.6s
before that change), but each `LibavDecoder` still does its own decode-then-scale-then-crop work on exactly
one thread (the prefetch thread, see v8.6.0) -- the ffmpeg CLI subprocess this replaces decoded a whole
window using its own internal multi-threaded pipeline in a wholly separate OS process, which on this box's
real workload evidently extracted more total parallelism than one Rust thread managed, overlap or not.

Version bumped to 8.6.1 with this entry; `Cargo.lock`'s three workspace members follow.

## v8.6.0 (2026-11-02)

Naman's "Core" redirect: stop VFX/look polish, build the render engine. The audit
(`kimo_core_audit.md`) measured the export-only render of a real 18.86s talking-head + b-roll edit at
14.6 fps / 720p and 5.9 fps / 1080p, with only ~2.5 of 4 cores busy on average -- about half the wall time
was the main thread blocked on a freshly-spawned ffmpeg decode, then blocked again writing frames one at a
time into the encoder's pipe, with no overlap between decode, compose and encode.

**Phase 1a: the three stages now run concurrently** (`crates/kimo-core/src/render.rs`,
`export_range_cmd`), with the exported bytes unchanged:

- A prefetch thread decodes the *next* export batch while the *current* batch composes. It works against
  a `Cache::snapshot()` -- a cheap, Arc-sharing point-in-time copy of the decoded-frame cache (no pixel
  data is duplicated, just the lookup table), so the prefetch thread can never alias the cache the
  compose work-queue is reading from. When both finish, the prefetched cache becomes the cache for the
  next batch -- same decode amortization as the old single-cache design, just no longer serialized with
  compose.
- The encoder runs on its own thread, fed by a bounded channel. The main loop hands off a composed
  batch's frames and moves straight on to prefetching/composing the next one instead of blocking on each
  frame's write-and-ack round trip to the encoder's pipe.

Proof the output didn't change: `tests/overlap_pipeline.rs` (new) exports the same project twice through
the concurrent pipeline and asserts the two runs are framemd5-identical with no frame dropped or
duplicated across batch boundaries, plus a direct test that `Cache::snapshot()` never aliases the
original. The real-world proof is `kimo_core_bench.md`: the new binary's 720p and 1080p renders of the
audit's benchmark project are **SHA256-identical, byte for byte**, to the same renders from the
pre-existing v85 baseline binary -- not just matching hashes of decoded frames, the literal .mp4 files are
identical.

Measured (median of 3 runs each, same benchmark project, `export`-only, no whisper/lint):
- 720p: 46.2s -> 37.5s wall (14.2 -> 17.5 fps), **1.23x**
- 1080p: 117.3s -> 96.5s wall (5.6 -> 6.8 fps), **1.22x**

This is the serialization fix alone; it does not yet touch the ffmpeg-CLI decode itself (phase 1b) or the
scaler/compositor (phase 2), which is where the rest of the audit's headroom is.

## v8.5.8 (2026-11-02)

The montage review (`montage_v85_v08_review_sheet.png`) ranked the end card as the #1 remaining weakness:
one frozen, heavily blurred frame held completely still for the whole 3s card (~14% of the edit's runtime,
frame-diff <2 across 2s), and the "SUBSCRIBE FOR MORE" pill read small (about 220px wide on a 1280-wide
frame).

Three changes, all scoped to `auto_edit`'s own `end_screen` stage (`crates/kimo-core/src/ext/auto_edit.rs`):

- **The backdrop drifts instead of sitting frozen.** The background clip's `scale` is now keyframed
  (`END_CARD_BG_SCALE` -> `END_CARD_BG_SCALE_END`, 1.08 -> 1.15) across the whole card in one eased
  (`in_out`) segment, a slow Ken Burns push-in rather than a flat value -- smooth and monotonic (proven by
  sampling the keyed prop at 21 points: no reversal, no step bigger than 4x the average step), so the card
  reads as a designed, moving background instead of a stuck frame.
- **Less mush.** `END_CARD_BG_BLUR_RADIUS` dropped from 9.0 to 5.5 -- the subject stays recognisable,
  clearly soft behind the CTA, not an unreadable smear.
- **The CTA actually reads.** The `subscribe_pop` badge (pill + dot + text) is rebuilt at
  `END_CARD_PILL_SCALE` (1.4x) instead of `titles.rs`'s own 1x design size: the text's own already-built
  font size and the dot's own already-built width are read back and multiplied by the same factor, then the
  pill width and the dot's room/position are recomputed with the exact same shared formulas `titles.rs`
  itself uses (`pill_width_for_text`, `dot_room`, `dot_x_for_pill`) at a proportionally scaled `k` -- every
  one of those functions is parametrized entirely by `k`, so scaling `k` by the same factor as the text/dot
  reproduces the identical padding and the 8.5.5 dot-inside-pill gap guarantee, just bigger, instead of a
  naive uniform `scale` transform that would leave the dot's own px-pinned clearance (`dot_x_for_pill`'s
  `14.0 * k`) out of step with the grown pill.

New/updated TDD coverage in `tests/auto_edit.rs`: `end_screen_background_freezes_early_blurs_gently_and_scales_up`
now samples the keyed `scale` prop at start/middle/end (clip-local time) and asserts the push-in is
monotonic and smooth (no outsized jumps), and checks the lowered blur radius; a new
`end_card_pill_is_scaled_up_and_dot_gap_still_holds` builds the same badge unscaled on a fresh 1280x720
project as a baseline, proves the real end card's pill is meaningfully bigger and clears "roughly 300+ px
wide on 1280", and re-proves the 8.5.5 dot-inside-pill and dot-to-text-gap (>=0.7x the dot's own diameter)
geometry on the now-bigger badge using the same rendered-position technique as
`subscribe_pop_dot_clears_the_text_after_the_pill_resize_fix` (`tests/director_small.rs`). `golden_frames.txt`
and `recipe_frames.txt` are byte-identical; `golden_registry.txt` is untouched (no tool description changed).

Verified against the real-footage benchmark: `real_v62.mp4`, md5 `dac36d18de29f81da090006d262c46c2` (was
`real_v61.mp4`, md5 `41caa0f5048e5cfa193b5071f2367953`). `framemd5` showed frames 538-656 differ
(t=17.9-21.83s); a per-pixel diff against a side-by-side rebuild of the OLD 8.5.7 binary isolated the real
content change to frame 566 onward (t=18.87s, exactly the end card's own start -- mean pixel delta jumps
from <1 to 2.4 there and climbs through the card as the push-in and the bigger pill take effect), while
frames 538-565 carry only ordinary encoder lookahead/mb-tree ripple (mean <1, max ~24-45 of 255, invisible),
the same class already documented here for `real_v57`-`real_v61`.

One honest side effect, examined and left as-is rather than worked around: `lint_edit`'s own review (which
`auto_edit` always runs) now reports one `text_over_subject` warning at 18.93s that real_v61 did not have.
Isolating each change independently traced it to the bigger pill alone (the backdrop's lower blur radius and
Ken Burns drift, tested in isolation, stay lint-clean): this clip's last trailing ASR caption ("about it.")
holds at full opacity until about 19.1s, a little past where the end card begins, and the bigger pill's own
solid, high-contrast shape -- not a face -- is what the saliency check reads as a "subject" once it is large
enough to reach that screen position. Viewed the actual frame: the opaque pill simply draws over the
caption (end-card content is on a later, higher track than the caption track, same ordering as every earlier
version), which is the correct, intended result -- a trailing caption hidden behind the new end card, not
corrupted or double-exposed. `apply_review_fixes` already auto-fixes the first occurrence it finds
(`16.66s`) and correctly declines to chase this second, introduced one further (the system's own documented
"a fix introduced a new problem, not auto-chased" shape, exactly as `apply_review_fixes.rs`'s existing tests
describe) -- left for a human/agent call rather than silently special-cased, and judged here to be a benign
interaction with this specific clip's caption timing, not a real visual defect, so left unfixed rather than
distorting the pill's geometry or touching caption timing (out of this stage's scope) to chase a warning
away.

Montage rebuilt the same way as `montage_v85_v08` (same driver, same 3 looks at the same clips/windows --
`glitch_surge`/city b-roll, `aurora_wash`/typing b-roll, `chrome_bloom`/final beat, confirmed via
`--dump-timeline` that every clip id is unchanged): `montage_v85_v09.mp4`, 4.2MB. Comparison sheet at
`endcard_v08_vs_v09.png` (frames at 19.0/20.0/21.0/21.8s, v08 row vs v09 row) viewed at full size and
zoomed on the pill: v08 is static and heavily blurred across all four frames with a small pill; v09 visibly
drifts (the shirt's pattern and the subject's position shift gently across the four frames), stays
recognisable rather than mush, and the pill reads as a real, legible call to action.

## v8.5.7 (2026-11-02)

The montage review (`montage_v85_v06.mp4`) and the benchmark (`real_v59.mp4`) both flagged the
`whip_left` transition into the first b-roll cutaway (around 4.05-4.07s) as a long smear instead of a
crisp whip-pan -- the outgoing talking-head shot and the incoming b-roll both turned to mush for several
frames in a row, with visible ghosting/double-image, not a clean directional streak.

Root cause, found by extracting and viewing the actual frames (not eyeballing the finished clip): three
separate bugs stacked up in `whip_left`/`whip_right` (`transitions.rs`, `plan()`):

- The blur's peak width scaled as `frame_width * 0.35 * intensity` -- about 450px at 1280px wide and
  intensity 1.0, roughly a third of the frame -- using only 16 box-filter taps. Taps that far apart
  (~30px) don't blend into a streak, they sample distinct "echoes" of the image: ghosting, not blur.
- A second directional blur (`overlay`, 0.6x the first, 12 taps) was applied by `render.rs` to the
  **already-composited** frame -- both the outgoing clip being wiped away AND the incoming clip already
  drawn underneath it -- so the incoming shot was smeared too, compounding the mush and directly
  contradicting "the outgoing and incoming shots stay sharp right up to the blur peak."
- The blur envelope was a plain `4k(1-k)` parabola, which stays above half its peak strength across
  roughly 70% of the transition's own duration -- so most of the window read as blurred, not just the
  middle frames.

Fixed, all in `whip_left`/`whip_right`:

- **The envelope is raised to a power** (`(4k(1-k))^2.4`), concentrating the blur on only the 2-3 frames
  nearest the midpoint; the outgoing clip's own start and end frames now measure <=2px of blur width
  (effectively untouched), same as before the fix, but now true for several surrounding frames too, not
  just the exact endpoint.
- **The peak blur width is tightened** (`frame_width * 0.22 * intensity`, down from `0.35`).
- **The tap count now scales with the blur width** (`ceil(width / 3)`, clamped 16-64) so samples never
  land more than ~3px apart -- the ghosting/double-image is gone regardless of how wide the blur gets.
- **The `overlay` pass is removed.** Only the outgoing clip's own frame (`post`) is ever blurred by this
  transition now; the incoming shot is never touched.
- `auto_edit`'s own b-roll-cutaway call now passes `intensity: 0.65` explicitly for its `whip_left`
  transitions specifically (opt-in-safe: a caller invoking `add_transition` directly still gets the
  tool's own default, 1.0, untouched) -- auto_edit fires this on every cutaway, so a touch gentler here
  keeps a run of several whips from ever feeling heavy.
- New TDD coverage in `tests/whip_transition.rs`, measuring blur width directly off a rendered frame
  (a hard edge's blurred transition-zone width) rather than eyeballing: the whip's own start/end frames
  stay <=2px blurred, the peak frame carries a real >60px blur (so the fix doesn't just chase smearing
  down to nothing), at most 5 of 9 sampled frames across the transition exceed a 20px visible-smear
  threshold (was ~7-8 of 9 on the old code), `whip_right` mirrors `whip_left`, and `overlay` is confirmed
  gone for both kinds.

Verified against the real-footage benchmark (the first render of this fix): `real_v60.mp4`, md5
`5919a8ece4f42e7426dac17a57e70f00` (was `real_v59.mp4`, md5 `9740b7c1b1f481db441d2f1f871e748e`). `framemd5`
showed frames 98-197 differ (t=3.267-6.567s, audio bit-identical throughout); comparing against a
side-by-side rebuild of the OLD 8.5.6 binary isolated the real content change to frames 124-128
(t=4.13-4.27s, mean pixel delta 9.8-20.6 of 255) -- exactly the whip's own transition window (clip1 starts
at 4.067s, duration 0.25s) -- while frames 98-122 and 130-196 carry only ordinary lossy-codec
lookahead/mb-tree ripple (mean <1.4, max ~35-65 of 255, invisible), the same class already documented here
for `real_v57` vs `real_v56`. The diff stops cleanly at frame 197/198, exactly the next scene cut (`clip1`
-> `clip2`), which resets the encoder's own lookahead. Viewed the actual before/after frames directly: the
old whip held visible ghosting/combing for about 6 frames; this first fix kept the outgoing shot sharp
through t=4.133s, carried one real (clean, not ghosted) blur frame around t=4.2s, and the incoming shot was
already sharp by t=4.267s.

**Follow-up, same version:** that first fix only ever blurred the INCOMING clip's own frame (`post`, which
`render.rs` runs before this clip is blended on top). It never touched `out`, the already-composited
backdrop under it -- the outgoing layer, still playing on its own track/time (for `auto_edit`'s b-roll
cutaways, the talking-head track continuing underneath). So the outgoing shot stayed perfectly sharp and
completely static through the whole transition while only the incoming b-roll ever got any blur: a cheap
slide/wipe, not a whip-pan, confirmed by viewing the actual frames at 1280x720 (the outgoing talking-head
was crisp at the exact moment the incoming b-roll was streaked and already covering about 80% of the
frame). A real whip blurs BOTH layers along the motion direction with the SAME envelope, peaking together
at the midpoint. Fixed by also setting `under` -- the hook `render.rs` already runs on `out` right before
this clip blends on top (it's how `push`/`gradient_wipe` move the outgoing picture) -- using the identical
`vel`/`n` as the existing `post`, so the backdrop gets the matching streak with no new taps and no change
to the incoming side: sharp at k=0, >40px blurred at the midpoint, sharp again (<=4px) by k=0.9, same as
the incoming layer. 5 new tests in `tests/whip_transition.rs` cover it directly (outgoing-midpoint blur,
outgoing-sharp-at-start, both layers sharp-by-k=0.9, no ghosting on either layer via the `under`/`post`
hooks on a synthetic edge frame).

Re-verified against the real-footage benchmark: rebuilt `real_v61.mp4`, md5
`41caa0f5048e5cfa193b5071f2367953` (was `real_v60.mp4`, md5 `5919a8ece4f42e7426dac17a57e70f00`). `framemd5`
shows frames 98-197 differ again (same window; a per-pixel diff against `real_v60.mp4` isolates the real
change to frames 123-128, t=4.1-4.27s, mean pixel delta up to 14.6 of 255 -- the outgoing layer now
streaking alongside the incoming one -- while the rest of the 98-197 range carries only the same ordinary
encoder-ripple class as before). Viewed the before/after frames directly (`whip_v06_v07_v08.png`,
`montage_v85_v08.mp4`): at the transition's midpoint the outgoing talking-head is now visibly streaked
along with the incoming b-roll, reading as a real whip-pan rather than a slide with a blurred overlay.

## v8.5.6 (2026-11-02)

The montage review (real-footage cut, `montage_v85_v05.mp4`) flagged a long talking-head stretch that read
as static to the eye, about 9.0-16.1s. Digging in: `auto_edit`'s existing job-2c logic (added back in
`7b6fcda`) already forces a split and a punch-in on any uncovered dialogue run longer than
`punch_max_static` (then 4.5s default), so a cut and a small zoom WERE already landing inside that window
(at 11.573s). The zoom just never registered -- it was a soft 0.2s eased ramp from 1.0x up to ~1.16x, so
for the first several frames after the cut the two clips looked almost the same size, and the whole 7.1s
span read as one static take even though it technically was not.

Fixed:

- **The punch-in ease is now a hard, instant jump (`duration: 0.0`, was `0.2`) instead of a soft ramp.**
  The scale lands at its full target value on the very first frame after the cut, so the punch is
  synced to the cut itself -- the "cut-on-phrase, hard punch" style top editors actually use, not a creep
  that is easy to miss. Scale targets (the existing randomized ~1.13-1.16x, alternating pattern) are
  unchanged.
- **`punch_max_static`'s default is tightened from 4.5s to 3.5s**, and `split_points()`'s own slack is
  removed: the old code could let a forced segment overshoot the cap by up to `max_static * 0.3 + 0.5s`
  when hunting for a natural pause past the ideal split mark, or let the final segment run up to
  `max_static + 0.5s` past the clip's own end. Both are now hard bounds -- no synthetic split's segment can
  exceed the cap, guaranteed by a new unit test (`split_points_never_lets_a_segment_exceed_the_cap`) built
  from synthetic long takes with no natural pauses at all, where the old slack was reachable.
  `punch_max_static_is_configurable`'s existing 30.0-second override test is untouched (nothing here
  changes the knob itself, only its default and its guarantee).
- New TDD coverage: a synthetic long uncut take gets forced split points such that the max static span is
  <= 3.6s; the resulting punch scales alternate (not every segment lands on the same side); nothing from
  job-2c's forced splitting ever lands inside b-roll coverage or the end card (both already excluded by
  the existing `covered_fraction` gate, now asserted directly).

Verified against this real-footage benchmark's own talking-head take specifically: its natural dialogue
pauses already happen to split every uncovered stretch at <=3.19s (`clip17`, 13.033-16.226s) even under
the OLD 4.5s cap, and its one >4.5s uncovered-looking stretch (`clip9`, 3.233-7.893s, 4.66s) is 94%
covered by b-roll and correctly exempt either way -- so for THIS asset the split-point structure is
byte-identical old vs new (checked directly, clip-by-clip, against a side-by-side old-binary rebuild). The
3.5s default and the slack fix are a correctness hardening that matters on footage whose natural pauses
don't already satisfy the cap, which the new unit tests exercise directly; what changed this benchmark's
own pixels is the ease hardening above, landing exactly at the one punch this footage already had
(11.573s).

**The pinned real-footage benchmark md5 changes**, from `db90ea441ab927521e0168da8a9899da` (real_v58) to
`9740b7c1b1f481db441d2f1f871e748e` (real_v59). `framemd5` against real_v58: frames 0-236 and 239-310
bit-identical; frames 237-238 (~7.90-7.97s) differ -- the first couple of frames of the one other
pre-existing punch in this take (`clip15`, onset 7.893s), now landing at full scale immediately instead of
a fraction of the way through a 0.2s ramp; frames 311-565 (~10.37-18.87s) differ -- the real content change
is the `clip10` punch onset at 11.573s landing instantly instead of easing in (confirmed by a direct
frame-11.6s visual diff: the subject is visibly larger in `real_v59` at that exact frame, same framing,
face fully in shot), and the remainder of that range is the encoder's own mb-tree/lookahead reacting to
those now-different frames rather than any further content change -- a frame pulled from well past the
ramp window (13.3s) is visually identical between the two files (max per-pixel delta 46/255, mean
1.48/255, not visible), the same propagation class already documented for `real_v57` vs `real_v56` above.
Frames 0-236, 239-310 and 566-655 (the end card) are untouched, as expected: `auto_edit`'s job-2c and
`add_punch_ins` never touch b-roll, captions timing, audio, or the end card.

## v8.5.5 (2026-11-02)

A fresh review of the 8.5.4 montage (same 3-look real-footage cut, re-rendered with the 8.5.4 fixes in)
found three more things that still read as amateur. Fixed below, each with a failing-first test.

- **The end-card background froze on the literal last frame of the talking-head take -- usually mid-
  gesture, mouth open -- then blurred it hard enough (radius 18) to go unreadable mush.** The freeze now
  grabs a frame about half a second earlier (`last_source_t - 0.5s`, clamped to the clip's own start), the
  blur is down to radius 9, the background clip is scaled up 1.08x so the gentler blur's own edge falloff
  never shows a seam at the canvas edge, and it is darkened a touch (-0.2 stops, about -13%) so the white
  pill/text/dot pop a little more against it.
- **`chrome_bloom` snapped from a warm baseline to a near-total cool inversion in well under a fifth of a
  second -- it read as a white-balance glitch, not a grade.** Its `color_wheels` push is pulled back to
  about half (`gain_b` ~1.25-1.3, `gain_r` floor ~0.82-0.85 at full intensity, lift halved to match), and
  a new per-look `min_fade` floor lengthens its own top-level mix fade-in to about 0.4-0.5s on a short
  clip (never shortening an already-slower fade on a longer one) so the push lands as a ramp instead of a
  snap. Still reads clearly cooler and shinier than the baseline, with 0% clipping.
- **The 8.5.4 dot fix put `subscribe_pop`'s badge dot OUTSIDE the pill, so it read as floating loose,
  disconnected from the badge.** `dot_x_for_pill`'s formula now places the dot INSIDE the pill, 14px
  (scaled) clear of its own left edge, and both the initial `subscribe_pop` build (`titles.rs`) and the
  `text_too_small` lint resize-fix (`director_tools.rs`) now grow the pill by the dot's own footprint (a
  new `dot_room` helper) so the two never drift apart and the dot never has to compete with the text for
  room. The dot's left-edge padding comes out constant (14px scaled) regardless of pill width, by
  construction.
- **Follow-up (same day): moving the dot inside the pill only fixed the overlap, not the cramped read --
  on `real_v57.mp4` at 20.5s the dot sat about 3px from the "S" of SUBSCRIBE, jammed up against the text
  rather than clear of it.** `dot_room`'s formula is widened so the dot-to-text gap lands at ~0.9x the
  dot's own diameter (the dot's 14px left-edge clearance from the pill is unchanged): because the text
  clip is never given its own x and stays centred on the pill, widening the pill only delivers HALF of
  that width as real gap (the other half opens equally on the pill's right side), so `dot_room` solves for
  twice the room actually wanted -- the derivation is spelled out on `dot_room`'s own doc comment. Applied
  identically on both the `subscribe_pop` build path and the `text_too_small` lint resize-fix path (both
  already shared `dot_room`/`dot_x_for_pill`, so this is a formula-only change, no call-site drift
  possible). `director_small`'s dot test now asserts the gap is >= 0.7x the dot's diameter, before AND
  after the resize fix (measured ~0.93x and ~2.6x respectively on the real inputs).

**The pinned real-footage benchmark md5 changes again**, from `36c25e57765e76a311a54bfe14ec8f10`
(real_v56) to `db90ea441ab927521e0168da8a9899da` (real_v58, superseding the intermediate real_v57). Cause:
the end-card background fix above (earlier freeze frame, lower blur radius, scale, darken) changes the end
card's own pixels, as intended -- `auto_edit` does not use `chrome_bloom` anywhere in this benchmark
(grepped, confirmed), so that fix is not a factor here. The dot-spacing follow-up above also lands inside
the same end-card frames (it only moves the dot and widens the pill, both already part of that region's
diff), so real_v58's own `framemd5` diff lands in the identical range as real_v57's did against real_v56:
frames 0-560 bit-identical against real_v57 (and audio identical throughout), frames 561-655 (the end
card, ~18.70s to the finish) differing as expected. Against the earlier real_v56 pin, frames 0-544 are
bit-identical and frames 566-655 (the end card) differ as expected (mean pixel delta ~13.5/255); frames
545-565 (21 frames, ~0.7s, inside x264's default 40-frame lookahead) also carry a tiny diff -- mean
<1/255, max 74/255, invisible -- traced to the encoder's own mb-tree/lookahead reacting to the now-softer
end-card transition rather than to any change in the dialogue content itself: those same frames are
bit-identical up to 544, and the same kind of comparison between the two prior end-card-only builds
(real_v53 vs real_v55, which did not touch the transition's softness) showed a perfectly clean cut with
zero bleed at exactly the frame boundary.

## v8.5.4 (2026-11-02)

A real-footage review montage (3 looks, boxed captions, driven end to end through the MCP tools an AI
director would use) surfaced five things that read as amateur even though every individual unit test
was green. Fixed below, each with a failing-first test.

- **`lint_edit`'s `text_too_small` auto-fix was a silent no-op on animated text.** The fix wrote only the
  clip's base `scale` Prop; once a Prop carries any keyframes (e.g. a pop-in entrance/exit curve), the
  base value is never read again, so the "SUBSCRIBE FOR MORE" end card stayed exactly as small as lint
  had just flagged it. The fix now scales the text's own `size` field directly (a plain f64, not a Prop,
  so it has no keyframes to be overridden by) -- it reaches the screen whatever the clip's scale
  animation is doing.
- **The end-card pill overflowed its own text once the text above was enlarged, and once that was fixed
  its own dot landed on the enlarged text instead.** A `subscribe_pop`-style pill is built once, sized
  for the text's original width; growing the text (by the fix above, or by hand) left it narrower than
  the label it was supposed to back. The pill shape is now tagged to the text clip it backs, a new
  `set_shape_size` tool resizes a shape clip's pixel width/height independent of any animated scale, and
  `lint_edit`'s own fix now chains a pill resize after the text resize so the box is always re-measured
  from the new rendered text bounds. That pill resize left a second bug: the badge's own white dot sits
  outside the pill at a fixed offset computed from the pill's width at build time, and once the pill grew
  wider that same offset put the dot on top of the enlarged text's first letter ("SUBSCRIBE FOR MORE"'s
  "B", caught on a montage render at full size). The dot is now tagged to the text clip it sits beside the
  same way, and `lint_edit`'s fix chains a third step that repositions the dot with the SAME clearance
  formula `titles.rs` used to place it originally, now evaluated against the new, wider pill -- so the
  dot's gap past the pill's edge never drifts out of sync with a pill that grew after the badge was first
  laid out. `apply_review_fixes` itself now walks a `fix`'s whole `then` chain (any depth), not just one
  hop, so a fix generator can describe this kind of multi-step, order-dependent repair in one `fix` value.
- **`glitch_surge` read as a sustained wash, not punch-and-recover, on short (<~2s) clips.** Two causes:
  the fine-grain glitch/RGB-split keyframes never rested at a true zero between punches (fine at full
  clip length, visible as "always on" on a short cutaway), and the preset's own outer mix fade-in was a
  flat 15% of the clip window regardless of the look's internal pulse period, so a short clip could still
  be ramping up mix through what should have been a full-strength first hit. Fixed: the low-baseline
  keys now hit true zero, and `apply_vfx_preset` caps the fade by the look's own pulse period.
- **`chrome_bloom` was too subtle on real (warm) footage at default intensity.** Same trap `frost_veil`
  hit in 8.5.2: its cool grade used `temperature`, which is scaled down 5x internally, so the push barely
  registered against warm lighting. Replaced with `color_wheels` for a controllable, clearly-visible
  cool push with 0% clipping.
- **A missing bundled font failed over to a system font with no warning anywhere.** The resolver in
  `text.rs` now emits one clear stderr warning per distinct missing font, naming it and pointing at
  `KIMO_FONTS` / `fonts/fetch.sh`, deduped so a long render doesn't spam it. Render output (resolved
  path, substituted flag) is unchanged.

**The pinned real-footage benchmark md5 intentionally changes** from `82ef81b676c9b78a3428e6d4bc57d8b4`
to `36c25e57765e76a311a54bfe14ec8f10`. Cause: the benchmark's own end-card text was itself flagged
`text_too_small` (20px under the 40px floor) and the old auto-fix silently did nothing against it --
the same bug fixed above. With the fix working, the benchmark's end card is now actually enlarged to
40px and its pill resized to match, exactly like the montage's end card, and the badge's dot is
repositioned together with the pill so it stays clear of the enlarged text instead of landing on top of
it. Verified frame-by-frame (`ffmpeg framemd5`, 656 frames @30fps, 21.867s, identical duration): every
frame from 0.0s to 18.7s is byte-identical between the old and new render; only the last ~3.1s (the end
card) differs, confirmed visually with a side-by-side frame comparison. This is the new expected
benchmark md5 (superseding the intermediate `8d41372662cf1508863564a77b3a79d7`, which had the pill fix
but not yet the dot fix).

## v8.5.3 (2026-11-01)

`vhs_decay` still didn't read as VHS in a 4fps/200px-wide thumbnail strip even though the v8.5.2
build looked like worn tape at full size -- measured directly: the native `scanlines` effect darkens
exactly 1 row every `spacing` rows, and a slow sine-wave luminance test (tried first, before this)
reads as a soft vignette rather than scanline texture, because the eye needs real edges, not slow
brightness drift -- both vanish under a ~6x thumbnail downscale. The `vhs` effect's own tracking band
only displaces pixels in a narrow region; it never brightens or adds noise there, so "a bright, noisy
tracking band rolling through the frame" was never actually visible, only a faint wobble.

- **`vhs_decay`**: replaced the plain `scanlines` node with a hard-edged duty-cycle stripe at a FIXED
  pixel period via a new `pixel_expr` node (`vhs_scanline_expr`) -- it reads as real scanline texture
  at full size AND survives a 200px-wide thumbnail downscale, verified both ways with `vfx_preview` +
  `attach_image` before this file changed. Added a second `pixel_expr` node (`vhs_tracking_band_expr`)
  at the same roll phase as the `vhs` effect's own band (`fract(t*0.35)*h`, so the two read as one
  event): inside a smoothstep-falloff band it brightens the image, resamples with extra horizontal
  jitter (`sample(u+offset,v)`), and adds strong hashed noise, masked to fall off outside the band.
  Raised the pre-blur for a genuinely softer, lower-resolution feel (a real downscale/upscale round
  trip isn't a vfx_graph node, so a stronger blur stands in, as the brief allowed). Added a `levels`
  node for lifted/crushed blacks (a faded, reduced-contrast tape floor -- the old chain used the full
  0..1 range). Checked 0% clipping at both the default intensity (0.4) and dialed to 1.0; face stays
  recognizable at both. No OSD timestamp/REC text was added -- `vfx_graph`'s only generators are
  solid/gradient/shape (circle/rect), there is no text/glyph node to drive a "PLAY"/"REC" overlay from,
  so per the brief this is skipped rather than faked with shapes.

## v8.5.2 (2026-11-01)

Three looks from the v8.5.1 pass still didn't read at phone size on real-footage review:
`glitch_surge`, `vhs_decay`, `frost_veil`. Reworked below, each iterated with `vfx_preview` and the
peak frame inspected at full size (`attach_image`) before touching `vfx_look_library.rs`.

- **`glitch_surge`**: the real bug was the peak-frame capture, not just the graph -- the old demo grabbed
  t=0.8s against a 0.55s pulse period, which lands on an already-decayed frame, so the v02 contact
  sheet showed almost nothing. The graph itself was also too weak on-hit. Now: the pulse period is
  ~0.6s (every 0.5-0.7s per the brief), two `glitch_blocks` layers are stacked (9 coarse slices for
  bold full-width horizontal bands, 24 fine slices layered on top for texture), `slice_threshold` is
  lowered so most slices trigger together instead of a scattered few, and the `rgb_split` pulse is
  pushed much harder on the hit. Between hits both layers settle near zero -- clean frames, confirmed
  by inspecting a frame between pulses. The face glitches hard on the hit (by design, per the brief)
  and is fully recovered one frame later.
- **`vhs_decay`**: had no actual low-res softness and no warm cast -- a real 90s camcorder skews warm
  and soft, not neutrally desaturated and sharp. Added a pre-blur before the `vhs` effect, raised
  wobble/bleed/noise/bands for genuinely visible line wobble, chroma bleed and a rolling tracking band,
  and added a `temperature` push (warm, not cool) after the grain pass, ahead of a lighter
  desaturation. Reads as worn tape at a glance now; chroma bleed on the patterned shirt in the demo
  clip is heavier than plain footage would show, which is the correct VHS chroma-interference
  artifact, not a bug.
- **`frost_veil`**: reworked twice already (pre-8.5.0: fixed a wireframe-reading `edge_glow`; 8.5.1:
  left untouched, which read as subtle again on this pass' real-footage review). Root cause this time:
  `temperature`'s `amount` is scaled by 0.2 internally, so even a -1 push is a mild shift against warm
  practical lighting, and `edge_glow` run directly on the raw frame outlines facial features -- the
  exact wireframe failure from the original pass. Fixed with `color_wheels` (lift/gamma/gain pushed
  blue per channel, a much stronger and more controllable cool push than `temperature`), `edge_glow`
  now running on the already-blurred/graded buffer instead of the raw frame (a soft rim, not a crisp
  outline), a `vignette` tinted icy white-blue (`color_r/g/b`) instead of plain black for an actual
  frosted-edge read, and two off-centre `snow` particle emitters (sides only, clear of a centred face).

Benchmark: `real_v51.mp4` renders byte-identical to the standing golden (md5 `82ef81b6…`, matches
v44-v47/v49/v50) -- this pass only touches `vfx_look_library.rs`'s opt-in graph JSON, nothing on the
auto-edit/caption/render path. Tests: `vfx_look_library`, `vfx_graph_core/tools/particles`,
`surreal_vfx_tools` green (no expectation changes needed -- the look tests are structural over names,
not pixels); `golden_frames`, `recipes`, `registry_lint`, `registry_unique` green and unmoved. Warnings:
34 (cap 35, unchanged from v8.5.1).

## v8.5.1 (2026-11-01)

Look library quality pass. Naman's goal is "put any clips into Kimo and get top-YouTube-editor
quality" judged by how the frames actually look -- so this pass is a straight review-and-rework of
the 9 v8.5.0 looks against real footage (the talking-head clip in `work/v7q_real`), not a feature
add. Verdict going in: `frost_veil` strong; `magic_sparkle`/`solar_flare` visible but mild; the other
6 (`ember_drift`, `chrome_bloom`, `glitch_surge`, `dream_haze`, `vhs_decay`, `aurora_wash`) nearly
indistinguishable from source at a glance on a phone. Every change below was iterated with
`vfx_preview` (no rebuild needed per tweak -- it takes an arbitrary graph JSON directly) and the peak
frame inspected at full size before touching `vfx_look_library.rs`; none of the 9 needed cutting --
all read clearly after the rework.

- **`ember_drift`**: the old graph used the `sparks` particle preset at its fixed default spawn point
  (a tiny fountain near the chest) -- technically "particles" but not "rising from the lower edge" and
  barely visible even at full intensity. Replaced with an explicit (no-preset) particle emitter: a
  wide line along the very bottom of frame, gentle upward buoyancy (negative gravity, modest speed),
  warm orange-to-red colour ramp, and a life short enough (~2.2s at this speed) that embers fade out
  roughly a third of the way up frame -- clear of a centred subject's face by construction, not by
  luck. Teal/orange grade and bloom amounts raised alongside it.
- **`chrome_bloom`**: bloom's threshold/amount pushed hard for a real "strong bloom on highlights"
  read, plus a `tint_r/g/b` cool tint on the bloom itself. The grade is now cool temperature + a
  desaturation pass + a touch of contrast, instead of relying on chromatic-fringe alone for the
  "chrome" read. Chromatic aberration and sharpen are dialled back from a first pass that aliased
  badly (visible moire) on a patterned shirt at full intensity -- unmistakable without reintroducing
  the aliasing the brief rules out.
- **`glitch_surge`**: was a constant mild amount at every frame -- visible as a texture, not as a
  "glitch". `glitch_blocks`' and `rgb_split`'s `amount` params now ride a new `pulse_prop` helper: a
  keyframed Prop (sharp attack, quick decay, `loop_out: cycle`) that punches hard on a ~0.55s period
  and settles to a light scanline/fringe texture between hits -- deterministic "on the beat" with no
  audio analysis (the engine only exposes the current instant `t`; see `vfx_graph.rs`'s own module
  note). Peak-intensity ceilings dialled back once from an even punchier first pass that fully
  scrambled a face at the attack frame -- still a real punch, face stays recognisable through it.
- **`dream_haze`**: added a real `halation` pass (the dedicated effect, distinct from `bloom`) for
  "clear halation", and a `grade` lift/gain pass (gentle lift on all three channels, a touch of gain
  pull on blue/green) plus mild desaturation for "lifted pastel" -- the old graph had neither; it was
  blur + bloom + light_rays + temperature + vignette, which reads as "soft", not specifically "hazy
  with lifted pastel shadows".
- **`vhs_decay`**: rebuilt on the dedicated `vhs` effect kind (per-line wobble, chroma bleed via
  offset RGB sampling, noise, and a moving tracking band) layered with scanlines/grain/desaturation/
  vignette. The old graph (grain + scanlines + chromatic_aberration + saturation) had no actual line
  wobble or tracking band -- which is most of what reads as "worn VHS tape" rather than just "a bit
  degraded". Values tuned down once from a first pass that was dramatic but left the face too
  degraded to read at full intensity.
- **`aurora_wash`**: the gradient wash was static -- a flat tinted overlay, not "flowing colour
  bands". `angle_deg` now rides a `sin`-expr keyframe Prop for a slow deterministic swing (no literal
  flow is possible: `gen_gradient`'s own stop parsing reads position/colour with plain `as_f64()`, not
  `value_to_prop`, so stop values themselves can't be keyframed today -- a pre-existing engine gap
  this pass did not touch), a third colour stop was added for a richer band structure, the wash is
  blurred before blending so it reads as soft bands rather than a sharp gradient edge, and overlay
  opacity plus the base bloom were both raised.
- **`magic_sparkle`**: pushed further per the brief (bloom amount/threshold, dust rate/size all
  raised) -- and in doing so, found and fixed a face-safety bug the push would otherwise have made
  worse: the `magic_dust` preset's own default spawn point (x=0.5, y=0.5, a 0.15-radius circle) sits
  squarely on a centred subject's face, so "push it further" without repositioning means MORE
  particles ON the face. The three dust emitters are now explicit (no preset defaults relied on),
  placed left, right and low-centre -- framing the subject instead of covering it.
- **`solar_flare`**: pushed further per the brief -- and the same review caught a second problem the
  push introduced: a stronger `light_rays` + `halation` + `bloom` + `exposure` stack blew 41.7% of a
  real frame to clipped white (mean luma 0.86), which is a washed-out frame, not a strong look, by the
  brief's own words. Every amount in the final graph is tuned down from that first pass to land a
  strong, unmistakable flare that still leaves the subject's face and most of the frame readable
  (measured clipping ~29-35% afterward, contained to the flare's own highlight, not the whole shot).
- **`frost_veil`**: untouched -- Tab's verdict going in was "strong" on real footage, and the previous
  worker had already reworked its one real miss (`edge_glow` reading as a full wireframe) before the
  8.5.0 wrap.
- New helper in `vfx_look_library.rs`: `pulse_prop(period, low, high)` (a periodic keyframed Prop via
  `loop_out: cycle`, used by `glitch_surge`) and `particles_raw` (an explicit particles node with no
  preset, used by `ember_drift` and `magic_sparkle` to avoid fighting a preset's own frame-centred
  defaults).
- v01 demos kept on disk untouched; new v02 demos rendered for all 9 looks
  (`files/v7q/v85_<look>_v02.mp4`, 5s, real talking-head footage, intensity 0.7 for a fair like-for-
  like comparison across looks) plus a new side-by-side contact sheet, source vs look at each look's
  own peak frame (`files/v7q/v85_look_library_contact_sheet_v02.png`).
- Tests: `vfx_look_library.rs`'s 5 tests are structural over `NAMES` (every look builds/validates/
  visibly changes a frame at 3 intensities) and needed no expectation changes -- none of the 9 looks
  were cut, and none broke the "visibly different from source" contract. `vfx_graph_core`/`_tools`/
  `_particles`, `surreal_vfx_tools`, `golden_frames` (incl. `golden_registry_contract`), `recipes`
  (incl. `golden_frames_per_recipe`), `registry_lint`, `registry_unique` all green, unmoved -- this
  pass only touches `vfx_look_library.rs`'s graph JSON and adds two private helper functions; no
  tool schema, effect kind, or registry entry changed.
- Warnings: 34 (cap 35; unchanged from 8.5.0 -- nothing added, nothing newly unused).
- Benchmark: `real_v50.mp4` (fonts already present in this worktree from the previous pass) re-ran
  `examples/auto_edit_benchmark.py` against the same real folder with the 8.5.1 build -- md5
  `82ef81b676c9b78a3428e6d4bc57d8b4`, matching `real_v44`-`v47`/`v49` exactly. No code in this pass
  touches auto_edit, captions, or the render/export path -- only `vfx_look_library.rs`'s own graph
  JSON, which is opt-in and unrelated to the default auto-edit path -- so this is confirmation, not a
  surprise.

## v8.4.0 (2026-11-01)

V8.4 surreal VFX tools. Inventoried the existing stylize catalog first (set_echo, kaleidoscope/
cc_kaleida, turbulent_displace, pixel_sort/glitch_confetti/vhs/film_damage, chromatic_aberration/
vr_chromatic_aberration, bloom/glow/halation already cover most of a "surreal effects" wishlist) and
built only genuinely new ones on top of existing infra. 6 new tools (526, was 532).

- **`droste_zoom`** (effects2.rs, pure per-frame math, no render.rs changes): Escher/Droste infinite
  recursive spiral tunnel via a log-polar radius wrap. Found and fixed a real bug during the demo
  pass: the first version wrapped the RAW pixel radius into the ring range, so every output pixel
  sampled a ~1px speck near the frame centre and painted it flat across the whole image -- a brown/
  orange wash with no scene content, not a tunnel. Fixed by wrapping the radius RATIO against a
  proper anchor radius (0.42x the short side) instead, so every wrapped sample lands on real picture
  content. Re-verified by extracting frames across the whole demo clip (not one cherry-picked frame)
  after the fix.
  - TDD: pixel-level test confirms it changes the frame and is opt-in outside its time window.
  - Demo: `vfx_droste_zoom_v02.mp4` (city b-roll) -- v01 is the pre-fix broken render, kept rather
    than overwritten so the before/after is on record.

- **`portal_mirror`** (effects2.rs): a soft-edged circular portal showing the frame flipped and
  colour-inverted inside it. Same class of bug as droste_zoom's first version: `intensity` was
  driving the blend (`mix`) itself, so anything under full intensity read as a faint, semi-
  transparent ghost overlay with no readable portal edge. Fixed by decoupling them -- `mix` always
  ramps to full opacity once the portal is open; `intensity` instead scales the portal's radius.
  - TDD: confirms a flipped, colour-inverted disc appears and is fully removable.
  - Demo: `vfx_portal_mirror_v02.mp4` (typing b-roll) -- v01 is the pre-fix translucent-ghost render,
    kept rather than overwritten.

- **`add_vertigo_zoom`** (ext/surreal_vfx_tools.rs): the Hitchcock dolly-zoom/vertigo move. Zero new
  pixel math -- a pure keyframed convenience over the existing `depth_parallax` (zoom in while
  dollying out, or the reverse), from a depth map clip the same way `depth_parallax` already takes
  one.
  - TDD: the masked subject's pixels stay put while the background moves.
  - Demo: `vfx_vertigo_zoom_v01.mp4` (talking-head footage) with a synthetic radial depth map (no
    automatic depth-from-RGB model exists in this engine; a centred radial gradient is a reasonable
    stand-in for a centred portrait shot, named honestly as a limitation) -- verified across the
    whole clip: the subject holds size while the room behind them visibly grows.

- **`subject_clone`** (new effect kind in layerfx.rs, reusing the exact same same-time aux-clip
  rendering pattern as `depth_parallax`/`lens_blur`): pastes N copies of a masked subject's own
  pixels at growing spatial offsets, each dimmer, the real subject always sharpest/on top.
  - TDD: a dimmer offset copy is produced and is opt-in.
  - Demo: `vfx_subject_clone_v01.mp4` (talking-head footage). Per review, the mask is NOT hand-
    supplied: built from Kimo's own matte tracker (`track_matte`, a couple of rough seed points,
    optical-flow propagated through the clip) refined with `refine_matte`, rendered to PNGs and
    assembled into a standalone mask clip -- no manual mask-drawing needed from the caller.
  - Known limitation, stated plainly rather than silently: this is spatial-offset only, not
    time-delayed ("echoes through time"). The only "read another clip" hook this effect (and
    depth_parallax/lens_blur) has fetches the aux clip at the SAME instant, never a different one;
    a true time-offset version needs new render-pipeline machinery, out of scope here.

- **`melt_drip`** (effects2.rs, pure per-frame math), shipped as **experimental**: a per-column-noise
  warp that displaces the image toward one edge (default straight down). Distinct from the existing
  symmetric `turbulent_displace`. Two passes at this, honestly reported:
  - A genuine pixel-math bug was found and fixed: the first version used 3 octaves of fbm noise per
    drip column, which reads as a jagged sawtooth/zigzag (fine high-frequency wobble stacked on the
    base lane pattern) instead of a smooth melt -- reported plainly as "a jagged wave, nothing flowing
    downward." Fixed by dropping to 1 octave (already a smooth bilinear-interpolated noise field, see
    `vnoise`) and replacing the raw quadratic along-the-flow growth with a smoothstep.
  - On a synthetic horizontal-stripe test clip the fix reads clean. On real footage (coffee and city
    b-roll, both reviewed frame-by-frame, not just one timestamp) it does not: a per-pixel diff against
    the unwarped source shows a tight, repeating corrugated/wavy band pattern along any edge the warp
    crosses (cup rim, hand, skyline silhouette) rather than a single smooth downward drip front. It
    reads as an uneven wavy/jitter distortion, not a convincing melt. Rather than keep tuning against a
    30-minute wrap budget, it ships labelled for what it actually does: the tool, its description, and
    this entry all now say "experimental wavy/jitter warp." It is NOT used by `apply_vfx_preset`.
  - TDD: a straight-down drip measurably drags the subject's content downward more than upward, and
    is a no-op outside its time window. Caught and fixed a real normalisation bug while writing this
    test too: the "how far along the flow" fraction was normalised by max(width,height), which
    understated the effect for a non-square frame on a mostly-vertical drip; fixed to normalise by
    the actual projected extent along the drip direction.
  - Demo: `vfx_melt_drip_v03.mp4` (coffee b-roll, clean 0-2.8s window, intensity 1.0, size 150) --
    v01 and v02 are the earlier, more broken renders, kept rather than overwritten. v03 is the
    honest current state of the tool, not a "fixed, looks great" claim.

- **`apply_vfx_preset`** (ext/surreal_vfx_tools.rs, pure orchestration via the same
  `crate::commands::dispatch` path add_clip/lift_range already use to call each other): one call for
  a named combo -- `dreamy` (glow + halation + chromatic_aberration + vignette, all pre-existing
  effects), `glitch` (pixel_sort + glitch_blocks + chromatic_aberration + vhs, all pre-existing),
  `vertigo` (dispatches to `add_vertigo_zoom`), `echo` (dispatches to the existing `set_echo`). No
  new pixel math; every sub-call goes through the real tool's own validation.
  - TDD: dreamy/glitch visibly change the frame, vertigo still locks the subject, echo dispatches
    without error, and vertigo without `depth_clip_id` is refused rather than silently skipped.

- **Dropped**: `slit_scan` was in the original candidate list and investigated, but dropped rather
  than built. It needs reading the same clip at many different points in time within one output
  frame; the only "read another clip" hook the renderer exposes (the one depth_parallax/lens_blur/
  subject_clone all use) fetches an aux clip at the SAME instant as the main clip, never a different
  one. Building real time-displacement would mean surgery in the core render loop, which is more risk
  than this pass's safety rules (protect the goldens, stay under the warnings cap) allow for.
  `melt_drip` was built in its place.

- **Contract fix, found while wrapping**: `add_subject_clone` and `apply_vfx_preset` had first sentences over the 149-character limit (203 and 267 chars) -- a pre-existing bug from their own commits, caught by `description_first_sentence`'s full-suite run, not part of the melt/droste/portal fixes above. Shortened both to a plain short first sentence with the detail moved after it, same pattern as the v5.0.0 REWRITTEN batch. golden_registry.txt updated for both (description-only, no schema or pixel change).

crates/kimo-core/tests/golden/golden_registry.txt: 6 new entries (one per new tool above) plus
`add_effect`'s own hash (its schema enum grew by 2: droste_zoom, melt_drip). No existing frame or
project golden touched -- the sanctioned use of this file per golden_frames.rs's own doc comment.

Build note: partway through the demo-render pass, a hard build failure surfaced from a shared
`CARGO_TARGET_DIR` -- another concurrent Kimo task building a different checkout of this same repo
had configured the vendored manifold C++ library's cmake cache against ITS source path, and this
task's build then collided with that cache (wrong source path, hard cmake error). Rather than clear
or touch a cache another task's work depends on, this task's build was moved to its own isolated
target dir for the rest of the pass -- cost one slow cold rebuild, cost nothing of the other task's
work.

Warnings: 34 (cap 35, unchanged across all 6 commits this pass).

Talking-head benchmark, checked once at the end per the brief: re-ran examples/auto_edit_benchmark.py
against the same real talking-head + b-roll + music folder used throughout this engine's work, output
real_v47.mp4 -- byte-identical (same md5, 82ef81b6...) to the last-checked real_v45.mp4. The
talking-head path is unmoved; nothing in this pass touches it.

Before/after contact sheet across all 5 built effects: `files/v7q/v84_vfx_compare.png`.

## v8.5.0 (2026-11-01)

V8.5 VFX engine + AI preview loop + look library. Read the existing engine first (particle_flow.rs is
a full deterministic particle system, keyframe/Prop covers every numeric param, effects2.rs/shader_ops
already wrap most of a node-graph's worth of ops) and built a composable layer on top rather than a
second pixel-math stack. 535 tools (was 532). Full `cargo test -p kimo-core` (not just the targeted new test files) caught one real gap before ship: the 3 new MCP tools had no `toolgroups.rs` entry (`every_tool_has_a_real_group` failed) -- fixed, and the full suite is now part of this pass's own checklist, not just the targeted one.

- **`vfx_graph`** (new effect kind, `vfx_graph.rs`): a small node DAG -- `effect` (wraps ANY existing
  effect kind by name, the main reuse lever), `solid`/`gradient`/`shape` generators, `blend` (add/
  screen/multiply/overlay/difference), `mask_apply`, `mask_clip` (an externally driven aux clip, same
  same-instant-only pattern `depth_parallax`/`subject_clone` already use), and `particles` (calls
  `crate::particles::render_fps` -- Kimo's existing emitter -- directly onto the graph's own buffer,
  `params.preset` for any of its 13 built-in looks, an optional `mask` input for silhouette/edge
  emission). Every numeric node param takes a literal OR a full keyframe `Prop`, so the whole existing
  keyframe system is reused with no new expression language. Honest limit, stated in
  `vfx_graph_describe`: render.rs has no time-offset clip fetch (`render_clip_alone` always renders at
  the CURRENT frame's `t`), so a graph's own "time" is `t` plus Prop's own expr ops, not frame-offset
  sampling. `mask_clip` DOES carry a real `track_matte` result -- `render_clip_alone_as` only clears
  the legacy single-mask field before a standalone render, not the `mask.layers` stack `track_matte`
  populates (verified directly, see the hero shot below for how v02 actually uses this).
- **`add_vfx_graph` / `vfx_graph_describe` / `vfx_preview`** (`ext/vfx_graph_tools.rs`): commit, catalog,
  and non-destructive 1-6-frame preview with cheap metrics (mean luma, clipping %, Sobel edge energy,
  diff from the clip's own unmodified frame). Bug found and fixed dogfooding the hero shot, not by test:
  `vfx_preview` was writing `crate::pixels::encode`'s output straight to a `.png` path -- that function is
  Kimo's own internal lossless pixel-interchange format (magic `KIMOPX01`), not a PNG encoder; the files
  opened as 14.7 MB of raw data. Swapped to `crate::render::write_image` (what every other render tool
  uses) and hardened the test to check real PNG magic bytes, not just that a file exists.
- **Look library, 9 names, exposed through the existing `apply_vfx_preset`** (not a second tool):
  `ember_drift`, `chrome_bloom`, `glitch_surge`, `dream_haze`, `frost_veil`, `magic_sparkle`,
  `vhs_decay`, `aurora_wash`, `solar_flare` (`vfx_look_library.rs`), each a real `vfx_graph`. V8.4's
  4 presets (dreamy/glitch/vertigo/echo) are untouched.
- TDD throughout: 32 new tests across `vfx_graph_core.rs` (10: parse/validate/cycle-detection/
  topo-order/solid/blend/effect-wrap), `vfx_graph_tools.rs` (6, PNG-bytes check added after the bug
  above), `vfx_graph_particles.rs` (5: determinism -- same seed/params/t -> byte-identical -- different
  seed moves it, a preset renders visibly, an unknown preset errors clearly, mask-driven layer
  emission), `vfx_look_library.rs` (5: every look builds/validates at 3 intensities, an unknown name
  errors, every look visibly changes a real-structure frame, `apply_vfx_preset` reaches all 9 and
  still runs V8.4's own presets unchanged).
- **Hero shot**, two rounds on real talking-head footage, both kept (never overwritten):
  `files/v7q/v85_unreal_v01.mp4` then `v02.mp4`, each with its own `.kimo` project and graph JSON. A
  real `track_matte` on the subject (seeded by hand, 2 seeds, confidence ~0.73-0.76 -- honest, not
  pixel-perfect) drives `set_effect_mask` on two plain masked effects (bloom + teal/orange) for a
  subject aura, and a `vfx_graph` chain (ripple+wave warp, teal/orange grade, chromatic aberration,
  bloom, magic-dust particles) builds across the clip to a peak around 90% through, then eases back to
  clean footage in the last ~15% (leaning into `add_vfx_graph`'s own ramp-back-to-0-by-`end_time`
  instead of fighting it). v01 shipped with particles at a fixed point near the chest -- wrong: I had
  misread `render_clip_alone_as`'s `m.matte = None` as stripping a clip's WHOLE mask stack before a
  standalone render, when it only clears the legacy single-mask field; a `track_matte` result lives in
  `mask.layers`, which IS honoured (verified directly with a small Rust probe before trusting it). v02
  fixes that for real: a duplicate of the subject clip (`duplicate_clip`, its copied effects removed,
  its copy of the same matte left at mode `add` so its own rendered alpha IS the matte) rides
  `mask_clip_id`, and the particles node's `shape:"layer"` + `emit_edge` now spawns genuinely off the
  tracked silhouette rim -- which is also what the review caught in v01 (sparkles scattered across the
  face read as a rash, not an effect) and v02 fixes by construction, not by hiding the symptom; warp
  peaks were also roughly halved after the real mask-driven pass read as face-melting at v01's values
  (the two were never directly comparable before, since v01 never exercised this code path). Per-look
  demo clips for all 9 looks on real b-roll: `files/v7q/v85_<look>_v01.mp4`, a labelled 3x3 contact
  sheet at `files/v7q/v85_look_library_contact_sheet.png` -- `frost_veil`'s first pass was a real miss
  (edge_glow at the look's original amount reads as a full edge-detection wireframe on real footage,
  not a frosted rim; fixed by screen-blending a much weaker edge pass under the shot instead of
  applying it in-line, re-rendered and re-checked before shipping) and the other 8 held up as built.
- Warnings: 34 (cap 35; removed one unused `bilinear` helper from commit #1 that nothing ended up
  needing once the particles node called the real emitter instead).
- `golden_registry.txt`: 4 new tool entries + `add_vfx_graph`/`apply_vfx_preset`'s own hashes moved
  (schema enums grew) -- each hand-computed with the exact `fnv(description|schema|mutates)` the real
  test uses (a throwaway local test printed them, never committed, never `KIMO_UPDATE_GOLDEN`). No
  frame or project golden touched.
- Talking-head benchmark, checked at the end per the brief: re-ran `examples/auto_edit_benchmark.py`
  against the same real folder, output `real_v48.mp4`. Its md5 (715e3c64...) does NOT match the
  recorded `real_v45`/`real_v47` baseline (82ef81b6...) -- but a FRESH, unmodified build of the exact
  8.4.0 base commit (3c328ed) this branch forked from, built the same way in this same environment,
  renders the identical 715e3c64... So this pass's VFX work introduces zero drift on the talking-head
  path (confirmed by direct control comparison, not assumed): the mismatch against the older recorded
  baseline is a pre-existing environment difference (toolchain/encoder, not investigated further --
  out of this pass's scope) from before this branch existed, not a regression from v8.5.

# Changelog

## v8.3.0 (2026-11-01)

V8.3-M montage mode: editing features for non-dialogue footage (travel, sports, pets, raw phone
clips) -- "top YouTube editor quality" regardless of clip type. Voice/audio-leveling and captions
were out of scope this pass (steered off). 4 new tools (526, was 522).

- **Best-moment selection**, new `score_windows` (read-only) and `best_segments` (mutating) tools.
  There was no path at all for non-dialogue footage before this: calling `auto_edit` without
  `talking_head_asset_ids` hard-errors. Scores every window of a clip on sharpness (`focus_series`),
  exposure (`frame_quality`), subject framing (`pick_thumbnail`'s own scorer), motion
  (`frozen_frames`), and one shake value per clip (`stabilize_clip`'s own read-only correction) --
  every signal reused from an existing tool, nothing re-derived. Hard per-axis floors
  (`min_sharpness`, `min_exposure`, `max_shake_px`) sit on top of the blended score so a window can't
  pass on a good blend alone while badly blurred. `best_segments` cuts the kept/dropped windows with
  `split_clip`/`delete_clip`.
  - TDD: a clean clip is kept; blurry/dark/shaky clips are scored low and dropped; `best_segments`
    actually deletes the junk and splits a mixed clip to just its sharp half.
  - Verified on real b-roll, not just synthetic clips: a static shot reads ~0.01px shake and is kept;
    the same shot with real jitter added reads ~25px (threshold 12) and is dropped; blurred/near-black
    copies dropped on sharpness/exposure. Contact sheet: `v83_bestmoment_compare.png`.

- **Beat-synced montage cuts with energy-varied shot length**, new `beat_sync_montage` tool. Reuses
  `beat_cut` for all the actual cutting (never re-implemented); reads `audio_transients`' own beat
  grid (per-beat strength), picks a shorter or longer shot at each beat from that beat's own
  strength, hands the chosen cut times straight to `beat_cut` as its own `beats` array (every cut IS
  a real detected beat), and ends on a `beats_per_phrase`-aligned beat instead of mid-phrase. Lays the
  music, normalizes to `target_lufs` (default -14) before keying a fade-out over the last
  `fade_out_beats`. Found and fixed a real gap along the way: a peaky/transient music bed can refuse
  `normalize_loudness`'s plain gain (would clip); now takes the refusal's own suggested fix (a light
  compressor) and retries once rather than leaving the music quiet.
  - TDD: cuts land within 1 frame of real beats and the edit ends on a phrase boundary; a peaky bed
    reaches target loudness via the compressor-retry path.
  - Verified on real footage (best_segments' own kept output): a two-tier music bed produces 0.5s
    shots in the loud section and 2.0s shots in the quiet section -- shot length visibly tracking
    energy. `match_events` on the real render: 34/35 cuts within 1 frame of a real beat (median offset
    0.3ms). Final export: -14.29 LUFS, -4.05 dBTP, zero silences, confirmed fade (no abrupt cutoff).
    Renders: `montage_v01.mp4`, `montage_v02.mp4`. Contact sheet:
    `v83_beatsync_montage_overview.png`.

- **Shot-to-shot colour consistency**, new `montage_color_match` tool. A thin wrapper around the
  existing `match_shot_look` (already used for broll-vs-talking-head, reused verbatim) scoped to a
  whole montage: pick one clip as the anchor (`clip_ids[0]` by default, or your own
  `reference_clip_ids`) and pull every other listed clip toward it in one call.
  - TDD: a warm clip and a cool clip -- the match moves the non-anchor clip's gain in the correct
    direction (red up, blue down toward the anchor), not just "ran without erroring"; an explicit
    reference is honoured; every clip also listed as its own reference errors cleanly.
  - Verified on real footage: a dark b-roll anchor pulls a warmer desk-shot clip's exposure and color
    down to match. Contact sheet: `v83_colormatch_compare.png`.

Talking-head path (`auto_edit`, `auto_rough_cut`) and its benchmark are untouched by this pass --
every new tool lives in its own file (`montage_tools.rs`) wired only into the `timeline`/`output`
toolgroups.

## v8.2.0 (2026-11-01)

V8.2-V visual finish quality pass: "if I put some clips into it, be it of anything, I get top YouTube
editor quality work" -- scoped to how the finished video LOOKS (no voice/audio work this pass, per
steer). Every item wires an existing, already-tested engine tool into `auto_edit`'s own defaults; no
new tools (522, unchanged).

- **Slow Ken Burns push-in on static b-roll cutaways**, new `push_in` auto_edit stage (default on).
  Wires `add_smart_punch` (saliency-driven continuous push-in, already registered and tested, never
  called from `auto_edit`) onto every static b-roll clip (no pre-existing scale/x/y animation) at
  least 1.2s long. New options `push_in` (bool, default true) and `push_in_zoom` (default 1.05 = 5%,
  clamped 1.01..1.3, inside the asked 3-6% range).
  - TDD: `push_in_animates_static_broll_by_default` (a real keyframed ramp, 2.5-7% over the shot, plus
    the off switch) and `push_in_skips_very_short_broll` (<1.2s left alone).
  - Verified on the real benchmark footage: `real_v41.mp4` vs the prior render at the identical 6.5s
    timestamp in the coffee-cup b-roll shows the push-in clearly by eye (background crossbars shifted,
    cups larger); the engine's own returned keyframes confirm it numerically (scale 1.0 -> 1.025 ->
    1.05). Audio completely unchanged: -13.996 LUFS, 90.0%/91.67% recall, identical to the prior render.
- **Punch-ins now force a split on any dialogue stretch that would sit static past `punch_max_static`
  seconds** (new option, default 4.5, clamped 1.5..20). Natural-pause splitting (`auto_rough_cut`,
  `tighten_pauses`) already keeps most real takes short enough for the existing `add_punch_ins` to
  alternate wide/tight on (the real benchmark footage's longest natural stretch was already 3.2s,
  unaffected by this change) -- but a continuous sentence with no breath, or a single long uncut take,
  could leave one giant clip with nothing to alternate against. New `split_points` helper finds the
  nearest real word-pause (>=0.12s gap between two transcript words) to each `punch_max_static` mark
  and splits there via the existing `split_clip`, falling back to a plain interval cut when no clean
  pause is nearby.
  - TDD: `job2_splits_a_long_uncut_dialogue_take_for_punch_ins` (a 10s single take splits into pieces
    all <=4.5s, at least one punched) and `job2_punch_max_static_is_configurable` (set high, a short
    take is left as one clip, matching the pre-existing behaviour and its warning).
  - Verified on the real footage with `pacing` disabled (so natural-pause splitting couldn't paper over
    the gap): the one long ~12.5s dialogue stretch split into 4.5/4.4/4.5/0.5s pieces, each with its own
    wide/tight zoom; frames right at one of the new cuts show a clean, real jump-cut by eye.
- **Captions default to `auto` placement** (new `caption_position` option, default `"auto"`, was a
  hardcoded `"bottom"`). `auto_captions` already had a real face-aware `auto` mode (samples the source
  footage for a skin-toned band, moves the caption strip to the top when a face/body reaches into the
  normal bottom band) that `auto_edit` simply never used.
  - TDD: `job3_caption_position_defaults_to_auto_and_avoids_a_low_face` (a synthetic low-face shot gets
    its captions pushed to the top band by default; an explicit `caption_position` still overrides it).
  - On the real benchmark footage the speaker's face sits clear of the bottom band already, so `auto`
    resolves to `"bottom"` exactly as before -- verified audio-identical to the prior render and looked
    at captions at 3 timestamps: clean, readable, inside safe margins, never over the face. (The
    word-by-word pop itself -- active word coloured + scaled up to 1.22x, synced to exact word timing --
    already existed in the caption styles `auto_edit` uses; placement was the one real gap.)
- **A short whip/zoom-blur transition into each b-roll cutaway**, new `broll_transitions` stage
  (default on; new `broll_transition_duration`, default 0.25s, clamped 0.1..0.6). Wires the existing
  `add_transition` tool's `zoom_blur`/`whip_left` kinds (already in the engine, never called from
  `auto_edit`) onto each b-roll clip's own `transition_in`, alternating kinds across multiple cutaways.
  Scoped strictly to the b-roll boundary -- never applied to the talking-head's own jump-cut punch-ins,
  which stay hard cuts on purpose.
  - TDD: `job4_broll_gets_a_short_whip_transition_by_default` (a b-roll clip gets a short
    zoom_blur/whip_left `transition_in` by default; the off switch leaves it with none).
  - Verified by eye mid-transition on the real footage: a clean, tasteful blur-blend, not jarring;
    audio unaffected.
- Not attempted this pass: any voice/audio work (explicitly steered off partway through: "Work on more
  features except voice now").

Tests: full workspace suite green apart from the pre-existing exempt failures named in this pass's own
brief (`director_small`'s text-crowding test and its CPU-timing lint_edit perf test; `readme_count`,
the `robust_est` doctest, the `search_tools` `fit_clip_duration` tie, one `xform_lint` read -- none
touched this pass). Goldens unchanged (no new tools, no default changed in a way that moves rendered
pixels on an existing golden's own call shape). Warnings: 34 (cap 35, unchanged from v8.1.0).

## v8.1.0 (2026-11-01)

V8.1-Q quality pass: fixing the real cause behind two V8.0-Q compromises, instead of
shipping around them. No new tools.

- **`level_dynamics` (the master-bus speech leveler) is now scoped to the dialogue span, not the
  whole mix.** New `Project.master_speech_level_scope_end` (set by `finish_audio` from its own
  classified dialogue clips' latest end, read by `audio::mix`/`mix_strict` via a shared
  `apply_master_speech_level`, with a 50ms crossfade at the boundary) narrows ffmpeg `speechnorm` to
  `[0, dialogue_end)`, leaving an end card or music-only tail untouched. `0` = unscoped (the old
  whole-buffer behaviour), so any caller that sets `master_speech_level` without this stays
  byte-identical.
  - This directly disproves v8.0.0's own explanation for why the end-card swell was capped at 3dB:
    with speechnorm now provably never seeing the end card (checked `finish_audio`'s own dialogue
    classification at the moment it sets the scope), raising the swell to 8dB reproduced the exact
    same 56.7% whisper-recall collapse v8.0.0 blamed on speechnorm. The dialogue audio itself was
    never damaged at any swell size (proven by cutting 3dB and 8dB renders down to the dialogue span
    and whisper-transcribing each -- byte-identical transcripts both times); the collapse was whisper
    transcribing the WHOLE exported file in one pass and reading the EARLY dialogue worse once a loud
    segment followed later in the same pass. See the benchmark fix below.
  - TDD: the scope fix itself has no new unit test (`finish_audio_level_dynamics_narrows_loudness_range_within_a_clip`
    and the rest of `director_small.rs`'s `finish_audio_*` suite cover it unchanged); verified end to
    end on the real benchmark.
- **`examples/auto_edit_benchmark.py` now reports and gates dialogue-span recall separately from a
  whole-file number.** `dual_span_recall()` whisper-transcribes a render twice -- once whole, once cut
  to the dialogue span -- against the same reference transcript; both numbers always print in the
  summary JSON (`word_recall_vs_full_source` / `word_recall_vs_ceiling`, each now `{dialogue, full}`),
  and `--recall-span {dialogue,full}` (default `dialogue`) picks which one gates pass/fail. Also fixed
  a second, smaller artifact found along the way: a dialogue-span crop with no lead-in silence reliably
  dropped whisper's read of the clip's very first sentence (66.7% recall straight; 90.0% with 0.5s of
  silence prepended, recovering exactly the dropped opening and nothing else) -- `_trim_to_span` now
  pads 0.5s before transcribing a cropped span, and does it audio-only (WAV) rather than re-encoding
  video it was going to throw away anyway.
- **End-card music swell raised 3dB -> 11dB**, now that both the real scoping fix and the honest
  benchmark gate are in place. End-card LUFS: **-18.4** (was -23.4 under the old unscoped/leaky
  behaviour at 3dB, -26.7 with no swell at all) -- inside the originally-asked -18..-20 range.
  Dialogue-span recall holds at 90.0%; full-file recall 91.7%.
  - TDD: `music_bed_swells_under_the_end_card_once_dialogue_ends` (its `after > before * 1.3`
    assertion holds comfortably at 11dB's ~3.5x boost).
- **Voice dynamics (loudness_range) [~]: investigated, not reached.** Target was dialogue-span
  `loudness_range` >= 3 LU (was 1.4-1.5) while holding -14+-0.5 LUFS, <=-1 dBTP, recall >=90%, no
  interior silences. Swept every candidate the mission named on the real benchmark footage
  (dialogue span only, now that the scope/benchmark fixes above make that measurement trustworthy):
  `level_strength` 1.0 (speechnorm's own floor) reaches 2.0 LU at 90.0% recall -- a real, safe gain,
  and disproves v7.9.0's note that a lower `level_strength` "collapses recall" (the same benchmark
  dialogue-span-crop-with-no-lead-in artifact described above, not a real regression). But 1.0 is a
  literal no-op for speechnorm (`e=c=1.0` cannot change gain either direction) and breaks the
  feature's own regression test for footage that genuinely needs leveling
  (`finish_audio_level_dynamics_narrows_loudness_range_within_a_clip`: on=off=11.4 LU at 1.0, zero
  narrowing). `level_strength` stays at its default 2.5 to protect that real case -- a caller editing
  already-even footage can pass `level_strength: 1.0` explicitly (now a tested, documented choice).
  With every leveling touch off at once (`level_dynamics` off, `match_strength` 0, `compress_strength`
  0 -- the gentlest this engine can be) the honest ceiling measured was **2.6 LU**, still short of the
  >=3 target. Reaching it would need an active dynamics *expander* (deliberately widening quiet/loud
  gaps beyond the source's own natural range), a materially different and riskier feature than
  "gentler leveling" -- out of scope for this pass.
- No job 3 (a visible slow push-in on static b-roll) this pass -- time went to finding and fixing the
  two real bugs above instead; disclosed, not attempted.

- Added preview proxy media management: generation, enable/disable, health listing, deep integrity validation, safe relinking and detachment. PNG/range previews can use verified proxies; exports, audio and analysis retain originals. Missing/stale proxies fall back. Persisted, undoable bindings; synchronous SDR/CFR scope. See [proxy workflow](docs/PROXY_WORKFLOW.md).

## v8.0.0 (2026-11-01)

V8.0-Q quality pass: the finished video itself, not feature count. Tools: 521 -> 522 (new
`match_shot_look`).

- **The 3.0s dead-air tail at the end of every render, fixed.** Every `real_*` render back to v15
  ended on 3.0s of near-silence (18.86-21.87s): the default-on end screen (v7.7-Q) extends the real
  export past the talking-head's own `edit_duration`, but the music bed's own clip length only ever
  targeted `edit_duration`, so the card played over a muted freeze-frame background with nothing else
  under it. Confirmed by extracting frames at the silent span (the SUBSCRIBE FOR MORE card, audibly
  dead) before touching any code.
  - Fix: the music clip's length now targets the full planned export (`edit_duration` +
    `end_screen_duration` when the end screen is on). A music asset shorter than that full length is
    TILED (looped from its own start, capped at 200 repeats) rather than left to run out, with a short
    fade at each loop seam and the true tail fading to silence over up to 0.5s. `duck_timeline` needed
    no change -- it already iterates every clip on a track.
  - Honest result: **zero silences anywhere** (was 3.0s), word recall unchanged at 90.0%, loudness and
    true peak unchanged within spec.
  - TDD: `music_bed_keeps_playing_under_the_end_screen`, `end_screen_with_no_music_warns_about_the_silent_tail`.
- **B-roll color/exposure match to the talking head** (new tool `match_shot_look`, wired into
  `auto_edit` as `broll_color_match`, default on whenever there is b-roll). `auto_grade` only ever
  pulls a clip toward one fixed absolute target (neutral cast, a target luma) -- it never looks at
  what ANOTHER shot in the same edit actually looks like, so a warm-lit interview cut against a
  cool-toned or bright-daylight b-roll still reads as two different shoots stitched together even
  after `auto_grade` runs (measured on the real benchmark: the talking head reads warm/indoor, the
  city b-roll cool, the coffee b-roll bright daylight, each already inside `auto_grade`'s own "fine"
  band). `match_shot_look(reference_clip_ids, target_clip_ids, strength)` measures each clip's own mean
  RGB with the same fit-aware reader `auto_grade` uses, then pulls each target clip's measured look a
  `strength` fraction toward the reference clips' averaged look -- white balance and exposure together,
  gains clamped 0.5..2.0 per channel so a very different reference can never crush or blow a shot.
  Before/after frame comparison saved to `v80_broll_compare.png` (talking head reference, b-roll
  before, b-roll after -- a clearly visible warm push on the cool coffee-shop shot, looked at by hand).
  New options on `auto_edit`: `broll_color_match` (bool, default true when b-roll exists),
  `broll_color_match_strength` (0..1, default 0.6).
  - TDD: `match_shot_look_pulls_target_toward_reference`,
    `match_shot_look_skips_a_clip_that_is_its_own_reference`,
    `broll_color_match_runs_by_default_and_can_be_turned_off`.
- **End-card music swell, capped at a measured-safe level.** Once the dialogue ends there is nothing
  left for the music to duck under, but `finish_audio`/`duck_timeline` only ever set the bed's level for
  use UNDER speech -- the end card's own span measured 12.6 LU quieter than the speech body with no
  voice left to protect. A short ramp keyed right where the card starts brings the bed up once speech is
  done. **Capped at 3dB, not the originally-targeted ~8dB**: an 8dB swell measured clean in isolated
  testing but, re-rendered on the real benchmark, collapsed whisper word recall from 90.0% to 56.7%
  (reproduced twice, byte-identical both times, with no change to the dialogue audio itself) --
  `finish_audio`'s master-bus speech leveler (`level_dynamics`, ffmpeg `speechnorm` run once over the
  WHOLE mixed timeline) reacts to a sudden loud segment anywhere in the mix, confirmed by
  `--no-level-dynamics` on the same 8dB render recovering to 93.3%. The boundary measured as a cliff,
  not a gradient: 3dB held at 91.7% recall, 5dB fell straight back to the same 56.7% collapse as 8dB.
  Shipped at the confirmed-safe 3dB. Honest result: end-card LUFS -26.7 -> -23.4 (a real improvement,
  short of the -18..-20 originally asked, reported as such rather than faked).
  - TDD: `music_bed_swells_under_the_end_card_once_dialogue_ends`.
- No job 3 (voice dynamics, `loudness_range` still 1.4 vs the >=3 target) this pass -- disclosed, not
  attempted; see v7.9.0's own entry for what was already tried and ruled out there.

## Unreleased

## v7.9.0 (2026-10-31)

V7.9-Q quality pass, continuing V7.7/7.8-Q's priority (what actually moves a finished video, not
feature count). Tools: 521 -> 523 (whoosh_sfx on `place_broll`; `compress_amount` on `set_audio`).

- **Voice dynamics investigated honestly; one real, verified, recall-safe gain shipped -- the >=3 LU
  target not reached, marked [~].** The final mix's `loudness_range` sat at 1.2 LU in 7.8.0 while the
  raw source measures 2.4-3.6 LU unprocessed. The suspected cause going in (from 7.8-Q's own notes):
  `finish_audio`'s per-clip average-matching loop pulls every dialogue clip's average loudness the FULL
  distance to the loudest one, with no knob. Added `match_strength` (0..1) to scale that pull -- but
  measured on the real benchmark, clips from the SAME speaker after a rough cut were already within
  ~2.3 dB of each other at that step, so lowering it barely moved `loudness_range` (1.2 -> 1.3 LU at
  0.6) while it reproducibly collapsed whisper word recall from 88.3% to 56.7% (the opening sentence
  dropped entirely -- a hard threshold effect in the small whisper model, not a gradual one, confirmed
  twice on identical input). `match_strength` defaults back to 1.0 (the exact old behaviour) and stays
  as a real option for its original case: two different speakers at very different mic levels (the
  existing `finish_audio_levels_speakers_and_hits_the_target` test covers this).
  - The actual dominant force: `finish_audio` always ran a fixed `acompressor` (threshold=-18dB,
    ratio=3:1) on every dialogue clip with no knob at all. Disabling `level_dynamics` (speechnorm)
    entirely only moved `loudness_range` from 1.2 to 1.4 LU -- the compressor alone was holding it
    there regardless. Added `compress_strength` (0..1) to scale its ratio; swept the real benchmark:
    `compress_strength:0.0` (compressor fully off) reproducibly measured **90.0% word recall (54/60,
    better than 7.8's 88.3% baseline)** with **`loudness_range` 1.2 -> 1.4 LU**. Any value above 0 that
    still ran some compression cost recall for no further LRA gain (0.35 -> 86.7% recall, 1.3 LU). The
    absolute ceiling -- everything off (match_strength 0, compress_strength 0, level_dynamics off) --
    only reached 2.3 LU, still short of 3, and that configuration is not recall-safe. `compress_strength`
    defaults to 0.0: a real, measured, recall-positive change, not a cosmetic knob.
  - Honest result: **`loudness_range` 1.2 -> 1.4 LU** (target >=3 not reached; marked [~] in
    FEATURES.md), **word recall 88.3% -> 90.0%** (improved, not regressed), -14 LUFS and true peak
    unchanged within spec.
  - `Audio.compress_amount` (new project field, custom serde default 1.0 so every pre-7.9 saved project
    loads unchanged) and `set_audio`'s `compress_amount` arg expose the same scale directly.
  - TDD: `finish_audio_match_strength_defaults_to_full_match`,
    `finish_audio_match_strength_explicit_value_partially_matches`,
    `finish_audio_match_strength_zero_leaves_clip_averages_untouched_relative_to_each_other`,
    `finish_audio_compress_strength_scales_the_stored_ratio`,
    `finish_audio_compress_strength_defaults_to_off`. Golden registry hashes hand-updated for the three
    changed schemas (`finish_audio`, `auto_edit`, `set_audio`) -- read from the failing test's own
    computed hash, never `KIMO_UPDATE_GOLDEN`.
- **Whoosh SFX on b-roll cut-ins and the hook title-in** (new, OFF by default): `synth_whoosh_sfx()` in
  `director_tools.rs` generates a short, purely procedural rising-pitch tone (300Hz -> ~2.3kHz over
  0.22s, exponential decay, gentle lowpass) at call time into the OS temp dir and reuses it -- same
  pattern as `add_keyword_pops`' `synth_pop_sfx` (0ae47c0), never a bundled sample. `place_broll` gets
  `whoosh_sfx`: when true, one whoosh at each b-roll cut-in's own start, on a dedicated SFX track.
  `auto_edit`'s hook-title stage places the same cue at the title's entrance when true (threaded through
  to `place_broll` too). Fails open exactly like `add_keyword_pops`' `sfx`: a warning, never a blocked
  cut or title.
  - **Defaults to false, not true, after a real measured cost**: a b-roll cut-in by `place_broll`'s own
    design always lands during active speech (never a true silence), so any sound placed there is a real
    risk, not just a loud one. At 0.3 volume on its own dedicated track, the whoosh cost whisper word
    recall 90.0% -> 86.7% on the real benchmark. Tried the obvious fix -- quieter, 0.15 -- and recall got
    WORSE, 90.0% -> 80.0%, not better: this is not a simple louder-is-worse masking curve, and a third
    blind guess at a volume was not going to be a verified fix with the time left. Left the volume at an
    actually-audible 0.3 and defaulted `whoosh_sfx` to false instead of shipping a recall regression as
    default behaviour -- the same standard this pass already held `match_strength` to. The feature is
    real, built, and TDD'd for a caller who opts in; it is not claimed as safe-by-default.
  - TDD: `place_broll_whoosh_sfx_places_a_real_sound_at_each_cut_in` proves the dedicated track exists,
    one clip per cut-in at the cut-in's own start time, the mix is actually audible there (non-zero
    PCM) when turned on, and the default (no `whoosh_sfx` arg) places none.
  - Classified the new file-open site (the temp whoosh WAV) in `external_refs.rs`.
- Job 3 (a visible, frame-verified b-roll gain -- colour/exposure match or a slow push) did not happen
  this pass; not claimed, not faked.

## v7.8.0 (2026-10-31)

V7.8-Q quality pass: more of `examples/auto_edit_benchmark.py`'s real CC0 interview footage, continuing
V7.7-Q's priority (what actually moves a finished video, not feature count). Tools: 520 -> 521 (one new
tool). The second item below is the headline: a serious pre-existing correctness bug, not a polish pass.

- **`tighten_pauses`** (new tool): a rough cut (`auto_rough_cut`) already drops dead air BETWEEN kept
  clips; nothing before this tightened the dead air a rough cut leaves INSIDE a clip it kept -- an
  interior breath between two phrases, or the pause before the speaker's first word. Probes each
  dialogue clip's own interior silence (reusing `audio_speech_intervals` in `silence` mode, not VAD,
  whose padding/hangover would have inflated speech boundaries and understated the real gap) and ripple-
  deletes everything past a natural pad (default 120ms interior, 80ms lead-in) via the same
  `trim_filler_words` machinery filler-word trimming already uses, so caption retiming comes for free.
  `auto_edit` runs it by default (`pacing: true`) right after the rough cut, before transcription, and
  re-derives dialogue_clips/edit_duration from the tightened track.
  - Three real-footage calibration bugs found and fixed while building this, each only visible on an
    actual render (a synthetic fixture missed all three): a fixed -45dB silence threshold never fired on
    real room tone (-20 to -25dB); the first per-clip auto-calibration attempt biased short speech-heavy
    segments' floor estimate toward speech level and gutted 9.6s of real dialogue as "false silence";
    the whole-track fix that replaced it was then too conservative on a recording with only ~8.5dB of
    real headroom between noise floor and quietest speech, finding zero gaps again. Settled: calibrate
    once from the whole track (more quiet frames to read), threshold = floor + a fraction (default 0.5)
    of the way to the quietest detected speech level, capped 3dB under speech either way.
  - Never leaves a surviving piece shorter than `min_piece_s` (default 1.0s, clamped 0.2-5): fragmenting
    a clip too far raised the odds of the bug below (a short clip reads less reliably to other per-clip
    tools downstream) -- directly responsible for making that bug worse mid-session, caught and capped
    before it shipped.
- **Found and fixed a serious pre-existing bug: `finish_audio` was silently muting most real dialogue as
  "ambience".** `finish_audio` classifies every media clip on the timeline as dialogue, music, or
  ambience by probing `audio_speech_intervals` at aggressiveness 2 and requiring speech_ratio >= 0.2;
  ambience gets muted. On the real benchmark interview, 4 of `auto_rough_cut`'s own 6 kept dialogue
  segments read speech_ratio under that bar at aggressiveness 2 (one segment read -0.0 speech_ratio on
  0.8s of unmistakable continuous speech) and were muted outright -- and every loudness/silence check in
  the benchmark still passed, because finish_audio's final gain-trim loop only ever levels whatever
  survived the mute up to the target LUFS, with no signal that most of the source was gone. `git log -S`
  on the classifier line traces this to commit 77e14e2 (~294 commits back, when `finish_audio` was first
  written) -- present in every real-footage render this project has ever made, not something any
  V7.6Q/7.7Q/7.8Q commit introduced. Caught by whisper-transcribing a shipped render and finding most of
  the source's real sentences missing.
  - Fix: try speech_ratio at aggressiveness 1 first (the same real segments read 0.69-0.90 there,
    comfortably over the bar), then rescue anything still called ambience by checking aggressiveness 0 at
    a materially higher bar (0.5, not the same 0.2) so a real miss still gets caught (the one segment that
    failed at both 1 and 2 reads 0.825 at 0) without casually relabelling real background tone as dialogue
    just because the most lenient level is more permissive.
  - TDD: a synthetic sine-harmonic voice stand-in (the test file's own `talk()` helper, reused everywhere
    else in this suite) does NOT reproduce this -- it is too spectrally pure to trip aggressiveness 2's
    steady-tone rejection the way real voice does. The new regression test slices a short excerpt of the
    real interview fresh at test time (ffmpeg, not committed media) and skips (not fails) if that
    box-local fixture isn't present, so it stays honest without demanding real media in every checkout.
  - New permanent regression gate: `examples/auto_edit_benchmark.py --whisper-recall-source <raw file>`
    transcribes both sides with whisper-cli and fails the run (exit 1) if the rendered word recall against
    the source falls under `--whisper-recall-min` (default 0.90) -- loudness and silence checks alone
    cannot catch this class of bug, since a 90%-muted dialogue track still mixes to exactly the target LUFS.
  - Measured on the real benchmark (whisper word recall vs the source transcript, bag-of-words):
    real_v1.mp4 (first real render, long before this quarter's work) 27.5%, real_v14.mp4 (last V7.7Q
    render) 27.5%, real_v15.mp4 with this session's pacing work but before this fix 13.0% (tighten_pauses'
    extra fragmentation made the pre-existing bug measurably worse), real_v15.mp4 with the fix 68.1%.
    Confirmed directly against finish_audio's own report, not just the recall number: every one of the 11
    real dialogue clips on the fixed render's talking-head track is now classified as dialogue and
    leveled; the only clips still muted as ambience are b-roll's own scratch audio (correct and intended).
    The remaining gap to the 90% gate on this one real clip is not muting -- it is whisper's own
    recognition noise on compressed/leveled speech plus a handful of words legitimately removed by
    rough_cut/filler-trim's own dead-air and filler trimming, not dropped audio.

- **Found and fixed: `auto_rough_cut` lost real opening words on a cold-open recording.** Its speech
  detector (VAD mode, aggressiveness 1) needs several consecutive confirming frames before declaring
  speech has started; on the real benchmark interview (talking begins immediately, no lead-in silence)
  that onset lag cost the first ~0.48s of real words -- confirmed independently with whisper, which
  hears real speech ("It takes so much knowledge...") at the source's literal 0.000s, while the raw VAD
  probe's own first detected span started at 0.48s. Fix: `recover_missed_onset` re-checks only the very
  first kept segment of the whole output (every later segment already has real silence, or another kept
  clip, right before it) with a plain RMS silence probe -- the same technique `tighten_pauses` already
  uses, with no VAD confirmation delay -- and pulls the start back to wherever real silence actually
  ends, never later than VAD's own answer. On the real benchmark: first kept segment went from source
  [0.48, 2.6] to [0.0, 2.6]. TDD against a real-footage excerpt sliced at test time (not committed media).
- **Made the recall gate honest.** `auto_rough_cut`'s own dead-air/filler trimming removes real source
  content ON PURPOSE -- gating a finished render's word recall against the FULL untrimmed source punished
  correct editing right alongside the real muting bug above. `--whisper-recall-source` now gates against
  the kept-span CEILING instead: it re-runs `auto_rough_cut` on the same talking-head asset(s) (read-
  derived, purely to recover the exact spans it kept), concatenates just that kept audio into a reference
  clip, transcribes it as the ceiling, and reports the render's recall against that (still 90% default,
  `--whisper-recall-min`). Reports both numbers plus the ceiling's own transcript text.
  - Measured on the real benchmark with every fix above in: 88.3% against the ceiling (53/60 words),
    up from the original broken baseline's 27.5% against the full source -- close to the 90% floor but
    not over it. The remaining gap looks more like whisper's own flag-sensitive recognition noise at clip
    boundaries than real content loss (an alternate whisper-cli invocation on the identical render
    recovered the one phrase bag-of-words scoring called missing) but this was not chased to full
    certainty this quarter; reported as a disclosed, open gap, not claimed closed.
- **Honest miss, not hidden: loudness range (LRA) on this one real clip.** The brief's 6-8 LU target was
  not met -- measured ~1.2-1.4 LU after every fix above, against a ~2.4-3.6 LU natural ceiling in the RAW
  unprocessed source itself (checked directly: `measure_loudness` on the track right after `auto_rough_cut`,
  before any `finish_audio` processing at all). This specific calm interview voice does not naturally carry
  6-8 LU of dynamic range. Tested with `level_dynamics` (speechnorm) fully disabled: LRA barely moved
  (1.4 vs 1.2), showing the dominant narrowing force is `finish_audio`'s per-clip gain-matching step
  (every dialogue clip leveled to the loudest clip's own average -- a deliberate consistency feature, not
  a bug, and not something this pass has an exposed knob to disable). The prior real_v14 render's 7.1 LU
  reading almost certainly reflects the finish_audio muting bug above (big silent-vs-loud swings from
  mostly-missing dialogue masquerading as dynamics), not healthy vocal variation -- not re-chased further
  this quarter given the time already spent on the higher-severity muting and onset bugs; disclosed as a
  known gap for a future pass, not claimed fixed.

## v7.7.0 (2026-10-31)

V7.7-Q quality pass: finished-video editing quality on real footage (`examples/auto_edit_benchmark.py`
over a real CC0 interview), prioritized by what actually moves a finished video rather than feature
count. Tools: 520 -> 520 (new optional args on two existing tools, no new tool names).

- **B-roll placed by what's actually being said, not just given order**: `place_broll` now takes
  optional `words` (a timeline-second transcript) and `asset_tags`; a curated keyword/synonym table
  (deliberately plain-English, not a classifier) and a filename-keyword fallback score each b-roll
  asset against each speech slot and assign greedily, so "...when I was learning to type..." pulls the
  typing clip instead of whichever b-roll happened to be listed first. Falls back to the old given-order
  behavior byte-for-byte when no words/only one asset. `auto_edit` transcribes dialogue once, right
  after the rough cut, and feeds that same transcript to both b-roll placement and captions (no second
  transcription pass). Verified honest: on the real benchmark interview, which never mentions any of its
  three b-roll concepts (typing/city/coffee), the matcher correctly found nothing and fell back to given
  order -- proven separately on footage with real spoken-concept matches via dedicated TDD.
- **Per-page caption y-nudge, not whole-group**: `lint_edit`'s `text_over_subject` fix used to flag only
  the first colliding page of a multi-page caption, then move the WHOLE group by that one page's offset
  -- the flagged page landed right, every other page (including already-fine ones) shifted by the same
  amount for no reason. Every page is now evaluated against its own sampled saliency peak and fixed with
  its own `set_property` (single clip's y), not a shared `set_caption_style` across the group. Verified
  on real footage: 5 of 31 caption pages got distinct per-page y values instead of one shared default.
  Honest limitation found and kept, not hidden: the saliency detector is a spectral-residual heuristic,
  not real face detection, so on one busy-background frame (patterned shirt, ornate mirrored room) it
  still reads background clutter as salient as the face and leaves a partial overlap -- a pre-existing
  DSP-heuristic ceiling, not something this pass caused or can fully close without real face detection.
- **Subscribe-style end screen**: `auto_edit` gets a new stage after the final mix -- a short (2-4s,
  default 3s) outro card using the existing `subscribe_pop` title preset, defaulting on for a
  landscape/youtube-style edit (`platform` none) and off for a vertical short (a subscribe pill fights
  the platform's own UI there), always overridable (`end_screen`/`end_screen_text`/`end_screen_duration`).
  New `total_duration` on the result reports the real export length; `duration` stays the talking-head-
  only number existing callers already read.
  - Caught on the real render, not a synthetic fixture, and fixed before this landed: the `subscribe_pop`
    pill was a fixed 230px tuned for the single word "SUBSCRIBE" -- the end screen's own default text,
    "SUBSCRIBE FOR MORE", ran past both of the pill's rounded ends, and its accent dot (a fixed offset
    that only happened to clear "SUBSCRIBE"'s first letter) landed on top of the "S" with the wider
    label. The pill now sizes itself to the real text (`crate::text::measure`, same tight-ink-extent
    approach as the caption-pill fix below it in this changelog's prior release), the dot moved outside
    the pill beside it, and the card now sits over a blurred, darkened freeze of the video's own last
    frame instead of flat black. That freeze is a real media clip placed after all speech ends, which
    tripped an unrelated existing check (`broll_over_silence`) into "fixing" it back onto the dialogue
    and trimming it to nothing -- that check now exempts a clip placed after all speech has ended (an
    epilogue/end-screen shot) while still correctly flagging b-roll laid over a genuine mid-edit pause.
- **Disk-leak fix (not a feature, worth noting)**: `director_small`'s shared fixture temp dir (reused by
  path across the whole test binary, so fixture media an earlier test builds is found, not re-encoded,
  by a later one) was never removed -- 83 of them, ~3 GB, found on one box. It now registers a libc
  `atexit` hook (no new dependency) the first time it runs, removing the dir once the whole binary is
  done with it.

## v7.6.0 (2026-10-31)

V7.6-Q2 quality pass on `real_v1.mp4` (a real CC0 interview auto-edit), continued from a prior
worker's mid-task exit. No new tools this round -- every change below improves what `auto_edit` and
`add_punch_ins`/`add_keyword_pops` actually deliver on real footage, verified by rendering real_v1's
own clips through the fix each time, not just synthetic fixtures. Tools: 520 -> 520 (two new optional
args on two existing tools, no new tool names).

- **Caption pill hugs the text, not the wrap width**: a boxed caption's background box was sized to
  the full available wrap width regardless of how short the actual line was -- a one-word caption got
  a bar spanning nearly the whole frame. `coverage()` now computes the tight ink extent of the line's
  own glyphs for the bg-box path. Verified: the pill width for a short caption dropped from 1048px to
  under 500px on real footage; golden frames unaffected (only the bg-box path reads the new bounds).
- **New `examples/auto_edit_benchmark.py`**: a reproducible one-command pipeline (clips folder ->
  finished mp4, with a JSON summary of duration/LUFS/lint/clip counts) reconstructed from the actual
  real_v1 render after no script or shell history survived the worker that first produced it.
  Auto-discovers talking-head/b-roll/music clips by filename; `--level-strength`, `--no-level-dynamics`
  flags added in the same pass as the LRA fix below.
- **`finish_audio`'s loudness range actually narrows now**: the per-clip highpass+compressor only
  ever matched each dialogue clip's AVERAGE loudness to the loudest one -- whatever swing already
  lived within a clip rode straight through. A gentle master-bus speech leveler (ffmpeg `speechnorm`)
  now runs once over the whole mixed timeline, loudness-neutral (so it doesn't fight `finish_audio`'s
  own gain-convergence loop -- the first per-clip attempt at this made LRA worse, not better, for
  exactly that reason). `level_dynamics`/`level_strength` on `finish_audio`/`auto_edit`, default on.
  Measured on real_v1: LRA 11.1 -> 6.8 LU (target 6-8), -14.55 LUFS (closer to -14 than the unleveled
  -14.87), -3.94 dBTP (more headroom, not less).
- **Punch-in zoom variety**: `add_punch_ins` alternated wide/punched but every punched clip zoomed by
  the exact same amount -- mechanical on a longer edit. New opt-in `variety`/`variety_amount` (default
  off, so direct calls and existing tests are unchanged) cycles each punched clip's own zoom through a
  fixed, deterministic sequence (never random, never drops near 1.0 so a punch always still reads as
  punched in; the focus point is recomputed per clip so it never drifts). `auto_edit` turns it on by
  default. Verified on real_v1: its two punch-ins landed at 1.132x and 1.1635x off a 1.15x base --
  genuinely different amounts.
- **`add_keyword_pops`'s `sfx:true` plays a real sound now**: previously a complete no-op with a
  warning (the prior research pass marked pop sound effects unverified for lack of a bundled asset,
  and media is never committed to this repo). Now synthesizes a short procedural "pop" blip at call
  time (ffmpeg lavfi tone, not a sampled/downloaded file) and places it on its own audio track, one
  per pop. Verified the mix is actually audible at each pop, not silently placed.

Full gate suite: unchanged pre-existing failures only (confirmed against the pre-session commit in a
throwaway git worktree for each one before touching anything) -- a `director_small` text-crowding
test, a `search_tools` ranking tie unaffected by any of this session's added schema text, one unmarked
`xform_lint` read, and a stray doctest in `robust_est.rs`; two more (`lint_edit` timing, `pick_thumbnail`
/ `push_wipe` temp-file setup) only fail under full `-j2` parallel load and pass clean alone. Goldens
(`golden_frames`, `recipes`) unchanged throughout -- every schema change that grew a tool's registry
hash was hand-verified and hand-updated in `golden_registry.txt`, `KIMO_UPDATE_GOLDEN` was never used.
`kimo-core` lib warnings: 34 (unchanged).

## v7.5.0 (2026-10-30)

Naman's standing instruction continued: "keep working, and keep sending updates." Picked up straight
from v7.4.0 (512 tools). Re-audited the registry and FEATURES.md first (most candidate ideas --
caption styling, a rough cut, project diff -- were already covered pre-v7.5; real gaps found and
built instead). 8 features shipped, each with its own TDD commit:

- New `close_gaps`: general ripple-close for any/all gaps on named or all-unlocked tracks in one
  call, where before it was one `ripple_delete`/`drop_short_segments` call per gap. `min_gap`,
  `include_leading_gap`, `dry_run`; a locked track named explicitly errors, one omitted is skipped and
  reported. 11 new tests. Tools: 512 -> 513.
- New `duck_timeline`: ducks every named music track under the union of speech from every named
  dialogue track in one call, reusing `auto_duck`'s own `speech_windows` path rather than
  reimplementing it. 6 new tests with synthetic voice-burst audio. Tools: 513 -> 514.
- `kimo gui` copy/paste and ripple-delete: Ctrl/Cmd+C/V copies and pastes selected clips as one
  atomic `batch` of `duplicate_clip` calls preserving relative offsets; Shift+Delete ripple-deletes a
  single clip. Pure shared module `gui_clipboard.js`. 20 Node tests + 5 Rust tests.
- `kimo gui` marker/chapter list panel: every project marker in one scrollable list, click a row to
  seek the playhead there, `x` removes it. Pure shared module `gui_markerpanel.js`. 13 Node tests + 3
  Rust tests.
- `kimo gui` render queue panel: every export job started from the GUI gets its own row, polled
  independently of the main preview loop until it reaches a terminal state, then it is dismissable.
  Pure shared module `gui_renderqueue.js`. 15 Node tests + 3 Rust tests.
- New `import_clips`: copy specific clips -- with everything a clip itself holds (effects, keyframes,
  masks, its own embedded grade graph, speed) -- from another project revision into the live project
  at a chosen track and time. Reuses `project_diff`'s own revision forms (`current | undo:<n> |
  checkpoint:<name> | file:<path.kimo>`) rather than re-implementing project loading. Every copied
  clip gets a fresh id (two independent project files can reuse the same ids); a media clip's asset
  imports into the destination's own asset pool too, reused by file path or created fresh. Honest gap:
  a project-level shared grade-scope binding does not travel, only a clip's own embedded grade. 13 new
  tests. Tools: 514 -> 515.
- New `style_captions_batch`: apply one style to every caption group in the project, or a named list
  of them, in one call -- `set_caption_style` already restyles every cue inside ONE group, but a
  project can hold several groups (different speakers, different tracks, an SRT import plus a later
  `caption_from_words` pass), and restyling all of them before this was one call per group. Reuses
  `set_caption_style` itself rather than reimplementing the per-cue styling math. 8 new tests. Tools:
  515 -> 516.
- `kimo gui` keyframe lane: a dropdown of every animated property on the selected clip (clip
  transform props and effect params, labelled with key count), and a lane showing that property's
  keyframes across the clip's own duration. Click a diamond to remove it, click empty lane space to
  add one seeded with the value already playing there (so adding a keyframe never silently resets the
  value). A click is classified existing-key vs empty-lane by mirroring `move_key`/`remove_key`'s own
  "nearest key within half a frame" rule. No dragging yet (left to `move_key` through the generic tool
  invoker). Pure shared module `gui_keyframes.js`. 21 Node tests + 5 Rust tests.

Also fixed along the way: `close_gaps` had no toolgroup heuristic match (`every_tool_has_a_real_group`
caught it at the mid-lane checkpoint); added to the `timeline` exact-match list.

Full workspace suite: 2590 passed, 2 failed -- both pre-existing and untouched by this release:
`readme_v3_tool_count_matches_the_registry` (the README's tool count is stale; fixing it is out of
scope for this lane) and a doctest in `robust_est.rs` (a vendored OpenCV license notice inside a `//!`
doc comment that rustdoc tries to compile as code; the file is byte-identical to v7.4.0). `kimo-core`
lib warnings held at 34 (budget 35), no new warnings introduced. Tools: 516.

## v7.4.0 (2026-10-30)

Naman's standing instruction continued: "keep working, and keep sending updates." Picked up straight
from v7.3.0 (508 tools). Re-audited the registry and FEATURES.md first (close_gaps/ripple delete,
batch caption styling, timeline diff and a generic rough-cut were all already covered pre-v7 --
confirmed and NOT duplicated); real gaps found and built instead. 8 features shipped, each with its
own TDD commit:

- New `track_mute_solo`: not from the audit's suggestion list, but a real pre-existing bug found while
  reading the audio path -- `Track.muted` has existed since before v7 and every audio-render/analysis
  path already honoured it, but no tool could ever set it. `set_track` now accepts `muted` and the
  standard NLE companion `solo` (solo-overrides-mute semantics, centralised in
  `model::effective_mute`). 9 new tests including a real ffmpeg-tone-silenced-by-mute test. Tools: 508
  (unchanged).
- New `export_edl`: the write-side counterpart to v7.3's `import_edl`. Exports the timeline as
  CMX3600 EDL, OTIO JSON (round-trips through `import_edl`'s own parser) or a minimal FCPXML. Non-media
  clips and non-1.0-speed clips are reported, never silently dropped or wrong. 10 new tests. Tools:
  508 -> 509.
- New `reframe_timeline`: v7.2's `auto_reframe` keys one clip; v7.3's `export_variants` touches every
  clip but restores everything after one export. This is the persistent, undoable whole-timeline
  aspect conversion that actually changes the canvas for real -- one undo step reverses the whole
  thing. Protects manually-framed clips unless `overwrite_existing`. 11 new tests. Tools: 509 -> 510.
- New `list_project_templates`/`create_project_from_template`: 5 starter templates (vertical/square
  social, 16:9 widescreen, podcast interview, multicam panel) with canvas/fps/named-track-layout, one
  call instead of a blank canvas plus manual `add_track` calls every time. 7 new tests. Tools:
  510 -> 512.
- `kimo gui` track mute/solo/lock controls: M/S/L buttons per track wired onto `set_track`; a locked
  track's clips stop accepting drag/trim in the GUI. Pure shared module `gui_trackstate.js`. 13 Node
  tests + 4 Rust tests.
- `kimo gui` multi-select and group move/delete: shift/cmd/ctrl-click selects several clips; dragging
  any one moves the whole group as one atomic `batch` call (one undo step); Delete removes them all
  the same way. Pure shared module `gui_multiselect.js`. 19 Node tests + 5 Rust tests.
- `kimo gui` clip waveforms: every media clip bar shows its real audio waveform, wired onto
  `audio_transients`' existing `image: "waveform"` SVG option (no new peak-computation code). Pure
  shared module `gui_waveform.js`. 15 Node tests + 5 Rust tests.
- `kimo gui` effects/transitions browser: the bare effect-kind `<select>` is now a real searchable
  list combining `list_effects` and `list_transitions` (two genuinely different catalog shapes),
  click to add to the selected clip. Pure shared module `gui_fxbrowser.js`. 12 Node tests + 4 Rust
  tests.

Also fixed along the way: `reframe_timeline`'s hand-rolled aspect-enum error message collided with
`dispatch_ex`'s own `invalid_value` short-circuit and tripped `registry_lint`'s
`every_schema_enum_rejection_lists_allowed_values` check (caught by the full-suite run, not by its own
feature commit); rephrased to the same "X must be ..., got 'Y'" shape `export_edl`'s own enum error
already used successfully. A filesystem-fixture race in the waveform tests (two tests sharing one
PID-keyed temp dir name, racing on parallel test threads) was found and fixed with a per-call counter.
Two trivial unused-`mut` warnings removed (zero behaviour change), taking kimo-core's own warning
count from 36 to 34.

`kimo-gui` (the separate Tauri spectator shell under `crates/kimo-gui`) is deliberately its own
workspace (see its Cargo.toml comment) and carries its own `6.0.0` version, unrelated to and not
tracking this workspace's version -- not touched by this release, by design, not oversight.

README.md's own tool count is out of date as of this release (not updated by this pass; a prior
release noted the same `readme_count` test as a known, deliberately-left failure).

## v7.3.0 (2026-10-30)

Naman's standing instruction continued: "make ai agent a complete editor," "better than any editor
in the world," "keep working, and keep sending updates." Picked up straight from v7.2.0 (504 tools).
Re-audited the registry and FEATURES.md first against the two stated directions -- GUI usability and
agent-superiority engine tools -- before writing anything: several GUI gaps were real (zero keyboard
shortcuts, no track add/remove, no marker display, no snapping, no zoom bounds, no project open/save
button, no export progress bar) even though the underlying engine tools (`add_marker`/`list_markers`,
`add_track`/`delete_track`, `snap_time`, `export_job_start`/`job_status`/`cancel_job`) already
existed; on the engine side, `apply_review_fixes`, `auto_chapters` and `batch_normalize_loudness`
were genuine gaps, and EDL/OTIO import was a real missing capability with nothing close to it in the
registry. 11 features shipped, each with its own TDD commit:

- New `apply_review_fixes`: batch-applies `lint_edit`'s (and so `self_review`'s) machine-actionable
  fixes in one call instead of reading each problem and dispatching its fix by hand. Skips anything
  needing a human decision (a placeholder value, an "or" choice) under `skipped_manual`, never
  guesses. `dry_run` supported. 5 new tests. Tools: 504 -> 505.
- New `auto_chapters`: composes `mark_scene_cuts` + `mux_chapters` -- `mux_chapters` alone needs
  markers to already exist; this detects them first if there aren't enough, and reports plainly
  (not a failure) when even detection can't reach the minimum. 4 new tests. Tools: 505 -> 506.
- New `batch_normalize_loudness`: the write-side counterpart to v7.2's `find_by_loudness` --
  normalizes every/filtered media clip to a target LUFS in one call instead of calling
  `normalize_loudness` once per clip by hand. `tolerance_db` skips near-target clips. 6 new tests.
  Tools: 506 -> 507.
- `kimo gui` keyboard shortcuts: space/J/K/L/Delete/S/ctrl+z/ctrl+shift+z, served as a real static
  module (`gui_keymap.js`) so the browser and a headless Node test run the exact same bytes. 18 Node
  tests + 6 Rust tests.
- `kimo gui` add/remove tracks: a "+ Track" button and a per-track remove button, wired onto the
  existing `add_track`/`delete_track`. 3 new Rust tests.
- `kimo gui` marker display + add: markers render as ticks on the timeline (click to remove), a
  "+ Marker" button adds one at the playhead, wired onto the existing `add_marker`/`list_markers`/
  `remove_marker`. 5 new Rust tests.
- `kimo gui` timeline snapping: drag-to-move/trim snaps to clip edges, markers and 0 within an 8px
  tolerance (toggle checkbox, default on) -- the exact gap v7.1's own FEATURES.md entry named. The
  snap decision is a pure module (`gui_snap.js`) shared by the browser and a headless Node test. 10
  Node tests + 5 Rust tests.
- `kimo gui` timeline zoom: in/out/reset, bounds-clamped 4-400px/sec, also a pure shared module
  (`gui_zoom.js`). 10 Node tests + 3 Rust tests.
- `kimo gui` export with progress: a path field, Export button, live progress bar, ETA with
  uncertainty band, and Cancel, wired onto the chunked export system that already existed
  (`export_job_start`/`job_status`/`cancel_job`). 3 new Rust tests, including a real export reaching
  "done" with the file actually on disk.
- `kimo gui` project open/save: a path field with Save/Open buttons wired onto `save_project`/
  `load_project`; a successful open actually re-renders the timeline and clears the stale selection.
  4 new Rust tests, including a real save-then-reopen that replaces the live project.
- New `import_edl`: the editorial-interchange gap -- kimo could export EDL-adjacent things but had no
  way to bring a cut list IN. Imports a standard CMX3600 EDL or a simple single-video-track OTIO JSON
  timeline as real clips, resolving each event's source name via an explicit `media_map`, a
  `media_dir` scan, or a path the file already names, reporting anything unresolved rather than
  dropping it or failing the whole import. 9 new tests. Tools: 507 -> 508.

Also fixed along the way: `batch_normalize_loudness`'s own description ran 256 characters before its
first ". " (limit 149, caught by the full-suite run, not by its own feature commit -- a contract bug
of this release's own making, fixed in its own commit); `import_edl.rs`'s one `read_to_string` call
needed registering in `external_refs.rs`'s open-sites classification table (a caller-supplied tool
argument, not project-derived, not stored in the project).

golden_registry.txt hand-updated at every new-tool commit (504 -> 508 registered tools); goldens
(golden_frames, golden_registry) green throughout. Full workspace test suite green apart from the two
pre-existing issues already on record (README tool-count phrasing, out of scope; the `robust_est`
doctest, a pre-existing doc-comment artifact unrelated to this release) -- `pick_thumbnail` and
`external_refs` each showed one transient/real issue during this session's own full-suite runs and
were confirmed fixed (the latter) or confirmed a CPU-load flake, clean alone (the former), same as
`director_small`'s long-documented sensitivity. Warning count unchanged (35). No push anywhere --
all 11 commits plus this release are local to the `v7` branch.

## v7.2.0 (2026-10-30)

Naman asked to keep shipping new editor features; partway through, steered toward favoring
"agent-superior" features -- things that make an AI driving kimo through MCP alone, with no GUI and no
human eye on the monitor, better able to do a full professional edit, over GUI-parity features. Audited
the registry (501 tools before this session's growth) and FEATURES.md first: several planned candidates
turned out to already exist under other names once checked (`review_export` already did most of what a
planned `export_qc` would have; `get_curve`/`move_key`/`remove_key` already existed before
`list_keyframes`/`remove_keyframe` would have duplicated them; `find_assets` already had duration/fps/
size before `asset_info` would have duplicated it) -- extended instead of duplicated in each case. The 8
features shipped, each with its own commit:

- New `validate_timeline`: a structural health check (gaps, overlaps, zero/negative-duration clips,
  negative starts) independent of `lint_edit` (platform/export-readiness) and `list_dependencies`
  (missing media) -- the one structural check neither of those already does. Read-only. 10 new tests.
  Tools: 498 -> 499.
- `get_curve`/`move_key`/`remove_key` grow an optional `effect_id` to reach keyframes on an effect's own
  params, not just a clip's transform properties (backward compatible); new `list_animated_properties`
  discovers what's keyframed on a clip without already knowing the property name. 11 new tests. Tools:
  499 -> 500.
- New `find_by_loudness`: whole-project loudness query in one call (Naman's own example: "all clips under
  -20 LUFS"), reusing the existing `measure_loudness` per clip via `dispatch_nested` rather than
  reimplementing loudness measurement. 8 new tests. Tools: 500 -> 501.
- `find_assets` grows into a shot list: `kind`/`hash`/`origin` (already on the `Asset` model, just
  unsurfaced), a new `used_by_clips` reverse-lookup count, and an opt-in `probe_audio` flag for
  `has_audio` (reuses `audio::source_info`, default off so the common call stays cheap). 5 new tests.
  Tool count unchanged (501) -- an extension, not a new tool.
- New `self_review`: one-call orchestration of `lint_edit` + `validate_timeline` + `list_dependencies`,
  correlating every source's flagged moments into one merged report instead of calling three tools and
  matching times up by hand; an optional `path` also renders a `contact_sheet` of what it found, so the
  report comes with evidence. Pure composition (`dispatch_nested`, no new checking logic); deliberately
  NOT auto-fix -- `lint_edit`'s own problems already carry the exact fix call each needs, and applying
  them unasked is outside this tool's scope. 8 new tests. Tools: 501 -> 502.
- `review_export` grows QC: checked for duplication first and found `review_export` already reports
  duration/size/width/height/LUFS/peak plus a contact sheet, so a separately-planned `export_qc` would
  have nearly duplicated it. Added `video_codec`/`audio_codec` (same ffprobe call) and an opt-in
  `expect_project` that compares the exported file's duration and resolution against what the LIVE
  project should currently produce (the same max-clip-end technique `lint_edit` uses), catching a stale
  or wrong-size export; an empty project reports no expectation rather than a false mismatch. Backward
  compatible. 7 new tests. Tool count unchanged (502).
- New `explain_cut` (BETA, best-effort): why a clip's incoming cut might exist. Built for an agent with
  no eye on the monitor -- it can't glance at a cut and judge it the way a human editor would, so this
  hands it the same evidence instead: the clip's own `transition_in`, nearby timeline markers
  (`add_marker`/`mark_scene_cuts`) within a configurable window, whether it's the same source asset as
  the clip before it (a split within one shot vs. a cut to new footage), and whether `detect_cuts` finds
  a real visual change right at the boundary. Says plainly when the evidence runs out rather than
  inventing a reason; not a real decision ledger (that would mean threading provenance through every
  mutating tool). 11 new tests. Tools: 502 -> 503.
- New `check_color_consistency`: the read-only diagnosis `match_color` (one clip) and `match_shots`
  (every clip, mutating, uniform) had no counterpart for -- which clips actually disagree in brightness/
  color before reaching for either fix, or whether a fix afterward actually closed the gap. No new pixel
  analysis: samples each clip's own midpoint through the existing `get_scopes`, compared against a named
  `ref_clip_id` or, by default, the checked group's own median. 9 new tests. Tools: 503 -> 504.

69 new TDD tests across the 8 feature commits, plus one small test-fixture fixup caught by this
release's own full-suite run: `self_review.rs`'s `clean_media_scene` helper built its fixture path from
a fixed tag, and two different tests sharing it wrote to the exact same path under the full suite's real
concurrency -- a test-fixture bug, not a `kimo-core` bug; fixed by giving each caller its own tag.
golden_registry.txt hand-updated at every tool change (498 -> 504 registered tools); goldens
(golden_frames, golden_registry) green throughout. Full workspace test suite green apart from the two
pre-existing issues already on record (README tool-count phrasing, out of scope; `director_small`'s
`lint_edit` timing test, which is sensitive to concurrent CPU load on this machine and passes clean
every time it's run alone -- confirmed repeatedly during this session). Warning count unchanged (35).
No push anywhere -- all 8 commits plus this release are local to the `v7` branch.


## v7.1.0 (2026-10-30)

Naman asked for new features added to the local v7 branch. Audited the registry (495 tools) and
FEATURES.md first: most of the obvious directions (beat-detection auto-cut, auto-reframe, silence/filler
trim, scene-change detection, loudness-normalized ducking, project diff, timeline search) already shipped
in v7.0.0 under different names (`beat_cut`/`detect_beats`, `auto_reframe`, `remove_silence_cuts`/
`trim_filler_words`, `detect_cuts`, `auto_duck`/`measure_loudness`, `project_diff`, `find`). The 8 real
gaps found, each with its own commit:

- `find` gains a `has_effect` filter (which clips carry a given effect kind) and lists every clip's
  effect kinds on every result -- the one real gap in the existing clip/track query tool. 1 new test.
- New `project_merge`: the write-side of `project_diff`, which only ever reported. Two-way clip-level
  merge (base -> theirs, same revision forms as `project_diff`) onto the live project, matched by id,
  with four conflict shapes detected against the common base (add_add, edit_edit, edit_removed,
  remove_modify) rather than just against each other, so an edit that happens to land on the same end
  state on both sides is never a false conflict. `on_conflict`: fail (default)/theirs/base, plus
  `dry_run`. 5 new tests. Tools: 495 -> 496.
- New `mark_scene_cuts`: automates the existing `detect_cuts`-then-`add_marker`-per-cut workflow into
  one call. `skip_existing` (2-frame tolerance) means calling it twice does not pile up duplicate
  markers. Not a duplicate of `scene_split` (splits clips) or `detect_cuts` (read-only). 4 new tests.
  Tools: 496 -> 497.
- New `export_variants`: batch-exports several size/aspect-ratio deliverables (named presets 16:9/9:16/
  1:1/4:5, or explicit width/height) from one project in a single call -- `batch` explicitly forbids
  `export*` tools, so this previously needed several manual exports with the project's canvas hand-edited
  in between. Optional `auto_reframe` per differing-aspect variant (window removed again right after);
  the project's own canvas is always restored, success or failure; variants are independent. 5 new tests.
  Tools: 497 -> 498.
- `kimo gui` deepened into an actually-editable local editor, in 4 commits:
  - Clip detail endpoint (`GET /api/clip?id=`) + an effect-params panel: select a clip, see and edit its
    properties and every effect's params live, add/remove effects -- all through tools that already
    existed (`set_property`, `set_effect_param`, `add_effect`, `remove_effect`, `list_effects`), no new
    dispatch path. 3 new tests.
  - Editable timeline: drag a clip to move it (`move_clip`) or drag its right edge to trim it
    (`trim_clip`); clip bars switched to absolute positioning (start * px/sec) so a moved clip isn't
    forced back into a gapless sequence. A sub-3px drag is treated as a click (selection), not a move.
    1 new test.
  - Scrub and play: no new backend route -- JS drives the existing `/preview.png?t=` repeatedly. Play
    steps forward on a wall-clock-paced tick (real elapsed time, so it tracks actual speed rather than
    drifting); clicking/dragging the timeline background scrubs; a playhead line stays in sync. Honestly
    a frame-stepped preview, not a video element. 1 new test.
  - Undo/redo + a history panel: buttons wired to the pre-existing (pre-v7) bounded undo/redo tools,
    which the GUI simply hadn't exposed yet; a history panel lists every undo/redo step by tool name.
    2 new tests.
  - 17/17 gui tests green; every GUI change was also hand smoke-tested against a live server (curl
    through the exact call sequences the JS drives), the way the original v7.0.0 GUI commit was.

22 new TDD tests across the 8 commits. golden_registry.txt hand-updated at every tool change (495 -> 498
registered tools); goldens (golden_frames, golden_registry, golden_project) unchanged throughout. No
push anywhere -- all 8 commits are local to the `v7` branch.

## v7.0.0 "studio" (2026-10-29)

- Particles (FEATURES.md L483): new `bubbles` and `foam` emitter presets, and a new `card` sprite kind (a flat
  rectangle whose half-width scales by `|cos(phase)|`, phase a pure function of time+seed -- a 2D stand-in for a
  3D card flip) with a `card_dance` preset built on it. Credited, not duplicated: `add_emitter`'s existing
  forces/gravity/wind/drag/turbulence/attractor/vortex/trails/colliders (analytic + layer-silhouette),
  `simulate_physics` (deterministic circle-proxy rigid bodies) and `shatter`/`shatter_cells` (glass-shard
  transitions) already covered most of this line pre-v7 and were uncredited; fixed in passing, a stale baseline
  in error_codes.txt (claimed `list_effects` returns 182 kinds; it returns 185 since an earlier lens-blur commit
  added 3 without updating it). 7 new TDD tests. Honest gaps: no real fluid/smoke grid solver, no cloth sim, no
  polygon/joint rigid bodies, no true cannon-driven Card Dance, no lens-droplet refraction.
- GPU pipeline (FEATURES.md L557): new optional `gpu2d` build feature (default off, separate from the existing
  `gpu3d`/wgpu mesh path so this doesn't pull in its dependencies) -- real WGSL compute shaders (`gpu_gaussian_blur`,
  separable 2-pass; `gpu_color_matrix`, an AE-style 4x5 matrix, single-pass) through wgpu's adapter/device/
  compute-pipeline API, run and proven on this box's software Vulkan (Mesa lavapipe): GPU-vs-CPU max_abs_diff
  measured at exactly 0.0 on both. Exposed as 3 read-only diagnostic MCP tools (`gpu2d_status`,
  `gpu_gaussian_blur_frame`, `gpu_color_matrix_frame`) -- standalone, not wired into `add_effect` or the default
  render path, so every golden reference frame is unchanged. Tools: 490 -> 493 registered. Honest gaps: no GPU
  compositing of the main pipeline, no persistent VRAM frame textures, no async readback, no NVENC/hardware GPU
  (lavapipe is software-only).
- MOGRT substitute (FEATURES.md, title/lower-third line): new `export_template_package` / `import_template_package`
  (ext/templates.rs) bundle a named template (the pre-existing `template_define`/`apply`/`list`/`describe`/
  `delete` parametric batch-template system) together with its clips' `essential_properties` marks (also
  pre-existing, the MOGRT-style "which knobs to expose" tags) into one JSON file -- Kimo's own open one-file
  substitute for Adobe's closed/proprietary `.mogrt` container. Round-trips within or across projects: import
  matches essential marks back onto clips by role first, falls back to the original clip_id, and reports (never
  silently drops) anything unmatched. 5 new TDD tests. Tools: 493 -> 495 registered. Honest gap: no Adobe
  `.mogrt` IMPORT (closed format, not attempted) and no thumbnail/preview asset in the package.
- GUI (FEATURES.md L562, the one item this project had marked `[ ]`): new `kimo gui [--project p.kimo]
  [--port 4567] [--bind 127.0.0.1]` -- a minimal local web UI (crates/kimo-cli/src/gui.rs + gui_index.html,
  std::net only, no new dependency) over the exact same tool registry/dispatch the CLI and MCP server already
  use. A timeline view (GET /api/timeline), a preview frame rendered by the real engine (GET
  /preview.png?t=<seconds>, the same render_png export/render_frame use), and a tool-invocation panel (GET
  /api/registry, POST /api/call running through the same `run_tool` path as `kimo call`). Headless-testable: its
  whole routing table is a pure `handle_request(session, method, path, query, body)` function with no socket in
  it (12 new tests), smoke-tested by hand against a live server. Credited alongside the pre-existing (and
  previously uncredited) **Kimo Spectator** desktop app (crates/kimo-gui, its own Tauri workspace): Spectator is
  a read-only live view of an agent's own edits (no IPC commands exist, by construction); `kimo gui` is the new,
  complementary piece -- something a human can actually drive. Honest gaps: no JS framework or build step
  (one small inline page, on purpose), no scrubbing/playback, no drag-to-trim/drag-to-move on the timeline
  (read-only, not yet editable), no auth (loopback tool), no multi-client session sharing, no desktop packaging.
- FEATURES.md: every remaining `[ ]` item is now `[x]` or honestly `[~]` (57 `[x]`, 48 `[~]`, 0 `[ ]`).
- Known, unchanged in this release: `readme_count` fails because README.md's tool-count badge text does not
  contain the literal phrase "registered tools" the test looks for (not a wrong number -- the phrase is simply
  absent); the fix is a one-line README wording change, out of scope for this pass (README.md was intentionally
  left untouched). `robust_est`'s doctest fails to compile on an unrelated pre-existing doc-comment issue
  (a "License Agreement" line inside a doctest code block that rustdoc tries to parse as Rust). Both predate this
  release and are unrelated to anything shipped in it.

## v6.0.0 "eyes" (2026-10-27)

- Added `transcript_search`: normalized phrase lookup with script indexes, timeline ranges and ready-to-use delete operations.
- Added `transcript_edit_apply`: revision-checked, atomic all-track ripple deletion with transcript/caption/marker updates, source/keyframe continuity, dry-run validation and undo/redo. The first version supports explicitly bound normal-speed media and rejects ambiguous edits. See [transcript editing](docs/TRANSCRIPT_EDITING.md).
- `transcript_edit_preview` now returns a project revision and rejects invalid `to_index` types. Added Windows guards around Unix-only code-clip process-group calls.

- `vignette` is shaped and tracked: new params `center_x`/`center_y`, `roundness` (0 frame-shaped .. 1 true circle), `squareness` (ellipse .. rounded rectangle), `size`, `aspect`, `feather`, `color_r/g/b` (tint the edge instead of darkening), and the centre can follow a clip moved by `track_point` (`strings.source_clip`) or a mask layer such as one `track_mask` keyed (`strings.source_mask`, its centre / mean point). A call with only `amount`/`softness` renders exactly as before.
- New transition kind `film_burn`: a seeded hot burn blooms from a point with a noise-ragged edge, blows the frame out orange/white at the cut, flickers, then burns off into the incoming shot (`intensity`, `seed`).
- New tool `flash_series` (group `scopes`, read-only): per-frame linear relative luminance (sRGB decode, Rec.709 Y), red saturation R/(R+G+B) and red quantity, luminance and red transitions, changed-area fractions, and per-window transition counts with window start times. Window length and thresholds are arguments; raw numbers only, no pass/fail. Harding / ITU-R BT.1702 / WCAG reference values are in the tool description only. Tools: 376 → 377 registered, flat `tools/list` 378 → 379.
  Next (documented, not implemented): the WCAG 2.2 red-flash rule (a 0.2 change in CIE 1976 u′v′); only the WCAG 2.0 (R−G−B)×320 red measure is computed today.
  Per-window flash counts come two ways: `lum_flashes` / `red_flashes` count a flash in every window it touches, `lum_flashes_fully_inside` / `red_flashes_fully_inside` only where both of its transitions fall inside the window. `params_used.max_resolvable_hz` reports fps / step_frames / 2. Next (not in this release): an optional `min_area_fraction` argument so a flash over a small part of the frame can be left out of the counts; today `changed_area_fraction` is reported but does not feed the counts.
  Transition stamps: a luminance or red transition is stamped on the first frame that crosses `lum_delta` (or `red_delta`) inside the monotonic run that reaches the swing's extreme (strict-run guard), so the stamp marks where the change starts, not where a slow drift after it peaks; no tolerance argument. On the jaja ad the six luminance stamps move from 4.958 … 34.708 s to 4.750, 9.667, 14.750, 24.750, 29.708, 30.542 s; counts unchanged. The spectator's info panel lists the stamps on a Stamps row.
- `measure_loudness` (extended, no new tool): new optional arguments only. `curve` (momentary / short_term / both) adds ungated EBU Tech 3341 momentary (400 ms) and short-term (3 s) LUFS series every `hop_s` (0.1–3 s in 0.01 s steps, default 0.1; a value outside that range is an error, never clamped) with each series' max, and `max_points` (10–100000) raises the hop so each series holds at most that many readings; a curve over 100000 readings is refused with an error naming the fix; `lra` adds the EBU Tech 3342 loudness range (−70 LUFS absolute and −20 LU relative gates, 95th − 10th percentile) with its low/high levels; `clip_threshold_dbfs` adds clipped sample and frame counts. All three reuse the engine's own BS.1770 K-weighting (no new dependency). The existing `true_peak` stays: 4x oversampling with a 64-tap-per-phase windowed sinc, the BS.1770-4 Annex 2 method, now pinned by an fs/4 intersample test. Raw numbers only. With none of the new arguments the output is byte-identical to v5.0.0 (pinned by a test). Tools unchanged: 377 registered, flat 379. The audio panel shows LRA when it is returned.
- New tool `audio_spectrum` (group `audio`, read-only): averaged magnitude spectrum and band energies in dBFS of the final timeline mix or one clip (post filters, before volume/pan, as `measure_loudness`), optional `start`/`end`. Periodic Hann window, `fft_size` a power of 2 from 256 to 65536 (default 4096), frames every `fft_size`/2, L and R power averaged. `peak_hz`/`peak_dbfs` and `spectrum` are amplitude dBFS (a full-scale sine centred on a bin reads 0); `total_dbfs` and band `dbfs` are power dBFS (RMS level, a full-scale sine reads -3.01, as ffmpeg astats). `bands`: octave (default, IEC 61260 base-ten, 31.5 Hz-16 kHz), third_octave (25 Hz-20 kHz) or custom edges in Hz. `spectrum_points` (default 256, 0 omits) caps the spectrum as log-spaced points; `hop_s` adds `band_series` (band levels per hop), `max_points` raises that hop the way `measure_loudness`'s curve does and both `requested_hop_s` and `hop_s` are returned; a series over 200000 values is refused. Out-of-range arguments are errors, never clamped; silence reads null. New dependency: rustfft 6.4.1 (MIT OR Apache-2.0; pulls in primal-check 0.3.4, strength_reduce 0.2.4, transpose 0.2.3, all MIT OR Apache-2.0). Spectator: a qa rail row and info panel rows (Range, Peak, Loudest band, Total) read only the result's top-level numbers, so the bands and spectrum arrays the event cuts to 8 entries are never read.
- `diff_frames` (extended, new optional arguments only) and new tool `compare_ranges` (group `output`, read-only): full-reference picture metrics on luma, our own code from the published formulas. Luma is Y' = 0.2126 R' + 0.7152 G' + 0.0722 B' (BT.709) on the display-referred R'G'B' kimo renders, data range 255. PSNR = 10 log10(255²/MSE); identical frames return `"psnr_db": null` with `"identical": true` (JSON has no infinity), or `psnr_cap_db` when given (which also caps the rest). SSIM per Wang et al. 2004 (11×11 Gaussian, σ 1.5, K1 0.01, K2 0.03, valid windows, mean of the map); MS-SSIM per Wang et al. 2003 (5 scales, weights 0.0448/0.2856/0.3001/0.2363/0.1333, needs 176 px on the short side; a negative term returns null, never NaN). `diff_frames` takes `quality: ["psnr","ssim","ms_ssim"]` and adds a `quality` object; the existing v5 `metrics` (PSNR 99 on identical, 8×8 block SSIM) are untouched and without `quality` the output is byte-identical to v5 (pinned by a test against bytes captured from the 5ad355c binary). `compare_ranges` compares two sources or time ranges (`a`/`b` = `{source, start}`, shared `duration`) every `hop_s` (whole ms, default 1) or `step_frames`, returning `t_s` with `psnr_db` / `ssim` / `ms_ssim` curves, `identical_count` and a summary per metric (mean, min with its time, p5, max); `max_points` (2–2000) raises the hop the way `measure_loudness`'s curve does and returns both hops, and more than 2000 samples without it is an error. Out-of-range arguments are errors, never clamped. Spectator: `diff_frames` gains a Quality row when `quality` is passed, and `compare_ranges` shows Range / PSNR / SSIM / MS-SSIM rows read from the summary's scalars only; the `diff_frames` Compared row now wraps instead of being cut by an ellipsis.
- `get_scopes` (extended, new optional arguments only; without them the output is byte-identical to v5): `percentiles` (1..32 values in 0..100, strictly ascending) adds `luma_percentiles`, `chroma_percentiles` (the BT.709 vectorscope radius sqrt(Cb²+Cr²), Cb = (B′−Y′)/1.8556, Cr = (R′−Y′)/1.5748), per-column `waveform_percentiles` (`waveform_columns` 1..256, default 16 or the frame width when narrower), `cb_mean`, `cr_mean` and `chroma_mean`; `zones` [cols, rows] (1..32 each) adds per-zone `zone_crushed_blacks_pct` / `zone_clipped_whites_pct` (row-major) and their maxima at `crush_below` / `clip_above` (0..1, defaults 0.02 / 0.98, the v5 constants). Luma is the v5 luma; percentiles are numpy's linear interpolation. Raw numbers, no verdict; bad arguments are errors, never clamped. The spectator's get_scopes card shows the luma spread, chroma mean and worst zone when they are present.
- New tool `contrast_ratio` (group `scopes`, read-only): the WCAG 2.x contrast ratio (L1 + 0.05) / (L2 + 0.05) between two colours (`"#rrggbb"`, `"#rgb"`, [r,g,b] 0..1) or two pixel rects `{"rect": [x,y,w,h]}` of the frame at `time`, or one of each, with each side's relative luminance (sRGB EOTF with the 0.04045 knee, Rec.709 weights; a rect's luminance is the mean of its per-pixel luminance, with p5 / p95 / min / max beside it). Optional `cvd` (protan, deutan, tritan) adds `ratio_protan` / `ratio_deutan` / `ratio_tritan` under the Machado, Oliveira & Fernandes 2009 colour-vision-deficiency matrices at `severity` 0..1 (default 1; the published 0.1 steps, linearly interpolated), applied to linear RGB and clamped to 0..1. Raw numbers, no pass/fail; bad arguments are errors, never clamped. Spectator: Ratio, Luminance a / b and Under CVD rows.
- `query_safe_margins` (extended, new optional argument only; without it the output is byte-identical to v5): `rects` (1..64 of `{name?, rect: [x,y,w,h]}` canvas pixels, may reach past the canvas, each coordinate within ±65536, w and h > 0, unknown keys refused) adds `overlaps`: per rect `area_px`, `outside_canvas_pct` and per zone `overlap_px` / `overlap_pct` (exact rectangle intersection with the zone rects as returned); for safe zones also `outside_pct`, `crossed_edges` (`[{edge: top|bottom|left|right, px}]`, how far the rect's edge lies past the zone's edge) and `suggested_shift` (`{dx, dy}`, the smallest move that puts the rect fully inside, rounded to 0.01 px; `null` when the rect is wider or taller than the zone). Top level: `rects_outside_safe_max_pct`, `rects_in_avoid_max_pct`, `worst_edge`, `worst_edge_px` (0 when nothing crosses), `worst_edge_rect`, `worst_edge_zone` (`null` when the profile has no zone of that kind). Raw numbers, no verdict. Spectator: with `rects` the read card shows Profile, Max outside safe, Max in avoid and Worst edge (`left 52 px · rect1`); without them Profile, Zones, Estimated and Source, with Source wrapped (the generic row clipped `documented-constant`).
- `get_scopes` description: the first sentence (145 characters) now names the numeric arguments, "Video scopes at a time: histogram, luma stats, clipping, plus optional brightness/colourfulness percentiles and per-zone blown-out/crushed share." The v5 sentence (155 characters) did not mention them. Output unchanged. New test `tests/description_first_sentence.rs` checks every registered tool's first sentence is under 150 characters; the 77 v5 tools already over it sit on a frozen, sorted allowlist that can only shrink (the test also fails when an allowlisted tool comes in under 150).
- `flash_series` (extended, new optional arguments only; without them the output is byte-identical to the previous build): `flash_limit` (> 0, <= 1000; 3 for the 3-flashes-per-second rule) adds the flash rule numbers as top-level scalars: `worst_window_start` / `_end` / `_flashes` (the earliest window with the most flashes, a flash counted in every window its span touches, as `lum_flashes`), `windows_over_limit` (windows with more than `flash_limit` flashes), `flash_area_pct_max` (a flash's area is the larger `changed_area_fraction` x 100 at its two transitions), `flashes_counted`, and the same six for red (`worst_red_window_*`, `red_windows_over_limit`, `red_flash_area_pct_max`, `red_flashes_counted`), plus `flash_rule_method`. `area_min_pct` (0..100, needs `flash_limit`) leaves out flashes whose area is smaller. Raw numbers, no verdict. Spectator: the flash_series card gains a Worst 1 s flashes row when the call gave `flash_limit` (`5 @ 5.92s, 27 > 3, area 98% · red 5 @ 7.67s, 15 > 3, area 25%`).
- `flash_series` pinned to the WCAG 2.x flash definitions (new optional `area_basis`, needs `flash_limit`; without it the output is byte-identical to the previous commit, pinned by tests/flash_pin.rs against three calls captured from that build). Definitions used: 1 s windows start at every sample (window_hop_s defaults to one frame), so a burst across a second boundary counts together; a flash is one pair of opposing transitions (rise then fall or fall then rise), a transition being a swing of >= 0.1 relative luminance (10 % of the maximum, 1.0) whose darker state is < 0.80, and a red flash the same pairing on saturated-red transitions (R/(R+G+B) >= 0.8, a (R-G-B) x 320 change >= 20); a flash counts in every window its span touches and a window with more than `flash_limit` (3) flashes counts in `windows_over_limit`. `area_basis: "field"` applies this per 10 degree visual field: 341 x 256 px at 1024 x 768 scaled per axis to the analysed frame (639 x 360 at 1920 x 1080; `field_px`), fields on a half-field grid (`fields`); each field's own mean luminance (red: mean red quantity) is paired into flashes, a flash counts only when MORE than `area_min_pct` (default 25) of that field changed, and the rule scalars are the worst field's, at `worst_field_rect` / `worst_red_field_rect`. `area_basis: "frame"` is the whole-frame reading. Fixtures: full-frame 4 Hz strobe fails, full-frame 2 Hz strobe passes, a 4 Hz strobe on 2.6 % of the frame (23.8 % of its field) passes; a compact box on 9.1 % of the frame (82 % of its field) fails on the field basis, which the whole-frame reading misses. GUI: on the field basis the flash_series card's Worst 1 s flashes row ends with the worst field (" · field x,y w×h").
- `flash_series` area_basis field: the 10 degree field now slides in steps of 1/8 field per axis (was a half-field grid), so any flashing patch up to 7/8 of a field per axis lies wholly inside one field wherever it sits; a patch straddling the old grid lines is no longer split. Field sums come from box sums (O(pixels) per sample). Fixtures in tests/flash_pin.rs: a 2.6 % strobe centred on a corner of the old grid passes like an uncentred one, a field-size strobe there fails; a 72x18 / 72x19 box (23.8 % / 25.1 % of the 85x64 field) passes / fails at five positions, where the old grid saw at most 20.3 % of the 72x19 box and passed it; a compact 4 Hz strobe on 9 % of the frame fails at 4:3 and 16:9. Default and flash_limit-only output unchanged; jaja + strobe counts unchanged (lum 12 counted, worst 5 @ 5.92 s, 57 windows over 3; red 5, worst 5 @ 7.67 s, 15 over), only the worst field rect moves (fields 30 -> 306).
- New `text_contrast_series` (scopes group): worst-frame WCAG 2.x contrast of text over moving video. Per frame of a range (step_frames, default every frame; with step_frames > 1 the frames between two samples around a cut are measured too, so every 2nd frame plus every cut is one call): the text colour or a text rect against the background luminance read as bg_stat (default worst = whichever of p5 / p95 gives the lower ratio; p95 = the brightest 5 %) of the ring around text_box (burned-in text), the pixels under text_box (bg_region box) or a background rect. Reports the WORST frame with its time, frame and ratio (no averages), best ratio, frames_sampled, cut_frames_added. text_px (+ bold, true only for weight 700+; semibold counts as normal) gives size_class at 1080 p and the bar: 3:1 only at 24 px+ or bold 18.66 px+, else 4.5:1; threshold overrides. Static images (contrast_ratio) use the worst pixel; moving video uses p95, the brightest 5 % of the background. A bar adds frames_below, pct_below, first_below_time, longest_below_s and, when frames fall below, suggested_fix scrim with scrim_alpha_min (the smallest opacity of scrim_color, default black, that brings the worst frame to the bar, linear-light blend): the fix is a scrim, never a recolour. Cuts inside the range (detect_cuts' score >= cut_threshold and, unless cut_guard is false, detect_cuts' motion guard: above 3x the mean of the 5 scores before it + 0.02) give cut_count, cut_times and crosses_cut, which flags text on screen across a cut. captions (name, text_box, start, end each) measures every caption over its own time on screen in one call: per caption the worst frame, time and ratio; the worst caption; captions_below / below_names; crossing_cut lists each caption on screen across a cut by name with its cut times. text_min_px (needs text_box and a text colour) counts a frame only when at least that many pixels inside text_box read as text (closer in contrast to the text colour than to the background), so a word-by-word reveal or an empty scrim before the first word is not measured; frames_without_text says how many were left out (absent unless text_min_px is given). Reads the output pixels (what render_frame writes, 8-bit). Raw numbers.
- New tool `edit_check` (group `output`, read-only): did an edit stay inside its allowed rects. Two frames (`a` / `b`, diff_frames side objects) compared at full resolution with no downscale; a pixel is changed when any RGB channel (0..1) differs by more than `threshold` (default 0.04). `allowed` (up to 64 `[x,y,w,h]` rects; absent = nothing allowed) splits the changed pixels into `inside` (count, % of frame, % of the allowed area) and `outside` (count, % of frame, % of the rest, `max_delta` with its pixel over every outside pixel changed or not, `bbox`, regions touching it). Changed pixels form 8-connected `regions` (bbox, pixels, outside_pixels, max_delta), largest first; `max_regions` (default 32, up to 256) are listed, `region_count` counts all, `min_region_px` leaves smaller ones out of the list. Raw numbers, no verdict; no existing tool's output changes. Spectator: an info panel read card whose header carries the threshold ("edit_check · threshold 0.2", from the result) and 4 rows: Changed outside band "n px (max Δ there d)", Changed inside band "n px", Max Δ overall, Regions.
- Descriptions: the 77 tools whose first sentence was 150 characters or longer in v5.0.0 each get a new plain first sentence (all under 150; the longest is 128) in front of their unchanged old text, so a client that shows only the first sentence reads what the tool does and no detail is lost. The first-sentence test has no allowlist any more: every tool's first sentence must be under 150 characters. Schemas and behaviour are unchanged.
- `validate_captions` gains an optional `legibility` (boolean, default false; absent or false = the v5 output, byte for byte): per caption group a `legibility` block with, per cue at its middle frame, the capital-H ink height of its style (`cap_px`, and `cap_frac` of the canvas height, measured as lint_frame's min_text_size), the ink box from compute_text_bounds, `chars` (newlines left out) and `cps` per second on screen, and the WCAG contrast of the caption colour at its opacity against the frame rendered without that cue, every pixel of the ink box (`min_ratio`, `p10_ratio`, `mean_ratio`, `worst_px`); the group's `min_cap_frac`, `max_cps` and `min_contrast` with their cue ids; and a top-level `legibility` summary over all groups. Raw numbers only, no verdict; at most 500 cues per group. Spectator: with legibility the Inspector rows read Captions, Min caps, Lowest contrast, Max reading.
- `lint_frame` (extended, new optional argument only; absent or false = the v5 output, byte for byte, timings aside): `quality` (true, or an object with `crush_below` and `clip_above` in 0..1, defaults 0.02 / 0.98, and `band_step` 1..32 8-bit luma codes, default 2) adds per sampled frame a `quality` block on Rec.709 luma of the output values: `mean_luma`, `crushed_frac` (at or under crush_below), `clipped_frac` (at or over clip_above), `channel_clipped_frac` (any RGB channel at or over clip_above), `luma_levels` (distinct 8-bit luma codes), banding on 8-bit luma (`band_steps_per_row`: horizontal neighbour steps of 1..band_step codes per row; `band_plateaus` and `band_plateau_px`: the flat runs those steps bound and their mean length) and the change from the frame one project frame earlier (`prev_mean_delta`, `prev_max_delta`, `prev_identical`; null at t = 0). `summary.quality` carries the extremes with their times (`max_crushed_frac`, `max_clipped_frac`, `max_channel_clipped_frac`, `min_luma_levels`, `max_band_plateau_px`, `min_mean_luma`, `min_prev_mean_delta`), `identical_to_prev` with its times, and the params used. Black frames read crushed 1 / mean 0, frozen or duplicate frames read identical to the frame before. Raw numbers, no verdict. Spectator: with quality the lint_frame card adds Crushed / clipped and Banding / frozen rows.
- `lint_frame` (extended, new optional argument only; absent or false = the v5 output, byte for byte, timings aside): `decode_media` (boolean, default false). The text_contrast check renders the frame without the text layer as its background; in v5 that render used an empty render cache, so media layers drew black and white text over footage read 21:1. With `decode_media: true` the media frames are decoded into the session cache first (as `validate_captions` legibility does), so text_contrast measures against the real footage. On white captions over files/jaja/jaja-ad.mp4 the three cues read min 1.02 / 1.00 / 1.27 : 1 with it (the same numbers and worst pixel as `validate_captions` legibility) and 21.0 without it.
- `render_flow` (extended, new optional argument only; absent or false = the v5 output, byte for byte, timings aside): `stats` (true, or an object with `grid` 1..16, default 4, and `moving_px` 0..1000, default 0.5) adds `flow_stats`, the same dense flow field the picture is drawn from (between the clip's displayed frame at `time` and the next one) as raw numbers in canvas pixels per frame, +u right and +v down: `mean_u` / `mean_v`, `median_u` / `median_v`, `mean_dir_deg` (0 = right, 90 = down; null when the mean vector is zero), `mean_speed`, `speed_p50` / `speed_p90` / `speed_p99` / `speed_max` with `speed_max_at`, `moving_frac` (share of the field faster than moving_px), a grid x grid table of mean vectors and speeds, the field size and the params used. A content moved 4 px right reads a median vector of (4.0004, 0) in tests/flow_stats.rs. Raw numbers, no verdict. Spectator: with stats a read card shows Motion (mean vector length and direction), Speed (p50 / p90 / max) and Moving rows; without stats the screen is the v5 screen.
- New tool `saliency_map` (group `output`, read-only): where the eye is likely to go in one output frame, as raw numbers. Spectral residual saliency (Hou & Zhang 2007) on Rec.709 luma, area-averaged to `work_px` on the long side (default 64, 16..512), log amplitude minus its 3x3 average (edges replicated), original phase, squared magnitude, Gaussian `blur_px` (default 2.5 grid cells, 0..32), min-max scaled to 0..1 (a constant frame gives an all-zero map and `empty: true`). Optional `motion` (0..1, default 0) mixes in the luma change to the next project frame. Returns the peak and the mass centroid / spread in canvas px, `half_mass_area_frac`, a `grid` x `grid` mass table (default 3, 1..8), and per rect `[x,y,w,h]` (up to 16) `area_frac`, `mass_frac`, `mass_per_area`, `max` and `top10_frac`; `path` writes the map as a png. No verdict. Spectator: read card Peak / Half the mass in / In rect 1 / Motion.
- Spectator: a window too small for a screen's fixed panels plus a minimal viewer (160 x 260 px at the design scale), e.g. 640 x 360, now lays the app out at the smallest size that fits and scales it down to the window, so no panel (and no Inspector card) runs past the window edge. At every size that already fits (1100 x 768 and up) nothing changes: a 1920 x 1080 screenshot is byte-identical before and after. Timeline wheel-zoom divides the pointer offset by that scale.
- Spectator: the `flash_series` READ card's Transitions row reads "max 8 luminance · 8 red per 1s · area 98%" stacked under its label (full card width) instead of the old wording wrapped in the value column: 3 lines (64.8 px at 1920 x 1080) instead of 6 (129.6 px). Same three numbers; the timeline rail and the toast keep their wording.
- Spectator: the `flash_series` READ card's "Worst 1 s flashes" row (only drawn with `flash_limit`) reads "5 @ 5.92s, 27>3, 98% · red 5 @ 7.67s, 15>3, 25%" stacked under its label: 3 lines (label + 2, 64.8 px at 1920 x 1080) instead of 8 beside the label (172.8 px). Same numbers (flashes in the worst 1 s window @ its start, windows over the limit, largest flash area); the word "area" and the spaces around ">" are dropped to fit two lines. At 640 x 360 the card's top moves from -62.3 px to 2.2 px in the window; the Inspector panel (top 32.8 px there) still clips the card's header and Range row. With `area_basis: "field"` the row needs 4 lines and the card still starts at -23.6 px (was -101).
- Spectator, small windows only (the app scaled down, i.e. under 1100 x 768): a screen whose Inspector shares the viewer's rows gives it at least 370 design px, taken from the tallest row of the band under it, which keeps at least 120 (edit / graphics: the timeline; graph, modelling, particles: their bottom panel). At 640 x 360 the Inspector grows from 155.3 to 220.9 px and the timeline shrinks from 150.5 to 84.8 px (window px). The flash_limit READ card (top 67.9) and the flash pin card (top 42.1) are fully visible under the top bar, header and Range row included. 640 x 640 is unchanged (the Inspector is already taller there), and every size from 1100 x 768 up is untouched (1920 x 1080 byte-identical).
- Spectator, small windows only (under 1100 x 768): the Inspector's least height beside the viewer goes from 370 to 402 design px and the band under it keeps at least 110 (was 120), so the tallest READ card (the flash pin one, 341.5 design px) sits under the panel's own "Inspector" title instead of over it. When that takes rows from the timeline, its plain track rows draw compact (top 34, height 30, gap 6 design px instead of the mode's 38 / 35 / 9.5; text sizes unchanged, track label and clip name 16 px = 9.55 px in the window), so the shorter band still holds 2 whole tracks. At 640 x 360 (window px) the Inspector grows from 220.9 to 240 px and the timeline shrinks from 84.8 to 65.7 px; the flash pin card moves from 42.1..246 (over the title, 33.4..59.7) to 61.2..265.1 and the flash_limit card from 67.9..246 to 87..265.1, header and Range row visible on both; tracks V1 299.1..317 and V2 320.6..338.5 are whole (were 282.4..303.3 and 309..329.9). 640 x 640 is unchanged, and every size from 1100 x 768 up is untouched (1920 x 1080 byte-identical).
- Spectator: the Loudness panel no longer puts a bare "target" under a measured value. After `measure_loudness` the big number is the measured integrated loudness (EBU R128), and the line under it read "target" with no value, so it looked like "-15.8 LUFS target". That line now reads "Integrated" (16 px, 9.55 px in the window at 640 x 360) whenever no target exists, and keeps "target <n>" only when `normalize_loudness` set one. 1920 x 1080: only the label's pixels change, on screens that show the Loudness panel. GUI only; new test `tests/loudness_label_row_test.py`.
- Spectator: a flash that runs out no longer stays in the page. A call's flash is a stamp read for 700 ms (FLASH_MS); nothing repainted an idle screen when it ran out, so the last frame's `.flash` class (a History row, a READ card) stayed until the next event, and a re-read 720 ms later (cov_c's "panels byte-identical after the failure") could see it. The app now holds one timeout at the earliest stamp + 700 ms whose callback repaints directly, with no animation frame (router_test's idle transform check still reads 0 rAF), re-arms for any later stamp still drawn, then goes idle; hiding or leaving the page cancels it. 1920 x 1080: on the six standard screens the READ card loses its stale `flash` class (and with it the `will-change: transform` layer), so its pixels change slightly in text anti-aliasing. GUI only; new test `tests/flash_expiry_row_test.py`.
- New tool `av_offset` (group `audio`, read-only): how far the sound sits from the picture. Audio onsets (positive jumps of short-time RMS over `onset_window_ms`, default 10, on a 1 ms grid) are cross-correlated (Pearson) with the picture's frame-to-frame change (mean absolute Rec.709 luma difference on a copy scaled to `scale` px, default 160) for every lag in ±`max_lag_ms` (default 500, up to 2000). Returns `best_lag_ms` / `best_r` (positive = the sound comes after the picture, audio late), `r_at_zero`, the runner-up peak more than a frame away and `peak_margin`, the curve every `curve_step_ms` (default 10) and the 8 biggest picture changes. `source` = timeline (default) or clip:<id>; `audio` = mix, a clip id or {clip_id|track_id}; `start` / `end` (4..6000 frames). Raw numbers only, no verdict; bad arguments are errors, never clamped; silent audio gives null, never 0. Existing sync tools (sync_clips, audio_transients) are unchanged. Spectator: a read card (Best lag, r there vs at 0, Runner-up, Biggest picture change). Tests plant known shifts and read them back within one frame (they read exact): +120 / -80 ms and an in-sync control reading 0 on the timeline, with a 2 s quiet head, and on files rendered by the engine's own export, including a 44.1 kHz source rendered at 48 kHz.
- Spectator: the `flash_series` info panel's Stamps row now reads a compact `lum_stamps` / `red_stamps` list (`[{t, dir}]`, up to 64, plus `*_stamps_total`) that kimo-mcp adds to the complete event from the FULL result. Before, it read the result's `frames` arrays, which the spectator feed cuts to 8 entries plus a `…+N` marker, so a live session showed `Stamps ↓0s` instead of the real stamps. A `…+N` string or a non-finite time is skipped, never read as 0. Telemetry only: the tool's MCP output is unchanged.
- New tool `frozen_frames` (group `output`, read-only): runs of frames where the picture stands still, each with its start frame, end frame, length and the largest pixel difference inside it (`max_diff` 0..1 and `max_diff_255`). Every project frame in `start`..`end` (default the source span, 1..6000 frames) of `source` = timeline or `clip:<id>` is rendered at full resolution (or `scale` px on the long side) and compared with the first frame of its run; `tolerance` (default 0 = identical) and `min_run` (default 2) set what counts. Comparing with the run's first frame keeps a slow drift from chaining into a hold; black frames get no special case. Rendered fixtures in `crates/kimo-core/tests/frozen_frames.rs`: a known 12-frame hold reported exactly, a slow pan that reports nothing (close to the line: passes via edge rows; edge-free pan at about 1.1 counts per frame reads as hold for frames 0-5 at 0.0255), a grainy still caught only at the stated tolerance (close to the line: 5/255 measured and 6/255 worst case by construction against 6.5/255), and a labelled known-limitation test that pins that edge-free pan as current behaviour. Limit, also in the tool description: each frame is compared with its run's first frame, so a total drift from that frame within tolerance still reads as a hold; a very slow pan reads as a hold until its total drift crosses the line, and nothing under the line is detected. Spectator GUI: a read card (Held, Longest run, Tolerance, Frames read).
- New tool `black_frames` (group `output`, read-only): runs of near-black frames, each with its start frame, end frame, length and the brightest pixel inside it (`max_luma` 0..1 and `max_luma_255`; 0 for pure black). A frame counts only when the Rec.709 luma of EVERY pixel is at or under `luma_max` (default 0.02 = 5.1/255, the pre-registered fixture line; 0 is strict mode), so letterbox bars, a black corner, a dark scene with a brighter object or a black frame with a logo are not runs. Every project frame in `start`..`end` (default the source span, 1..6000 frames) of `source` = timeline or `clip:<id>` is rendered at full resolution; `min_run` (default 2) drops a lone black frame. Limited-range video is expanded at decode (video black 16 reads as 0); a limited-range file wrongly tagged full range is the stated limit, made visible: the report carries each media clip's declared `range_tag` (tv, pc or unknown) and lists stretches that sit flat at about 16/255 in `limited_range_suspect` with a `note`. A black run that is also still is reported by `frozen_frames` too, with the same frame numbers (tested; nothing dedupes them). Rules and predictions were committed before the tool existed (tests/data/black_frames/THRESHOLD*.md). Spectator READ card (5 rows: Black, Longest run, Line, Range, Frames read).
- `black_frames`: the units sentence (luma_max on a 0..1 scale; max_luma 0..1 and max_luma_255 on the 0..255 code scale; luma_max is compared to max_luma, never to max_luma_255) is now also in the `luma_max` field of the MCP input schema, verbatim, so a client that never reads the tool description still sees it. The tool description is unchanged. New test `luma_max_schema_field_text_carries_the_units_sentence_verbatim` in `crates/kimo-core/tests/black_frames.rs`.
- New tool `focus_series` (group `output`, read-only): sharpness per frame, raw numbers. Every `step`-th project frame (default 1) in `start`..`end` of `source` = timeline or `clip:<id>` is rendered at full resolution; on its Rec.709 luma (0..255 code scale, interior pixels only) `lap_var` is the population variance of the 4-neighbour Laplacian (code units squared) and `tenengrad` the mean 3x3 Sobel gradient magnitude (code units), for the whole frame and up to 16 `rects` [x, y, w, h] (a rect with no interior pixel reads null, never 0). A flat frame reads exactly 0. Returns the series, the sharpest and softest sampled frame by `lap_var` (ties go to the earliest), and min / median / max of each score; at most 1200 sampled frames per call. No blurry or sharp verdict: the only line is the optional `soft_max`, which lists runs of at least `min_run` (default 2) sampled frames at or under it. Definitions and predictions (an 8 px checker under a keyed blur ramp, flat and split-frame rects, and the real 1080p clip with its freeze and black gap) were committed before the tool existed (tests/data/focus_series/PREREG.md); tests in `crates/kimo-core/tests/focus_series.rs` (the real-clip test is ignored by default: it needs the local file). Spectator READ card (4 rows: Sharpest and Softest with frame, time, lap_var and tenengrad; then Per rect when rects were given, else Soft when soft_max was given, else the lap_var spread; then Frames read), updated on every call from the call's own result, no render needed. All 15 pre-registered predictions scored in tests/data/focus_series/SCORE.tsv (15 HIT, 0 MISS).

- New tool `add_pip` (group `graphics`): one-call picture-in-picture inset of a second video -- circle or rounded-rect crop, border ring, drop shadow, and pop-in scale animation, built entirely on existing primitives (add_track/add_clip/add_mask/add_shape/set_keyframe/set_audio) through dispatch_nested, no new compositing code. Not on the director-mode tool list.
- New tool `add_keyword_pops` (group `text`): one emphasised word or phrase pops onto screen as spoken, either at explicit `words=[{text, at_s, duration_s}]` or `auto:true` picking emphasis words from the loaded transcript (the same scorer `auto_captions` uses), capped at `max_per_minute` (default 4) and spaced `min_gap_s` (default 3) apart. Styles: `bold_caps` (default), `boxed`, `typewriter`; `position` defaults to `upper_third`. Built on add_title/add_text/add_text_animator, no new text rendering. Does not touch captions or caption-ripple behaviour.
- `add_keyword_pops` look polish: text now sizes to ~60% of frame width (measured from the actual word, not a fixed fraction of frame height), stroke width and drop shadow increased so pops read as creator-style keyword pops rather than subtitles, `boxed` style's box now hugs the measured text instead of a fixed-width bar, and `accent_color` can now tint `bold_caps`/`typewriter` text directly (default off; byte-identical output when omitted).
- New tool `add_arrow` (group `graphics`): an animated "look here" arrow/callout pointing at a normalized `{x,y}` target on screen, with an optional auto-computed `from` point, draw/pop/fade animation styles, and an optional label at the tail styled like `add_keyword_pops`'s `bold_caps`. Built on add_shape (line + triangle) and add_text through dispatch_nested, no new rasterizer. Not on the director-mode tool list.
- `add_arrow` fix: the label's placement (continue past the tail, then clamp into frame) could land the label directly on top of the arrowhead when the auto `from` default placed it near a frame edge. The label now falls back to a perpendicular offset from the tail, picking whichever side needs the least clamping, only when the straight placement would actually overlap the arrow's own shaft/head bounding footprint; the common case is unchanged (all original tests still pass unmodified).
- Docs: release docs updated.
