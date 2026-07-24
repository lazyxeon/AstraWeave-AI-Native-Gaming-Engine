# T.2a — Terrain Surface Quality: the "eyes hurt" beat (outcome)

> **Beat:** T.2a (terrain series; executes the AD.4.A §5c S2 hand-off) · **Date:** 2026-07-24
> **Baseline commit:** `89fbe97eb`. Commits listed per phase below.
> Evidence tiers: **built** / **run** / **verified**. Station frames and metrics in
> `d:/tmp/t2a_staging/render/<leg>/` (local, not committed); each leg has a `metrics.csv`.
> Anti-drift honoured: no water shading, no coverage/classification-height work, no scatter
> or judging-aid revert, no amplitude change, no golden re-bake.

---

## 0. Summary

The director's standing complaint — *"biomes look right at distance but wrong up close … they
kinda make my eyes hurt trying to figure out what's actually wrong with them"* — had **three
separate causes**, not one, and only one of them was the suspect the prior diagnosis named
first. In order of contribution:

1. **The material data was corrupt** (Phase 1, ratified first). Two independent defects in the
   cook script had destroyed real measured channels: a 16-bit read clamp flattened roughness and
   AO to constants, and the AO formula was **inverted**, applying occlusion to peaks instead of
   crevices. Three flat channels across two slots; a third slot rendering back-to-front
   occlusion. Both fixed at the root and re-cooked.
2. **The normal-strength boost** (Phase 2.1) — `NORMAL_XY_STRENGTH = 1.8`, applied
   unconditionally to every fragment.
3. **The hex-tile pow-4 sharpening** (Phase 2.2) — a ~4 m-scale lattice superimposed on every
   terrain material, and the same artifact the T.W.1.A session saw refracting through shallow
   water.

Two further findings are **surfaced, not acted on**, because they are art-direction purchases
rather than defect repairs: the grassland slot's albedo is a near-featureless synthetic green
paired with an alpha-cutout foliage card's normal map, and the desert and tundra slots are 100%
procedural with near-flat normals.

---

## 1. Method: the instrument the beat required

Every knob change is registered to **pinned camera stations** so an improvement is attributable
to one knob rather than to a blended "it looks better now".

**The editor cannot pin a camera.** Verified at HEAD:

| mechanism | why it fails |
|---|---|
| numeric position entry | does not exist — the only camera UI is FOV/near/far/speed (`tab_viewer/mod.rs:2443-2482`) |
| console command | the full command set (`console_panel.rs:366-441`) has no camera verb; `viewport-info` reads, never sets |
| F1-F12 bookmarks | in-memory only, lost on restart — and `set_yaw`/`set_pitch` (`camera.rs:577-584`) never update `yaw_target`/`pitch_target`, so `smooth_update` (k=20, every frame) drifts the restore back within ~50 ms |
| `.editor_preferences.json` | exact on startup, but `PanelEvent::TerrainReady` → `frame_terrain` (`main.rs:5842`) overwrites focal point, distance and pitch on **every** generation |
| screenshot command | none — `polish.rs`'s `include_screenshot` / `screenshot: Option<PathBuf>` are settable-but-never-read dormant fields |

Each shader-constant leg additionally needs a rebuild and restart, because the WGSL is
`include_str!`-compiled (`terrain_material_manager.rs:171-179`) and `ShaderManager`'s disk-reading
hot-reload has zero production callers. So an editor-driven station is not reproducible across
legs, and a `set_yaw`/`set_pitch` bug is separately worth fixing.

**`tools/aw_editor/tests/terrain_ab_stations.rs`** renders the *same editor viewport path*
offscreen with an exactly-specified camera: real generated terrain (`TerrainState`, seed 12345,
radius 6, the editor's noise defaults), the live 8-slot biomes pack, uploaded through the
editor's own `upload_terrain_chunks_raw`, drawn by `ViewportRenderer::render`, read back from
`engine_ldr_texture()` — the overlay-free target the parity harness hashes, so no grid or gizmo
contaminates a comparison.

```text
cargo test -p aw_editor --profile release-fast --test terrain_ab_stations -- --ignored --nocapture
  T2A_MODE=survey   census + per-slot representative positions (no GPU needed)
  T2A_LABEL=<leg>   render all stations to $T2A_OUT/<leg>/ + metrics.csv
```

### 1.1 The station map (pinned; do not tidy these numbers)

Coordinates were chosen from a survey run at `89fbe97eb`, taking the median-x position among
vertices where one slot's weight is ≥ 0.85 (a station framed on a 50/50 blend does not show the
material it is named after). Close-ups use a 55° look-down at distance 20, which fills the frame
with ground: at fovy 60° the top of the frame is still 25° below the horizon.

| station | world | focal (x, y, z) | dist | yaw | pitch | why |
|---|---|---|---|---|---|---|
| `01_med_grassland_closeup` | Mediterranean | 0.0, 12.6, 2037.2 | 20 | 45° | 55° | dominant biome (91.3%) **and** the worst material in the pack |
| `02_ct_forest_closeup` | Continental Temperate | 10.8, 26.6, 964.7 | 20 | 45° | 55° | **CONTROL** — the only slot with no placeholder channel |
| `03_med_mountain_closeup` | Mediterranean | -10.8, 412.8, -441.9 | 30 | 30° | 40° | flat AO; also the only tiling-64 slot, so it probes hex at a second scale |
| `04_desert_sand_closeup` | Desert | 43.1, 36.3, -1961.8 | 20 | 45° | 55° | control for data; primary probe for normal strength (near-flat normal map) |
| `05_boreal_tundra_closeup` | Boreal / Subarctic | 177.9, 34.5, 544.3 | 20 | 45° | 55° | the Boreal world's 93% surface |
| `06_boreal_overview` | Boreal / Subarctic | 0.0, 120.0, 0.0 | 2600 | 45° | 32° | the Q5 judgement frame |

**A swamp close-up is not possible on this world.** Swamp (slot 5) and river (slot 7) both have a
dominant-vertex count of exactly **0** in all four archetypes at seed 12345 / radius 6. The beat's
station list asks for a swamp close-up; it is reported as unreachable rather than faked from a
blended vertex.

### 1.2 The metrics, and how to read them

Each station reports mean luminance, stddev luminance, and **mean |Laplacian|** (high-frequency
energy). The Laplacian column is the one that moves for these knobs, because "harsh up close" is
excess local contrast.

**Direction of "better" is not constant.** For the Phase-1 data fix, *higher* high-frequency
energy is the improvement — flat roughness under sun is uniform sheen, and restoring real
roughness restores material variation. For the Phase-2 shader knobs, *lower* is the improvement —
they are amplifying contrast that the authored data does not contain. The metric is a change
detector and an attribution tool, not a score.

---

## 2. Phase 1 — DATA (ratified first) · commit `c0753b551`

### 2.1 Measurement (`tools/material_cook/channel_stats.py`)

The beat asked for mean/stddev. **Standard deviation is the wrong primary detector here**, and it
fails in both directions on this pack:

- `grass_mra` roughness has **sd 13.43** — it would clear an `sd < 2.0` filter — yet **99.5% of
  its pixels are exactly 255** and its IQR is 0. The sd is manufactured entirely by a 0.37% tail
  of near-zero pixels bleeding in from the source's foliage alpha cutout. It is the worst channel
  in the pack.
- `gravel` roughness (sd 1.43) and `beach` roughness (sd 2.25) would both *fail* an sd filter, and
  both are faithful to genuinely uniform source scans (`gravel_concrete_03`, `coast_sand_01`).
  Neither should be touched.

So the tool's primary detector is **modal fraction > 90% or IQR == 0**, with sd reported as a
secondary signal. Metallic is exempt: a hard constant 0 on every slot is the post-AD.4.A-D1
contract (terrain is dielectric), not a placeholder, and a blanket "zero variance = fake" sweep
would re-introduce the mirror-terrain regression.

**Measured, on disk, before (3 flat channels):**

| slot | layer | channel | mean | sd | IQR | modal% | uniq | verdict |
|---|---|---|---|---|---|---|---|---|
| 0 | grassland | roughness | 254.23 | 13.43 | 0 | **99.5%** | 227 | **FLAT (degenerate)** |
| 0 | grassland | ao | 217.00 | 0.00 | 0 | **100.0%** | 1 | **FLAT (constant)** |
| 1 | desert | roughness | 201.42 | 2.62 | 3 | 24.7% | 29 | low-variance |
| 1 | desert | ao | 220.66 | 8.43 | 14 | 3.9% | 52 | real |
| 2 | forest | roughness | 237.92 | 10.75 | 12 | 4.8% | 114 | real |
| 2 | forest | ao | 153.36 | 53.02 | 80 | 0.7% | 256 | real (best in pack) |
| 3 | mountain | roughness | 208.66 | 10.98 | 15 | 3.9% | 95 | real |
| 3 | mountain | ao | 140.00 | 0.02 | 0 | **100.0%** | 6 | **FLAT (degenerate)** |
| 4 | tundra | roughness | 160.67 | 3.83 | 4 | 19.2% | 39 | real |
| 4 | tundra | ao | 238.60 | 3.03 | 4 | 13.1% | 29 | real |
| 5 | swamp | roughness | 238.80 | 7.46 | 11 | 12.7% | 31 | real |
| 5 | swamp | ao | 211.87 | 10.69 | 13 | 4.8% | 83 | real *(but inverted — §2.2)* |
| 6 | beach | roughness | 245.45 | 2.25 | 3 | 18.9% | 25 | low-variance (genuine) |
| 6 | beach | ao | 240.43 | 14.41 | 16 | 7.0% | 190 | real |
| 7 | river | roughness | 220.10 | 1.43 | 2 | 27.7% | 16 | low-variance (genuine) |
| 7 | river | ao | 247.07 | 3.00 | 3 | 16.7% | 87 | low-variance |

### 2.2 Two root causes, both in `scripts/import_terrain_textures.py`

**(a) A 16-bit read clamp.** `load()` did `Image.open(p).convert("RGBA")`. PIL *clamps* 16-bit
modes (`I;16` etc.) to 255 rather than rescaling, so every 16-bit source decoded to solid white.
That is exactly why slot 0's roughness is 99.5%-flat 255 — its source
`grass_medium_01_rough.png` really has mean 111.6 / sd 40.6 — and why slot 3's AO is the constant
**140**, which is `0.55 × 255`, the floor of `build_mra`'s curve when height is uniformly 1.0.
Same class as the AD.4.A "D2" defect fixed in `cook_1k.py::to_l8`; this reader never received it.

**(b) Inverted ambient occlusion.** `build_mra` computed `0.55 + 0.45·blur(1 − h)` — darkening
peaks and lighting crevices. Occlusion rises with height: a peak is exposed. Scored against
same-scan ground truth (a real AO map correlated with its own displacement map, both resampled
to 1024):

| scan | corr with upright `h` | corr with inverted `1−h` |
|---|---|---|
| `ganges_river_pebbles` | **+0.478** | −0.478 |
| `forest_leaves_02` | **+0.230** | −0.230 |
| `aerial_rocks_01` | **+0.122** | −0.122 |
| `aerial_beach_01`, `coast_land_rocks_01`, `sandy_gravel_02`, `snow_02` | ±0.03-0.06 | (near-flat displacement; discriminate neither way) |

**The inversion shipped.** Live `assets/materials/mud_mra.png`'s AO correlates **+0.9908** with
the inverted curve and **−0.9908** with the upright one — slot 5 has been rendering ambient
occlusion on the wrong half of its relief.

Also removed the `else: out[:,:,2] = 217` branch. A flat constant is a silent lie: downstream it
is indistinguishable from measured data. Families without a displacement map now derive AO
explicitly.

### 2.3 The re-cook (surgical — `_mra` only; albedo and normal untouched)

| slot | channel | source / method | before | after |
|---|---|---|---|---|
| 0 grassland | roughness | `pine_forest/grass_medium_01_rough.png`, read 16-bit-safe (**real data restored**) | 254.23 / sd 13.43 / 99.5% modal | **111.63 / sd 39.80 / 8.3% modal / 256 uniq** |
| 0 grassland | AO | **derived** — Frankot-Chellappa integration of the slot's own normal map (no displacement exists upstream) | constant 217 | **197.69 / sd 20.16 / 116 uniq** |
| 3 mountain | AO | `pine_forest/rock_face_03_disp_1k.png` — same scan as the albedo (identity confirmed), read 16-bit-safe | constant 140 | **206.01 / sd 14.49 / 111 uniq** |
| 5 swamp | AO | same displacement, re-derived **upright** | inverted, mean 211.87 | **182.85 / sd 10.68** (structure preserved, orientation corrected) |

Roughness for slots 3 and 5 is *preserved* from the existing map (`--rough-from-mra` lifts the G
channel), so exactly one channel changed in each.

**The derivation is calibrated, not assumed.** Grass has no upstream displacement, so its AO is
integrated from its own normal map. The slope sign convention was settled empirically — all four
combinations scored against the two live families that *do* ship a real displacement:

| slopes | mountain (`rock_face_03`) | swamp (`forrest_ground_01`) |
|---|---|---|
| `p=-nx/nz, q=-ny/nz` | −0.122 | −0.196 |
| **`p=-nx/nz, q=+ny/nz`** | **+0.651** | **+0.632** |
| `p=+nx/nz, q=-ny/nz` | −0.651 | −0.632 |
| `p=+nx/nz, q=+ny/nz` | +0.122 | +0.196 |

Two independent scans agree. (Correlation is ~0.65 rather than ~1.0 because a normal map and a
displacement map capture different frequency bands of the same surface.)

**After: 0 flat channels.** `aw_asset_cli validate` — biomes `materials.toml` ✅ (the 10
`arrays.toml` "Missing 'name'" failures are a pre-existing validator/schema mismatch present in
**all ten** packs, not introduced here). `cargo xtask ci-guard` — 0 stray blobs, ignore surfaces
match. No new tracked files, so no keeplist regeneration was required.

Regression guards added to `tools/material_cook/test_cook_1k.py` (**4/4 pass**): the existing
contract, 16-bit safety, ARM→MRA guard, plus a new `test_ao_orientation_and_normal_integration`
that pins both derivations' orientation so the sign cannot silently flip back.

### 2.4 Isolation evidence (run + verified)

`00_baseline` → `10_data`, identical camera, identical build, only the material bytes changed:

| station | mean (before → after) | std | **mean \|Laplacian\|** | |
|---|---|---|---|---|
| 01 grassland **(repaired)** | 101.410 → 95.047 | 22.126 → 24.472 | **17.869 → 21.213** | +18.7% |
| 02 forest **(CONTROL)** | 76.817 → 76.817 | 15.484 → 15.484 | **20.876 → 20.876** | **0.000** |
| 03 mountain **(repaired)** | 91.272 → 93.266 | 25.799 → 25.615 | **12.536 → 13.104** | +4.5% |
| 04 desert (control) | 142.666 → 142.666 | 3.938 → 3.938 | **2.402 → 2.402** | **0.000** |
| 05 tundra (control) | 179.879 → 179.879 | 1.559 → 1.559 | **1.355 → 1.355** | **0.000** |
| 06 boreal overview | 177.955 → 178.327 | 39.449 → 38.780 | 11.697 → 11.563 | (mountain slot in frame) |

**Every slot whose data was not touched renders a numerically identical frame**, and only the two
repaired slots moved. That is the attribution the beat asks for.

---

## 3. Findings surfaced, deliberately NOT acted on

Both are **art-direction purchases**, not defect repairs, and the ratification's data-first
discipline puts them on the director's side of the line. Each is stated with its measurement so
the call can be made without re-deriving anything.

### 3.1 The grassland albedo is a synthetic flat green paired with a cutout foliage card's normal

Slot 0 is the most-rendered surface in the world (91.3% of Mediterranean, and grassland is the
editor's default primary biome). Measured at native 1024²:

| file | R mean/sd | G mean/sd | B mean/sd | mean \|Laplacian\| |
|---|---|---|---|---|
| `grass.png` (live albedo) | 74.38 / **3.02** | 178.57 / **15.08** | 27.00 / **2.30** | **6.53** |
| `mud.png` (for scale) | 144.78 / 22.41 | 135.02 / 17.77 | 93.21 / 24.59 | 23.06 |
| `mountain_rock.png` | 130.90 / 17.59 | 104.95 / 15.85 | 80.36 / 13.21 | 15.91 |

The grassland albedo carries roughly **a quarter of the high-frequency content** of the other
ground materials — it is a nearly uniform saturated green.

It is also **not** the scan its own normal and roughness maps come from. `grass_n.png` is
byte-consistent with `pine_forest/grass_medium_01_nor_gl.png` (mean 124.27/127.08/225.76 vs
124.27/127.08/225.97, the difference being the 4096→1024 resize), and `grass_mra`'s roughness
traces to `grass_medium_01_rough.png` — but `grass_medium_01` is an **alpha-cutout grass card**
(its alpha map is mean 45.5 / sd 77.3, i.e. mostly transparent; its diffuse is blades on black,
mean 15.5). Someone substituted a flat green for the albedo, sensibly, because compositing a
cutout card as an opaque ground layer would show black gaps — but kept the card's normal map,
whose values in the transparent regions are meaningless.

That is the visible defect in station 01: hard-edged black shards scattered through flat green.
They are the cutout regions' garbage normals being shaded, and the normal-strength boost
amplifies them. The Phase-1 data fix and the Phase-2.1 reduction each calm them measurably
(lap 21.21 → 14.68 at 1.0) but **neither removes them**, because the source asset is wrong for
the job.

**Options, if the director wants slot 0 fixed properly:** `assets/textures/leafy_grass_arm_4k.jpg`
is a complete tileable ground-grass ARM set already on disk (AO channel mean 188.6 / sd 34.3);
`grass_medium_02_disp.png` (8-bit, sd 15.49) is a sibling scan. Either is a family swap — new
albedo + normal + mra — not a channel repair.

### 3.2 Desert and tundra are 100% procedural, with near-flat normals

`scripts/import_terrain_textures.py:15` states it plainly — *"Procedural (sand, snow) (no real
sources available in workspace)"* — and `PROCEDURAL = ["sand", "snow"]` at `:107`. Their normal
maps are effectively flat (`sand_n` sd 1.83/1.41/0.07, `snow_n` sd 1.43/1.43/0.02) and their
albedos nearly featureless (`snow.png` sd 2.16 on all three channels).

The consequence is visible at stations 04 and 05: a smooth tone with **no material structure at
all**, in which the only discernible pattern is the hex-tile lattice itself (see §4.2). Their
Laplacian energies — 2.40 and 1.36 — are an order of magnitude below forest's 20.88.

Real replacements exist on disk, acquired after that script ran: `snow_02_{ao,arm,rough,diff,
disp,nor_gl}_4k.*` (complete; AO sd 10.79) and `assets_src/materials/snow_mra.png` (ARM order,
AO sd 55.10) with a real `snow_n.png` (sd 43.48) for tundra; `damp_sand_*` and `gravelly_sand_*`
(complete but no `_ao`) for desert. Again: family swaps.

### 3.3 Slots 5 (swamp) and 7 (river) never render on this world

Dominant-vertex count is exactly **0** for both in all four archetypes at seed 12345 / radius 6.
The swamp AO inversion fixed in Phase 1 is therefore **correct but not visually verifiable at any
station on this world** — stated plainly rather than claimed as an observed improvement. Slot 7
being unreachable is also worth noting against the T-series ratification's row-7 decision, which
ratified gravel as "honest riverbed".

### 3.4 An editor camera bug, found while establishing the instrument

`OrbitCamera::set_yaw` / `set_pitch` (`camera.rs:577-584`) set the value but not `yaw_target` /
`pitch_target`, and `smooth_update` (k=20) runs every frame from `widget.rs:1629`. So **every**
F1-F12 bookmark restore and every `ViewportCameraPreset` panel event snaps for one frame and
then drifts back to the prior orientation within ~50 ms. The Alt+1/3/7/0 hotkey presets are
unaffected because they go through `set_view_front()` etc., which set targets correctly. Not
fixed here (out of this beat's scope); reported for an editor-health beat.

---

## 4. Phase 2 — SHADER CONSTANTS (each isolated)

Both knobs live only in WGSL — `rg NORMAL_XY_STRENGTH --type rust` and
`rg 'hex_cells|pow\(hex' --type rust` both return zero hits, so there is no Rust mirror to keep
in step. Both are `include_str!`-compiled, so every leg below is a separate build.

### 4.1 `NORMAL_XY_STRENGTH` (`pbr_terrain_forward.wgsl:331`)

**What it actually does.** It is a function-local `let` *inside* the per-layer accumulation loop,
multiplying only the hex-blended tangent-space normal's XY (Z passes through unscaled), before
the TBN transform. After renormalization the effect is a slope steepening: the effective tangent
slope becomes `atan(1.8·tan θ)`. Every micro-facet's specular lobe and N·L is tilted ~1.8× harder
than the authored normal map says.

**The prior diagnosis's "mip0 boost … mip-gated" phrasing is not literal code.** There is no mip
check, no LOD branch and no distance term anywhere near it — verified by grepping the whole file.
The boost is applied unconditionally to every fragment. The distance falloff is an *emergent*
property of the hardware mip chain: at range the sampler reads a box-blurred normal mip whose XY
has already collapsed, and 1.8× of nearly-nothing is still nearly-nothing. Same constant, both
cases. Provenance: introduced by the E3 build `d506658d8` at 1.8; `git log -S` shows the value has
**never** been changed.

**Ladder** (all legs post-data-fix, hex at 4.0; mean |Laplacian|, and Δ vs 1.8):

| station | **1.8** (shipped) | **1.4** | **1.0** |
|---|---|---|---|
| 01 grassland | 21.213 | 18.121 (−14.6%) | 14.675 (**−30.8%**) |
| 02 forest (control) | 20.876 | 18.846 (−9.7%) | 17.077 (−18.2%) |
| 03 mountain | 13.104 | 11.200 (−14.5%) | 9.397 (**−28.3%**) |
| 04 desert | 2.402 | 2.336 (−2.8%) | 2.286 (−4.8%) |
| 05 tundra | 1.355 | 1.282 (−5.4%) | 1.220 (−10.0%) |
| 06 boreal overview | 11.563 | 11.496 | 11.445 (−1.0%) |

The response is monotonic and its *shape* is the confirmation: the reduction is large exactly
where the normal map carries real relief (grassland −31%, mountain −28%, forest −18%) and small
where it is near-flat (desert −4.8%, tundra −10%). The constant is amplifying whatever the normal
map contains — including, at slot 0, the garbage in a cutout card's transparent regions.

Visually at station 03, 1.8 renders the rock's cracks as hard black gashes; at 1.0 they read as
stone. At station 01 the black shards soften but do not disappear, which is the evidence that
slot 0's residue is a source-asset problem (§3.1), not a constant.

**Proposal: 1.4.** It takes ~15% off the harshness on every detailed material while keeping more
relief than 1.0, and the original constant's stated purpose — compensating relief flattening so
the ground does not read "like a plain .png" — argues against going all the way down in one step.
The frames for all three values are in `d:/tmp/t2a_staging/render/{10_data,21_normal_1p4,20_normal_1p0}/`;
this is a one-line amendment at the gate.

**If the director would rather retire the constant than tune it**, the causal fix is upstream:
`downsample_rgba8_box` (`terrain_material_manager.rs:1519`) box-averages the *normal* array as
raw RGBA8 with no renormalization, and `canonical_terrain_pack.rs:231-246` resizes normals to
512² with a triangle filter, also without renormalizing. Both shrink normal XY toward flat, which
is precisely the flattening 1.8 was added to compensate. Fixing the downsample is the root cause;
changing 1.8 is the symptom. Out of this beat's scope, recorded as the next lever.

### 4.2 Hex-tile pow-4 weight sharpening (`pbr_terrain_forward.wgsl:264-266`)

**What it actually is.** `hex_cells()` gives three inverse-distance weights over a hex lattice
in *texture* space; `pow(w, 4.0)` sharpens them and they are renormalized. There is no separate
blend-width constant — **the exponent 4.0 *is* the blend width.** With `tiling = 128` over a
512 WU chunk, one hex cell is about **4 m of world**, which is the scale a player notices while
walking. Raising the exponent makes cells near-binary and their borders hard (each cell has a
different rotation, so the normal field snaps across the seam); lowering it widens the transition
and three rotated copies ghost together.

**Isolated A/B** (`10_data` → `30_hex_pow2`; `NORMAL_XY_STRENGTH` held at the shipped 1.8, only
the exponent changed):

| station | pow 4.0 | pow 2.0 | Δ |
|---|---|---|---|
| 01 grassland | 21.213 | 19.349 | −8.8% |
| 02 forest (control) | 20.876 | 18.567 | −11.1% |
| 03 mountain | 13.104 | 11.617 | −11.3% |
| 04 desert | 2.402 | 2.136 | **−11.1%** |
| 05 tundra | 1.355 | 1.230 | −9.2% |
| 06 boreal overview | 11.563 | 11.499 | −0.6% |

**The uniformity is the finding.** Where `NORMAL_XY_STRENGTH` scaled with how much relief a
material's normal map carries (−31% on grassland vs −4.8% on the near-flat desert), the hex
exponent removes a near-constant **9-11% at every station**, including the two materials that
have essentially no content of their own. That is the signature of a *structural* artifact
superimposed on the surface rather than an amplification of authored data — two different
mechanisms, two distinguishable signatures, which is exactly what the isolated legs were for.

**It is visible, and it is the T.W.1.A artifact.** Station 02 shows it plainly as a diamond/
hexagonal patchwork of subtly different tones tiling the forest floor; station 04, whose material
is a nearly featureless procedural tan, shows it as faint chevrons that are *the only discernible
structure in the frame*. This is the same "checkered diamonds" pattern the T.W.1.A session saw
refracting through clear shallow water and handed forward as "a terrain-material concern, not
water-owned" (`TW1A_OUTCOME.md` §6). **Confirmed: same mechanism, now tuned rather than chased.**

**Proposal: 2.0.** The lattice softens markedly at station 04 while the forest floor keeps its
material reading at station 02.

**A structural note the beat did not ask for but that bounds what this knob can do.** `in.uv` is
per-chunk normalized `[0,1]` (`engine_adapter.rs:2382-2395`), so `scaled_uv` restarts at zero in
every chunk and `hex_cells` hashes chunk-local coordinates. **Every 512 m chunk therefore receives
a byte-identical hex rotation/translation field** — the de-tiling mechanism itself tiles, with a
512 m period. Recorded for whoever owns the next pass on this shader.

### 4.3 Joint pass

Run last, against the isolated states, per the beat's ordering. See §7 for the combined table.

---

## 5. Phase 3 — Boreal taiga threading (Q5) · measured before tuned

### 5.1 The problem, quantified

Per-archetype census on the real generation path (seed 12345, radius 6, interior vertices,
n = 620,620 per archetype), at the T.2a baseline:

| archetype | grassland | desert | forest | mountain | tundra | swamp | beach | river |
|---|---|---|---|---|---|---|---|---|
| Mediterranean | **91.349%** | 3.486% | 0.542% | 3.313% | 1.110% | 0.000% | 0.200% | 0.000% |
| Continental Temperate | 1.106% | 0.000% | **96.144%** | 1.000% | 1.404% | 0.000% | 0.345% | 0.000% |
| Desert | 0.000% | **94.730%** | 0.000% | 4.798% | 0.472% | 0.000% | 0.000% | 0.000% |
| Boreal / Subarctic | 0.000% | 0.000% | **0.017%** | 6.651% | **93.331%** | 0.000% | 0.000% | 0.000% |

Boreal is **108 forest vertices out of 620,620** — the "snow-white dominant lowlands … no green"
the E3 pre-flight recorded, now with a number. The `06_boreal_overview` baseline frame is the
picture: white and brown to the horizon, not one green pixel.

### 5.2 Why — measured, not inferred

`BorealForest` requires `temp ∈ [0, 5)` **and** `moisture ≥ 200`. Sampling each archetype's
climate field over the radius-6 extent at a lowland elevation (37,249 points):

| archetype | mean °C | p5 | p25 | p50 | p75 | p95 | moisture ≥ 200 |
|---|---|---|---|---|---|---|---|
| Mediterranean | 14.48 | 9.58 | 13.07 | 14.92 | 16.23 | 17.81 | 99.8% |
| Continental Temperate | 8.94 | 2.55 | 7.13 | 9.47 | 11.22 | 13.25 | 100.0% |
| Desert | 22.59 | 14.53 | 20.53 | 22.97 | 25.40 | 28.32 | 1.4% |
| **Boreal / Subarctic** | **−7.46** | −16.00 | −10.00 | −6.55 | −4.41 | −1.57 | 99.7% |

**Boreal is 100% below 0 °C.** Moisture is not the gate (99.7% pass); temperature is. The band's
floor sits ~7 °C above the world's median, so `classify_whittaker_polygon` returns `Tundra`
essentially everywhere and the 0.017% forest is noise in the warm tail.

Share of the Boreal world colder than each candidate floor — i.e. the share that would *stay*
Tundra:

| floor | −2.0 | −4.0 | **−5.0** | −6.0 | −8.0 | −10.0 |
|---|---|---|---|---|---|---|
| stays Tundra | 93.5% | 78.7% | **69.3%** | 57.6% | 37.7% | 25.0% |
| becomes BorealForest | 6.5% | 21.3% | **30.7%** | 42.4% | 62.3% | 75.0% |

### 5.3 The lever chosen, and why the global band is safe here

**`TUNDRA_MAX_TEMP_C: 0.0 → −5.0`** (`biome_lookup.rs:200`).

- It targets **character, not a percentage**, per Q5: snow stays the dominant reading (~69% of
  the surface before the mountain overlays take their share) with forest threading through the
  warmer ground — taiga-and-snow.
- It is the *physically honest* direction. Real-world taiga mean annual temperature runs roughly
  −5 … +5 °C; the shipped band started at 0, which is the tundra/taiga boundary, not taiga's.
- **The cross-archetype blast radius that made this lever look risky is empirically zero at this
  configuration**: Mediterranean, Continental Temperate and Desert each have **0.0%** of sampled
  vertices below 0 °C, so no vertex in any of them can cross a floor lowered from 0 to −5. Their
  small tundra census (1.110% / 1.404% / 0.472%) is **not** Whittaker Tundra at all — it is the
  `SnowCap` elevation overlay (`elev ≥ 350 m`, `temp < 18`), which is evaluated *before* the
  Whittaker polygon and which this change does not touch. §5.4 verifies that empirically rather
  than resting on the argument.
- It respects every binding assertion: `biome_lookup.rs`'s canonical-tundra test needs the floor
  strictly above −10.0 (−5.0 ✓); the Equatorial and Desert distribution tests assert
  `BorealForest < 0.005`, which only *raising* `BOREAL_MAX_TEMP_C` could break, and that constant
  is untouched; `every_biome_appears_in_some_archetype` needs Tundra > 0.5% somewhere, and Boreal
  retains ~69%.

The stale comment at `biome_lookup.rs:357-358` — which claimed a sub-zero vertex "can be
BorealForest if temperature is at the warm end of cold" while the branch returned `Tundra`
unconditionally — is corrected in the same edit, since it now describes what the code does.

### 5.4 Result — census before/after, all four archetypes (run + verified)

`00_baseline` → `50_boreal`, same instrument, same seed, same radius:

| archetype | slot | before | after |
|---|---|---|---|
| **Mediterranean** | *all eight* | — | **byte-identical** (91.349 / 3.486 / 0.542 / 3.313 / 1.110 / 0.000 / 0.200 / 0.000) |
| **Continental Temperate** | *all eight* | — | **byte-identical** (1.106 / 0.000 / 96.144 / 1.000 / 1.404 / 0.000 / 0.345 / 0.000) |
| **Desert** | *all eight* | — | **byte-identical** (0.000 / 94.730 / 0.000 / 4.798 / 0.472 / 0.000 / 0.000 / 0.000) |
| **Boreal / Subarctic** | forest | **0.017%** (108 verts) | **40.878%** (253,695) |
| | tundra | 93.331% | **52.386%** |
| | mountain | 6.651% | 6.653% |
| | desert (ColdDesert) | 0.000% | 0.083% |
| | grassland / swamp / beach / river | 0.000% | 0.000% |

**Collateral shift is not "small", it is zero** — the three warm archetypes' censuses are identical
in every slot, exactly as the temperature measurement predicted. Snow keeps the plurality on
Boreal (52.4% tundra + 6.7% mountain rock vs 40.9% forest) with forest threading the warmer valley
ground.

Measured 40.9% against the histogram's predicted 30.7%: the probe sampled a single lowland
elevation while real terrain varies with the lapse rate and the coastal gate, so the prediction was
a lower bound. The ladder is still the right dial — roughly, floor −2.0 → ~7%, −4.0 → ~25%,
**−5.0 → 40.9% (measured)**, −6.0 → ~50%+.

### 5.5 Read this at the gate: coverage is right, legibility is T.3's

The `06_boreal_overview` frame changes from *"white and brown, no green"* to large threaded regions
following the valleys — but they read **brown**, not green. Slot 2's only forest signal today is
`derived_1k/tree_leaves`, a leaf-litter forest *floor* texture; there are no trees because scatter
is still disabled. So the overview now reads brown-and-white rather than green-and-white.

This is exactly the condition the T-series ratification anticipated: *"forest legibility re-judged
at T.3 when tree scatter returns (floor texture is currently the only forest signal)"* (§2 row 2).
The classification is correct and measurable now; whether it *reads* as taiga is a T.3 judgement.
If the director wants less brown in the interim, lowering the magnitude of the floor (e.g. −4.0)
is a one-line amendment and §5.2's ladder gives the expected coverage.

---

## 6. Phase 5 — the conditional aux-resolution question (Q4): **RETIRED, no purchase needed**

The ratification's Q4 held that T.2 must *earn* any memory spend with evidence that data fixes
are insufficient. The evidence says the opposite of insufficient — it says resolution is not the
axis the defect lives on:

1. **The close-up defect fully decomposed into three non-resolution causes**, each isolated and
   measured: corrupt channel data (§2), an unconditional normal-strength multiplier (§4.1), and a
   4 m-scale hex lattice (§4.2). None of the three is a sampling-density deficit.

2. **Raising resolution on disk buys nothing at all.** `load_albedo_bytes` and `load_aux_bytes`
   resize to 1024² / 512² *unconditionally* (`canonical_terrain_pack.rs:201-210, 231-246`), so a
   2K or 4K source is downsampled to the same runtime buffer. Any real spend would have to be a
   `CANONICAL_AUX_RES` increase, which is a Rust/Rust duplicated constant — `terrain_material_
   manager.rs:79` **and** `canonical_terrain_pack.rs:35` must move together or `set_material`
   rejects the byte counts.

3. **The cost of the only spend that would do anything** (aux 512 → 1024, calculated from the
   loader's clamps): per layer normal + ORM go 1 MiB + 1 MiB → 4 MiB + 4 MiB, so a layer goes
   6 MiB → 12 MiB. Eight active layers: **48 MiB → 96 MiB**. The 32 allocated array slices:
   **192 MiB → 384 MiB**, or **256 MiB → 512 MiB** with the full mip chain — which alone exceeds
   the 256 MB soft texture budget the Terrain Asset Quality campaign measured against.

4. **It would make the largest remaining defect worse.** The residue at station 01 is the
   alpha-cutout card's garbage normals being shaded (§3.1). Higher aux resolution renders those
   shards *sharper*, not softer. And the residue at stations 04/05 is procedural source material
   with no detail to recover at any sampling density (§3.2).

**Q4 therefore retires without a purchase.** The next lever, if the director wants more close-up
fidelity, is *source material* (§3.1, §3.2) — and before that, the free one: renormalizing the
normal-map downsample (`downsample_rgba8_box`, §4.1), which addresses the flattening
`NORMAL_XY_STRENGTH` was invented to paper over.

---

## 7. The A/B ledger (mean |Laplacian| per station, per leg)

Every leg is the *same* camera, the *same* generated terrain and the *same* build settings; only
the named knob differs. Legs `20`/`21`/`30` each change exactly one thing from `10_data`.

| leg | data | `NORMAL_XY_STRENGTH` | hex `pow` | 01 grass | 02 forest (ctl) | 03 mtn | 04 desert | 05 tundra | 06 overview |
|---|---|---|---|---|---|---|---|---|---|
| `00_baseline` | corrupt | 1.8 | 4.0 | 17.869 | 20.876 | 12.536 | 2.402 | 1.355 | 11.697 |
| `10_data` | **fixed** | 1.8 | 4.0 | 21.213 | 20.876 | 13.104 | 2.402 | 1.355 | 11.563 |
| `21_normal_1p4` | fixed | **1.4** | 4.0 | 18.121 | 18.846 | 11.200 | 2.336 | 1.282 | 11.496 |
| `20_normal_1p0` | fixed | **1.0** | 4.0 | 14.675 | 17.077 | 9.397 | 2.286 | 1.220 | 11.445 |
| `30_hex_pow2` | fixed | 1.8 | **2.0** | 19.349 | 18.567 | 11.617 | 2.136 | 1.230 | 11.499 |
| **`40_joint`** | fixed | **1.4** | **2.0** | **16.200** | **16.764** | **9.930** | **2.080** | **1.161** | **11.450** |

**The knobs are independent.** Predicting the joint leg by adding the two isolated deltas to
`10_data` lands within a few percent everywhere — 01: −4.96 predicted vs −5.01 actual (101%);
02: −4.34 vs −4.11 (95%); 03: −3.39 vs −3.17 (94%); 04: −0.332 vs −0.322 (97%); 05: −0.198 vs
−0.194 (98%). So no joint re-tuning is needed: the director can amend either value one line at a
time and the other's contribution holds.

Net from the shipped baseline to the joint proposal: grassland −9.3%, forest −19.7%, mountain
−20.8%, desert −13.4%, tundra −14.3%. Grassland's smaller net is *because* its data fix pushed
the number up first — the data restored real material variation, then the constants removed
amplified harshness on top of it. Those are two different things happening to the same station,
which is precisely why they were measured apart.

## 8. Verification ladder

| check | result |
|---|---|
| `cargo test -p astraweave-terrain --lib` | **799 passed / 7 failed / 3 ignored** — measured at the T.2a base `89fbe97eb` as **797 / 7 / 3**, with the **identical seven** failure names. The +2 are this beat's new invariant tests; **zero regressions**, and in particular every `biome_lookup` and `world_archetypes` distribution test still passes with the −5.0 floor |
| `cargo test -p astraweave-render --lib stochastic_tiling` | 2 passed (the test that pins the four *legacy* WGSL function names by string — untouched) |
| `python tools/material_cook/test_cook_1k.py` | **4/4 PASS** — contract, 16-bit safety (D2), ARM→MRA guard (D1), and the new AO-orientation regression |
| `python tools/material_cook/channel_stats.py` | 3 flat channels → **0** |
| `cargo run -p aw_asset_cli -- validate assets/materials` | biomes `materials.toml` PASS; the 10 `arrays.toml` "Missing 'name'" failures are a pre-existing validator/schema mismatch present in **all ten** packs |
| `cargo xtask ci-guard` | PASS — 0 tracked pack members, 0 stray blobs, ignore surfaces match. No new tracked files, so no keeplist regeneration needed |
| `cargo fmt` (touched crates) | clean |

### 8.1 Golden/baseline rot for T.G — the numbers to inherit

The seven `astraweave-terrain --lib` failures are **unchanged in name and count** by this beat.
Four are the pre-E3 D5FIX/golden family already adjudicated in `E3_PREFLIGHT_2026-07.md` §2.4, and
three (`temperature_golden_value_default_config`, the two `fbm_*_affects_output`) were already
failing at the base. **Phase 3 added no new baseline rot** — it changed a classification threshold
that no test asserts, and the assertions that *do* bound it (canonical-tundra, the Equatorial and
Desert `BorealForest < 0.005` distribution tests, `every_biome_appears_in_some_archetype`) all
still pass.

### 8.2 A pre-existing failure this beat found but did not fix

`cargo test -p astraweave-render --test shader_validation` → **3 passed / 1 failed**. The failure
is `test_all_shaders_compile`, and it is **not a shader defect** — its own output reports
`Failed: 0`. It trips a *vacuity guard*: "only 58 shaders were actually parse+validated
(expected >= 60)". Confirmed pre-existing by re-running with the base commit's shader content
restored: **identical failure, identical counts**. This beat's entire `astraweave-render` diff is
four numeric literals in one WGSL file, which cannot change how many *files* get validated.

Not fixed here deliberately: it is CI/test-infrastructure drift (skip list vs glob vs the
hard-coded floor of 60), which the T-series ratification Q8 assigned to the **separate parallel
CI-workshop beat**, and a session may be active in that area. Handed over with the diagnosis:
79 files found, 58 validated, 0 failed, floor 60 — so either the skip list has legitimately grown
and the floor is stale, or a glob stopped matching.

---

## 9. Director gate repro

`cargo editor` → Terrain panel → seed **12345**, radius **6** (or the harness, which is exact:
`cargo test -p aw_editor --profile release-fast --test terrain_ab_stations -- --ignored --nocapture`).

1. **Close-up, Mediterranean and Continental Temperate.** The pass bar is your own words inverted:
   the materials read as materials, nothing makes the eyes hurt, and you can *attribute* it — the
   uniform sheen is gone (roughness is real data again), the rock's cracks read as stone rather
   than black gashes (normal strength), and the 4 m diamond/chevron lattice has stopped shimmering
   (hex sharpening). Frames for every intermediate value are in `d:/tmp/t2a_staging/render/`.
2. **The two knob values are yours to amend, one line each.** `NORMAL_XY_STRENGTH` at
   `pbr_terrain_forward.wgsl:331` (1.8 → **1.4**; 1.0 also captured) and the hex exponent at
   `:264-266` (4.0 → **2.0**). They are near-independent, so amending one does not invalidate the
   other's evidence.
3. **Boreal overview.** Forest now threads the valleys (0.017% → 40.9%) with snow keeping the
   plurality — but see §5.5: it reads *brown*, not green, because the forest slot's only signal is
   a leaf-litter floor texture until T.3 restores tree scatter. `TUNDRA_MAX_TEMP_C`
   (`biome_lookup.rs:200`) is the one-line dial; §5.2 has the coverage ladder.
4. **The two art-direction calls in §3** — grassland's cutout-card source and the procedural
   desert/tundra families — are purchases only you can authorise. They are the largest remaining
   close-up defects, and neither is a resolution problem (§6).

---

## 10. Residue / open items

- **Slot 0's albedo is the biggest remaining close-up defect** and is a source-asset problem (§3.1).
  Both data and constant fixes measurably calm it; neither removes the black shards.
- **Desert and tundra have no authored detail at all** (§3.2) — family swaps, on the director's
  side of the line.
- **Swamp and river never render** on this world (§3.3), so the swamp AO inversion fix is correct
  but not visually verifiable at any station here.
- **`OrbitCamera::set_yaw`/`set_pitch` do not set their smoothing targets** (§3.4) — every bookmark
  restore and `ViewportCameraPreset` silently drifts back within ~50 ms. Editor-health beat.
- **The hex random field repeats per chunk** (§4.2) — the de-tiling mechanism tiles with a 512 m
  period. Bounds what the exponent can ever achieve.
- **The normal downsample does not renormalize** (§4.1) — the root cause `NORMAL_XY_STRENGTH`
  compensates. Free next lever.
- **`shader_validation`'s vacuity guard fails pre-existing** (§8.2) — handed to the CI-workshop beat.
- Q4 (aux resolution) is **retired without a purchase** (§6). Q5 is answered as far as
  classification can answer it; the *reading* of it is T.3's (§5.5).

---

## 11. Commits

| phase | commit | what |
|---|---|---|
| 0 | `7dd08fc9f` | pinned-station A/B harness + `channel_stats.py` |
| 1 | `c0753b551` | cook root-cause fixes (16-bit clamp, AO inversion) + 3 slots re-cooked |
| 4 | `611c8edc7` | six production `expect()`s retired + CI invariant tests |
| 2.1 | `621d7b646` | `NORMAL_XY_STRENGTH` 1.8 → 1.4 (isolated) |
| 2.2 | `cb1d92a52` | hex weight sharpening `pow` 4.0 → 2.0 (isolated) |
| 3 | `344234924` | `TUNDRA_MAX_TEMP_C` 0.0 → −5.0 |

Trace bumps land with this note: `terrain_materials.md` v1.3 → **v1.4** (Invariant 8: no
placeholder aux channel, AO orientation), `terrain.md` v1.2 → **v1.3** (Invariants 8 and 9;
`expect()` retirement; the boreal band), `render_pipeline_material_system_shader_infrastructure.md`
v1.10 → **v1.11** (both constants measured and retuned; the "mip-gated" correction; Q4 retired).
