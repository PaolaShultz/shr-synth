# SHR Synth workspace handoff

Last updated: 2026-09-28, Europe/Zagreb.

This is the durable starting point for a fresh Codex session in
`/home/shome/p/shr-synth`. Read this file before planning or changing the
workspace. Update it at meaningful checkpoints so later sessions do not have
to reconstruct decisions from chat history.

## 2026-09-28 project rename

The project, GitHub repository, checkout and executable are `shr-synth`; the
Rust library is `shr_synth`. SHR-DAW's command, public install layout and exact
source pin follow the rename. The `.mojsint` preset format and model IDs stay
stable. SHR-DAW accepts old configuration keys and saved backend names and
normalizes persisted channel bindings before checking identity. Old absolute
private paths on this machine resolve through a deliberate compatibility link;
current launch configuration uses the renamed checkout.

The four remaining full audition CLI generators (Clean Kick, Micro Machine,
Strange Oscillator and Dual Filter concept) are now opt-in. Their existing
one-time evidence remains in the dated research sections; production DSP,
allocation, schema, host and short offline CLI contracts remain in the normal
suite. Run a particular generator with `cargo test --locked --test NAME --
--ignored` or all development-only checks with the command in `AGENTS.md`.

Rename validation on exact Rust 1.97.1 passed all 370 tests in the previous
normal all-target/all-feature selection, with 36 ignored. The four historical
CLI renderers also passed in that run before being marked opt-in; their
classification check then passed with four ignored. Warning-denied Clippy
passes, as do audit/deny and DEV/REL host builds and help checks. All 28
cleared presets validate. Old and renamed release hosts render every preset
byte-identically with finite samples at note 48, one second, 48 kHz and velocity
0.85. The concatenated hash remains
`68c2c6c323ac122844283ceec504ac6e0ccca74942063d3311b2a66d5ced729c`.
Production preset and host semantics are unchanged.

## 2026-09-14 MIDI release loss under overload

A Player stuck-note report with N00B off prompted inspection of the SHR Synth host.
Offline regressions reproduced two release-loss paths: events beyond the
256-event callback budget were discarded, and a full MIDI queue could lose a
release while leaving the host sounding. The callback now retains the next
event and FIFO backlog for later periods and stops draining at its budget.
A full queue requests normal host shutdown and reports an explicit MIDI
overflow error after closing this instrument's JACK client. Other clients and
JACK remain untouched. The host contract owns recovery details.

Both new regressions failed before the fixes. Exact Rust 1.97.1 passed the
locked check, formatting, eight host tests and ten focused engine tests.
Strange Oscillator and Swarm releases reach finite silence in both MIDI release
formats after a control burst, with allocation guarding. The normal full suite,
historical tests, Clippy and release builds were outside the authorized focused
pass. No live host, JACK, MIDI, audio or hardware test was started; release
binaries remain unchanged. The user's incident is not conclusively attributed
to overload without live event evidence.

The owner subsequently authorized rebuilding all. Locked all-target/all-feature
DEV and REL builds pass in both SHR Synth and SHR on exact rustc 1.97.1. Both SHR Synth host
help checks and both SHR version/help checks pass; existing SHR warnings remain.
No additional test suites or live audio/hardware checks were run. Running
processes were preserved; normal exit/reopen selects the rebuilt checkout
binaries containing the fixes.

## 2026-09-11 held bass voice protection

Swarm Warm Pad exposed shared oldest-voice stealing that could cut a held bass
while released high notes still occupied voices. Allocation now chooses idle
voices, then released voices in note-on order, then the oldest held voice only
when all voices are held. The voice budget is unchanged. A Swarm regression
covers reverse release order, velocity-zero release, held-note protection,
full-held fallback, stale note-off, panic/reuse, finite output and allocation
guarding. The owner-authorized end-of-day pass used exact rustc 1.97.1
(8bab26f4f, LLVM 22.1.6), AArch64. Formatting, locked all-target/all-feature
checking, the focused regression and 368 normal tests passed; 36 historical
cases stayed intentionally ignored. Warning-denied Clippy, audit and deny
passed, retaining the known non-fatal duplicate winnow warning. All DEV/REL
targets built and both host help checks passed. All 28 cleared presets validate
and paired one-second 48 kHz release renders (note 48, velocity 0.85) are exact
and finite; allowlist-order concatenated WAV SHA256 remains

`68c2c6c323ac122844283ceec504ac6e0ccca74942063d3311b2a66d5ced729c`.

SHR passed 1,200 normal tests (14 historical cases ignored), 20 Python helper
tests and 31 isolated audio-policy cases. Its locked checks, Clippy with
existing warnings, DEV/REL builds and version/help checks passed. No live
process, JACK, MIDI, audio playback, recording or hardware was changed by this
pass. Normal exit/reopen loads the rebuilt checkout binaries.

## Current documentation authority

The current [documentation index](README.md), [preset/control schema](PRESET_SCHEMA.md),
and [host contract](HOST_CONTRACT.md) describe the implemented eight-model,
schema-10 engine and 28 cleared factory starts. SHR now owns a shared 4×4
surface: eight tone slots, four envelope slots,
then Volume and three AUX sends. Rotary 1 edits parameter 1 until clicked into
visible NAV. Previously displaced timbre controls return; Dual Filter's amp
ADSR stays on row 3, with filter attack/sustain/release retained as preset-owned
detail. Native engine CCs and schema fields remain independent of physical
positions; the linked SHR instrument guide in `docs/PRESET_SCHEMA.md` owns the
complete current mapping.

Entries below are dated evidence and historical decisions, not simultaneous
current contracts. In particular, earlier twelve-control-only, unimplemented
host, isolated Swarm, and smaller-catalog descriptions are superseded. The
September 7 documentation reconciliation changes no engine, preset, runtime,
or hardware state. Current deployment evidence distinguishes historical
callback simulations from the later connected debug/release defect acceptance.

## 2026-09-11 performance wheels and combined validation

All eight production models now receive 14-bit pitch bend (±2 semitones),
CC1 vibrato (5 Hz, up to ±50 cents), and CC121 controller reset. The shared
10 ms smoothing and 32-sample pitch updates preserve note gates, oscillator
phase, preset timbre, and mono glide. The existing omni host applies wheels
instrument-wide; this is not MPE. New engines start neutral. The native
Open303 adapter exposes its existing bend setter without vendor changes.

The authorized combined pass used exact rustc 1.97.1 (8bab26f4f, LLVM 22.1.6)
on AArch64, with compilation serialized across the two checkouts. Locked
all-target/all-feature checking, formatting, the normal suite (367 passed,
36 historical cases intentionally ignored), warning-denied all-target Clippy,
`cargo audit`, and `cargo deny check` passed. Deny retains its non-fatal duplicate
`winnow` warning. The passing suite includes MIDI wheel decoding, pitch range
and reset, oscillator phase/bounds, and all-model finite/allocation regressions.

All DEV and REL binaries build, and both host binaries pass `--help`. All 28
cleared presets validate. Two one-second release renders of each preset at
48 kHz, MIDI 48 and velocity 0.85 are byte-identical and finite. The concatenated
allowlist-order WAV SHA256 is
`68c2c6c323ac122844283ceec504ac6e0ccca74942063d3311b2a66d5ced729c`.
Temporary WAVs were removed. No JACK, live host, MIDI transmission, playback,
recording or hardware acceptance was started. Existing processes retain their
loaded executable until normal exit/reopen.

SHR's companion validation passed 1,189 normal Rust tests with 14 historical cases
ignored, plus 20 Python helper and 31 isolated audio-policy cases. Both SHR
profiles build and pass version/help checks. Its only validation correction
was a render-test fixture that asserted AUX labels without an active instrument.
Current 4×4 control-surface documentation now separates SHR physical slots
from SHR Synth native macro/CC order; no SHR Synth DSP or preset data changed in this pass.

## 2026-09-10 live monophonic note articulation

The owner reported that new notes changed pitch without refreshing the
envelope. Both live mono adapters treated every overlapping or repeated held
NoteOn as legato. Pressure Chain and Open303 now retrigger their filter and
amp contours on each positive live NoteOn, including repeated keys. The amp
attack starts from its current level; overlapping pitch still glides. A
release-driven return to an older held note remains a non-retriggering slide,
and detached notes retrigger even during the previous release tail.

The bounded note stacks, stale-release handling, accent/pressure, and panic
remain in place. Open303's ordinary candidate/native note API retains its
original legato default; only the explicit live API requests retriggering.
No preset schema, control, oscillator, or filter algorithm changes. Focused
Rust/native regressions cover both contours, glide, repeat, priority, release,
finite output, and allocation boundaries.

The authorized ordinary development pass used exact Rust 1.97.1 on AArch64
with one compile job shared serially with SHR-DAW. Locked checking, formatting,
seven focused retrigger-related tests, six active Open303 contracts, and the
normal all-target suite passed: 362 tests, zero failures, and 36 intentionally
ignored historical cases. The normal suite took 309.95 seconds including lock
wait; warning-denied all-target Clippy also passed. All debug and release
binaries build, and both fresh host binaries pass their existing `--help`
smoke check. Package version remains 0.2.3. No source correction was needed
during validation, and no live host, audio, MIDI, or hardware action occurred.

## 2026-09-09 authorized combined build

The owner authorized building all after the Open303 integration. Exact rustc
1.97.1 (8bab26f4f, LLVM 22.1.6), AArch64, built every debug and release target
in both SHR Synth (all features) and SHR-DAW. SHR's locked check passed; its
normal suite passed 1,141 tests with 14 historical tests intentionally ignored.
One existing routing-recovery assertion expected obsolete status text; the
correction checks the current save-error prefix while preserving all direct
draft, selected-row, layout, and cancellation assertions. No routing behavior
changed. Existing SHR compiler warnings remain.

All 28 SHR Synth factory presets validate, and repeated one-second release renders
of the four Open303 starts are byte-identical. The unchanged engine's prior
359-test/sanitizer/spectral evidence remains applicable; unrelated historical
renderers were not rerun. Vendor hashes and formatting checks passed.
The fresh SHR release discovers all four starts in an isolated, hardware-free
catalog. Existing local launch configuration already selects the checkout
release host and public preset directory; no configuration or private sounds
needed changing. Normal exit/reopen loads the new SHR binary. No interactive application,
JACK server, live engine, MIDI transmission, or audible test was started/restarted.

## 2026-09-09 Open303 live integration

The owner requested Open303 integration into SHR-DAW and a few presets.
Open303 is now a distinct eighth SHR Synth model (`open303`), enabled in default
builds, monophonic, with fixed-per-preset TB_303 or LP_18 filter identity.
Schema 10 adds its strict native control vocabulary; schemas 1–9 still migrate.
The four authored starts are Rubber Bass, Accent Wire, Hollow Slide, and Soft
Pluck, bringing the cleared catalog to 28. They are ordinary requested factory
presets, not preserved experimental renders.

The live adapter prepares one core outside rendering, receives all note-offs
through its bounded last-note stack, and uses inherited envelopes/slide/accent.
The Engine's 10 ms smoothers feed cached native controls every 32 samples;
note-on applies current values immediately. Native normal/accent attack,
accent decay and amp decay have explicit bounded setters; accent decay updates
held accented notes. No additional generic ADSR is multiplied onto the voice.
Position 5 remains volume, 9–12 are native envelope timings, and 13–15 stay SHR
AUX. There is no new mode button or live filter switch.

SHR source adds catalog identity A01–A04, exact load/save/reset support, the
native control labels, mono marker, and installer license-notice retention.
The owner subsequently authorized the combined build; the build record above
owns its completed software checks and normal-reopen boundary.
See [Open303 integration](OPEN303_INTEGRATION.md) for controls and evidence.

The normal all-target/all-feature suite passed (359 tests, 36 ignored), followed
by all three focused live-integration tests in debug and release, including
the subsequently added all-control-effect regression. ASan/UBSan and native
C++ allocation guards passed with the articulation setters; the six opt-in
oscillator spectral measurements match the previous evidence. All 28 presets
validate; paired one-second release renders at MIDI 40/velocity .85 are exact.
Open303 peaks for that probe are .3172, .3155, .1914, and .1393 respectively.
Formatting, warning-denied Clippy, release build, audit/deny, and minimal-feature
library checks passed. Historical unrelated renderers/benchmarks stayed ignored.


## 2026-09-09 isolated Open303 candidate

The owner authorized proceeding with the repaired C++ candidate. The optional,
default-off `open303` feature now builds a pinned, license-reviewed Open303
core behind `native/open303` and a safe owning Rust API. `open303-lab` renders
an authored sequence through TB_303 and LP_18 into a new offline output folder.
The production Engine, seven models, schema, presets, physical controls, and
SHR/JACK integration are unchanged. No playback or hardware work was performed.

[Candidate contract and validation](OPEN303_CANDIDATE.md) owns the build/run
commands, bounded note/control behavior, output ceiling, tests, and remaining
integration gates. [Vendor provenance](../vendor/open303/README.md) records the
exact source selection, upstream hashes, local repairs, and separate MIT/Ooura
notices. This supersedes the earlier research-only/no-import state below.

The candidate fixes reproduced array bounds defects, allocating note storage,
initialization/rate inconsistencies, held-note tuning/accent restoration,
shared preparation scratch, unsafe exponent extraction, and idle/reset state.
It preserves the inherited oscillator/filter flow; filter mode is fixed at
preparation. Creation/destruction stay outside rendering. Controls are applied
at call boundaries with cached unchanged values; smoothing and live event-rate
budgeting remain future integration work. A counted ±0.999 output ceiling and
sticky nonfinite fault-to-silence boundary are explicit adapter behavior.
This is software reuse evidence, not hardware fidelity or sound acceptance.

Software validation passed the final normal all-target/all-feature suite
(356 passed, 36 intentionally ignored), focused candidate tests in debug and release,
ASan/UBSan native bounds/state/C-ABI/allocation/fault checks, FFT roundtrip,
and the six opt-in oscillator spectral measurements. Formatting, warning-denied
all-target/all-feature Clippy, release build, audit/deny, exact vendor manifest,
and knowledge validation passed. The default build checks successfully with an
unusable CXX path and excludes the optional C++ build crates. All 24 production
presets validate and yield byte-identical paired one-second release renders.
The candidate repeats exactly within each profile; debug/release sample delta
is at most 3.7253e-9 for the authored phrase. Both modes end idle with no ceiling
hits. Unrelated historical/benchmark ignored tests were intentionally skipped.

## 2026-09-09 Open303 engine analysis

The owner selected Open303 for a deep source and integration assessment.
[Open303 engine analysis](OPEN303_ANALYSIS.md) owns the pinned source audit,
license/dependency review, reconstructed signal flow, note/control semantics,
JC-303 comparison, offline probes, and proposed integration boundary.

The recommendation is to retain the Open303 C++ DSP behind a narrow C ABI in
an isolated candidate, with a bounded note adapter and explicit preparation.
This avoids rewriting its oscillator/filter/envelope interactions. It is not
ready for the live callback: confirmed issues include constructor and table
bounds errors, allocating note storage, inconsistent initialization, tuning
loss on held-note return, shared table-generation scratch, and no idle return.
The default TB_303 filter path is linear in audio amplitude; the original VST
initializes LP_18 instead. Do not describe it as a validated nonlinear circuit
replica or silently replace Pressure Chain with it.

A core-only AArch64 build succeeded with missing standard headers supplied.
After repairing only the constructor array overrun in a disposable copy,
sanitized bounded probes ran; direct C++ and Rust/C-ABI rendering produced
identical samples for one declared sequence. Functional, allocation, finite,
control-motion, and oscillator spectral evidence is in the report. There was
no JACK, audio playback, SHR change, native performance claim, or production
integration. Temporary source/probe/render outputs are disposable; only the
research conclusions and reproduction methods belong in durable docs.

## 2026-09-09 open-source analog modeling knowledge base

The owner asked that future modeling start by studying prior implementations
and useful device signal flows. [The analog modeling knowledge base](OPEN_SOURCE_ANALOG_MODELING.md)
records a primary-source survey, project authorship and license pointers,
implementation entry points, limitations, and a prioritized map to SHR Synth.
Consult it before proposing a new analog topology or rebuilding a known DSP
mechanism. Preserve the reference flow and control interactions in a baseline,
then vary one meaningful mechanism with a stated musical purpose.

This is research guidance, not selection or integration of a new model. No
third-party code/content was imported and no DSP, controls, presets, hardware,
or runtime behavior changed. Documentation/link checks and local knowledge
validation apply; production and opt-in audio tests are unnecessary for this
documentation-only change. Sound fidelity and Pi cost were not evaluated.

## Goal

Build a low-level, headless Rust synthesizer focused on sophisticated,
deliberately modified oscillators and genuinely unfamiliar sounds. It is
one of several software instruments managed by SHR-DAW, not a standalone DAW
and not a replacement or compatibility disguise for synthv1.

The primary hardware target is a Raspberry Pi 5 with 2 GB RAM, 64-bit
Raspberry Pi OS, and NVMe. Sources must also build and run on the current
x86_64 Ubuntu development machine. Do not make performance, latency,
polyphony, or sound-quality claims before measuring them on the actual Pi.

SHR Synth is not permanently monophonic. Design and validate its sound engine
monophonically first so oscillator topology, routing, macro behavior, and cost
can be understood without voice-count multiplication. Expand the selected
architecture to polyphony only after native Raspberry Pi callback/headroom
measurements establish a safe voice budget.

There is no UI in this repository. Control comes through MIDI and SHR-DAW.

## 2026-09-05 complete non-audible build pass

Exact rustc 1.97.1 (8bab26f4f, LLVM 22.1.6) on AArch64 passed formatting,
locked all-target/all-feature checks, the normal suite (349 passed, 35 ignored),
warning-denied Clippy, `cargo audit`, and `cargo deny check`. Deny reports the
existing non-fatal duplicate `winnow` versions. All debug and release targets
build. The new Pressure Chain test allocator needed `cfg(debug_assertions)`
because assert_no_alloc disables that type in release mode; its five focused
tests pass in both profiles, with allocation guarding retained in debug.

The refreshed release host validates all 24 cleared presets. Two one-second
release renders of each Pressure Chain topology at MIDI 40/velocity 0.85 are
byte-identical; temporary WAVs were deleted after comparison. SHR's normal
suite passes 1,128 tests with 14 ignored, plus 40 hardware-free helper checks;
its debug and release targets also build. No live host, JACK, MIDI, playback,
recording, or hardware test was started. Already running processes retain their
loaded executable until the owner's normal restart. Real-time headroom and
listening remain unverified. Historical/audition/exhaustive tests stayed ignored.

## 2026-09-05 Pressure Chain live integration

The owner requested yesterday's model in SHR-DAW. Pressure Chain now enters
`Engine` as one monophonic voice with its own amp envelope and three explicit
preset topologies: Deep Cascade, Body Tap, and Cross Feed. Schema 9 owns
`pressure_chain_topology` and twelve normalized macros; schemas 1–8 migrate
without changing their values. More than one Pressure Chain voice is rejected.
A fixed 128-key last-note stack makes overlapping notes slide, returns to
still-held notes, and ignores stale releases. All Notes Off clears both voice
and held-key state. The original oscillator/filter DSP is unchanged.

SHR exposes all eight timbre values followed by amp ADSR on CC20–31, with
SWEEP at physical position 5 and Project AUX sends at 13–15. It uses the
existing one-owned-process and isolated stereo instrument strip path. This
is the seventh model, with three new project-authored starts (24 total).
No release executable was rebuilt and no audio/hardware session was started;
source integration does not update an already installed or running host.
Listening, controller acceptance, and real-time headroom remain unverified.

Non-audible validation uses rustc 1.97.1 (8bab26f4f, LLVM 22.1.6), native
AArch64. Formatting, locked checks, the normal all-target/all-feature suite
(346 passed, 35 ignored), and focused live/schema/control regressions pass.
SHR's normal suite passes 1,128 tests with 14 historical cases ignored. The
additional held-key and topology regressions run in the focused live suite.
No opt-in historical renderers or release build ran for this integration.

## 2026-09-04 Pressure Chain research and isolated listening gate

Research into the Behringer TD-3-SB is recorded in
`docs/ACID_CHAIN_RESEARCH.md`. `SB` is the Strawberry/red colour variant of the
ordinary TD-3 (`SR` is silver), not a separate synth architecture.
Manufacturer documentation establishes the broad monophonic chain: one
selectable reverse-saw/pulse VCO, resonant
four-pole low-pass, envelope-controlled filter motion, amplitude control,
accent and slide sequencing, then switchable output distortion. Roland and
Robin Whittle sources clarify the more important performance behavior: accent
couples brightness and loudness through a stateful sweep, while slide slews
pitch under a held gate rather than behaving as an ordinary retrigger. Tim
Stinchcombe's filter analysis supports treating the reference ladder as a
four-stage system despite conflicting 18/24 dB shorthand.

The resulting **Pressure Chain** experiment preserves only that causal idea.
Its PolyBLEP falling-ramp/variable-pulse source, causal nonlinear filter cells,
coefficient/range choices, pressure-memory state, and three routings are
independently authored. `DeepCascade` uses all four cells serially; `BodyTap`
recombines a protected two-cell body with the four-cell edge; `CrossFeed`
returns bounded differentiated stage-two energy through one-sample-delayed
cross paths. This is not a TD-3/TB-303 circuit, preset, sequencer, compatibility
mode, or product identity, and no third-party source, values, diagrams,
patterns, prose, or audio were copied.

The exact timbral surface is `SOURCE`, `SHAPE`, `CUTOFF`, `RESONANCE`, `SWEEP`,
`DECAY`, `PRESSURE`, and `BITE`, followed by SHR Synth's normal amp ADSR. A
trigger refreshes the filter sweep without forcing a discontinuous oscillator
restart; a slide slews pitch without restarting either contour. Velocity
charges pressure memory, close high-velocity events accumulate it, and it
jointly affects cutoff, pulse asymmetry, and colour before relaxing.

The isolated public module and `pressure-chain-lab` are not reachable from
`Engine`, presets, the factory catalog, or SHR-DAW. The lab presents the three
genuinely different routings under one identical 56-step note, velocity,
slide, and cutoff score. Focused contracts prove eight distinct controls,
distinct topology output, deterministic finite dual-mono rendering, a 0.94
bound, allocation-free note/control/sample/reset paths, non-retriggering slide,
stateful pressure, exact release silence, deterministic lab output, and a
maximum adjacent-sample jump below 0.90. The generated files peak from
0.891432 to 0.919852 with RMS 0.383755 to 0.431874 and absolute DC below
0.005727.

The WAV-generating CLI contract is development-only and ignored in the normal
suite now that its deterministic evidence is recorded. Run it on demand with
`cargo test --test pressure_chain_cli -- --ignored` when its renderer,
presentation score, output contract, or recorded evidence changes.

The conservative 48/384 kHz fitted residual diagnostic ranges from -15.683015
to -1.709247 dB across MIDI 36/60/84. It deliberately conflates nonlinear
transfer, filter phase/time response, and foldback, so it is engineering
evidence rather than an aliasing or sound-quality acceptance claim. Human
listening, live integration, Raspberry Pi load, JACK/ALSA/MIDI, and hardware
testing remain open. Do not add a preset/schema/Engine/SHR route until the
owner chooses a topology or asks for further development.

## 2026-08-28 stale release-host repair

SHR's source catalog already discovered all 21 cleared SHR Synth presets, including
the five strict schema-8 Dual Filter sounds, but the configured
`target/release/shr-synth` artifact had last been built before schema 8. Loading
a Dual Filter sound therefore exited immediately with `unsupported preset
schema version 8`, after which SHR correctly restored the prior synth. This was
an executable/source mismatch, not a preset or private-configuration defect.

The release executable is refreshed from current source. All 21 cleared
presets pass that exact executable's offline validator. Two one-second
production renders of Dual Filter Counter Growl at the same note, velocity,
rate, and duration are byte-identical (SHA-256
`862404947e81fd5edaee233588b58507d5026d2c88513f3c20bca86014dc515b`).
Formatting, the complete normal all-target/all-feature suite, warning-denied
Clippy, the release build, `cargo audit`, and `cargo deny check` pass; the
normal suite's historical/audition/benchmark cases remained intentionally
ignored. No JACK, synth process, MIDI, playback, hardware, or audible test was
started or changed by the agent.

## 2026-08-28 SHR 3×5 host-surface integration

SHR's controller correction makes that host surface direction-only: the master
and all fifteen mapped rotaries must emit Relative 1 or Relative 2 steps.
Positional 0–127 rotary modes are no longer learned, stored, decoded, or
presented as a supported controller option. SHR Synth's MIDI CC and preset
contracts are unchanged; SHR carries its current parameter value and sends the
resulting CC update to SHR Synth. The old MiniLab 3 positional parameter knobs are no
longer bundled as a valid performance mapping.

SHR-DAW's 15-rotary performance surface now has one explicit 3×5 contract.
Dual Filter's existing schema-8 host integration remains a full fifteen synth
controls on CC20–34. The five older SHR Synth models retain their settled twelve
continuous synth controls; SHR owns physical slots 13–15 outside SHR Synth and
uses them for the current Project's AUX 1, AUX 2, and AUX 3 send levels. Those
messages are consumed by SHR and are not translated or forwarded to this
engine, so SHR Synth's older preset schemas and DSP contracts do not change.

The SHR Player and FT2 parameter child render older SHR Synth models as twelve synth
values plus three aux sends, while Dual Filter renders all fifteen synthesis
values. SHR expands its bounded wet-aux graph to three buses and Project format
18. SHR Synth source and preset files are unchanged by this host-side work.
SHR formatting and whitespace checks passed; its standing combined-pass gate
means no Cargo compilation/tests or live MIDI/JACK/audio/controller acceptance
has yet run for this integration.

## 2026-08-27 dual-filter/envelope controller exercise

The owner reported a replacement physical controller with sixteen rotaries in
total. One remains the master rotary, leaving fifteen continuous synth
controls; two rotaries are clickable in total, so after reserving the master
there is one synth-specific push action. The physical arrangement is temporary
and will be revisited. This superseded the old hardware-count assumption. The
later explicit production approval expands only Dual Filter to 15 mapped
values; the five older models retain their 12-value contracts.

An isolated original dual-filter concept now tests that fifteen-control budget:
`A CUTOFF`, `A RESONANCE`, `A ENV DEPTH`, `B CUTOFF`, `B RESONANCE`,
`B ENV DEPTH`, `STRUCTURE`, filter ADSR, and amp ADSR. The one available synth
push toggles serial versus parallel routing and does not open a hidden control
page. The continuous routing control changes the A/B contribution in parallel;
in serial it moves from A-then-B toward direct-to-B, retaining a clear result in
both states.

`src/dual_filter_concept.rs` independently implements two trapezoidal-integrated
state-variable branches, log-spaced prepared cutoff coefficients, curved
filter and amp contours, a bounded nonlinear input/output response, and four
existing band-limited oscillators. `SweetSerial`, `ParallelSplit`, and
`CounterMotion` use fundamentally different filter/source routing topologies.
This is informed by the Korg multi/poly workflow, but it is not a Korg filter
model, factory preset, UI copy, compatibility mode, or production SHR Synth
model. No Korg code, preset, sample, diagram, parameter values, prose, or
figures were copied.

The first static three-file presentation was rejected as uninformative because
it exposed only three fixed points among many parameter combinations. Its first
sound nevertheless received a promising identity: a strange but "cute" lead
for nasty techno or electro-industrial use. The owner requested actual control
changes during playback and bass examples from the same machine. The rejected
batch was removed from the repository artifact tree.

The replacement disposable gate is
`artifacts/dual-filter-controller-listening/` and contains WAV files only. Its
first fifteen files retain that promising lead source and demonstrate one
physical rotary each. Direct filter/routing controls move continuously over a
held note; filter and amp envelope controls use repeated notes so their stages
can actually be heard. File 16 performs three click-conscious serial/parallel
topology pushes. Files 17-20 are low-register musical examples with audible
cutoff/resonance motion, counter-motion routing, envelope-punch motion, and
topology pushes. Direct controls use 10 ms smoothing and topology changes fade
out, switch at zero, and fade in over 5 ms per side.

Focused contract and CLI tests pass: exactly fifteen distinct controls,
deterministic distinct WAV-only output, finite bounded samples, allocation-free
sample/note paths, and byte-identical repeat generation. Earlier explicit
48 kHz versus 192 kHz fitted residuals range from -13.485698 to -22.490217 dB;
they conflate filter transfer/phase changes with foldback and remain diagnostic
only.

Human listening gave the complete exercise a strongly positive verdict:
the moving-control presentation is "awesome" and expected to work very well,
and all four bass examples have substantial potential and sound nice. This
passed the first musical concept gate for the dual-filter/controller machine,
not merely one static patch. The owner then explicitly approved production and
SHR-DAW integration.

Dual Filter is now the sixth production model. One instrument owns two
backstage cores: INDUSTRIAL preserves the accepted lead plus serial/topology
bass directions and continuously crossfades serial to parallel with STRUCTURE;
COUNTER preserves the accepted counter-motion growl direction and uses the same
STRUCTURE position as its routing/growl macro. Both cores and both INDUSTRIAL
branches render preallocated state continuously. CC35 changes only the core and
crossfades over 30 ms without retriggering a held note; CC36 restores exact
core state. All fifteen knob positions remain unchanged across the switch.

Preset schema 8 adds `dual_filter`, exact `[controls]` names, and persisted
`dual_filter_core`. Five factory starts preserve the accepted lead and four
bass directions. The existing five models, their CC20–31 behavior, and schemas
1–7 remain readable; Dual Filter uses CC20–34 and owns its filter and amp
envelopes internally. Focused production contracts cover all 15 controls,
continuous STRUCTURE endpoints/midpoint, held-note core crossfade, finite
bounded output, reset-to-silence, allocation-free note/control/core/sample
work, strict round-trip persistence, MIDI CC translation, and 21 distinct
finite factory starts.

No JACK server, ALSA hardware route, synth launch, physical controller, audible
review of the integrated host, or Raspberry Pi timing/headroom measurement was
performed. The production voice runs three synchronized concept graphs per
voice, so native Pi voice capacity is specifically open and must be measured
before any polyphony claim.

The workstation software pass completed after integration: formatting and
diff checks passed; the normal all-target/all-feature suite passed (277 library
tests passed with five documented development-only ignores, and every active
binary/integration test passed); warning-denied Clippy and the all-target
release build passed. `cargo audit` found no vulnerability, and `cargo deny
check` passed advisories, bans, licenses, and sources with only the existing
duplicate-`winnow` warning. Two independent release renders of Counter Growl
were byte-identical at SHA-256
`78b69760b7bd82d61de6e9ac365dc6f47fa0a1dd8592e8847f72ceebe17e4762`;
their temporary files were removed.

## 2026-08-16 two-model live integration

The owner explicitly requested two new instruments for immediate SHR testing.
The earlier warm-pad swarm hypothesis is now the fourth live model rather than
remaining offline: `model = "swarm_machine"`, `swarm_patch = "warm_pad"`, and
`presets/15-swarm-warm-pad.mojsint`. Its typed graph is parsed and compiled only
while fixed voices are constructed; frequency changes, controls, reset, and
sample rendering are allocation-free.

The fifth live model is the deliberately different Bass Matrix:
`model = "bass_matrix"`, `bass_matrix_patch = "transformer"`, and
`presets/16-bass-matrix.mojsint`. It keeps a clean phase-locked half-frequency
body outside a PM/metal/drive/filter/feedback branch so bass weight survives
aggressive transformations. Its seven physical timbre roles are `BODY`,
`GROWL`, `METAL`, `PUNCH`, `DRIVE`, `FILTER`, and `UNSTABLE`.

Preset schema 7 adds exact identities for both models plus independent
`instrument_volume`. Schemas 1–6 migrate at unity volume. Physical position 5
is now volume for every SHR Synth model; MIDI CC 7 drives a separate 10 ms output-gain
smoother and does not alter model tone. The historical fifth timbre macro stays
serialized so old preset/automation sound identity remains intact. SHR-DAW owns
matching catalog, Player, FT2, pickup, reset, save, and automation routes for
all five models.

Automated output evidence is technical only. Native Raspberry Pi callback
headroom and the musical usefulness of both new starts remain owner listening
decisions; do not claim either from workstation tests.

The authorized combined pass used exact Rust 1.97.1
(`rustc 1.97.1 (8bab26f4f 2026-07-14)`). Formatting, locked all-target and
all-feature checking, the complete normal test suite, and debug and release
all-target/all-feature builds passed. The suite left 34 documented historical,
audition, and benchmark tests ignored. Both release presets validate with the
release CLI. No JACK, ALSA, MIDI, synth launch, or audible test was performed.

## 2026-08-05 Strange Oscillator live experimental integration

The gated Strange Oscillator experiment is now the third live synthesis
model. One `TYPE` macro selects triangle, saw, pulse, modulated resonator,
deformed loop, stochastic breakpoints, scanned string, or register machine
with a 10 ms crossfade. The remaining timbral positions are `FORM`, `WARP`,
`COUPLE`, `MOTION`, `CHAOS`, `COLOR`, and `SPACE`; positions 9–12 remain ADSR.
The engine preserves this model's stereo output while Model D and Six-Op PM
remain dual mono. Live rendering is finite, bounded, deterministic, and
allocation-free, including rapid macro movement.

Preset schema 6 adds `model = "strange_oscillator"`,
`strange_patch = "unified"`, and the exact model-specific macro names. Schemas
1–5 still load and migrate in memory. The cleared starting point is
`presets/14-strange-oscillator.mojsint`. SHR-DAW has matching schema, catalog,
route, save, automation, and model-specific control support in its working
tree. This remains experimental product work. On 2026-08-05 the owner
explicitly authorized committing and publishing it for continued
experimentation before the open musical and native-load verdicts. Publication
is not production acceptance.

## Historical 2026-08-05 typed swarm micro-machine experiment

This section records the earlier isolated gate. Its stop decision was
superseded by the owner's 2026-08-16 instruction above to wire the warm-pad
hypothesis as a live model.

The smallest useful vertical slice of the low-code typed micro-machine
direction began as an isolated offline experiment. The tracked authoring input is
`experiments/swarm-micro-machine-v1.toml`; generated listening material is
disposable below ignored `artifacts/micro-machine-swarm-v1/`.

Schema 1 is deliberately specific to this experiment. It compiles seven
transparent node kinds—phase swarm, bandlimited saw bank, bounded stereo mix,
spectral tilt, bounded drive, stereo width, and output guard—rather than
hiding the instrument inside one supersaw node. The typed route is
`PhaseBank -> OscillatorBank -> AudioStereo -> GuardedStereo`. Unknown graph
or node fields, unknown node types, duplicate IDs, bad references, incompatible
ports, instantaneous cycles, non-finite/out-of-range values, and fixed resource
limit violations fail before rendering. Compilation allocates and prepares an
immutable deterministic topological plan; sample/block rendering uses only its
fixed mutable state and caller-owned output.

The exact experimental timbral controls are `MASS`, `DETUNE`, `SPREAD`,
`SHAPE`, `BITE`, `MOTION`, `COLOR`, and `SPACE`. ADSR remains the existing
outer four-control envelope and is not represented as a graph node. MASS
crossfades a preallocated population without allocation, DETUNE and MOTION
drive prepared phase/drift/gear state, SPREAD places the individual machines,
SHAPE moves the bandlimited waveform bank, and the four downstream controls
own their named spectral, nonlinear, and stereo stages. The deterministic
cycle gear perturbation gives MOTION a small machine-coupled phase behavior
without an instantaneous feedback cycle.

The current graph compiles to seven nodes, six edges, nine oscillator slots,
3,416 fixed state bytes, and a conservative declared 355 work units per sample.
These are bounded scalar implementation facts, not workstation timing,
Raspberry Pi callback, polyphony, or latency claims. Focused contracts cover
strict parsing/validation, deterministic plan identity and seeded reset,
allocation-free machine and outer-voice rendering, rapid live controls,
internal/output bounds, low/mid/high notes, a three-note chord, real stereo,
mono fold, MASS gain normalization, note release/panic cleanup, conservative
48 kHz versus 384 kHz error diagnostics, and resource ceilings.

`micro-machine-lab` renders eleven clearly named dry float32 stereo WAVs: a
neutral reference, forceful lead, warm pad, and one low/high demonstration for
each timbral control. It also writes deterministic hashes, level/stereo/mono
measurements, the compiled resource summary, and alias/error diagnostics. No
reverb or production effect is present. Automated evidence proves that the
small TOML graph can become a strict fixed render plan and produce a bounded,
recognisably swarm-oriented listening set. It does not prove musical value,
production readiness, native Pi headroom, or safe polyphony. It supplied the
evidence later used for the deliberately narrow live integration above.

Focused validation used pinned Rust 1.97.1. Eight micro-machine contract tests
and the offline-lab CLI test pass; the focused binary/test Clippy command passes
with warnings denied, formatting passes, and two independently generated lab
directories compare recursively byte-for-byte. The final listening set peaks
at 0.434786 or below and every report row is finite. Neutral 48 kHz versus
384 kHz fitted residual diagnostics are -24.821754, -21.198766, and
-13.636553 dB at MIDI 36, 60, and 84. The complete production suite,
historical/ignored research matrices, release build, native benchmark, JACK,
ALSA, MIDI, playback, and hardware tests were intentionally not run for this
isolated new experiment.

The owner listened to the complete dry set on 2026-08-06. The warm pad was
described as really nice and is the only promising result from this pass. The
neutral reference, forceful lead, and control demonstrations were not
compelling, and the graph is not accepted in its current overall “shape.” This
was not approval of the complete batch. The later 2026-08-16 instruction chose
the pad as the specific live hypothesis while leaving the rejected sounds out
of the factory catalog.

The listening discussion also exposed the next authoring gap. Schema 1 lists
the eight public control names, but their destinations are still fixed by the
Rust node implementations: MASS/SPREAD own the mixer, DETUNE/MOTION own phase
state, SHAPE owns the waveform bank, COLOR owns the spectral node, BITE owns
drive, and SPACE owns width. A later graph-authoring slice should make those
bindings explicit and typed in TOML, including target parameter, bounded
range, curve/polarity, smoothing, and optional coordinated gain compensation.
Graph topology, maximum allocations, seed policy, state/delay sizes, and the
final safety ceiling remain compile-time constructor policy rather than live
knob targets. Do not build this extension until its exact small graph and
listening question are chosen.

## Open experimental direction

SHR Synth should become open to model creation, not merely source-visible. The
favored long-term authoring surface is the typed low-code micro-machine format
already outlined in `docs/MICRO_MACHINE_ROUTING.md`, usable directly or with AI
assistance while retaining the fixed eight-timbral-controls-plus-ADSR surface
and all real-time validation. A swarm or supersaw-like instrument is a possible
first familiar experiment for this architecture, not an approved model or
scheduled promise. The concise product intent is in
`docs/FUTURE_DIRECTION.md`.

## User working preferences and authorization

- The user explicitly authorizes installing any tools and user-local
  dependencies needed for this work. Do not repeatedly ask for permission for
  ordinary in-scope installation.
- The assistant cannot use sudo. Report any required system package with the
  exact command for the user to run.
- If a tool would materially accelerate or improve the work, mention and
  recommend it instead of silently working around its absence.
- Keep the OpenAI documentation MCP disabled unless a real OpenAI-specific
  question requires it. It has recently been slow and is unnecessary for this
  project setup.
- Research should preserve direct links, authorship, publication details,
  licensing implications, and notes about why each source matters.
- New-task prompts should state project work, context, and acceptance criteria;
  they should not copy generic agent or skill instructions that the next
  session will already load.

### Experimental intent and rapid idea capture

The user is building SHR Synth to explore unfamiliar machine behavior, not to
make another conventional sine/saw synthesizer or to demonstrate music-theory
knowledge. The desired instrument is a machine whose physical controls produce
meaningful, discoverable responses and can reach sounds worth playing without
hiding experimental behavior behind generic presets.

Capture the user's new sound or machine ideas in this handoff or
`docs/RESEARCH.md` promptly, even when they arrive as incomplete metaphors,
rough implementation thoughts, or apparently incompatible mechanisms. Do not
require the user to translate an idea into established synthesis terminology,
and do not silently normalize unusual ideas into familiar subtractive-synth
patterns. Preserve the strange premise, separate what is known from what is
speculative, and turn it into the smallest bounded experiment that could prove
or reject it.

Think from the machine outward as well as from acoustics or music theory
inward. Registers, integer overflow, shifts, rotates, carry, quantization,
lookup addressing, state-machine cycles, memory layout, connection order, and
cheap parallel state are legitimate sources of sound hypotheses. Mathematical
or psychoacoustic analysis should help bound and understand those hypotheses;
it should not automatically replace them with textbook oscillator designs.

## Experimental-output and variation policy

This policy applies specifically to sound-research experiments. Generated
audio, measurement tables, manifests, batch-specific reports, parameter files,
and similar experiment outputs are disposable by default. Generate them under
the ignored `artifacts/` tree or outside the repository. When an experiment is
rejected, record its conclusion and limitation in the durable research/handoff
documents, then delete the generated batch rather than archiving it.

If a batch, individual tone, experiment-specific document, parameter/preset
file, or other output appears worth developing or retaining, the assistant may
offer to preserve that exact material. It must not copy anything into a
separate tracked directory unless the user explicitly requests preservation.
No preservation directory should be created speculatively. This restriction
does not apply to ordinary source code, tests, or concise updates to durable
project documentation.

Listening experiments must compare fundamentally different sound-generation
hypotheses: for example, a phase-structured multi-oscillator source versus a
noise-excited resonator versus another genuinely distinct topology. Different
parameter values, drive amounts, filtering strengths, wet levels, or several
closely related saw/sine variants do not count as different sounds. Automated
parameter sweeps remain useful for bounds, aliasing, stability, and cost, but
must not be presented as the musical-variation listening gate.

## Current workspace state

At this checkpoint:

- The current sound-research milestone is one isolated monophonic Strange
  Oscillator instrument, not eight instruments. One `TYPE` control selects
  triangle, saw, pulse, modulated resonator, deformed loop, stochastic
  breakpoints, scanned string, or register machine. Runtime changes prepare the
  new topology and crossfade for 10 ms; switching and both sample paths are
  allocation-free. The other seven timbral roles are `FORM`, `WARP`, `COUPLE`,
  `MOTION`, `CHAOS`, `COLOR`, and `SPACE`, followed by the unchanged outer ADSR
  contract. Production `Engine`, schema, presets, host, JACK/ALSA, SHR-DAW, and
  voice count remain unchanged during this gate.
- The first 28-reel low/high mapping was rejected by the owner after Triangle:
  all seven controls sounded like small variations of the same basic sound.
  Its raw full-output residual floor is not acceptable evidence and must not be
  cited as success. The replacement adds common structural stages after every
  topology: strong contour/fifth-harmonic deformation, inharmonic cross/ring
  coupling, a 0.05–50 Hz deep cyclic envelope, deterministic whole-cycle
  admit/drop chaos, fundamental-to-fifth harmonic color anchoring plus two-pole
  tone control, and protected mid/side width. Source-specific FORM behavior is
  retained.
- All eight TYPE positions now pass all seven domain-specific landmark tests.
  FORM/WARP require at least 6 dB normalized harmonic-profile distance;
  COUPLE requires at least 0.25 cycle decorrelation or equivalent normalized
  spectral-topology displacement; MOTION proves at least 6 dB envelope depth
  at each measured endpoint and a 200× rate ratio; CHAOS adds at least 0.08
  nonrepeatability between modulation-cycle envelope contours; COLOR moves the
  harmonic center by at least 2×; SPACE changes side/mid energy by at least
  12 dB. These gates reject inert mappings but do not establish musical value.
  Separately, the conservative high-rate diagnostic still rejects Saw,
  stochastic breakpoints, and scanned string at MIDI 84 and rejects the
  register machine at every test note; TYPE retention for listening is not a
  production alias/sample-rate acceptance claim.
- The redesigned disposable listening batch contains exactly sixteen files:
  eight neutral TYPE references, one uninterrupted held-note TYPE reel through
  all eight positions using the live crossfade, and seven plainly named
  `low, silence, high` macro reels on Saw, which the owner preferred in the
  earlier source comparison. MOTION's low state lasts eleven seconds; CHAOS
  endpoints last four seconds. No ADSR, effect, master strip, input mix, other
  synth, sampler, drums, JACK, ALSA, MIDI, or SHR-DAW is rendered. Human
  listening of this replacement batch is the next decision. The owner-authorized
  AudioBox playback completed in TYPE, FORM, WARP, COUPLE, MOTION, CHAOS,
  COLOR, SPACE order and the temporary JACK ports disconnected cleanly; the
  owner's musical verdict remains open.
- Fresh Rust 1.97.1 AArch64 validation passed formatting, `git diff --check`,
  all 304 active normal all-target/all-feature tests, warning-denied Clippy,
  and the release lab build. Thirty-four historical research, audition,
  publication-recovery, and native-benchmark tests remained intentionally
  ignored. Two independent release batches matched recursively byte-for-byte;
  the aggregate `sha256sum` of the canonical top-level inventory is
  `d934ec46f6e17853abd261d283f1656b15b58883830f66b544bb53f5cdd4f75e`.

- Version 0.2.3 makes the public install boundary reproducible without changing
  synthesis or host behavior. `rust-toolchain.toml` now pins exact Rust 1.97.1,
  `presets/cleared-presets.txt` names the 13 project-authored factory starts,
  and `THIRD_PARTY.md` records their MIT/public boundary plus the locked
  dependency licence review. Whole-system installation is owned by SHR-DAW;
  ignored experiments and private user presets remain outside that path.

- The single SHR Synth host now exposes two synthesis models without splitting
  JACK/ALSA ownership. `Engine` voices dispatch through a fixed model enum:
  Model D has seven authored starts and Six-Op PM has six. Strict schema 5
  gives each model its own patch field and exact macro table; schemas 1–4
  migrate to Model D in memory.
- The live-host/control boundary still owns one process, one ALSA input, two
  JACK outputs, bounded event timing, shared voice stealing, one outer ADSR,
  and the same twelve physical CC positions. The loaded model supplies the
  first eight control meanings; CC 28–31 remain ADSR.
- `shr-synth --client-name NAME --preset FILE` implements the owned live
  process: dynamic JACK with `JACK_NO_START_SERVER`, exactly `out_l`/`out_r`,
  one ALSA Sequencer `input`, fixed SPSC timing handoff, overflow counters,
  panic, and SIGINT/SIGTERM/JACK-shutdown cleanup. Connected JACK and physical
  acceptance remain intentionally untested.
- The stable schema is version 5. Model D uses `model_d_patch` and its original
  eight timbral macros; Six-Op PM uses `six_op_patch` plus `index`, `ratio`,
  `feedback`, `operator_decay`, `balance`, `key_scale`, `velocity`, and
  `motion`. Strict version-2 migration selects Model D bass, and version-1
  migration also discards only its provisional `WIDTH` and redundant envelope
  table.
- `Preset::to_toml` is the public strict writer for user-preset publication.
  It validates model/patch identity, always emits schema 5, preserves voices,
  output gain, and the exact model-specific patch, and writes only that model's
  twelve macro names. Parsing the result yields the same in-memory preset.
- SHR-DAW Playback now uses Overwrite/Save New/Cancel for live synthv1 and SHR
  Synth sounds. SHR Synth user sounds are private numbered files split beneath Model D
  and Six-Op PM directories, appear immediately in Presets and FT2 ROUTE, and
  become the new RESET baseline without restarting SHR Synth. Factory, public,
  unsupported, malformed, oversized, and symlink-backed sources remain
  non-overwritable; failed publication preserves the live session and prior
  file.
- The Model D catalog contains Full Bass, Full Lead, Full Filter Articulation,
  Matched Idealized, Matched Linear Mixer, Matched Linear Ladder, and Matched
  No Drift or Feedback. Each preserves the corresponding audition coordinates
  while retaining all twelve live controls. The Six-Op PM catalog contains
  Bell Metal, Fractured Metal, Electric Piano Mallet, Glass Wood, Brass Bass,
  and Mechanical Stab. These are starts within their models, not separate
  engines.
- The final 2026-08-01 locked production gate used Rust 1.97.1 on AArch64. The
  full all-target/all-feature normal suite passed 276 tests with zero failures
  across 27 harnesses; 34 historical render, research, publication, and native
  benchmark tests remained ignored. The main library harness took 129.67
  seconds. Formatting, locked check, fresh debug build, strict serializer
  regressions, and direct integration coverage passed. The repository-local
  SHR configuration selects this checkout's fresh debug host without reading
  private user sounds. No JACK, ALSA, MIDI, playback, audible, or
  physical-hardware test was run.
- `WIDTH` was removed solely because this Model D production path is dual-mono
  and contains no width experiment. There is no hidden thirteenth control.
- The shared project notebook lives at
  `/home/shome/Documents/knowledge/SHR-Synth/Current.md`. Tracked docs and live
  source remain authoritative. After material decisions, update this handoff
  first, then that concise note, validate the notebook, and rebuild the shared
  index.

- Git state, branch, and artifact existence must be inspected live rather than
  inferred from this handoff.
- The Rust crate contains the portable DSP/control/preset/engine library,
  offline renderer/validator binary, tests, reference preset, and documentation.
- The first bandlimited-oscillator milestone is implemented: fair scalar
  PolyBLEP and integrated-wavetable candidates were measured, the integrated
  wavetable was selected by the recorded rule, and smoothed `SHAPE`/`COLOR`
  routes now drive the engine.
- The oscillator listening matrix was rejected as insufficiently varied. All
  generated milestone artifacts have been removed from the workspace; only
  the documented measurements and disposable generators remain.
- The rejected harmonic selector has been retired from the engine render path.
  The subsequent per-voice parallel character layer also failed listening: it
  presented the same weak source under similar treatments rather than distinct
  sound identities. It is not an accepted factory sound or macro mapping.
- The foundation engine can preallocate multiple voices, but this is not a
  final whole-system polyphony commitment. Native Raspberry Pi 5 callback
  simulation at 48 kHz/64 frames established an engine-budget provisional cap
  of eight tested voices: the corrected ten-minute rapid-control soak had zero
  deadline misses, 3.992% p99.9 period use, 9.751% maximum period use, finite
  output, flat RSS, and no new throttling. The new live host has not been
  measured in connected SHR/JACK, so final whole-system polyphony remains open.
- User-local stable Rust 1.97.1, Cargo, rustfmt, Clippy, cargo-audit, and
  cargo-deny are installed.
- No audio service or hardware was touched while implementing the live host.
- The approved five-family comparison is implemented as isolated disposable
  offline research code. The user found the direction promising but still far
  from the intended instrument; no family is selected and none is routed into
  `Engine` or stable macros. The reviewed 15-file batch was deleted under the
  experimental-output policy.
- The approved clean-room-oriented six-operator PM gate passed its automated
  acceptance bounds. Its independently authored fixed-capacity core validates
  32 source-numbered connectivity records; six selected sounds using source
  algorithms 1, 5, and 10 are now factory starts in the second production
  model. A bounded live adapter reaches them through the existing `Engine`,
  host, JACK/ALSA, and SHR-DAW ownership path with model-specific controls.
  No expressive manual content, code, diagrams, voice data, or SysEx data was
  reproduced in the recorded process. It makes no compatibility or historical
  emulation claim; separate legal review governs distribution. Live musical
  acceptance and native callback headroom remain open.
- A second isolated gate now implements three complete, structurally different
  hybrid voices with genuine stereo plus single-note, held-chord,
  four-chord-progression, and explicit mono-fold auditions. Automated evidence
  passes the predeclared finite, level, DC, stereo, mono, and target-note
  bounds, but human listening is still open. Nothing is selected, mapped, or
  routed into the production `Engine`.
- The first strongly positive listening direction came from accidentally
  combining all twelve hybrid files in separately launched player processes.
  A new isolated composite-machine lab reconstructs a synchronized
  counterfactual, a clearly labeled delayed-launch estimate, and five
  structurally different successor graphs. Its corrected hot presentation now
  adds fixed-gain full-score, D1/D2/D3, D1-pedal, punch-envelope, mono, and raw
  sections. Engineering bounds pass, but the musical verdict is open.
- The compact one-to-three-mechanism power experiment was rejected completely:
  none of its newly designed sounds worked, and its 4.854-29.208% clipping
  overcorrected the request for a slightly hotter signal into prolonged
  distortion/noise. Its generated batch was deleted.
- Human listening rejected the eight-file coherent composite gate as steady
  tones. Although its layers shared a nominal ADSR, the 0.88 sustain held most
  of each long source near a constant level, so it did not expose the requested
  audible envelope shapes. Its generated batch was deleted.
- Human listening rejected the 2.4-second monophonic envelope batch: its 0.58
  sustain still held too long, and its attack/decay behavior was too slow. The
  generated batch was moved to Trash.
- Human listening rejected the 800 ms piano-strike batch as a muted,
  towel-damped imitation without convincing natural decay. Its body was the
  old source sum under a broadband amplitude contour, so the strike did not
  excite an independently decaying object. The generated batch was moved to
  Trash.
- Human listening selected Coupled Wire from the three struck objects as very
  nice, bright enough, and not excessive. Spectral Plate and Dual Bridge were
  not selected for continued work. The prior batch was moved to Trash only
  after its exact Coupled Wire reference was reproduced byte-identically.
- Human listening rejected the Coupled Wire envelope/motion batch. Only its
  exact first reference was somewhat usable; the longer envelopes and orbit
  developments were not retained. At high line-output gain the reference
  exposed excessive bass/sub distortion. Inspection found that its complete
  signal was hard-clamped at -0.3 dBFS from about 8-80 ms while its 45-90 Hz
  onset band remained very strong.
- The controlled-thump successor kept the original 73 Hz fundamental and sub
  path clean and centered, reduced only their strike crest, and moved bounded
  hard-crest character into a 105-500 Hz branch for a short onset window.
  Its historical engineering checkpoint is recorded below; nothing from that
  experiment was integrated.
- The formerly isolated Model D character model exercises a documented
  three-VCO, nonlinear mixer, four-stage nonlinear ladder, dual-contour, VCA,
  and output-feedback path. It is now the production `Engine`; all its modeled
  mechanisms remain open for user evaluation through the complete controls.
- A 2026-08-01 native Player audition exposed note-count-dependent distortion:
  Model D failed audibly at two held notes and Six-Op PM at four. Inspection
  found that SHR was launching this checkout's unoptimized
  `target/debug/shr-synth`. A focused factory-chord render remained finite and
  below full scale, while the native callback smoke measured one production
  Model D voice at 20.609% mean / 21.700% maximum of a 48 kHz, 64-frame period
  in debug versus 2.967% mean / 3.949% maximum in release. The concurrently
  running four-slot Six-Op debug host used about 36% of one CPU in a short
  observation at the live 128-frame JACK period. This supports callback
  starvation/xruns, not mix clipping, as the defect. SHR now launches the
  fresh `target/release/shr-synth`, and the user confirmed that the reported
  two-note Model D and four-note Six-Op artifacts are gone. The connected path
  therefore has direct user acceptance for this defect only; broader control,
  routing, polyphony, and sound acceptance remain open.
- SHR's source repair makes SHR Synth the first visible engine and
  renders its stable factory identities compactly without changing preset or
  Project route IDs: for example, `01 M-D Full Bass` and
  `08 6-OP Bell Metal`, with no duplicate list/model number or bracketed model
  sentence. On native AArch64 Rust 1.97.1, the focused SHR Synth/order/screenshot
  regressions and complete normal SHR suite passed, with 912 tests passed and
  12 historical/development tests intentionally ignored. Locked check, debug
  and release builds, formatting, dependency audit, and regeneration plus exact
  comparison of all 142 deterministic screenshots also passed. Warning-denied
  Clippy still finds 38 pre-existing repository-wide lints outside this repair;
  `cargo deny` has no repository policy file and therefore rejects all licenses
  under its default configuration. Live visual confirmation remains open until
  the user next relaunches SHR.
- SHR-DAW was rechecked read-only at main commit
  `8b7d0d7c17c582292ac06a915ca1fe750d77bc40` using a temporary clone.

## Development-machine audit

Current machine:

- Ubuntu 24.04.4 LTS, x86_64
- Linux 6.8.0-136-generic
- AMD Ryzen 5 5600G, 6 cores / 12 threads
- 62 GiB RAM
- approximately 214 GiB free on the workspace filesystem at audit time

Present tools and runtimes:

- GCC/G++ 13.3
- Make, CMake 3.28, `pkg-config` 1.8
- Git 2.43 and authenticated GitHub CLI
- JACK 1.9.21 runtime
- PipeWire 1.0.5 runtime
- ALSA runtime utilities and visible playback devices
- `perf`, `gdb`, `chrt`, and `taskset`
- Rust 1.97.1, Cargo 1.97.1, rustfmt, Clippy, cargo-audit, and cargo-deny
- ALSA development package `libasound2-dev` 1.2.11-1ubuntu0.3; `pkg-config`
  resolves `alsa` 1.2.11

Still missing:

- JACK development metadata
- PipeWire development metadata
- Clang/LLD, Valgrind, rr, hyperfine, and just

Rust and ALSA development metadata were missing during the original machine
audit and are now installed as recorded in the present-tools list. The
remaining tools are not needed for the current portable foundation and should
not be installed speculatively.

Do not install every missing item automatically. Install only what the chosen
architecture or validation actually needs. On this development machine,
`libasound2-dev` is already installed. A fresh Raspberry Pi OS machine will
likely need:

```sh
sudo apt update
sudo apt install libasound2-dev
```

Whether JACK development headers are required depends on the selected Rust
boundary. SHR-DAW itself dynamically loads `libjack.so.0`, avoiding a build-time
JACK development dependency. Evaluate that approach against a maintained Rust
JACK crate before choosing.

## SHR-DAW integration source of truth

The repository named in the first discussion had a spelling mismatch. The
actual public repository is:

<https://github.com/PaolaShultz/shr-daw>

The GitHub owner is `PaolaShultz`, with a final `z`.

The inspection used the current `main` branch on 2026-07-22. Recheck current
files in a new session because this repository is actively changing. Important
sources are:

- [`src/engine.rs`](https://github.com/PaolaShultz/shr-daw/blob/main/src/engine.rs)
- [`src/preset.rs`](https://github.com/PaolaShultz/shr-daw/blob/main/src/preset.rs)
- [`src/config.rs`](https://github.com/PaolaShultz/shr-daw/blob/main/src/config.rs)
- [`src/control.rs`](https://github.com/PaolaShultz/shr-daw/blob/main/src/control.rs)
- [`src/midi.rs`](https://github.com/PaolaShultz/shr-daw/blob/main/src/midi.rs)
- [`src/jack.rs`](https://github.com/PaolaShultz/shr-daw/blob/main/src/jack.rs)
- [`src/ui.rs`](https://github.com/PaolaShultz/shr-daw/blob/main/src/ui.rs)
- [`config/shsynth.conf`](https://github.com/PaolaShultz/shr-daw/blob/main/config/shsynth.conf)
- [`docs/AUDIO_GRAPH.md`](https://github.com/PaolaShultz/shr-daw/blob/main/docs/AUDIO_GRAPH.md)
- [`docs/CONTROLLER_INTERFACE.md`](https://github.com/PaolaShultz/shr-daw/blob/main/docs/CONTROLLER_INTERFACE.md)
- [`docs/HOW_IT_WORKS.md`](https://github.com/PaolaShultz/shr-daw/blob/main/docs/HOW_IT_WORKS.md)
- [`docs/PI5_HEADROOM_PLAN.md`](https://github.com/PaolaShultz/shr-daw/blob/main/docs/PI5_HEADROOM_PLAN.md)

### Observed instrument-host contract

SHR-DAW currently manages synthv1, Yoshimi, and FluidSynth as distinct
backends and distinct preset catalogs. Only one SHR-owned software instrument
runs at a time.

The integration model is:

```text
MIDI controller / SHR sequencer
             |
      ALSA Sequencer MIDI
             |
       managed synth process
             |
       stereo JACK outputs
             |
 direct playback or SHR audio graph
             |
       configured interface
```

Important behavior:

- Software-instrument audio is JACK-first. JACK is required for managed synth
  audio, loops, effects, and recording.
- MIDI to the managed synth uses ALSA Sequencer through `midir`.
- SHR-DAW starts and owns one external synth child at a time.
- Readiness requires one unambiguous JACK client and exactly two audio output
  ports. A MIDI port alone is not readiness.
- Exact configured client names are preferred; a single unique prefixed JACK
  client is accepted for hosts such as Yoshimi.
- SHR first establishes conservative direct playback. Its optional owned graph
  can later move the synth into the effects/final-bus path transactionally.
- Process replacement sends All Notes Off and terminates only the child SHR
  owns. Unrelated synth processes and JACK routes must remain untouched.
- Executables, client names, preset roots, MIDI selectors, and JACK ports are
  configuration rather than Rust constants.
- SHR-DAW does not start or restart JACK.
- Its JACK callback forbids allocation, locks, file access, subprocesses,
  logging, formatting, panics, and per-sample trigonometry.

### Integration decision

SHR Synth should be a fourth native managed engine with its own identity. It
must not replace `synthv1.command`, inherit synthv1 preset parsing, or pretend
that `.mojsint` files are `.synthv1` files.

The desired live executable shape is provisionally:

```sh
shr-synth --client-name shs-shr-synth --preset /path/to/file.mojsint
```

The live host exposes:

- one stable discoverable ALSA Sequencer MIDI input;
- exactly two JACK audio outputs with stable short names;
- an explicit JACK client name supplied by SHR-DAW;
- graceful SIGINT/SIGTERM shutdown;
- bounded MIDI-to-audio event transfer;
- no automatic JACK startup or restart; and
- an allocation-free, lock-free, file-free real-time callback.

The DSP core must not depend on JACK, ALSA, files, or process management. The
same core should support unit tests and deterministic offline WAV rendering on
x86_64 and AArch64.

LV2 is not recommended initially because SHR-DAW is not currently an LV2 host.
Embedding SHR Synth directly into SHR-DAW is also not recommended initially
because it breaks the established process-ownership and failure-isolation
model. Direct ALSA audio would bypass and compete with SHR's JACK graph.

SHR-DAW 0.4.4 supplies the fourth `BackendKind`, preset ID, catalog discovery,
configuration block, process command, Project/Idea/FT2 route identity,
controller schema, pickup/reset handling, and Playback labels.

## Performance controller contract

Controller design is a first-class synth requirement. The target physical
surface exposes exactly twelve continuous synth controls: eight sound-shaping
rotaries and four ADSR pots. SHR's relative master rotary remains a host
navigation/context control and is not a thirteenth SHR Synth control.

The version-2 schema implements the settled twelve-control surface:
`EVOLVE`, `SHAPE`, `COLOR`, `EDGE`, `COUPLE`, `MOTION`, `DEPTH`, `SPACE`,
`ATTACK`, `DECAY`, `SUSTAIN`, and `RELEASE`. `WIDTH` was removed because the
production Model D path is dual-mono and has no width mechanism. No button,
hidden page, mode, or master-encoder takeover retains it.

Settled physical roles:

| Physical control | Musical role | Intent |
| --- | --- | --- |
| Rotary 1-8 | Exactly eight evidence-selected timbral/performance macros | Useful sound variation across the physical travel |
| Pot 1 | `ATTACK` | Perceptually scaled onset; may coordinate amplitude and timbre |
| Pot 2 | `DECAY` | Perceptually scaled decay; may coordinate amplitude and timbre |
| Pot 3 | `SUSTAIN` | Sustained level and, where authored, sustained spectral state |
| Pot 4 | `RELEASE` | Perceptually scaled tail; may coordinate amplitude and timbre |

The selected controls are semantic anchors, not fixed one-to-one DSP
parameters. A versioned preset may map one macro to multiple internal
parameters with explicit minimum, maximum, curve, polarity, smoothing, and safe
gain/energy compensation. For example, `EDGE` may increase fold depth, adjust
feedback damping, and reduce output gain together.

The four ADSR controls remain predictable even when they coordinate amplitude
and timbre envelopes. Time controls need perceptual/exponential mappings rather
than linear milliseconds.

### SHR-DAW controller implications

Current SHR-DAW behavior discovered during inspection:

- The physical synth surface provides 12 continuous mappings.
- They use pickup after preset load/reset and currently refer to verified
  synthv1 parameter indices.
- The master rotary is translated into internal `EncoderAction` UI events and
  is not forwarded to managed synths.
- On Playback, N00B mode temporarily uses the master rotary to choose a scale.

Required SHR Synth behavior in a later SHR-DAW change:

- Map the 12 continuous synth controls to the final eight timbral roles plus
  ADSR, with pickup after preset load, reset, or Idea restore.
- Keep the master rotary's SHR navigation/context responsibilities; do not add
  a SHR Synth-only encoder mode merely to preserve a ninth timbral candidate.
- Give SHR Synth its own stable macro CC/schema; it never inherits synthv1
  parameter indices or semantics.
- Follow SHR-DAW's actual continuous-control path. Safe, musically continuous
  parameters should affect held notes with smoothing.
- Treat “the next launched tone may receive the new value” only as permission
  for a simpler implementation where a particular structural or expensive
  change genuinely requires note-boundary application. It is not a global
  product constraint and must not be imposed merely for convenience.

### Control-usefulness gate

A factory preset is incomplete if any exposed control is decorative or nearly
inert. Each macro should affect most of its physical travel and remain useful
at ordinary notes, velocities, and held durations.

Automated rendering should detect at least:

- output unchanged beyond numerical noise;
- almost all change compressed into a tiny part of controller travel;
- non-finite or unbounded output;
- unintended silence at ordinary positions;
- unsafe level jumps or discontinuities;
- missing/incompatible parameter routes; and
- smoothing failure under rapid movement.

Useful measurements include waveform difference, RMS, peak, spectral centroid,
harmonic distribution, modulation depth, and envelope timing. These only prove
that a control changes output; they do not prove musical usefulness.

Every factory preset later needs a low-level human listening pass across
several notes, velocities, held durations, and polyphonic phrases. The user is
the final judge of whether the full physical travel is musically worthwhile
and whether the stable label matches what is heard.

## Voice-count strategy

The musical architecture is **mono-first, poly-later**, not mono-only:

- During oscillator research, routing experiments, macro mapping, and initial
  listening, render exactly one active musical voice. This makes phase,
  feedback, nonlinear gain, smoothing, and CPU cost attributable.
- Do not use the existing `voices = 8` foundation preset as evidence that eight
  complex voices are affordable. It only proves fixed preallocated voice
  storage for the simple current engine.
- Keep oscillator/DSP state structurally per-voice and keep the engine boundary
  capable of fixed polyphony; do not introduce global singleton DSP state that
  would make later expansion unsafe.
- Before expanding, run native Raspberry Pi callback timing under representative
  notes, macro motion, and worst-case topology. Establish a conservative budget
  with headroom for JACK, MIDI/event transfer, and the rest of SHR-DAW.
- Measure explicit 1-, 2-, 4-, and 8-voice cases, then repeat allocation,
  deadline, determinism, finiteness, level, and listening checks. Four voices
  may be sufficient and is an acceptable result; eight is neither required nor
  preferred without evidence.
- Polyphony may also need per-voice phase/seed policy, voice stealing, mix
  compensation, and reduced internal topology; none is selected yet.
- Do not promise a voice count until native evidence exists. The 1/2/4/8 test
  set is an evaluation ladder, not a commitment to its maximum. Monophonic
  design is a sequencing decision that protects sound research, not a product
  lock.

## Initial software direction

Keep the first implementation bounded:

- a pure Rust DSP library;
- a small headless host binary;
- deterministic offline WAV rendering;
- one simple reference oscillator before exotic oscillator work;
- preallocated voices, events, buffers, modulation routes, and DSP state;
- `f32` internal audio initially;
- a portable scalar implementation first;
- optional x86_64/AArch64 optimization only behind measured, compile-time
  gates; and
- native builds on both machines as the truth, with cross-compilation checks as
  supporting evidence rather than a substitute for a native Pi build.

Suggested focused modules, subject to the approved implementation plan:

```text
src/lib.rs              public engine boundary
src/engine.rs           voices, events, block rendering
src/control.rs          stable 12 IDs and CC 20-31 mapping
src/envelope.rs         perceptual ADSR behavior
src/dsp/mod.rs          finite guards and DSP primitives
src/dsp/oscillator.rs   first reference oscillator
src/preset.rs           strict versioned .mojsint parsing/validation
src/offline.rs          deterministic rendering
src/host/jack.rs        dynamic JACK lifecycle and callback boundary
src/host/midi.rs        ALSA Sequencer translation
src/host/queue.rs       bounded SPSC event handoff
src/main.rs             headless CLI and shutdown
```

Do not lock in this exact file map without checking what the approved design
and first tests require.

## Research backlog

After the repository and testable foundation exist, perform a structured web
investigation using authoritative or primary sources where possible. Preserve
links and references in project docs. Topics include:

- oscillator aliasing and band-limited waveform generation;
- PolyBLEP, minBLEP/minBLAMP, BLIT, wavetable, and additive methods;
- phase distortion, hard sync, FM/PM, and feedback oscillators;
- wavefolding and antiderivative antialiasing;
- nonlinear filters and virtual-analog modeling;
- coupled oscillators and chaotic systems;
- physical modeling and feedback-delay networks;
- modulation-matrix and macro-control design;
- perceptual parameter scaling and control ergonomics;
- denormals, parameter smoothing, DC blocking, and numerical stability;
- JACK real-time callback requirements;
- ALSA Sequencer MIDI; and
- Raspberry Pi 5, AArch64, and real-time Linux audio behavior.

Independently implemented Rust may use published equations and topologies with
proper provenance. Do not copy third-party DSP source code. Record licensing
and redistribution boundaries for every code, preset, sample, or other asset.

Also investigate maintained Codex skills, MCP servers, and command-line tools
for Rust DSP, source curation, persistent project knowledge, benchmarking,
dependency auditing, and Raspberry Pi deployment. Do not install speculative
or abandoned integrations merely because they exist.

The typed micro-machine routing direction is recorded in
`docs/MICRO_MACHINE_ROUTING.md`. Its first narrow swarm slice now connects
phase, oscillator-bank, stereo-audio, and guarded-output ports and compiles
outside real time into fixed state. The broader audio, integer-word, trigger,
measurement, feedback, and delay vocabulary remains future work. Do not turn
the isolated slice into a generic graph merely because its first listening set
exists.

Potential skill gaps identified so far:

- Rust real-time audio and DSP engineering;
- Raspberry Pi audio deployment and latency measurement;
- synth research/source curation;
- reproducible DSP benchmarking; and
- listening-test and sound-design experiment protocols.

The first broader oscillator-system survey is now recorded in
`docs/RESEARCH.md` under “Distinctive oscillator systems and routing survey.”
It covers Moog, Prophet-5, Buchla, DX7, Casio CZ, PPG, JP-8000, higher-order
FM, nonlinear modeling cost, and coupled oscillators, then converts the user's
intentionally speculative ideas into seven testable SHR Synth experiment
families. Continue from that register rather than reducing the next phase to
vintage emulation.

## Completed experimental phase: five-family listening gate

The user approved and completed a genuinely varied listening gate built from five separate
sound-generation hypotheses. These are not five parameter settings in one
graph, and the first implementation should not force all five into the
production `Engine`. Prototype them as disposable monophonic offline research
sources first:

1. **Nonlinear PM/complex oscillator.** Shape or fold a modulator before it
   drives a bounded phase-modulated carrier. Connection order, ratio, phase,
   DC control, and sideband behavior are part of the source identity; this is
   not another processed saw or sine bank.
2. **Excited comb/resonant source.** Excite tuned or deliberately inharmonic
   feedback combs with an impulse, noise burst, or another short excitation.
   Here the delay network generates the sustained tone. Compare pitch-locked,
   dispersed, and safely damped structures as engineering sweeps, but present
   the family as one listening candidate rather than pretending that several
   delay lengths are different source mechanisms.
3. **Psychoacoustic micro-delay spatial-motion source.** Use several very
   short, unequal, slowly changing delay paths to create controlled
   decorrelation, apparent space, and a sensation that energy moves or
   pulsates across the middle of the image or spectrum. Investigate precedence
   effect, comb coloration, interaural time/level relationships, mid/side
   energy, mono compatibility, headphone/speaker translation, and modulation
   audibility. It must have its own perceptual hypothesis and must not collapse
   into an ordinary chorus, flanger, ping-pong echo, or wet/dry sweep.
4. **Spectral-traversal source.** Traverse a small SHR Synth-authored family of
   related spectra or phase laws as one coherent identity. It must not become
   an arbitrary waveform browser or copy a commercial wavetable or preset.
5. **Small-register integer machine and oscillator swarm.** Build sound from
   explicitly sized integer phase/state registers, wrapping arithmetic,
   shifts, rotates, carry/borrow relationships, bit selection, and other
   bounded state-machine operations. For a fixed-point phase increment, a
   left shift can represent a power-of-two frequency relationship such as an
   octave until the defined-width boundary is reached; the boundary behavior
   must be deliberate rather than accidental overflow. Explore whether small
   registers, short cycles, quantization, and many extremely cheap interacting
   integer voices create useful controlled nastiness. This is a sound-source
   hypothesis, not merely a premature optimization exercise.

The comb/resonant and psychoacoustic micro-delay candidates are deliberately
separate. In the comb family, delay is the resonating sound generator. In the
psychoacoustic family, multiple sub-echo delays organize spatial perception
and internal motion. Sharing a delay-line primitive does not make the two
topologies equivalent.

Before implementation, research each family from primary or authoritative
sources and extend `docs/RESEARCH.md` with authorship, publication details,
direct URLs, licensing implications, and the specific design claim supported
by each source. Define a concise perceptual hypothesis for every candidate:
what the listener should recognize, why it differs structurally from the
other four, and what failure would sound like.

The first listening batch should contain one bounded representative of each
family, loudness matched across representative low, middle, and high notes.
Automated sweeps within a family remain engineering evidence only. They test
stability, useful travel, pitch behavior, aliasing, modulation, mono
compatibility, and cost; they do not count as additional musical variations.
The user decides whether the five candidates actually sound distinct and
worth developing before any one is selected for engine integration or macro
mapping.

For the integer-machine family, use portable scalar Rust with explicit
fixed-width types and defined wrapping operations first. Do not introduce
inline assembly, SIMD, architecture-specific behavior, or undefined overflow
semantics merely because the idea began from an assembly metaphor. Convert to
the floating-point audio boundary in a controlled place and measure DC,
periodicity, pitch error, level, spectral distribution, aliasing, deterministic
replay, and the audible consequences of register-width and state-cycle
changes. Different bit widths and oscillator counts are engineering sweeps
inside this one family, not separate listening mechanisms.

The hoped-for payoff is enough cheap parallel machines to make a four-note
instrument a serious candidate with rich internal oscillator populations.
“Zillions of oscillators” is a productive hypothesis, not a performance claim.
Research remains monophonic first; only native Raspberry Pi callback/headroom
measurements may establish how many machines per voice and whether four or any
higher count is actually safe and worthwhile.

## Design and workflow state

The architecture above was presented in chat and then revised at the user's
request to include the controller target. The revised high-level architecture
is accepted. There is no unresolved high-level design-approval blocker. Later
sessions should proceed without reopening settled questions such as installation
authorization, ALSA-versus-JACK output, external-process integration, or the
exact 12-continuous-control budget.

The initial plan and design are recorded under `docs/superpowers/`. The
foundation fixed module and preset boundaries. The JACK crate-versus-dynamic-FFI
decision, CC numbers, useful macro mappings, and measurable usefulness
thresholds remain later engineering decisions, not broad design blockers.

The settled high-level choices are:

- external managed process;
- JACK stereo audio;
- ALSA Sequencer MIDI;
- pure/testable DSP core;
- fourth distinct SHR-DAW engine;
- exactly 12 continuous performance controls: eight evidence-selected timbral
  roles plus ADSR, with no invented extra button/mode or master-encoder macro;
- live control timing aligned with SHR-DAW, with note-boundary deferral only
  where a particular parameter's implementation requires it;
- mono-first oscillator-system design with polyphony deferred until native Pi
  cost/headroom evidence across 1/2/4/8 voices, without requiring eight or
  permanently locking the engine to mono;
- Raspberry Pi 5 / 2 GB / 64-bit OS primary target; and
- x86_64 Linux development compatibility.

## Model D character checkpoint

Implemented on 2026-07-29. The first human listening comparison is now
recorded:

- added an isolated monophonic `model_d` research path and offline
  `model-d-lab` without modifying production `Engine`, preset schema, stable
  macros, JACK, ALSA, or SHR-DAW;
- built three independently phased VCOs with prepared octave/static-tuning
  offsets, bounded recurrence-based drift, waveform asymmetry, pulse-width and
  level differences, PolyBLEP-corrected saw/pulse edges, PolyBLAMP-corrected
  triangle slope corners, and a periodic value/derivative-matched rational
  warp in place of the former piecewise-linear saw asymmetry;
- summed the VCOs and delayed output feedback in a bounded odd cubic mixer,
  with an exact linear diagnostic substitution;
- passed the mixer into four cascaded one-pole ladder stages with bounded odd
  input/stage transfers, resonance feedback, a 2,049-entry prepared cutoff
  table, and fixed four-times internal sampling;
- decimated the ladder with a 63-tap Blackman-windowed linear-phase FIR whose
  group delay is 31 internal samples, or 7.75 host-rate samples;
- used independent attack/decay/sustain filter and loudness contours, reusing
  each contour's decay duration for release, followed by velocity and one
  authored fixed voice output gain;
- retained exact idle zero, deterministic reset, finite/bounded output, and
  allocation-free prepared VCO, contour, mixer, ladder, and full-voice sample
  paths in tests; and
- provided matched idealized-path, linear-mixer, linear-ladder, and
  no-drift/no-feedback ablations using the same bass score, duration, and
  presentation gain as the full bass render.

The disposable listening set is generated with:

```bash
cargo run --release --bin model-d-lab -- render artifacts/model-d-character
```

It contains three authored 48 kHz dual-mono coverage phrases followed by four
matched causal ablations. Listen in filename order:

1. `01_full_bass_phrase.wav`
2. `02_full_lead_phrase.wav`
3. `03_full_filter_articulation.wav`
4. `04_matched_idealized_path.wav`
5. `05_matched_linear_mixer.wav`
6. `06_matched_linear_ladder.wav`
7. `07_matched_no_drift_or_feedback.wav`

On 2026-07-29 the user preferred `04_matched_idealized_path.wav` over the
other six renders, while explicitly qualifying the verdict as a non-expert
assessment. On 2026-07-30 the user clarified that this selects the default
baseline only: none of the Model D mechanisms is rejected because the batch
did not provide the complete live parameter surface needed to judge their
travel. The production controls therefore expose oscillator character/drift,
mixer and ladder nonlinearity, feedback, source balance, cutoff, contour
motion, and resonance. Future documentation must record actual control
auditions rather than converting the earlier whole-file preference into a
rejection.

The presentation gains are fixed at 1.0 for the bass and every matched
ablation, 0.75 for the lead, and 1.6 for the filter-articulation phrase.
Authored internal voice output gains are 0.42/0.40/0.42 for bass/lead/filter
respectively. There is no per-file or post-render normalization, full-band
limiter, compressor, reverb, or delay. The full bass, lead, and filter files
measure peaks of 0.062773/0.043744/0.107469, RMS
0.023689/0.020234/0.026794, DC
-0.003295/+0.004664/-0.003326, maximum jumps
0.003856/0.010627/0.027015, and headroom
24.044527/27.181656/19.374320 dBFS. Every render is finite and
has an exact zero tail. Matched-ablation RMS residuals against the full bass
are 0.067214/0.018535/0.004535/0.003867.

The linear low-drive ladder probes measure cutoff at
125.555420/498.803711/2000.136719/7999.453125 Hz for
125/500/2000/8000 Hz targets, a 23.113182 dB/octave stop-band slope, and
increasing resonance-peak ratios of 2.008079 then 2.187911. These establish
the declared digital model behavior; they are not hardware calibration.

The original plan proposed accepting a time-aligned 48/192 kHz waveform
residual. Implementation showed that this residual also measures ordinary
transfer and phase differences, even after accounting for the ladder FIR's
7.75-host-sample delay, so it is diagnostic only. The controlled probe's
retained values are -29.879594/-30.956849/-22.678313 dB for notes 36/60/84.

The controlled engineering alias gate uses native-rate Blackman-Harris
spectra over `N = 131072` steady-state samples. It measures nonharmonic
out-of-mask foldback at 48 kHz and an independent native-192 kHz proxy floor in
the same physical 0–24 kHz band. A four-bin half-width masks expected
harmonics; estimates less than 6 dB above the floor are classified as
floor-limited. Notes 36/60/84 measure controlled 48 kHz proxies of
-64.393327/-55.921169/-36.927605 dB and 192 kHz floors of
-62.360012/-62.288916/-52.208880 dB. Note 36 is floor-limited; notes 60 and
84 resolve excesses of -57.060745/-37.058275 dB above the floor. The
conservative values pass unchanged bounds of -45 dB for notes 36/60 and
-35 dB for note 84. Mask coverage is 10.0662/2.5131/0.6180%; energy folding
inside those masks is an explicit blind spot and is not bounded by this proxy.

Final review added evidence that prevents that controlled result from being
generalized to the audition path:

- `oscillators.tsv` now includes exactly nine configured pitch/drift rows for
  MIDI 36/60/84 at 44.1/48/96 kHz, using -2.0 cents static offset and
  +/-1.5 cents drift over a complete deterministic recurrence cycle; all mean
  pitch errors are within 5 cents and every observed drift excursion remains
  within +/-1.5 cents;
- fifteen MIDI-96 waveform rows cover triangle, maximum-asymmetry saw,
  rectangle, maximum-width wide pulse, and minimum-width narrow pulse at all
  three rates. Their 44.1/48/96 kHz nonharmonic proxies are
  -48.128146/-49.678474/-59.819637 dB for triangle,
  -28.269403/-28.854447/-31.445767 dB for saw,
  -28.643688/-31.864009/-32.335421 dB for rectangle,
  -26.353655/-24.572373/-26.663287 dB for wide pulse, and
  -26.353658/-24.572258/-26.663348 dB for narrow pulse. These are
  waveform-specific proxy bounds with the same masked-bin limitation, not a
  claim of alias-free output; and
- a separate full-authored-bass probe retains source levels
  `0.88/0.72/0.14`, mixer drive `2.4`, ladder drive `2.2`, static oscillator
  mismatch/asymmetry/level differences, and feedback. Only drift is frozen for
  stationary analysis. Its 48-vs-192 kHz spectral-magnitude alias/error values
  are -34.099830/-32.786449/-26.817410 dB for MIDI 36/60/84, while the
  corresponding 192-vs-768 kHz floors are
  -23.154683/-24.411124/-27.471559 dB. Conservative values
  -23.154683/-24.411124/-26.817410 dB fail the unchanged -45/-45/-35 dB bounds and are
  explicitly reported as `diagnostic_fail`. Nonlinear harmonic differences
  of -4.790412/-8.672100/-13.050540 dB confirm the full probe did not remove
  the authored nonlinear character.

The full authored path therefore has no passing alias claim. The controlled
rows remain useful diagnostic acceptance evidence only for their exact
idealized/lower-drive configuration. The full-path high-rate comparison also
retains transfer and sample-rate-model differences, so its failure is an
honest unresolved alias/error diagnostic rather than a quantified alias-only
estimate.

Artifact publication is transactional through promotion. Once the staged
batch has replaced the destination, that new destination is authoritative.
The previous destination is first renamed to a unique validated retired
sibling and then removed. If that recursive cleanup fails after partial
deletion, the command still succeeds and prints an explicit warning naming
the nonblocking retired path; it never attempts to restore partially deleted
old data. A later run ignores such residue, while ordinary successful
publication leaves no staging, backup, or retired sibling.

This is a circuit-informed causal model based on documented signal flow,
Robert Moog's ladder patent, and Huovilainen's circuit-derived digital model.
It is not calibrated to an individual instrument, does not use copied factory
presets, third-party code, or reference recordings, and is not claimed to be
hardware-equivalent. AArch64 compilation and x86_64 offline generation do not
establish Raspberry Pi callback cost, latency, safe polyphony, or sound
quality.

## Six-operator PM listening-gate checkpoint

Implemented on 2026-07-31 as the clean-room-oriented experiment specified in
`docs/superpowers/specs/2026-07-31-six-operator-pm-listening-gate-design.md`.
The implementation uses John Chowning's 1973 JAES paper, Yamaha's official
DX7 operating manual, and the Yamaha Corporation *PLG100-DX Owner's Manual*
algorithm chart on pp. 28–29 as a narrow factual source register. The official
PLG chart is published at
<https://usa.yamaha.com/files/download/other_assets/1/320951/PLG100DXE.pdf>;
its PDF metadata records 1999 and its MIDI chart is dated March 20, 1998. The
implementation was independently authored from the cited mathematical and
functional facts, including 32 source-numbered connectivity records. No
expressive manual content, source code, diagrams, factory presets, voice data,
or SysEx data was reproduced in this recorded process. It makes no Yamaha
affiliation, DX7 compatibility, file-format compatibility, or
historical-emulation claim. Separate legal review governs distribution; this
research boundary is not a legal conclusion.

`dsp::six_op_pm` provides a fixed-capacity scalar core with six operators and a
validated catalog of 32 unique source-numbered connectivity records and
fingerprints. Operator frequency, envelope, keyboard scaling, velocity,
detune, shared sine-table access, pitch envelope, LFO rotation, and graph order
are prepared before rendering. Every declared feedback edge consumes the
source operator's previous-sample output;
source algorithm 4 therefore implements group feedback from operator 4 to
operator 6 rather than treating it as a same-sample ordinary edge. The
prepared sample path is finite-guarded, deterministic, and allocation-free.

`six_op_pm`, including its focused `measurements` submodule, owns the fixed
four-slot event scheduler, renderer, independently authored listening
inventory, and engineering evidence. `six-op-pm-lab` owns offline validation,
WAV/report I/O, staged single-rename publication, and workstation timing. None
is called by production `Engine`, presets, macros, host, JACK, ALSA, or
SHR-DAW.

The gate deliberately presents only three graphs and six patches. Source/manual
algorithm IDs 1, 5, and 10 correspond to zero-based internal
`SixOpPatch::algorithm` indices 0, 4, and 9; `manifest.tsv` records those
internal indices:

1. source algorithm 1, score `bell-strikes`: `bell-metal` then
   `fractured-metal`, fixed pair gain `0.25`;
2. source algorithm 5, score `mallet-single-and-chord`:
   `electric-piano-mallet` then `glass-wood`, fixed pair gain `0.23`; and
3. source algorithm 10, score `brass-low-mid-phrase`: `brass-bass` then
   `mechanical-stab`, fixed pair gain `0.20`.

All six presentations are dry dual-mono 48 kHz, 32-bit-float renders with no
post-render clipper, per-file normalization, effect, compressor, limiter,
filter, oversampling, or mastering. `SixOpVoice` has a built-in emergency
safety clamp; the retained renders recorded zero contacts. The automated gate
reports a maximum peak of `0.247308403` against the `<= 0.95` bound, maximum
absolute DC of `0.000125243` against `<= 0.0002`, and maximum adjacent-sample
jump of `0.238479972` against `<= 0.25`. Pair active-RMS differences are
`2.806095/2.807908/2.059745` dB against the `<= 3` dB bound. Harmonic pitch
evidence has a worst absolute error of 10 cents and a weakest strength of
`-0.568402` dB against the `-12` dB floor; the two inharmonic patches use the
declared conservative nominal-note anchor rule.

All 18 alias/error rows at MIDI 36/60/84 pass the predeclared
`-20/-20/-12` dB floors; the tightest margin is `16.175919` dB. The aligned
48 kHz versus eight-times-rate fitted residual includes transfer and phase
differences as well as aliasing, so it is conservative engineering evidence,
not an alias-only or perceptual score. All 54 attack/sustain/release spectral
rows are finite, and all 162 rational/inharmonic, modulation, feedback,
register, and stage sweep rows are finite and unclamped.

Three fresh release renders were byte-identical for every deterministic file;
only the intentionally volatile `workstation-cost.txt` differed. The scalar
workstation verification took approximately `1.37–1.42` seconds. That timing
is offline development evidence only, not callback timing, Raspberry Pi
evidence, latency, polyphony, or sound-quality evidence.

The canonical ignored listening batch is disposable under the experimental
output policy. Its automated status does not select a graph or establish
musical usefulness. The next research gate is human listening of the three
exact pairs in order; retain or integrate nothing unless the user explicitly
selects it afterward.

Final six-operator verification on 2026-07-31 established:

- `cargo fmt --check` and `git diff --check` passed;
- `cargo test --all-targets --all-features` passed all 301 tests with zero
  failures in 266.37 seconds;
- `cargo clippy --all-targets --all-features -- -D warnings` passed with no
  warnings;
- `cargo build --release` passed;
- `cargo audit` scanned 43 dependencies and found no vulnerabilities;
- all `cargo deny check` categories passed, retaining only the accepted
  duplicate warning for `winnow` 0.7.15 and 1.0.4;
- plain `cargo check --target aarch64-unknown-linux-gnu` failed in `alsa-sys`
  because the target pkg-config/sysroot was absent. Retrying with
  `PKG_CONFIG_ALLOW_CROSS=1` checked `shr-synth`, but this is Rust compile-only
  evidence using host pkg-config metadata, not target sysroot, target-link,
  runtime, callback, or Raspberry Pi evidence;
- two fresh release renders each contained the exact 15-file inventory and
  were byte-identical except for `workstation-cost.txt`. All twelve decoded WAV
  copies were stereo 48 kHz, 32-bit IEEE float, finite, and exact dual-mono;
  every recomputed FNV sample hash matched `hashes.tsv`;
- the canonical ignored batch contained the same exact 15-file inventory and
  matched the fresh deterministic files byte-for-byte, differing only in the
  volatile workstation-cost report; and
- no artifact file was tracked, no staging residue remained, and Git status
  was clean.

These results close the automated engineering gate, not the musical one.
Human listening of the three exact six-operator pairs remains open. Separately,
Model D listening must still decide whether the full path sounds like one
coherent instrument, whether three-oscillator movement stays useful rather
than chorused, whether mixer and ladder nonlinearities add proportionate
character, and whether the filter retains body under articulation/resonance.
Those mechanisms are now mapped for that evaluation; no listening approval is
claimed.

## Current continuation prompt

Use this short prompt after resetting; this handoff contains the detailed
context and should not be copied back into the new prompt:

```text
Continue SHR Synth in `/home/shome/p/shr-synth`. Confirm the owning repository
and inspect live Git state before changing files.

Read `docs/HANDOFF.md`, `docs/RESEARCH.md`, `docs/FUTURE_DIRECTION.md`, and
`docs/MICRO_MACHINE_ROUTING.md` before planning the next experiment.

Continue from the single live SHR Synth engine with five selectable synthesis
models: Model D has seven factory starts, Six-Op PM has six, and Strange,
Swarm, and Bass Matrix have one each. Strict schema 7 owns model-specific patch
and macro fields plus instrument volume; schemas 1–6 remain readable. SHR-DAW
presents ENGINE -> MODEL -> PATCH in FT2 ROUTE and uses the loaded model's
twelve labels in Player and FT2.

Do not touch connected JACK/hardware, add SIMD, claim whole-system Pi
performance, or expand production polyphony without explicit scope and native
evidence. Keep every model inside the one owned process and settled 12-control
budget.
```

## Next action

The next action is owner listening of the live Swarm warm pad and Bass Matrix
transformer in SHR-DAW. Do not widen the graph vocabulary or claim either model
musically accepted from automated evidence. Strange, Swarm, and Bass Matrix
musical/native-load verdicts remain open. Automated tests establish bounded
deterministic software behavior but not sound quality, native callback headroom,
or hardware acceptance. Historical listening-render and exhaustive research
tests remain opt-in unless their own code, evidence, or protected assumption
changes.

## Executed foundation checkpoint

Completed later on 2026-07-22 and merged into local `main`:

- initialized Git and recorded the accepted design and implementation plan;
- installed user-local stable Rust, rustfmt, Clippy, cargo-audit, and cargo-deny;
- created a pure Rust library, strict version-1 `.mojsint` preset, thirteen
  then-provisional control identities, reference sine/ADSR, fixed voice engine,
  and deterministic two-channel float WAV renderer/validator CLI; the
  production engine currently writes the same mono mix to both channels;
- enforced no allocation inside `Engine::render_block` in tests;
- rechecked SHR-DAW main at
  `8b7d0d7c17c582292ac06a915ca1fe750d77bc40`;
- documented architecture, live-host contract, portability/Pi validation,
  primary-source research, licensing, and repository-specific instructions.

That checkpoint's proposed next milestone—the PolyBLEP versus integrated-
wavetable comparison and first `SHAPE`/`COLOR` route—is recorded below as
complete from automated evidence. The live JACK/ALSA host remains a separate
milestone. `libasound2-dev` is installed on the development machine; it will
still need installation on a fresh Raspberry Pi OS image.

Fresh foundation verification evidence:

- `cargo fmt --check`: exit 0;
- `cargo test --all-targets --all-features`: 21 passed, 0 failed;
- `cargo clippy --all-targets --all-features -- -D warnings`: exit 0;
- `cargo build --release`: exit 0;
- `cargo audit`: scanned 35 crate dependencies with no reported vulnerability;
- `cargo deny check`: advisories, bans, licenses, and sources passed; it reports
  one accepted duplicate-version warning for `winnow` 0.7/1.0 inside `toml`;
- `cargo check --target aarch64-unknown-linux-gnu`: exit 0 (compile evidence
  only, not a native Pi build);
- two independent reference renders were byte-identical at SHA-256
  `306e7af0f5ddf9a2fffad3a5b040ae77963244206d8bd155e4ad1fe6d11d92bc`.

## Bandlimited oscillator checkpoint

Completed later on 2026-07-22:

- implemented independent PolyBLEP and generic integrated-wavetable candidates
  over the same corrected saw-to-square target family;
- measured coherent note/shape matrices against finite band-limited Fourier
  references, with peak, RMS, DC, finiteness, exact sample hashes, and
  conservative alias/error residual energy;
- selected the integrated wavetable from aggregate residual (-25.586 dB versus
  -25.188 dB) after worst cases tied within the documented 0.1 dB window;
- added sample-path and full-engine allocation guards for both candidates and
  rapid macro events;
- routed `SHAPE` through the corrected morph and `COLOR` through a tracked
  harmonic-dark to direct-bright path, both with 10 ms smoothing and bounded
  level compensation;
- generated, measured, and later removed 27 dual-mono, two-channel 32-bit float
  WAVs at 48 kHz
  for notes 36/60/84 and the complete low/mid/high `SHAPE`/`COLOR` matrix;
  listening-render peak spans
  0.132612 to 0.178935, RMS spans 0.046470 to 0.110782, and maximum absolute DC
  is 0.000082385; and
- did not implement the live host, touch SHR-DAW/JACK/hardware, add SIMD, or
  make Raspberry Pi or human musical-usefulness claims.

Fresh oscillator-milestone verification evidence:

- `cargo fmt --check`: exit 0;
- `cargo test --all-targets --all-features`: 27 library and 4 CLI tests passed,
  0 failed;
- `cargo clippy --all-targets --all-features -- -D warnings`: exit 0;
- `cargo build --release`: exit 0;
- `cargo audit`: scanned 35 crate dependencies with no reported vulnerability;
- `cargo deny check`: advisories, bans, licenses, and sources passed, retaining
  the accepted `winnow` 0.7/1.0 duplicate warning inside `toml`;
- `cargo check --target aarch64-unknown-linux-gnu`: exit 0 (compile evidence
  only, not a native Pi build); and
- two fresh independently generated 27-WAV matrices plus manifests had no hash
  diff; their sorted SHA-256 evidence aggregates to
  `aa8458f0209eb8d63ffa3b44c71a7d21d09e295e5fd5aeb52d86d8a8f58b705b`.

## Shared-phase harmonic-selector checkpoint

Completed later on 2026-07-22:

- compared nonlinear modulator preprocessing, a shared three-phase selector,
  and a small directed operator graph, then selected the shared 0/120/240-degree
  bank as the smallest bounded connection-order experiment;
- implemented one scalar per-voice recursive phase source whose algebraic taps
  cancel linearly and whose normalized equal cubic sum isolates the third
  harmonic, without per-sample trigonometric setup;
- routed smoothed `EDGE` from the selector fundamental to its third harmonic and
  smoothed `COUPLE` from the existing oscillator to the selector, preserving the
  then-current thirteen-ID schema and the unchanged `COUPLE=0` baseline;
- added exact tap/cancellation, deterministic reset, finite/bounded output,
  high-note third-harmonic guard, macro-travel, rapid-movement, and
  oscillator/engine allocation tests;
- generated 27 loudness-matched one-voice listening conditions for notes
  36/60/84 and low/middle/high `EDGE`/`COUPLE`, with harmonic, pitch-retention,
  residual alias/error, peak/RMS/DC, and deterministic-hash evidence;
- measured the selector through MIDI 127 and tapered its third harmonic between
  40% and 48% of sample rate so the route returns to the fundamental before the
  generated partial crosses Nyquist;
- recorded a separate volatile release workstation micro-timing for the
  isolated selector, without treating it as callback or Raspberry Pi evidence;
  and
- left human musical-usefulness acceptance open at generation time and made no
  Pi, latency, polyphony, or sound-quality claim.

The design and plan are in `docs/superpowers/`. The pure third-harmonic endpoint
intentionally removed the fundamental, while the rest of the matrix retained it
under the recorded test rule.

The user completed the human listening pass and rejected all 27 conditions as
too close to pure sine material and not usefully distinct. The generated
`artifacts/harmonic-selector-milestone/` directory was removed after review;
the lab generator remains only for reproducible temporary test evidence. The
experimental `EDGE`/`COUPLE` route is therefore a negative research result, not
an accepted macro mapping or factory sound. The next phase should keep a stable
base sound and investigate controlled parallel output/character layers such as
bounded saturation, harmonic excitation, subharmonic reinforcement, or
feedback/resonant processing, comparing per-voice and post-mix placement rather
than stacking every layer serially.

## Parallel character-layer checkpoint

Completed later on 2026-07-22:

- compared a full-band symmetric saturation return, a band-limited symmetric
  generated-residual return, and a band-pass asymmetric exciter; separately
  deferred per-voice oscillator, divider, and tracked subharmonic forms;
- selected one per-voice branch before mixing, preserving the existing
  `SHAPE`/`COLOR` output as an untouched dry anchor and avoiding post-mix
  inter-voice products;
- implemented a four-pole 6 kHz branch low-pass, bounded cubic soft clip,
  linear-component subtraction, 10 Hz DC blocker, and two-stage note-tracked
  return high-pass, all with scalar preallocated per-voice state;
- retired the rejected selector from `Voice` while preserving its standalone
  deterministic negative-result generator and primitive tests;
- kept `EDGE` as candidate drive/intensity and `COUPLE` as candidate return,
  both smoothed over 10 ms, with sample-identical `COUPLE=0` bypass for every
  `EDGE` value;
- rejected two intermediate revisions that either cancelled the dry
  fundamental or measured like minor level/EQ change, then capped drive at 2x
  and retained a return that measurably lifts a broad upper-harmonic set;
- compared direct, first-order ADAA, and two-times evaluation against an eight-
  times zero-phase reference. Direct passed the declared rule at -73.700 dB
  worst moderate and -59.121 dB worst strong residual and was selected; this is
  topology-specific evidence, not a general rejection of nonlinear
  antialiasing;
- measured 600/900 Hz intermodulation at -134.381 dB for separate per-voice
  branches versus -15.463 dB for the deferred post-mix placement;
- generated exactly nine loudness-matched listening WAVs: dry, moderate, and
  strong for MIDI notes 36, 60, and 84. Peak is 0.139552-0.143008, RMS is
  0.079769-0.079980, maximum absolute DC is 0.000000196, and every condition
  retains the fitted fundamental;
- recorded 12-partial distributions, deterministic hashes, alias/error rows,
  intermodulation evidence, and volatile scalar workstation timing; and
- received a negative listening verdict: all conditions sounded like the same
  basic tone with small treatments, so neither the graph nor its
  `EDGE`/`COUPLE` mapping is an accepted factory sound.

All generated oscillator, selector, and parallel-character milestone artifacts
have been removed after review. Future evidence must be generated into a fresh
temporary directory and removed after its decision is documented. The next
experiment must improve the dry per-voice source and compare structurally
different source families rather than adding more output processing.

All cost evidence in this checkpoint comes from the scalar x86_64 workstation.
It is not Raspberry Pi callback, latency, safe-polyphony, or sound-quality
evidence. No JACK/ALSA host, SHR-DAW change, hardware connection, SIMD path, or
Pi claim was added.

## Five-family listening-gate checkpoint

Completed and reviewed on 2026-07-23:

- researched nonlinear PM, excited combs, precedence/micro-delay perception,
  spectral traversal, and small-register sound machines from primary or
  authoritative sources, preserving authorship, publication details, direct
  URLs, supported claims, and licensing boundaries in `docs/RESEARCH.md`;
- defined a distinct perceptual hypothesis and audible failure condition for
  each family before implementation;
- added an isolated `dsp::research` source boundary and `five-family-lab`
  offline binary without changing the production `Engine`, presets, controller
  routes, JACK/ALSA work, or SHR-DAW;
- implemented one fixed scalar representative per family with per-source state,
  deterministic reset, finite/bounded output, and allocation-free sample paths;
- generated exactly 15 two-channel 32-bit-float 48 kHz files for MIDI 36/60/84;
  twelve were dual-mono and only the three spatial-micro-delay files generated
  different left and right signals,
  matched to RMS 0.06 except the crest-limited high comb at 0.059116, with peak
  0.085294-0.979000 and maximum absolute DC 0.000229049;
- measured harmonic distributions, fitted fundamental/pitch retention,
  left/right correlation, side-to-mid energy, mono fold-down, adjacent-sample
  continuity, deterministic hashes, integer phase periods, conservative 8x
  alias/error residuals, and volatile scalar workstation cost;
- corrected two issues found by release evidence: approximate spectral rotation
  coefficients caused long-render pitch drift, and the high comb retained too
  much DC; exact prepared rotations and a prepared 10 Hz comb DC blocker now
  have focused regressions;
- retained the integer swarm's -0.658/-0.399/-0.707 dB high-rate residual as a
  documented negative result showing strong register-quantization and
  sample-rate dependence rather than calling it alias-clean; and
- produced byte-identical release WAVs and deterministic reports in two fresh
  directories, excluding only the explicitly volatile workstation timing file;
  the sorted per-file hash manifest has SHA-256
  `820f8a46f5fa8bcf39c9884b5b986196809b4cccfb7f3b328e4e67916798f572`; and
- passed fresh `cargo fmt --check`, all-target/all-feature tests (61 library,
  one five-family CLI, and six existing CLI tests), Clippy with warnings denied,
  release build, `cargo audit` over 35 crate dependencies, `cargo deny check`,
  AArch64 compile check, and `git diff --check`. `cargo deny` retains only the
  accepted `winnow` 0.7/1.0 duplicate warning inside `toml`.

The user's first listening verdict is that SHR Synth remains far from the goal,
but these fundamentally different sources finally point in the right direction.
This is not acceptance, rejection, or ranking of any family. Do not select,
integrate, expand, or map one based on this pass. The next session should keep
exploring different fundamentals under the user's guidance rather than
prematurely converging on these five representatives. The spatial candidate
has not been accepted on headphones, speakers, or mono; automated metrics
cannot make that decision. The reviewed ignored batch was deleted after the
verdict, while the reproducible generator, tests, and durable evidence remain.

## Complete hybrid stereo/chord checkpoint

Implemented on 2026-07-23 and awaiting human listening:

- converted the visceral-bass research into three complete voices rather than
  isolated starter oscillators: cross-coupled machine, spectral shadow, and
  dual resonant body;
- used a single small-register mechanism as an exciter, perturbation, or
  address/coupling source inside each mixed topology instead of repeating the
  rejected all-integer swarm interpretation;
- added genuine stereo generation through unequal resonant/filter state,
  bounded cross-coupling, and independently moving channel delays;
- added exactly three independently seeded voices for chord conditions, with
  nonlinear processing inside each voice before the linear mix;
- rendered single MIDI 38, held MIDI 50/53/57, a four-segment three-note
  progression, and an explicit mono-fold diagnostic for every family;
- added deterministic reports for peak/RMS/DC/crest, onset/body windows,
  harmony targets, difference products, correlation, side/mid energy, mono
  survival, movement rates, topology identity, scalar workstation cost, and
  conservative 8x high-rate residual;
- measured release peaks of 0.153129-0.283571, maximum absolute DC
  0.000029871, genuine-stereo correlations of 0.651742-0.944257, and side/mid
  ratios of 0.031072-0.213552; every chord target remains far inside the
  predeclared 36 dB relative rejection bound;
- retained the dual-resonant body's MIDI-36 residual of -2.889 dB as a severe
  negative engineering result. The other residuals are also descriptive, not
  proof of inaudibility or quality; and
- kept `Engine`, presets, stable macros, JACK/ALSA, SHR-DAW, production
  polyphony, and architecture-specific code unchanged; and
- passed fresh `cargo fmt --check`, all-target/all-feature tests (71 library,
  one five-family CLI, one hybrid CLI, and six existing CLI tests), Clippy with
  warnings denied, release build, `cargo audit` over 35 crate dependencies,
  `cargo deny check`, AArch64 compile check, and `git diff --check`. Two fresh
  release generations were byte-identical except for the declared volatile
  workstation timing report. The manifest report SHA-256 is
  `b1b3d720b1e791d6170f1fe8836b21d2192657dcb9ce794a4043c803a554cd10`.
  `cargo deny` retains only the accepted `winnow` 0.7/1.0 duplicate warning
  inside `toml`.

Automated evidence establishes bounded, reproducible audition material; it
does not establish “kidney-cutting” impact, translation, a useful macro, or a
desirable sound. The ignored batch remains available only until the user gives
the headphone/speaker/mono verdict. After that verdict, document conclusions
and delete rejected output unless the user explicitly requests preservation.

## Composite-machine checkpoint

Completed on 2026-07-23 and awaiting human listening:

- corrected the accident model: the real files were spawned in separate
  processes with noticeable, unknown delays, so the 30-voice first-four-second
  inventory applies only to a synchronized counterfactual;
- implemented an exact internal twelve-schedule synchronized reference and a
  clearly labeled 0-4110 ms delayed-launch estimate;
- verified the synchronized render against the old twelve-WAV sum at
  -90.31 dB peak and -130.35 dB RMS difference;
- implemented reduced-stack, role-separated, harmonic-lattice,
  cross-topology-follower, and risky pairwise-exchange machines;
- rejected a 0.984317-correlated risky revision, then rejected a second
  revision whose difference products had only 9.5 dB target margin;
- retained a third risky revision whose isolated junction products have
  31.281 dB margin, while honestly retaining its severe -3.670 dB isolated
  high-rate residual;
- measured peaks 0.066021-0.289289, maximum absolute DC 0.000006314,
  correlations 0.753955-0.966233, side/mid 0.029964-0.147105, low-band
  side/mid 0.026599-0.103616, and mono/stereo RMS 0.933681-0.985347;
- found no inert final layer and no final candidate pair above 0.765512
  correlation; and
- kept `Engine`, presets, stable macros, JACK/ALSA, SHR-DAW, production
  polyphony, and the generic graph compiler unchanged.

The complete inventory, iterations, evidence, limitations, and typed-port
suggestions are in `docs/COMPOSITE_MACHINE_RESEARCH.md`. The ignored final
batch is `artifacts/composite-machine-lab/`. Automated bounds do not establish
that any candidate preserves the accidental magic.

Fresh integrated verification:

- `cargo fmt --check` and `git diff --check`: exit 0;
- `cargo test --all-targets --all-features`: 79 library tests, one composite
  CLI test, one five-family CLI test, one hybrid CLI test, and six offline CLI
  tests passed with zero failures;
- Clippy with warnings denied and release build: exit 0;
- `cargo audit`: 35 locked crate dependencies scanned with no vulnerability;
- `cargo deny check`: advisories, bans, licenses, and sources passed, retaining
  only the accepted `winnow` 0.7/1.0 duplicate warning inside `toml`;
- AArch64 target check: exit 0, compile evidence only; and
- two fresh release generations were byte-identical except volatile
  workstation timing, with aggregate deterministic SHA-256
  `73974529034c7bce2882cd1e792c142c0a1ac6bf31746b47bbc5cddcb084920c`.

## Hot composite, octave, bass, and punch checkpoint

Implemented on 2026-07-23 and awaiting human listening:

- diagnosed the unfair old presentation: synchronized raw RMS 0.070910 was
  7.088 dB above the delayed-launch estimate and 7.900-12.052 dB above the
  five candidates;
- preserved every raw engineering render and locked the synchronized/delayed
  48 kHz hashes at `be3ea0fdd66b4472` and `c919cb57920c520f`;
- added a 0.12 active-body RMS target, 0.10-0.14 shared-register range, 0.75
  sample-peak ceiling, one explicit fixed gain per topology/audition kind, and
  no limiter, compression, clipping, maximization, or per-file normalization;
- made delayed launch the primary hot reference and synchronized accumulation
  the second-position counterfactual;
- rendered every surviving topology at D1/D2/D3 with one shared topology gain,
  preserving the dynamic follower and nonlinear junction rather than reducing
  octave files to equivalent linear stacks;
- measured octave active RMS 0.100051-0.139794, peak
  0.353137-0.542087, correlation 0.576155-0.966702, low-band side/mid
  0.021902-0.450904, and mono loss 0.113-1.108 dB;
- exposed risky-braid D1's nominal fundamental at only -60.520 dB against
  roughly -23.4 dB octave/third projections, so hot gain does not disguise
  its weak bass pitch;
- added one explicit D1 pedal source to every musical candidate and a
  sample-accurate, deterministic, bounded, allocation-free research ADSR on
  that source before summing;
- rejected 1/70/0.55/100 and 5/160/0.75/250 ms sweep settings for
  onset-to-sustain ratios below 1.05, rejected an intermediate
  3/110/0.65/180 revision near 0.98, and retained 3/110/0.55/180 ms as the
  bounded engineering candidate at ratio 1.094-1.098;
- generated a 54-WAV ignored listening set in eight controlled README
  sections plus complete gain, octave, ADSR, allocation, residual, similarity,
  stereo/mono, hash, processor, and cost reports; and
- kept production `Engine`, presets, stable macros, JACK/ALSA, SHR-DAW, Pi
  claims, and the typed graph compiler unchanged.

Digital level is not acoustic SPL or safe playback evidence. Automated metrics
do not establish fused identity, bass quality, spatial translation, or musical
punch. The exact next gate is the README-ordered human headphone, speaker, and
mono pass.

Fresh integrated verification:

- `cargo fmt --check` and `git diff --check`: exit 0;
- `cargo test --all-targets --all-features`: 86 library tests, one composite
  CLI test, one five-family CLI test, one hybrid CLI test, and six offline CLI
  tests passed with zero failures;
- Clippy with warnings denied and release build: exit 0;
- `cargo audit`: 35 locked crate dependencies scanned with no vulnerability;
- `cargo deny check`: advisories, bans, licenses, and sources passed, retaining
  only the accepted `winnow` 0.7/1.0 duplicate warning inside `toml`;
- AArch64 target check: exit 0, compile evidence only;
- synchronized and delayed raw reconstruction hashes remained exactly
  `be3ea0fdd66b4472` and `c919cb57920c520f`; and
- two fresh final 48 kHz generations were byte-identical except volatile
  workstation timing, with aggregate deterministic SHA-256
  `a11fa10d04fb34b8dcbfb8c9268be0d40672133896faa245c245a4ab637c9754`.

## Compact composite power checkpoint

Implemented on 2026-07-23 and rejected by human listening on 2026-07-24:

- preserved the old reconstruction code and exact 48 kHz raw hashes while
  replacing only the ignored disposable listening batch;
- added an isolated `compact_composite` module with ten hardwired machines,
  each limited to one, two, or three simultaneous mechanisms;
- covered sustained low, playable mid, evolving, D1 pedal, D2 bass, two
  distinct thumps, synthetic kick, struck comb, and an eight-event musical
  context;
- declared every source gain, stereo width, envelope, pitch drop, drive,
  saturation/clipping method, 12 Hz pre/post-drive DC control, output gain,
  and 0.999 ceiling;
- used one gain policy across all D1/D2/D3 and tone tests with no hidden
  per-file normalization or analysis-dependent limiter;
- removed one inaudible Clipped Thump noise layer and strengthened other weak
  mechanisms until full/onset mute evidence passed;
- corrected excessive DC and a false absolute-note Context Relay pitch report
  during critical release review;
- measured active/event RMS and perceptual proxy against the hot delayed
  reference, low energy, crest, five event windows, pitch trajectories,
  decay/tails, clipping proportions, jumps, return to zero, tone/pitch
  retention, mono, ablations, residuals, and deterministic hashes;
- retained severe conservative residuals honestly, especially Struck Comb
  -0.004 dB, Resonant Thump -2.262 dB, Pedal Monolith -3.292 dB, and Synthetic
  Kick -5.694 dB;
- produced two byte-identical release batches excluding the volatile cost
  file, with both reconstruction hashes unchanged; and
- measured 73.11 seconds of written WAV audio in 4.612 seconds on this
  workstation, a 15.852x audio-duration/generation ratio and 0.126 seconds per
  equivalent two-second WAV.

The user rejected every primary sound. The experiment used newly designed
mechanisms rather than smaller combinations of the successful original twelve,
and its 4.854-29.208% clipping was an excessive interpretation of "slightly
hotter." The ignored generated batch was deleted. Its reproducible source,
tests, and negative evidence remain tracked.

## Superseded original hybrid subset checkpoint

Implemented and rejected as a timing interpretation on 2026-07-24:

- exposed the exact twelve original layers without changing the synchronized
  or delayed 48 kHz reconstruction hashes;
- created four same-condition three-layer combinations and three role-swapped
  four-layer combinations, preserving original DSP, scores, seeds, fades,
  stereo construction, per-layer preparation, and rebased relative launch
  delays;
- added no new oscillator, mechanism, envelope, pitch event, effect,
  compressor, soft saturator, cross-coupling, or per-file normalization;
- selected shared fixed gains of 17.5 for three-layer files and 16.5 for
  four-layer files into a static -0.3 dBFS ceiling;
- measured candidate active RMS of -10.813 to -10.090 dBFS and sparse ceiling
  contact of 0-0.292%; the reference is -10.122 dBFS with 0.480% contact;
- retained 100% scheduled tonal coverage, no noise-like classification,
  0-0.509 dB mono loss, 0.804-1.000 correlation, absolute DC below 0.000126,
  maximum jump below 0.165, and eight-times residuals from -8.820 to
  -3.706 dB; and
- generated two byte-identical release batches except volatile workstation
  timing, with deterministic aggregate SHA-256
  `5001495920bb0fd23034ee9b91b13b6e87bb5470b326ed2c36982158ed716ddc`.

The user clarified that these second-scale rebased delays made layers enter as
separate sounds. The intended variation was only a slight offset inside one
summed voice under one master envelope. The generated
`artifacts/original-hybrid-subset-mix/` batch was removed. Nothing from it is
selected, preserved in Git, mapped to controls, or integrated into `Engine`.

Verification recorded for that superseded batch:

- `cargo fmt --check` and `git diff --check`: exit 0;
- `cargo test --all-targets --all-features`: 93 library tests, 11 compact
  contract tests, four lab integration tests, and six offline CLI tests passed
  with zero failures;
- Clippy with warnings denied and the release build: exit 0;
- `cargo audit`: 35 locked crate dependencies scanned with no vulnerability;
- `cargo deny check`: advisories, bans, licenses, and sources passed, retaining
  only the accepted `winnow` 0.7/1.0 duplicate warning inside `toml`;
- AArch64 target check: exit 0, compile evidence only;
- synchronized and delayed raw reconstruction hashes remained exactly
  `be3ea0fdd66b4472` and `c919cb57920c520f`; and
- the final ignored directory contains exactly the reference plus seven
  passing candidate WAVs and no rejected WAV.

## Coherent hybrid composite checkpoint

Implemented and rejected by human listening on 2026-07-24:

- retained the exact seven three- or four-layer memberships and all original
  source DSP, scores, seeds, fades, and stereo construction;
- replaced second-scale launch spacing with fixed `0/2/5 ms` three-layer,
  `0/4/9/15 ms` four-layer, and
  `0/1/3/4/5/7/8/9/11/12/14/15 ms` reference offsets;
- applied equal-power layer trim, then one shared post-sum master ADSR with
  25 ms attack, 180 ms decay, 0.88 sustain, and 320 ms release;
- applied one explicit fixed presentation gain per complete composite into a
  static -0.3 dBFS hard ceiling, with no compressor, automatic limiter, soft
  saturator, time-varying gain, or post-render normalization;
- measured all eight files at -10.053 to -10.003 dBFS active RMS with
  0-0.297% ceiling contact, 100% scheduled tonal coverage, and no noise-like
  classification;
- measured 0-0.956 dB mono loss, 0.616-1.000 correlation, absolute DC below
  0.000134, maximum adjacent-sample jump below 0.188, and eight-times
  residuals from -6.675 to -2.548 dB;
- generated two byte-identical 48 kHz batches except volatile workstation
  timing, with deterministic aggregate SHA-256
  `e3d88ce822abd66885d79289d1fad56bd8e3e2b171cb8435864666ec949c3e2c`;
  and
- retained exactly eight WAVs: one twelve-layer orientation reference and the
  seven complete composites. No solo, long-delay, diagnostic, sweep, or
  rejected WAV is present.

The user found the outputs to be steady tones rather than useful envelope
auditions. The nominal ADSR did not solve that perceptual problem: its 0.88
sustain kept most of each long file at a nearly steady level. The ignored
artifact directory was deleted. Nothing was selected, preserved in Git,
mapped to controls, or integrated into `Engine`.

Fresh integrated verification:

- `cargo fmt --check` and `git diff --check`: exit 0;
- `cargo test --all-targets --all-features`: 95 library tests, 11 compact
  contract tests, four deterministic lab integration tests, and six offline
  CLI tests passed with zero failures;
- Clippy with warnings denied and the release build: exit 0;
- `cargo audit`: 35 locked crate dependencies scanned with no vulnerability;
- `cargo deny check`: advisories, bans, licenses, and sources passed, retaining
  only the accepted `winnow` 0.7/1.0 duplicate warning inside `toml`;
- AArch64 target check: exit 0, compile evidence only;
- two final 48 kHz generations compared byte-identical except
  `workstation-cost.txt`; and
- artifact hygiene confirmed one ignored directory, exactly eight WAVs, and
  no rejected output.

## Monophonic envelope audition checkpoint

Implemented and rejected by human listening on 2026-07-24:

- retained only the exact Cross, Spectral, and Dual single-note D2 sources;
- summed their fixed `0/2/5 ms` offsets as one voice before applying one shared
  post-sum stereo envelope;
- rendered exactly three 2.4-second comparisons with 6, 35, and 140 ms
  attacks, shared 220 ms decay, 0.58 sustain, 500 ms release, and release
  beginning at 1.9 seconds;
- applied one shared fixed gain of 51.5 into a static -0.3 dBFS ceiling, with
  no per-profile normalization, compressor, automatic limiter, or soft
  saturator;
- rejected any candidate below -14 dBFS whole-file RMS instead of writing its
  WAV; the three retained files measure -10.123, -10.076, and -10.039 dBFS;
- retained 100% tonal coverage, no noise-like classification, 0.033-0.275%
  ceiling contact, correlation above 0.882, mono loss below 0.476 dB, absolute
  DC below 0.000431, finite output, valid tails, and bounded jumps; and
- generated two byte-identical 48 kHz batches except volatile workstation
  timing, with deterministic aggregate SHA-256
  `c495a4d26c572db307502b9a70f9e2593fa955050723f62c508ad451fcf13bbc`.

The user found the sustain too long and requested much shorter attack and
decay plus a varied piano-like bat/hammer tone. The generated artifact batch
was moved to Trash. Nothing was selected, preserved in Git, mapped to
controls, or integrated into `Engine`.

Fresh integrated verification:

- `cargo fmt --check` and `git diff --check`: exit 0;
- `cargo test --all-targets --all-features`: 102 library tests, 11 compact
  contract tests, four deterministic lab integration tests, and six offline
  CLI tests passed with zero failures;
- Clippy with warnings denied and the release build: exit 0;
- `cargo audit`: 35 locked crate dependencies scanned with no vulnerability;
- `cargo deny check`: advisories, bans, licenses, and sources passed, retaining
  only the accepted `winnow` 0.7/1.0 duplicate warning inside `toml`;
- AArch64 target check: exit 0, compile evidence only;
- two final 48 kHz generations compared byte-identical except
  `workstation-cost.txt`; and
- artifact hygiene confirmed one ignored directory, exactly three WAVs, and
  no rejected output.

## Piano-strike envelope audition checkpoint

Implemented and rejected by human listening on 2026-07-24:

- retained the same exact Cross, Spectral, and Dual single-note D2 body with
  fixed `0/2/5 ms` offsets and equal-power trim;
- replaced the held ADSR with an 800 ms one-shot body: 2 ms rise, 60 ms fast
  decay to 0.28, curved decay to exact zero at 700 ms, and 100 ms final
  silence;
- added no flat sustain or note-off release;
- varied one short exact-source pitched D2 strike per file: Cross 16 ms,
  Spectral 28 ms, and Dual 42 ms, each with a 1 ms rise and fixed 0.30 mix;
- applied prepared 4 Hz DC control, one shared gain of 137.0, and a static
  -0.3 dBFS ceiling, with no per-file normalization, compressor, automatic
  limiter, or soft saturator;
- rejected any profile below -14 dBFS whole-file RMS instead of writing its
  WAV; the retained files measure -12.932, -12.901, and -12.883 dBFS;
- retained 100% tonal coverage, no noise-like classification, 0.933-0.999%
  ceiling contact, correlation above 0.936, mono loss below 0.256 dB, absolute
  DC below 0.000708, finite output, exact final silence, and bounded jumps; and
- generated two byte-identical 48 kHz batches except volatile workstation
  timing, with deterministic aggregate SHA-256
  `423cb4bbdaffd3f5ea65bf9bf0d280e588f3825ca5b340df6267a0e6bcd1cdac`.

Human listening rejected the batch because it sounded like a towel-damped
imitation without a convincing naturally evolving decay. The old source body
was still being shaped by a broadband amplitude contour rather than acting as
an energy-bearing resonant object. The artifact directory was moved to Trash.
Nothing was selected, preserved in Git, mapped to controls, or integrated into
`Engine`.

Fresh integrated verification:

- `cargo fmt --check` and `git diff --check`: exit 0;
- `cargo test --all-targets --all-features`: 103 library tests, 11 compact
  contract tests, four deterministic lab integration tests, and six offline
  CLI tests passed with zero failures;
- Clippy with warnings denied and the release build: exit 0;
- `cargo audit`: 35 locked crate dependencies scanned with no vulnerability;
- `cargo deny check`: advisories, bans, licenses, and sources passed, retaining
  only the accepted `winnow` 0.7/1.0 duplicate warning inside `toml`;
- AArch64 target check: exit 0, compile evidence only;
- two final 48 kHz generations compared byte-identical except
  `workstation-cost.txt`; and
- artifact hygiene confirmed one ignored directory, exactly three WAVs, and
  no rejected output.

## SHR Synth struck-object checkpoint

Implemented on 2026-07-24 and awaiting human listening:

- added isolated `struck_object` research DSP without modifying production
  `Engine`, presets, or stable macros;
- built three monophonic single-D2 topologies: two coupled eight-mode wires,
  one eleven-mode inharmonic plate, and two internally coupled six-mode bridge
  bodies;
- used the differentiated first `7/11/9 ms` of the exact Cross, Spectral, and
  Dual successful sources only as exciters; the source audio is never mixed
  dry;
- delayed only the second internal bank by `2/0/3 ms`, keeping one common
  onset and one overall 1.6-second object;
- used prepared second-order modal recurrences, frequency-dependent losses,
  bounded previous-velocity exchange of `0.0002/0/0.0003`, prepared 35 Hz DC
  control, a 0.5 ms boundary rise, and final 100 ms safety fade;
- added no body ADSR, sustain stage, compressor, soft saturator, per-file
  normalization, dry layer, or new nonlinear oscillator;
- selected one shared gain of 4.43 into the static -0.3 dBFS sparse ceiling;
- rendered `01_coupled_wire.wav`, `02_spectral_plate.wav`, and
  `03_dual_bridge.wav` at -13.926/-13.636/-13.743 dBFS whole-file RMS;
- retained 100% tonal coverage, no noise-like classification, 0.516/0.861/
  0.993% ceiling contact, correlation above 0.995, mono loss below 0.029 dB,
  absolute DC below 0.001552, finite output, bounded jumps, and exact return to
  zero; and
- measured early-to-late decay of -41.531/-47.235/-43.103 dB with falling
  high-band ratios for all three bodies.

Two release generations are byte-identical except
`workstation-cost.txt`. Their deterministic aggregate SHA-256 is
`c72d853e5cc7177585999986e8f3ab198c731703c1edf9d7479a78fb1dff5ff9`.
Human listening selected Coupled Wire as very nice, bright enough, and not
excessive. Spectral Plate and Dual Bridge were not selected for this
development pass. The batch was moved to Trash after its exact Coupled Wire
reference was reproduced inside the successor batch.

Fresh feature-worktree verification:

- `cargo fmt --check` and `git diff --check`: exit 0;
- `cargo test --all-targets --all-features`: 108 library tests, 11 compact
  contract tests, five deterministic lab integration tests, and six offline
  CLI tests passed with zero failures;
- `cargo clippy --all-targets --all-features -- -D warnings`: exit 0;
- `cargo build --release`: exit 0;
- `cargo audit`: 35 locked dependencies scanned with no vulnerability;
- `cargo deny check`: advisories, bans, licenses, and sources passed, retaining
  only the accepted `winnow` 0.7/1.0 duplicate warning inside `toml`;
- `cargo check --target aarch64-unknown-linux-gnu --all-targets
  --all-features`: exit 0, compile evidence only;
- two fresh 48 kHz release generations and the installed batch compared
  byte-identical except `workstation-cost.txt`; and
- artifact hygiene confirmed one ignored directory, exactly three passing
  WAVs, and no rejected or prior-batch output.

## Coupled Wire envelope and motion checkpoint

Implemented on 2026-07-24 and awaiting human listening:

- preserved the accepted Coupled Wire reference byte-for-byte, including its
  4.43 gain, -13.926 dBFS RMS, and FNV-1a sample hash
  `443e5faae3184791`;
- retained the exact Cross-derived exciter, D2 pitch, modal ratios, 0.7-cent
  wire split, `0.0002` velocity exchange, brightness structure, pickup
  identity, and prepared 35 Hz DC control;
- extended every modal loss time by one shared 5.0 scale for the developments,
  so the later sustain contains resonant energy rather than only a multiplier
  over a dead one-shot;
- applied one complete stereo master envelope per development, with exact
  attack/decay/sustain/note-off/release contracts recorded in
  `envelopes.tsv`;
- kept Warm Hold motionless and added only equal-and-opposite high-residual pan
  above a prepared 320 Hz split to Slow High Orbit at 2.6 Hz/depth 0.10 and
  Fast High Orbit at 6.2 Hz/depth 0.055;
- measured stereo-side difference ratios of 0.017688 and 0.009986 for the two
  orbits while maximum mono-sum error remained `0.000000060`;
- selected one shared developed gain of 4.66 without per-file normalization,
  compression, soft saturation, reverb, delay, chorus, dry parallel audio, or
  pitch vibrato;
- rendered Warm Hold, Slow High Orbit, and Fast High Orbit at
  -10.573/-10.532/-11.336 dBFS whole-file RMS with sustain RMS
  0.174/0.160/0.179 and ceiling contact 0.990/0.980/0.862%; and
- retained 100% tonal coverage, no noise-like classification, correlation
  above 0.996, mono loss below 0.028 dB, absolute DC below 0.000900, finite
  output, rising 200 ms attacks, falling releases, bounded jumps, and exact
  final zero.

Two release generations are byte-identical except
`workstation-cost.txt`. Their deterministic aggregate SHA-256 is
`498f32bdfd4d1a43eae3de588ace3d3f7a6dc2ca990e861b3e153ea4caeda695`.
The only active ignored artifact directory is
`artifacts/coupled-wire-envelope-motion/`, containing exactly the reference,
three passing developments, and their reports. Nothing is routed into
production `Engine`, presets, stable macros, JACK, ALSA, or SHR-DAW.

Fresh feature-worktree verification:

- `cargo fmt --check` and `git diff --check`: exit 0;
- `cargo test --all-targets --all-features`: 116 library tests, 11 compact
  contract tests, six deterministic lab integration tests, and six offline
  CLI tests passed with zero failures;
- `cargo clippy --all-targets --all-features -- -D warnings`: exit 0;
- `cargo build --release`: exit 0;
- `cargo audit`: 35 locked dependencies scanned with no vulnerability;
- `cargo deny check`: advisories, bans, licenses, and sources passed, retaining
  only the accepted `winnow` 0.7/1.0 duplicate warning inside `toml`;
- `cargo check --target aarch64-unknown-linux-gnu --all-targets
  --all-features`: exit 0, compile evidence only;
- two fresh 48 kHz release generations and both installed copies compared
  byte-identical except `workstation-cost.txt`;
- the reference WAV SHA-256 remained
  `52aca28e3d82d8308ef242e728e6c6921854c8f675ec2372f1bbbb1ab92c1b03`;
  and
- artifact hygiene confirmed one ignored directory, exactly four passing
  WAVs, and no rejected or prior-batch output.

## Coupled Wire controlled-thump checkpoint

Implemented on 2026-07-24 and awaiting human listening:

- preserved the exact unpresented 1.6-second Coupled Wire generator, with
  source FNV-1a hash `647e93d33e919af3`;
- split a centered linear low body below 105 Hz from a 105-500 Hz thump branch
  and clean material above 500 Hz;
- used the accepted low contour at 8/12/25/50 ms, the nonlinear wet window at
  8/12/45/70 ms, and a clean upper recovery from gain 0.02 through 80 ms to
  unity by 130 ms;
- selected the least nonlinear `gentle` configuration at fixed gain 4.60,
  without a full-band limiter, compressor, per-file normalization, chord,
  delay, reverb, or production integration;
- reduced 45-90 Hz onset RMS from the rejected reference's -7.456 dBFS to
  -11.147 dBFS while keeping below-105 Hz nonlinear leakage at -40.218 dB and
  the 105-500 Hz shaped residual at -29.815 dB;
- measured -15.107 dBFS whole-file RMS, -2.006 dBFS sample peak,
  -2.006 dBTP estimated true peak, zero ceiling contact, DC `0.000341796`,
  maximum jump `0.015249848`, correlation `0.996780839`, mono loss
  `0.016345` dB, full tonal coverage, spectral flatness `0.000014807`, finite
  output, natural 1.6-second decay, and exact final zero; and
- measured the candidate nonlinear high-rate residual at -53.577 dB relative
  to probe input, passing the absolute -50 dB alias bound. The rejected
  full-band clamp's -57.864 dB result is comparison-only, not the gate.

Two release generations and the installed batch are byte-identical except
`workstation-cost.txt`. The deterministic file-set SHA-256 is
`e8aa1c458ff0a4fda6c5f4184e282fad377448719e4153efc2005b6e4afd2f5d`;
the single WAV SHA-256 is
`c4ccb994405c05a95369a081819ee0e4dffaf72c2e39aac7cf93b3ecac353e59`.
The rejected `artifacts/coupled-wire-envelope-motion/` batch was moved to
Trash. The only active ignored artifact directory is now
`artifacts/coupled-wire-controlled-thump/`, containing exactly one WAV and its
reports. Digital headroom does not prevent independent overload in the
external line output, amplifier, loudspeaker, room, or listening level.

Fresh feature-worktree verification:

- `cargo fmt --check` and `git diff --check`: exit 0;
- `cargo test --all-targets --all-features`: 122 library tests, 11 compact
  contract tests, and 13 offline CLI/lab tests passed with zero failures;
- `cargo clippy --all-targets --all-features -- -D warnings`: exit 0;
- `cargo build --release`: exit 0;
- `cargo audit`: 35 locked dependencies scanned with no vulnerabilities;
- `cargo deny check`: advisories, bans, licenses, and sources passed, retaining
  only the accepted `winnow` 0.7/1.0 duplicate warning inside `toml`;
- `cargo check --target aarch64-unknown-linux-gnu --all-targets
  --all-features`: exit 0, compile evidence only;
- two fresh release generations matched each other and the installed artifact
  byte-for-byte except `workstation-cost.txt`; and
- artifact hygiene confirmed one ignored directory, exactly one passing WAV,
  and no rejected or prior-batch output.

## Two clean house-kick listening gate

The approved isolated experiment was implemented on 2026-08-03 as two
structurally separate one-shot voices, not two positions in one graph:

- **House Impact** is direct phase modulation with an analytically integrated
  156 -> 52 Hz carrier, a 2:1 modifier, a 45 ms index envelope, and a 320 ms
  -60 dB amplitude envelope. Fixed-order selection retained the first passing
  index at 1.2 radians and static output gain 0.8.
- **Long Pressure** is an analytic two-mode damped system: a 112 -> 76 Hz impact
  mode with 115 ms decay shapes the rise of a 58 -> 48 Hz body mode with a
  280 ms pitch sigh and 760 ms decay. Fixed-order selection retained coupling
  0.5 and static output gain 1.5. A recursive two-pole prototype was rejected
  because its 48 kHz/8x residual was approximately -1 to -2.5 dB; the retained
  analytic realization preserves the distinct modal hypothesis without that
  rate dependence.

Both trajectories are prepared outside the sample path and replayed by index;
trigger and sampling allocate nothing. A linear 5 Hz DC blocker is applied
during preparation. There is no noise layer, clipper, limiter, compressor,
saturation, waveshaper, or normalizer. This precomputed experimental
realization is not a production memory/voice architecture decision.

The selected solo evidence at 48 kHz is:

| Voice | sample/8x peak | RMS | absolute DC | max jump | 8x residual | onset ablation | late body |
| --- | ---: | ---: | ---: | ---: | ---: | ---: | ---: |
| House Impact | -2.805/-2.805 dB | -22.470 dBFS | 0.000000033 | 0.020852 | -89.935 dB | -4.796 dB residual/full in 100-800 Hz | -0.000314 dB change |
| Long Pressure | -5.079/-5.079 dB | -21.384 dBFS | 0.000000017 | 0.010848 | -88.953 dB | -0.181 dB residual/full in 70-250 Hz | -39.765 dBFS at 44-54 Hz |

Both have zero ceiling contacts, finite output, exact zero padding, and pass
124 BPM quarter-note plus 248 BPM eighth-note-equivalent retrigger checks with
maximum jumps below 0.10. The 8x values use an independently generated 384 kHz
render, windowed-sinc reduction, bounded alignment, and fitted gain. These are
engineering checks, not claims that either kick sounds massive, gut-ripping,
clean, or house-ready.

The ignored batch `artifacts/two-clean-house-kicks/` contains exactly four
48 kHz, two-channel float32 WAVs: two padded solos and two four-bar 124 BPM
quarter-note presentations. Two fresh release generations match byte-for-byte
apart from `workstation-cost.txt`. Interleaved-sample FNV-1a hashes are
`566b9ea1e2efdd59`, `dfec5d603b23d8b9`, `52d2311f9106b8c5`, and
`2e46b7cbd0e80485` in filename order.

The canonical design is
`docs/superpowers/specs/2026-08-03-two-clean-house-kicks-design.md`. Production
`Engine`, models, presets, twelve controls, JACK, ALSA, SHR-DAW, and factory
catalogs remain unchanged. The generated batch is disposable, and no voice is
accepted or selected for integration until the user listens.

Fresh feature-worktree verification:

- `cargo fmt --check`, `cargo build --release`, and `git diff --check` exit 0;
- `cargo test --all-targets --all-features` exits 0: 266 library tests passed,
  five declared development-only library tests remained ignored, the current
  clean-kick CLI/contract tests passed, and historical audition/benchmark tests
  retained their documented ignored classification;
- the exact `cargo clippy --all-targets --all-features -- -D warnings` command
  is blocked by the pre-existing `clippy::large-enum-variant` warning on
  `VoiceModel` in `src/synthesis_model.rs`; the same command fails identically
  on unchanged `main`. Re-running with only that baseline lint allowed passes,
  so this experiment introduces no additional Clippy warning. The unrelated
  production enum was not changed to conceal the baseline failure;
- `cargo audit` scanned 43 locked dependencies with no vulnerability failure;
- `cargo deny check` passes advisories, bans, licenses, and sources, retaining
  only the accepted `winnow` 0.7/1.0 duplicate warning inside `toml`;
- both knowledge validators pass; and
- two final release generations and the retained batch match byte-for-byte
  except the declared volatile `workstation-cost.txt`.

## Five-kick and snare comparison gate

The cross-engine listening batch was completed on 2026-08-03. It compares the
two SHR Synth candidates with the three restored SHR Drums factory kits: Big
Rock (Muldjord), Experimental Noise (Muldjord), and Electronic House. The gate
contains exactly 15 stereo 48 kHz float32 WAVs: five raw solos, five four-bar
124 BPM patterns using the same Electronic House snare, three native old-kit
kick/snare patterns, one raw-level kick reel, and one peak-matched kick reel.
The raw reel exposes delivered level; the attenuation-only matched reel makes
timbre and envelope easier to compare. No EQ, dynamics, saturation, clipping,
limiting, normalization, reverb, or delay was added.

The raw solo measurements are:

| Kick | Peak | RMS | Crest |
| --- | ---: | ---: | ---: |
| House Impact | -2.805 dBFS | -22.426 dBFS | 19.621 dB |
| Long Pressure | -5.079 dBFS | -21.355 dBFS | 16.276 dB |
| Big Rock (Muldjord) | -10.743 dBFS | -32.405 dBFS | 21.662 dB |
| Experimental Noise (Muldjord) | -15.337 dBFS | -35.502 dBFS | 20.165 dB |
| Electronic House | -8.446 dBFS | -26.261 dBFS | 17.815 dB |

The closest presentation to the digital ceiling is House Impact with the
common snare at -0.293 dBFS; it has no ceiling contact or clipped sample. This
is useful level evidence, not an endorsement of that balance.

The renderer used the real `shr-drums` package loader and engine for the old
kits. MIDI velocity is 110, kick is note 36, snare is note 38, and common-snare
files linearly sum the exact Electronic House snare-only render with each
kick-only render. Native files instead render each old kit's kick and snare in
one engine. The source packages are read from SHR-DAW's engine-owned `kits/`
directory; none is copied into a user preset directory or SHR Synth.

Big Rock's bus filter produced a deterministic subnormal tail of approximately
`1.72e-43` after meaningful sound ended. The renderer therefore defines a
terminal-silence floor of `1e-12` (-240 dBFS), replaces only subsequent
subnormal residue with exact zero, and retains at least 250 ms of exact terminal
silence. It does not gate audible program material.

Verification established exactly 15 WAVs and seven reports, valid headers,
finite samples, peaks below 0 dBFS, 250 ms exact-zero endings, valid SHA-256
records, and byte-identical independent generations except the explicitly
volatile workstation timing report. The normal SHR Synth test suite passed after
the local merge. The batch is ignored and disposable at
`artifacts/kick-comparison-with-snares/`; its temporary renderer, build output,
second-generation output, worktree, and Trash entry were removed. The
canonical design is
`docs/superpowers/specs/2026-08-03-kick-comparison-with-snares-design.md`.
No kick, balance, or integration direction is accepted until the user listens.

Human listening rejected that batch on 2026-08-03. The delivered factory
levels sounded distant, Experimental Noise sounded like an unsuccessful tom
rather than a bass-heavy kick, the filenames did not make the comparison easy
enough to navigate, and the controlled common-snare section's deliberate use
of the Electronic House snare with other kits was unwanted and confusing. The
old 15-file artifact was already absent when the rejection was processed; it
was not regenerated or archived.

Inspection explains the level and identity problem. The raw factory peaks were
approximately -9.7 dBFS for Big Rock, -15.3 dBFS for Experimental Noise, and
-6.8 dBFS for Electronic House at velocity 127. Big Rock and Experimental
Noise use the same Muldjord note-36 kick sample assignments, voice gain, and
voice envelope. Experimental Noise does not supply a distinct bass kick; its
kit bus instead lowers output to -7 dB, reduces body to 0.10, and raises
saturation to 0.32, versus Big Rock's -5 dB output, 0.18 body, and 0.12
saturation. Compression or normalization can raise it, but EQ alone cannot
create the missing low-frequency source identity.

The next 12-file solo-kick successor was also rejected. Despite louder parallel
compression, dry/room pairs, explicit source names, and a labelled sub-rescue,
isolated one-shots did not provide a rhythm against which the user could judge
kick/snare balance. The user also still heard tom-like sources. That entire
solo folder and its support files were permanently deleted rather than
retained as another batch.

The only current audition is now
`artifacts/RHYTHMS - CURRENT ONLY/`. It contains exactly five simply named WAVs
plus `Effects.txt`: House Impact, Long Pressure, Big Rock, Experimental Noise,
and Electronic House, each named `<sound> - Rhythm - Processed.wav`. Every file
schedules eight literal alternating quarter-note hits at 124 BPM and velocity
127: kick, snare, repeated four times. Big Rock, Experimental Noise, and
Electronic House use one fresh instance of their own SHR Drums kit. At the
user's explicit request, House Impact and Long Pressure now trigger their new
notes 27 and 28 inside one fresh Electronic House kit instance with its
note-38 snare; no other sources are mixed.

All five files receive the same external presentation after the source bus:
4:1 compression at -18 dBFS with 4 ms attack, 120 ms release, and 3 ms
lookahead; one restrained short-room return at -10 dB wet gain; and fixed -1
dBFS peak normalization. They are stereo 48 kHz float32. The temporary rhythm
renderer, its raw WAVs, build output, obsolete solo helper, and prior solo batch
were permanently removed after the three final files passed basic format
checks.

The owner then rejected the Experimental Noise snare as a cowbell-like,
agricultural sound rather than a distorted metallic industrial snare.
Inspection found a 298 Hz pitched body with a 700 ms decay, the same acoustic
snare samples as Big Rock, and a metallic layer. SHR-DAW now replaces only that
note-38 voice with an authored model; the six unreferenced snare WAVs were
removed from that kit. The first modeled replacement was also rejected as
high-pitched, distant fuzz because it stacked hard clipping, 4.3 kHz band-pass
noise, FM, and ring modulation. The current revision instead uses a short 158
Hz body, low-pass broadband noise, no FM or ring modulation, restrained cubic
drive, and brief quiet modes. Its eight-hit rhythm was regenerated with the
same external processing and replayed alone. The owner accepted it as a
convincing snare—possibly better than Big Rock's—and explicitly classified it
as rock/industrial rather than suitable for Electronic House. Leave it as is
in Experimental Noise and do not move it into the House kit.

The owner subsequently selected House Impact and Long Pressure for inclusion
as two additional Electronic House kicks. Notes 33–35 were already occupied by
Tight Kick, Clipped Kick, and Sub Kick, so SHR preserved those voices and the
original note-36 House Kick, adding the new sounds on free notes 27 and 28.
Because SHR Drums does not implement SHR Synth's direct-PM and coupled-mode
topologies, the kit stores their deterministic 48 kHz float32 CC0 synthetic
one-shot exports rather than an altered approximation. Both trigger through
the ordinary House kit bus and note-38 House snare. The two updated rhythms
were played through the AudioBox; final judgment of their in-kit presentation
remains open.

The user explicitly authorized soundcard playback. A private reusable
allocation-free C JACK WAV player now preloads float WAVs, uses
`JACK_NO_START_SERVER`, creates only `shr-wav-review:out_l/out_r`, connects
them to `system:playback_1/2`, and closes cleanly after playback. The first
attempt to discover an installed player accidentally ran `jack_simple_client`'s
built-in approximately 1 kHz test oscillator; it was stopped immediately and
left no ports. Do not run unknown JACK example clients to discover their CLI.
Use `user/bin/play-current-rhythms`, which played the five current files through
the configured AudioBox in House Impact, Long Pressure, Big Rock, Experimental
Noise, Electronic House order and disconnected cleanly. No JACK lifecycle,
persistent route, MIDI, or recording changed. The Experimental Noise source
repair and the two added Electronic House kicks are the only factory-package
changes from this playback work.
