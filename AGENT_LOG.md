# FabMesh Agent Log

**RULE: I MUST read this file at the start of any session that touches
mesh quality, texture projection, or multi-view generation. I MUST append
to it after every experiment — success or failure. This prevents running
the same failed experiments twice.**

Most recent at the top. Each entry: date (YYYY-MM-DD), what was tried,
what happened, conclusion.

---

## Constraints (never forget)

- **Commercial target**: Gumroad / itch.io / Fab.com (NOT Steam)
- **Must be**: free, local, commercially licensable, **EU-safe**
- **User is in France** → EU licensing restrictions apply
- **Hardware**: RTX 5080 (16 GB VRAM)
- **Prefer French** in chat replies

## Licence status of tried/considered models

| Model | License | EU + commercial? | Status in FabMesh |
|---|---|---|---|
| Stable Fast 3D | Stability Community (<1M$/yr) | ✅ | Bridged, current default mesh pipeline |
| TripoSG | MIT | ✅ | Bridged (`local_triposg_bridge.py`) — user has used it |
| TRELLIS | MIT | ✅ but UNUSABLE | Bridge exists but **never managed to run** — don't retry |
| Hunyuan3D-2 | Tencent Community | ❌ EU excluded | Bridged but **not allowed** for EU release |
| Zero123++ v1.2 | Apache 2.0 | ✅ | Current multi-view generator |
| RealESRGAN x4plus | BSD-3 | ✅ | Upscales multi-views 320→1024 |
| RealVisXL V4.0 | OpenRAIL++-M | ✅ | Current image generator |
| IPAdapter Plus | Apache 2.0 | ✅ | Tried for multi-view, failed (see log) |
| IPAdapter-FaceID | Research only | ❌ NON-COMMERCIAL | Never use |
| xinsir ControlNet OpenPose SDXL | Apache 2.0 | ✅ | Not yet tried |
| Unique3D | MIT | ✅ | Not yet bridged — candidate |

## Texture pipeline reference state (2026-04-14)

Current scripts:
- `scripts/multiview_gen.py` — Zero123++ → 6 views → RealESRGAN upscale 320→1024 → rembg bg removal
- `scripts/texture_project.py` — per-pixel barycentric projection of all 7 views (input + 6 multi) onto mesh UVs, with hard-override blend against SF3D fallback
- `scripts/multiview_sdxl_gen.py` — SDXL + IPAdapter alternative (does NOT work well, see log)

Commits of interest:
- `515ca97` — looser UV filters + hard blend + bg removal on multi-views
- `c68344a` — per-pixel rasterization uses ALL 7 views (not just front)
- `bfb2aaa` — RealESRGAN 320→1024 upscale integration

---

## Log entries

### 2026-04-15 — Style-harmonize multi-views via SDXL img2img (commit `7c9225a`) — Solution 1

**User observation**: after regenerating the pipeline end-to-end on
test_e2e, the input image was photorealistic but the 6 Zero123++
multi-views came out with a cartoon/dessin look — atlas ends up with
incoherent style (photo front, cartoon back/sides).

**Why**: Zero123++ v1.2 was trained on Objaverse synthetic renders;
it imposes that style on whatever you feed it. Known limitation.

**3 options considered**:
 1. SDXL img2img style-transfer pass after rembg (light, commercial-safe)
 2. IPAdapter-guided multi-view gen (heavy refactor, also commercial-safe)
 3. Lower Zero123++ guidance_scale (5-min hack, inconsistent results)

**User chose 1 first; 2 as fallback if not enough.**

**Implementation** (`multiview_gen.py`):
- After the rembg bg-removal pass, each view is sent to the always-on
  SDXL server at `/img2img` with strength=0.35.
- Prompt = `<subject>, photorealistic, sharp focus, natural materials,
  consistent with reference photo, 8k detail`.
- Subject prompt comes from `prompts.json` via env var
  `FABMESH_REFINE_PROMPT` set by the bridge before spawning multiview.
- Alpha channel from rembg is preserved (reapplied after img2img so
  projection still knows which pixels are subject vs background).
- Falls through silently if the SDXL server is not up (no hard
  dependency, pipeline still produces raw Zero123++ views as before).

**Cost**: +30s (~5s × 6 views). Still within the 5 min budget.

**Ready to test**: user regenerates test_e2e end-to-end.

---

### 2026-04-15 — Bilateral-symmetry auto-align (commit `2eea5ea`) — drops the ±7° drift

**Root cause of the residual "décalage"**: the chest-bulge heuristic
was ~7° off optimal on real meshes because asymmetric surface features
(tilted head, diagonal sash, single pauldron, etc.) bias the mean
vertex-from-center direction.

**Validation on the pre-rotation test_e2e mesh**:
- chest-bulge (old): 176.86°
- bilateral symmetry (new): 169.75°
- Δ = 7.1° — exactly the order of magnitude the user saw as "pas loin
  mais il y a encore un décalage".

**New algorithm** (in `local_sf3d_bridge.py`):
1. Downsample mesh to 4000 vertices.
2. Coarse Y-rotation scan (2° steps, 0..180°) + fine (0.25° steps,
   ±3° around coarse best). Score = histogram-overlap between the
   rotated cloud and its x→-x mirror in a 64×16×64 XYZ grid.
3. Resolve front/back (180° ambiguity of mirror plane) via chest-z
   direction after rotation.
4. Apply only if >0.5° from identity.

Falls through to try/except with full traceback if any edge case hits,
so silent skip becomes impossible.

**Ready to test**: user to run a fresh generation on test_e2e. Expected:
face + multi-view back/sides precisely aligned (no ±2-7° residual).

---

### 2026-04-15 — Rotation-offset propagated to multi-view projection (commit `1965889`)

Follow-up to the auto-align fix: the rotation of the mesh (169.5° for
the apilive test) left the 6 Zero123++ views at their original
pre-rotation azimuths, so they bled onto the wrong parts of the rotated
mesh — visible as a slightly soft face + head and imperfectly aligned
side details.

**Fix** — `texture_project.py` now accepts `--rotation-offset DEG`; when
passed, every MULTIVIEW_VIEWS azimuth is shifted by that angle (modulo
360) so views land on the same mesh regions they depict. The bridge
(`local_sf3d_bridge.py`) captures `auto_align_rot_deg` at align time
and threads it through every `texture_project.py` invocation
(refine/atlas/atlas_refine/augment/vc paths).

**User verdict on the resulting mesh** (2026-04-15 evening): "on est
pas loin mais il y a encore un décalage". Face well-positioned overall,
shoulders/pectorals/pagne all correct, but face texture still slightly
off + buckle/sash positions drift a couple degrees.

**Root cause**: auto-align uses "average chest-bulge direction" which
has ±3–5° noise. The rotation offset compensates the alignment applied,
but if the alignment itself lands 2° off optimal, the multi-views get
offset by the same 2°. They don't hit the wrong side of the mesh any
more, but the ±2° residual drift is still visible.

**Next step** (in progress): replace the chest-bulge heuristic with a
**bilateral-symmetry-maximizing** rotation search. Humanoid subjects
(orcs, humans, animals) have a clean left/right mirror plane. Finding
the Y rotation that maximizes mesh-to-mirrored-mesh overlap lands
within ~0.5° of optimal, eliminating the drift. Scheduled for next
commit.

---

### 2026-04-15 — Auto-align WORKS (user visual confirmation)

Generated test_e2e_sf3d_apilive_1776274212.glb via direct CLI bridge call:
```
LOCAL_SF3D: auto-aligned mesh by 169.5° around Y (face was pointing [-0.182, 0.0, 0.983])
```
The orc's face was pointing ~dead-Z (away from glTF viewer). Rotation
brings it to -Z as expected. User confirmed visually: "l'orc est
parfaitement de face" in the FabMesh viewer — sash, buckle, armor on
thigh all visible in the right position.

Side note: CLI bridge runs bypass FabMesh's `mcp-job-start` event, so
no "Running task" dialog appears when bridged directly. Functionally
fine, just UX-different.

**Still to polish** (user mentioned): the face/head texture looks a
bit soft compared to the reference. Candidate next step: run the
ControlNet Tile refine with IPAdapter fed from the reference image +
multi-views, so SDXL has the actual orc identity to match when
injecting detail. Distinct task from fidelity (shape) which is now
solved.

---

### 2026-04-15 — Mesh auto-align to -Z (root cause of "texture inverted" on test_e2e)

**User symptom**: newly generated test_e2e mesh appeared as if the
texture was inverted front/back, and the back looked all black in the
FabMesh viewer.

**Investigation** (via `_check_orientation2.py` Python renderer, 4
cardinal views):
- GLB geometry is intact (same 19567 verts / 24576 faces as earlier
  working generations).
- `_proj_debug.png` generated at projection time shows the orc perfectly
  from the front — so `texture_project.py` IS projecting the correct
  view onto the correct part of the mesh.
- BUT the chest bulge (in-plane XZ component of chest-outward average)
  points at `(-0.606, 0, +0.795)` — face direction ~53° off any axis.
- FabMesh Three.js viewer spawns camera at `(+X,+Y,+Z)` looking at the
  origin. With the orc facing 53° in the (-X, +Z) quadrant, the viewer
  ends up photographing the orc's left side, not its front.
- Hence the impression of "inverted / back black" — the front IS painted,
  just not visible from the viewer's default angle.

**Fix** (commit `7f36fc3`): added an auto-align step in
`local_sf3d_bridge.py` right before `mesh.export`. Slices the
mid-body (30-80% height), averages chest-outward direction in the XZ
plane, and rotates the entire mesh around Y so that direction becomes
-Z (glTF "forward"). Skips if already within 3° to avoid numerical
drift. Applies to every SF3D generation, so the viewer + projection +
rig all see a canonically oriented mesh.

**Test plan**: generate a new test_e2e mesh → confirm the thumbnail
shows the orc from the front (or a 3/4-front), not from the side.

---

### 2026-04-15 — MAJOR COURSE CORRECTION — going back to fidelity-first

**User restated the #1 goal** (not a new requirement, the *original*
demand): *"je veux un mesh 3D qui soit le plus proche possible de
l'image initiale (shape et texture) → c'est la demande de base"*.

**Recognition**: I've been chasing SDXL refine quality for hours, but
every refine (v1 + v2 of CN Tile) was adding/changing pixels that have
**no relationship to the reference image**. The refine was never going
to fix fidelity — it was a purely stylistic layer on top.

**Real diagnosis — multi-views are silently not generating**:
- `logs/_multiview_*` latest folder is from 2026-04-14 23:01 (project
  orc_blue_crown). No multiview folder exists for today's test_e2e
  generation (12:12–12:16).
- `grep multiview logs/fabmesh.log` around 10:12–10:16 returns zero
  matches. The SF3D bridge's multiview step was skipped.
- SF3D received only the single reference image → no back/sides info
  → the atlas can only have front-biased texturing, with back/sides
  fabricated from SF3D's prior. This is **the real reason** the base
  mesh texture is weak, and no amount of refine can add back info the
  mesh never had in the first place.

**Immediate next steps** (pivoting away from CN Tile experiments):
1. Reproduce a mesh generation and capture EVERY log line to find
   where multiview is being skipped. `local_sf3d_bridge.py` has a
   try/except at line ~108 that silently sets `_multiview_dir = None`
   on failure — likely the culprit.
2. Once multiview is confirmed running again: verify the 6 views go
   through RealESRGAN upscale + rembg + feed into SF3D's atlas bake.
3. Then A/B the mesh with/without multiviews on the same reference.
4. Only after fidelity is verified: consider IPAdapter-guided refine
   that takes the reference image AND the 6 multiviews as conditions,
   so any refine stays aligned with the actual orc.

**FIX 1 applied** (commit `f61ecf0`): added `'refine'` to
`_modes_using_mv` in `local_sf3d_bridge.py`. Multi-views will now
generate again in the default refine path.

**FIX 2 applied** (commit `2f63b3f`): even with fix 1, the refine
branch was *ignoring* the generated multi-views. Refactored the refine
path into two steps:
 1. `texture_project.py --multiview` bakes the 6 Zero123++ views onto
    the SF3D atlas (same as 'atlas' mode)
 2. `texture_refine.py` then SDXL-polishes the *projected* atlas.
If projection fails, we gracefully keep the vanilla SF3D atlas.

**Test plan** (next run from user): generate a fresh mesh on the orc
reference → confirm `_multiview_*` folder appears → compare the
resulting mesh's back/sides with the reference image. Should now show
real multi-view data instead of SF3D's single-view prior.

**Hyper-SDXL 8-step LoRA work was started** (sdxl_server.py +
texture_refine.py branches) but **stashed** (`wip_hyper_sdxl_pause`) —
optimizing refine speed is useless while the base mesh isn't faithful
to the reference.

**Added to memory** (`project_core_requirement.md`): fidelity to
reference image (shape + texture) is FabMesh's #1 goal, everything
else is secondary.

---

### 2026-04-15 — ControlNet Tile SDXL atlas refine — FIRST RUN DONE (pending user visual verdict)

**Run 1 (failed at tile 1)**: auto-derived `steps=42` at strength 0.6,
each tile took ~250s → client timeout 240s. Fixed by pinning
`steps=25` for CN Tile + bumping HTTP timeout 240→600s (commit
`39dfd02`).

**Run 2 (success)**: `strength=0.6 cn_scale=0.7 steps=25 target=2048`
on `test_e2e_sf3d_1776247937665.glb`. Output:
`test_e2e_sf3d_1776247937665_cntile.glb` (same byte size — in-place
atlas swap kept GLB structure intact).
- Tile times: 177+72+65+58+71+57+52+23+17 = **596s total ≈ 10 min**.
  (1st tile includes 1-time xinsir/controlnet-tile-sdxl-1.0 download
  + load into VRAM ~2.5 GB. Subsequent tiles ~60s each.)
- VRAM peak ~15.3/15.9 GB (96%) — at the edge but no OOM.

**Speedup research (agents, 2026-04-15)**:
- **Hyper-SDXL 8-step CFG-preserved LoRA** (ByteDance, openrail++ with
  $1M cap): can drop to 8 steps × CFG 6 × strength 0.55 → ~25s/tile
  (-65%). Micro-detail softens slightly. Yellow-light for ship.
- **torch.compile**: theoretical +20% but recompile triggered on every
  pipe unload/reload (our server juggles 3 SDXL pipes on 16 GB), so
  net gain is negative. **Red-light — skip.**
- **Atlas 1024 default + RealESRGAN x2** (matches Meshy free tier):
  1 tile × 60s = **~70s total (-88%)**, better global coherence.
  **Green-light — biggest win, should be the default mode.**
- **Preset tuning**: strength=0.42 steps=18 cn_scale=0.75 CFG=5.5
  DPM++ 2M Karras — ~50s/tile (-30%), more visible micro-detail
  (lower strength lets CN Tile inject high-freq instead of being
  overridden). **Green-light — try before going LoRA.**

**Next decision** (pending user visual judgement on the 2048/9-tile
output): if quality is visibly better than vanilla refine, ship the
new default as 1024 single-tile + RealESRGAN x2 + preset
`strength=0.42 steps=18 cn_scale=0.75`. Add a "Max Quality" button
for 2048/9-tile when needed.

---

### 2026-04-15 — ControlNet Tile SDXL atlas refine — IN TEST

**Motivation**: user wants Meshy-quality texture; TRELLIS.2 is legally
unshippable (nvdiffrast NC); Hunyuan3D EU-excluded. Only commercial-safe
lever left is to push the existing SDXL atlas_refine harder.

**Problem with current refine** (`strength=0.25`, plain img2img):
- Too timid to add visible detail
- Bump strength above 0.3 → SDXL hallucinates and breaks UV layout
- No 3D-structure awareness — it repaints tile-blind

**Fix**: plug xinsir/controlnet-tile-sdxl-1.0 (Apache 2.0, commercial-safe)
into the refine pipeline. Tile ControlNet forces SDXL to respect the
source image structure while still adding micro-detail. This lets us
push `strength` to 0.5–0.75 without destroying the atlas layout — same
technique Meshy/Scenario use.

**Also fixed a stale bug**: `texture_refine.py` was pointing at
`http://127.0.0.1:7777/health` but the SDXL server binds 5555 and
exposes `/ping`. So `_server_alive()` always returned False → every
refine went through the slow in-process fallback. Corrected to 5555
+ /ping.

**New code** (commit `c456ec2`):
- `sdxl_server.py`: lazy-load `StableDiffusionXLControlNetImg2ImgPipeline`
  with xinsir/controlnet-tile-sdxl-1.0 + RealVisXL V4.0. Unload-with-others
  rule preserved to stay under 16 GB. Endpoint `/img2img_tile` accepts
  `strength`, `controlnet_scale`, `guidance_scale`, `steps`.
- `texture_refine.py`: flags `--controlnet_tile --cn_scale 0.7`,
  threaded through the whole call chain. Default strength 0.25 kept
  for back-compat; ControlNet test will use 0.6.

**Test plan** (pending): run on `test_e2e_sf3d_1776207309698.glb`
with `--controlnet_tile --strength 0.6 --cn_scale 0.7 --target 2048`
→ compare side-by-side with previous refine (strength 0.25, no CN).
User will judge visually.

---

### 2026-04-15 — TRELLIS.2 already installed in WSL — DIDN'T RUN (CUDA ABI mismatch)

Re-discovery: `local_trellis2_bridge.py` (170 lines) already exists in
`scripts/`, and `/root/TRELLIS.2` exists in WSL Ubuntu with a `.venv`
(python 3.12) and the official `example_texturing.py`. Module
imports cleanly (`from trellis2 ...`).

The bridge's docstring claims "works out of the box with ~14 GB VRAM
peak on RTX 5080" — so a previous attempt DID succeed once.

**Failure mode this time** (test on orc image, output to /tmp):
```
ImportError: ... flex_gemm/kernels/cuda.cpython-312-x86_64-linux-gnu.so:
undefined symbol: _ZNK3c1010TensorImpl15incref_pyobjectEv
```
flex_gemm 1.0.0 was pre-compiled against torch 2.6 (TRELLIS.2 README
explicitly recommends torch 2.6.0 + CUDA 12.4) but the venv has
torch 2.9.1+cu128. Pre-built CUDA extensions break across torch
minor versions.

**Why this happens repeatedly**: TRELLIS.2 ships its own custom CUDA
ops (flex_gemm, custom_rasterizer). They're tightly coupled to the
specific torch ABI they were built against. Any pip install/upgrade
in the venv that touches torch breaks them.

**Two ways forward**:
- A. `pip install torch==2.6.0 --index-url cu124` inside the venv
  (5 min, narrow risk — only the trellis2 venv affected)
- B. Recreate the venv from scratch via TRELLIS.2's official
  `setup.sh` (~30 min, cleanest)

**User instruction**: install it for real this time, log every step
to avoid going in circles.

**Attempt 1 (2026-04-15 ~10:35)**: downgrade torch in the venv to
2.6.0+cu124 to match the flex_gemm 1.0.0 pre-built wheels. Command:
`/root/TRELLIS.2/.venv/bin/pip install torch==2.6.0 torchvision==0.21.0
--index-url https://download.pytorch.org/whl/cu124 --upgrade`.

→ torch 2.9.1+cu128 → torch 2.6.0+cu124 OK. Re-tested
`import flex_gemm` — **STILL** `undefined symbol _ZNK3c1010TensorImpl
15incref_pyobjectEv`. The locally-installed flex_gemm 1.0.0 isn't
built for torch 2.6 either. Origin unknown — pip says "from local"
without source URL. Probably built earlier against an even older
torch.

**Web research (agent ad0a60f011a9cdcca, 2026-04-15)** — clarifies
the Windows landscape:
- ❌ Microsoft TRELLIS.2 has **NO official Windows wheels**. Repo
  has 0 GitHub releases, no `wheels/`/`dist/`, README explicitly
  says "tested only on Linux". The earlier agent #3 finding "wheels
  Windows officielles available" was WRONG.
- ❌ Native Windows build attempts (issue #4) fail for nvdiffrast,
  nvdiffrec, cumesh, FlexGEMM, o-voxel — `CUDA_HOME` errors even
  when set. No Microsoft maintainer has helped on Windows.
- ✅ **Community wheels Linux cu128** at
  `siraxe/TRELLIS.2-4B_cuda_12.8.r12.8_wheels` for python 3.12 —
  usable inside WSL on Blackwell (RTX 5080 / 5090). 3 wheels:
  `cumesh-0.0.1`, `flex_gemm-0.0.1`, `o_voxel-0.0.1`.
- ✅ Real working setup: WSL2 Ubuntu + python 3.12 + torch
  2.6.0+cu128 (or torch from siraxe wheel set) + the 3 community
  wheels above.

**Packaging consequence for FabMesh commercial release**:
TRELLIS.2 cannot be shipped as a Windows-native local app. End
users would need WSL2 installed (~5 GB extra). Three options
remain:
- (A) Bundle WSL2 + everything in installer — feasible but heavy
- (B) Cloud premium endpoint that we host — defeats "100% local"
- (C) Skip TRELLIS.2 — keep current SF3D + atlas_refine which is
  100% Windows native

User chose: install attempt continues to validate quality. If
TRELLIS.2 is visibly much better, decide packaging strategy after.

**Attempt 2 (2026-04-15 ~10:55)**: switch venv torch to cu128 + install
community Linux wheels. **PARTIAL FAILURE so far**:
- `pip install torch==2.6.0 --index-url cu128` → "No matching
  distribution". The PyTorch index has torch+cu128 only from 2.7.0
  onwards; 2.6.0 is cu124-only.
- Without --force-reinstall, the previous 2.6.0+cu124 stayed.

→ Pivot: use **torch 2.7.0+cu128** (lowest cu128 version available)
and hope the siraxe community wheels (built against cu128 around
2025-12) are compatible with torch 2.7's ABI. Wheel filenames don't
encode their torch version, so risk: same `_ZNK3c1010TensorImpl
15incref_pyobject` symbol mismatch all over again.

**Wheels downloaded** to `/root/trellis2_wheels/`:
- `flex_gemm-0.0.1-cp312-cp312-linux_x86_64.whl`
- `cumesh-0.0.1-cp312-cp312-linux_x86_64.whl`
- `o_voxel-0.0.1-cp312-cp312-linux_x86_64.whl`

**Result torch 2.8.0+cu128**:
- flex_gemm OK ✅
- cumesh OK ✅
- o_voxel OK ✅ (the SymBool symbol is in torch 2.8)
- ❌ **nvdiffrast** now breaks: `undefined symbol _ZN3c104cuda29
  c10_cuda_check_implementationEiPKcS2_jb`. nvdiffrast was built for
  another torch ABI.

Trying: rebuild nvdiffrast from source against torch 2.8
(`pip install --force-reinstall --no-deps git+https://github.com/
NVlabs/nvdiffrast.git`).

→ **Build wheel FAILED** (exit code 1, output truncated to 5 lines).
Verbose retry with `-v` also failed. Output too noisy to triage,
need to inspect the build log on disk.

`Trellis2TexturingPipeline` requires nvdiffrast at import time
(confirmed via direct `from trellis2.pipelines import ...`), so
this blocks the whole pipeline.

**Next**: capture the actual nvdiffrast build error.

→ Build error: `Cannot compile nvdiffrast CUDA extension. Run pip
install with --no-build-isolation flag`. Trivial fix.

→ Retried with `--no-build-isolation`: **NEW ERROR**
`nvcc fatal : Unsupported gpu architecture 'compute_120'`. The
WSL Ubuntu has nvcc 12.0 system-wide, but Blackwell (RTX 5080 =
sm_120) requires **nvcc 12.8+** to compile.

This is the real blocker. Three options:
- A. Force build with `TORCH_CUDA_ARCH_LIST=8.9` (sm_89, Ada
     Lovelace 4090) — Blackwell may run sm_89 binary by fallback.
- B. Install CUDA Toolkit 12.8 in WSL (~3-4 GB) — clean fix.
- C. Abandon TRELLIS.2 path entirely.

**Discovery**: CUDA Toolkit 12.8 is **already installed** at
`/usr/local/cuda-12.8/`. The `nvcc` symlink at `/usr/bin/nvcc`
just points to the older 12.0. Use the explicit path.

Retry with `CUDA_HOME=/usr/local/cuda-12.8`,
`PATH=/usr/local/cuda-12.8/bin:$PATH`, and
`TORCH_CUDA_ARCH_LIST=12.0` (Blackwell sm_120, RTX 5080 native).
This is option B without a download (toolkit was already there).

→ First retry FAILED — `wsl -- bash -c "..."` from Windows
explodes when env vars contain Windows PATH segments with spaces
(`Program Files`). The shell parser hits `(x86)` and dies.

→ Workaround: package the build commands into a `.sh` script
(`c:/tmp/_build_nvdiff.sh`), copy into WSL, run there. PATH inside
the script is set explicitly to Linux-only dirs.

Build now running with clean env. Compile time ~3-5 min for nvdiffrast.

→ **SUCCESS** 🎉 — `nvdiffrast-0.4.0-cp312-cp312-linux_x86_64.whl`
built and installed (15 MB wheel, sm_120 native).

**Full stack smoke test** passed:
- torch 2.8.0+cu128 ✅
- flex_gemm (siraxe wheel) ✅
- cumesh (siraxe wheel) ✅
- o_voxel (siraxe wheel) ✅
- nvdiffrast 0.4.0 (locally rebuilt for sm_120) ✅
- `Trellis2TexturingPipeline` import ✅

**Working recipe** (for reproducibility and packaging):
1. WSL2 Ubuntu with venv python 3.12
2. CUDA Toolkit 12.8 at `/usr/local/cuda-12.8`
3. `pip install torch==2.8.0 torchvision==0.23.0 --index-url cu128`
4. `pip install --no-deps` the 3 siraxe community wheels
   (flex_gemm, cumesh, o_voxel from HF)
5. `CUDA_HOME=/usr/local/cuda-12.8 PATH=/usr/local/cuda-12.8/bin:$PATH
    TORCH_CUDA_ARCH_LIST='12.0' pip install --no-build-isolation
    --no-deps git+https://github.com/NVlabs/nvdiffrast.git`

Next: `local_trellis2_bridge.py` on orc image, inspect quality.

**First real test launched** (2026-04-15 ~11:30): `Trellis2TexturingPipeline`
on orc mesh + no-bg image.

→ **FAILED** at pipeline load (before inference!):
```
OSError: You are trying to access a gated repo.
Cannot access gated repo briaai/RMBG-2.0
403 Client Error.
```

The texturing pipeline instantiates a `BiRefNet` rembg module on
from_pretrained (trellis2/pipelines/rembg/BiRefNet.py:10), which
tries to download `briaai/RMBG-2.0` weights — a **gated** HF repo.

**Licence caveat**: `briaai/RMBG-2.0` is under a research license
(not commercial-free). Even if we got access, shipping FabMesh with
RMBG-2.0 would violate our "commercial + EU-safe" constraint. Same
as IP-Adapter-FaceID (research-only, we excluded it earlier).

**Options**:
A. Patch `trellis2_texturing.py` to skip rembg_model when the input
   image has alpha (our no-bg inputs already do).
B. Monkey-patch to inject a no-op rembg.
C. Replace BiRefNet with our existing `rembg` (u2net, Apache-2.0).

Going with **B** for the test (fastest to validate quality) then
**C** for commercial viability if quality is worth it.

**Add to "do not retry"**: TRELLIS.2 texturing depends on
`briaai/RMBG-2.0` (gated + research license). Must be patched out
for any commercial usage.

**Attempt B (2026-04-15 ~12:10)**: monkey-patch `BiRefNet.__init__`
to a no-op before pipeline load (`c:/tmp/_trellis2_monkey.sh`).
Pipeline load **SUCCEEDED** in 27 s with the 4B weights (415/415
loaded, flex_gemm + flash_attn backends active). RTX 5080 / cu128
stack is fully functional.

**Next blocker**: `trimesh.load()` returned a `Scene` because
SF3D GLB has one geometry inside a node. Fixed by calling
`trimesh.util.concatenate(list(loaded.geometry.values()))` when
`isinstance(loaded, trimesh.Scene)`. Mesh became a 15269-vert /
19048-face `Trimesh`.

**Next blocker after that**: `AttributeError: 'DINOv3ViTModel'
object has no attribute 'layer'` in
`trellis2/modules/image_feature_extractor.py:86`. Cause:
transformers ≥4.41 wraps DINOv3 as `model.model.layer` (i.e. the
encoder is at `.model`, not flattened). Older transformers the
TRELLIS.2 code was written against had `.layer` directly. Patched
the extractor in place:
```python
_layers = getattr(self.model, "layer", None) or self.model.model.layer
for i, layer_module in enumerate(_layers):
    ...
```
Backup saved as `image_feature_extractor.py.bak_preLayerFix`.

**Add to "do not retry"**: don't trust TRELLIS.2's feature
extractor to work out of the box on current transformers. The
`DinoV3FeatureExtractor.extract_features` hardcoded `self.model.
layer` which is now one level deeper.

### 2026-04-15 — TRELLIS.2 — FINAL VERDICT: ❌ ABANDONED FOR FABMESH

After getting the pipeline to actually load (monkey-patch rembg + scene
concat + DINOv3 layer patch), the next error was `no kernel image is
available for execution on the device` from flex_gemm — the siraxe
community wheels were built for sm_89 (Ada), not sm_120 (Blackwell / RTX
5080). They work for imports but kernels don't launch on our GPU.

Web research (agent a227cd7a80731f3cf, 2026-04-15) found that:
- ✅ `visualbruno/ComfyUI-Trellis2` ships **Windows sm_120 prebuilt wheels**
  in `wheels/Windows/Torch270/` — would likely run on RTX 5080 in 10 min.
- 🚫 **nvdiffrast (hard dep of TRELLIS.2) is NVIDIA Source Code
  License-NC**: §3.3 "The Work and any derivative works thereof only
  may be used or intended for use non-commercially." The so-called
  "1-way commercial" exception covers NVIDIA itself, not us.
- 🚫 ComfyUI itself is GPL-3.0 — can't be bundled in a closed paid
  app without source-opening everything.

**Conclusion**: even with infinite engineering time, TRELLIS.2 **cannot
be shipped** in FabMesh commercial release (Gumroad/itch.io/Fab). The
non-commercial nvdiffrast clause is a hard legal wall, not a technical
one. All further TRELLIS.2 install work is **wasted time** for this
project.

**Add to "do not retry"**: TRELLIS.2 for FabMesh shipping. Full stop.
Even if the wheels work tomorrow and the output is photorealistic,
we cannot legally redistribute nvdiffrast binaries in a paid `.zip`.
Only viable future use: "Bring Your Own ComfyUI" mode where the user
installs ComfyUI themselves and FabMesh talks to `localhost:8188` —
but that's a separate feature, not now.

**Path forward (user-chosen 2026-04-15)**: double down on SDXL
atlas_refine (already commercial-safe, 100% Windows native). Next
experiments: tighter tile overlap, strength ramp per region,
ControlNet depth-guided refine to preserve geometry while repainting.

---

**Result torch 2.7.0+cu128 + community wheels** (previous attempt):
- `flex_gemm OK` ✅
- `cumesh OK` ✅
- `grid_sample_3d OK` ✅
- `o_voxel` ❌ — `undefined symbol _ZNK3c107SymBool14guard_or_falseEPKcl`
  (= `c10::SymBool::guard_or_false(const char*, long)`) — present in
  torch 2.8+, not in 2.7. So o_voxel was built against torch 2.8.

**Attempt 3 (in progress)**: bump to torch 2.8.0+cu128 + same wheels.
3 of 4 things now work; o_voxel needs the 2.8 symbol.
Note: pin between flex_gemm/cumesh ABI (2.7-compatible) and o_voxel
(2.8-required) is fragile — there might be no torch version where
ALL 3 wheels are happy at once. Will know in 1 minute.

**Add to "do not retry"**: don't trust agent claims about "wheels
Windows officielles" without verifying via direct GitHub release
listing — Microsoft TRELLIS.2 has none.

### 2026-04-15 — TRELLIS.2 install attempt — STARTED

**Why retry**: Earlier `AGENT_LOG` entry says "TRELLIS never ran, don't
retry". That was for **v1** (CUDA / nvdiffrast / kaolin issues on
Windows). **TRELLIS.2** released by Microsoft in Dec 2025 has
**official Windows wheels** for nvdiffrast 0.4.0 (cp311-cp311) per
the agent #3 research today.

**Goal**: install TRELLIS.2 from `microsoft/TRELLIS.2` repo, run
`example_texturing.py` on the orc image, judge whether it produces
PBR atlases that beat our current SDXL refine. If yes, bridge it as
a new mode `FABMESH_PROJECT_MODE=trellis2`.

**Backup**: `git tag before-trellis2-attempt` created so we can
revert any accidental damage to the working pipeline.

**Constraints**: must be MIT or Apache, EU + commercial OK, must
fit in 16 GB VRAM (v2 docs say peak 30 GB in rendering — risky on
RTX 5080, will need the 4B distilled checkpoint).

### 2026-04-15 — Post-refine saturation/contrast punch — DONE

User feedback on atlas_refine result: "la texture semble toujours
délavée". The orc identity was preserved (green skin, blue crown
on head only, brown armor) but colours were too pale.

**Fix**: PIL ImageEnhance.Color x1.25 + ImageEnhance.Contrast x1.12
applied right after SDXL refine, before atlas write-back. Non-
destructive on detail (keeps the micro-texture SDXL added) but
restores the chroma SDXL softens.

Pending visual check.

### 2026-04-15 — atlas_refine: 2-pass projection + SDXL refine — IN PROGRESS

**Premise** (user request): retry the multi-view UV projection now
that we have all the latest fixes (alpha-aware multi-views,
elevation-correct camera, NEAREST→trilinear filter, normal-map
preservation), then chain SDXL refine on top to clean the seams.

**New mode**: `FABMESH_PROJECT_MODE=atlas_refine` in
`local_sf3d_bridge.py`. Runs `texture_project.py` (multi-view
projection, EDT dilation) then chains `texture_refine.py` with the
subject-aware prompt at strength 0.22.

**Side fix**: `texture_project.py` was iterating ALL images in the
GLB and overwriting them — same bug as upscale_atlas/texture_refine
had — destroying the normal map. Now resolves baseColorTexture index
explicitly before writing.

**Status**: not yet visually validated.

### 2026-04-15 — Trilinear filter + preserve normal map — POLISH

**Problem**: when zooming on a mesh, user saw "carrés" (the actual
texels of the 2048 atlas in NEAREST filtering). Also asked if we even
had a normal map.

**Findings**:
- Normal map IS present in every SF3D-baked GLB (SF3D `system.py:508`
  exports `normalTexture=bump_tex`).
- BUT: `upscale_atlas.py` was iterating ALL images in the GLB and
  upscaling them — including the normal map. RealESRGAN trained on
  photos was flattening the XY components of the normal, killing the
  bump.
- `texture_refine.py` was always replacing `images[0]` — when SF3D
  ordered the normal map first, refine wrote SDXL's hallucination
  ON the normal map.

**Fix** (commit `0737124`):
- Both scripts now resolve baseColorTexture explicitly via
  `materials[0].pbrMetallicRoughness.baseColorTexture.index` →
  `textures[i].source` to find which image to touch.
- `_applyMeshTextureFilter` in renderer: NEAREST → LinearMipMapLinear
  + 16x anisotropy; covers normalMap/roughnessMap/metalnessMap/aoMap
  too (was only `mat.map`).

**Status**: visual validation pending. Should give clean trilinear
zoom + working normal-map relief.

### 2026-04-15 — Subject-aware refine prompt — IN PROGRESS

**Premise**: refine SDXL at strength 0.25 with default generic prompt
("photorealistic detailed surface texture") was hallucinating an ice
golem on the orc because the blue crown dominated the signal.

**Fix** (commit `5cc4f6b`):
- `local_sf3d_bridge.py` reads the latest entry from
  `images/<project>/prompts.json` and passes it via `--prompt` to
  `texture_refine.py`.
- `texture_refine.py` prepends the user prompt to the quality
  keywords so SDXL is anchored to the right subject.

**Verified manually**: standalone refine with prompt "orc warrior
with blue crown..." in 60s, atlas correctly refined.

**Bug found**: pipeline run does NOT produce a refined atlas —
`FABMESH_PROJECT_MODE=upscale` was lingering in the OS env from a
previous PowerShell `Start-Process`, so the bridge was using upscale
instead of refine. Restarted clean without the env var.

### 2026-04-15 — SDXL atlas refine (Meshy-style) — DEFAULT

**Approach**: pass SF3D's baked atlas through SDXL img2img (RealVisXL,
strength 0.25) tile by tile (1024 tiles, 128 px overlap, feather
blend). Hallucinates micro-detail (skin pores, fabric weave, fur)
without changing colours or UV.

**Files**: `scripts/texture_refine.py` (new), wired in
`local_sf3d_bridge.py` as `FABMESH_PROJECT_MODE=refine` (default
since commit `958b30d`).

**Result on poule_geante**: visibly sharper plumage detail (orange
striping, defined feathers) vs the upscale baseline. Cost: +60-90 s
per generation (in-process fallback when SDXL server isn't up).

**Subprocess timeout**: bumped 120 → 600 s (commit `b7905a0`) because
the in-process fallback loads RealVisXL ~6 GB on first call.

### 2026-04-15 — RealVisXL prompt: 3/4 view bias — DONE

**Fix** (commit `3be97b5`): added "three-quarter view showing one
side, slight rotation" to the optimized_prompt and "strict frontal
view, flat profile" to negative_prompt in `local_juggernaut_bridge.py`.

**Why**: SF3D textures only what the front shows and invents the
back/sides. A 3/4 source image exposes one side directly, so SF3D's
bake has real data instead of inventions.

**Verified**: prompts produce 3/4 chickens / orcs / camels reliably.

### 2026-04-15 — Multi-view ADDITIVE augment on top of SF3D atlas — REJECTED VISUALLY

**Premise** (user's idea): SF3D textures the front well from the source
image but invents the back/sides. Augment those by overwriting only
where a Zero123++ multi-view sees that surface better than the front.

**Implementation**: scripts/texture_augment.py. Per face: front_score
= front_vis, mv_score = vis * priority for each of 6 views. If max
mv_score beats front_score by `margin` (default 0.15), overwrite the
SF3D pixels of that face's UV triangle with the multi-view sample.
Wired as `FABMESH_PROJECT_MODE=augment`.

**Result on poule_geante**: 8264/16534 faces overwritten (50%). Mesh
came out with **blotchy patchwork** plumage — black/yellow/white
patches because each Zero123++ view has its own implicit lighting and
the seams between SF3D and overwritten zones are abrupt.

**Conclusion**: photometric mismatch between Zero123++ views and SF3D
makes additive augmentation visually WORSE than plain upscale.
Keeping the script (it works) but `upscale` stays the default mode.

### 2026-04-15 — Atlas-only RealESRGAN upscale — NEW DEFAULT

**Insight**: we kept replacing SF3D's native atlas (which has CORRECT
UV layout — SF3D made it). The replacement (multi-view projection)
is what created the mosaic. Just keep SF3D's atlas + sharpen it.

**New script**: `scripts/upscale_atlas.py`. Takes a GLB, finds the
embedded baseColorTexture, runs RealESRGAN x4plus on it, writes back
to the same GLB (rebuilds binary chunk). 15 s on a 2048 atlas.

**SF3D bridge**: default mode now `FABMESH_PROJECT_MODE=upscale`. The
old multi-view UV projection lives behind `=atlas`, vertex-color
behind `=vc`, no post behind `=none`.

**Smoke test on man mesh**: 2048 -> upscale x4 -> resize 2048. Subtle
sharpening but limited because input is already 2048. Real benefit
when SF3D bake at 1024 then upscale to 2048 or 4096.

**Status**: not yet visually validated by user end-to-end through
FabMesh.

### 2026-04-14 — InstantMesh as alternative texture-aware mesh generator — STARTED

**Why**: SF3D ceiling reached. All atlas-based projections (mosaic),
xatlas re-pack (mosaic), vertex coloring (15k verts → flou granuleux).
User suggested using a dedicated texturing AI.

**Audit of texturing/mesh AIs (EU + commercial constraints)**:
- ❌ Paint3D, TexFusion, Text2Tex, MeshAnything: research only or
  Tencent Community license
- ❌ Hunyuan3D-2: EU-excluded
- ✅ InstantMesh (`external/InstantMesh/`): Apache 2.0, takes Zero123++
  multi-views as input, generates mesh + texture in single forward pass
- ✅ TripoSR (already in repo via `local_triposr_bridge.py`): MIT, but
  texture native ~SF3D quality

**Next experiment**: bridge InstantMesh as alternative engine.
External repo present, CLI at `external/InstantMesh/run.py`, takes
`config + input_path` and exports OBJ/GLB. `--export_texmap` flag.

### 2026-04-14 — Vertex coloring pipeline (no UV atlas) — DONE, REJECTED VISUALLY

**Result**: GLB 660 KB (vs 4 MB atlas), pipeline 0.1 s. Code clean,
camera math correct, 97% of verts covered by multi-view, 478 fall
back to SF3D atlas.

**Visual**: smooth, no mosaic — but **flou granuleux**. SF3D's 15k
vertices = ~128×128 effective texture resolution stretched on full
mesh surface. Not enough density for fine details (face, ornaments).
**User rejected**.

**Conclusion**: vertex coloring is structurally limited by mesh
density. Would need ≥60k verts (subdivide + paint) to compete with a
2048 atlas.

**File preserved**: `scripts/texture_project_vc.py` (gated by
`FABMESH_PROJECT_MODE=vc` env var).

### 2026-04-14 — Vertex coloring pipeline (no UV atlas) — IN PROGRESS

**Why**: 3 agents diagnosed the fragmented-mosaic atlas. Agreed strategy
recommendation: bypass UV atlas entirely. Each vertex carries its own
RGB, Three.js interpolates linearly across faces — no island borders to
sample across, no EDT dilation, no xatlas tuning.

**Implementation**: `scripts/texture_project_vc.py` (new, parallel to
texture_project.py). Same camera math (Zero123++ schema with elevation
fix), but per-vertex single-winner-takes-all instead of UV rasterization.
Unseen verts fall back to SF3D baked atlas via UV lookup. Output GLB
carries COLOR_0 attribute, no baseColorTexture.

**Status**: script written, NOT yet wired into local_sf3d_bridge.py.
Needs end-to-end test on the orc.

### 2026-04-14 — Zero123++ camera elevation fix — REAL BUG, partial visual win

**Problem (found by 3-agent investigation)**: Zero123++ v1.2 produces 6
views at ALTERNATING elevations: azimuth=[30,90,150,210,270,330],
elevation=[20,-10,20,-10,20,-10]. Verified in
`external/InstantMesh/src/utils/camera_util.py:99-100`.

`texture_project.py` was treating all 6 views as pure Y-axis rotation
at zero pitch. Every non-front sample fetched from a vertically-shifted
pixel — back-of-head verts sampled the chest area in view_3, etc.

**Fix** (commit `672c14e`): added `rot_x(elev_deg)` to camera transform,
re-derived translation since it's no longer azimuth-invariant when
elevation != 0.

**Result**: math fixed BUT visual still mosaic at render. The other
half of the problem is SF3D's micro-island UV layout. Multi-agent
verdict: vertex coloring is the pragmatic next step.

### 2026-04-14 — xatlas UV re-pack — DOES NOT HELP, disabled by default

**Tried**: `xatlas.parametrize` to re-unwrap SF3D micro-islands into
big contiguous UV charts. Implemented in `texture_project.py`, gated by
`FABMESH_UV_REPACK` env var.

**Result on orc**: 15273 → 19707 verts (seams duplicated), 19048 faces
preserved, sharp_ratio 25% → 58%, BUT visual atlas still mosaic. xatlas
default `ChartOptions` produces per-triangle charts on this dense mesh.
Final rendering still bad.

**Conclusion**: not a silver bullet for SF3D meshes. Disabled by
default (`FABMESH_UV_REPACK=0` is now the default — set to 1 to opt
in). Could be revived with custom `ChartOptions(max_iterations=4,
normal_deviation_weight=2.0)` but vertex coloring is more promising.

### 2026-04-14 — EDT dilation atlas fill — WIN for coverage, NEUTRAL for visual

**Tried**: `scipy.ndimage.distance_transform_edt` to fill atlas pixels
with the nearest projected colour instead of falling back to SF3D blur.

**Result**: every atlas pixel now has a colour from our projection
(no SF3D blur leak), but on SF3D's micro-island layout this produces
the voronoi-mosaic appearance because EDT spreads each tiny island's
colour across the whole inter-island padding.

**Status**: still active. Helps when UV layout is good (TripoSG?).

### 2026-04-14 — Alpha-aware multiview input — SUSPECTED FIX

**Problem**: orc_blue_crown texture came out as a broken voronoi mosaic
(blue leaking everywhere, no recognizable silhouette in atlas, face
missing). Debug overlay showed projection math was correct.

**Root cause found**: `multiview_gen.py` opened the preprocessed input
and did `convert('RGB')` before saving `input.png`. That stripped the
alpha channel produced by SF3D's `remove_background`. When
`texture_project.py` later loaded that input.png to sample colours, it
had no alpha to gate with — so background pixels were sampled onto the
mesh, then EDT dilation smeared them across the full UV atlas.

**Fix**: preserve alpha end-to-end. If the input has no alpha, run rembg
on it (new code path). Save the RGBA result as input.png. Zero123++
still gets an RGB composite (paste on white).

**Expected**: atlas should now have clean silhouettes; background weight
is zero because texture_project.py already multiplies by src_alpha.

**Not yet visually verified by user** — needs a fresh end-to-end run.

### 2026-04-14 — Atlas 2048 + EDT dilation — WIN (needs user visual check)

**Tried**: two changes to `scripts/texture_project.py`:
1. Default atlas res stays 1024 but SF3D bridge already passes 2048 in
   production — confirmed on test mesh.
2. Replaced SF3D fallback blending with SciPy EDT-based dilation: unseen
   pixels take color from the nearest projected pixel, not from SF3D's
   blurry baked texture.

**Metrics on test "man" mesh at 2048**:
- sharp pixels: 226k @ 1024 → **907k @ 2048** (4× as expected)
- faces drawn: 8971/9788 (87%) → **9338/9788 (95%)**
- all 4M atlas pixels now filled (no black gaps)

**Conclusion**: atlas is fully populated by our projected color
(projected regions + EDT-dilated neighbors). No more SF3D blur leaking
into the final texture except where scipy unavailable (graceful fallback
still works).

**Still to verify**: actual FabMesh 3D render — user has not yet run a
full generation on this new code path.

### 2026-04-14 — SDXL + IPAdapter multi-view (Option 2) — PARTIAL FAILURE

**Tried**: `scripts/multiview_sdxl_gen.py` — RealVisXL + IPAdapter Plus + per-orientation prompts.
Per-view IP scales: right/left=0.35, back=0.55. Shared seed across views.

**Result on "man" prompt**:
- view_3 (back): ✅✅ **Perfect** — real rear view, same identity, clothes match
- view_1 (right profile): ❌ Still 3/4 front, just head slightly turned
- view_4 (left profile): ❌ Same — SDXL dataset bias prevents true 90° profile

**Conclusion**: IPAdapter alone cannot force true side profiles. Would need
ControlNet OpenPose on top, which adds ~1.5 GB models + fragility.
**DO NOT retry this without ControlNet.**

### 2026-04-14 — SDXL pure prompt + seed (Option 1) — FAILURE

**Tried**: same RealVisXL, no IPAdapter, just prompt+seed for 4 orientations.

**Result**: Each view was a completely different person with different
clothes (white shirt + jeans → gray T-shirt → shirtless in shorts for back).
Shared seed is nowhere near enough to preserve identity.

**Conclusion**: **Pure prompt steering is useless for multi-view texture.**
**DO NOT retry.**

### 2026-04-14 — Texture projection debugging — PARTIAL WIN

**Problem**: Generated 3D mesh had black/blurry face even though the 6
upscaled multi-views (1024 px each) were clean and sharp.

**Root causes found**:
1. Per-pixel rasterization only used `views[0]` (front) — any surface not
   visible from front fell back to SF3D blur. Fixed in `c68344a`.
2. UV filters (`min_edge > 0.5`, `aspect < 15`) rejected ~15% of faces
   including the entire face/hair region (SF3D packs these as tiny
   triangle strips). Fixed in `515ca97`.
3. Smoothstep blend weighted small triangles near zero. Fixed with hard
   override at 0.002.
4. Zero123++ output RGB gray background bled into projection. Fixed by
   running rembg on all 6 views after upscale.

**Measurement**: after fixes, 37% of atlas pixels differ from the
untouched SF3D texture (head + torso + limbs all covered). Not yet
visually verified in FabMesh 3D viewer by the user.

**Open question**: User reports visual result still unsatisfying. Unclear
if remaining blur comes from:
- PBR lighting in Three.js viewer (roughness/metallic rendering)
- SF3D fallback still dominating the ~60% of atlas pixels we don't touch
- Base SF3D atlas being a rendering ceiling

### 2026-04-14 — Zero123++ 1024 px upscale via RealESRGAN — WIN

**Tried**: upscale 6 Zero123++ tiles from 320 → 1024 via RealESRGAN x4plus.
Patched `basicsr/data/degradations.py` (torchvision.transforms.functional_tensor → functional).

**Result**: 6 views now 1024×1024, **visually sharp** (user confirmed:
"les images sont propres et pas flou"). Coût: +12 s per generation.

**File**: `scripts/multiview_gen.py` calls RealESRGAN before saving tiles.

---

## Things to NOT do again

- ❌ Retry IP-Adapter-FaceID (research license)
- ❌ Retry pure-prompt SDXL multi-view (identity drift)
- ❌ Retry TRELLIS (never ran)
- ❌ Ship Hunyuan3D-2 (EU excluded)
- ❌ Tune per-pixel UV projection on SF3D meshes — micro-islands make
  the rendered atlas inevitably mosaic regardless of projection quality
- ❌ Retry xatlas with default ChartOptions on SF3D output — produces
  per-triangle charts that don't help the rendering issue
- ❌ Treat Zero123++ multi-views as pure Y-axis rotations — they have
  alternating elevations +20°/-10°. Always include `rot_x(elev_deg)`
- ❌ Iterate ALL images in a GLB and run RealESRGAN/SDXL on them —
  this destroys the normal map. Always resolve baseColorTexture
  explicitly via `materials[0].pbrMetallicRoughness.baseColorTexture
  .index → textures[i].source`.
- ❌ Set FABMESH_PROJECT_MODE in the OS env "just for one test". It
  persists in the parent shell and overrides the bridge default for
  every subsequent FabMesh launch. Always set on the Start-Process
  invocation only, or unset after.
- ❌ Hardcode NEAREST filtering on Three.js material — kills normal
  maps, makes texels visible at zoom. Default trilinear + 16x aniso
  works once UV padding is good.
