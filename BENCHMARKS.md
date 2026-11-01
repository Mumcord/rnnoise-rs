# Benchmarks: rnnoise-rs vs RNNoise (C) vs nnnoiseless

Reproducible benchmarks comparing:

- **rnnoise-rs** — this crate (current RNNoise model, ~2.9 M params).
- **RNNoise (C)** — upstream Xiph C library, scalar and `-O3`/NEON builds, same model.
- **nnnoiseless** — the other Rust port, of the *old* RNNoise model (~215 K params).

> **TL;DR.** rnnoise-rs is **~1.5× faster than the official C library** on the
> same model, bit-exact with it, at **~32× real time** single-threaded — or
> **~95× real time** with the opt-in int8 + `sdot` path (3× faster, audibly
> identical). `nnnoiseless` is faster still, but only because its model is ~13×
> smaller and lower quality — an apples-to-oranges speed comparison. The model is
> **compute/load-bound, not memory-bandwidth-bound** on Apple Silicon, so a naive
> int8 path does *not* help, but `sdot` (4 int8 MACs/instruction) does.

## System under test

| | |
|---|---|
| CPU | Apple M4 Pro (10 performance cores), 48 GB |
| OS | macOS (Darwin 25.5, arm64) |
| Rust | rustc 1.94.1, `opt-level=3, lto=true, codegen-units=1` |
| C | Apple clang 21, `-O2` (scalar, `-DDISABLE_NEON`) and `-O3` (NEON) |
| Audio | 48 kHz mono; `test_data/testing.raw` (≈1 s) tiled to 100 s |

## Methodology

Two complementary measurements:

1. **Per-frame compute (in-process).** Each implementation processes the *same*
   480-sample frame, so the number is pure steady-state compute, excluding process
   start-up and I/O. An **active** frame (tone + noise) keeps the NN running; a
   **silent** frame makes RNNoise skip the network, so `full − front-end ≈ NN cost`.
   The tables below were produced by the tight-loop harness (20 000 iters after 200
   warm-up); `cargo bench` now measures the same ablation through criterion — see
   "How `cargo bench` produces the numbers".
2. **End-to-end CLI wall-clock.** Each tool denoises the same 100 s RAW file;
   we report the **min of 7 runs** (and derive µs/frame and the real-time factor).
   This includes start-up + I/O (small at this length).

All four read/write the same RAW 16-bit 48 kHz mono format.

## How `cargo bench` produces the numbers

`benches/process.rs` is a criterion harness (dev-dependency, `harness = false`): one
group per implementation — `float`, `int8`, `legacy` — each with an **active** input (tone
+ noise, so the network runs on every frame) and a **silent** input (front-end only,
network skipped), i.e. the same `full − front-end ≈ NN cost` ablation the tables use.

`make bench` saves a baseline; the CI `bench` job runs
`cargo bench --all-features -- --save-baseline ci` on x86-64, aarch64 and Apple Silicon
and uploads `target/criterion` as `bench-<runner>`. Compare numbers **within** an
artifact, never across runners — they are different machines. Each run prints the tier
runtime detection selected, so a result is attributable to a kernel path
(`RNNOISE_SIMD_TIER` is a test-only override and does not apply to benches).

Current run on an x86-64 CI-shape box (tier v3 AVX2, 100 samples), to show what the
artifacts look like — not the Apple M4 Pro reference numbers above:

| group | active frame | silent frame | NN | NN % | real time |
|---|--:|--:|--:|--:|--:|
| `float` | 181.9 µs | 24.8 µs | 157.1 µs | 86 % | 55× |
| `int8` | 106.0 µs | 24.6 µs | 81.4 µs | 77 % | 94× |
| `legacy` | 35.9 µs | 21.4 µs | 14.5 µs | 40 % | 279× |

Real time = 10 ms (one 480-sample frame at 48 kHz) divided by the active-frame time.

Why the per-tier matrix matters: on the same box, `RNNOISE_SIMD_TIER=scalar` (with
`simd-tier-override`) gives **787 µs/frame** for the float path against **181.9 µs** at
tier v3 — a 4.3× difference that a single benchmark run would hide. The CI `bench` job
therefore runs `detected`, `avx2` and `scalar` on x86-64 and `detected` and `dotprod` on
aarch64, each uploaded as its own artifact.

## Results — per-frame compute (in-process)

| Implementation (model) | Full frame | Front-end | Neural net | NN % | Real-time |
|---|--:|--:|--:|--:|--:|
| **nnnoiseless** (old, ~215 K) | 27.6 µs | 19.0 µs | 9.8 µs | 36 % | 290× |
| **rnnoise-rs** (old, `legacy-model`) | **25.9 µs** | — | — | — | **309×** |
| **rnnoise-rs** (new, float) | 312.6 µs | 35.3 µs | 277.3 µs | 89 % | 32× |
| **rnnoise-rs** (new, int8 + `sdot`) | **105.1 µs** | 34.0 µs | **68.9 µs** | 66 % | **95×** |
| RNNoise C, NEON `-O3` (new) | 456.4 µs | 25.9 µs | 430.5 µs | 94 % | 22× |
| RNNoise C, scalar (new) | 497.0 µs | 24.5 µs | 472.5 µs | 95 % | 20× |

## Results — end-to-end CLI (100 s audio, min of 7)

| Implementation | Wall-clock | µs/frame | Real-time |
|---|--:|--:|--:|
| **rnnoise-rs** (float) | **3.125 s** | 312.5 | **32.0×** |
| RNNoise C, NEON `-O3` | 4.585 s | 458.5 | 21.8× |
| RNNoise C, scalar | 4.896 s | 489.6 | 20.4× |
| nnnoiseless (old model) | 0.321 s | 32.1 | 312× |

rnnoise-rs start-up (parsing the 11.3 MB embedded blob, once): **≈ 5.3 ms**.

## Analysis

**rnnoise-rs is faster than the C reference on the same model** (3.13 s vs
4.59 s NEON). The win is entirely in the neural net: rnnoise-rs's GEMVs
(277 µs) beat C's auto-vectorized ones (430 µs NEON, 473 µs scalar). The
decisive change was reorganising the matmuls into sequential, bounds-check-free
SAXPY/8×4 kernels the compiler vectorises cleanly (the per-output accumulation
order is preserved, so output stays **bit-identical** — 3 / 47 520 samples differ
by 1 LSB vs the C build).

**rnnoise-rs's front-end is slower than C's** (35 µs vs 25 µs) — our KISS-FFT
port and pitch search aren't as tight as upstream's. It's only ~11 % of the
frame, so it barely moves the total, but it's the clearest remaining target.

That target is now closed on x86-64: with bit-exact SIMD butterflies, the
cross-correlation tiers and the precomputed band weights, the front-end is
**21.8 µs** of a **208–216 µs** frame on the AMD Zen 3 core (full frame was
270.6 µs; int8 116.8 → 102–107 µs). See [doc/performance.md](doc/performance.md)
for the tier table. These tiers keep the reference accumulation order, so the
parity numbers above are unchanged.

**nnnoiseless is faster because its model is smaller, not because the code is
faster.** Its NN is 9.8 µs (old ~215 K-param model, int8, fits in cache) vs our
277 µs (new ~2.9 M-param model, 11.5 MB of weights). Per byte of weights,
rnnoise-rs is actually *more* efficient. The trade is quality: rnnoise-rs runs
the modern, substantially better-denoising model. No faithful port of current
RNNoise can match the old model's throughput.

**The model is compute/load-bound, not memory-bandwidth-bound, on Apple
Silicon.** The float NN moves 11.5 MB/frame at ≈ 41 GB/s — well under the M4
Pro's single-core ceiling — so it's limited by load-port / FMA *instruction*
throughput, not DRAM bandwidth. That distinction is the whole story for int8: a
naive int8 path (dequantise to f32 in the loop) does **not** help (it adds
instructions), but `sdot` — which does 4 int8 MACs per lane in one instruction —
cuts instruction count ~4× and gives a real **4.0× speedup on the NN** (next
section).

## Legacy model vs nnnoiseless — *faster* (apples-to-apples)

With the `legacy-model` feature, `rnnoise-rs` runs the *same* old model as
`nnnoiseless`. Fair head-to-head, standalone (isolated) processes, median of 15
runs each on the M4 Pro:

| | full frame | real-time |
|---|--:|--:|
| nnnoiseless | 27.6 µs | 290× |
| **rnnoise-rs `DenoiseStateV1`** | **25.9 µs** | **309×** |

→ **`rnnoise-rs` is ~1.7 µs (≈6 %) faster.** Getting there took three steps:

1. **Match the FFT.** The from-scratch KISS-FFT is ~2× slower per transform than
   nnnoiseless's `rustfft`. So the legacy model uses `realfft` (rustfft) too — the
   exact approach nnnoiseless takes. This brought legacy 44.9 → ~27.8 µs and put
   the front-end at parity. (KISS-FFT remains the dependency-free default for the
   *current* model, which must stay bit-exact with the C reference.)
2. **Tighten the pitch.** A 4-lags-at-a-time cross-correlation kernel and
   4-wide inner products (the hottest loops of the pitch search).
3. **Beat the NN with `sdot`.** The GRU input matmuls (the bulk of the network)
   run as int8 `sdot` dot products with dynamically-quantized activations —
   something nnnoiseless doesn't do. This is the decisive edge: it makes our NN
   faster than nnnoiseless's i8×f32 matmuls while keeping the low-memory int8
   weights (storing f32 weights was *slower* — 4× the cache traffic).

Output parity (legacy): **rel. energy 1.1e-5, max 21 LSB** on int16 output vs the
old model — imperceptible; the residual is the `sdot` activation quantization.

## How to speed up — investigation

The NN is 89–95 % of every frame, so that's where speed lives. Findings:

### 1. int8 + `sdot` SIMD — ✅ *implemented, 3× faster*

Quantising conv2 + the GRUs to int8 with a per-output scale (opt-in via
[`RnnModel::quantized`]) stores a transposed dense `[output][input]` matrix so
each output is a contiguous int8 dot product. Activations (all in `[-1, 1]` after
tanh/sigmoid/GRU) are quantised to int8, and each output is computed with ARM
`sdot` — 4 int8 MACs per lane per instruction — via stable inline `asm!` (the
`vdotq_s32` intrinsic is still nightly-only), with a scalar fallback that gives
the identical integer result.

Measured on M4 Pro: **NN 277 → 68.9 µs (4.0×)**, **full frame 312 → 105 µs
(3.0×, 95× real time)**, footprint ~4× smaller. Accuracy vs the float model:
**rel. energy 4.8e-6, max 13 LSB** — audibly identical. Not bit-exact, so it's
opt-in; the float model stays the default. (A naive dequant-to-f32 int8 loop, by
contrast, measured *0.81×* — slower — confirming the win is the instruction-count
reduction, not bandwidth.)

### 2. x86 int8 SIMD — ✅ *implemented (SSE2 → SSE4.1 → AVX2 → VNNI, runtime-detected)*

`src/simd/` dispatches per architecture. On x86-64 the kernel is
`pmovsxbw` + `pmaddwd` (runtime AVX2 detection); before that the int8 path had no
SIMD at all on the SSE2 baseline (`pmaddubsw` is SSSE3) and was **slower than
float** — 487 vs 289 µs of NN per frame on an AMD Zen 3 core. With the kernel:
int8 net 487 → **88 µs** (5.6×), full frame 519 → **120 µs** (84× real time),
legacy 40.2 → 37.8 µs. Still exact int32, so output is unchanged.

`vpdpbusd` (AVX-VNNI / AVX-512-VNNI, 64 MACs per instruction on Zen 4+ / Ice
Lake+) is now tier v4 of the int8 ladder: it is unsigned × signed, so it needs a biased
weight domain plus a `128 · Σ q_x` correction (`simd/x86_64/vnni.rs`, asserted exact by
`simd/tests.rs`), and it is only *used* when CPUID reports `avx512f` + `avx512bw` +
`avx512vnni` (`set1_epi8`/`add_epi8` are AVX512BW) — which is why `rust-version` is 1.89.

**Measured on a Zen 4 core (Ryzen 7 7800X3D), per row** — same machine, same binary, isolated
kernel, `m = 384`, `n = 1152` — the tier is faster, and the bias op is not the reason it was
thought to lose:

| shape | ns/row |
|---|--:|
| tier v3 as committed | 17.29 |
| tier v3, four accumulators | 8.44 |
| tier v4 as committed (`vpaddb` per chunk, one accumulator) | 4.88 |
| tier v4, `+128` hoisted out of the loop | 4.77 |
| tier v4, `+128` hoisted into registers + four accumulators | **3.06** |

`vpdpbusd` does win on this core (≈3.5× tier v3 per row); the `vpaddb` is worth ~2% of a row, and
the fixed per-row cost (horizontal sum, int→float, scale, store) is ~0.7–1 ns of a ~5 ns row. The
change that landed is the one the shapes pay for: `quantize()` now stores the per-row `128 · Σ w`
correction, the activations are biased once per layer, and the 6-chunk hot loop is `load +
vpdpbusd` only. ARM is unaffected either way: `sdot` is signed × signed and needs no bias.

**Re-measured on the same box, five rounds on one core, min** — #16's premise was a measurement
error. The 114.9 µs / 135.9 µs row it quotes as tier v4 is the *float* path (114.4 / 136.1 on this
core); its tier v3 row (77.5 / 98.5) is genuine. Tier v4 was never slower than tier v3 here:

| | int8 NN µs/frame | ns/row | full frame |
|---|--:|--:|--:|
| tier v4, shape as committed | **45.5** | 5.25 | 66.8 |
| tier v4, shape as #16 measured it | 52.8 | 6.25 | 74.0 |
| tier v3 (AVX-512 branch forced off) | 78.2 | 9.73 | 99.4 |
| float path, same binary | 114.4 | — | 136.1 |

The shape change is worth 1.16× end to end, not the 1.37× per row it measures in isolation: the
isolated kernel keeps 442 KB hot in L2, the model streams 2.8 MB of int8 weights per frame from L3,
so the crate damps shape ratios. `select` stays top-down (`simd::tier::resolve` is the ladder in one place: top-down by default, capped to what a kernel implements when CI forces a tier). Closed as issue #16.

### 3. f16 weights + f16 SIMD — *medium win (future)*

ARM does 8-wide f16 FMA (≈2× f32 throughput) and halves weight loads. ~1.5–2×
with intrinsics, with ~half the accuracy loss of int8 — a middle ground when int8
error is undesirable.

### 4. Multi-threading the GEMVs — *situational*

The three GRUs are sequential, but each layer's matmul (1152 outputs) can be
split across the M4 Pro's 10 perf cores. At a 10 ms frame budget the sync
overhead is significant for one stream; most useful for offline/batch. Expected
~2–4× wall-clock for batch, little benefit for a single real-time stream.

### 5. Tighten the front-end — ✅ *done for the legacy model*

The legacy model now uses `realfft` (rustfft) and 4-wide pitch kernels, putting
its front-end at parity with nnnoiseless (see the legacy section above). For the
*current* model the FFT stays the dependency-free KISS-FFT to preserve bit-exact
agreement with the C reference; swapping it to a real-input/SIMD FFT (relaxing
that bound) would shave a few µs off the int8 frame too.

### 6. Smaller model — *quality trade*

The official "little" (sparse) model is ~½ the size; loading it (or training a
custom one) trades some quality for speed and footprint.

### Recommended priority

int8 + `sdot` (#1) is done and is the big lever on ARM; the x86 int8 ladder (#2) is
done too, per ISA tier, runtime-detected. The x86 **float** path (issue
[#1](https://github.com/Mumcord/rnnoise-rs/issues/1)) is at its throughput ceiling: the
tiers landed, the "3×" acceptance criterion was measured to be unreachable (1.6–1.9× of the
pre-tier baseline; ≤1.2× for the FMA variant on top of the committed block-major tier), and
an SSE4.1 float tier would be the SSE2 kernel with a different name — see
[doc/performance.md](doc/performance.md#fma-and-sse41-on-x86-64-measured-and-not-shipped).
Next: the real-input FFT (#5) for a broad front-end win; f16 (#3) and threading (#4) as
needed.

## Reproduce

```sh
# rnnoise-rs per-frame (float + int8 breakdown)
cargo bench --bench process

# end-to-end on your own 48 kHz mono RAW (16-bit):
cargo run --release --bin rnnoise-demo -- noisy.raw out.raw

# parity + int8 accuracy vs the C reference
cargo test --release
```

The C reference and `nnnoiseless` figures were produced by building each from
`bup/` and timing the same RAW input; see the in-process harnesses described
above. Numbers vary with CPU and thermal state — treat them as ratios, not
absolutes.
