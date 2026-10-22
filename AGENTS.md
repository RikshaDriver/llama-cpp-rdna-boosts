# AGENTS.md — working in this repo

This guide is for humans AND LLM coding agents. Read it before changing anything in
`~/llama-cpp-rdna-boosts/` (or acting on its behalf). It is deliberately short: policies, hard
invariants and pointers only. The dated record lives in `WORKLOG.md` (newest first) and `archive/`;
the pre-2026-10-04 AGENTS.md is preserved verbatim in `archive/docs/AGENTS-HISTORY.md`.

**Current state:** `release.json` is the single source of truth (fork point, canonical tip/tree,
block count, per-artifact sha256); the top of `WORKLOG.md` is the newest dated record. Do not restate
release history here — this file is the policy layer, not the log.

## What this repo is

A **delivery repo**. It packages the RDNA/ROCm work of the [`stew675/llama.cpp`](https://github.com/stew675/llama.cpp)
fork (`rdna-boosts` branch) as a **14-block set (V2.1)** (block 00 + blocks 01-13) that applies to a clean
llama.cpp checkout at the fork point named in `release.json`. This repo is NOT the fork: the fork
lives at `~/llama.cpp`; its `rdna-boosts` branch is re-cut from `patches/` on every release and
force-pushed to the personal fork so it never goes stale (see the Pushing policy). `patches/` is the
deliverable; `scripts/` is the apply/regenerate/validate flow; `README.md`
is the consumer overview; `MANIFESTS.md` is the apply order + verification contract, `BASELINE.md` the
provenance + drift policy (both are contracts now — their dated history is in `archive/docs/`);
`GREEDY-PURITY.md` is
the purity rulebook.

## Report findings before shipping (MANDATORY)

Surface review findings, open questions and small nits to the maintainer **before** any
delivery-affecting commit and **before** any release or tag, and wait for a decision. Do not bury them
in a commit message, a post-push summary or a GitHub reply. If something turns up mid-flight, stop and
ask instead of finishing the release and mentioning it afterwards. The maintainer decides whether a
finding is fixed now, deferred or dropped, and the decision is recorded (a `TODO.md` item, a block
amendment, or a note in the relevant record).

## Pushing policy (MANDATORY — read before any `git push`)

**Never push to upstream llama.cpp.** The only permitted push targets are this repo (the delivery,
`github.com:stew675/llama-cpp-rdna-boosts`) and the maintainer's personal fork
(`git@github.com:stew675/llama.cpp.git`). A bare `git push` in `~/llama.cpp` targets upstream
`ggml-org/llama.cpp` — never acceptable; repeated attempts can get the account banned.

- All deliverable changes live in THIS repo (`llama-cpp-rdna-boosts`) as the `patches/` set. That is
  the primary thing that gets pushed.
- **Every release MUST refresh the fork's `rdna-boosts` branch.**  Consumers clone the personal fork
  and check out `rdna-boosts` instead of applying the patch set, so a stale branch is what produced
  the 2026-10 Reddit "rdna-boosts is slow" incident (the branch was a month behind).  On every
  release (and whenever the block set changes), do a clean apply and push the branch:
  1. In a clean `~/llama.cpp`, check out upstream `master` at the **baseline point** — the `.base`
     commit in `release.json`, never the tip of `master`.
  2. Delete the existing `rdna-boosts` branch and re-create it with `scripts/apply-all.sh` (strict
     `git am`; the applied tree must equal `release.json`'s `.tree`).
  3. Build it and run the coherence + MTP gates and `scripts/gate-prefill-logits.sh`; `scripts/validate-set.sh` must be green.
  4. `git push --force-with-lease origin rdna-boosts` — the **personal fork only**, never upstream;
     never a bare `--force`.
- **Every release MUST also publish the ROCm container images.**  They are built and pushed
  **off-host** by the worker watcher (`scripts/container-watch.sh` on `radiance`), which polls for the
  new release tag and runs `scripts/build-containers.sh --rocm "7.14.1 10.1" --push --prune`; see
  `CONTAINERS.md` → "Offload the image build to a worker".  **Do not run the full container image build
  (all targets, both ROCm lines) on the primary box during a release**: it pins all cores for tens of
  minutes and contaminates any benchmark running beside it.  Nothing here changes the normal local
  **source** build for testing and development (`~/bin/build-llama-rocm`, Common tasks → "Build the
  fork"), which stays on the primary box.  The local `scripts/build-containers.sh` is for a smoke test or
  a manual worker-less container build only.  CI no longer builds them (the tag-push matrix took ~5 h and its failure mode was a cold
  retry).  The fork-branch refresh and the worker image push are both part of tagging a release.
- The `~/llama.cpp` checkout exists to host the block commits and to apply/test the diff set locally.
  Apart from the release-time branch refresh above it is disposable: delete the pre-patched branch and
  re-apply rather than editing history in place.
- Confirm the exact branch name and remote before any push: the branch is always `rdna-boosts`, the
  permitted target is always `git@github.com:stew675/llama.cpp.git` (the personal fork).
- Repeated attempts to push directly to llama.cpp can result in an account ban. When in doubt: don't
  push, ask.

## Layout

| path | what |
|------|------|
| `README.md` | consumer overview + workflow (start here) |
| `ENVIRONMENT.md` | **every environment variable** the delivery adds or repoints — default, and whether it is a kill-switch (default-on, set to disable), an opt-in, a tuning value or a diagnostic. Read it before adding a variable or changing a default |
| `release.json` | **delivery single source of truth** (fork point, canonical tip/tree, block count, per-artifact sha256) — read by `apply-all.sh`, `validate-set.sh` and CI; regenerate with `scripts/make-release.sh`, never hand-edit hashes |
| `MANIFESTS.md` | apply order + the verification contract (release gates, per-block verification, failure handling). Its dated validation history is in `archive/docs/validation-history.md` |
| `BASELINE.md` | fork point, what the patches are, how they are cut, drift policy. Its dated baseline/re-base records are in `archive/docs/baseline-history.md` |
| `TODO.md` | **forward-looking only**: open items, items waiting on someone else, accepted limitations, parked ideas. A closed item is one `WORKLOG.md` entry — never a TODO entry. `#NN` numbers are permanent handles and are never reused |
| `GREEDY-PURITY.md` | the purity rulebook (index + invariants + per-finding claims); dated narratives/evidence are in `archive/docs/GREEDY-PURITY-FINDINGS.md` under the same `§` numbers |
| `patches/` | **the delivery set** (0000-0013: block 00 + blocks 01-13) + `README.md`, the per-block reference (what each block contains, its knobs, its purity notes). The dated amendment notes moved to `archive/docs/patch-notes-history.md` |
| `scripts/` | `apply-all.sh` (the tested apply flow, strict tree check + `git am -3` fallback), `gate-prefill-logits.sh` (the prefill-logit KLD release gate, issue #113), `gate-per-block-build.sh` (a clean `all` build per block commit), `gate-qwen4exp-quant-coherence.sh`, `check-gpu-faults.sh` (reads the kernel journal and scans a llama log for **real** GPU faults, filtering the echoed prompt lines — never grep a log for `page fault`/`slab` by hand), `make-patches.sh`, `make-release.sh`, `validate-set.sh` (checksums + fresh-tarball strict apply, runs in CI), `build-containers.sh` (the image build itself), `container-watch.sh` (the off-host release watcher, run on `radiance`), `cleanup-ghcr.py` (GHCR version retention; called by `build-containers.sh --push`), `extract-generated.py` (hashes llama-cli generated text; a naive sed/grep slice does not reproduce the hashes), `check-windows-paths.sh` (fails on a path that Windows cannot check out). **Index: `scripts/README.md`** |
| `rdna-boosts-all.patch` | the entire 12-patch net as ONE patch (fork point only) |
| `benchmarks/` | dated bench records + methodology; **`mtp-adaptive-methodology.md` = the adaptive-MTP baseline gate** (run before shipping any decode/fusion change) and **`prefill-logit-methodology.md` = the prefill-logit KLD gate** (run before shipping any prefill-kernel change or release) |
| `prompts/` | versioned, hash-stable test prompts; sizes/token counts/**sha256** in `prompts/README.md`. A shipped prompt is **never edited in place** (add a new file); a result is only valid against the prompt hash it names |
| `wip/` | **ACTIVE** exploration docs/tools — **NOT part of the delivery**; see the WIP rule. Each campaign is a self-contained handover under its own `README.md` (no `wip/README.md`); the open set is indexed in `wip/CAMPAIGNS.md` |
| `beta/` | **promotion-candidate patches** staged for a beta test — **NOT part of the delivery**. Each candidate is `<name>/` with `README.md` (what/why/status), `BETA-TESTING.md` (the tester's apply + gate checklist) and `<name>.patch` cut against the current `release.json` tree. Nothing here is applied by default: `scripts/apply-all.sh --include-beta` applies `beta/*/*.patch` on top of the verified release tree for a tester. A confirmed or refuted candidate moves to `archive/work/` and is recorded in `WORKLOG.md` |
| `upstream/` | **upstream-PR candidates** (self-contained changes for unadulterated `ggml-org/llama.cpp`), one sub-directory per candidate (`README.md` + `UPSTREAM-PR-<name>.patch`); the index is its `README.md`. None is part of the delivery |
| `archive/docs/` | moved-out historical records (validation/baseline history, the pre-cleanup AGENTS.md) — reference only |
| `archive/work/` | closed experiments and campaigns, preserved for future re-evaluation (mmb/qsa3, moe-expert-cache, issues/PRs, …) — reference only |
| `baseline/*` branches, `block/*` tags | **historical** pre-block-12 checkpoints — do not use for the current delivery |
| `.github/workflows/` | `validate.yml` (per-push delivery validation), `release.yml` (tag-triggered GitHub Release assets) and `docker-ghcr.yml` (manual-only ROCm image fallback); fork point read from `release.json`. **The release container images are built and pushed off-host by the worker watcher (`scripts/container-watch.sh` on `radiance`), not in CI and not on the primary box** — see `CONTAINERS.md` |

## Scope policy — RDNA first, other backends uninjured

This repo is **RDNA/ROCm-specific**: validation, tuning and claims cover the AMD devices the
maintainer runs (gfx1201 = RDNA4, plus validated gfx1151/RDNA3_5 and gfx1100/RDNA3_0). The patch set
is generic llama.cpp, so it must not *break* other backends (NVIDIA/CUDA, MUSA, SYCL, Vulkan, CPU):
keep the shared CMake lists, dispatch tables and predicates mutually consistent even where a change
is unreachable on AMD. **Behaviour and performance on non-AMD backends are explicitly out of scope** —
no tuning, no validation, no waiting on hardware there.

- An AMD-only fix may land without its non-AMD counterpart as long as the non-AMD paths stay
  consistent (no aborts, no uninstantiated pairs) and the difference is documented (see the F1 chooser
  example in `upstream/fa-decode-verify-kernel-family/`).
- New KV-cache types / instances / predicates **are** kept cross-backend consistent — an inconsistent
  set is a crash on whichever backend reaches it (`GREEDY-PURITY.md` §20). That is correctness, not
  scope creep.
- "Not validated on NVIDIA" is an acceptable, documented state — never a blocker for an RDNA win.

## Default-on policy — beneficial features are ON; env vars only disable

A feature that improves performance (or correctness) and has passed the relevant QA gates is
**enabled by default**. An environment variable for such a feature exists **only to disable it** — for
A/B testing, bisection or debugging — never to enable it.

**Why:** the maintainer's validation boxes (Strix Halo / gfx1151 in particular) are much slower than
gfx1201, so a gate that silently runs without a beneficial opt-in wastes wall-clock time and reports
slow numbers as if they were the product (the `mmb`/HC16 campaign measured ~835 t/s for a session
when the full set is ~1136 t/s, +36 %).

- When a gate passes, flip the default **in the same change** and turn the old opt-in into an opt-out
  (`FEATURE=0`). Keep reading the env var; just invert the default.
- A feature that is beneficial but not fully gated is a reason to **gate it**, not to leave it off.
  Default-on with the risk documented, then run the gate.
- A kill-switch for a *correctness* risk (a bisect knob, a known-bad-state workaround) may stay
  default-off — the distinction is "on because it helps" vs "off because it is known-risky".
- Before any benchmark, use the full feature set. If you write `FOO=1 <bench>`, ask why the default is
  not already `1`.

## WIP and promotion rules (MANDATORY)

Everything under `wip/` and `archive/work/` (including loose patches/diffs and experiment trees) is
**experimental work, NOT part of the delivery**. Never apply a `wip/`/`archive/work/` item to the fork
or any llama.cpp checkout, and never fold its content into `patches/`, **unless the user explicitly
asks for that specific item**. WIP stays env-gated OFF and excluded from `patches/`; the sanctioned way
out is promotion: collect *validated* wins, give each an env kill-switch, re-validate the
**combination** (individual validations do not carry over), then cut a new block with the maintainer's
go-ahead. Anything also applicable to unadulterated upstream gets a copy under `upstream/`.

**`beta/` is the external-validation holding area, not a third kind of source.**  `scripts/apply-all.sh
--include-beta` is the sanctioned way to *test* one (it applies `beta/*/*.patch` after the release blocks and
reports the resulting tree); nothing in `beta/` is ever picked up without that flag.  A candidate that
cannot sit in `wip/` because it edits a file a block owns, but is not yet validated on the reporter's
platform, goes to `beta/<name>/` (a `README.md`, a `BETA-TESTING.md` and a patch cut against the
current `release.json` tree; nothing in it is applied by `apply-all.sh`).  On confirmation or
refutation it moves to `archive/work/<name>/` and is recorded in `WORKLOG.md` — same no-stub rule as
`wip/`.

**A finished campaign leaves `wip/` — it does not become a stub.**  The moment a campaign is promoted
(folded into `patches/`), closed, or refuted, its record moves to `archive/work/<campaign>/` and the
result is recorded in `WORKLOG.md`, then the `wip/` entry is **deleted** and `wip/CAMPAIGNS.md` is
updated.  Do **not** leave a "MOVED — see archive" placeholder behind: a redirect stub makes `wip/` claim
work is in flight when it is not, which is exactly the state this rule exists to prevent.  Dated records
(`WORKLOG.md`, `MANIFESTS.md`, `BASELINE.md`, `archive/`) keep the path that was correct when they were
written; when a campaign moves, fix those paths to the new `archive/work/` location rather than keeping a
stub alive to serve them, and treat a `wip/` path in an old record as a historical location.

## Critical facts (do not re-derive)

- **`llama-cli` MUST be run with `--single-turn`** (plus `--no-display-prompt` for scripted output).
  Without it, the interactive chat loop blocks forever. Wrap potentially blocking commands in `timeout`.
- **Apply method:** all 14 blocks with **`git am`**; `scripts/apply-all.sh` is the tested path. Plain
  `git apply` of the concatenated series **silently drops hunks**. Every block is a normal commit.
- **Naming (V2.1):** the current set is **14 blocks, 00-13** (`v14-097cf33d9-r109`).  Every `block NN`
  reference elsewhere in this file that is not one of the V2.1 numbers below is the **pre-V2.1 16-block
  numbering** and is kept as a historical handle.  The V2.1 map: **01** all-reduce, **02** adaptive MTP,
  **03** chunked GDN, **04** BF16 KV, **05** FA band/native/derived, **06** MMB, **07** k-quant,
  **08** fused kernels (fused MoE), **09** host-resident MoE (slab/cache), **10** slab + fusion dispatcher
  + async input ring (infrastructure), **11** qwen4exp (model/QSA/HC/lazy reader), **12** campaign
  remainder, **13** MTP draft vocabulary subset (opt-in).  V2.1 split r109's old block 10 in two: the
  **infrastructure stays 10**, the **qwen4exp architecture is 11** (QSA went with it by decision), so
  every pre-r109 "block 10" note about slab / dispatcher / async-input is still block 10 while a note
  about qwen4exp / QSA / HC / the lazy reader is now block 11.
- **Throughput is NOT a correctness signal.** Verify coherence (same-seed `llama-cli` diff, or
  `archive/work/tools/ar_kernel_unit.cpp`). Decode perf work is validated at **depth-16384**, not
  shallow `llama-bench`. **Never run parallel/background benches.**
- **A fresh-process comparison is only valid with `ROCBLAS_USE_HIPBLASLT=0`** (set it for that run, do not
  ship it).  On ROCm before the `rocm-libraries` fix (Linux 10.x included — 10.1.0's pin predates it),
  hipBLASLt picks its solution for an untuned FP32 GEMM size **per process start**, so two identical
  commands can produce different logits and a different gen t/s.  This is *not* a defect in this patch set
  (issue #67, external) but it **will** be misread as one: it was the entire residual of the 2026-10 MTP
  determinism hunt (3 logit classes in 18 fresh starts of one gemma4 MTP config; 10/10 with the env set),
  and it made every graph/capture arm look like a cause.  Attribute a per-start difference to the library
  before touching code; **never judge run-to-run determinism on a greedy text hash** — use a logit-level
  probe.  **Keep hipBLASLt enabled in the delivery** (disabling it costs up to -15 % decode; the switch is
  for reproducible runs and bisection only).  `GREEDY-PURITY.md` §44,
  `archive/work/fix-gemma-4/evidence/MEASUREMENTS-2026-10-21d.md`.
- **DFlash2 under `-sm tensor` is supported (r106, TODO #78 closed):** the selector's `ggml_top_k` /
  `ggml_get_rows` over the draft logits -- which are the *target's* `output.weight` projection, placed
  vocabulary-split -- are served by a new general collective **`GGML_OP_ALL_GATHER`** (`ggml_all_gather()`)
  that `build_dflash2_selector()` emits when the draft is a >= 2-device tensor split.  On the Meta backend it
  is `MIRRORED`, its own subgraph boundary, and dropped from every per-device child graph; the collective
  copies one row (of every dim above the split axis) at a time because a slice is contiguous in its own copy
  but strided in the full tensor.  **Only a plain axis-0 split is implemented** (anything else aborts by
  design), and there is no env knob: `-sm layer` is the escape hatch.  Mirroring the *drafter* does not work
  (the offending tensor is the target's), and neither does demoting only the drafter to `-sm layer` (a
  layer-split context cannot read the target's Meta-buffer weights).  Two related fixes ship with it: the F1
  `extract_layer_inputs()` device copy cannot express a Meta buffer (host path instead; it aborted for **any**
  DFlash drafter with `dflash.target_layers`), and the **slab narrow-2** pin must yield from the arena when
  the draft's compute buffer exceeds the unmapped VA spare (a tensor-split drafter's is 1280 MiB against the
  estimator's 512 MiB tier; without it `-sm tensor` + draft + `-ncmoe` aborts in `graph_reserve`).  Rule:
  `patches/README.md` (block 12, "Facts that span blocks").
- **Thread sizing is not optional.** `/usr/local/bin/pin_gpu_irqs.sh` puts the GPU IRQs on the top
  `NUM_GPUS` cores (13,14,15 with 3 GPUs); the default `-t` puts the worker pool there and starves the
  GPU (Q4_K_M `-ncmoe 99` tg1024: `-t 16` 19.6 vs `-t 8` 38.9). Size `-t` (or `--cpu-mask` with `-t`
  *inside* the mask) to leave those cores free; one CCD (8) is within 1-2 % of best. r19's block-06
  cap only covers `-ncmoe` offloaded-MoE decode; override with `GGML_CPU_MOE_OFFLOAD_THREADS=N`.
- **Our per-card host link is PCIe 5.0 x4, not x8/x16.** Each R9700 sits behind its own PCIe switch
  (`Navi 10 XL Upstream Port`): the GPU side negotiates **x16 @ 32 GT/s**, but the switch **uplink to the
  host** negotiates **x4 @ 32 GT/s** (`/sys/bus/pci/devices/0000:01:00.0/current_link_width` = 4; root
  ports `00:01.1` / `00:01.2` are x4 too). That is ~16 GB/s raw per card, **half** of a x8 host and a
  quarter of x16.  Consequences for measurement, measured 2026-10-17 on 35B-A3B Q4_K_M q8_0
  `pp31500`: 1 GPU 3614 t/s, 2 GPU tensor **4482 (+24 %)**, 3 GPU tensor **4347 (-3 % vs 2 GPU)**; the
  same +17 % / +1 % shape is in `wip/three-gpu-performance/` (1065 / 1246 / 1258 t/s).  So **multi-GPU
  prefill on this box is link-bound**, and a tensor-split prefill claim from a x8/x16 contributor host
  can only be *under-measured* here, not refuted: report it as "not measurable on our link", not as
  "does not reproduce".  Decode claims do carry over (the per-token AR traffic is tiny): #175's decode
  gain reproduced at 2-GPU tensor while its prefill claim did not.
- **`-ncmoe`/`-cmoe` host experts are always pinned (`ROCm_Host`); `--load-mode mmap` alone does NOT
  change that.** The loader rewrites the `-ncmoe` CPU override for a host `MUL_MAT_ID` weight to the
  layer device's **pinned** host buffer, and the "avoid a host buffer when using mmap" downgrade is
  skipped for it. The pageable `--host-experts mmap` mode and the legacy `LLAMA_MMAP_HOST_EXPERTS` env
  were **removed in r33** (issue #116: a no-XNACK GPU -- gfx1201 reports `XNACK enabled: NO` -- cannot
  read a pageable host master in a kernel, and the pageable fill faults `hipMemcpy2DAsync` on ROCm 7.14).
  `--host-experts` (`llama_model_params.host_experts_mode`) now selects **`pinned`** (default) or
  **`pool`** (r35, opt-in: a bounded pinned host pool over the page cache, `MOE_HOST_POOL_MIB`, default
  25 % of the MoE host expert bytes via `MOE_HOST_POOL_FRAC`); `mmap` logs "unsupported" and falls back
  to pinned. Pinned is deliberate -- the per-ubatch op-offload H2D upload and the expert-cache fill both
  read this master in place, and under `-sm tensor` a pageable master would land in the non-`is_host`
  `CPU_REPACK` (no device access, cache inert). Cost: the host expert set is non-swappable RAM (Q4_K_M
  35B-A3B `-ncmoe 40`, cache off: `ROCm_Host` 18662 MiB; peak RSS ~41.7 GB) unless the bounded `pool` is
  used. `--lazy-mode` governs the mmap *reader*, not this. `ENVIRONMENT.md` §§1.2.1/4;
  `patches/README.md` (V2.0 blocks 09-10).
- **MTP gates must be long and reasoning-pinned.** Use `-n 3000` (`-n 2000` floor), `--reasoning on`
  for R and `--reasoning off` for P/C/K. Short runs are a correctness smoke test only. Rule 0 in
  `benchmarks/mtp-adaptive-methodology.md`.
- **Prefill-logit purity is a release gate (issue #113).** Same-seed coherence and MTP are blind to a
  uniform prefill shift. Run `scripts/gate-prefill-logits.sh` before shipping any change to a prefill
  kernel (GDN/SSM chunked, FA, MMQ/MMVF/MMB, MoE prefill) or a default-on approximate path: it compares
  against a recorded known-good base and requires mean KLD <= 0.005 and same-top-p >= 98 %. The r29
  example: the default-on BF16 chunked GDN measured 0.032 / 93.6 % and was flipped off.  A
  **kernel-family switch** (a tile→WMMA head cap) uses `--family-switch` instead: it refuses a point
  outside the gate's calibrated domain (base PPL > 10; at a point the model finds hard even a benign
  same-kernel ubatch change measures 0.105 / 85 %) and always prints a same-kernel control, so the
  absolute limits stay the criterion without an insensitive point waving a bad change through.
  Protocol: `benchmarks/prefill-logit-methodology.md`, `GREEDY-PURITY.md` §46.
- **Mixed K/V cache types are HARD-REJECTED** at context creation (`params.type_k != params.type_v`);
  every mixed pair measured 1.7-3.6x slower and never smaller. Pass matching `-ctk`/`-ctv`.
- **The MTP draft-vocabulary trim is opt-in and draft-only (block 13, r107).**  `--spec-draft-mtp-vocab N`
  copies the LM-head rows for ids `< N` (+ control/user ids) into the draft context, scores the draft over them
  and scatters into a full-vocab row of `-inf`; the target still verifies the full vocabulary, so the trim can
  only lose proposals.  `0` = off = today's code path.  **N is payload-specific** (98304 on Qwen3.8-27B Q8_0,
  64000 is the reporter's gfx1151 value and a *loss* on our 27B, gemma4's only lossless cut is 245760/262144 =
  a no-op), it costs `N/n_vocab` of the head in VRAM (510 MiB at 98304, per device under `-sm tensor`) and it
  is **not** in the `--fit` estimate.  Gate purity at **`n_max <= 7`** (`GREEDY-PURITY.md` §48: the trim moves
  acceptance, which moves the adaptive controller's depth, which moves the verify widths); the shipped
  recommendation is `--spec-draft-n-max 7 --spec-draft-mtp-vocab 98304` (leave `--spec-draft-n-start` at its
  default 3 — it is the *initial* depth, not a ceiling).  **Check the device count before enabling it:** the
  subset head is *mirrored* per device under `-sm tensor` while the untrimmed head is *split*, so it pays only
  when **`N * n_devices < n_vocab`** — on the 27B 98304 is +1.4 % at 2 GPU (share 124160) and **-2.2 % at
  3 GPU** (share 82773, the server shape), and no N pays at 3 GPU.  The `ggml` half is the
  `ggml-backend-meta` row-range read that makes a vocabulary-split LM head readable piecewise.
  Record: `archive/work/spec-draft-mtp-vocab/VALIDATION-2026-10-22.md`.
- **`--spec-draft-n-max` is capped at 15** (the recurrent snapshot bound); purity is promised only to
  **7** (the kernel-family switch at 8 rows). `LLAMA_SPEC_DRAFT_N_MAX_CLAMP=0` escapes the clamp.
- **The mmvq band-uniform knobs are a purity requirement *and* a perf trap.** `nwarps` and the vec_dot
  VDR participate in the mmvq K-split order, so one value must hold across the whole band (`W=1..8`)
  and must be tuned at the **verify widths**. RDNA4 dense `nwarps=1`; dense VDR=2, MoE-expert VDR=4.
  The **pinned fusion ops (GDN/SSM, shared-expert, gate fusions) MUST keep plain `calc_nwarps`** — they
  are single-token reduction-order anchors. Run the stock-relative
  `llama-batched-bench -npl 1,4,8` gate (`mtp-adaptive-methodology.md` rule 5) before any decode/mmvq
  change. `GREEDY-PURITY.md` §§19/24/25.
- **The adaptive-MTP controller is the tuned bucketed one** (`v16-d1d3c3396-r2`): `delta = n_accepted -
  depth`, `climb_budget(d) = 20 + 6*(d-1)`, `drop_pressure(d) = max(60, 10*d)`, cold start
  `max(floor, cap-3)`, `--spec-draft-n-start N`. Judge any change on the four axes **and** the
  phase-switching `prompts/code-reasoning-mixed.txt`. Records:
  `benchmarks/2026-09-15-adaptive-mtp-tuning.md`, `archive/work/adaptive-mtp-ceiling-scaling/`.
- **FA instantiation discipline:** a FA kernel's KV *type* axis must be instantiated in the generated
  `template-instances/*.cu` files, never left implicitly in the dispatch TU (it gates the build).
  Check with `nm -C <obj> | grep -c <case>`: the dispatch TU shows `U`, the instance TUs `T`/`W`.
  Detail: `archive/work/build-time-regression/`.
- **The host-resident-expert device gather's head pad must match the host path**
  (`min(expert_size, 512)`; **64 is IQ4_NL-only**), keyed on `(input_cpy buffer, expert_bytes)`. Run
  `scripts/gate-qwen4exp-quant-coherence.sh` before changing `moe_cache_gather_host` or the head zero.
  Needs no `MOE_EXPERT_CACHE_MIB`.
- **A compute buffer that cannot grow must never abort; the MoE arena is what yields (r20).**
  `GGML_COMPUTE_BUFFER_MARGIN_PCT` (default **10**, `0` disables) pads each COMPUTE buffer allocation so a
  runtime graph's slightly larger layout (+3.3 % measured) does not force a free-then-allocate-larger
  **contiguous** block -- that needs a block *bigger than the one just released*, so free VRAM elsewhere
  (including a smaller arena) does not substitute. The slack is an opt-in buffer-type capability
  (`get_compute_margin_pct`), set only by the RDNA/ROCm path and aggregated (min) by the meta buffer type,
  so no other backend's allocation sizes change. `ggml_cuda_device_malloc` is the single allocation choke
  point: on OOM it frees the largest arena table, then the whole arena, and retries; a failed ramp leaves
  the cache disabled rather than aborting. Keep the two together. Related invariant: a partially-failed
  cache **falls back wholesale** (the fusion guard and `moe_cache_take_over` must agree), and no arena may
  be freed while a kernel that carries its address in its launch parameters is in flight
  (`moe_cache_sync_devices_locked`). `GREEDY-PURITY.md`/`archive/work/moe-cache-autosize/ARENA-UB-TENSION.md`
  §13-§14.
- **The movable-boundary slab is MoE-only and must stay that way (r37).** `ggml_cuda_slab_enabled()`
  returns `env_on && g_slab_armed`; `g_slab_armed` is set **only** by the MoE preflight
  (`ggml_backend_cuda_device_moe_cache_preflight`), which `llama_model_moe_cache_preflight` calls only for
  models with a non-empty `model->moe_host_expert_bytes` (`-ncmoe`/`-cmoe` > 0).  The slab exists to let the
  work region and the expert-cache arena coexist; with no arena it parks nearly all free VRAM in an unused
  region (measured ~18 GiB/GPU on a dense 27B).  The **compute chunk** (`GGML_COMPUTE_BUFFER_CHUNK_MIB`) is
  slab-motivated and is gated on the same condition.  Do **not** re-enable either for dense models; the
  dense regression is issues #118 (slab before the weights OOMs a 48 GiB card under `--mmproj`) and #120
  (the chunk cost a dense config +739 MiB and tipped it into shared memory).  The percentage margin
  (`GGML_COMPUTE_BUFFER_MARGIN_PCT`) is deliberately *not* gated (kept for dense).
- **An upload that writes a scheduler-managed buffer goes on the main stream (r62, block 10).**  The
  scheduler's `wait_before_overwrite()` (a wait on the previous split's event) guards the graph
  allocator's reuse of a split-input buffer and is enqueued on the **main** stream.  The compact
  splice-gather's 1-D H2D ran on `cuda_ctx->copy_stream()` and only ordered the *consumer*, so it could
  overwrite the buffer while the previous split still read it -- garbage/NaN for `-sm tensor` + `-ncmoe`
  on the below-gate path (35B-A3B, gemma4, Flash-Next GSQ).  A side stream is only safe with an explicit
  wait on the main stream recorded *before* this upload; the gather has no such need (it must wait for
  the reused-buffer read anyway).
- **The async graph-input ring (`GGML_CUDA_ASYNC_INPUT`) is opt-in and a run is not start-to-start
  deterministic when the consumer is a captured HIP graph** (r69; re-characterised 2026-10-19).  `-ub 8`
  and `-ub 1` self-KLD comparisons diverge with `n_seq = 1`; `-ub 512` and `GGML_CUDA_DISABLE_GRAPHS=1`
  are bit-identical.  **The cause is NOT the ring**: the uploads verify byte-correct at the graph's first
  read, HIP's wait-before-replay / event-after-replay ordering is correct, and consecutive graphs do not
  overlap — so the async path is the *trigger* (it removes the per-copy host block), not the defect.
  **FIXED in r90 (TODO #73 closed)**: the defect was `ggml_backend_cuda_set_tensor_async` /
  `_set_tensor_2d_async`, which issued a pinned-source `cudaMemcpyAsync` **straight from the caller's live
  host pointer** while the scheduler uses that path for a host-resident split input -- a CPU split's
  output that the next ubatch rewrites in place -- so with the host running ahead the copy could read the
  next ubatch's bytes (a rare single-graph corruption that propagated to the end of the chunk).  Both now
  snapshot through the pinned upload ring, unconditionally, and the ring's wait/done guard is
  unconditional; `GGML_CUDA_ASYNC_INPUT` is **default-on** (`=0` disables) and the batched uploads
  (`GGML_CUDA_ASYNC_INPUT_BATCH`, r89/PR #182) stay default-on inside it.  Self-KLD control 91.0-95.1 %
  -> 99.967-100.000 %; decode +9.3 % (35B-A3B 2 GPU tensor tg400) / +5.2 % (27B MTP n3 end-to-end).
  Evidence: `archive/work/async-input-graph-ordering/` (`RESOLUTION.md`, `FINDINGS-2026-10-19b.md`).
- **The op-offload H2D staging ring (V2.0 block 09; old block 06, r12) has three invariants:** (1) prefill is never
  CUDA-graph captured, so a redirected split input that reaches a copy path aborts (tripwire asserts
  this); (2) the width gate is floored at **64 tokens**; (3) the arena lives **outside** the
  compute-graph reserve, so a failed allocation disables staging instead of aborting, and a partially
  staged ubatch is never allowed. Under `-sm tensor` the meta backend owns one ring per device and
  `MIRRORED` tensors must serve arbitrary byte ranges. The expert weights themselves are **split** per
  device, not mirrored (`GGML_META_SPLIT_COPY=1`; each cache table holds `expert_bytes = host_bytes/2`,
  measured 2026-10-07), so any `-sm tensor -ncmoe` vs `-sm layer` gap is the per-op upload/pruning
  machinery, not weight duplication. (`TODO.md` #44 was closed on that finding; see
  `archive/work/expert-cache-split/`.)
- **Cross-device split inputs (V2.0 block 09; old block 06, r12):** a device-to-device input copy runs on the SOURCE
  backend's stream, so `wait_before_overwrite` (which only orders the destination stream) is not
  enough; the block records a fresh event on the destination backend and makes the source wait on it
  before the copy. Without it, `-sm layer` on 2 GPUs with host experts (`--n-cpu-moe` >= 29) can
  overwrite an earlier split's output before its outbound copy reads it (garbage prefill);
  `GGML_SCHED_EVENTS=0` is the old workaround. Issue #103, contributor PR #104,
  `archive/work/2gpu-sched-fixes/VERIFICATION.md`.
- **The QSA op has a CPU oracle** (`test-backend-ops -o FLASH_ATTN_QSA`, 18/18 minimum). The `W=1..8`
  matrix is **blind to a width-uniform corruption**, and MTP acceptance is not a quality signal when
  draft and target share the defect; use the perplexity ratio vs the dense masked path
  (`LLAMA_QSA_SPARSE_FA=0`). A fused op with several heads sharing a staging buffer must keep the block
  homogeneous in every index the staging reads (QSA: the K/V head). `GREEDY-PURITY.md` §21.
- **Block 03 (GDN; old block 02):** the chunked prefill is K-independent with threshold `max(K>16?K:16, n_rs_batch)`,
  `n_rs_batch = common_speculative_n_max()+1`; `GGML_CUDA_GDN_CHUNKED=0` forces the sequential kernel
  (correct, bit-identical, slow). The pure `none == draft-mtp` range is `n_max <= 7`.
  `GREEDY-PURITY.md` §27, `WORKLOG.md` 2026-09-12.
- **The rollback bound is enforced by `n_rs_batch`, not observed — do not re-derive it.**  `common`
  sets `cparams.n_rs_batch = common_speculative_n_max() + 1` over **every** speculator type (draft
  simple/mtp/adaptive/eagle3/dflash/dspark *and* ngram simple/map/mod/cache, so ngram-mod's default
  n_max 64 gives 65), `llama_context` floors it at `n_rs_seq + 1`, and `delta-net-base` passes it as
  GDN op param 1.  The op's threshold is floored at it, so a **speculative verify batch can never take
  the chunked path** and always restores snapshots it wrote (r91; the campaign's "ngram is an exposure"
  claim was wrong).  The r91 sequential tail (`GGML_CUDA_GDN_TAIL`, block 10) then covers the remaining
  source of a partial rollback: a **non-speculator** rewind into a prefill batch (server cancel /
  `--cache-reuse`).  The per-sequence tracker is block 03's (`prepare()` folds in every ubatch;
  `LLAMA_RS_ROLLBACK_DEBUG=1` shows `RSPREP`/`RSROLL`).  Record + probe:
  `archive/work/rs-rollback-boundary/`.
- **Test baselines are per box *and* per model: never compare to a number in this file.**  E.g.
  `test-recurrent-state-depth` on Qwen3.6-35B-A3B-UD-Q3_K_M: **130** failures on gfx1201, **153** on
  gfx1151; the gate is that the per-arm FAIL/PASS set is unchanged, not that the count is zero.  Run it
  (and any other GPU test) **alone** — two GPU jobs at once changes the arena/band layout and invents
  failures.
- **Block 01 (all-reduce; old block 12):** the `GGML_CUDA_AR_PROFILE` device-list init fix; on the first NCCL runtime failure the
  comm layer warns once, disables NCCL and re-routes to the internal pipeline/butterfly.
  `GGML_CUDA_ALLREDUCE=nccl` is **NOT bit-identical** under `-sm tensor` (the internal AR BF16-round-trips).
- **Block 08 MTP regression fixes (old block 13):** the dense K-split kernel for verify batches, and the
  rms_norm->mmvq Q8_1 fold gated to single-token MMID + plain `MUL_MAT`. **Purity ranks above raw
  non-MTP throughput.** `GREEDY-PURITY.md` §19.
- **MoE decode/verify is byte-identical by default:** the fused shared-expert band serves
  `1 <= nt <= 8` with `nwarps` pinned; `GGML_CUDA_DISABLE_SHEXP_DOWN_GATE=1` is the A/B kill-switch.
- **The r25 tensor-split fold (PR #106 minus its patch 0002) has three invariants to keep together:** a
  retired **Q8_1 arena must outlive captured graphs** (`GGML_CUDA_Q8_1_ARENA_FREE_OLD=1` restores the
  `quantize_q8_1` page fault); a graph is **recaptured when the pool / FA-staging / H2D-ring memory it
  captured is freed** (`GGML_CUDA_GRAPH_MEM_GEN=0` disables); and the **meta split-state cache keeps 8
  versions with compact entries** (`GGML_META_SS_VERIFY=1` verifies hits).  **PR #106 patch 0002 (the
  data-pointer graph key) is deliberately NOT in the delivery**: on the r22+ movable-boundary slab the
  per-device allocations vary between otherwise-identical calls, so the extra key invalidates warm graphs
  and recaptures (measured -19 % `-sm tensor` MTP at `--spec-draft-p-min 0.5`, with identical text and
  acceptance).  Re-cut it against the slab before revisiting.  `TODO.md` #46, `WORKLOG.md` 2026-10-07 (r25).
- **A captured graph is only valid while the slab work region's layout is unchanged.**  The work region is a
  movable boundary: at the post-prefill drop the narrow re-reserve shrinks it and the bytes above the new
  boundary go back to the MoE arena.  A captured CUDA/HIP graph bakes the work-region addresses into its
  executable graph, so the shrink **must** bump `ggml_cuda_graph_mem_freed(device)` (block 10,
  `ggml_cuda_slab_work_alloc`) — otherwise a later replay reads released memory.  Issue #187: a 4-stream MTP
  decode replayed a graph whose KV `set_rows` source indices pointed into the released wide region and
  faulted with `HSA_STATUS_ERROR_MEMORY_APERTURE_VIOLATION`; `GGML_CUDA_DISABLE_GRAPHS=1` hid it.  Every
  shrink path taken at a drop still needs this; add it wherever a new one is introduced.
- **The deepseek4/glm5-next `DSV4_HC_POST` arm is split-mode dependent (r97).**  `cparams.fused_dsv4_hc_post`
  is the fused **op** whenever a Meta (tensor-split) device is in play and the primitive
  `hc_combine_norm` chain on one device.  The chain is faster on one device (+0.9..+1.8 % prefill,
  gfx1151) but is **not correct across a tensor split**: `test-llama-archs -a deepseek4` on 3x gfx1201
  read NMSE 1.74e-01 through the chain vs 6.5e-06 through the op.  Do not make the chain unconditional
  again without fixing its split-state handling; `LLAMA_FUSED_DSV4_HC_POST` forces either arm.
- **A host buft with no device is never accounted as host experts (r97).**  `ggml_backend_cpu_buffer_type()`
  has `.device = NULL` upstream; the account map, the slab, the H2D ring and the expert cache all need a
  **pinned** master read in place by a device kernel, so a pageable placement (CPU-only, or
  `--override-tensor exps=CPU`) is left to the upstream `llama_moe_cache` engine.  Keying a null device
  aborted in `ggml_backend_dev_memory()`; keying the layer's device reserves a ring/arena the path cannot
  use.  `patches/README.md` (block 09).
- **Dense greedy purity:** `plain == draft-mtp` greedy text is kept for **f16/bf16/q8_0**; the coarse
  quants (q4_0/q4_1/q5_0/q5_1/iq4_nl) are relaxed to the **logits level** (argmax preserved, top-2
  margin >= 2.2). The FA chooser is TILE across the whole band. Re-run the 8-type x 5-length grid when
  a single-token-tuned kernel changes. `GREEDY-PURITY.md` §36.
- **The high-power pin regressed** (`~/bin/high-power`: tg -5-7 %, pp -15-18 % on RCCL/hybrid paths).
  Servers run **unpinned**, 3-GPU (`HIP_VISIBLE_DEVICES=0,1,2`), hybrid default.
- **The set applies whitespace-clean** (`apply-all.sh`, no git whitespace warnings).

## Common tasks

### Apply the set to a fresh llama.cpp checkout

```bash
git clone https://github.com/ggml-org/llama.cpp && cd llama.cpp
git checkout <release.json.base>
bash <this-repo>/scripts/apply-all.sh .     # creates branch rdna-boosts, 14 commits

# with the beta candidates on top (NOT the release tree; for a beta test only)
bash <this-repo>/scripts/apply-all.sh --include-beta .   # 14 blocks + beta/*/*.patch (15 commits)
```

### Verify (the coherence gate — mandatory after any change)

Local models live under `/llm/models/` (e.g. `Qwen3.5/4B/Q8_0/...`, `Qwen3.8/27B/Q4_K_XL/...`,
`Qwen3.6/35B-A3B/Q8_0/...`, the Gemma4 tree). Paths in older docs are host-specific; resolve them
against `/llm/models/`.

```bash
HIP_VISIBLE_DEVICES=0,1,2 ./build/bin/llama-cli -m /llm/models/Qwen3.5/4B/Q8_0/Qwen3.5-4B-Q8_0.gguf \
  -ngl 99 -sm tensor -mg 0 -p "The capital of France is" -n 20 \
  --seed 42 --temp 0 --no-display-prompt --single-turn
```

Diff against a known-good build: same-seed output must be IDENTICAL. `GGML_CUDA_ALLREDUCE=nccl` is not
a bit-identical reference under `-sm tensor` (see Block 01 above); treat it as a smoke comparison.

The coherence gate is a decode/greedy check and is **blind to a uniform prefill-logit shift**. For any
change to a prefill kernel (GDN/SSM, FA, MMQ/MMVF/MMB, MoE prefill) or a default-on approximate path,
run the **prefill-logit gate** as well:

```bash
./scripts/gate-prefill-logits.sh          # compare the current build against the known-good base
./scripts/gate-prefill-logits.sh --record # (re)record the base from a known-good build
./scripts/gate-prefill-logits.sh --ab "GGML_CUDA_GDN_CHUNKED_BF16=0"  # exact-fallback A/B
```

It requires mean KLD <= 0.005 and same-top-p >= 98 %. Issue #113 (the lossy default-on BF16 chunked
GDN) passed the coherence gate and was only visible to this one; protocol in
`benchmarks/prefill-logit-methodology.md`.

### Regenerate the patches (after fork changes)

`scripts/make-patches.sh` (defaults read from `release.json`) `git format-patch --start-number 0`s the
block commits (block 00 keeps prefix `0000`; `git diff <base>..<tip>` yields `rdna-boosts-all.patch`).
Always regenerate from a canonical fork rebuilt at `release.json.base` via `scripts/apply-all.sh`:
the working `~/llama.cpp` branch is not the canonical chain and a raw range there can export upstream
commits. Then re-verify the clean-apply simulation (fresh worktree, apply, build, coherence, and
`scripts/gate-prefill-logits.sh`).

### Build the fork

```bash
cd ~/llama.cpp && ~/bin/build-llama-rocm          # default BUILD_DIR=build-rocm, ROCm 10.1.0
# fast loop: cmake --build build-rocm --target llama-cli llama-bench -j 16
# runtime libs: LD_LIBRARY_PATH=/opt/rocm-10.1.0-gfx120X/lib
```

**Keep the ccache large enough for a per-block build or it thrashes.**  The tool's default
`max_size = 5 GiB` is far too small once one source tree carries several `GGML_CUDA_FA_*` instantiation
sets: `scripts/gate-per-block-build.sh` then misses on nearly every FA translation unit and evicts the
entries the next block needs (measured 2026-10-21: block 05 went from ~45 min at 5 GiB to ~7 min after
`ccache --max-size=30G`).  Set it once per box.

**`~/bin/build-llama-rocm` (ROCm 10.1.0, `/opt/rocm-10.1.0-gfx120X`) is the canonical build tree.**
`~/bin/build-llama-rocm-714` is the older ROCm 7.14 tree (its own `BUILD_DIR`, `build-rocm-714`); it is
still valid for a 7.14-specific check, but do not present it as the default. **Do not pass
`EXTRA_CMAKE_FLAGS="-DCMAKE_HIP_FLAGS="`** (or any `-DCMAKE_HIP_FLAGS` override): both scripts pass a
joined `-isystem<rocm>/include` there and abort the configure if the flag does not reach the HIP compile
line (the include-order guard). That guard exists because the failure is otherwise silent -- HIP headers
resolve from Fedora's ROCm 7.1 in `/usr/include`, and the resulting binary still produces identical
greedy text on 7.14. The old CMake >= 4.3 problem (a bare `-mllvm` swallowing the injected
`--cuda-host-only`) is already handled by not passing `-mllvm` at all. **ccache is on by default** when
present (the build dir is reused incrementally unless you pass `clean`; ccache makes even a wiped
rebuild of unchanged sources a cache hit).

The FA instances are deliberately force-inlined — do **not** outline the FA loader
(measured: a universal 1.5-2.5 % prefill loss). This is the sanctioned answer to "the build is slow";
detail in `archive/work/build-time-regression/`.

### Build the release container images (worker by default; local only for smoke)

The ROCm container images are built and pushed **off-host** by the worker watcher
(`scripts/container-watch.sh` on `radiance`), which polls the delivery repo for a new `v12-*` tag and
runs `scripts/build-containers.sh --rocm "7.14.1 10.1" --push --prune` on that box.  This keeps the
primary box free for benchmarks, and a tag-push CI build is not used either (~5 h for two ROCm lines,
and a failed/timed-out run wrote no registry cache so every retry was cold).  **After `git push` of
the tag, nothing else is needed: the worker picks it up within 10 minutes.**  The commands below are
for the worker's one-time setup, or for a smoke build on the primary box; **do not run the full
`--rocm "7.14.1 10.1" --push` on the primary box during a release.**  The fast CI workflows stay:
`validate.yml` (per-push patch validation) and `release.yml` (the tag-triggered GitHub Release
carrying `rdna-boosts-all.patch`, `patches.tar.gz`, `release.json` and `SHA256SUMS`).

**Scope: this is the container image build only.**  The normal local source build used for testing,
benchmarking and the release gates (`~/bin/build-llama-rocm`, `build-pr`/`build-r69`/..., plus the
coherence, MTP and prefill-logit runs) is unaffected and is still done on the primary box.  "Do not run
the full build locally" means the `podman` image build below, not `cmake --build`.

**Worker (`radiance`) one-time setup** (full detail in `CONTAINERS.md`):

```bash
sudo loginctl enable-linger "$(id -un)"     # cron + rootless podman survive logout/reboot
gh auth login -h github.com                 # classic PAT needs write:packages + delete:packages
install -m 755 <repo>/scripts/container-watch.sh ~/bin/rdna-container-watch.sh
( crontab -l 2>/dev/null; echo '*/10 * * * * $HOME/bin/rdna-container-watch.sh >> $HOME/.cache/rdna-containers/watch.log 2>&1' ) | crontab -
```

**Primary box: manual container build (only if not using the worker) or a fast smoke:**

```bash
./scripts/build-containers.sh --prepare-only               # reconstruct + verify the release tree
./scripts/build-containers.sh --rocm "7.14.1 10.1" --push --prune   # full build; prefer the worker
./scripts/build-containers.sh --rocm 10.1 --arch gfx1201 --targets server   # fast smoke, no push
```

`scripts/build-containers.sh` reads `release.json`, materialises the canonical patched tree
(`release.json.tip`, asserting `tree`) into `$HOME/llama-src`, writes the build-context
`.dockerignore` (from `.devops/dockerignore`), builds `full`/`light`/`server` per ROCm line with the
same build args the CI matrix used, applies the same registry tags (`rocm-<v>`,
`server-/light-/full-rocm-<v>`, the immutable `-<base>` variants and `latest` on 10.1) and (`--push`)
pushes to `ghcr.io/stew675/llama-cpp-rdna-boosts`.  `docker-ghcr.yml` remains only as a manual
`workflow_dispatch` fallback.

**ccache is on.**  `.devops/rdna-rocm.Dockerfile` installs the upstream static ccache **4.12.3** (the
version the host validates, not Ubuntu's older package), sets `CCACHE_DIR=/root/.ccache` and adds
`-DCMAKE_{HIP,C,CXX}_COMPILER_LAUNCHER=ccache` (mirroring `~/bin/build-llama-rocm`), with
`/root/.ccache` as a build cache-mount — never an image layer, so the published images are unchanged.
Measured single-arch: cold compile 10m01s → cache-warm rebuild 1m28s (835/836 direct hits).  A release
whose sources mostly match the previous one recompiles only the delta.

**Prune only the built images, never the base images.**  `--push --prune` publishes and then removes the
just-built `ghcr.io/...` images and dangling build layers, keeping the ROCm base images and the ccache
store so the next build neither re-pulls ~20 GB per line nor recompiles from cold.  Do **not** use
`podman system prune -a` for this (it takes the base images and ccache with it).

**The push also prunes the GHCR package.**  GHCR keeps every manifest ever pushed (an index plus one
version per architecture, plus whatever a moving tag left behind), so the package grows without bound;
`scripts/cleanup-ghcr.py` runs automatically on `--push` and deletes everything outside a rolling
`--keep-days` window (default **7**, one release cycle) while **always keeping the current base's
`*-<base>` tags** — the images just pushed can never be deleted.  `--no-cleanup` skips it.  A GitHub
bulk-delete throttle (secondary rate limit) is a warning, not a failure; re-run the tool to finish.

**Only ROCm 7.14.1 and 10.1 are built by default.**  7.2 (`-complete`) is much slower and is manual-only.

## What NOT to do

- Do not `git apply` the concatenated block series (drops hunks); use `scripts/apply-all.sh`.
- Do not hand-edit the committed patches as a permanent drift fix — regenerate and re-verify.
- Do not mix the historical `baseline/*` branches or `block/*` tags with the current `patches/`.
- Do not push anything from the `~/llama.cpp` checkout except the release-time `rdna-boosts` refresh
  to the personal fork (see the Pushing policy). Never push to upstream `ggml-org/llama.cpp`.
- Do not present old docs as current: `MANIFESTS.md`/`BASELINE.md` are contracts, their dated history
  is in `archive/docs/`; current claims are their current-state headers + `patches/README.md` +
  `release.json` + the newest `WORKLOG.md` entry.
- Do not add new WIP experiments to the delivery set, and **never apply anything from `wip/`** or
  `archive/work/` unless the user explicitly asks for that specific item.

## Editing the docs

The docs have a freshness problem by design: historical records are kept, and the CURRENT state lives
in the current-state headers (`patches/README.md`, `README.md`, `MANIFESTS.md`, `BASELINE.md`,
`release.json`) plus the newest `WORKLOG.md` entry. When you change the delivery, update those headers
and add a new dated `WORKLOG.md` entry (newest first) — never edit dated validation records in place.

**Each top-level doc has one job — keep it that way.**  `README.md` describes the *set* (what it is, how
to apply it, what a consumer needs); `MANIFESTS.md` is the apply order + verification contract;
`BASELINE.md` is provenance + the drift policy; `GREEDY-PURITY.md` is the rulebook (claim, rule, numbers
per `§N`, with the narratives in `archive/docs/GREEDY-PURITY-FINDINGS.md`); `TODO.md` is
**forward-looking only** (open, waiting, accepted-limitation, parked — a closed item is one `WORKLOG.md`
entry, never a TODO entry); `ENVIRONMENT.md` is the variable catalogue.  **Release narrative belongs in
`WORKLOG.md` and nowhere else** — do not paste a release summary into `README.md`, `BASELINE.md` or
`MANIFESTS.md`; point at `WORKLOG.md` instead.

**WORKLOG dated headers use `YYMMDD.VVV`** (e.g. `## 261011.005 (r47) -- ...`).  `YYMMDD` is the
real local calendar date and `VVV` is a per-date, monotonically increasing 3-digit sequence number in
file order (the topmost/newest entry of a date carries the highest number).  The date is only a
date — never treat it as a version; the revision is the explicit `(rNN)` tag.  A new entry takes
today's real date and the next free number for that date.  Do not invent or extrapolate a future
date: if the work is done today, the header says today. Keep this file terse: policies, invariants and pointers only. Session/dev handovers belong
under `wip/` or `archive/docs/`, not at the repo top level.
