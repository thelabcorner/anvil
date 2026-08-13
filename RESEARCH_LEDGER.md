# ANVIL Research Ledger — Initial Implementation

## Experiment A — Greedy LZ + adaptive arithmetic backend

**Hypothesis:** Separate adaptive models for token type, literal-run length, match length, distance, and literals can give a compact first implementation without transmitting entropy tables.

**Result:** Correct and compact, but the Fenwick-backed arithmetic decoder is the dominant performance problem.

On the 26,904-byte Project ANVIL task document:

- encoded size: 11,212 bytes
- ratio: 0.417
- encode: 18.76 MB/s
- decode: 21.19 MB/s

**Conclusion:** Keep as a ratio/reference backend, not the primary performance path.

## Experiment B — Bit-cost-aware DP parse

**Hypothesis:** A parse minimizing an estimated bit objective can beat longest-match greedy parsing.

**Result:** With the same order-0 arithmetic backend, output fell from 11,212 to 11,107 bytes (-0.94%), while encode throughput fell from 18.76 to 4.41 MB/s.

**Conclusion:** The representation responds to parse optimization. The next parser iteration should use costs derived from the actual downstream coder and reduce candidate-search overhead.

## Experiment C — Naive order-1 literal contexts

**Hypothesis:** Previous-byte contexts improve literal entropy.

**Result:** On the task document, order-1 increased DP output from 11,107 to 11,491 bytes (+3.46%). The sparse per-context models spend too long in cold-start states.

**Conclusion:** Reject unconditional order-1 as a default. Confidence-gated modes remain implemented for cross-corpus testing, but the current document selects order-0.

## Experiment D — Separated-stream static rANS

**Hypothesis:** De-interleaving token domains and replacing Fenwick arithmetic decoding with static rANS will materially improve decode speed at modest ratio cost.

**Result:** DP+rANS produces 11,232 bytes versus 11,107 for DP+arithmetic (+1.13%), but median decode throughput improved from ~20.16 MB/s to ~163.72 MB/s (~8.1x). Greedy+rANS reaches ~145.44 MB/s decode and ~39.49 MB/s encode on the same document.

**Conclusion:** Strongly validated. rANS becomes the performance backend; arithmetic remains a compression-ratio comparator.

## Baseline snapshot — task document

| Codec | Bytes | Ratio | Encode MB/s | Decode MB/s |
|---|---:|---:|---:|---:|
| ANVIL greedy arithmetic | 11,212 | 0.417 | 18.76 | 21.19 |
| ANVIL DP arithmetic | 11,107 | 0.413 | 4.41 | 20.16 |
| ANVIL greedy rANS | 11,414 | 0.424 | 39.49 | 145.44 |
| ANVIL DP rANS | 11,232 | 0.417 | 4.95 | 163.72 |
| Brotli q1 | 11,903 | 0.442 | 248.05 | 321.72 |
| Brotli q4 | 10,203 | 0.379 | 65.47 | 537.29 |
| Brotli q6 | 9,725 | 0.361 | 44.58 | 547.45 |
| Brotli q9 | 9,709 | 0.361 | 4.14 | 467.94 |
| Brotli q11 | 8,275 | 0.308 | 1.01 | 359.05 |
| Zstd 1 | 11,103 | 0.413 | 364.01 | 913.42 |
| Zstd 3 | 10,594 | 0.394 | 283.02 | 826.57 |
| Zstd 9 | 10,115 | 0.376 | 59.96 | 761.44 |
| Zstd 19 | 9,880 | 0.367 | 5.96 | 711.82 |

This is one small development file, not evidence of a general-purpose win. ANVIL currently beats Brotli q1 in compressed bytes on this input, but loses badly in throughput, so it is **not** a Pareto victory.

## Next highest-value experiments

1. Replace sampled heuristic DP costs with measured rANS stream costs and iterative re-parsing.
2. Replace byte-at-a-time match-copy with specialized small-distance and wide-copy kernels.
3. Add four-way interleaved rANS states to expose instruction-level parallelism.
4. Encode distance as class + low bits instead of generic varint bytes.
5. Introduce a dual-timescale phrase dictionary across independent blocks.
6. Test lightweight reversible transforms only through the block router; reject them unless end-to-end bytes improve.
7. Add standard corpora and peak-RSS measurement before making any cross-codec performance claims.

## Four-file smoke aggregate

A second smoke pass used four heterogeneous local files: the ANVIL task markdown, the ANVIL C++ source, deterministic generated JSON, and 256 KiB deterministic pseudo-random data. This is still **not** a standard corpus and used one timed repetition per codec, so treat throughput as directional.

Environment:

- x86-64, AMD EPYC 9V74
- Debian GNU/Linux 13
- GCC 14.2.0, `-O3 -DNDEBUG`
- Brotli library 1.1.0
- Zstd 1.5.7

Aggregate result is computed as total compressed bytes / total input bytes. Aggregate throughput is total bytes divided by summed per-file measured time.

| Codec | Aggregate ratio | Encode MB/s | Decode MB/s |
|---|---:|---:|---:|
| ANVIL greedy arithmetic | 0.371942 | 19.59 | 50.37 |
| ANVIL DP arithmetic | 0.345498 | 2.88 | 61.04 |
| ANVIL greedy rANS | 0.372972 | 39.31 | 218.70 |
| ANVIL DP rANS | 0.345777 | 3.05 | 225.05 |
| Brotli q1 | 0.365250 | 484.83 | 786.50 |
| Brotli q4 | 0.364779 | 150.44 | 1039.58 |
| Brotli q6 | 0.347324 | 54.60 | 1142.93 |
| Brotli q9 | 0.342482 | 16.60 | 1085.65 |
| Brotli q11 | 0.311155 | 0.99 | 650.92 |
| Zstd 1 | 0.360045 | 758.19 | 1809.03 |
| Zstd 3 | 0.359825 | 592.25 | 2187.74 |
| Zstd 9 | 0.349152 | 87.03 | 1758.20 |
| Zstd 19 | 0.325202 | 3.29 | 1820.75 |

Interesting result: DP+rANS reaches ratio 0.345777, slightly smaller than Brotli q6's 0.347324 in this smoke aggregate, but it is far slower in both encode and decode throughput. Therefore this is **not a Pareto win**; it only demonstrates that the current representation has enough ratio potential to justify continued systems work.

The raw row-level data is in `tests/benchmark-suite.csv`.

## Experiment E — SPARSE-REF R1 (block mode 11, flat bitmask) — FIRST MEASURED EVIDENCE

**Hypothesis (agenda §1):** a sparse-corrected phrase copy — copy a prior
phrase, entropy-code a sparse correction mask + residuals — beats exact-LZ on
record-structured data while staying LZ-fast. R1 ships the minimal form:
rep A flat 32-bit mask words (4 B per 32 B window), single-pass greedy parser
over literal/exact/sparse edges, cost rule = mask(L/8 bits) + residuals at
literal cost vs exact+literals over the same span.

**Mechanism as implemented (by `arch`, t-sparse):** block mode 11,
`--parse=sparse` (single candidate) + `--parse=auto` (router). Seven
substreams: token types, lit-len varints, match-len varints, dist varints,
literals, correction masks, residual bytes. Decoder = copy + sparse stores.
Existing modes 0-10 untouched. Correctness: round-trip verified on all 9
corpus files; fuzz 480 variants + ASan/UBSan clean; canonical fuzz.py
(incl. sparse) 350 variants PASS.

**A/B results (Windows, clang-cl Release, single-rep directional —
independently re-measured by `research`, agrees with `arch`):**

| File | sparse (m11) | dp-rans | greedy-rans | sparse vs dp |
|---|---:|---:|---:|---:|
| generated.jsonl (2.82 MB, stress) | **0.0790** | 0.0874 | 0.1074 | **−9.6% bytes** |
| generated.repeat.jsonl (control) | 0.00126 (1182 B) | 0.00123 (1157 B) | 0.00123 (1152 B) | **+2.2% bytes** |
| random.bin (control) | 1.0001 | 1.0 | 1.0 | degrades to raw block |
| generated.log | 0.0942 | 0.0906 | 0.1182 | +4.0% (dp wins) |
| generated.json | 0.1635 | 0.1381 | 0.1754 | +18.4% (dp wins) |
| src.cpp | 0.3239 | 0.2986 | 0.3048 | +8.5% (dp wins) |
| doc.md | 0.5971 | 0.5775 | 0.5929 | +3.4% (dp wins) |

**Encode speed (the headline):** on generated.jsonl, sparse encodes at
**~35 MB/s vs ~1.5 MB/s dp-rans (~21x)** while matching/beating its ratio.
Decode ~222 MB/s (sparse) vs ~211 (dp-rans) — comparable, still far from
Brotli q9's ~900 MB/s on this file.

**Verdict per the novelty gate (agenda §1.3, FLAG-A/B/C):**

- **RATIO-VALIDATED on its target domain.** On the record-structured stress
  file, sparse-corrected edges deliver −9.6% bytes vs the best exact-LZ
  baseline (dp-rans) at ~21x encode speed. This is the falsifiable claim's
  ratio leg, confirmed.
- **NOT a Pareto win (FLAG-A binds).** Decode ~222 MB/s is still ~4x slower
  than Brotli q9's ~900 MB/s on the same file — the decode leg of the
  falsifiable target (≥3x brotli decode) fails. Ratio-vs-decode plane still
  dominated. Recorded as a result, not a claim.
- **No-regression guard — CORRECTION to `arch`'s handoff.** On the
  identical-record control, standalone mode 11 is **+2.2% larger than
  dp-rans (1182 vs 1157 B)** — a real, deterministic delta (ratio CV =
  0.000%), not "no regression". The flat-A mask costs ~L/8 bits even when
  corrections are zero. The router protects this case: `--parse=auto` picks
  dp-rans (873 B) on the repeat control and dp on src.cpp — the mechanism
  never ships worse when routed. But a standalone `--parse=sparse` default
  would regress identical-record files by ~2%; this is an R2 mask-topology
  target (a "mask==0 → exact edge" shortcut should recover the delta).
- **Sparse loses where records are absent** (src.cpp, doc.md, generated.json
  small-structure): exact-LZ dp wins; the router correctly selects exact
  blocks there. Expected per agenda §1.2 — SPARSE-REF targets repetitive-but-
  not-identical data.

**Why it works (overlap nuance, flagged by `arch`, confirmed by re-measure):**
overlapping sparse copies (len > dist) are periodic — the encoder must
compute corrections against `src[j % dist]`, and offsets are relative to the
copy DESTINATION start, not the source. Decoder does copy + sparse stores,
so the periodic aliasing is where the "structural distance" lives: a record
period of ~92 B copied with corrections at field offsets is exactly the
edge type exact LZ cannot express. This is the empirical validation of
agenda claim 3 (structural-distance propagation), in its R1 minimal form.

**Next (R2 candidates, per agenda):** mask topology coding (flat-A is now
the measured baseline — 1182 vs 1157 B shows the headroom), mask==0 shortcut,
structural-distance channel reuse (R5). `bench` will add anvil-sparse-rans
rows (median 3) to the full-corpus regression before any further claim.

**Decoder safety (t-format closure, `format`):** FORMAT.md now specs mode 11
exactly as landed (7 substreams S0-S6, flat 32-bit mask words, strict type-2
invariants incl. mask-bits-beyond-len rejection, len(residuals)==popcount(mask),
full substream consumption, CRC). Malformed-input audit
(`docs/decoder-audit.md`) found two shared-machinery gaps: unbounded substream
raw_n → ~1 GiB alloc on a 65 KB file, and unbounded declared total — both
closed by arch's landed fixes (max_n=16*out_len+64; total ≤ (in.size()/7+2)·
2^26), re-verified as instant rejects. Fuzz strengthened (mutations phase
asserting reject-or-identical; 6200+ variants, 15700+ mutations across two
seeds, all PASS; all 10 corpus files round-trip on --parse=auto and
--parse=sparse). This is the safety gate's evidence for mode 11 — a
precondition for any Pareto claim, since a decodable-but-unsafe wire would
disqualify the mechanism regardless of ratio.
