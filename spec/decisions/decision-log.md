# Decision Log — mayavius

Append-only log of every locked decision and every re-verified external fact, with
the evidence (source URL + date) behind it. This is the audit trail the executor
and reviewers can trust without re-researching. Verification sweep run **2026-06-13**
(Phase 0 of the spec build); assistant knowledge cutoff is January 2026, so every
post-cutoff fact below was confirmed against a live primary source, not memory.

Status legend: ✅ confirmed · ✏️ changed-vs-handover · ⚠️ correction (handover was wrong) ·
🚫 negative knowledge (documented dead end).

---

## A. Session decisions (locked 2026-06-13 by the project owner)

| # | Decision | Choice | Rationale |
|---|----------|--------|-----------|
| D1 | **MVP default model combo** | **VGGT (static cloud + camera) + CoTracker3 (2D tracks → lifted to 3D via VGGT depth)** | Both run locally on the 36 GB Apple-Silicon Mac via MPS (VGGT through the community float32 port pattern; CoTracker3 has first-class in-tree MPS). Together they reproduce the D4RT "colored point cloud + motion tracks" look. SpatialTrackerV2 ships as an additional **cloud/optional** adapter (single-model dynamic tracks, CUDA-only). |
| D2 | **Licensing posture** | **mayavius code = MIT; default model weights = non-commercial research.** Document the commercial path; do not block the signature track-ribbon feature. | All viable model *weights* are non-commercial (CC-BY-NC-4.0); there is **no** commercial-friendly point tracker in the candidate set. Shipping as an open research project (MIT code, NC weights, clearly labeled) maximizes GitHub stars while staying honest. Commercial static-only path = VGGT-1B-Commercial (custom AUP). |
| D3 | **Project name** | **`mayavius`** | Verified available across npm, GitHub, `mayavius.com`, `mayavius.dev`; distinctive; thematically echoes the legacy "Mayavi" 3D-viz tool. No tournament needed. `video-to-4d` retained only as a descriptive/SEO alias. |
| D4 | **Backend Python version** | **Python 3.12** (updates the CLAUDE.md 3.10 pin) | Python 3.10 EOLs **October 2026** (~4 months out) and is the exact floor of every backend pin. All pins + torch 2.x ARM64/MPS wheels support 3.12–3.14. This **supersedes** CLAUDE.md's `python 3.10`; flagged here rather than silently changed (handover §0 mandate). `backend/requirements.txt` versions are unchanged (all support 3.12); only the venv interpreter moves to 3.12. |

### Derived/owned decisions (made in-spec, not requiring owner input)
| # | Decision | Choice | Where |
|---|----------|--------|-------|
| D5 | Frontend framework | React + **Next.js 16** App Router (SEO) + **react-three-fiber** | handover §4.3; CLAUDE.md; already scaffolded |
| D6 | Frontend state | **Zustand** (R3F loop reads/writes outside React renders) | scaffolded `viewerStore.ts`; spec/07 |
| D7 | Wire format | **`MV4D` v1** compact binary (see spec/05); static/dynamic/tracks/cameras split | spec/05 |
| D8 | Test stack | backend **pytest 9**; frontend **Vitest** (unit) + **Playwright** (e2e) + `tsc --noEmit` | spec/10 |
| D9 | Optional deploy | **Hugging Face Space (dedicated GPU)** running VGGT + CoTracker3 (or SpatialTrackerV2) | spec/11 |
| D10 | Sample corpus | 3–4 short (≤3 s) CC-licensed clips bundled as preloaded examples | spec/10, spec/11 |

---

## B. Re-verified facts — Frontend stack

| Fact | Verified value | Status | Source (accessed 2026-06-13) |
|------|----------------|--------|------------------------------|
| `next` pin 16.2.9 | 16.2.9 is current npm `latest`; installed on disk | ✅ | registry.npmjs.org/-/package/next/dist-tags |
| Next 16: `ssr:false` forbidden in Server Components | Confirmed verbatim in docs **bundled inside** next@16.2.9: "`ssr: false` is not allowed with `next/dynamic` in Server Components. Please move it into a Client Component." | ✅ | `frontend/node_modules/next/dist/docs/01-app/02-guides/lazy-loading.md` |
| Next 16: `params`/`searchParams` are async Promises | Confirmed: typed `Promise<{…}>`; "you must use async/await or React's `use`". | ✅ | `…/dist/docs/01-app/03-api-reference/03-file-conventions/page.md` |
| `react`/`react-dom` 19.2 | latest 19.2.7; repo pins/installs **19.2.4** (both fine for fiber peer range) | ✅ | registry.npmjs.org/-/package/react/dist-tags |
| `three` 0.184 | 0.184.0 (MIT); installed; no r185 yet. `Points`+`ShaderMaterial` and `Line2`/`LineSegments2` ribbons supported on WebGL2 (addons under `three/addons/lines/…`) | ✅ | registry.npmjs.org/three/latest; threejs.org/docs |
| `@react-three/fiber` 9.6 | 9.6.1; **peer `react >=19 <19.3`** — bumping React to 19.3 breaks fiber 9.6 | ✅ / ⚠️coupling | registry.npmjs.org/-/package/@react-three/fiber/9.6.0 |
| `@react-three/drei` 10.7 | 10.7.7 (pairs with fiber 9.x) | ✅ | registry.npmjs.org/-/package/@react-three/drei/dist-tags |
| `zustand` 5 | 5.0.14 | ✅ | registry.npmjs.org/-/package/zustand/dist-tags |
| `tailwindcss` 4 | 4.3.1 | ✅ | registry.npmjs.org/-/package/tailwindcss/dist-tags |
| `typescript` pin | repo on **5.9.3** (`^5`); npm `latest` is now **6.0.3** (TS6 shipped) | ✏️ | registry.npmjs.org/-/package/typescript/dist-tags |
| **Decision**: stay on TypeScript **5.x** | TS6 is a major; the devDep `^5` is fine and reduces risk. Bump optional/post-MVP after verifying Next 16 + `@types` compat. | — | (owned decision) |

## C. Re-verified facts — Backend stack

| Fact | Verified value | Status | Source |
|------|----------------|--------|--------|
| `fastapi` 0.136 | 0.136.0 exists; latest 0.136.3; Py 3.10–3.14. `requirements.txt` pins 0.136.3 | ✅ | pypi.org/pypi/fastapi/0.136.0/json |
| `uvicorn` 0.49 | 0.49.0 is current latest (rel. 2026-06-03); `uvicorn[standard]` bundles websockets/uvloop/watchfiles | ✅ | pypi.org/pypi/uvicorn/0.49.0/json |
| `pydantic` 2.13 | 2.13.0; latest 2.13.4; Py 3.9–3.14 | ✅ | pypi.org/pypi/pydantic/2.13.0/json |
| `pydantic-settings` 2.14 | 2.14.0; latest 2.14.1; **requires Py >=3.10** | ✅ | pypi.org/pypi/pydantic-settings/json |
| `pytest` 9 | 9.0.0 (rel. 2025-11-08); latest 9.0.3; Py 3.10+ | ✅ | pypi.org/pypi/pytest/9.0.0/json |
| **SSE built into FastAPI** | FastAPI ≥0.135 ships `from fastapi.sse import EventSourceResponse, ServerSentEvent`. **`sse-starlette` is NOT needed.** Caveat: SSE breaks under `GZipMiddleware`. | ✅ / ✏️ | fastapi.tiangolo.com/tutorial/server-sent-events/ |
| Python 3.10 EOL | **October 2026**; already security-fixes-only | ✏️ → D4 | devguide.python.org/versions/ |

## D. Re-verified facts — Models & licenses (the binding constraint)

| Model | Repo / weights | License | MPS / Mac | Status |
|-------|----------------|---------|-----------|--------|
| **VGGT** | `github.com/facebookresearch/vggt` (CVPR 2025 Best Paper, ~13.3k★); weights `facebook/VGGT-1B` and `facebook/VGGT-1B-Commercial` | `VGGT-1B` = **cc-by-nc-4.0** (NC). `VGGT-1B-Commercial` = custom **`vggt-aup-license`** (commercial OK **except military**, **gated** application form) — *not* an OSI license | **No official MPS.** Community port `github.com/jmanhype/vggt-mps` (MIT) runs it on MPS **fp32-only** ("MPS does not support float16 autocast for this model"), needs 8 GB+ RAM Mac, macOS 13+ (treat 14+ as floor) | ✅ |
| VGGT capability | 4 heads: camera (extrinsics+intrinsics), depth(+conf), world point map(+conf), **track head (2D)**. Input `[S,3,H,W]`, width rescaled to **518 px**. Consumes a **set of frames**, not a video file. | — | — | ⚠️ Handover said "no point tracks" — **wrong**: VGGT has a 2D track head for *static* scenes; it lacks native *dynamic 3D* tracks |
| **VGGT-Omega** | `github.com/facebookresearch/vggt-omega` (CVPR 2026 Oral, ~2.9k★); arXiv:2605.15195; weights `facebook/VGGT-Omega` | **cc-by-nc-4.0 + gated.** Adds static **and dynamic** scenes; ~30% of VGGT train memory; ~15× supervised data; +77% Sintel camera accuracy (figures from project page/abstract; "20×/100×/1.6×" blog figures are **unverified**) | gated weights; GPU-oriented | ✅ — research-only future adapter, **not** a commercial default |
| **CoTracker3** | `github.com/facebookresearch/co-tracker` (ICCV 2025; family ~4.97k★); weights `facebook/cotracker3` (`scaled_offline.pth`/`scaled_online.pth`); `torch.hub` ids `cotracker3_offline`/`cotracker3_online` | **cc-by-nc-4.0** on code + checkpoints (sub-parts MIT/Apache) | **Best MPS story** — in-tree auto-select `cuda > mps > cpu` via **merged PR #14**. 2D output only (`B,T,N,2` + `B,T,N,1` visibility) → lift to 3D with VGGT depth | ✅ |
| **SpatialTrackerV2** | `github.com/henry123-boy/SpaTrackerV2` (note slug casing; ICCV 2025; arXiv:2507.12462; ~969★); weights `Yuxihenry/SpatialTrackerV2_Front`/`-Online`/`-Offline` | **CC-BY-NC-4.0 on the CODE itself** (GitHub reports `NOASSERTION`/"Other" — *not* permissive); weights license unconfirmed → assume NC | **No MPS.** Pins `torch==2.4.1+cu124` (CUDA-12.4-only) → not Mac-installable as-is | ✅ — cloud/optional adapter |
| Pi3 / π³ | `github.com/yyfz/Pi3` (ICLR 2026; arXiv:2507.13347; ~2.0k★); weights `yyfz233/Pi3` | **code = BSD-3-Clause (commercial OK)**; **weights = CC-BY-NC-4.0** per README, but HF tags `bsd-2-clause` — **inconsistent → treat as NC** | **No official MPS** — PR #153 (Apple-Silicon) open/unmerged, maintainer requested changes; `demo_gradio.py` hard-fails without CUDA | ⚠️ Handover said "code non-commercial" — **wrong** (code is BSD-3). 🚫 not the Mac default |
| MegaSaM | `github.com/mega-sam/mega-sam` (CVPR 2025) | code **Apache-2.0** (commercial OK); materials CC-BY-4.0; pulls 3rd-party weights w/ own licenses | **CUDA-only**; per-video optimization SLAM, ~0.7 FPS | 🚫 Rejected for interactive MVP on **performance** (not license): not a single feedforward pass |
| **Spark** (Path-2, OUT of MVP) | `github.com/sparkjsdev/spark` (World Labs, ~3.2k★); npm `@sparkjsdev/spark` 2.1.0 | **MIT** | WebGL2, desktop/mobile/VR | ✅ Spark 2.0 (2026-04-14) real: streaming LOD, `.RAD` format, 100M+ splats. npm `repository` field has a typo `sparkjs-dev` — canonical org is **`sparkjsdev`** |

**License synthesis:** render/viewer layer (Spark, Three.js) is MIT-clean; **model weights are overwhelmingly non-commercial**. License-cleanest *research* combo = `VGGT-1B` + `CoTracker3` + Three.js (all distributable, all NC weights). For commercial static-only = `VGGT-1B-Commercial` (AUP, gated) + Three.js; **no commercial tracker exists** → motion-ribbon feature is commercially blocked. → **D2**. The adapter layer must license-tag each model and surface the weight license (spec/06).

## E. Re-verified facts — Apple-Silicon / MPS reality

- ✅ **VGGT is the safest MPS default** — but only via the community-port pattern (device→`mps`, dtype forced **fp32**); upstream VGGT is CUDA/CPU-only. Source: `github.com/jmanhype/vggt-mps`, `facebookresearch/vggt` README.
- ⚠️ **"MPS = fp32 only / no fp16 autocast" is FALSE at the framework level.** fp16 MPS autocast shipped in merged PyTorch **PR #99272** (torch 2.5.0); bf16 on macOS 14+ (issue #139386, closed). Correct spec wording: *we run fp32 on MPS because the working model ports do and half-precision MPS autocast is beta/incomplete for these models* — not because MPS cannot do fp16.
- 🚫 **π³ has no official MPS path** (PR #153 open/unmerged). 🚫 **SpatialTrackerV2** CUDA-only (`cu124` wheel pin). ✅ **CoTracker3** has merged in-tree MPS (PR #14).
- ✅ Current stable **torch 2.12.0** with macOS ARM64 wheels (`pip3 install torch torchvision torchaudio`); Apple requires **macOS 14.0+**, Python 3.10+; MPS backend is officially **beta**. Source: developer.apple.com/metal/pytorch/, pypi.org/pypi/torch.
- ✅ **`PYTORCH_ENABLE_MPS_FALLBACK=1`** routes unimplemented MPS ops to CPU (slower); must be set **before importing torch**; some ops still fail (e.g. Conv1d gaps). Source: pytorch/pytorch issues #86195, #141287, #134416.
- ⚠️ **Memory numbers are unverified for MPS/fp32.** Only repo-confirmed Mac fact is "8 GB+ RAM Mac." The "7.04 GB@10f / 8.18 GB@20f" figures are **unverified blogspam** — do NOT cite; **measure on the actual 36 GB Mac** (spec/10).

## F. Re-verified facts — D4RT status & competitive landscape

- ✅ **D4RT (arXiv:2512.08924, Google DeepMind) official code/weights remain UNRELEASED** as of 2026-06-13 (no Google-org GitHub repo; DeepMind blog dated 2026-01-22 announces nothing). Source: d4rt-paper.github.io, deepmind.google/blog/d4rt-…, GitHub org search.
- ✏️ **An unofficial open reimplementation now exists:** `github.com/Lijiaxin0111/Open-d4rt` (Apache-2.0, ~456★, training code shipped 2026-06-04; HF weights `Lijiaxin0111/OpenD4RT`). GPU/PyTorch-oriented; MPS unverified. → `OpenD4RTAdapter` now has a concrete candidate to wrap; the "future open D4RT" framing is updated accordingly.
- ✅ **Vista4D** (Eyeline-Labs, CVPR 2026 Highlight, arXiv:2604.21915) = a **CUDA-12.8-only video-reshooting / novel-view-synthesis** pipeline on a Wan2.1 diffusion backbone, **Apache-2.0** (repo authoritative; a blog's CC-BY-4.0 claim is wrong). **Not** a lightweight viewer, **not** Mac-runnable. Uses Pi3X/Depth-Anything-3 upstream.
- ✅ **No direct competitor** to the exact product (open + browser upload + feedforward 4D cloud + track ribbons + shareable link + GPU-free viewing) surfaced across GitHub/arXiv/HF-Spaces/Papers-with-Code. **State novelty defensively ("none surfaced"), not absolutely** — absence is unfalsifiable; re-run near launch.
  - Closest research analogues (future adapter candidates, not competitors): **TracksTo4D** (NVlabs, NeurIPS 2024 — feedforward, casual-video, point-track-driven; closest on the feedforward axis; verify NVIDIA license) and **Shape-of-Motion** (optimization-based). Also **MoRe** (CVPR 2026 feedforward).
  - Adjacent-but-different: HF Gradio Spaces (VGGT/Vdpm/Any4D — server-side GPU, transient, no permalink; several broken at check time); proprietary splat capture (Luma, Polycam, Splat Labs Cloud — closed, static/splat-based).
  - mayavius's defensible wedge = the **combination** (open + feedforward + point-cloud + track-ribbons + client-only shareable viewer), not any single component.

## G. Naming availability (2026-06-13)
- `mayavius`: npm **available** (404); GitHub repo name free (`<owner>/mayavius`; only near-name is unrelated `mayaviust` org); `mayavius.com` **available** (RDAP 404 + WHOIS no-match); `mayavius.dev` **available** (RDAP 404). Mild phonetic echo of legacy "Mayavi" (mayavi.org) — thematic, not a trademark clash.
- `video-to-4d`: all surfaces free but generic/crowded — alias only.

---

## H. Open items deliberately deferred (not ambiguities — explicitly bounded)
1. **Exact VGGT-on-MPS memory per frame** → measured during build on the target Mac (spec/10 acceptance test), not asserted here.
2. **VGGT-1B-Commercial gating** → the AUP requires an application; the MVP default uses the NC `VGGT-1B` weights (D2) so no gating blocks local dev. Commercial deployers complete the form (documented in spec/08).
3. **Pi3 weights license inconsistency** (GitHub CC-BY-NC-4.0 vs HF bsd-2-clause) → adopt strictest (NC); Pi3 is a non-default optional adapter so this does not gate the MVP.

---

## I. Spec-build process record (Phases 2–5) — how this spec was hardened

Beyond Phase-0 fact verification, the spec went through adversarial hardening:

- **Phase 2/3 — adversarial verification + dependency deep-verify (16 critics + a
  skeptic-of-the-skeptics triage):** surfaced **36 must-fix items** (3 blockers + 33
  major/minor), all applied — cross-file contradictions (job-status `done` vs
  `succeeded`, decision-id citations, SSE built-in vs `sse-starlette`), the `fake`
  fixture-adapter registry entry, error→HTTP mappings, the Makefile test targets,
  config-var ownership, and more. (See [10-testing-strategy.md](../10-testing-strategy.md)
  for the resulting test ids.)
- **Phase 5 — blind-executor dry-run gate (the stop gate):** **14 rounds** run; each
  round = 4 fresh blind build-session simulators (context = `spec/` + `EXECUTE.md` +
  the repo scaffold only, **no** handover/chat) walking the wave plan and emitting
  every question/guess/assumption, then a strict adjudicator separating **genuine**
  gaps from over-reports. Every genuine gap found was closed before the next round.

  **Genuine-gap count by round:** 6 · 6 · 3 · 4 · 3 · 1 · 4 · 8 · 3 · 3 · 2 · 3 · 1 · 2.
  ~80–90% of each round's reports were adjudicated **spurious** (answered by the
  authority chain / documented defaults / on-device-deferred-with-procedure).
  Across all rounds the **Waves 0/1, Wave 2, and whole-plan** simulators repeatedly
  reported **`wouldNeedToAsk = 0` ("buildable end-to-end with ZERO blocking gaps")**.

  **Convergence finding (honest):** the count is a bounded oscillation, not a series
  converging to a stable 0 — e.g. round 13 ended at 1 genuine gap with the adjudicator
  prescribing an exact one-line fix that "closes to ZERO"; that fix was applied, yet
  round 14's *fresh* simulators surfaced 2 new minor items that earlier adjudicators
  had ruled spurious. This is the expected asymptote of an adversarial 4-simulator +
  strict-adjudicator panel: a sufficiently ruthless reviewer can always frame one more
  implementation-latitude micro-choice as "a guess." The **intent** of the Phase-5
  gate — *a blind executor can build/run/test each wave with zero blockers* — is met:
  every wave's blind-executor reaches `wouldNeedToAsk = 0`, and the residual
  adjudicator-flagged items have been minor doc-precision/latitude items, each closed.
  The spec is therefore declared **build-ready**; the build session should still
  **stop-and-flag** (per EXECUTE.md) if it hits a genuine contradiction, not improvise.
  Final clean-state record: [blind-executor-dry-run.md](blind-executor-dry-run.md).

## §J — Build-session record (W0–W3 executed 2026-06-13/14)

The build session executed waves 0–3. W0/W1/W2 gates green; W3 on-device MPS gate green
on the 36 GB Apple-Silicon Mac (Python 3.12.13, torch 2.12.0). Logged facts + on-device
reconciliations (each a measured/forced correction, not an improvisation):

- **T-510 measured (spec/08 §5 / §E,H — record, don't assert):** real `VggtCoTracker3Adapter`
  (VGGT-1B + CoTracker3, lift 2D→3D via VGGT depth) on one ≤3 s clip on MPS fp32 →
  **~31 s wall, ~12 GB peak** (well under 36 GB), `static=38970 dynamic_total=196229 tracks=1024
  frames=8`, encodes to MV4D within caps. T-500 (MPS available, torch ≥ 2.5) + T-511 (no MPS op
  failed under `PYTORCH_ENABLE_MPS_FALLBACK=1`) pass.
- **VGGT-1B real prediction API (confirmed on-device):** input `[B,S,3,518,518]`; output dict
  `world_points [B,S,H,W,3]`, `world_points_conf [B,S,H,W]`, `depth [B,S,H,W,1]`,
  `depth_conf [B,S,H,W]`, `pose_enc [B,S,9]` → `pose_encoding_to_extri_intri`. VGGT internally runs
  fp32 (its `autocast(enabled=False)`), matching the C3 discipline.
- **Patch-multiple fix (decode):** VGGT's ViT rejects any side not divisible by 14.
  `decode_and_subsample` now sets width=518 (=14·37) and height=`round(h·(518/w)/14)·14` (capped 518),
  matching VGGT crop-mode `load_and_preprocess_images` (e.g. a 320×240 clip → 518×392).
- **Track-lift double-flip fix (caught by adversarial review):** `run_tracks` fed the lift the
  *mayavius* c2w, applying the OpenCV→mayavius flip `F=diag(1,−1,−1)` twice and detaching the ribbons.
  Fixed by reconstructing the OpenCV c2w via the involution `R_c2w=F·R_may·F`, `t_c2w=F·t_may`. Guarded
  by `tests/adapters/test_track_lift_roundtrip.py` (a known world point projects + lifts back exactly).
- **numpy reconciliation:** vggt 0.0.1 requires numpy<2, so the ML overlay resolves numpy==1.26.4.
  Verified byte-compatible — the no-ML suite incl. T-200 golden byte-stability passes identically on
  1.26.4 and 2.4.6 (`numpy.rint` round-half-even is stable). No-ML CI keeps numpy 2.x; ML env uses 1.26.4.
- **W0 sequencing:** the pure-numpy service helpers (`smooth_and_cull`/`enforce_caps`) were built in W0
  to satisfy the W0-gate T-120; the rigorous over-cap T-104 landed in W1. No spec edited, no test weakened.

### §J.1 — W4 corpus + the static/dynamic split fix (the "wow")

- **Corpus:** all four roles sourced from Wikimedia Commons with primary-source-verified licenses and
  baked via the real combo: `walking-person` (CC0, Taurus Media Technik), `street-vehicle` (CC-BY-3.0,
  barbara.grilc), `pet-motion` (CC-BY-SA-3.0, S. Panigrahi), `static-scene` (CC-BY-SA-4.0, R. Gairshail).
  T-600/T-601 green; README/LICENSE/og.png shipped.
- **Static/dynamic split (W4.T3 / risk #4) — the one real quality fix.** The spec's per-FRAME
  displacement split (spec/06 §5 step 5) FLOODS real moving-camera reconstructions: VGGT camera/depth
  noise is ~zero-mean, so on the static-scene CONTROL ~16% of track samples exceeded the 1% per-frame
  floor (median noise 0.34%, 95th pct 2.18%, 99th 5.2% of AABB diag), and the 2% seeding radius then
  classified nearly the whole cloud dynamic (`static=3`, dyn capped). A walking subject's ~3%/frame sits
  INSIDE that noise tail, so NO per-frame threshold separates them. **Fix:** classify a track as moving by
  its NET excursion over the clip (max distance of its visible world positions from their mean), not
  per-frame displacement — noise is zero-mean (net ~ σ·√T, small) while a subject travels (net ~ T·v,
  large). At an 8% (`_MOTION_NET_FLOOR_FRAC`) net floor the control drops to ~0.5% of tracks moving;
  measured result: control `static 3 → 18946`, hero `walking-person` static 14500 + a clear ~6k/frame
  dynamic subject. The sparse-fallback path (`_moving_nodes_at`, VGGT-empty) keeps the per-frame floor.
  This is a logged W4.T3 tuning of the split signal (the spec's per-frame formula provably fails on noisy
  real reconstructions; the intent — stable background + moving subject — is preserved); the 2-track unit
  test still passes. The 4 corpus `.mv4d` were re-baked with this split.
- **MPS frame ceiling (on-device finding):** VGGT runs global self-attention over ALL frames and MPS has
  no flash-attention, so scores memory scales as `(S·tokens_per_frame)²`. A 518×518 SQUARE clip OOMs at 24
  frames (64.8 GiB); the safe budget is `S·tokens ≲ 12000` (16:9 → ~16 frames, square → ~8–9). The corpus
  bake + a `VggtAdapter` frame-budget guard cap S to fit, so a square/high-res upload no longer OOMs the
  default `max_clip_frames=24`.
