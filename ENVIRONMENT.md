# ENVIRONMENT.md — environment variables that affect this repo

Scope: everything **this repo adds or repurposes**, plus the upstream variables and the non-ggml
runtime variables (HIP/ROCm) that materially affect how this delivery behaves.  Defaults are taken from
the `rdna-boosts` tree at the current release (`release.json`; every default stated here is the shipped
one, and a row that changed after the V2.0 cut names the `rNN` that changed it), and the table is generated
from the code, not from memory (see [Maintaining this file](#maintaining-this-file)).

## How to read this

| class | meaning |
|---|---|
| **Kill-switch** | the feature is **ON by default** because it passed its gate; the variable exists to disable it for A/B, bisection or a workaround. Setting it to `0` restores the old behaviour. |
| **Opt-in** | OFF by default; the feature is not gated or not for production. |
| **Tuning** | takes a number/string; the default is the validated value. |
| **Diagnostic** | no effect on the default path — it only logs, dumps, or gates a debug helper. Never set in production. |

Two idioms are used in the code and they are **not** interchangeable:

* *presence-only*: `getenv("X") != nullptr` — **any** value (including `0`) enables it.
* *value-gated*: `getenv("X") != nullptr && atoi(...)` — `1` enables, `0` leaves it off.

The tables below say which one each variable uses, because guessing wrong is a classic time sink.

Every behaviour-affecting variable is also resolved **once** (into a function-local static or value) on
first use, so setting one after the process has started has no effect.  This is deliberate: `getenv()`
takes a lock and rescans the environment block on Windows, and several hot paths (per matmul, per
device allocation, per graph input, per batch) would otherwise read it thousands of times.  It also
avoids caching a `const char *` returned by `getenv()` across calls, which is unsafe on Windows because
the MSVC CRT reuses its buffer for the next `getenv()`.

## The short answer: what you actually need

**Nothing.** Every feature the delivery ships is default-on, and this is deliberate policy (see
`AGENTS.md`, "Default-on policy"). You do **not** need to set anything for the recommended server or
`llama-cli` invocation. The variables below exist to *disable* things, to bisect a regression, or to
tune a value that has a validated default.

The only ones worth knowing by heart:

| variable | default | why you would touch it |
|---|---|---|
| `GGML_COMPUTE_BUFFER_MARGIN_PCT` | `10` (HIP only) | `0` disables the compute-buffer slack — the fastest way to reproduce the old TODO #42 abort |
| `MOE_EXPERT_CACHE_MIB` | unset = auto | `0` disables the MoE expert cache entirely (CPU expert path) |
| `GGML_CUDA_SLAB` | **on** | `0` disables the movable-boundary slab allocator (back to per-allocation `cudaMalloc`; reintroduces the TODO #42 server abort).  Since **r37** the slab is additionally **armed only for models with host-resident experts** (`-ncmoe`/`-cmoe` > 0); a dense model never creates one.  Since **r47** the arm is independent of `--fit` (issue #136): if the cache is enabled the slab is armed |
| `GGML_CUDA_SLAB_HEADROOM_MIB` | `640 + 128 x n_gpu` (768 / 896 / 1024 MiB) | VRAM left outside the slab after it reclaims the unused reserve. **Raising it buys steady-state margin at the cost of arena**; `2048` aborts the 16k path inside hipBLASLt |
| `GGML_CUDA_ALLREDUCE` | `hybrid` | force `internal` \| `nccl` \| `ce` for multi-GPU A/B |
| `LLAMA_DROP_COMPUTE_BUFFERS` | **on for every tool** | `0` keeps the wide-prefill layout (smaller arena). Under the slab a later wide prefill reclaims it via a boundary move, so a server may drop too |
| `GGML_CUDA_OP_TIMING` | off | per-op GPU timing/profiling |

---

## 1. Compute buffers and the MoE arena

### 1.1 `GGML_COMPUTE_BUFFER_MARGIN_PCT` — **tuning**, default `10`, HIP/ROCm only

Pads every **compute** buffer allocation by that percentage (`ggml-alloc.c`, via the buffer type's
`get_compute_margin_pct`).  The graph allocator sizes the compute buffer from a *measure* graph, but a
runtime graph can carry a different live-tensor set (host-expert staging, MTP taps) and need a little
more — measured +3.3 %.  Growing it is a free-then-allocate-larger, so it needs a contiguous block
**bigger than the one just released**, which fails once the free VRAM belongs to the MoE arena.  Taking
the slack up front moves the cost to before the arena is sized.

* `0` disables it — and **reproduces the original abort**, so it is the natural A/B control.
* Cost, measured on 2× R9700 (`-sm tensor -ncmoe 48`): 1275 MiB of arena residency (63.8 % → 61.5 %),
  ≈127 MiB per percentage point.
* Only the RDNA/ROCm path opts in (`#if defined(GGML_USE_HIP)`); every other backend's allocation sizes
  are unchanged.  Read once per process.
* **Unchanged in r37:** the margin still applies to dense models (about 10 % of a now-small layout).  Only
  the **chunk** is slab-gated (`GGML_COMPUTE_BUFFER_CHUNK_MIB`); together with the r37 host-expert slab gate
  this is what restores a dense model's pre-slab compute-buffer sizes (issue #120).
* Compute-only: model weights, the KV cache and the arena are untouched.

### 1.2 MoE expert-cache arena

| variable | default | class | notes |
|---|---|---|---|
| `MOE_EXPERT_CACHE_MIB` | unset = **auto** | tuning | sizes each device from its free VRAM. `0` disables the cache **completely** (CPU expert path) — prefer this over a tiny arena, which stands the cache-aware MoE fusions down and is ~8× slower than the cache-less path.  On an **integrated GPU** (shared host/device pool) **auto is refused** (r91): the cache is declined with one WARN and the run takes the host-expert path, because AUTO + the slab would map host RAM (see `MOE_EXPERT_CACHE_UNIFIED`). |
| `--moe-cache-mib` (CLI, upstream `llama_moe_cache`) | unset = off | **works, not recommended** | the **upstream** cache engine, not this block's.  It was unusable from block 09 to r98 (the scheduler never invoked `sched->callback_copy`, so its slot map stayed `-1` and the cached layer's `MUL_MAT_ID` indexed the expert bank one expert below it: wrong values on gfx1201, an HSA fault on gfx1151); fixed in r99 (TODO #56).  It is correct now but slower than `MOE_EXPERT_CACHE_MIB` here, because it synchronises the split backend once per cached layer per pass (35B-A3B `-ncmoe 40`: decode 50.1 -> 37.8 t/s), so use the delivery's own arena.  Not affected by `MOE_EXPERT_CACHE_*` or `GGML_CUDA_SLAB`/`GGML_SCHED_STAGE`. |
| `MOE_EXPERT_CACHE_IDENTITY_PREF` | `1` | kill-switch | **whole-table identity placement** (r117, block 09).  A table is on the decode band's identity fast path only at its FULL slot count, and a uniform slot count that lands one slot short (each table's arena is rounded up to the slab arena unit) drops *every* table off it — worth ~40 % of decode (46.7 -> 65.0 t/s measured).  On: when at least 96 % of the layers can have their full slot count, those layers get full residency and the coldest few are dropped to 0 slots (they run through the scheduler's host copy) instead of spreading the shortfall.  `0` restores the pre-r117 uniform placement (A/B and bisect only).  `MOE_EXPERT_CACHE_MIB` still bounds the arena — the placement never exceeds the budget. |
| `MOE_EXPERT_CACHE_UNIFIED` | unset = refused | **opt-in, APU only** | r91.  On a device whose "VRAM" is the same physical pool as host RAM (`cudaDeviceProp_t::integrated`), the expert arena is **off by default** and this variable is the only way back in: it requires an explicit `MOE_EXPERT_CACHE_MIB` **and** an explicit `GGML_CUDA_SLAB_RESERVE_MIB`, so the slab is bounded by construction (`mapped = free - reserve`) instead of mapping the machine.  Ignored on a discrete GPU. |
| `MOE_EXPERT_CACHE_RESERVE_MIB` | `1024` | tuning | VRAM held back from the arena for the compute side / KV cache.  The old server workaround raised this to `8192`; **that is no longer needed** (the r20 slack + the fail-soft yield cover it). |
| `MOE_EXPERT_CACHE_MIN_MIB` | `0` | tuning | auto-sizing floor; below it the cache declines itself instead of building a useless arena.  Decided **early** (before the context exists, i.e. before any graph) since r24 -- a late `g_enabled = false` would plan the MTP draft and the target with different kernels.  If a config still trips it late, it logs an ERROR and keeps the small arena (correct, slower). |
| `MOE_EXPERT_CACHE_MIN_RES_PCT` | `18` when auto | tuning | minimum residency worth keeping.  Live since r24 (it was silently inert while the early floor never ran). |
| `MOE_EXPERT_CACHE_AUX_RESERVE_MIB` | unset = derived (r86) | tuning | **the draft CONTEXT reserve** since r86 (KV + narrow-2 compute + slack; the draft weights are already resident because the draft model is loaded before the target context).  Taken verbatim per device; unset/0 falls back to the derived value from `draft-reserve.cpp`.  Before r86 it was the whole draft footprint. |
| `MOE_EXPERT_CACHE_SLOTS` | `0` | tuning | explicit slot count hint (0 = derive from the budget). |
| `MOE_EXPERT_CACHE_PERIOD` | `32` | tuning | promotion/rebalance period, in tokens. |
| `MOE_EXPERT_CACHE_FILL` | `1` | kill-switch | fill-on-miss. |
| `MOE_EXPERT_CACHE_TOUCH` | `2` | tuning | `admit=touch`: uses since last resident before a fill is allowed. |
| `MOE_EXPERT_CACHE_PROVISIONAL` | `1` | kill-switch | provisional eviction during a pass. |
| `MOE_EXPERT_CACHE_PREFILL_SEED` | `1` | kill-switch | seed the cache during prefill. |
| `MOE_EXPERT_CACHE_PREFILL_SEED_N` | `0` | tuning | how many prefill seeds (0 = default). |
| `MOE_EXPERT_CACHE_SIZE_AT_PRIME` | `1` | kill-switch | **size the arena at the warmup, not the first real decode, and stop the seed at the prefill reclaim boundary** (r75, blocks 09/10/11; developed as the unpublished r74 beta).  The warmup only *primes* each host table, so the deferred sizing used to wait for the first user decode and pay the whole arena allocation + H2D seed on the first generated token.  On (default): the priming pass sizes, `slab_extend_all` is skipped there (it over-mapped the reserve and a later graph capture OOM'd), and the arena is sized to the **full** region while the seed stops at `narrow_floor + ring + wide` -- the band a wide prefill immediately reclaims (the coldest, heat-ordered-last tables stay unseeded and fill lazily during decode).  Measured (maintainer's GSQ command, 13.8K prompt): arena 15666.6 MiB at load, 97/144 tables seeded, first-prefill eviction 6150 MiB (the band), re-arm restores the arena, decode 75.0 t/s.  `0` restores the deferred sizing. |
| `MOE_EXPERT_HEATMAP` | `1` | kill-switch | **persistent cross-run expert heat map** (r60, block 09).  On: the cache tallies a long-horizon per-expert use count (device-side on the prefill band, host-side on the eager decode band) and writes it to a sidecar next to the model; the next run seeds the arena with the hottest experts at sizing and allocates the hottest **layers** first (so the work-pool boundary reclaims the coldest).  Measured on `MOE_EXPERT_CACHE_MIB=4096`: **+34 % decode over a 48-token turn** (38.15 -> 51.30 t/s, hit 0.767 -> 0.940, fills 11748 -> 2976) and **+10.3 % over 256 tokens** (48.53 -> 53.55 t/s, fills 19452 -> 6912); prefill unchanged.  It is a placement prior only (the expert bytes are unchanged), so the output is bit-identical.  `0` restores the exact pre-change behaviour.  `load` (aliases `ro`, `read-only`) loads and seeds from the map but never writes it.  A **read-only heat-map file** is also loaded and frozen: the file's mode is the freeze signal, and it does not fall back to a cache directory. |
| `MOE_EXPERT_HEATMAP_DIR` | unset | tuning | directory for the sidecar when the model directory is not writable.  Otherwise the fallback order is `$XDG_CACHE_HOME/llama-moe-heatmap`, `$HOME/.cache/llama-moe-heatmap`, `/tmp`. |
| `MOE_EXPERT_HEATMAP_DEBOUNCE_S` | `60` | tuning | minimum seconds between heat-map writes (the server flushes at turn end; process exit always flushes). |
| `MOE_EXPERT_HEATMAP_MAX_FAILS` | `3` | tuning | consecutive write failures before persistence is disabled for the session (non-fatal throughout). |
| `MOE_EXPERT_HEATMAP_DECODE_SAMPLE` | `64` | tuning | **sampled decode-band heat tally for a fully-resident (identity) table** (r110, block 09, TODO #64.2).  Every other table's decode routing is tallied *exactly* on the host (the eager path already reads it), but a fully-resident table takes the identity fast path, which never reads the routing back at all -- so its decode traffic contributed nothing to the heat prior.  This tallies it from the device entry, one op in `N`, **weighted by `N`** so the counts stay on the same scale as the exact tallies.  `0` disables it.  Cost: one atomic tick per decode op and, for a sampled op, one small kernel launch; the tally mirror is pre-allocated at sizing so nothing is allocated on the captured decode path.  Measurement-side effect only (the prior changes which experts are resident, never the bytes served). |
| `MOE_EXPERT_TRACE` | unset = off | **diagnostic** | **offline routing trace** (r110, block 09, TODO #61 P1): writes the raw routing of every `mul_mat_id` to this path, in a text format that `scripts/moe-trace-replay.py` replays to score cache policies (the shipped F-LRU, static top-f, a per-layer capacity quota, pass-start pre-admission) against a real workload.  DECODE records come from the scheduler hook, where the ids are already on the host (no readback, no sync); PREFILL records come from the device entry, because the staged prefill path never brings them to the host -- that costs one readback per prefill op (a prefill ubatch is never CUDA-graph captured, so it is safe).  A fully-resident (identity) table's decode band is not traced: it cannot miss.  It is a *diagnostic*, never default-on, and the replayer's absolute hit rate is a model of the cache, not the cache -- judge policies by their delta. |
| `MOE_EXPERT_TRACE_MIB` | `1024` | tuning | cap on the trace file, in MiB (r110).  Recording stops at the cap with one warning; the records already written are kept.  A 296-token prompt + 128 decode tokens on a 40-layer MoE is ~2 MiB. |
| `GGML_MOE_CACHE_MAX_TOK` | device MMVQ band (16 on RDNA4; 8 on RDNA3, NVIDIA) | kill-switch | caps the expert-cache **decode/verify band** (routed `MUL_MAT_ID` tokens the cache serves from the arena).  It defaults to the routed-expert MMVQ kernel's own band on the device since r31; `8` restores the pre-r31 band (band widening in `archive/work/moe-cache-band16/`).  A non-numeric value silently yields 1. |
| `GGML_MOE_GATHER_ONCE` | off | diagnostic | gather each expert once per pass. |

> **Heat map (r60; unified naming r75).**  The per-expert heat map is **on by default** whenever the
> cache is active on host-expert tables (`MOE_EXPERT_CACHE_MIB` auto/positive and a `-ncmoe`/`-cmoe`
> model).  Its sidecar is a **single unified index per model**, `<base>.moe-heatmap`, where `<base>` is
> the model filename with the `.gguf` extension and any llama.cpp split marker (`-NNNNN-of-NNNNN`)
> stripped -- so every shard of a sharded GGUF shares one file (`Qwen3.8-Flash-Next-...-00001-of-00009.gguf`
> -> `Qwen3.8-Flash-Next-....moe-heatmap`), and an unsharded `model.gguf` -> `model.moe-heatmap`.  It is
> geometry-keyed, atomic (`tmp`+`rename`), debounced 60 s and non-fatal on failure; if the model
> directory is read-only it falls back to `MOE_EXPERT_HEATMAP_DIR` / the XDG cache.  It is
> a **placement prior only**: the expert bytes are unchanged, so a run's output is bit-identical and
> `MOE_EXPERT_HEATMAP=0` reproduces the pre-change behaviour exactly.  The retired per-shard
> `<gguf>.moe-heatmap` naming is **never read or written**; a stale file in that form next to the model
> is ignored with a warning (delete it -- the map relearns from a cold start).  The in-run
> `MOE_EXPERT_CACHE_PREFILL_SEED` remains as a second (weaker) seed source; the heat map is applied
> first.  **Freezing a map (r61):** set `MOE_EXPERT_HEATMAP=load`, or simply make the heat-map file
> read-only (`chmod 400 <base>.moe-heatmap`).  A read-only file is loaded and used to seed, is never
> overwritten, and is not relocated.  See `patches/README.md` (block 09, r60/r61/r75) and
> `archive/work/moe-heatmap-persistence/`.  **Two bands, two counters (r114, TODO #88):** the map keeps
> a **combined** counter (prefill + decode) and a **decode-only** one, because the two consumers want
> different rankings.  The **arena** serves the decode/verify band, so its seed (`apply_heat_seed_locked`)
> and the heat-ordered layer placement rank by the decode counter; the **host pool** stages whole tables
> *for a prefill*, so its bulk layout (`pool_rank_experts_locked` / `pool_rerank_from_heat_locked`) keeps
> the combined one.  Before the split, one counter held both and a prefill ubatch (which routes ~`n_tok`
> experts) outweighed the decode by tens of times, so the arena was seeded from a nearly uniform
> distribution: measured on a real trace, the stored prior's top-112/table covered **80.3 %** of the
> decode mass where the same map restricted to its decode component covers **95.3 %** (the oracle's).
> On the GPU (35B-A3B Q4_K_M, 2 GPU tensor, `-ncmoe 40`, `MOE_EXPERT_CACHE_MIB=4096` = 43.8 % residency,
> the *same* map in both arms): `h` **0.8747 → 0.8862** (284-token prompt) and **0.8698 → 0.8948**
> (5256-token prompt).  The sidecar format is **MHT2** (both arrays); a **MHT1** file still loads and is
> used for both counters, i.e. exactly the pre-r114 behaviour, so an existing map keeps working and simply
> re-learns the split as it is rewritten.  (`MHT2` is two counters per expert, so a map doubles in size.)
> **Host-pool warm order (r110):** the `--host-experts pool`
> pinned tier used to be warmed in expert-id order, because the eager `prefill_count` tally never runs
> under the staged prefill.  It now takes its order from the device prefill tally, folded in once at the
> first decode-band pass (`pool_rank_from_prefill_locked`); the prewarm log line says which source it
> used (`ranked by the prompt tally` / `ranked by expert id (no tally)`).  With `MOE_EXPERT_HEATMAP=0`
> there is no tally and the historical id order remains.

> **REMOVED — do not reintroduce (2026-10-10, released r40).**  The device-remap path and its whole family
> (`MOE_EXPERT_CACHE_DEVMAP`, `MOE_EXPERT_CACHE_DEVPOLICY`, `MOE_EXPERT_CACHE_DEVPOLICY_SPLIT`,
> `MOE_EXPERT_CACHE_KSLOT`, `MOE_EXPERT_CACHE_DEV_EAGER`) plus the device-policy knob `MOE_HOST_POOL_POLICY`
> were **deleted from the code base**.  The eager
> host-routing path (materialized remap) is the only `-sm tensor` split policy; it is MTP-pure on qwen4exp
> (`none == n3`), within noise of the old `DEVMAP=0` performance, and resolves `TODO.md` #50.  The device
> path's divergence was a layout-sensitive **hipBLASLt** solution flip (issue #67), not a cache bug; the
> only workaround (`ROCBLAS_USE_HIPBLASLT=0`) costs ~12-17 % prefill on gfx1201/ROCm 7.14, and ROCm 10.1.0
> does not fix it.  See `wip/moe-verify-fusions/FINDINGS-devmap-removal.md`.  Do **not** add any
> `*DEVMAP*`/`*KSLOT*`/`*DEVPOLICY*` variable or device slot-map path back. |

> The arena is the **lowest-priority** VRAM consumer: without a slab, any device allocation that runs short
> frees the largest table (then the whole arena) and retries.  With the slab on (the default, see §1.3) that
> path is *skipped* — freeing a table cannot return bytes to the driver once the slab owns them — and the
> allocation instead fails with a message naming `GGML_CUDA_SLAB_RESERVE_MIB`.  There is no variable for the
> yield behaviour, and it should stay that way.  See `ARENA-UB-TENSION.md` §13/§14.

### 1.2.1 Host-expert pool (`--host-experts pool`, blocks 09/12) — **no pinned master**

The pool is an **option** for systems that cannot hold the weights resident; the default `--host-experts
pinned` (and `auto`) keeps the usual behaviour (a full pinned `ROCm_Host` master) and allocates **no**
pool.  r35 shipped the pool as a bounded bounce tier *next to* that master; **r111 completes it**: in POOL
mode there is no master at all.  **POOL mode is only for the case where the host expert set does NOT fit in
RAM** — when it does fit, `pinned` is faster and cheaper on every axis, and POOL mode will be slower.

| tier | what |
|---|---|
| L1 | the VRAM expert-cache arena (the movable-boundary slab) |
| L2 | the bounded pinned host pool — the **only** non-swappable tier (`MOE_HOST_POOL_MIB`/`FRAC`), one per host tensor, process-wide budget |
| L3 | the read-only **model mapping** → page cache → the GGUF on disk |

The host expert tensors are placed in the model's read-only mapping (a dedicated per-device host buffer
type, `ROCm_HostMap`, which still carries its device so the scheduler keeps the `MUL_MAT_ID` on the owning
GPU).  **No device copy and no kernel reads that mapping**: every host read is served from a pool slot
(a `memcpy` out of the page cache, or a `pread` with `MOE_HOST_POOL_DIO=1`), and when the pool declines
through a per-table pinned bounce ring.  The in-place cold read and the device-side gather therefore stand
down in this mode (they need a device-mapped master, issue #116) — a miss becomes a pool fill instead.

Measured (35B-A3B UD-Q4_K_M, `-ncmoe 40` = 18 662 MiB of host experts, 1x R9700): `RssShmem` **18.6 GiB
(`pinned`) → 6.8 GiB (FRAC 25)**, the difference sitting in reclaimable page cache; FRAC 50 pins 10.2 GiB
and FRAC 100 reproduces the old footprint, so **the pinning is the fraction knob**.  Under a 12 GiB or
8 GiB cgroup (`MemoryMax`, no swap) the `pinned` arm is OOM-killed and the `pool` arm runs at ~93 t/s —
that is the point of the mode: a host expert set larger than RAM streams from disk instead of failing.
Cost: one extra host memcpy per staged byte on the host-expert *prefill* staging path when the fills are
buffered (decode parity; `llama-cli` prefill −1…−6 %, a single-ubatch `pp512` on the 2-GPU tensor config
−34 %).  A non-mapped load (`--load-mode none/dio`) has no mapping to place the tensors in and keeps the
pinned master (warned); use the default mmap load mode.  r111.

**r113 — the pool is a LAYOUT, not a churning cache, and it is ranked by the persisted heat prior.**
`MOE_HOST_POOL_FRAC` is a percentage of the **model's host expert set** (`-ncmoe`/`-cmoe` bytes), *not* of
system RAM, and it is inherently capped there (FRAC 100 = each table's pool is exactly its expert count,
i.e. the whole set pinned once — a pool can never be larger than the model needs).  Two consequences drive
the r113 change:

1. **What the pool HOLDS decides the disk traffic; the eviction policy barely matters.**  Measured offline
   on a real 10.5K-prompt routing trace with the model's own persisted `.moe-heatmap`
   (`scripts/moe-trace-replay.py --pool-frac 80 --pool-init sidecar-complement:<sidecar>`; arena 369 and pool
   409 slots per table, the field config's real geometry): pool content ranked by expert id (the pre-r113
   behaviour) = 3571 MiB of L3 (disk) reads over 451 decode tokens; the same pool ranked by the persisted
   heat prior as the arena's *complement* = **237 MiB**; an oracle prior = 237 MiB.  Every
   eviction/hand-over policy (no-evict, retire-on-promote, evict-LRU-and-admit, swap with a weak candidate,
   swap with the incoming's own slot) lands within **0–246 MiB** of that — i.e. noise next to the content
   effect, while each costs host↔device copies.  So the pool is laid out in bulk — as the arena's
   complement, ranked by the heat prior — at sizing (after the heat/prefill seeds), and again at the first
   decode-band pass (after the prompt's routing is folded into the heat vector).  The **demand path never
   evicts**: a resident expert is the source, a miss takes an EMPTY slot, otherwise it falls through to the
   per-table pinned bounce.  The background eviction-prefetch worker is gone with that (see
   `MOE_HOST_POOL_BGFETCH`).
2. **A pool that does not fit is worse than a small one.**  `MOE_HOST_POOL_RAM_PCT` (r113, default **85**
   since r114)
   caps the *whole* pinned pool at that percentage of `MemAvailable`, measured once at the first pool build.
   Without it, `frac %` of a large host set can exceed what the box can pin, and the failure is silent: each
   table's `cudaHostAlloc` fails, that pool is marked `failed`, and its reads take the bounce path (the
   disk).  The cap trims per table (with one WARN naming both knobs) and keeps the one-slot floor.

Measured on the gfx1201 field config (Qwen3.8-Flash-Next **IQ4_NL**, 2× R9700, `-ncmoe 48` = 64 800 MiB of
host experts, MTP `--spec-draft-n-max 7`, `--cache-ram 16384`, 70K-token prompt, 128-token decode, all on
the same build): the pool's hit rate went **0.7999 → 0.9183** and its evictions **4600 → 0**, and against the
`pinned` reference (836 t/s prefill / 57.5 t/s decode) the pool arm went from 581 / 30.6 (**DIO=0**) and
a prefill that could not finish in 27 minutes (**DIO=1**, 39 t/s) to **733 / 53.7** and **287 / 23.1**.  The
remaining `DIO=1` gap is the fraction of each table no pool tier holds (FRAC 80 leaves 20 %), which a prefill
ubatch re-reads per ubatch; it disappears under `DIO=0` (page cache) or FRAC 100.  Purity is unchanged: the
pool only chooses which byte-identical copy fills a slot (greedy text byte-identical old vs new, and
`MOE_HOST_POOL_VERIFY=1` is clean).

**r114 — the fill mode is chosen per box, and the pool-backed prefill stages in one launch.**  Two of the
three `TODO #87` follow-ups landed: `MOE_HOST_POOL_DIO` became **`auto`** (see the table row) and the
pool-backed prefill staging fills every tier-resident expert with one kernel instead of one
`cudaMemcpyAsync` per expert.  Measured, 2x R9700 / 35B-A3B Q4_K_M `-ncmoe 40 --host-experts pool`,
70K-token prompt, `-ub 2048`, `-ncmoe 40`:

| arm | prefill t/s | decode t/s |
|---|---:|---:|
| pool, one-launch staging, `DIO` auto → buffered | **2103 / 2099** | 46.6 / 46.4 |
| pool, `MOE_HOST_POOL_STAGE_BATCH=0` (the per-copy arm) | 1564 | 46.2 |
| pool, `MOE_HOST_POOL_DIO=1` forced | 2088 | **22.7** |
| `pinned` (reference) | 2099 | 49.3 |

So the pool now stages prefill within 0.3 % of `pinned` and decodes within 6 %, and the `pinned`-only tax the
mode used to carry on a RAM-rich box (287/23.1 t/s at the shipped `DIO=1`) is gone.  Text is byte-identical
across every arm (`pinned` / pool / `DIO` 0 and 1 / staging on and off) and `MOE_HOST_POOL_VERIFY=1` is
clean — the pool only changes which byte-identical copy fills a slot.

**r112 — the defaults are tuned for the case the mode exists for.**  `MOE_HOST_POOL_FRAC` defaults to
**80 %** and, since **r114**, `MOE_HOST_POOL_DIO` is **`auto`**: buffered when the host expert set fits
beside the pool in `MemAvailable`, O_DIRECT when it does not (so a box with the RAM to spare no longer pays
the disk tier's price by default, and a memory-tight box still never lets the page cache compete with the
pinned pool).  A memory-tight box cannot afford two copies of the same weights (pinned pool *and* page
cache), and a page cache that cannot hold the set only
buys swap thrash; 80 % keeps the working set hot and lets the disk serve the remainder.  Measured on the
field case (gfx1100, 24 GB VRAM, **30 GiB RAM**, 35B-A3B **Q8_0** = 37.8 GB, `-ncmoe 40` = 31.9 GiB of host
experts, 2000-token runs): pool 26.0 GiB pinned, **78.3 t/s decode**, 0.3 GiB swap — versus 48.6 t/s for
r111's 25 % buffered default and 2-3 t/s (16 GiB of swap) for `pinned` on the same box.  The knee is 80 %:
90 % measured 71.8 t/s *and* started swapping.  The cost is the first prefill: with nothing cached it stages
the whole set through O_DIRECT (~10 s on that box, i.e. a short prompt shows ~0.6 "prompt t/s"; a 1400-token
prompt measures 49 t/s).  On a box where the set fits in RAM, stay on `--host-experts pinned`.

| variable / flag | default | class | notes |
|---|---|---|---|
| `--host-experts pool` | `pinned` | option | select the bounded host pool and **drop the pinned master** (r111).  `pinned`/`auto` = full pinned master, no pool; `mmap` was removed in r33. |
| `MOE_HOST_POOL_MIB` | `auto` | tuning | process-wide pool budget: unset/`auto` = `MOE_HOST_POOL_FRAC` % of the MoE host expert bytes (`moe_host_expert_bytes`), split over the host tensors in proportion to their size; `N` = explicit MiB; `0` = disable the pool (with `--host-experts pool` the master is then still dropped and every miss takes the pageable-free bounce path). |
| `MOE_HOST_POOL_FRAC` | **`80`** (r112; `25` in r111) | tuning | the auto percentage (1–100) of the **model's host expert set** (`moe_host_expert_bytes`), per table, capped at that table's expert count — *not* a percentage of RAM.  This is the **whole** non-swappable host footprint, not a tier beside it.  80 % is the measured knee for the "set does not fit in RAM" case (90 % was slower *and* swapped); lower it when RAM is needed elsewhere.  The pool's *content* is chosen by the heat prior (r113), so a bigger pool is not automatically a better one. |
| `MOE_HOST_POOL_RAM_PCT` | **`85`** (r114; `80` in r113) | kill-switch / tuning | ceiling on the **whole** pinned pool, as a percentage of `MemAvailable` measured once at the first pool build.  Raising it 80 -> 85 is a maintainer decision: the ceiling binds **only** on a memory-tight box (on the 184 GiB primary box it is 147 GiB against a 14.9 GiB pool, i.e. inert), and there it only decides how much of the set gets trimmed.  The reference point is the same box's FRAC sweep (r112): FRAC 80 pinned **26.0 GiB** with 0.3 GiB of swap, FRAC 90 pinned 26.4 GiB and was 9 % slower — 85 % of that box's `MemAvailable` (~29 GiB) allows ~24.6 GiB, i.e. a trim that stays below the pinned total it already tolerated, so the ceiling is on the safe side of a measurement.  **It has not been re-measured on the tight box with the r114 binary**; if a soak is wanted, run the field command there with `MOE_HOST_POOL_RAM_PCT=80` vs `85` and watch `VmSwap`, because the interaction with `MOE_HOST_POOL_FRAC` is the untested part.  Bounded (1–100); `0` disables the ceiling (the pre-r113 behaviour, which can silently fail every `cudaHostAlloc` for a table and drop it to the bounce path).  The clamp trims per table and WARNs once, naming both knobs; the one-slot floor per table is kept, so the pinned total can exceed the ceiling by ~`n_tables x host_bytes`. |
| `MOE_HOST_POOL_VERIFY` | unset | diagnostic | `1` byte-compares every pool fill against the model mapping and logs the first mismatching expert (`POOLREAD MISMATCH`).  The instrument that found the O_DIRECT bounce race; costs a memcmp per fill, never default-on. |
| `LLAMA_HOST_MASTER_PINNED` | unset | A/B only | force the pinned master even with `--host-experts pool` — the control arm for a measured comparison. |
| `MOE_HOST_POOL_POLICY` | — | **removed (r40)** | the pooled-table device-policy selector.  The device-policy fill (and the whole device-remap family) was deleted 2026-10-10; pooled tables always fill from the pinned pool (a master fallback only exists in `pinned` mode).  The variable is ignored. |
| `MOE_HOST_POOL_PREFETCH` | `0` | opt-in | routing-driven speculative pool prefill; **off** because a long-prompt sweep showed it hurts until the pool nears full residency (`1` enables). |
| `MOE_HOST_POOL_PREWARM` | `1` | kill-switch | one-shot slot fill when a pool is built, ranked by the persisted heat prior (then the prefill tally, then expert id — r113).  The layout is re-derived as the arena's complement once the arena is seeded, so the prewarm's order is only a warm start. |
| `MOE_HOST_POOL_BGFETCH` | — | **removed (r113)** | the low-priority background eviction-prefetch worker.  The demand path no longer moves an arena victim into the pool (measured: the hand-over cost 2x decode for no L3 benefit, because the pool's CONTENT is what decides the disk traffic), so there is no eviction to prefetch.  The variable is ignored. |
| `MOE_HOST_POOL_DIO` | **`auto`** (r114; `1` in r112, `0` in r111) | tuning / A/B | `auto` (unset, or any negative value) = **decided once, at the first pool build**, from `MemAvailable` vs the host expert set (the same measurement `MOE_HOST_POOL_RAM_PCT` takes): if `planned pool + the whole host expert set fits in MemAvailable`, fills are **buffered** (a `memcpy` out of the model mapping, so the page cache acts as an L3); otherwise they are **O_DIRECT** (the page cache cannot hold the set, so buffering would only compete with the pinned pool for RAM).  The decision and its three inputs are logged (`pool_decide_dio_locked`).  `0` forces buffered, `1` forces O_DIRECT — use them for an A/B or a bisect, and in the unmeasured middle band (the set fits, the set + a full pool does not).  Measured on 2x R9700, 35B-A3B Q4_K_M `-ncmoe 40 --host-experts pool`, 70K prompt: `auto` picks buffered and measures 2103/46.4 t/s (prefill/decode) against 2088/**22.7** for a forced `1` and 2098/49.3 for `pinned`; on the 30 GiB gfx1100 box `auto` picks O_DIRECT, which is the arm that runs clean there.  **The `0`-mode SIGSEGV it used to carry (in the background worker) went away with that worker in r113.** |
| `MOE_HOST_POOL_STAGE_BATCH` | `1` | kill-switch | `1` = a pool-backed prefill staging fills every expert that lives in either VRAM/host tier with **one kernel launch** (the per-expert slot map carries both the arena slot and the pool slot), which is what closes the prefill gap to `pinned`; `0` restores the pre-r114 arm (one `cudaMemcpyAsync` per expert) for an A/B.  Measured, 2x R9700 / 35B-A3B Q4_K_M `-ncmoe 40 --host-experts pool`, 70K prompt, `-ub 2048`: **2103 t/s** with `1` vs **1564 t/s** with `0` (+34 %), identical text. |

### 1.3 The movable-boundary slab (block 06) — `GGML_CUDA_SLAB`, default **on**

**This is the delivery's central allocator.**  ONE slab per device is reserved and mapped **exactly once**
(`cuMemAddressReserve` + one `cuMemMap`), then split by a movable **boundary**: the work pool (the compute
buffer) below it, the MoE arena above it.  Growing the work region is a *boundary move inside the
already-mapped slab* — the lowest arena chunks change owner and the tables living there are evicted — so
**HIP is not called at runtime** and the work region's base VA never moves (a growing layout keeps every
tensor address).  It replaces the per-allocation VMM pool (`GGML_CUDA_COMPUTE_VMM`, **removed**) and the
"chunk the compute buffer so the arena can yield" plan: nothing is ever unmapped, so the ROCm sub-range
`hipMemUnmap` limitation stops mattering.

**r47 (issue #136):** the slab is **armed whenever the MoE expert cache is enabled, independent of
`--fit`**.  `moe_cache_preflight` runs an idempotent env parse before its cache gate, so `--fit off` (no
fit probe load, and therefore no backend init before the preflight) no longer leaves `g_slab_armed` false
with the cache on a raw `cudaMalloc` arena.  `GGML_CUDA_SLAB=0` is the only up-front opt-out; if the slab
is armed but cannot be **created** (no VMM, bad chunk geometry, or too little free VRAM for the reserve)
the run logs the reason and **streams** the experts from the host, and a one-time WARN in the
cache-enable path makes the (now bug-only) "cache on, slab not armed" state loud.  The fail-soft arena
yield now guards on the global `ggml_cuda_slab_enabled()` (not the failing device's slab) and the
stand-down is device-scoped.

| variable | default | class | notes |
|---|---|---|---|
| `GGML_CUDA_SLAB` | **on** | kill-switch | `0` disables the slab.  The plain `cudaMalloc` path returns, together with the pre-slab failure mode (a later wide prefill aborting — the TODO #42 crash).  Since **r47** the slab is armed independent of `--fit`; a slab that is armed but cannot be created logs the reason and the cache streams from the host (issue #136). |
| `GGML_CUDA_SLAB_CHUNK_MIB` | `64` | tuning | the boundary-move granularity (must be a power of two).  Arena *allocations* use the finer VMM granularity (2 MiB), so this does not waste arena. |
| `GGML_CUDA_SLAB_RESERVE_MIB` | `max(8192, 25 % of the device)` | tuning | left OUTSIDE the slab for the weights / KV / draft / workspaces.  This is a **hard** constraint: ROCm will not unmap a sub-range of the slab's single mapping, so a value too small ENDS THE RUN (measured: 4096 -> a failed hipBLASLt workspace, exit 134). |
| `GGML_CUDA_SLAB_MIN_ARENA_MIB` | `2048` | tuning | hard cache floor: the slab is created only if it fits `estimated work buffer + this`.  Otherwise it declines, logs an error and the cache STREAMS from the host (`MOE_EXPERT_CACHE_MIB=0` semantics). |
| `GGML_CUDA_SLAB_HEADROOM_MIB` | `640 + 128 x n_gpu` (768 / 896 / 1024 MiB; `6144` under `-sm layer` with host experts, r36) | tuning | how much stays free outside the slab when `slab_extend` reclaims the reserve the model did not need.  A **MiB value, not a boolean** (the only knob for this; `0` disables the reclaim).  **Not slack**: it must cover every allocation made after that point, including ones we cannot redirect (see below).  Since r36 the MoE cache asks for at least **6144** when every cache table is unsplit and the tables span more than one device (`ggml_cuda_slab_headroom_at_least_mib`); the 255k `-sm layer -ts 59,41` run OOMed at 4096 and passes at 6144.  An explicit value still wins.  **3072 was trialled and rejected (2026-10-10):** the H2D ring moved inside the slab so it no longer spends ~1 GiB here, and 3072 measured **+8.5 % decode step rate** on the field config (arena residency 61.7 -> 64.9 %) — but on the §2.2 wide-prefill config (`--fit off`, IQ4_XS, `-ngl 99 -sm tensor -ncmoe 48 -ub 6144 -c 204800`) 4096 is clean (312 t/s, 0 corruption) while 3072 dies in `hipblaslt.cpp:164`.  **Since r86 the default is `640 + 128 x n_gpu`** (768 / 896 / 1024 MiB): the 2-GPU MTP field run left only **148 MiB** free in the decode steady state at the old 768 default (the decode graph-capture pool temporaries and the 400 MiB Meta all-reduce temp are outside the slab) and settles at ~270 MiB at 896.  An explicit `GGML_CUDA_SLAB_HEADROOM_MIB` is taken **verbatim** (no per-GPU addition); the pre-r86 `4096` remains a valid per-config choice.  **Measured 2026-10-17 on the field GSQ config (1 GPU, `-ub 4096 -c 131072`, `--fit off`, MTP):** 4096 -> arena 15 666.6 MiB / hit 0.9056, 3072 -> 16 705.7 / 0.9147, 2048 -> 17 744.8 / 0.9223, and on a 16 384-token prompt 2048 gives 0.9380 vs 0.9165 at 4096 with identical text — i.e. **~1 pt of hit rate per GiB of headroom converted to arena**, on a config whose widest ubatch is 4096.  It is a per-config tuning value: the 3072 rejection above was `-ub 6144 -c 204800`. |
| `GGML_CUDA_POOL_MIN_FREE_MIB` | `512` when the cache holds host-expert tables, else `0` | tuning / kill-switch | r36.  The workspace pool's **first** attempt refuses like a real OOM when it would leave less than this much VRAM free, so its existing flush + retry runs instead.  The retry has no floor, so it never aborts.  `0` disables the floor. |
| `GGML_CUDA_SLAB_RING_MIB` | `6144` | tuning | MiB cap on the H2D staging-ring region the slab carves as a **work sub-region** (r39).  The auto size is `slots x (largest host table + 512)`, and that estimate comes from `llama_model::max_host_weight_tensor_bytes()`, which can be a MERGED host tensor (every layer/expert in one -- measured 27 GiB on Qwen3.8-Flash-Next where the largest staged slice is 270 MiB), so this cap keeps the region proportional to a real table.  The ring lives between the narrow work floor and the wide work view, never in the arena, and is reclaimed on the prefill->decode drop.  `0` puts the ring back outside the slab (the raw `cudaMalloc` + G4 path).  The field tables (270 MiB) fit in `2560` and give nearly the same prefill as `6144`. |
| `GGML_CUDA_OPTIONAL_ALLOC_MAX_FREE_PCT` | `50` | tuning / kill-switch | caps an **optional** raw allocation at this percentage of the device's *free* VRAM.  Since r39 the op-offload H2D staging ring lives **inside the slab** (see `GGML_CUDA_SLAB_RING_MIB` above), so this now effectively guards the **FA prefill staging arena** only (`GGML_CUDA_SLAB_RING_MIB=0` restores the ring to this path).  A refusal is graceful: the ring falls back to the serial path, the FA staging to the native K/V read (one-time warning) -- and on `fingon` that refusal is *faster* than allowing it (2502.2 vs 2315.1 t/s prefill), so this is an adaptive win, not a limitation.  `0` restores the pre-change unbounded behaviour.  **Inert unless the slab is active on the device**, so a non-host-expert / non-ROCm run is unchanged; it is a cap, never a reservation.  `GGML_SCHED_STAGE_MAX_MB` remains the hard ring override. |
| `GGML_COMPUTE_BUFFER_CHUNK_MIB` | `256` | tuning | the compute buffer is allocated in whole chunks + one spare (`(ceil(need/C)+1)*C`), so growth inside the chunk is free.  `0` falls back to `GGML_COMPUTE_BUFFER_MARGIN_PCT`.  Since **r37** the chunk applies **only when the slab is in use**: a dense model (no slab) falls back to the percentage margin, which removes the +739 MiB of issue #120. |
| `GGML_CUDA_POOL_CACHE_MB` | unset / `0` = unlimited (r46, block 06) | **opt-in tuning** | cap on the bytes of FREED buffers the **legacy** `ggml_cuda_pool_leg` keeps cached.  A long prefill's temporaries grow with the KV length and each smaller predecessor stays cached, so at ~256K the idle VRAM starves allocations outside the pool.  Before a new device allocation, once the cached bytes exceed this MiB value the pool frees them (never during graph capture).  Unset/0/negative/garbage = today's behaviour.  Only the legacy pool is touched (HIP uses it; CUDA's VMM pool is unaffected), and the release is a whole-cache flush, not largest-first eviction. |
| `GGML_CUDA_POOL_WIDE` | **on** (r86) | kill-switch | while the wide (prefill) band is armed, the legacy workspace pool serves its **large** temporaries from the slab's wide-phase auxiliary region instead of caching them outside the slab (`set_wide_routing` + `pool_wide_pin`).  `0` keeps every pool allocation outside the slab.  A `POOL_WIDE_LEAK` tripwire fires at the drop if a pool block is still live. |
| `GGML_CUDA_POOL_WIDE_MIN_MIB` | `1` (r86) | tuning | the smallest pool allocation redirected into the wide band; the band rounds to the slab unit (2 MiB here), so the many tiny prefill scratch blocks stay in the pool. |
| `GGML_CUDA_GRAPH_TRACE` | off | diagnostic | trace the graph capture state machine (`capturing graph`, `capture deferred`, `deferred-capture warmup`).  A capture must never be attempted while `SLAB_STATS ... armed=1` (r86 refuses it). |
| `GGML_CUDA_SLAB_STATS` | off | diagnostic | per-device slab accounting at the arm/drop and destructor.  Since r86 it prints `free=`/`free_min=` **for the selected device** (BETA 1 repeated device 0), `outside_max` / `outside_failed` (the largest allocation the cushion refused) and `pool_wide` / `wide[n_pop hole inval rebase]`; `hole=0` and `outside_failed=0` are the acceptance signals. |

**Why the cards sit near-full.**  `GGML_CUDA_SLAB_HEADROOM_MIB` is what is free *at the moment the slab is
extended*, and the steady state is that minus everything allocated afterwards — measured ~3.7 GiB of it: the
MTP draft buffer (762 MiB), the FA-QSA workspace (762 MiB), hipBLASLt's Tensile code objects and internal
workspace, and the workspace-pool high-water mark.  So ~200-350 MiB free is normal, and raising the headroom
raises it one-for-one (8192 -> ~4.3 GiB free) at the cost of an equal amount of arena.

> **Do not disable hipBLASLt to buy headroom.**  The ROCm BLAS stack allocates its own Tensile code objects
> and workspace behind the application's back, and that class of allocation CANNOT be routed into the slab.
> Measured with `ROCBLAS_USE_HIPBLASLT=0` at `GGML_CUDA_SLAB_HEADROOM_MIB=2048`: the output was CORRUPT
> (`////`), and at 4096 a 16k request returned one token then EOS.  It is not a supported configuration.

---

## 2. Scheduler and H2D staging (block 06)

The whole-shard H2D staging path for host-resident MoE expert tables.  Defaults below are the validated
configuration.

| variable | default | class | notes |
|---|---|---|---|
| `GGML_SCHED_STAGE` | on | kill-switch (value) | master switch for the staging path. |
| `GGML_SCHED_STAGE_MODE` | unset | tuning | staging mode; the delivery uses the `stage_d2d` form (redirect is corruption-prone). |
| `GGML_SCHED_STAGE_MIN_TOKENS` | `64` | tuning | width gate floor.  Below it the copy loop's gather branch serves the input instead. |
| `GGML_SCHED_STAGE_SLOTS` | unset | tuning | ring slot count. |
| `GGML_SCHED_STAGE_MAX_MB` | unset | tuning | hard ring budget cap; the slab-gated free-VRAM cap `GGML_CUDA_OPTIONAL_ALLOC_MAX_FREE_PCT` (§1.3) also applies to a growth. |
| `GGML_SCHED_STAGE_TABLE_REF_MB` | `0` | tuning | `0` = width-only gate (r18 disabled the stale r7 table-size scaling; a positive value restores it for A/B). |
| `GGML_SCHED_EVENTS` | on | kill-switch | set `0` to drop the cross-device event ordering. This was the pre-r12 workaround for the `-sm layer` + host-expert garbage-prefill bug; it is **fixed** in block 06, so leave it on. |
| `GGML_SCHED_DEVGATHER` | on | kill-switch | device-gather path. |
| `GGML_SCHED_MOE_DUP_SPLIT` | **on** (r96, block 09) | kill-switch | a second `MUL_MAT_ID` consumer of the expert weights the current split already stages (qwen4exp's full-row MTP export tail next to its gathered logits tail) starts a split of its own, so each consumer is staged for its own routing.  Required for correctness as well as throughput: in one merged split the second consumer reads the expert-cache arena slots staged for the first consumer's routing, which produced non-greedy-pure text with 0.00000 draft acceptance on `-sm layer` + `-ncmoe` + MTP and cost a full table copy per prompt chunk on `-sm tensor`.  `0` restores the merged split (A/B and bisection only).  Detail: `GREEDY-PURITY.md` §43. |
| `GGML_SCHED_SYNC_GRAPH_INPUTS` | on | kill-switch | extra graph-input sync. |
| `GGML_SCHED_DEBUG` | unset | diagnostic | scheduler debug output. |
| `GGML_SCHED_DEBUG_REALLOC` | unset | diagnostic | log buffer reallocations. |
| `GGML_META_SPLIT_COPY` | unset | tuning | meta-backend split copy handling. |
| `GGML_META_SEG_ASYNC` | **on** (r101, block 10) | kill-switch | the meta backend's **row-aligned segmented `set_tensor_async`** splice: a segmented (`n_segments > 1` or `nr > 1`) host-expert table upload is issued as one async `set_2d_async` per (segment, repeat, device) plus an async `set_async` for the MMQ tail pad, instead of one synchronous setter call.  Mid-row ranges stay synchronous by design (the loader's chunked upload owns a staging ring that may be reused on return).  `0` restores the fully synchronous segmented setter (A/B and bisection only; measured neutral on the gemma4 miss path — the win there is the arena sizing, not this). |
| `GGML_META_SS_VERIFY` | off | diagnostic | `1` recomputes every outermost meta split-state cache hit and aborts on a stale entry (r25 added the 8-version + compacted cache; this verifies it). |
| `GGML_META_SS_SCRATCH` | **on** (r100, block 09) | kill-switch | the meta split-state cache's pre-warm walk keeps its `wstack`/`wseen` in a reused per-thread `monotonic_buffer_resource` (1 MiB, released per walk) instead of allocating one heap node per visited tensor on every graph re-allocation.  Inert on the computed states (the walk visits the same tensors in the same order; `GGML_META_SS_VERIFY=1` re-derives every outer hit and agrees).  `0` restores the heap containers (A/B and bisection only). |
| `GGML_STAGE_META_REDIRECT` | off | diagnostic | meta redirection instead of the explicit d2d completion. |
| `GGML_STAGE_NO_RESTORE` | off | diagnostic | skip the redirect restore (debug only — unsafe). |
| `GGML_STAGE_GATHER_SCRATCH` | off | diagnostic | force the gather scratch path. |
| `GGML_MOE_CACHE_STAGE` | on | kill-switch | r83.  With `-ncmoe`/`-cmoe` host experts, a whole-table staging copy is filled from the expert-cache arena for the experts already resident and from the pinned host master for the rest, so only the non-resident experts cross PCIe.  `0` restores the full whole-table upload.  It declines to the plain upload for a table the slab stood down mid-prefill, an unpinned host master or a geometry mismatch; `moe_cache_report` prints the staged arena/host split and the H2D percentage. |

`GGML_MOE_CACHE_INPLACE` (r36) was removed with the device-remap path at r40 and is not read by this
set; the cache-aware staging above is the only prefill residency path.

---

## 3. MTP / speculative decoding

| variable | default | class | notes |
|---|---|---|---|
| `MTP_DRAFT_N_UBATCH` | `512` | tuning | caps the MTP draft's encoder-injection chunk.  The draft only drafts `n_max+1` tokens, so a 512-token chunk is plenty, and the ~1.6 GiB/device the wide chunk held at `-ub 8192` goes to the MoE arena.  `0` restores the target's `-ub` (no cap); a tiny cap (e.g. 4) costs prefill speed. |
| `LLAMA_SPEC_DRAFT_N_MAX_CLAMP` | `1` = clamp on | kill-switch | clamps `--spec-draft-n-max` to 15 (the recurrent snapshot bound). `0` escapes the clamp; **purity is only promised to 7**. |
| `LLAMA_MTP_DRAFT_OP_OFFLOAD` | unset | tuning | op-offload behaviour for the draft model. |
| `LLAMA_MTP_SPARSE` / `LLAMA_MTP_SPARSE_DECODE` | unset | tuning | sparse MTP variants. |
| `LLAMA_MTP_INGEST_TAIL` | unset/`0` = every row | **opt-in tuning** (r52, block 02) | feeds the MTP draft only the last N positions of each prompt (the server reports each prompt end via `common_speculative_set_prompt_end()`); generation rows are always fed.  The draft loses look-back over the skipped prefix only, so output is unchanged, but draft acceptance drops: on a ~31k-token prompt, `4096` measured prefill **+4.8 %** and decode **-4.4 %** (acceptance 0.821 -> 0.715).  Kept opt-in because it is a speed/look-back trade, not a pure win.  Tools other than the server never report a prompt end, so there the variable has no effect. |
| `LLAMA_ARG_SPEC_DRAFT_MTP_VOCAB` | unset/`0` = off | **opt-in tuning** (r107, block 13) | env alias for `--spec-draft-mtp-vocab N`: the MTP draft head scores only the LM-head rows for token ids < N plus every control/user-defined id, and scatters the logits into a full-vocab row of `-inf`.  The target's verification is untouched, so output is unchanged by construction and only proposals are lost.  **N is payload-specific**: 98304 on Qwen3.8-27B Q8_0 with `--spec-draft-n-max 7` (four-axis `-n 3000`: R +1.3 %, P +1.7 %, C +2.4 %, K +0.8 %; acceptance 0.6193 -> 0.6194), 64000 is a *loss* there at n-max 9, and gemma4's only lossless cut is 245760/262144 (a no-op).  Costs `N/n_vocab` of the LM head in VRAM (510 MiB at 98304 on the 27B, per device under `-sm tensor`) and is **not** in the `--fit` estimate.  Purity holds inside `n_max <= 7` (`GREEDY-PURITY.md` §48).  **Device count decides whether it pays** (r109 validation): the subset head is *mirrored* on every device under `-sm tensor` while the untrimmed head is *split*, so its draft matmul costs `N` columns per device versus `n_vocab / n_devices` — enable it only when **`N * n_devices < n_vocab`**.  On the 27B (vocab 248320) 98304 is +1.4 % aggregate at 2 GPU (share 124160) and **-2.2 % at 3 GPU** (share 82773, the delivery's server shape), and at 3 GPU no N pays: 64000 is below the share but loses acceptance (0.68878 -> 0.67260) for -9.4 %.  Depth 16384 is flat.  Record: `archive/work/spec-draft-mtp-vocab/VALIDATION-2026-10-22.md` |
| `LLAMA_DRAFT_SCHED2` | **on** (r65, block 09) | kill-switch | runs the MTP draft context's graphs **with outputs** on a second scheduler (`llama_context::sched_alt`), so the no-output ingest graph and the 1-token draft-step graph both stay allocated and are reused instead of re-split/re-allocated every cycle.  Needs a per-scheduler meta view slot and a `slab_compute_plain` device-iface entry (the second scheduler's small COMPUTE buffer bypasses the slab).  On Qwen3.8-Flash-Next + shared MTP (`-sm tensor`, 2 GPUs) the draft's graph reallocations drop 1068 -> 34 and generation is about +1.5 %; kill switch `0` restores the single scheduler.  The second scheduler depends on block 00's graph-layout fingerprint (r84, issue #183): a draft graph that keeps its node count but changes its node order or output marking (another sequence's in-graph sampling chain) re-reserves instead of reusing a layout computed for a different graph. |
| `GGML_LF_DFLASH_DEV` | **on** | kill-switch | DFlash device-resident layer-input features (F1).  `0` uses the host path.  Default-on since r26; if the device buffers cannot be allocated the target warns once and stays on the host path for the rest of the context.  Since **r106** a Meta (tensor-split) layer-input buffer forces the host path regardless of this variable (the device copy is one pointer range, which the meta backend cannot express; the device path there aborted).  Since r53 F1 also covers several sequences (`--parallel >= 2`); with host-resident MoE experts (`-ncmoe`/`-cmoe`, `llama_model_moe_host_expert_dev_count(...) > 0`) several sequences stay on the host path and log a warning (the movable-boundary slab's device reads, issue #127 MoE form).  One sequence is unchanged. |

The tuned adaptive-MTP controller is selected with **`--spec-type draft-mtp-adaptive`** (a CLI flag, not
an environment variable).  Plain `--spec-type draft-mtp` does not use it.

---

## 4. Model loading and context

| variable | default | class | notes |
|---|---|---|---|
| `LLAMA_MMAP_HOST_EXPERTS` | — | **removed (r33)** | the legacy alias for `--host-experts`.  The pageable `--host-experts mmap` mode was dropped in r33 (issue #116): a no-XNACK GPU (gfx1201 reports `XNACK enabled: NO`) cannot read a pageable host master in a kernel, so `-ncmoe`/`-cmoe` experts are always pinned (`ROCm_Host`).  The variable is now ignored.  The bounded pinned DIO host tier that replaces the reclaimable-page-cache idea is the `archive/work/host-expert-dio-cache/` campaign. |
| `LLAMA_LOAD_RELEASE_MMAP` | **on** (block 06, r49) | kill-switch | unmaps each model-mapping range right after the tensor is copied to its device buffer, and skips the up-front whole-file prefetch, so a `-ncmoe` load does not hold the full file mapping and the pinned host expert master at the same time.  `madvise(MADV_DONTNEED)` is not enough here (the ROCm runtime re-faults those pages on the next pageable H2D copy), so the range is munmapped; the exact ranges a host-pointer tensor points into (a tied embedding is loaded host-side and device-side from the same range) are preserved.  `0` restores the pre-r49 prefetch-then-unmap-at-end behaviour.  Skipped under `--load-mode mlock`/`--mlock`, `--check-tensors` and lazy tensors. |
| `LLAMA_TENSOR_HOST_BUFT` | unset | tuning | host buffer type for overridden tensors. |
| `LLAMA_DEVICE_INPUT` | off | **opt-in** | device-side input handling. |
| `LLAMA_OUTPUT_PINNED` | **on** (r65, block 12) | kill-switch | when the output device is a meta (tensor-split) device with no host buffer type of its own, `output_reserve` uses the first simple device's pinned host type for the output buffer (logits/embeddings/MTP hidden state).  Without it those per-step D2H reads land in pageable memory and each blocks the host; the output buffer is never scheduled on, so its `.device` does not matter.  About +2.7 % MTP decode on Flash-Next (`-sm tensor`, 2 GPUs) and about +4.7 % on the dense 27B; `0` restores the CPU-buffer fallback.  The meta device's own `get_host_buffer_type` is unchanged. |
| `LLAMA_DROP_COMPUTE_BUFFERS` | **on** (every tool) | tuning / kill-switch | drop the wide-prefill compute layout at the prefill→decode transition so a wide `-ub` and a large arena coexist (`-ub 8192` cache-auto cli decode 45.6 → 78.7 t/s).  Follows `common_params::drop_compute_buffers`; set the env to `0`/`1` to override.  **A server may drop too** (this was cli-only until r22): the movable-boundary slab reclaims a later wide layout with a boundary move, which is verified on `wide1 → short → wide2` at `-ub 8192` (0 aborts, all coherent).  `0` is only needed where the compute layout CANNOT be reclaimed — i.e. with `GGML_CUDA_SLAB=0`. |
| `LLAMA_DROP_EXTRA_RESERVE_MIB` | `0` | tuning | when the drop fires, VRAM held out of the arena per device for a later compute growth.  Default `0` — the compute-buffer margin covers the small post-drop growth and the arena's layer-uniform re-size absorbs fragmentation, so a reserve only costs arena. |
| `LLAMA_LAZY_BUF_MB` / `LLAMA_LAZY_IO_THREADS` / `LLAMA_LAZY_READER_STATS` | unset | tuning / diagnostic | lazy-mode buffer size, reader thread count, reader statistics. |
| `LLAMA_KV_N_PAD_MIN` | `256` | tuning (**opt-in**) | raises the n_kv padding floor (r25).  n_kv is padded to this many cells, so a larger value keeps the per-device tensor-split graphs constant for longer (the PR measured `1024` as the useful value, `4096` gave nothing more).  Default unchanged. |
| `LLAMA_KV_N_PAD_PREFILL` | `8192` on a multi-device split, `0` on a single device | default-on (r79, block 10); `0` disables | a coarser n_kv pad for **prompt ubatches only** (`n_tokens > 64`), rounded up to a power of two, so consecutive prompt chunks share one graph shape instead of rebuilding the split state and re-allocating every ubatch.  It applies only once the decode-padded occupancy is past `LLAMA_KV_N_PAD_PREFILL_FROM`, so a model's small-context shortcuts (qwen4exp's dense attention for the first ~2051 cells) still apply; decode/verify batches keep the decode pad, and the extra cells are masked exactly as before (prefill logits are unchanged).  **Default-on only when more than one device is in use** (`model.n_devices() > 1` or the meta split state has more than one device); a single GPU keeps the r77 default of `0` because the coarse pad only adds masked attention work there (-0.35 % measured), and that shape is now inactive.  The env value still overrides the default (`0` disables).  Measured on r79, `-ub 2048 -b 2048`, q8_0 KV, 31 k-token prompt: **+2.5 %** prefill on 35B-A3B (3 GPUs, `-sm tensor`), **+0.8 %** on the dense 27B (3 GPUs, tensor), and **+42 % / +49 %** on a 3-GPU `-sm layer` split (MoE / dense), with the decoded text identical; the r77 2-GPU numbers were +2.0 % (MoE) and +1.0 % (dense), and the 1-GPU shape is inactive.  It affects the **unified** KV cache only (not the iswa/DSA caches) and is not for training, whose graphs assert `n_kv == n_tokens`. |
| `LLAMA_KV_N_PAD_PREFILL_FROM` | `4096` | tuning (r77, block 10) | the decode-padded occupancy (cells) above which `LLAMA_KV_N_PAD_PREFILL` starts to apply.  Compared with `GGML_PAD(used, LLAMA_KV_N_PAD_MIN)`, not with the raw used count. |
| `GGML_READBACK_SYNC` | **on** | kill-switch (block 06, r43) | completes the per-ubatch device->host logits/embd readbacks before the next ubatch's graph reuses the same device output tensor.  Required because ROCm's pinned async D2H copy is not ordered against the following compute, which otherwise lets an earlier ubatch's host rows receive a later ubatch's data (multi-ubatch per-token outputs: perplexity / KLD).  `0` restores the unordered readback for A/B.  A single-ubatch decode is unaffected either way. |
| `LLAMA_STATE_GET_MERGE_GAP` | `262144` (256 KiB) | tuning (r56, block 12) | in `llama_io_write_host` (the state / prompt-cache save), consecutive deferred `write_tensor` ranges of one tensor whose gaps are at most this many bytes are read as one `ggml_backend_tensor_get` span and scattered on the host; contiguous ranges are read straight into the output.  Under concurrent decoding a slot save was ~8,000-10,000 short synchronous reads on ROCm (340-400 ms); merged it is one get per tensor (25-65 ms).  The saved bytes are identical.  `0` restores the per-range reads. |
| `LLAMA_STATE_ASYNC` | **on** (r96, block 12) | kill-switch | `llama_io_write_host` queues its deferred state-save reads as `ggml_backend_tensor_get_async` into one pinned staging buffer kept by the context, then synchronizes each backend once and copies to the caller's buffer, instead of one synchronous read per range per device.  A recurrent model's checkpoint is about 75 small ranges, so under `-sm tensor` it paid about 150 device syncs before every prompt chunk of a follow-up turn (Flash-Next + MTP, 2 GPU: 55-59 ms of TTFT on the short follow-up turns).  `0` restores the synchronous path.  The staged bytes are identical. |
| `LLAMA_STATE_ASYNC_MAX_MIB` | `256` | tuning (r96, block 12) | the largest state (`llama_io_write_host` tensor bytes) that takes the batched read path; a larger state, which includes every whole-slot save with a real KV cache, keeps the synchronous path, so no save pins gigabytes.  The staging buffer is **retained by the context** across saves and rounded up to 16 MiB (about 64 MiB for the Flash-Next checkpoint), and it only ever grows, so a small save after a large one keeps the large allocation.  It is one buffer per context: state saves on one context must not run concurrently.  Raising this raises the per-context pinned ceiling by the same amount. |

---

## 5. CPU MoE offload threading

| variable | default | class | notes |
|---|---|---|---|
| `GGML_CPU_MOE_OFFLOAD_THREADS` | derived (block-06 cap) | tuning | overrides the thread cap for `-ncmoe` offloaded-MoE decode.  The cap only covers that case. |
| `GGML_CPU_DISABLE_TINY_GRAPH_SINGLE_THREAD` | off | diagnostic | disables the single-thread path for tiny graphs. |

Thread sizing is **not** an environment variable and is not optional: `/usr/local/bin/pin_gpu_irqs.sh`
puts the GPU IRQs on the top `NUM_GPUS` cores, and the default `-t` puts the worker pool there and
starves the GPU.  Size `-t` (or `--cpu-mask` with `-t` inside the mask) to leave those cores free.
See `AGENTS.md`.

---

## 6. Multi-GPU comms

| variable | default | class | notes |
|---|---|---|---|
| `GGML_CUDA_ALLREDUCE` | `hybrid` on Linux | tuning | `hybrid` (NCCL for large, internal for small) \| `internal` \| `nccl` \| `ce` (SDMA copy-engine, 2 GPU).  Unrecognised values warn and fall through to the platform default.  `nccl` is **not** bit-identical under `-sm tensor` (the internal AR BF16-round-trips), so use it as a smoke comparison only. |
| `GGML_CUDA_AR_SPIN_TIMEOUT_MS` | `2000` (r59, block 01) | **diagnostic / tuning** | the internal all-reduce's **soft** spin deadline in ms, measured with `wall_clock64()` at the device's wall-clock rate.  A peer wait that exceeds it is a late peer (a driver queue stop), not a lost one: the kernel reports it once and **keeps waiting**, so the reduction still completes.  `0` disables the soft check (and, with it, the hard cap below).  Before r59 the budget was a `clock64()` cycle count with a 20 ms default; on gfx1201 `clock64()` can step backwards while a queue is stopped, so the budget wrapped and a slightly-late peer was treated as lost. |
| `GGML_CUDA_AR_SPIN_HARD_MS` | `20000` (r59, block 01) | **kill-switch / safety** | the internal all-reduce's **hard** spin cap in ms.  If a peer wait exceeds it the kernel treats the peer as lost: it sets the host poison flag and the next call falls back to the meta-backend butterfly.  This is the last-resort bound that keeps an unbounded spin from making the compute queue non-removable (the MES `REMOVE_QUEUE` hazard).  `0` = never poison (unbounded).  A value below the soft budget is clamped up to it. |
| `GGML_CUDA_AR_CE_SCRATCH_MIB` | `0` = unlimited (r47, block 12) | **opt-in tuning** | budget for the copy-engine (`GGML_CUDA_ALLREDUCE=ce`) all-reduce scratch: each of the three per-rank staging buffers is `n_rank * ceil(ne/n_rank) * 2 B`.  Above it, CE returns `false` **before** any collective phase and the dispatcher falls back to the internal pipeline for that call; the fallback is sticky after the first failed grow, so an allocation failure also degrades cleanly instead of aborting.  `0` keeps the pre-r47 unbounded behaviour. |
| `GGML_CUDA_P2P` | off | tuning | enables peer access.  Note VMM allocations need explicit `cuMemSetAccess` for P2P (see `FOLLOWUP-compute-arena-chunking.md`). |
| `GGML_CUDA_AR_SMALL_BLOCKS` | `4` (r46, block 12) | kill-switch / tuning | block count for a **small** internal all-reduce (decode/verify, `<= GGML_CUDA_AR_SMALL_BYTES`).  Each block signals and polls its own arrival slot, so fewer blocks shorten the call.  `GGML_CUDA_AR_SMALL_BLOCKS=8` restores the pre-r45 launch; the fused stage and larger messages always keep 8. |
| `GGML_CUDA_AR_SMALL_BYTES` | `65536` (r46, block 12) | tuning | the small-message threshold in bytes for the knob above. |
| `GGML_CUDA_AR_P2P` | off (r46, block 12) | **opt-in** | 2-device, not-fused P2P push all-reduce: each device writes its wire data and arrival token into the peer's fine-grained VRAM and reads locally, replacing the host ring and the three all-thread `__threadfence_system()` calls with a store-count drain plus one system-scope release store.  Falls back to the host ring if peer access / fine-grained allocation fails or there are not exactly 2 devices.  Bit-identical; MTP-neutral on the reporter's box, +2.6 % one-token decode. |
| `GGML_CUDA_AR_P2P_LITE` | `1` (r46, block 12) | kill-switch | `0` keeps the full `__threadfence_system()` fences on the P2P path (A/B only). |
| `GGML_CUDA_AR_KER_EVENTS` | `0` = off | **opt-out / diagnostic** (r52, block 01) | the chunked kernel path no longer records `ev_pool[*][slot].ker` after every all-reduce (each record is a ROCm marker packet the GPU processes after every AR kernel); slot reuse on that path is already ordered on the GPUs by the arrival tokens, so `acquire_slot` syncs only when the slot's last user recorded the event.  `1` restores per-AR recording for A/B; pacing (`GGML_CUDA_AR_PACE=1`) also forces it. |
| `GGML_CUDA_AR_P2P_LARGE` | off (r52, block 01) | **opt-in** | 2-device copy-engine path: each device pulls the peer's contribution straight into `dev_tmp` with `hipMemcpyPeerAsync` (one PCIe crossing) instead of bouncing both halves through pinned host memory (two).  Same add kernel on the same bytes, so bit-identical; a 10.5 MB exchange measured 808 -> 437 us on the reporter's pair, +1.3 % on a 31.5k prefill.  Unset/`0` keeps the host-bounce path. |

---

## 7. Fusion A/B switches

Each of these disables exactly one optimization so it can be bisected.  **The feature is on by default;
the variable turns it off.**  Read the idiom column carefully — setting a presence-only switch to `0`
still disables the feature.

**The fusions are ON, and stay ON.**  The one known stand-down path — the cache-aware guard against
per-table slab eviction (`TODO.md` #50, evidence in `archive/work/slab-ring-region/FINDINGS-numerics.md` F3) — is a
pre-existing property of the arena, not a reason to turn them off.  Measured on the field config
(Qwen3.8-Flash-Next IQ4_NL, `-sm tensor -ncmoe 48`, 32 358-token prompt, `--spec-type none`, warm):

| | prefill t/s | decode t/s |
|---|---:|---:|
| fusions on (default) | 945-972 | 61.3-65.2 |
| `GGML_CUDA_DISABLE_FUSION=1` | 845-890 | 57.5-65.3 |

so a full disable costs **~9-10 % prefill and ~6 % decode**, and the fusion-off prefill (845-890) is
*below* the unpatched stock reference (922) — it gives back the delivery's prefill win.

**To restore the full speed** after an A/B or a debug recipe, make sure none of the switches below is set:
unset `GGML_CUDA_DISABLE_FUSION` and the rest of §7.2/§7.3, and unset (or `=1`) every `GGML_CUDA_FUSE_*` in
§7.1.  A clean environment is already the full-speed configuration — there is nothing to add, only
switches to remove.  (`GGML_CUDA_DISABLE_FUSION=1` is a **sledgehammer**: it also skips the
`graph_optimize` alloc-dependency pass and its shared-expert node reorder, so its cost is not the cost of
any single fusion.)

### 7.1 `GGML_CUDA_FUSE_*` — presence of the variable with a value, `0` disables

`GGML_CUDA_FUSE_ADD_RMS_Q8`, `GGML_CUDA_FUSE_CPY_BATCH`, `GGML_CUDA_FUSE_GATE_BETA_VERIFY`,
`GGML_CUDA_FUSE_GDN_BETA_SIGMOID`, `GGML_CUDA_FUSE_GDN_CONV_VERIFY`, `GGML_CUDA_FUSE_GDN_GATE`,
`GGML_CUDA_FUSE_GLU_Q8_1`, `GGML_CUDA_FUSE_HC_COMBINE_MIX`, `GGML_CUDA_FUSE_Q8_1_VERIFY`,
`GGML_CUDA_FUSE_SIGMOID_MUL_ADD`, `GGML_CUDA_FUSE_SWIGLU_MMQ`.
These use `getenv(...) == nullptr || atoi(...) != 0`, so unset = **on** and `0` = off.
(Git history note: these were originally *opt-in* `=1` switches; they are now default-on kill-switches.)

Four more from r102 (PR #200, block 10), all bit-identical with their own switch: `GGML_CUDA_FUSE_GATE_BETA_BF16`
(qwen4exp's alpha/beta BF16 projections plus `softplus(alpha + dt) * a` in one `mul_mat_vec_f` launch),
`GGML_CUDA_FUSE_GDN_CONV_NORM` (the q/k l2 norm pair folded into the direct conv kernel; falls back when a
SCALE output would overlap the conv's `x`/state/weight/output, which the allocator may do since all of them
are dead after the CONCAT), `GGML_CUDA_FUSE_CONT_GATE_Q8_1` (the attention gate's row-strided view read in
place by the gate -> Q8_1 kernel, so its CONT copies nothing) and `GGML_CUDA_FUSE_GDN_NORM_GATE` (qwen4exp's
GDN output `RMS_NORM * w` computed inside the gate kernel).  Worth +0.2-0.3 % on 27B MTP and +0.7 % on
Flash-Next 2 GPU `-sm tensor` + MTP, flat on 35B-A3B 1 GPU.  The GDN-norm pair is the only fusion in the set
whose skip and emit are two decisions (the norm node comes before the gate that computes it): while a norm is
pending no other fusion may start in between, so the two abort tripwires are unreachable.
`GGML_CUDA_FUSE_GATE_BETA_BF16` is **multi-sequence-clean since r108** (issue #204): it used to launch with the
gate chain's `MUL` as the `mmvf` dst, which gave the launch `n_seq_tokens` columns and `n_seqs` channels for a
flat one-channel `y`, so every sequence but the first got sequence 0's alpha/beta gates (invisible to
single-stream text/MTP gates; only multi-sequence serving saw it).  The switch still exists as an A/B
kill-switch, and `tests/test-fusion-gate-beta-multiseq.cpp` is the gate that covers it — no model needed, so
run it after touching any fusion that consumes a reshaped chain (`GREEDY-PURITY.md` §49).

The same idiom — and therefore also default-on despite the name — covers
`GGML_CUDA_DISABLE_IDX_RELU_SUM`, `GGML_CUDA_CONCAT_VERIFY` and (r46, block 15) `GGML_CUDA_FUSE_GDN_STATE_GATHER`.

`GGML_CUDA_DISABLE_NORM_PAIR` is value-gated (listed with §7.2): `0` keeps the paired GDN q/k norm.

`GGML_CUDA_FUSE_ADD_RMS_Q8=0` (r78) is the A/B switch for the **single-token** ADD + `rms_norm_q8_1`
fusion as well as the verify band: the r78 change dropped the old `ne[1] > 1` gate, so the FFN residual
ADD after an MoE/`ffn_out` producer now folds into the norm at one token too.  Measured on gfx1201:
dense 27B UD-Q4_K_XL, 3-GPU tensor, q8_0 KV, tg256 54.88 t/s default vs 53.91 with `=0` (the pre-r78
behaviour); the fused kernel's values are those of the unfused `k_bin_bcast` + `rms_norm_q8_1` pair, and
the same-seed text is byte-identical either way.  Not reached on Qwen3.6-35B-A3B, whose residual add is
already consumed by the fused shared-expert output epilogue.

**Arch scope of the three verify-band switches (r95).**  `GGML_CUDA_FUSE_Q8_1_VERIFY`,
`GGML_CUDA_FUSE_GDN_CONV_VERIFY` and `GGML_CUDA_FUSE_CPY_BATCH` gate the **verify band** (2..8-token
Q8_1 pre-quantize fusions, the direct GDN conv for 2..255-token batches, and the batched run of up to 16
same-layout f32 `GGML_OP_CPY` nodes) on **RDNA4 and RDNA3_0 (gfx1100-1102)**.  They were RDNA4-only
until r95 (PR #192 + PR #193); gfx1101-gfx1102 are inside the arch predicate but are **not explicitly
validated**, and **RDNA3_5 is excluded** (`GGML_CUDA_CC_IS_RDNA3_0` is `0x1100 <= cc < 0x1150`).
Every one of them is a default-on kill-switch: `=0` restores the pre-r95 RDNA3_0 path.  The three are
bit-identical to the paths they replace (gfx1100 `W = 1..8` width-probe maxdiff 0, greedy text identical
for `none` and `draft-mtp n3`, prefill-logit KLD 0.000000 / 100.000 %); the GDN conv keeps its
pre-existing single-device restriction, the batched CPY does not, and RDNA3_0 multi-device
(`-sm tensor` / `-sm layer`) is a recorded open gap — the batched CPY fires ~450 times (`-sm layer`) /
~1350 times (`-sm tensor`) per 60-token MTP run on 3x gfx1201, so that arm is exercised on RDNA4 but
not measured on RDNA3_0.

### 7.2 `GGML_CUDA_DISABLE_*` — value-gated (`=1` disables, `0` keeps it on)

`GGML_CUDA_DISABLE_FUSED_ADDMUL`, `GGML_CUDA_DISABLE_FUSION`, `GGML_CUDA_DISABLE_GDN_CPY`,
`GGML_CUDA_DISABLE_HC_FUSION`, `GGML_CUDA_DISABLE_L2_NORM_PAIR`, `GGML_CUDA_DISABLE_MOE_DOWN_FOLD`,
`GGML_CUDA_DISABLE_NORM_PAIR` (r81, the paired GDN q/k norm below),
`GGML_CUDA_DISABLE_MOE_MMQ_FUSION`, `GGML_CUDA_DISABLE_MWR`, `GGML_CUDA_DISABLE_NORM_Q8_1`,
`GGML_CUDA_DISABLE_NORM_ROWS`, `GGML_CUDA_DISABLE_ROPE_SETROWS`, `GGML_CUDA_DISABLE_SCALE_UNARY`,
`GGML_CUDA_DISABLE_SHEXP_DOWN_GATE`, `GGML_CUDA_DISABLE_SNAKE`, `GGML_CUDA_DISABLE_SSM_CONV_IN`,
`GGML_CUDA_DISABLE_SSM_PRESCAN`, `GGML_CUDA_DISABLE_WEIGHTED_DOWN`.

`GGML_CUDA_DISABLE_SHEXP_DOWN_GATE=1` is the A/B switch for the byte-identical fused shared-expert band
(`1 <= nt <= 8`).

`GGML_CUDA_DISABLE_NORM_PAIR=1` (r81) restores the two separate `rms_norm_f32<256, false, false, true>`
launches for the GDN q and k l2 norms that `build_gdn_l2_norm` builds; the default runs both in one
`rms_norm_scale_pair_f32<256>` launch (blocks `[0, nrows)` take q, `[nrows, 2*nrows)` take k, same
per-row body, so each output is bit-identical).  It is taken only when both inputs are F32 views of the
same `view_src` with equal shape, strides, eps and scale and only no-op nodes sit between the pairs.
Measured on gfx1201 35B-A3B Q4_K_M 2-GPU tensor: tg256 114.4 -> 115.7 t/s (+1.2 %, 3/3 rounds) and the
kernel count for the norms halves (7500 -> 3750 per 120-token decode).

### 7.3 `GGML_CUDA_DISABLE_*` — **presence-only** (any value, including `0`, disables)

`GGML_CUDA_DISABLE_CONV_FUSION`, `GGML_CUDA_DISABLE_MMID_512`, `GGML_CUDA_DISABLE_MMQ_ROUTED`,
`GGML_CUDA_DISABLE_MMVQ_DENSE_BAND`, `GGML_CUDA_DISABLE_MMVQ_MOE_BAND`,
`GGML_CUDA_DISABLE_RMS_NORM_MUL_ROPE`, `GGML_CUDA_DISABLE_ROPE_SET_ROWS`,
`GGML_CUDA_DISABLE_TOPK_MOE_FUSION`,
(r78, block 10) `GGML_CUDA_DISABLE_ROPE_FWHT` and `GGML_CUDA_DISABLE_FWHT_Q8_1`,
and (r81, block 10) `GGML_CUDA_DISABLE_ROPE_MROPE_FUSE` and `GGML_CUDA_DISABLE_ROPE_FWHT_SET_ROWS`.

`GGML_CUDA_DISABLE_ROPE_MROPE_FUSE` (r81) puts `GGML_ROPE_TYPE_MROPE` / `IMROPE` back on the unfused
`rms_norm_f32` + `rope_multi` + `fwht_cuda` chain (the r78 matcher, NORMAL/NEOX only);
`GGML_CUDA_DISABLE_ROPE_FWHT_SET_ROWS` (r81) stops the fused rope kernel from also writing the q8_0 K/V
cache rows, so the two `SET_ROWS` launches come back.  **Since r101 it is live on iSWA archs too**: the
iSWA KV builder now expands `q, v, k` (instead of `q, k, v`), so the V block no longer sits between the K
rotation and the K cache write and the matcher admits the fusion — gemma4 with `-ctk/-ctv q8_0` folds
1152 `k_set_rows_q8_0_group` launches to 192 and runs `rms_norm_mul_rope_f32<...,kv=true>` 480 times in
a 8-token run.  It stays inert where the V-row write cannot apply (gemma4's 512-wide full-attention
layers: `fwht_n` is `{64,128,256}` and the fused V-row write assumes `ncols <= 256`).

The two r78 switches split PR #172's two fusions: `GGML_CUDA_DISABLE_ROPE_FWHT` keeps the KV rotation's
FWHT as its own `fwht_cuda` launch (rope only, no shared-memory staging row) and
`GGML_CUDA_DISABLE_FWHT_Q8_1` stops the attention-output FWHT from also writing the output projection's
Q8_1 activation (the projection then runs its own `quantize_q8_1`).  Both fusions are bit-identical to
the unfused path; measured together on gfx1201 Gemma4 12B QAT UD-Q4_K_XL (1 GPU, layer, q8_0 KV):
tg256 61.05 t/s default, 60.41 with `DISABLE_ROPE_FWHT=1`, 60.80 with `DISABLE_FWHT_Q8_1=1`, 60.15 on
the r77 build.  They only fire for NORMAL/NEOX rope with the `RMS_NORM, MUL, ROPE` chain, so on r78 they were
inert on `rope_multi` models (all Qwen3.x here) -- a trace showed `rope_multi` + `fwht_cuda` there.
**r81 closes that gap:** `GGML_ROPE_TYPE_MROPE` / `IMROPE` are admitted too, so the same two fusions
(and the K/V cache write fold) now run on every Qwen3.x model.  Measured on gfx1201 35B-A3B Q4_K_M,
1 GPU, 120-token decode: `rope_multi` 2500 -> 40, `fwht_cuda<256>` 2500 -> 40,
`rms_norm_f32<256,true,...>` 6120 -> 3660, and 2460 `rms_norm_mul_rope_f32<256,...,256>` launches
replace them; with the cache-write fold, `k_set_rows_q8_0_group` 2500 -> 20 (all 35B-A3B 2-GPU tensor,
see `../WORKLOG.md` 261017.008).

### 7.4 Other kernel tuning

| variable | default | notes |
|---|---|---|
| `GGML_CUDA_MMQ_J_MAX` | tuning | MMQ `J` tile width cap. |
| `GGML_CUDA_MMVQ_RDNA3_SMALL_M` | `8192`, RDNA3_0 only — **kill-switch / tuning** (block 08) | row-count `M` band for the dense mmvq *weight* kernel's narrow (1-warp) block.  `Q4_0/Q4_1/Q5_0/Q5_1` always take it; `Q8_0` takes it for `2048 <= M <= this`; `Q6_K`/`IQ4_NL` never do.  `M` is the weight's row count, i.e. a tensor property, so all widths `W = 1..8` of a tensor take the same branch — and the three fusion kernels that reproduce a dense weight launch (`ggml_cuda_op_ssm_gate_beta`, `_ssm_conv_l2_gatebeta`, `_shexp_down_gate`) take the same value, which is the width-purity requirement (`GREEDY-PURITY.md` §19).  `0` restores the pre-2026-10-19 wide-block table (byte-identical to r91).  Measured on gfx1100: 35B-A3B MTP n3 **+10.7 %** (prose) / **+6.3 %** (code), gemma-26B `tg128` **+5.0 %**, 35B-A3B `tg128` @ d16384 **+1.7-2.0 %**, gemma-12B +0.4 %, 27B neutral; `W = 1..8` probe PASS on all four models and all eight KV types.  Record: `archive/work/nwarps/`. |
| `GGML_Q6_COMPACT_J` | tuning | Q6 compact-`J` variant. |
| `GGML_CUDA_ENABLE_RDNA3_5_SINGLE_TOKEN_FUSIONS` | off (**opt-in**, RDNA3.5 only) | the qwen4exp weighted-down single-token chain. |
| `GGML_PAIR_OFF` / `GGML_PAIR_DENSE_OFF` / `GGML_PAIR_2X` | off | paired-kernel variants. |
| `GGML_CUDA_SPLICE_GATHER`, `GGML_CUDA_SCALE_UNARY`, `GGML_CUDA_HC_MIX_BAND`, `GGML_CUDA_HC_MIX_PREQ`, `GGML_CUDA_DISABLE_HC_COMB`, `GGML_CUDA_DISABLE_HC_MIX`, `LLAMA_FUSED_HC_MIX`, `LLAMA_FUSED_HC_COMBINE`, `LLAMA_FUSED_DSV4_HC_PRE/POST`, `LLAMA_HC_MIX_BF16`, `GGML_CUDA_LIGHTNING_INDEXER4_GFX1100/GFX1201`, `GGML_LF_FAST_TOPK`, `LLAMA_INDEXER_NOBLOCK`, `LLAMA_INDEXER_NOGROUP` | off / default-on | model-specific fused chains. A/B only.  One of them has a **split-mode-dependent default** (r97): the deepseek4/glm5-next `DSV4_HC_POST` arm is the fused op whenever a **Meta (tensor-split) device** is in play, and the primitive `hc_combine_norm` chain otherwise — the chain is faster on one device but is not correct across a tensor split (NMSE 1.74e-01 vs the CPU reference through the chain, 6.5e-06 through the op; `patches/README.md` block 10).  `LLAMA_FUSED_DSV4_HC_POST=0/1` still forces either arm. |
| `GGML_CUDA_DISABLE_VERIFY_GRAPHS`, `GGML_HIP_GRAPH_FORCE_UPDATE` | off | HIP graph-capture controls. |
| `GGML_HC_UP_V2` | on | kill-switch | `0` restores the row-at-a-time BF16 `hc_mix` up/collapse kernel (r27); v2 is bit-identical and 4-21 % faster on the op. |
| `GGML_CUDA_GRAPH_KEY_DATA` | on (r115, block 09) | kill-switch | `0` restores the old HIP graph-cache key (the first node's `ggml_tensor` *object* address).  The key is now the first node's **`data`** pointer, which is what a captured graph bakes in and is stable across a Meta (tensor-split) rebuild; with the object address the cache never warmed under `-sm tensor` (3954 keys / 1206 captures / 484 ms of `hipGraphInstantiate` per 300-token decode at 3 devices), which was the 3-GPU stutter and the r115 **+41 %** decode (A/B and bisect only). |
| `GGML_CUDA_GRAPH_MEM_GEN` | on | kill-switch | `0` disables the per-device graph memory generation (r25): a graph that captured pool temporary / FA-staging / H2D-ring memory freed since is otherwise recaptured. |
| `GGML_CUDA_Q8_1_ARENA_FREE_OLD` | off | kill-switch (**opt-in**) | `1` restores the immediate `cudaFree` of a grown-out Q8_1 input arena (the r24 behaviour, A/B only): captured decode/verify graphs keep pointers into it, so this reintroduces the `quantize_q8_1` page fault. |
| `GGML_CUDA_BF16_SRC1_CACHE` | on | kill-switch | r36.  `0` disables the per-graph reuse of the BF16 copy of a shared F32 src1 across the qwen4exp hc-mixer cuBLAS BF16 GEMMs (prefill only, `>= 64` columns); bit-identical either way. |
| `LLAMA_HC_PIN_BLOCK_OUT` | off | kill-switch (**opt-in**) | `1` restores pinning every qwen4exp layer's `block_out` as a prefill graph output (r24 behaviour; costs ~1.9 GiB of the `-ub 2048` compute buffer). |
| `LLAMA_HC_MIX_PLANAR` | on | kill-switch | `0` restores the interleaved HC_MIX output (r24) instead of the planar layout (r25; BF16 CUDA path only). |
| `LLAMA_CONV_TAIL_CONT` | off | kill-switch (**opt-in**) | `1` restores the `cont` + `cpy` conv-state tail copy instead of the direct strided 2D memcpy (r25). |
| `GGML_FORCE_NO_INTEGRATED` | off | ignore integrated GPUs when picking devices. |
| `GGML_CUDA_ASYNC_INPUT` | **on** (r90) | **kill-switch** | async graph-input uploads: a `set_tensor` of `<= 1 MiB` into a COMPUTE buffer stages through a per-device 16 MiB pinned ring with a done-event ordering, so the host does not block on every copy; any setup failure falls back to the synchronous path.  **`=0` disables it.**  `=0` also restores the block-10 `< r90` behaviour of the two `set_tensor_*_async` paths (a direct copy from the caller's host pointer).  The per-copy `cudaStreamSynchronize` is invisible on a fast host and measured ~1.4 % of decode on a slow one; default-on is worth **+5.8 %** (35B-A3B 2-GPU tensor) and **+3.6 %** (27B MTP 2-GPU) decode, flat on one card.  **History:** r69 reverted the r68 default-on because a run was not start-to-start deterministic when the consuming graph was captured.  **r90 fixes that**: the ring was never the defect (uploads verify byte-correct at the graph's first read, no inter-graph overlap, HIP's wait/record ordering correct); `ggml_backend_cuda_set_tensor_async` / `_set_tensor_2d_async` copied **directly from the caller's live pinned host pointer**, and the scheduler uses that path for a CPU split's output, which the next ubatch rewrites -- a rare single-graph corruption that propagated.  Both paths now snapshot through the pinned ring (unconditionally, i.e. also with `=0`, where the old direct copy is the fallback), and the ring's wait/done guard is unconditional so the snapshots stay ordered.  Record: `archive/work/async-input-graph-ordering/` (TODO #73, closed). |
| `GGML_CUDA_ASYNC_INPUT_BATCH` | **on** (inside `ASYNC_INPUT=1`) | **kill-switch** (r89, block 10) | PR #182 `0001`: a graph's staged inputs are queued per device and copied by **one kernel** on the compute stream when the next graph starts, instead of one `cudaMemcpyAsync` + one event record per input.  Any other buffer/backend access (get/set/memset/clear/cpy, the 2-D and async forms, `synchronize`, `free_buffer`) first drains the queue through the old per-copy path and orders `cudaStreamPerThread` after the last batch kernel; an overlapping upload, a full queue (64) or a ring wrap also waits.  `cudaHostGetDevicePointer` failure falls back to per-copy.  Byte-exact.  `=0` restores the per-copy uploads.  Worth **+4.6 %** over per-copy on 35B-A3B 2-GPU tensor and +1.4 % on 27B MTP 2-GPU (decode); it also *widened* the r69 nondeterminism window up to r89 (which is what made that defect cheap to isolate); with r90's split-input snapshot fix that window is closed, so batching is a pure win (`archive/work/async-input-graph-ordering/`). |
| `GGML_CUDA_ASYNC_INPUT_LAZY_DONE` | = the `..._BATCH` default | **kill-switch** (r89, block 10) | PR #182 `0002`: `done_ev` is recorded by the **next upload** on that graph's stream instead of after every `graph_compute` (a decode step runs hundreds of graphs per device, each record a marker packet).  Only uploads read the event, and recording it later on the same stream covers at least the same work; a context destructor flushes a still-pending event before its streams are destroyed.  `=0` / `=1` override.  With per-copy uploads alone it measured ~1 % slower on one GPU, hence the coupling. |
| `GGML_CUDA_ASYNC_INPUT_DEBUG` | unset | diagnostic (r105, block 10) | prints, on stderr and for the first 16 events only, every ordering **origin** the ring creates (`AIN origin: dev=… key=… thread=… origins=…`) and the first 16 waits (`AIN wait: … origins=… issued=… ev=… flush=…`).  Diagnostic only — it never changes what is computed.  Its purpose is to make the origin count a **measurement**: the ring's ordering state is per host thread (keyed on `std::this_thread::get_id()`, issue #201), so two contexts decoding on one device from two threads must log `origins=2`, and a wait must never consume another origin's ordering state.  The two-thread reproducer that reads it is `archive/work/async-input-per-origin/repro/`. |
| `GGML_CUDA_Q8_1_CACHE_EXACT` | unset (canonical match) | **kill-switch** (r69, block 10) | set to any value to restore the pre-r69 exact-shape Q8_1 cache key.  By default the cache matches the canonical row layout (size-1 dims dropped, contiguous dims merged), so a `MUL_MAT_ID` view `[K, 1, n]` and a `MUL_MAT` view `[K, n]` of one activation share one quantization (PR #163, output bit-identical). |
| `LLAMA_SHEXP_FIRST` | on | **kill-switch** (r69, block 10; the qwen4exp node order it moves is block 11) | `0` restores the qwen4exp node order with the shared expert expanded after the MoE; the default expands it first so it shares the MoE segment's Q8_1 (PR #163, output bit-identical).  On a model whose shared-expert down+gate fusion fires (`ffn_down_shexp` Q8_0 + `ffn_gate_inp_shexp` F32), `=0` keeps that fusion. |
| `GGML_HC_MIX_Q8` | on | **kill-switch** (r69, block 11) | `0` restores the pre-r69 `hc_mix_bf16_up_collapse2` path and row mapping; the default writes the mixed rows' Q8_1 straight into the quantize cache for the mmvq consumers (PR #163, output bit-identical). |
| `GGML_CUDA_BOUNCE_MIN` | `1` = every size | **kill-switch / tuning** (r56, block 09) | `buffer_get_tensor`, `buffer_set_tensor` (not weight buffers) and `buffer_get_tensor_2d` copy pageable host data through a reused 64 MiB pinned chunk per device.  A pageable device<->host copy is slow on ROCm at any size (~25 us 1-D / ~57 us 2-D on gfx1201), and the server's context checkpoint + `--cache-ram` slot saves make thousands of them.  A pinned host pointer keeps the direct copy; a failed chunk allocation leaves the copy direct and is not retried.  `0` (or unparsable) disables the bounce; a byte count is the minimum copy size that bounces.  HIP/CUDA only — the pointer-attribute helper is not defined for MUSA, which stays direct. |
| `GGML_CUDA_STAGE_PIN` | on (r116, block 08) | **kill-switch** | `0` restores the per-tensor `cudaMallocHost`+`cudaFreeHost` of `ggml_backend_cuda_buffer_set_tensor_2d`'s pinned staging buffer (the pre-r116 behaviour).  A `-sm tensor` model load uploads each tensor through that gather buffer, so the old code allocated and freed ~8-32 MiB of pinned memory **per tensor** — 678 pairs, measured as 2.2 s of `hipHostMalloc` + 1.1 s of `hipHostFree` of a ~10.7 s load (27B Q8_0, 3 devices).  The buffer is now grow-only per device, retained for the process (bounded at **64 MiB**; a larger tensor falls back to the one-shot allocation), which takes the same load to **9.5 s** and 5 allocations.  Bytes, stream and sync are unchanged, so text is identical; `0` is for an A/B or a bisect. |
| `GGML_CUDA_MOE_RPB_SHORT` | unset = on (RDNA4) | **kill-switch / tuning** (r52, block 10) | rows per block for a short-K (`< 8` K-blocks per row) `MUL_MAT_ID` expert GEMM: RDNA4 uses **8** instead of `ceil(8 / K-blocks)` (the Flash-Next q2_0 down split under `-sm tensor` measured 43.0 -> 29.8 us per 4-token verify call).  `0` restores the old rule; `2`/`4`/`8` force a value on any architecture; other values are ignored. |
| `GGML_CUDA_TOPK_SORTED` | unset = on | **kill-switch** (r52, block 08) | `topk_moe`'s argmax uses DPP lane exchanges (`ggml_cuda_xor_lane`) and per-lane sorted 64-bit keys for the gating outputs (softmax/sigmoid/sqrt-softplus, no bias, no delayed softmax, power-of-2 candidates per lane).  Same ids, weights and order (ties to the lower index).  `0` restores the per-round scan; the argmax rounds drop 7.1 -> 3.8 us per 512-expert/10-used call. |
| `GGML_CUDA_GRID_STALL_PAD` | on, HIP only (r46, block 15) | kill-switch | `0` disables the gfx1201 grid-size dispatch workaround: a launch whose block count is a multiple of 256 (or work-item count a multiple of 65536) waits ~6-11 us on gfx1201 (ROCm/legacy-rocm-build#6689), so `mul_mat_vec_f`/`mul_mat_vec_q_ksplit`/`mul_mat_vec_q_moe` add one returning block.  Bit-identical; delete the helper and its call sites once AMD ships the fix. |

---

## 8. Flash attention / QSA (qwen4exp)

| variable | default | class | notes |
|---|---|---|---|
| `GGML_HIP_FA_BAND_WIDE` | on | kill-switch | `0` disables the wide band. |
| `GGML_HIP_FA_BAND_WMMA` / `GGML_HIP_FA_BAND_WMMA_SPLIT` / `GGML_HIP_FA_BAND_WMMA_GQA_MAX` | unset | tuning | band kernel selection.  `GGML_HIP_FA_BAND_WMMA=0` disables the band; `2` / `4` force `ncols1` (any other non-zero value means 4).  The default is **4 for every K/V type** since r92 (the 2-byte f16/bf16 arm used 2 before TODO #27; with the band's 64-half2 row the narrower tile only wins ~5 % at `n_q = 1` and loses at every verify width).  `SPLIT` = blocks per output tile: default `nsm` for the native-quantized types and `nsm/2` for the 2-byte types (r92; was `3*nsm/4`).  It must not depend on `n_q` or the KV length, or decode and verify would split differently.  `GQA_MAX` (default `12`) is the largest GQA ratio the band folds into its `ncols2 = 8` groups; `<= 8` keeps the old whole-group fold (issue #133). |
| `GGML_CUDA_FA_WMMA_256` / `GGML_CUDA_FA_WMMA_MAX_HEAD` | unset | tuning | WMMA tile / head caps.  The RDNA4 cap is 576, which covers the head-512 Gemma 4 global layers; that only pays because r92 retuned the `(512, 512, 32)` RDNA MMA row (issue #188), so `GGML_CUDA_FA_WMMA_MAX_HEAD=256` is the A/B arm that shows the tile kernel is 1.35x slower there. |
| `GGML_CUDA_FA_RDNA3_WMMA_512` | **on** | kill-switch | r102 (PR #199): RDNA3_0 (gfx1100-1103) head-512 (`DKQ == DV == 512`, e.g. Gemma 4's global layers) takes WMMA prefill on top of the 256 head cap, using its own rows in `ggml_cuda_fattn_mma_get_config_rdna` (Q in shared memory, 128 threads, 64-wide K/V/combine batches: the gfx1201-tuned head-512 rows keep Q in registers and spill ~1.0-1.4k VGPRs per lane on gfx1100).  `=0` sends head 512 back to the tile kernel, which is the pre-r102 behaviour and bit-identical to r101.  `GGML_CUDA_FA_WMMA_256=0` also takes it out; `GGML_CUDA_FA_WMMA_MAX_HEAD` only decides whether head 512 takes WMMA at all (the rows themselves are RDNA3_0-only).  Worth +34 % deep prefill at d32768 and +45 % at d65536 (gemma-4-26B-A4B QAT, `q8_0` K/V) with decode unchanged.  It is a tile->WMMA **family switch**, so it moves the prefill logits against the tile kernel; judged with the gate's `--family-switch` mode (calibrated point + a same-kernel ubatch control) it measures **mean KLD 0.001778 / same-top-p 98.967 %**, i.e. inside the absolute limits, and 8x more faithfully than the same-kernel control; at a wikitext point (base PPL 607) even a benign `-ub` change measures 0.105 / 85 %.  See `GREEDY-PURITY.md` §46 and `archive/work/fa-rdna3-head512-purity/RESOLUTION.md`. |
| `LLAMA_TEST_SEED` / `LLAMA_TEST_OP_NMSE` | unset | diagnostic (test harness only) | r103, `tests/test-backend-ops.cpp`.  `LLAMA_TEST_SEED=<n>` makes the test data deterministic so the same op on two builds/arms can be compared element by element (unseeded, an NMSE moves by up to 13x between runs — that is how the first "WMMA is more accurate" reading in the head-512 campaign was produced and then refuted).  `LLAMA_TEST_OP_NMSE=1` prints the error magnitude every case already computes against the CPU reference, including the passing ones, so a kernel-family switch can be judged by *how far* each arm is from the truth rather than by a pass/fail at a fixed threshold.  Neither variable affects a model run. |
| `GGML_HIP_FA_BAND_FETCH_AHEAD` | **on** | kill-switch | r98 (PR #195): with `q8_0` K and V read in place (decode/verify, `n_q <= 8`, head 256) the RDNA4 band runs a kernel variant that fetches the next K/V batches into registers ahead of use and orders only shared memory at its barriers.  `=0` runs the same kernel without the fetch-ahead, as every other K/V type does.  Bit-identical either way; worth ~+1 % decode at 8K and ~+2.4 % at 110K context (27B, `q8_0` K/V). |
| `GGML_CUDA_FA_KV_NATIVE` / `GGML_CUDA_FA_MASK_SKIP` | unset | tuning | native-KV and mask-skip paths. |
| `GGML_CUDA_FA_STAGE_MAX_MB` | unset | tuning | FA staging budget. |
| `GGML_CUDA_FA_STAGE_PREALLOC` | **on** | kill-switch | `0` restores the 1.25x growth ladder (issue #138).  The prefill staging arena is allocated once at the F16 size of the K/V view roots, capped per operand by `GGML_CUDA_FA_STAGE_MAX_MB` and only while `optional_alloc_within_free_cap` allows it; an unbounded cap (`GGML_CUDA_FA_STAGE_MAX_MB=0`) passes no hint. |
| `LLAMA_QSA_OFF` | off | kill-switch | disables QSA. |
| `LLAMA_QSA_SPARSE_FA` | on | kill-switch | `0` = the dense masked path. **This is the QSA oracle**: the `W=1..8` matrix is blind to a width-uniform corruption, so measure the perplexity ratio against `LLAMA_QSA_SPARSE_FA=0` when touching the QSA op. |
| `LLAMA_QSA_KEYS_ONLY`, `LLAMA_QSA_PLE_HOSTGATHER`, `LLAMA_QSA_DENSE_SHORTCUT`, `LLAMA_QSA_SCORE_BOUNDS`, `LLAMA_QSA_SCORE_STRIP`, `LLAMA_QSA_SCORE_WMMA`, `LLAMA_QSA_SCORE_WMMA_MB`, `GGML_CUDA_QSA_IDENTITY`, `GGML_CUDA_QSA_SLICES`, `GGML_CUDA_QSA3`, `GGML_CUDA_QSA_INDEXER_CACHE`, `GGML_CUDA_QSA_INDEXER_SCORE`, `GGML_QSA_DERIVED_BIAS`, `GGML_QSA_DERIVED_VIS`, `GGML_QSA_SCORE_MEM`, `LLAMA_KQ_MASK_DERIVED` | off / unset | tuning | QSA variants and indexer tuning. |

The QSA op has a CPU oracle: `test-backend-ops -o FLASH_ATTN_QSA` (18/18 minimum).

---

## 9. GDN / SSM (block 02)

| variable | default | class | notes |
|---|---|---|---|
| `GGML_CUDA_GDN_CHUNKED` | on | kill-switch | compared as a **string** against `"0"` — literally `GGML_CUDA_GDN_CHUNKED=0` forces the sequential kernel on the whole batch (correct, bit-identical, slow; the exact reference the prefill-logit gate compares against). The chunked prefill is K-independent with threshold `max(K>16?K:16, n_rs_batch)`. |
| `GGML_CUDA_GDN_TAIL` | on (r91, block 10) | kill-switch | inside that chunked path, a single-sequence batch above the threshold runs the chunked kernel on its first `n_tokens - D` tokens and the **sequential** kernel on the last `D = max(K>16?K:16, n_rs_batch)` in the same launch, so the rollback snapshots `0..D-1` exist for every batch.  `=0` restores whole-batch chunking (the r90 behaviour, and the A/B base for the prefill-logit gate).  Prefill-only (decode / verify batches ≤ the threshold never take it); no extra memory or graph; measured pp2048 −0.58 %, decode flat. |
| `GGML_CUDA_GDN_CHUNKED_BF16` | on | kill-switch | BF16/WMMA chunked GDN variant, **default-on since r30** (RDNA3/RDNA4, `S_v == 128` prefill). Near-lossless, not bit-exact (bf16 operands, fp32 accumulation; ~1e-5 op NMSE; prefill mean KLD 0.0007 / 0.00005 / 0.00015 on gfx1201 / gfx1100 / gfx1151, same-top-p >= 98.7 %). `=0` runs the fp32 chunked kernel. r29 had defaulted it off as a workaround for the n_seqs > 1 `A_sc` stride aliasing bug (issue #113), fixed in r30. |
| `GGML_CUDA_FUSE_GDN_STATE_GATHER` | on (r46, block 15) | kill-switch | in the one-sequence `<= 16`-token decode/verify band the graph skips the per-GDN-layer recurrent-state `GET_ROWS` and the sequential kernel reads `s0` from the cache row directly (`GET_ROWS` is a plain copy, so bit-identical).  Uses the §7.1 presence idiom (unset = on, `0` = gather as before). |
| `LLAMA_RS_ROLLBACK_DEBUG` | unset | **diagnostic** | r91 (block 03).  `1` logs one `RSPREP` line per prepared ubatch and one `RSROLL` line per partial recurrent rollback (rollback distance, the sequence's own last-batch shape, `n_rs_seq`, `n_rs_batch`).  This is the instrument that proved the issue-#131 warning was a stale per-sequence tracker entry.  Verbose; diagnosing only. |
| `GGML_CUDA_GDN_GATHER_INDEX` | unset = on (r68) | **kill-switch / diagnostic** | replaces the `O(gathers × nodes)` `ggml_cuda_gdn_state_gather_deferrable` forward walk with one index per graph evaluation, built **lazily on the first candidate** so a non-GDN graph pays only one pointer check per `GET_ROWS`.  `0` = the per-gather walk; `2` = both, `GGML_ABORT` on a different answer.  Conservative relative to the walk (a disagreement can only drop a deferral, never add one), so the kernel path is unchanged.  Issue #151: 0.63 ms/graph less host work on gfx1201 (13 %), ~+0.3 % decode on a slow host. |
| `GDN_DBG_SKIP_KKT`, `GDN_DBG_SKIP_SCAN` | off | diagnostic | skip stages (debug). |

---

## 10. MMB (block 08)

The `mmb` campaign is part of the delivery.  `GGML_CUDA_MMB` defaults to `1`; the rest are tuning knobs
for tile/shape selection and cache sizing.  Treat them as internal: the validated configuration is the
default, and they exist to reproduce measurements from `benchmarks/`.

`GGML_CUDA_MMB`, `GGML_CUDA_MMB_BF16W`, `GGML_CUDA_MMB_CACHE`, `GGML_CUDA_MMB_CFG`,
`GGML_CUDA_MMB_DENSE`, `GGML_CUDA_MMB_DENSE_TYPES`, `GGML_CUDA_MMB_DOWN16`, `GGML_CUDA_MMB_F32SPLIT`,
`GGML_CUDA_MMB_F32SPLIT_MIN_K`, `GGML_CUDA_MMB_F32SPLIT_MIN_M`, `GGML_CUDA_MMB_GLU`,
`GGML_CUDA_MMB_GLU_THRESH`, `GGML_CUDA_MMB_HC16`, `GGML_CUDA_MMB_IQ3XXS`, `GGML_CUDA_MMB_MIN_T`,
`GGML_CUDA_MMB_RDNA3`, `GGML_CUDA_MMB_ROUTED`, `GGML_CUDA_MMB_ROUTED_THRESH`, `GGML_CUDA_MMB_SHADOW`,
`GGML_CUDA_MMB_SHADOW_MB`, `GGML_CUDA_MMB_TALL`, `GGML_CUDA_MMB_TALL_MIN_M`, `GGML_CUDA_MMB_TILE`,
`GGML_CUDA_MMB_TINY_M`, `GGML_CUDA_MMB_TINY_TT`, `GGML_CUDA_MMB_TYPES`, `GGML_CUDA_MMB_LOG`,
`GGML_CUDA_MMB_MARK_LOG`, `LLAMA_MMB_CVT_LOG`, `LLAMA_MMB_F32SPLIT`, `LLAMA_HC_BLK16`,
`LLAMA_HC_GATEMIX`, `LLAMA_HC_RES16`.

### 10.1 `GGML_CUDA_MMF32` -- the F32 skinny prefill GEMM (block 06)

`mmf32` serves the F32 prefill GEMMs that `mmb` cannot (non-quantized weights, more than 16 token
columns, `m <= 256`: the GDN `ssm_alpha`/`ssm_beta` projections and the MoE routers).  Taking them out of
rocBLAS/hipBLASLt is what makes those models' prefill logits reproducible across fresh processes, and it is
faster there (`GREEDY-PURITY.md` §47).

| variable | default | kind | notes |
|---|---|---|---|
| `GGML_CUDA_MMF32` | **on** (RDNA4, RDNA3_5); unset = off on RDNA3 | kill-switch | `=0` disables (the old rocBLAS path).  **RDNA4 (gfx1201) and RDNA3_5 (gfx1151) are the validated devices**, so the kernel is default-on there and the variable exists to disable it; both passed the same four legs (exact, deterministic by construction, a prefill win, and a `--family-switch` PASS at a confident point — `GREEDY-PURITY.md` §47).  gfx1151: `test-backend-ops -o MUL_MAT` 2444/2444 with NMSE 6.11e-14 vs rocBLAS 6.83e-13, 12/12 fresh starts one logits class, **+1.0 % pp512 / +1.6 % pp2048** with decode flat, family-switch 0.013016 / 98.673 % against a same-kernel control of 0.019125 / 97.975 %.  On **RDNA3 (gfx1100) it is not a win** (−1.3…−2.2 % at `pp2048`, one visit a tie), so it stays **opt-in** (`=1`) there until that box has a pinned per-arch tile. |
| `GGML_CUDA_MMF32_LOG` | unset | diagnostic | prints the first 16 resolved plans on stderr (`MMF32 m=… n=… k=… tile=… ks=…`).  Does not change what is computed. |

Scope: F32 weights only, `m <= 256`, `17 <= n <= 65536`, `256 <= k <= 8192`, `ldc == m`; every other mul_mat
keeps the rocBLAS call.  BF16/f16 prefill (Flash-Next) is untouched, and so is its hipBLASLt advantage; a
full-F32 model's FFN GEMMs (`m >> 256`) stay on rocBLAS (a recorded limitation).

---

## 11. Diagnostics and profiling

None of these change the computed result on the default path.

| variable | notes |
|---|---|
| `GGML_CUDA_OP_TIMING` | per-op GPU timing. |
| `GGML_CUDA_GCDBG` | CUDA-graph debug. |
| `GGML_STREAMDBG` | stream debug. |
| `GGML_ALLOCATOR_DEBUG` | build-flag companion for allocator tracing. |
| `GGML_CUDA_MWR_DEBUG`, `GGML_CUDA_HC_BLK16_DEBUG`, `GGML_CUDA_IDX_RELU_SUM_LOG`, `GGML_CUDA_FUSE_CPY_BATCH_DEBUG`, `GGML_CUDA_CONV_DEBUG`, `GGML_CUDA_CONV_FUSION_MULTI`, `LLAMA_HC_CN_DEBUG`, `LLAMA_HC_GATEMIX_DEBUG`, `LLAMA_QSA_SCORE_STRIP_DEBUG`, `GGML_CUDA_QSA_DEBUG` | feature-specific debug output. |
| `FA`, `KV`, `RS`, `GDN_DBG_A`, `GDN_DBG_P`, `GDN_DBG_ONES`, `GDN_DBG_DUMP`, `GDN_DBG_SAVE` | **internal probes.** Single/double-letter or `_DBG_` names used by debug dump blocks. Never set these in production — two of them take a value that selects a dump *mode*. |

---

## 12. Non-ggml environment (HIP/ROCm runtime)

These are not llama.cpp variables but they control how the delivery runs.

| variable | notes |
|---|---|
| `HIP_VISIBLE_DEVICES` | which GPUs are visible, in order. Part of every validated command (`0,1` or `0,1,2`). |
| `LD_LIBRARY_PATH` | must include the matching ROCm runtime libs, e.g. `/opt/rocm-10.1.0-gfx120X/lib` (the canonical build tree), or the build will not start. |
| `ROCR_VISIBLE_DEVICES` | lower-level alternative to `HIP_VISIBLE_DEVICES`; prefer `HIP_VISIBLE_DEVICES`. |
| `GGML_CUDA_ENABLE_UNIFIED_MEMORY` | forces managed allocations; not used in this repo's validated configurations. |

There is **no** environment variable for thread pinning; use `-t` / `--cpu-mask` as described in §5.

---

## 13. Retired / superseded

| variable | status |
|---|---|
| `MOE_EXPERT_CACHE_RESERVE_MIB=8192` | the pre-r20 server workaround. **No longer needed** — the default `1024` plus the r20 compute-buffer slack and the fail-soft arena yield cover it. |
| `MOE_ARENA_HEADROOM_MIB` | tried and **removed**. A flat arena headroom changes nothing: the failure is a realloc needing a block bigger than the one just freed, so the slack has to be on the *allocation*, not the arena. |
| `MTP_DRAFT_N_UBATCH=4` | was a workaround for the same failure; a cap is now the default (`512`), so this is just an over-tight value. |
| `GGML_HIP_NO_VMM` (build option, not runtime) | HIP VMM is **off by default** (`ON` = do not use VMM).  Whether to enable it is an open investigation — see `archive/work/moe-cache-autosize/FOLLOWUP-compute-arena-chunking.md`. |

---

## 14. Build-time gates (not environment variables)

These are compile-time, because a device-side runtime gate does not work cleanly here.

| flag | default | what |
|---|---|---|
| `-DGGML_HIP_RDNA4_Q4K_DENSE_VDR4` | off | RDNA4 uses the 32-element dense Q4_K VDR-4 dot product (`vec_dot_q4_K_q8_1_vdr4_dense`); RDNA3_0 always uses it (PR #162 0002).  One flag gates both the device selection (`mmvq-vecdot.cuh`) and the host K-split (`get_vdr_mmvq_dense`), because the K partition must match.  It changes the K summation order, so greedy text changes on some prompts (deterministically); width purity is preserved (`none == draft-mtp`, width probe PASS).  Measured only ~+0.3 % `tg128` on a single R9700, so it stays off by default. |
| `-DGGML_HIP_RDNA4_Q4K_MOE_VDR4` | off | the **MoE expert** kernel (`mul_mat_vec_q_moe`) uses `vec_dot_q4_K_q8_1_vdr4_dense` (PR #167 0002; RDNA3_0 uses it by default since r79).  Same 32-element layout and VDR 4, so only the summation changes (one integer `dp4a` chain per sub-block); the MoE VDR, the width-uniform selector and the pinned fusion `calc_nwarps` are unchanged.  Separate from the dense flag above, so the two can be A/B'd independently.  The patch also defines a host-visible `ggml_cuda_rdna4_q4k_moe_vdr4` constant so ccache keys the HIP object on this device-only flag (without it the unchanged object was returned for the flag toggle).  It changes greedy text on some prompts.  RDNA4 2-GPU tensor measured flat on single-token decode (+0.06 % tg256), +0.5-1.5 % at the verify widths (batched B=1/4/8), and mixed MTP (R +3.4 %, K +0.8 %, P -1.65 %, C -0.5 %); not a clear default-on win, so it stays **off**.  RDNA3_0 ignores it (its path is already on). |
| `-DGGML_HIP_NO_DPP_XOR` | off (DPP on) | restores `__shfl_xor` for the wave32 warp reductions on RDNA3/RDNA4 (PR #110's DPP lane exchange, folded into block 15).  The DPP path is **bit-identical** and speeds up the HC_MIX / Flash-Next band (measured on gfx1201 / ROCm 7.14: BF16 HC_MIX 58.84 -> 45.26 us at 4 tokens, 100.00 -> 62.55 us at 8, i.e. +23 % / +37 %; bandwidth-bound matmuls unchanged).  **There is deliberately no runtime env var**: a device-side runtime gate was implemented and A/B-tested but reproducibly wedged the FA prefill at ~4096 tokens with MTP, so it was dropped. |

The `llama` C++ target compiles with `-Wshadow=local` under **GCC** and plain `-Wshadow` under **clang**
(block 00).  The container build's host compiler is GCC (the `rocm/dev-ubuntu` image default, unlike the
local `~/bin/build-llama-rocm`, which forces clang), and GCC's `-Wshadow` additionally reports
"declaration shadows a member" / "hides constructor" for the ubiquitous `Foo(int x) : x(x) {}` idiom.
`-Wshadow=local` keeps the class the gate exists for (a local shadowing a local) and drops that
member/global output; clang has no `=local` form.  The container's `RUN cmake` step zeroes ccache stats
(`ccache -z`) before the build, so its trailing `ccache -s` reports the rate of that build rather than
the lifetime average.

---

## Maintaining this file

The tables were derived from the code, so re-derive rather than trust them after a block change:

```bash
# every variable the delivery adds or repoints, with the idiom used
for f in ~/llama-cpp-rdna-boosts/patches/*.patch; do
  grep -hoE 'getenv *\( *"[A-Za-z0-9_]+"|GGML_ENV_STR *\( *"[A-Za-z0-9_]+"|env_int *\( *"[A-Za-z0-9_]+"' "$f"
done | grep -oE '"[A-Za-z0-9_]+"' | tr -d '"' | sort -u
```

Then, for each name, grep the tree for its usage.  **Do not** classify by name alone: `*_DISABLE_*` is
not consistently value-gated, and `*_FUSE_*` semantics changed from opt-in to kill-switch.  A variable
that is genuinely new should follow the repo's conventions: default-on if it helps (with the variable as
a *kill-switch* that restores the old behaviour), default-off only for a known-risky correctness
workaround, and a first line in the relevant block's `patches/README.md` note.
