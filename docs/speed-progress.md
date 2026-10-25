# arcinferzero speed progress

One file that tracks the speed of arcinferzero over time on the same laptop (Core Ultra 5 125H, Arc Xe-LPG 112 EU, no
XMX, DP4a, ~75 GB/s, 32 GB LPDDR5x-6400, Windows 11). The newest measurements come first; each dated section keeps
what was measured then; where a later change overturned a statement, a **Later:** note says so. Add a new dated
section at the top when the speed changes, and update "Where it stands" in [before-after.md](before-after.md).
The story behind the numbers: [review.md](review.md); what helped and what did not: [lessons-intel-arc-igpu.md](lessons-intel-arc-igpu.md).

## Current speed

The current numbers for every model are in one place: [before-after.md](before-after.md#where-it-stands)
("Where it stands"). In short (24 Oct; 25 Oct: the 27B with `--npu on` +13-15 % on prompts of 2K-34K): 35B UD-IQ4_XS prompt 604 tok/s (32K), generation 20.6 tok/s; 27B prompt
~135 tok/s (4K), generation 4.9 tok/s; Flash Next prompt ~164 tok/s (4K), generation 6-7 tok/s; Gemma 4 26B-A4B
prompt 252 tok/s (4K), generation ~25 tok/s with its drafter; Gemma 4 E4B 724 tok/s (4K), 32 tok/s. The sections below keep what was measured on each date.

## 2026-10-25: the NPU next to the GPU for prompts (`--npu on`)

The Meteor Lake NPU computes part of each prompt chunk's matrix products while the GPU computes the rest (Level Zero
graph extension only; [npu-experiment.md](npu-experiment.md)): 1/3 of ffn_gate / ffn_up in per-row int8, 27.5 / 29 %
of ffn_down / attn_qkv in f16. Off by default, kept across model switches in the server, worth it on the 27B only
(models with resident W8 weights gain nothing and stay off).

Benchmark (`bench/run_bench.ps1 -Engines arcinferzero,arcinferzero-npu,arcinferzero`, 2026-10-25, off measured
before and after the NPU round; results in `bench/results/npu-2026-10-25.jsonl`):

| 27B-AP IQ4_XS | off | `--npu on` |
|---|---|---|
| pp512 (one 512-row chunk: no NPU) | 94.7-100.2 tok/s | 97.7 |
| pp2048 | 125.9-133.5 tok/s | **153.8 (+15 %)** |
| 11,240-token code prompt, time to first token | 84.7-86.2 s (130-133 tok/s) | **73.7 s (152.6 tok/s, +15 %)** |
| 33,937-token code prompt, time to first token | 292.1-295.3 s (115-116 tok/s) | **258.4 s (131.3 tok/s, +13 %)** |
| generation (tg64; 32 tokens after the 11K / 34K prompt) | 3.67-4.04; 3.76-3.79; 3.65-3.68 tok/s | 3.91; 3.83; 3.46 (unchanged: noise and heat) |

## 2026-10-22 / 24: Gemma 4 accurate by default, Flint, image encoders

- **Gemma 4 runs its accurate mode only** (since 2026-10-22, the user's KL limit of 0.015): float attention and, on
  the 26B / 12B, two int8 passes per matmul input. That first cost the 26B half its prompt speed (450 -> ~200 tok/s
  at 4K); the kernels were then rebuilt for it: fused passes in one-token GEMVs and the per-tile expert kernels,
  `attn_fa_gh` (one read of each key row for all q heads of a kv head, 2 key blocks per step in the sliding layers),
  a tiled f32 router. 26B: **252 tok/s** (4K), 210 (14K), ~25 tok/s with its drafter. 12B 137 tok/s (4K). E4B went
  back to one pass (KL 0.00088 is far under the limit) and to the int8 K / V copy for its global layers in prompts:
  724 tok/s (4K), 615 (14K).
- **Flint** (2026-10-24; Flint support was removed on 2026-10-25 (the user)): 4K prompt 240 -> 248 tok/s after reading its GPU assembly (ocloc: spills and needless
  instructions removed), generation 13-17 tok/s; its accuracy (KL 0.029 -> 0.0043) came from f32 V rows and an f32
  router, not from speed changes.
- **Flash Next**: the expert gate / up kernel reads the activation scales transposed (4K 160 -> 164 tok/s);
  `ARC_FN_PRECISE=1` (KL under 0.015 at 3.5K) runs prompts at ~87 tok/s, so it stays opt-in.
- **Image encoders**: Gemma 4 26B 12.7 -> **7.4 s** per 1,064-token image (the encoder's GEMMs on the engine's int8
  GEMM with two passes, K / V rows in one 8-wide block read, 8-key tiles for head 72); E4B 51.5 -> 3.1 s (a wrong
  head size in its attention, a bug); Qwen3.5 9B / Qwen3.8 27B attention 3-7 % faster with 8-key tiles. An int8
  vision attention was accurate enough but not faster: not taken.

## 2026-10-19 / 20: two conversations at once, Gemma 4 26B-A4B, Flash Next accuracy

Batched decoding over slots (`--slots 2`): while two requests write their answers, their next tokens and drafts run
in one engine pass, so the weights are read once for both. Tok/s of the two together, taking turns -> batched:

| Model | Prose | Code |
|---|---|---|
| Qwen3.8 27B (MTP / DFlash2) | 7.32 -> 10.48 (1.43x) | 11.63 -> 15.42 (1.33x) |
| Qwen3.6 35B-A3B (MTP / DFlash2) | 20.24 -> 24.65 (1.22x) | 28.97 -> 30.73 (1.06x) |
| Gemma 4 26B-A4B (no drafter) | 19.80 -> 26.15 (1.32x) | 19.60 -> 26.47 (1.35x) |

Engine steps without drafts (`runz --bench-batch`): 27B 2 / 3 / 4 slots 1.78 / 2.43 / 3.04x one slot's speed, 35B
1.35 / 1.67 / 1.91x, Gemma 26B 2 / 3 slots 1.30 / 1.58x. A question in one slot while another processes a 46K-token
prompt (35B) is answered after 9.6 s (49 s when the turns were every step).

Gemma 4 26B-A4B (19 Oct, experts on the SSD, expert file 13.2 GB): prompt 4K 450 tok/s, 8K 410; generation
19.6-20.6 tok/s.

Flash Next (20 Oct): the two-pass int8 input of the hyper-connection mixers' up projection is the default: prompt 4K
168.4 -> 159.8 tok/s, 9,000 tokens 148.3 -> 138.6; KL 0.0647 -> 0.0483.

The MTP block's KV rows of DFlash2 steps (20 Oct, a bug fix) left the speed unchanged: 256-token answers, best of two,
35B prose 20.56 -> 21.01 tok/s, code 37.45 -> 38.65; 27B prose 8.91 -> 8.78, code 15.76 -> 16.29.

## 2026-10-18 (later): deep prefetch, 35B chunk 8192, drafter variants

Full table with the checks: [before-after.md](before-after.md#changes-newest-first).

**Deep expert prefetch** (arcinferzero, prompts with >= 2048 tokens; `ARC_XCOPY=0` turns it off): while the GPU runs
layer L of a prompt, a thread reads every missing expert of layer L+1 from the SSD and the GPU's copy engine copies
them into their slots. Logits bit-identical (56 regression runs).

| Prompt | Before | After |
|---|---|---|
| Flash Next, 4096 tokens | 107 tok/s | 166 |
| Flash Next, 9000 tokens | 116.9 tok/s | 144.5 |
| Flash Next, 32K tokens (GPU idle on SSD reads) | 131.7 tok/s (62.4 s) | 162.6 (5.8 s) |
| 35B, 32K at ctx 131K | 488.6 tok/s | 557 |
| 35B, 41 % expert cache | 541 tok/s | 592 |

**35B prompt chunks 4096 -> 8192** (ctx 262K; Flash Next stays at 2048). Not compared bit for bit: the chunk size
groups the prompt arithmetic differently.

| Chunk | 2048 | 4096 | 8192 |
|---|---|---|---|
| Expert cache | 83 % | 81 % | 77 % |
| 32K prompt | 485 tok/s | 533 | 604 |
| 128K prompt | 284 tok/s | 306 | 324 |
| Generation at 128K depth | 13.0 tok/s | 12.8 | 12.6 |

**Drafter variants** (`<id>-nodf`: MTP block only; `<id>-df`: DFlash2 only, MTP block not loaded; `--draft
auto|mtp|dflash`). Greedy text identical in every mode.

| 35B UD-IQ4_XS | both (default) | MTP only | DFlash2 only |
|---|---|---|---|
| Python code | 45.1 tok/s | 39.1 | 49.9 |
| Indonesian prose | 21.0 tok/s | 21.9 | 16.5 |

The 27B `-df` (no MTP block) gets an automatic context of 94,208 tokens instead of 69,632.

## 2026-10-18: long contexts with the experts streamed from the SSD

`runz`, no image encoder loaded (the server also holds one: about 1 GB less expert cache). Generation: 128-token
answers right after loading (short prompt); "hit" is the expert cache hit rate during generation; the SSD column is
everything read from the expert file, mostly the cache fill at load. Long prompts: synthetic tokens
(`--bench-pp`, one run), then 64 tokens of plain decoding at that depth. Pauses between runs (the laptop throttles
when hot).

### Qwen3.6 35B-A3B UD-IQ4_XS (18.2 GB; experts 14.7 GiB in the expert file)

The file: expert `down` IQ4_XS (37 layers) / Q6_K (3), `gate` and `up` IQ3_S (39 of 40 layers), dense parts Q8_0,
output Q6_K. The expert file (15.8 GB) is written once at the first load.

| Context | Expert cache (DFlash2 + MTP) | Code, DFlash2 + MTP | Indonesian, DFlash2 + MTP | Code, MTP only | Indonesian, MTP only | Plain |
|---|---|---|---|---|---|---|
| 32,768 | 12.96 GiB (88 %) | 39.0 * | 19.6 * | – | – | – |
| 65,536 | 12.61 GiB (86 %) | 48.6 | 21.7 | – | – | – |
| 98,304 | 12.26 GiB (83 %) | 48.9 | 21.6 | – | – | – |
| 131,072 | 11.91 GiB (81 %), hit 100 % | 47.5 | 20.7 | 34.6 (cache 87 %) | 22.0 | 21.2 (90 %) |
| 262,144 | 10.48 GiB (71 %), hit 93-96 % | 36.5 | 19.2 | 36.6 (78 %) | 23.4 | 21.2 (81 %) |

\* the first run after the expert file was written and the kernels compiled.

| Context | Prompt | Generation at that depth (plain) |
|---|---|---|
| 131,072 (prompt 125,000) | 321 tok/s (6.5 min) | 13.5 tok/s (median step 72.8 ms) |
| 262,144 (prompt 250,000) | 193 tok/s (21.6 min) | 10.6 tok/s (median step 92.5 ms) |

Against the OpenCL engine with UD-Q3_K_M (section "Prompt and generation at different context lengths" below):
prompts +27 % at 131K (253.5 -> 321) and +32 % at 262K (146 -> 193); generation at depth about the same
(13.8 / 10.1 then).

- The 35B's KV cache is small (10 attention layers, 2 KV heads): from 32K to 262K the expert cache only drops from
  88 % to 71 % (81 % without drafters), so short answers stay fast up to 131K.
- At depth, generation is bound by **reading the KV cache**, not by the SSD: a step takes ~48 ms at a short context
  and 92 ms after 250K tokens; the difference matches reading ~2.6 GB of int8 K/V per token at ~60 GB/s. A 4-bit V
  (or K and V) cache would cut that directly (see the accuracy section below).
- DFlash2 at 262K: no gain for code (36.5 vs 36.6 MTP only) and a loss for Indonesian (19.2 vs 23.4): its 8-row
  verification touches more experts while the cache is smaller. At 131K it still pays for code (47.5 vs 34.6).
- **Recommended context: 131,072** (cache 81 % with DFlash2 + MTP, hit 100 % in these runs, the same speed as 64K).
  262,144 works, but DFlash2 should then be off, and long sessions run close to the 60 % cache where generation used
  to stall (server, 17 Oct).

### Qwen3.8 Flash Next IQ3_S (83.6 GB; experts 52.1 GiB, expert file rebuilt 18 Oct)

| Context | Expert cache | Hit (code / Indonesian) | Code | Indonesian |
|---|---|---|---|---|
| 32,768 | 11.55 GiB (22 %) | 77.4 / 82.8 % | 5.99 tok/s | 6.87 |
| 65,536 | 11.12 GiB (21 %) | 76.2 / 81.9 % | 5.99 | 6.66 |
| 98,304 | 10.68 GiB (20 %) | 75.0 / 80.9 % | 5.90 | 6.60 |
| 131,072 | 10.24 GiB (20 %) | 74.2 / 79.9 % | 5.85 | 6.44 |
| 262,144 | 8.44 GiB (16 %) | 70.8 / 78.0 % | 5.47 | 6.23 |

| Context | Prompt | Generation at that depth (plain) |
|---|---|---|
| 131,072 (prompt 125,000) | 78.6 tok/s (26.5 min); **123.4 (16.9 min) with qsa_score_rt** | 3.35 tok/s (median step 190 ms; the first step took 7.3 s); 5.38 (median 184 ms) |
| 262,144 (prompt 250,000) | 37.8 tok/s (110 min) | 3.97 tok/s (median step 240 ms) |

- The cache is a fifth of the experts at any context, so the context costs little: from 32K to 131K short answers
  lose 2-6 %, at 262K 9-10 %.
- Long prompts are the limit: 165 tok/s at 8K, 79 at 125K, 38 at 250K (measured before qsa_score_rt). The slowdown
  grew faster than the length: the QSA block scores read the whole pooled key array once per query row. With 8 rows
  per work-group (`qsa_score_rt`, same logits) qsa_score fell from 13.8 to 2.4 s on a 32K prompt (pp32768 131-146 ->
  153-154 tok/s) and the 125K prompt went from 78.6 to 123.4 tok/s; the 250K prompt was not measured again.
- **Recommended context: 131,072** (−2 to −6 % against 32K); 262,144 only for occasional very long documents.

Since 18 Oct the automatic context gives both MoE models 131,072 tokens (it reserves 128K of context before sizing
the expert cache; it reserved 32K before).

### 4-bit KV cache: accuracy (simulated)

`ARC_KV4` rounds K and / or V as llama.cpp's q4_0 does (blocks of 32, 16 levels) before they are stored in the int8
cache, so the attention kernels are unchanged and only the accuracy is measured (no memory or speed gain yet).
Perplexity over the second half of each chunk of a code + documentation text (zero/engine.h and two docs files),
and KL of each scored token's distribution against the int8 run (its top 64 tokens + the rest as one bucket). The
first row of each model is the cost of int8 itself: f16 K/V (`--attn-f32`) against int8.

| Model | Context | Variant | Perplexity | KL vs int8 | Same top token |
|---|---|---|---|---|---|
| 27B | 8K | f16 (vs int8) | 2.1917 (int8 2.1928) | 0.0006 | 99.2 % |
| 27B | 8K | V 4-bit | 2.1970 | 0.0027 | 98.7 % |
| 27B | 8K | K + V 4-bit | 2.1963 | 0.0064 | 97.6 % |
| 27B | 32K | V 4-bit | 1.9979 (int8 1.9954) | 0.0024 | 98.6 % |
| 27B | 32K | K + V 4-bit | 2.0013 | 0.0060 | 97.8 % |
| 35B | 8K | f16 (vs int8) | 2.6639 (int8 2.6718) | 0.0112 | 97.8 % |
| 35B | 8K | V 4-bit | 2.6838 | 0.0160 | 96.6 % |
| 35B | 8K | K + V 4-bit | 2.7001 | 0.0311 | 95.8 % |
| 35B | 32K | V 4-bit | 2.3554 (int8 2.3494) | 0.0095 | 97.2 % |
| 35B | 32K | K + V 4-bit | 2.3659 | 0.0145 | 96.5 % |
| Flash Next | 8K | V 4-bit | 2.2003 (int8 2.2036) | 0.0238 | 95.6 % |
| Flash Next | 8K | K + V 4-bit | 2.2071 | 0.0313 | 95.0 % |
| Flash Next | 32K | V 4-bit | 2.0438 (int8 2.0406) | 0.0220 | 95.9 % |
| Flash Next | 32K | K + V 4-bit | 2.0450 | 0.0291 | 95.3 % |

- The error does not grow from 8K to 32K.
- K is more sensitive than V (K + V costs 2-2.5x the KL of V alone), as expected.
- The MoE models react more to any change (a slightly different attention output can pick other experts): for the
  35B even f16 against int8 gives KL 0.011, and V 4-bit adds about as much again.
- Flash Next has no f16 baseline: `--attn-f32` had no QSA masks (perplexity 42.6); it is refused for QSA models now.
- Scale granularity of a 4-bit V at 8K (KL vs int8): 27B 0.0027 (per 32 dims) / 0.0032 (per 64) / 0.0047 (per
  256 = one scale per key, which the current P x V kernels can fold into P like the int8 scale); 35B 0.016 / 0.021 /
  0.030 (perplexity 2.6838 / 2.6690 / 2.6884, int8 2.6718).
- Candidate: a real V-only 4-bit cache for long contexts (35B at 250K: the K/V reads are ~45 ms of a 92 ms step). A
  per-key scale is the simple kernel change (nibbles, an 8 x sum(P) correction per tile) but doubles the error of
  q4_0's per-32 scales; per-64 scales need the SB > 1 path of every attention kernel.

### 4-bit V copy for generation (`--v4`, opt-in, since 18 Oct)

`--v4` keeps the int8 V that prompt chunks read and adds a 4-bit copy that generation and the verification of
drafts read (attn_decode / attn_split / attn_dsplit, up to 8 rows): prompts keep their speed, generation at depth
reads half the V bytes, and the KV cache takes ~25 % more memory. The copy: per key and 64-dim block a scale
amax / 7 and 16 levels (n - 8) (an exact zero). Grids compared first with the `ARC_KV4` simulation (35B, 8K, KL vs
int8): (n - 8) * amax / 7 per 64 dims 0.0172, / 8 0.0212, (n - 7.5) * amax / 7.5 0.0237, per key 0.0264, per 128
dims 0.0292 (q4_0 per 32: 0.016).

35B UD-IQ4_XS, ctx 131,072:

| | int8 | `--v4` |
|---|---|---|
| 125K prompt | 321 tok/s | 316 |
| Generation after it (median step) | 72.8 ms (13.5 tok/s) | 67.5 ms (14.3 tok/s) |
| 32K prompt (attention) | 540 tok/s (15.4 s) | 570 (15.7 s) |
| Expert cache | 90 % | 87 % |
| Generation-path accuracy (8K fed 8 tokens at a time): perplexity, KL vs int8 | 2.8805 | 2.8915, 0.0208 |
| Flash Next, the same | 2.3162 | 2.2877, 0.0297 |
| 35B, 32K fed 8 tokens at a time | 2.3491 | 2.3600, 0.0124 |

At ctx 262,144 (35B): the 250K prompt 193 -> 190.8 tok/s, generation after it 92.5 -> 84.9 ms per step (10.6 ->
11.5 tok/s), expert cache 81 -> 76 %: the smaller cache does not cancel the gain.

**int8 windows (since 18 Oct evening).** Generation reads the first 128 keys (sink) and each row's last 4096 keys
(recent window) from the int8 V and only the rest from the 4-bit copy (`ARC_V4_SINK`, `ARC_V4_RECENT`; runtime
only, the cache layout is the same). 35B generation path, KL vs int8:

| sink / recent | 8K | 32K |
|---|---|---|
| 0 / 0 | 0.0232 | 0.0124 |
| 128 / 1024 | 0.0188 | – |
| 128 / 2048 | 0.0119 | – |
| **128 / 4096 (default)** | **0.0080** (perplexity 2.8691, int8 2.8805) | **0.0053** (2.3516, int8 2.3491) |

At 125K the windows are 3 % of the keys; the measured step was 70.7 ms (int8 72.8, without windows 67.5), within the
run-to-run spread, not separated further (the tests were stopped: `--v4` stays an option). Per-tile scale search
(squared-error optimal, `ARC_KV4=V64O`) was worse: 0.0221 vs 0.0172 for amax / 7 (outliers matter more than the mean
error). Under `--v4` the verification rows of the dense models run one by one (each has its own recent window):
27B MTP code 15.6 -> 14.6 tok/s.

Greedy answers with MTP and DFlash2 are identical to plain decoding under `--v4`; tool calls, prefix reuse and the
session cache (saved, server restarted, loaded again: the same follow-up answer; an int8 server refuses those
files) work through the server; the default path is bit-identical to before. Not measured: Flash Next's
generation path at 32K and beyond (8K: KL 0.0297).

#### First version (17-18 Oct): one 4-bit V for prompts and generation


Per key and 64-dim block a scale amax / 7.5 and 16 levels (n - 7.5) (the scale folds into P like the int8 one;
q4_0's signed scale cannot). 35B UD-IQ4_XS, against the int8 cache:

| | int8 | `--v4` |
|---|---|---|
| 8K perplexity, KL vs int8 | 2.6718 | 2.6749, 0.0245 (27B: 2.1928 -> 2.1934, 0.0041) |
| 125K prompt | 321 tok/s | 241 |
| Generation after 125K (median step) | 72.8 ms | 66.6 (14.7 tok/s), expert cache 90 -> 92 % |
| 250K prompt | 193 tok/s | 135 |
| Generation after 250K (median step) | 92.5 ms | 86.1, expert cache 81 -> 85 % |
| 32K prompt: attention / attn_prep | 15.4 / 0.31 s | 24.9 / 0.33 s |

Generation at depth gains 7-8 % (memory-bound attention reads half the V bytes); prompts lose 25-30 % because the
prompt attention is ALU-bound and with per-64 scales P is re-quantized four times per 16-key tile instead of once
(the atomics that write the nibbles cost nothing measurable). Greedy answers with MTP and DFlash2 are identical to
plain decoding under `--v4`; the default path is bit-identical to before.

## 2026-10-17: speculative decoding, MoE prompts, Flash Next

| Change | Before | After |
|---|---|---|
| Token-outer multi-token GEMVs (verification rows) | 27B FFN, 8 rows: 23 GB/s | 39-43 GB/s |
| Default MTP drafts 27B 3 -> 7, 35B 3 -> 5 | 27B code 12.6 tok/s, 35B code 34.2 | 15.2, 37.7 |
| 2-5-token GEMVs: 4 rows per sub-group for codebook types / long rows | 27B Indonesian with MTP 6.95 tok/s | 7.2 |
| DFlash2 drafter weights Q4_0 (was Q8_0) | 27B code 16.9 tok/s | 17.2 (drafter 0.84 GiB smaller) |
| DFlash2 selector: one-pass top-16 instead of nth_element | 35B code 48.4 tok/s, 27B 16.9 | 52.7, 18.3 |
| Draft confidence with a vectorized float exp | 35B code DFlash2 49.4 tok/s, MTP 37.5 | 53.3, 39.1 |
| DFlash2 probes backed off on dense models | 27B Indonesian hybrid 6.2 tok/s | 6.5 |
| Cached experts computed while missing ones are read from the SSD | Flash Next generation 6.6 tok/s | 7.3 |
| Flash Next prompt mixer (gated mean) with vector loads | 45 ms per 2048-row chunk; pp8192 98 tok/s | 3.7 ms; 127 |
| moe_rg (MoE GEMM on raw expert rows) for Flash Next's down projection | pp8192 145 tok/s | 165 |
| moe_rg for 35B 384-1152-token chunks | 412 / 440 / 449 / 486 / 529 tok/s (384 / 512 / 768 / 1024 / 1152) | 424 / 459 / 511 / 520 / 548 |
| serverz reports 4096-token chunks for streamed MoE (was 2048) | 35B pp8192 620 tok/s | 750 |
| Automatic context: expert cache first for streamed MoE | 35B server: 253,952 tokens, 60 % cache, 10-15 tok/s | 32,768-40,960 tokens, 77 % cache, ~32 / 18 tok/s (code / Indonesian) |
| Automatic context: Flash Next | 4,096 tokens (the 60 % cache reservation did not fit) | 32,768 |

**Later:** since 18 Oct the 35B uses 8192-token prompt chunks and Flash Next 2048 (35B at ctx 262K: 32K prompt
533 -> 604 tok/s); the automatic context reserves 128K before sizing the expert cache, so both MoE models get 131,072
tokens (35B cache ~76-81 %, Flash Next ~20 %). See the 18 Oct sections above.

Details of each change: [arcinferzero-log.md](archive/arcinferzero-log.md) (16-17 October entries).

## 2026-10-16: arcinferzero (Level Zero) becomes the default engine

arcinferzero, overnight results, 15 → 16 October 2026.

Tests ran from 17:00 to 06:05. Since this morning zero is the default engine; the old OpenCL engine is still available with `--opencl`. Every number here comes from real runs on this laptop.

Hardware: Core Ultra 5 125H, Arc Xe-LPG 112 EU, no XMX (DP4a), 32 GB RAM.


### Summary

| Measurement | Result | Context |
|---|---|---|
| Qwen3.6 35B, MTP 3 drafts (code) | 31.5 tok/s | 19.9 without MTP, identical answers |
| Gemma E4B, 2K prompt | 827 tok/s | 733 the evening before (+13 %) |
| Qwen3.8 27B, MTP (code) | 9.1 tok/s | 5.1 without MTP; 5 drafts used to be 3.8 |
| Match with OpenCL | 6 / 6 models | bit-identical logits, same image and audio answers |

### Answer speed through the server

400-token answers at temperature 0 to two questions: Python code, and an explanation of TCP/UDP in Indonesian. Answers with MTP are always exactly the same as without it. Values in tok/s.

| Model | Drafts | Without MTP | MTP, code answer | MTP, Indonesian answer |
|---|---|---|---|---|
| Qwen3.5 4B | 3 drafts | 20.5 | 30.4 | 25.9 |
| Qwen3.5 9B | 2 drafts | 12.1 | 16.7 | 15.0 |
| Qwen3.8 27B | 3 drafts | 5.1 | 9.1 | 7.4 |
| Qwen3.6 35B | 3 drafts | 19.9 | 31.5 | 24.6 |
| Gemma E4B | drafter | 21.6 | 39.6 | – |
| Gemma 12B | drafter | 9.8 | 21.1 | – |

Gemma uses its assistant drafter (not MTP) and was measured with the code question only (baseline, evening of 15 Oct). The Qwen numbers come from the last runs with the final build.

### Number of MTP drafts

Mean of the code and Indonesian answers, tok/s. More drafts are not automatically faster: every draft runs the MTP block with the full output head.

| Model | 1 | 2 | 3 | 4 | 5 | 7 | Default |
|---|---|---|---|---|---|---|---|
| Qwen3.5 4B | – | 22.9 | 24.8 | 25.2 | – | – | 3 (was 2) |
| Qwen3.5 9B | – | 15.8 | 15.6 | 15.9 | – | – | 2 |
| Qwen3.8 27B | – | – | 8.3 | – | 8.2 | 8.2 | 3 |
| Qwen3.6 35B | 23.9 | – | 26.1 | – | – | – | 3 (was 1) |

**Later (17 Oct):** with the token-outer multi-token GEMVs more drafts did pay off; the defaults became 7 for the
27B and 5 for the 35B (code 12.6 -> 15.2 and 34.2 -> 37.7 tok/s), 3 for the 4B and 2 for the 9B.

### Prompt and generation at different context lengths

`runz --bench-pp`: a prompt of N tokens, then 64 generated tokens. Prompt = tok/s processing the prompt; gen = tok/s generating after it. The "later" columns are a second, later measurement: for Gemma, evening of 15 Oct → morning of 16 Oct; for the Qwen3.8 27B prompt, morning → afternoon of 16 Oct (faster prompt GEMM; generation not re-measured). "–" means not re-measured.

| Model | Context | Prompt | Gen | Prompt, later | Gen, later |
|---|---|---|---|---|---|
| Qwen3.5 4B | 2K | 862.5 | 20.2 | – | – |
| | 16K | 696.9 | 18.7 | – | – |
| | 131K | 280.5 | 9.5 | – | – |
| Qwen3.5 9B | 2K | 399.1 | 12.1 | – | – |
| | 16K | 387.9 | 11.5 | – | – |
| | 131K | 221.9 | 8.8 | – | – |
| Qwen3.8 27B | 2K | 110.2 | 5.1 | 130.1 | – |
| | 16K | 102.8 | 4.7 | 125.4 | – |
| | 64K | 79.6 | 4.0 | – | – |
| Qwen3.6 35B | 2K | 660.0 | 20.1 | – | – |
| | 16K | 678.7 | 18.8 | – | – |
| | 131K | 253.5 | 13.8 | – | – |
| | 262K | 146.1 | 10.1 | – | – |
| Gemma E4B | 2K | 733.3 | 21.0 | 827.5 | 21.5 |
| | 16K | 571.1 | 19.6 | 624.9 | 20.1 |
| | 131K | 209.4 | 9.5 | 197.2 | 9.4 |
| Gemma 12B | 2K | 270.6 | 9.5 | 289.4 | 9.6 |
| | 16K | 218.4 | 9.2 | 227.7 | 9.2 |
| | 131K | 86.1 | 7.4 | 86.5 | 7.6 |

Generation after a long prompt is sometimes very noisy (one E4B run at 32K dropped to 10.8 from 17.9 tok/s). Seven repeat runs were steady at 18.5–19.0, so the E4B drop at 131K in a single run (209 → 197) is not treated as a regression yet.

### Kernels improved

| Kernel | Before | After |
|---|---|---|
| 35B generation attention, 64K | 1.16 ms | 0.94 ms (improved) |
| GEMV for 4–7 drafts (27B, 5 drafts) | 3.8 tok/s | 9.2 tok/s (improved) |
| attn_prep_g Gemma HD512, spill | 4,608 B | 0 (improved) |
| add_norm_quant Gemma, spill | 3,712 B | 64 B (improved) |
| gdn_conv Qwen, spill | 1,024 B | 1,024 B |
| moe_gateup_q 35B, spill | 2 KB | 2 KB |

The last two spills go away with 256 registers, but that is not faster, so they stay.

### Qwen prompt attention

The last 4K chunk at 64K depth, ms per layer. The current kernel (256 registers) against the best variant that splits the head dimensions.

| Model | Heads | attn_q8 (in use) | best attn_ps |
|---|---|---|---|
| 4B / 9B | 16 q / 4 kv | 926 ms | 1,117 ms |
| 35B | 16 q / 2 kv | 923 ms | 1,138 ms |
| 27B | 24 q / 4 kv | 1,516 ms | 1,669 ms |

### Correctness

| Test | Result |
|---|---|
| Logits, zero vs OpenCL, 11K tokens (4B, 9B, 27B, E4B, 12B) | bit-identical |
| Qwen3.6 35B with the same prompt chunking | bit-identical |
| Gemma E4B / 12B after this morning's spill fixes | bit-identical |
| Images (E4B, 12B, 9B) and audio (E4B, 12B) | same answers |
| MTP with 1–7 drafts, every Qwen model | same answers |
| Gemma tool calls with the constraint (stress test) | 9/10 valid (was 2/10) |
| API formats (OpenAI, Anthropic, Ollama, Responses, JSON schema, logprobs) | all working |
| API unit tests and tool-call streaming | all passed |
| New 35B generation attention, KL vs the f32 reference | within noise (flagged for attention) |

### Notes

- Correction: during the night I first concluded that Level Zero ignores the 256-register flag. That was wrong; my own environment switch came out empty. Every number on this page was measured again with the correct build.
- A server started right after another one stops sometimes runs at half speed. `arc-server stop` now waits 5 seconds, and runz logs the time of every step so the cause can be seen if it happens again.
- Not done yet: cheaper MTP drafts (a dynamic token list or a draft tree), and the two small spills above.
  **Later:** a fixed draft vocabulary was tried on 17 Oct and dropped (Indonesian tokens lie beyond id 131,072); the
  host-side cost of drafting was cut instead (one-pass top-K, vectorized softmax: 35B code 44 -> 53 tok/s).

## 2026-10-10 to 2026-10-14: the OpenCL engine, from the first version

Performance test report for arcinferzero, 10–14 October 2026: prompt processing (prefill) and token generation for models from 4B to 35B on the Intel Arc iGPU, from the first version to the current state.

**Running a 35B model on a laptop without a discrete graphics card.** This report summarizes the performance tests of arcinferzero, an inference engine built specifically for the Intel Arc iGPU, from its first version to its current state. The tests cover prefill (prompt processing) speed and token generation speed on six models, from Qwen3.5 4B to Qwen3.6 35B-A3B.

Every measurement was taken on the same machine. Data sources: the arcinferzero CHANGELOG, QUEUE, review_notes ([archive/review_notes.md](archive/review_notes.md)) and bench/results.


### Test platform

| Item | Value |
|---|---|
| CPU | Core Ultra 5 125H |
| iGPU | Arc, 112 EU (7 Xe-cores, 2.2 GHz) |
| Matrix units | No XMX (DP4a int8 only) |
| int8 peak | 13 TOPS (DP4a, measured) |
| Memory | 32 GB LPDDR5x |
| Bandwidth | ~75 GB/s measured (102 theoretical) |
| GPU allocation | 18.3 GiB (shared with Windows) |
| API | OpenCL 3.0 (Level Zero from 16 October) |

### The main limit: memory bandwidth

During token generation the model reads all of its weights once for every generated token. With a measured memory bandwidth of about 75 GB/s, the upper bound on generation speed is simply `75 GB/s ÷ weight size`. For example, Qwen3.8 27B with about 11 GB of weights can reach only about 6.5 tokens per second in theory, however good the kernels are.

So the most useful measure for generation is not tokens per second alone but **the share of bandwidth actually used**. In the first measurement Qwen3.8 27B used only 36 % of the bandwidth. The rest was lost in three places:

- **Decoding the quantization format:** formats such as IQ3_S, IQ2_XXS and IQ4_XS need extra compute to unpack into weight values.
- **Unaligned reads:** most blocks start at addresses that are not a multiple of 4 bytes, so they cannot be read with vector instructions.
- **Kernel launch overhead:** too many small kernels, each with a fixed cost.

#### Bandwidth use during token generation (% of ~75 GB/s)

| Model | First measurement | After the GEMV optimizations |
|---|---|---|
| Qwen3.5 4B | 64 % | 79 % |
| Qwen3.5 9B | 72 % | 86 % |
| Gemma 4 E4B | 68 % | 81 % |
| Gemma 4 12B | 80 % | 82 % |
| Qwen3.8 27B | 36 % | 72 % |
| Qwen3.6 35B | – | 58 % |

First measurement: QUEUE item 2. After the optimizations: quantization blocks re-laid-out so they can be read with aligned vector loads (12–13 October). Qwen3.6 35B has only one data point because the MoE expert kernel reads small, scattered blocks.

The largest gain came from a step that looks simple: **re-laying-out the bytes**. GGUF puts the `f16` scale at the start of every block, so the quantized data after it lands on an address that is not a multiple of 4 bytes. Moving the scale to the end (IQ2/IQ3) or gathering the scales at the start of the superblock (Q8_0, Q4_0) lets every GPU lane load its block in one vector instruction. The effect on GEMV speed per quantization type:

#### GEMV speed per quantization type (GB/s)

| Type | Before | After |
|---|---|---|
| Q8_0 | 37 | 77 |
| IQ2_XXS | 27 | 60 |
| IQ3_XXS | 41 | 62 |
| IQ3_S | 61 | 66 |
| IQ4_XS (E4B q) | 44 | 67 |
| Q6_K (head) | 66 | 72 |

Source: CHANGELOG 12 October (GEMV bandwidth) and review_notes (IQ4_XS gemv_v on E4B: q matrix 44 → 67 GB/s).

### Token generation: from the first version to now

The table below compares generation speed in the first measurement with the current state. For models that have an MTP block (Qwen) or a drafter (Gemma), the result with speculative decoding is shown too: a small model guesses several tokens at once and the main model verifies them in one pass. The output stays bit-identical to plain decoding, only faster.

#### Token generation speed (tokens/s)

| Model | First measurement | Now, without MTP | Now, with MTP / drafter |
|---|---|---|---|
| Qwen3.5 4B | 17.1 | 20.4 | – |
| Qwen3.5 9B | 10.3 | 12.0 | – |
| Gemma 4 E4B | 16.9 | 21.2 | 30.7 |
| Gemma 4 12B | 7.5 | 9.1 | 18.5 |
| Qwen3.8 27B | 4.1 | 4.9 | 9.5 |
| Qwen3.6 35B | 17.5 | 19.8 | 22.3 |

Qwen3.8 27B with MTP reaches 9.5 tok/s on code (3 drafts); on general text the number is lower. Gemma 4 12B and E4B: the first measurement used a community quantization file that was later replaced by Google's official QAT file (Q4_0). Qwen3.6 35B: the first measurement used the standard Unsloth file (12 October); the earlier 2-bit GSQ version was around 15 tok/s.

### Prefill: getting the most out of int8 compute

Prefill behaves differently from generation. Thousands of tokens are processed together, so the weights are reused many times and the limit moves from memory bandwidth to compute. This iGPU has no matrix units (XMX) and relies only on the `DP4a` instruction, four int8 multiplies in one step, with a peak of about 13 TOPS. arcinferzero converts all weights to int8 (W8), quantizes the activations per 32 values, and runs them through its own DP4a GEMM kernels, which reach 6–9 TOPS.

For comparison, here are results against llama.cpp (build b11527, Vulkan and SYCL backends, flash attention on, best ubatch) with the same prompts:

| Speedup | Measurement |
|---|---|
| 6× | Qwen3.8 27B, 11,240-token prompt: 97 s, against 590 s (Vulkan) and 504 s (SYCL) |
| 7.4× | Qwen3.8 27B, 33,937-token prompt: 5.5 minutes, against 40 minutes (Vulkan) |
| 3.8× | Qwen3.5 4B pp2048: 911 tok/s, against 242 (Vulkan) and 337 (SYCL) |
| 4.9× | Gemma 4 12B, 35,957-token prompt: 240 s, against 1,165 s (Vulkan) |

#### Prefill speed pp2048 (tokens/s)

| Model | arcinferzero | llama.cpp Vulkan | llama.cpp SYCL |
|---|---|---|---|
| Qwen3.5 4B | 911 | 242 | 337 |
| Qwen3.5 9B | 402 | 151 | 189 |
| Gemma 4 12B | 240 | 96 | – |
| Qwen3.8 27B | 113 | 23 | 25 |
| Qwen3.6 35B | 642 | – | – |

Source: bench/results/results.jsonl, 10 October (first test). Gemma 4 12B used a community Q4_K_M quantization file; SYCL was not tested. Qwen3.6 35B: llama.cpp cannot load the GSQ file, so only the arcinferzero number for the Unsloth Q3_K_M file is shown (13 October).

The lead also shows in generation after a long prompt. At 34K tokens of context Qwen3.8 27B still generates 3.70 tok/s, against 2.06 tok/s for Vulkan and 1.09 tok/s for SYCL. The difference comes from int8 attention: keys and values are stored as int8 with a per-row scale, and both the `Q·K` scores and `P·V` also use DP4a.

### Qwen3.8 27B: time to first token down from 116 to 89 seconds

The 11,240-token prompt on Qwen3.8 27B has been the reference since the start of development. Each step below is one optimization that proved to work:

| Time to first token | Step |
|---|---|
| 116 s | first version with correct output |
| 112 s | int8 attention scores and tiles in local memory |
| 101 s | int8 P·V, int8 V cache, head splitting |
| 94 s | split-K and Q4_K conversion to signed int8 |
| 91 s | per-layer prefill (W8 decode only once) |
| 89 s | fused SwiGLU and vectorized convolution |

Attention alone went from **33 seconds to 5.1 seconds**. This was done in stages: int8 scores with the key tile in local memory, then int8 `P·V` (probabilities quantized to 8 bits per block, following the SageAttention approach), then splitting heads across sub-groups.

### Qwen3.6 35B-A3B: mixture of experts on an iGPU

Qwen3.6 35B has 256 experts in every layer, but only 8 are active for each token. For generation this is a big advantage, since only about 2.4 GB is read per token, so the 35B runs about 4 times faster than the 27B. For prefill it is the opposite: each expert gets only about 64 tokens per 2,048-token prompt chunk, too few for GEMM to work efficiently. The optimizations done so far:

| Optimization (Qwen3.6 35B) | Before | After |
|---|---|---|
| Q8_0 stored once and decoded per prompt chunk | context 61,440 | 208,896 (Q3_K_S) |
| Router and shared expert fused into one GEMV | 17.4–18.5 tok/s | 18.2–18.8 tok/s |
| Experts run with int8 GEMM (decode per 64 experts, then GEMM per tile) | 476 tok/s | 642 tok/s (pp2048) |
| IQ3_XXS decode through local memory (decode_w8_sl) | 1,038 ms | 518 ms per chunk |
| DeltaNet qkv and z fused into one GEMV | 19.2 tok/s | 19.8 tok/s |
| MTP block enabled (Unsloth MTP repo file, Q3_K / Q4_K on the GPU) | 19.7 tok/s | 22.3 tok/s (83 % of drafts accepted) |
| MoE buffers share memory with the attention buffers | context 86K | 102,400 |
| Prompt attention with 4 heads per sub-group (21,590 tokens) | 9.4 s | 8.4 s |

### Accuracy: speed must not cost correctness

> An optimization that changes the output, however slightly, is not accepted.

Every optimization on the decode path is checked in two ways:

- **KL divergence against an f32 reference:** the token distribution is compared with a full-precision CPU computation. Results: Qwen3.5 4B 0.0021, Qwen3.6 35B (GSQ) 0.0008, Gemma 4 12B QAT 0.021.
- **Bit identity for MTP:** output with speculative decoding must be exactly the same as plain decoding on a 2K-token prompt.

The second check caught a well-hidden bug on the 35B. Two-token verification used an attention kernel that split the keys differently from the one-token kernel. As a result the text started to diverge after about 40 tokens, and only on long prompts. After the fix, the 35B MTP output is bit-identical again.

### Long context

Automatic context uses as much of the remaining GPU memory as possible after the weights, the work buffers and about 1.2 GiB kept free for Windows (**Later:** for MoE models with streamed experts the automatic context now reserves 128K of context before sizing the expert
cache, which gives 131,072 tokens; see the 18 Oct sections). Results at the extremes:

| Model | Prompt length | Processing time | Generation afterwards |
|---|---|---|---|
| Qwen3.5 4B | 235,929 tokens | 27.3 minutes (144 tok/s) | 9.0 tok/s |
| Gemma 4 E4B | 117,965 tokens | 11.9 minutes (165 tok/s) | 11.6 tok/s |
| Qwen3.8 27B | 81,100 tokens | 16.4 minutes (82 tok/s) | 4.9 tok/s |
| Qwen3.6 35B | 21,590 tokens | 44 s (493 tok/s) | – |

When used as an agent (Pi), these numbers are rarely felt directly. The server keeps the running conversation, so each turn processes only the new tokens. The per-project system prompt is also cached on disk, so a new Qwen3.8 27B session on a project that was opened before can start in about 5 seconds, against about 40 seconds before.

### Optimizations that did not pay off

Not every idea worked. These approaches were tried and dropped, with the reason:

- **Level Zero instead of OpenCL.** The gap between kernels was only 1.6–2 %, not worth rewriting the runtime.
  **Later: overturned.** Level Zero was built anyway (arcinferzero) and became the default engine on 16 October:
  bit-identical results, MoE experts streamed from the SSD with a GPU cache (35B at long contexts, Flash Next at all),
  explicit control of memory and queues, and many kernels made faster on it since (see the 16 and 17 October
  sections). The 1.6-2 % figure measured only the launch gaps, not what the runtime made possible.
- **SIMD8 GEMM.** Reached 13.7 TOPS in a microbenchmark, but was slower in the model.
- **P·V in f16.** No speedup, and the KL got worse.
- **32-key attention tile.** 14–20 % slower because of register spills.
- **Split-K in GEMV.** 512-row matrices were 10–15 % faster, but other matrices slowed down, so no gain overall.
- **W8 with a min value.** Only 2.4 TOPS, three times slower than converting to signed int8.
- **Byte-pair LUT for IQ4_XS.** Dropped from 66 to 55 GB/s; a small table in registers is still better.
- **Fusing down and combine (35B).** 212 ms against 211 ms. Fewer kernels are not automatically faster.
- **Q8_0 through gemv_v.** Slower than GEMV with a local-memory window.
- **Per-chunk DeltaNet.** Only 4–9 % of prefill time, so the extra complexity is not worth it.
- **attn_ps for the Qwen configurations.** Only 1.0–1.6 T MAC/s, below attn_q8 at about 2.2.
- **A third MTP draft on the 4B and the MoE.** No speed gain. Defaults: 3 drafts for the 27B, 1 for the MoE, and 2 for the other models.
  **Later: overturned** by faster multi-token verification: defaults now 7 (Qwen 27B-class, and whenever DFlash2
  drafts), 5 (MoE, 35B), 3 (4B), 2 (9B and Gemma).

### Next steps

Two priorities matter most to keep long-context performance up:

- **4-bit KV cache:** halves the data read per token at deep context and doubles the maximum context, provided its accuracy passes the tests.
- **Decode the 35B experts once per layer:** today about 22 % of the 35B prefill time is spent decoding the same weights again for every prompt chunk.
  **Later:** partly addressed on 17 Oct: 4096-token chunks (decode share 29 -> 17 %), and moe_rg, which reads the raw
  expert rows without the decode pass, for 320-1279-token chunks. Decoding once per layer across chunks is still
  open (it needs per-chunk MoE buffers of ~1 GB). **Later (18 Oct):** 8192-token chunks for the 35B give most of
  that gain (32K prompt 533 -> 604 tok/s), so decoding once per layer was not built.

Methodology note: generation numbers are the best of two runs, because the first run after another process stops tends to be slower, and the iGPU lowers its clock by about 5–8 % under sustained load. During this period some models also changed files (Gemma community quantization to Google QAT; 35B GSQ to Unsloth), and the tables note where the first measurement came from a different file.
