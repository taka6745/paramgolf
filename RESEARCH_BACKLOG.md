# Research Backlog — candidate pool for the stack-novelty campaign

**Day-1 seed: 30 candidates (3 per layer).** The C30 research cron appends more on every fire. The C5 monitor cron pops from the top of each layer's table when a pod's queue runs dry. Slot #3 in each layer is the world-novel seed.

See `STACK_NOVELTY_PLAN.md` for the per-layer hypothesis details and the world-novel justifications. This file is the **operational queue**, not the design doc.

Schema for every row:
```
| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
```

`novelty_estimate` ∈ `world-novel-candidate` | `comp-novel` | `in-comp` | `unknown`. `code_skeleton_loc` is rough lines-of-code for implementation. `added_utc` is when the row was added (so we can age out stale candidates).

**Minimum backlog floor: every layer must have ≥5 untried candidates.** When a layer drops below 5, the next C30 fire prioritizes filling it (3 WebSearches + 1 GitHub search).

---

## L13 — Eval-time techniques (LEGAL only)

The single biggest unspent leverage per COMPETITION_SCOPE.md gap analysis. 234
PRs use TTT (best 0.3212 with SLOT), 85 PRs use LEGAL_TTT (best 0.7139). The
top legal open PRs (#642, #620, #512, #940, #761, #1185) all use this category.

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | LEGAL_TTT_per_batch_split | C90 1148Z — port from PRs #642/#620/#512/#940/#761 | per-batch context/target split (50/50) + K SGD steps on context + eval CE on target only; weights reset between batches; legal because no val-data leakage across docs | -0.20 to -0.40 BPB (cheap-pod 1.41 → projected ~1.0-1.2 with TTT) | **comp-port** **SHIPPED 1148Z** as LEGAL_TTT_MARKER | 200 | 20260408T1148Z |

---

## L11 — Infra/throughput (virtual cross-cutting layer)

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | SPD_ngram_tile_cache | C90#5 0700Z infra build | in-place fp16 cast of bigram/trigram/fourgram tables on first forward → halves gather bandwidth on n-gram critical path | 5-10% step time reduction (n-gram path) | infra-novel **SHIPPED 0700Z** as SPD_NGRAM_TILE_CACHE_MARKER | 50 | 20260408T0700Z |
| 2 | SPD_pinned_prefetch | C90#6 0700Z infra build | 1-deep async prefetch of next batch in pinned host memory + non-blocking H2D copy via background thread on DistributedTokenLoader | 3-7% step time reduction (data load overlap) | infra-novel **SHIPPED 0700Z** as SPD_PINNED_PREFETCH_MARKER | 100 | 20260408T0700Z |
| 3 | SPD_rmsnorm_fused_into_linear | C90 plan-A — DEFERRED, deemed too risky for in-flight stack (interacts with LN_SCALE) | precompute rmsnorm scale into next Linear weight; eliminate F.rms_norm forward op per block | 5-15% step time reduction | infra-novel | 70 | 20260408T0700Z |
| 4 | CPU_worker_pool_brotli_ngraminspect | C90#7 0710Z infra build | run N-2 CPU workers per pod consuming jobs from data/cpu_jobs/pending/ in parallel with GPU training; brotli sweeps + ngram inspect; closes PD8 gap (idle CPU) | indirect — finds best brotli level for L10 + n-gram tile sizes for L09 | infra-novel **SHIPPED 0710Z** as cpu_workers.py + cpu_jobs_emitter.py + run_forever.sh hook | 280 | 20260408T0710Z |
| 5 | KER_fused_ngram_attention_triton | C30#7 — Triton kernel fusion for our (8h, 4kv, 64) GQA shape | hand-tuned Triton kernel fuses (n-gram fp16 gather + SDPA + residual accumulate) into 1 kernel; eliminates 3 D2H/H2D boundary crossings per attn block | -25 to -35% attn forward time → 20-25% more steps → -0.008 to -0.015 train_loss | **world-novel-candidate** | 280 | 20260408T0750Z |
| 6 | RAM_persistent_kernel_step_unroll | C30#7 — NVIDIA CUDA persistent kernel + torch.cuda.CUDAGraph capture of full inner training step | capture forward + backward + opt.step as 1 CUDA graph; persistent kernel (occupancy=100%); separate scalar-op stream hides bias/LN latency behind tensor-core compute | -8 to -15% step time → -0.010 to -0.020 BPB via step budget reallocation | **world-novel-candidate** | 250 | 20260408T0750Z |
| 7 | DYN_lyapunov_exponent_gradient_clip | C30#9 — nonlinear dynamics (Oseledec stability theory) | estimate dominant Lyapunov exponent λ₁ from rolling 20-step grad_norm history; auto-clip when λ₁ exceeds threshold → prevents bifurcation into oscillatory instability; cleaner gradient signal | -0.008 to -0.015 BPB (stability preserves step effectiveness) | **world-novel-candidate** **SHIPPED 0825Z** as DYN_LYAPUNOV_CLIP_MARKER | 90 | 20260408T0800Z |
| 8 | DYN_phase_portrait_attractor_checkpoint | C30#9 — dynamical systems (basin of attraction + phase recovery) | monitor 3D phase portrait (loss, grad_norm, entropy(logits)); detect drift > 2σ from training attractor; soft-checkpoint restore within 1 step → recovers from transient divergence without hard reset | -0.010 to -0.020 BPB (fewer divergence episodes) | **world-novel-candidate** | 200 | 20260408T0800Z |
| 9 | DYN_bifurcation_mixed_precision_schedule | C30#9 — control theory (bifurcation detection + Lyapunov-margin parameter switching) | detect phase transitions (warmup→main, main→cooldown) via control-Lyapunov stability margin; switch precision at bifurcation points (fp32→fp16 at main, fp16→int8 at cooldown) → cheaper matmuls when stable | -0.008 to -0.015 BPB (precision elasticity + step reallocation) | **world-novel-candidate** | 180 | 20260408T0800Z |
| 10 | KER_tma_megakernel_mlp_port | C30#10 audit — SOTA `record/tma-megakernel-triple-loop` (b27fe93) by Andrew Baggio | port the Triton TMA async descriptor + persistent kernel that fuses fc→leaky_relu→square in MLP path; +10.5% throughput → +127 steps in 10 min budget | -0.02 to -0.03 BPB (validated by SOTA val_bpb 1.08480) | **comp-port** **SHIPPED 0905Z** as KER_TMA_MEGAKERNEL_MARKER (Hopper-only, falls back on cheap pods) | 200 | 20260408T0810Z |

---

## L12 — Comp-port baseline gaps (from 1.07/1.08 SOTA stack audit)

These are NOT world-novel but ARE necessary baseline pieces. The SOTA val_bpb 1.08480 (`record/tma-megakernel-triple-loop`, b27fe93) uses ALL of these. Without them as a base, our world-novels can only reach the trigram floor 1.10. With them as a base + our world-novels stacked on top = potential winning combination.

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | SP8192_VOCAB | C30#10 audit — SOTA stack uses 8192 vocab | expand vocabulary 1024→8192; rebuild bigram/trigram/4-gram tables for dense coverage; unlocks BigramHash 3072×112 cascade | -0.08 to -0.12 BPB | **comp-port** (highest impact missing piece) | 200 (chore script + tokenizer swap + table rebuild) | 20260408T0810Z |
| 2 | WEIGHT_EMA_SWA_COMBO | C30#10 audit — PR #1019 abaybektursun | EMA 0.997 + SWA every 50 steps; final model is weighted blend; orthogonal to params | -0.006 to -0.010 BPB | **comp-port** **SHIPPED 0815Z** as WEIGHT_EMA_SWA_MARKER | 100 | 20260408T0810Z |
| 3 | GPTQ_FULL_HESSIAN_AR | C30#10 audit — PR #1019 abaybektursun | full Hessian GPTQ + autoregressive self-gen calibration (64×2048 tokens, temp=0.8); legality-safe (no train/val data access during quant) | -0.008 to -0.015 BPB | **comp-port** | 180 | 20260408T0810Z |
| 4 | BIGRAMHASH_EXPAND_3072 | C30#10 audit — PR #1019 abaybektursun | scale BigramHash from 1536×64 → 3072×112; stays under 16 MB | -0.004 to -0.008 BPB | **comp-port** | 40 | 20260408T0810Z |
| 5 | DEPTH_RECUR_NUM_LOOPS_3 | C30#10 audit — SOTA b27fe93 | DEPTH_RECUR with NUM_LOOPS=3 (vs our 1) — deeper recurrence over the same params | -0.005 to -0.010 BPB | **comp-port** | 20 (env var change + validation) | 20260408T0810Z |

---

## L01 — Tokenizer candidates

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | TOK_bpe8192_standard | LESSONS §18c | BPE-8192 with frequency merges; Mac claims -0.129 BPB at 500 steps; tables exist on disk but never built for vocab=8192 | -0.05 to -0.13 BPB | comp-novel | 30 (tokenizer swap + table rebuild script) | 20260408T0000Z |
| 2 | TOK_vocab512_compact | inverted §33 logic | smaller vocab → bigram coverage densifies → more bias signal per byte | -0.01 BPB net (after n-gram tables grow) | comp-novel | 25 | 20260408T0000Z |
| 3 | TOK_entropy_aware_bpe_merge | Plan-A WebSearch + extension of LESSONS §18c | merge pairs whose joint distribution has lowest residual joint entropy after merge → maximize compression of bigram surprise into vocab | -0.05 train_loss vs vanilla BPE-8192 | world-novel-candidate | 80 (custom sentencepiece training loop) | 20260408T0000Z |
| 4 | TOK_dynamic_byte_codepoint_merger | C30#2 — ByteFlow arXiv:2603.03583 extension | compute next-byte entropy per position online; place merge boundaries where prediction entropy is highest (hard-to-predict bytes don't merge) | -0.04 to -0.08 BPB | comp-novel | 90 | 20260408T0312Z |
| 5 | TOK_frequency_variance_BPE | C30#2 novel synthesis | merge pairs by frequency × variance ratio: prioritize merges that REDUCE variance in token-length distribution → more uniform token difficulty across vocab | -0.015 BPB | **world-novel-candidate** | 65 | 20260408T0312Z |
| 6 | TOK_learned_byte_huffman_init | C30#2 novel synthesis (Huffman + SentencePiece weight prior) | build Huffman tree on FineWeb byte frequencies; codeword lengths become initialization signal for SentencePiece merge weights → biases vocab toward info-theoretic optimality | -0.02 to -0.05 BPB | **world-novel-candidate** | 75 | 20260408T0312Z |
| 7 | TOK_entropy_patch_boundary_dynamic | C30#4 — Meta BLT arXiv:2412.09871 + custom hybrid synthesis | fork SentencePiece; merge boundaries placed at next-byte entropy peaks computed by an auxiliary 2-layer byte predictor; bytes hardest to predict don't compress together | -0.08 to -0.14 BPB | **world-novel-candidate** | 250 (auxiliary entropy net + sentencepiece fork) | 20260408T0426Z |
| 8 | TOK_morphology_aware_segmentation_fine_grain | C30#4 — Slovak SKMT (2025) + LiteToken dedup (Feb 2026) | train BPE on morpheme-segmented FineWeb; forbid merges that cross root boundaries; drop intermediate merge residues | -0.04 to -0.08 BPB | **world-novel-candidate** | 180 | 20260408T0426Z |
| 9 | TOK_adaptive_vocab_gradient_aware_training | C30#4 novel synthesis — Rho-1 + GPTQ Hessian | train tokenizer JOINTLY with model: each merge step ranked by Fisher info on downstream feedforward weight gradients; vocab aligns with model's learning dynamics | -0.06 to -0.12 BPB | **world-novel-candidate** | 220 | 20260408T0426Z |
| 10 | TOK_cross_boundary_supermerge_byte | C30#6 — BoundlessBPE COLM 2025 (arXiv:2504.00178) + byte-level adaptation | allow SentencePiece merges across FineWeb tokenization boundaries (spaces, punctuation); track merge contexts; prune merges that reduce next-byte predictability in validation split | -0.06 to -0.12 BPB | **world-novel-candidate** | 140 (sentencepiece fork + boundary tracking + validation loop) | 20260408T0635Z |
| 11 | TOK_learned_merge_auxiliary_predictor | C30#6 — arXiv:2602.13940 RL tokenization + byte synthesis | maintain a tiny 2-layer byte predictor (~50KB) during BPE training; rank merge candidates by (frequency × entropy_reduction / predictor_loss_delta); gradient-aware merge ordering | -0.07 to -0.13 BPB | **world-novel-candidate** | 180 (auxiliary predictor + merge ranking loop + STE backprop) | 20260408T0635Z |
| 12 | TOK_merge_residue_culling_litetoken_byte | C30#6 — LiteToken Feb 2026 adapted to byte-level | post-train, measure each token's training-frequency vs final-tokenization frequency; remove top-K residues whose final freq < 0.01× training freq; reallocate vocab; validate held-out BPB | -0.04 to -0.08 BPB | **world-novel-candidate** | 90 (frequency tracking + cull heuristic + rebuild table) | 20260408T0635Z |
| 13 | TOK_hyperdimensional_byte_hdvector | C30#7 cross-domain — Frady+Kleyko 2022 hyperdimensional computing transplanted to byte-level vocab building | embed 3-byte windows in 16384-dim HDV (random projection + binding); rank merge candidates by (frequency × HDV-cosine-similarity); vocab self-organizes around byte-context affinity not visible to vanilla freq | -0.06 to -0.14 BPB | **world-novel-candidate** | 160 | 20260408T0750Z |
| 14 | TOK_audio_codec_mdct_alphabet | C30#7 cross-domain — MP3/AAC MDCT filterbanks (Bellanger 1983, ITU-T G.722.1) | run MDCT on sliding 8-byte windows; rank merge candidates by (frequency × MDCT high-band energy); vocab biased toward bytes that co-occur in acoustically-dense regions | -0.04 to -0.10 BPB | **world-novel-candidate** | 140 | 20260408T0750Z |
| 15 | TOK_input_token_smooth | C90#8 0710Z novel synthesis — input-side analog of label smoothing | with prob p, replace embed[T] with 0.5*embed[T] + 0.5*mean(embed[K random tokens]); forces robustness to embedding noise on rare tokens; no artifact rebuild needed | -0.005 to -0.012 BPB | world-novel-candidate **SHIPPED 0710Z** as TOK_INPUT_SMOOTH_MARKER **DEMOTED 0915Z** | 60 | 20260408T0710Z |
| 16 | TOK_kraft_inequality_merge_validator | C30 1212Z — Kraft 1949 + ICLR 2025 info-theory tokenization (info-theory pollination) | during BPE merge phase, validate each proposed merge against Kraft's inequality (Σ 2^-L_i ≤ 1); prune merges that violate prefix-free property; rerank by frequency × kraft_efficiency. Yields decoder-unambiguous vocab with minimal average codeword length | -0.03 to -0.08 BPB | **world-novel-candidate** | 110 (sentencepiece fork + merge validation loop + Kraft sum tracker) | 20260408T1212Z |
| 17 | TOK_arithmetic_coding_merge_frequency | C30 1212Z — Arithmetic Coding (Rissanen 1976) + BLT (Meta 2024) (info-theory pollination) | score BPE merge candidates by arithmetic code length -log2(p_merge); prioritize merges with lowest AC cost. Vocab self-organizes toward arithmetic-optimal prefix assignment | -0.04 to -0.10 BPB | **world-novel-candidate** | 95 | 20260408T1212Z |
| 18 | TOK_kolmogorov_complexity_pruning_inference | C30 1212Z — Kolmogorov 1965 + Neural NCD arXiv:2410.15280 + MDL (info-theory pollination) | post-BPE, estimate K_LB(t) per token via tiny 2-layer compressor; prune top-K high-KC "noise" tokens; reallocate vocab to predictable sub-tokens | -0.02 to -0.06 BPB | **world-novel-candidate** | 130 | 20260408T1212Z |

---

## L02 — Data pipeline candidates

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | DAT_coprime_stride_validate | existing Patch 19 | USE_COPRIME_STRIDE=1; coprime-to-seq_len stride decorrelates batches | -0.005 train_loss | comp-novel | 0 (env var only) | 20260408T0000Z |
| 2 | DAT_in_batch_dedup | standard pretrain hygiene | drop seqs whose first 256B already appeared this batch; FineWeb has duplicate boilerplate | -0.005 train_loss | comp-novel | 40 | 20260408T0000Z |
| 3 | DAT_byte_entropy_curriculum | Plan-A novel | order shards low-to-high zstd-ratio; easy bytes first → curriculum → faster early loss drop → more effective steps in 10 min | -0.015 train_loss | world-novel-candidate **SHIPPED 0451Z** as DAT_BYTE_ENTROPY_CURRICULUM_MARKER + chore/09_compute_shard_entropy.py | 60 | 20260408T0000Z |
| 4 | DAT_loss_stratified_minibatching | C30#5 — arXiv:2405.07490 + custom probe | compute per-sample loss on tiny 2-layer probe; stratify into difficulty quartiles; minibatches with fixed difficulty ratios (hard:medium:easy = 1:1:1) | -0.012 to -0.025 train_loss | world-novel-candidate | 110 | 20260408T0451Z |
| 5 | DAT_adaptive_sampling_temperature_schedule | C30#5 — curriculum + importance sampling | running per-sample CE histogram; sampling weight w(t)=exp(β(t)·rank); β starts 0.1 ramps to 2.0 → hard samples 8× more often as training progresses | -0.008 to -0.018 train_loss | world-novel-candidate | 95 | 20260408T0451Z |
| 6 | DAT_cross_shard_rle_biased_interleaving | C30#5 — RLE-aware shuffle | detect high-RLE sequences (zstd > 0.4); coprime interleave biased toward structure-dense early; preserve linguistic patterns | -0.006 to -0.015 train_loss | world-novel-candidate | 85 | 20260408T0451Z |
| 7 | DAT_heterogeneity_loss_weight | C30#10 — FineWeb-Edu byte-class analysis (~10% code, ~17% URLs, ~42% wiki, ~30% prose) | per-sample loss reweighting schedule β(t): 0.1→2.0 over 600s; hard samples (code, URLs detected via byte signatures) weighted 8× more by step 600 | -0.010 to -0.020 BPB (10-15% effective step gain on hard content) | **world-novel-candidate** | 120 | 20260408T0810Z |
| 8 | DAT_byte_entropy_stratified_minibatch | C30#10 — FineWeb heterogeneity stratification | compute zstd-ratio per 2048-token sequence; stratify into 4 buckets (easy→hard); minibatch construction: 25% hard + 50% medium + 25% easy (inverse of curriculum) | -0.005 to -0.012 train_loss | comp-novel | 85 | 20260408T0810Z |
| 9 | DAT_domain_gated_smoothing | C30#10 — FineWeb domain-aware label smoothing | online 2-layer 512→256 byte-histogram domain classifier predicts {code, URL, wiki, prose}; per-domain ε ∈ {0.02, 0.005, 0.01, 0.008}; inverts standard label smoothing (harder on rare, softer on easy) | -0.006 to -0.012 BPB | **world-novel-candidate** | 95 | 20260408T0810Z |
| 10 | DAT_mdl_compressible_first_reorder | C30 1212Z — MDL principle Rissanen 1978 + arXiv:2504.09597 (info-theory pollination) | reorder shards by online zstd-ratio but PRIORITIZE incompressible (high-entropy) sequences early — INVERSE of byte_entropy_curriculum. Anti-curriculum: high-entropy data teaches structure faster, improving effective steps before high-density curriculum stabilization | -0.008 to -0.015 train_loss | **world-novel-candidate** **SHIPPED 1232Z via existing BEC_REVERSE=1 flag** (no new marker needed; existing DAT_BYTE_ENTROPY_CURRICULUM_MARKER infrastructure supports both directions via BEC_REVERSE env var) | 0 (uses existing infra) | 20260408T1212Z |
| 11 | DAT_mutual_info_lightweight_subsequence_dedup | C30 1212Z — Kolmogorov structure func arXiv:2504.09597 + LSHBloom arXiv:2411.04257 (info-theory pollination) | rolling Bloom filter (128 MB) of 8-byte subsequence hashes; skip 256-byte chunks where >50% rolling 8-byte windows already seen → online MI reduction | -0.006 to -0.012 train_loss | comp-novel (online dedup is standard, MI-justified application is novel) | 110 | 20260408T1212Z |
| 12 | DAT_entropy_rank_quartet_stratified | C30 1212Z — entropy stratification + smooth curriculum (info-theory pollination) | partition shards into 4 entropy quartiles via byte histogram H(b); curriculum: epoch 1=Q1, epoch 2=50/50 Q1+Q2, epoch 3=33/33/33, epoch 4+=balanced. Smooth (not abrupt) entropy-ranked curriculum | -0.010 to -0.018 train_loss | **world-novel-candidate** | 95 | 20260408T1212Z |

---

## L03 — Embedding candidates

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | EMB_dual_codebook_lloyd_max | LESSONS §37 | K-means cluster the 1024 embeddings into 64 prototypes + int4 residual; ~1.7 MB freed | -0.005 BPB indirect | comp-novel | 70 | 20260408T0000Z |
| 2 | EMB_factorized_2matmul | LESSONS §22 | (vocab × 64 + 64 × 512) tied head; bypass tied-head constraint, save 1.87 MB | -0.003 BPB after spending freed bytes | comp-novel | 50 | 20260408T0000Z |
| 3 | EMB_hadamard_rotated_tied | Plan-A WebSearch (PALU/HiRA ICLR 2025 extension) | precompose Walsh-Hadamard rotation R into tok_emb; logits unchanged exactly, but quant noise after rotation is uniformly spread → lower int4/int6 GPTQ error | -0.004 BPB at int6, -0.012 at int4 | world-novel-candidate | 90 (Hadamard buffer + GPTQ-aware rotate) | 20260408T0000Z |
| 4 | EMB_poly_fourier_embed | C30 WebSearch — PETE arXiv:2505.02266 (May 2025) | replace learned tok_emb with Fourier polynomial expansion of token IDs ([cos(2πk/V), sin(2πk/V), ...]) + light MLP projection; saves ~0.5 MB → reallocate to n-gram tables | -0.008 BPB indirect | comp-novel | 45 | 20260408T0245Z |
| 5 | EMB_tied_tensorized_tt | C30 WebSearch — arXiv:1901.10787 + arXiv:2401.12819 | TT-decompose tok_emb (1024×512) into ranks [1,16,16,1] and share factors with output projection (dynamic tying); saves ~1.2 MB | -0.006 BPB indirect | comp-novel | 80 | 20260408T0245Z |
| 6 | EMB_byte_adaptive_projection_mixing | C30 novel synthesis — Bolmo (2025) entropy-driven inversion | learned sigmoid gate ϕ(byte_entropy_bucket) routes between (a) compact 512-d learned embedding for common bytes and (b) 256-d Fourier for rare bytes; allocates capacity by frequency | -0.007 BPB | **world-novel-candidate** | 70 | 20260408T0245Z |
| 7 | EMB_dct_coefficient_energy_truncate | C30#3 signal-processing pollination — alphaXiv 2508.00220 | DCT-II on (1024, 512) tok_emb; truncate to top-K coefficients carrying 85% energy; reconstruct sparse → 30-40% size reduction with preserved logit geometry at int6 | -0.006 to -0.012 BPB indirect | **world-novel-candidate** **SHIPPED 0451Z** as EMB_DCT_COEFFICIENT_ENERGY_TRUNCATE_MARKER | 70 | 20260408T0349Z |
| 8 | EMB_wavelet_hard_threshold_dyadic | C30#3 SP — Daubechies-4 wavelet + WaveletGPT distinction | wavelet decomposition + hard thresholding on detail coefficients; multi-resolution: smooth dims compressed, sharp dims preserved. Distinct from WaveletGPT which targets activations | -0.004 to -0.010 BPB indirect | **world-novel-candidate** | 95 | 20260408T0349Z |
| 9 | EMB_polyphase_token_phase_routing | C30#3 SP — Bellanger / Crochiere-Rabiner audio codec polyphase | split 1024 vocab into 4 cohorts (ID % 4 → phase); each phase uses (256, 512) sub-embedding; sum outputs → 62% storage reduction. Audio codec technique transplanted to vocabulary routing | -0.008 to -0.015 BPB indirect | **world-novel-candidate** | 85 | 20260408T0349Z |
| 10 | EMB_mdct_polyphase_projection | C30#6 — cross-domain pollination: MDCT filterbanks (audio MP3/AAC) + Bellanger 1983 polyphase | split 1024 vocab into 16 polyphase channels via learned rotation R; project each channel through 64×32 MDCT-preconditioned matrix (cosine kernel from MP3/AAC filterbank); learned summation reconstruction → 50% size reduction; **MDCT block-overlap matches vocab cluster boundaries for quantization robustness** | -0.008 to -0.016 BPB indirect | **world-novel-candidate** | 110 | 20260408T0635Z |
| 11 | EMB_spherical_norm_compression | C30#6 — Jina AI spherical compression Jan 2026 + byte-vocab application | normalize embeddings to unit sphere; learnable per-dim 4-bit nonlinear quantization with entropy-adaptive bin placement (learned histogram, not uniform); reconstruction error <1e-6 on logit geometry; **byte-vocab clusters tightly on sphere** | -0.005 to -0.010 BPB indirect (1.0-1.5 MB freed) | **world-novel-candidate** | 85 | 20260408T0635Z |
| 12 | EMB_learned_hessian_codebook_tiling | C30#6 — Goya/GPTQ-Lite Hessian-aware + group-adaptive K-means | compute Fisher-Hessian of logit loss w.r.t. embedding rows; cluster into 32 prototype groups by Hessian norm; assign each group its own K-means codebook (rank 4-8 by importance); critical rows get higher precision | -0.006 to -0.012 BPB indirect | comp-novel | 130 | 20260408T0635Z |
| 13 | EMB_lsq_gradient_aware_embedding_quantization | C30 1127Z — LSQ ICLR 2020 + GWQ arXiv:2411.00850 fusion | apply Learned Step-Size Quantization (learnable scalar α per layer) to tok_emb during training; use Fisher/Hessian to allocate bits per embedding DIMENSION (not row): high-gradient dims get more bits, rare-byte dims fewer. Tied head inherits factorization automatically | -0.008 to -0.015 BPB (1.1-1.8 MB freed via int4 + learned step) | **world-novel-candidate** | 110 | 20260408T1127Z |
| 14 | EMB_intrinsic_dimension_adaptive_projection | C30 1127Z — arXiv:2503.02142 ID estimation adapted to byte vocab | compute intrinsic dimension (ID) of byte-vocab clusters via skipped-SVD during 500-step warmup; embed common bytes (ID_cluster < threshold) through 512-d learned, rare bytes through 256-d Fourier basis + 256-d learned; gate by entropy bucket. Distinct from #6 (uses ID, not entropy) | -0.006 to -0.012 BPB (0.9-1.4 MB freed) | **world-novel-candidate** | 95 | 20260408T1127Z |
| 15 | EMB_tied_lsq_tt_codebook_factorization | C30 1127Z — TT-decompose arXiv:1901.10787 + LSQ + tied co-training | TT-decompose tok_emb into ranks [1,64,16,1]; share TT factors across BOTH tok_emb and lm_head; apply LSQ learnable step per TT factor; co-train embedding+head with separate LRs. Extension of #5 with LSQ + Hessian-driven rank selection | -0.010 to -0.018 BPB (1.5-2.1 MB freed via factorized cores + int5) | comp-novel (TT known; tying-with-LSQ is the novelty) | 130 | 20260408T1127Z |

---

## L04 — Attention candidates

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | ATT_gated_attention_validate | Patch 16 (NeurIPS 2025) | USE_GATED_ATTENTION=1 re-validation under fixed batch (existing patch failed under broken batch) | -0.005 train_loss | comp-novel | 0 (env var) | 20260408T0000Z |
| 2 | ATT_muoneq_mousse_depth_revalidate | Patches 17/18/19 | re-validate prior verdicts which were measured under broken batch | TBD | comp-novel | 0 (env vars) | 20260408T0000Z |
| 3 | ATT_coprime_per_head_rope | Plan-A novel | each head uses a different prime base in its 16 partial-RoPE dims, so heads see slightly different positional spectra; reduces head redundancy | -0.008 train_loss | world-novel-candidate **SHIPPED 0445Z** as COPRIME_PER_HEAD_ROPE_MARKER | 25 | 20260408T0000Z |
| 4 | ATT_hymba_mamba2_hybrid | LESSONS §28 + PR #852 | Mamba-2 + attention hybrid; claims 85ms/step at 1.1189 BPB on H100; potentially massive throughput | -0.05 BPB | comp-novel | 110 (HymbaAttention class + mamba-ssm install) | 20260408T0000Z |
| 5 | ATT_triton_gqa_kernel | stretch S3 | hand-tuned Triton kernel for our specific GQA shape (8h, 4kv, head_dim=64); F.scaled_dot_product_attention has overhead at small batches | 20-40% step speedup → more steps in budget | comp-novel | 200 (Triton kernel + bindings) | 20260408T0000Z |

---

## L05 — Feedforward candidates

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | FFN_parallel_residuals_revalidate | comp has it merged | USE_PARALLEL_RESIDUALS=1; our prior implementation regressed | -0.005 train_loss | comp-novel | 0 (env var) | 20260408T0000Z |
| 2 | FFN_swish_leakyrelu_mix_gate | Plan-A | combine Swish² and LeakyReLU(0.5)² in parallel halves with learned scalar | -0.004 train_loss | comp-novel | 35 | 20260408T0000Z |
| 3 | FFN_norm_percentile_dropout | Plan-A novel | zero out FFN intermediate features whose row-norm is in the top 1%; targets the rare exploding-activation pathway | -0.006 train_loss | world-novel-candidate **SHIPPED 0419Z** as NORM_PCT_DROPOUT_MARKER | 30 | 20260408T0000Z |
| 4 | FFN_polyglu_state_conditional_routing | C30#2 — arXiv:2603.13347 PolyGLU (Mar 2026) | replace fixed ReLU² with learned input-conditioned softmax gate over [ReLU², Swish², LeakyReLU(0.5)²]; 3 parallel projections + single gate, no expert weight duplication | -0.007 train_loss | comp-novel | 45 | 20260408T0312Z |
| 5 | FFN_squared_activation_sparsity_exploit | C30#2 — arXiv:2503.16672 + custom synthesis | exploit intrinsic 2:4 sparsity in ReLU² outputs: zero-mask the 2-of-4 smallest activations per position with STE gradient; 1.3× faster step → more steps in 10 min budget | -0.004 train_loss + 1.3× throughput | **world-novel-candidate** | 65 | 20260408T0312Z |
| 6 | FFN_per_layer_alpha_learnable_activation | C30#2 — LESSONS §2 + adaptive activation lit | per-layer scalar α∈[0.01,0.5] gates ReLU² intensity: act = α·(ReLU(x))² + (1−α)·x; init α=0.1 shallow / 0.3 deep | -0.005 train_loss | comp-novel | 30 (9 floats + elementwise) | 20260408T0312Z |

---

## L06 — Normalization & residuals candidates

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | NRM_ln_scale_validate | Patch (in 1.1147 stack) | USE_LN_SCALE=1 — RMSNorm output × 1/√(layer+1) | -0.003 train_loss | comp-novel | 0 (env var) | 20260408T0000Z |
| 2 | NRM_per_layer_residual_scalar | ReZero variant | per-layer learned residual scalar (init 1.0, ≤9 floats) | -0.004 train_loss | comp-novel | 20 | 20260408T0000Z |
| 3 | NRM_asymmetric_skip_init_half | Plan-A novel | self.skip_weights at line 673 defaults to ones; init at 0.5 instead → explicit info bottleneck | -0.006 train_loss | world-novel-candidate **SHIPPED 0419Z** as ASYMMETRIC_SKIP_INIT_MARKER | 5 | 20260408T0000Z |
| 4 | NRM_adaptive_resid_gating | C30#5 — Qwen NeurIPS 2025 Gated Attention (arXiv:2505.06708) + control theory (Peri-LN) + byte-LM cross-domain synthesis | per-layer sigmoid gates on residual output (both attn & MLP), modulated by running norm of layer activations; reduces "massive activation" observed deep at byte scale | -0.008 to -0.015 train_loss | **world-novel-candidate** | 50 | 20260408T0545Z |
| 5 | NRM_layer_adaptive_rnorm_schedule | C30#5 — Bolmo (2512.15586) adaptive byte pooling + UN-η adaptive normalization | learn per-layer RMSNorm temperature α(ℓ) ∈ [0.5, 2.0] (init 1.0); optimizer adjusts per-layer instead of fixed 1/√(ℓ+1) | -0.004 to -0.012 train_loss | **world-novel-candidate** | 15 | 20260408T0545Z |
| 6 | NRM_skip_gate_with_entropy_modulation | C30#5 — UN-η + Bolmo entropy + extension of shipped ASYMMETRIC_SKIP_INIT | expand skip_weights into gated path: skip_out = sigmoid(gate_param(ℓ)) * skip_weights[ℓ] * x0; entropy-adaptive modulation | -0.006 to -0.014 train_loss | **world-novel-candidate** | 40 | 20260408T0545Z |

---

## L07 — Loss candidates

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | LSS_byte_weight_validate | Patch (LESSONS §3b) | USE_BYTE_WEIGHT=1 at proper scale; never validated on H100 stack | -0.003 BPB direct | comp-novel | 0 (env var) | 20260408T0000Z |
| 2 | LSS_mtp_validate | Patch 21 (DeepSeek-V3) | USE_MTP=1 multi-token prediction aux loss | -0.005 train_loss | comp-novel | 0 (env var) | 20260408T0000Z |
| 3 | LSS_asymmetric_label_smoothing | Plan-A novel | ε=0.01 only for tokens whose unigram log-prob > -3; rare tokens get hard targets | -0.004 train_loss | world-novel-candidate **SHIPPED + DEMOTED 1112Z** (n=2 mean above baseline) | 40 | 20260408T0000Z |
| 4 | LSS_focal_loss_gamma_tuned | C30 1141Z — Lin et al. 2017 focal loss + byte-vocab extension | γ-tuned focal loss (1-p_t)^γ on byte-vocab CE: downweights high-confidence common bytes (space/newline) so rare byte transitions contribute more gradient. PhD-defensible: γ=2 baseline + per-byte-class learned γ as ablation | -0.008 to -0.015 train_loss | **world-novel-candidate** **SHIPPED 1202Z** as LSS_FOCAL_LOSS_MARKER | 85 (4-anchor patch: Param init + scalar_params register + forward ternary + helper method) | 20260408T1141Z |
| 5 | LSS_token_uncertainty_aux_loss | C30 1141Z — STARS arXiv:2511.03827 + Token-Uncertainty arXiv:2503.16511 | aux loss term `λ·Σ_t u_t·CE(logits[t], targets[t])` where u_t = epistemic uncertainty estimated via 3-checkpoint jackknife rollback; rare bytes get u_t≈0.8-1.0, common ≈0.2 | -0.006 to -0.012 train_loss | comp-novel (uncertainty weighting known; byte-specific ensemble est is custom) | 95 | 20260408T1141Z |
| 6 | LSS_hellinger_bregman_divergence | C30 1141Z — arXiv:2602.04380 Beyond KL + Banerjee 2005 Bregman theory | replace symmetric KL with Hellinger distance: `H(p,q) = Σ(√p_i - √q_i)²` on softmax dists; symmetric divergence may reduce instability from KL asymmetry on imbalanced byte vocab | -0.005 to -0.010 train_loss | **world-novel-candidate** (Hellinger/Bregman tested in RL but never byte-LM training) | 60 | 20260408T1141Z |

---

## L08 — Optimizer candidates

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | OPT_normuon_validate | Patch 25 (Mac claims -0.132 BPB) | USE_NORMUON=1 per-row norm post-NS | -0.01 train_loss | comp-novel | 0 (env var) | 20260408T0000Z |
| 2 | OPT_muoneq_r_validate | Patch 18 | USE_MUONEQ_R=1 row-only norm post-NS | -0.005 train_loss | comp-novel | 0 (env var) | 20260408T0000Z |
| 3 | OPT_per_projection_lr_split | Plan-A novel | split Muon param group so q.weight, k.weight, v.weight get different LRs (currently they share) | -0.005 train_loss | world-novel-candidate **SHIPPED 0445Z** as PER_PROJ_LR_SPLIT_MARKER | 60 | 20260408T0000Z |
| 4 | OPT_chebyshev_optimized_newton_schulz | C30#5 — arXiv:2506.10935 Chebyshev NS (May 2025) + custom Muon adaptation | replace Muon's 5-step NS with 3 Chebyshev-optimized steps (optimal alternance coefficients); fewer matmuls per step → faster Muon | -0.003 to -0.007 train_loss + 1.5× Muon speedup | **world-novel-candidate** **SHIPPED 0750Z** as OPT_CHEBYSHEV_NS_MARKER | 75 | 20260408T0545Z |
| 5 | OPT_riemannian_gram_projection_qkv | C30#5 — arXiv:2508.17901 Riemannian Stiefel optimization + custom synthesis | apply Riemannian Gram-Schmidt projection ONLY to Q/K/V matrices before NS orthogonalization; sublayer-aware Stiefel constraint reduces attention parameter redundancy | -0.004 to -0.008 train_loss | **world-novel-candidate** **SHIPPED 1133Z** as OPT_RIEMANNIAN_GRAM_QKV_MARKER | 130 (3 anchors: helper + Muon.step + matrix_params populator) | 20260408T0545Z |
| 6 | OPT_schedule_free_momentum_adaptation | C30#5 — Yemets et al. Apr 2025 + Muon adaptation | replace fixed momentum 0.95 with schedule-free interpolation: momentum(t) = 1 - α·exp(-β·t), α/β learned via per-group EMA; removes hyperparameter lock-in | -0.005 to -0.010 train_loss | **world-novel-candidate** | 50 | 20260408T0545Z |

---

## L09 — N-gram engine candidates

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | NGR_entropy_adaptive_validate | Patch 14 | USE_ENTROPY_ADAPTIVE_NGRAM=1 — model-entropy-gated bias mixing (prior verdict invalid under broken batch) | -0.005 train_loss | comp-novel | 0 (env var) | 20260408T0000Z |
| 2 | NGR_skipbigram_table | LESSONS §31 | skip-bigram table (Q-R trick); +0.28 bits/tok signal | -0.005 BPB | comp-novel | 80 (build script + bias apply) | 20260408T0000Z |
| 3 | NGR_context_partitioned_tabulation | MINIPAPER_TABULATION_HASH extension | use a different tabulation table per (prev3 mod 16) slice → 16× n-gram capacity in same memory budget by partitioning input space at higher-order modulus | -0.008 train_loss | world-novel-candidate **SHIPPED 0445Z** as CTX_PARTITIONED_TAB_MARKER | 60 | 20260408T0000Z |
| 4 | NGR_adaptive_cuckoo_hash_collision_free | C30 WebSearch — Cuckoo hashing (Wikipedia) + TikTok Monolith embedding work + CMU 2024 perfect hashing study | replace tabulation XOR with cuckoo hash (two hash functions + displacement table) → true zero collisions on the fly; bias mixing noise becomes purely stochastic instead of systematic | -0.006 BPB | **world-novel-candidate** | 120 | 20260408T0245Z |
| 5 | NGR_kneser_ney_logit_bias | C30 WebSearch — Chen & Goodman 1998, revisited arXiv:1706.07786, applied to logit space | apply modified Kneser-Ney discount (count_distinct_contexts / count_total) to n-gram bias weight at lookup time → context-dependent bias strength, smoothes long-tail backs-off | -0.004 BPB | comp-novel | 45 | 20260408T0245Z |
| 6 | NGR_counting_bloom_high_freq_suppress | C30 WebSearch — countBF arXiv:2106.04364 + custom synthesis | track n-gram bucket frequencies via 4-bit counting Bloom filter (~0.5 MB) and suppress bias for high-freq contexts (logit *= 1 − freq_rank/B) → avoids swamping the model on common patterns it already predicts confidently | -0.005 BPB | **world-novel-candidate** | 85 | 20260408T0245Z |
| 6b | NGR_log_freq_inverse_bias | C90 0935Z novel synthesis — inverse-log bucket frequency weighting on n-gram bias tables | lazy one-time in-place mutation: m[i] = 1/log(2+count[i]); high-freq buckets muted, low-freq keep full strength; targets Shannon trigram floor (currently 1.107) by freeing bias capacity for rare contexts | -0.005 to -0.012 train_loss | **world-novel-candidate** **SHIPPED 0935Z** as NGR_LOG_FREQ_INV_MARKER | 90 | 20260408T0935Z |
| 7 | NGR_interpolation_filter_byte_backoff | C30#8 — Stanford NLP smoothing (Chen-Goodman 1998) + byte-scale synthesis | 3-layer Kneser-Ney-like interpolation: P(t\|prev2) = λ1·P_bigram + λ2·P_unigram + (1−λ1−λ2)·P_byte_backoff with learned λ per byte-pair context slice | -0.006 BPB; +0.22 bits/tok signal on byte-boundary reuse 3-grams miss | **world-novel-candidate** | 70 | 20260408T0720Z |
| 8 | NGR_higher_order_skip_4gram_hadamard | C30#8 — Infini-Gram arXiv:2401.17377 + Hadamard randomization | 4-gram skip-bigram tables (positions [0,2], [1,3], [0,3]) with hadamard-rotated indices to avoid systemic modular collisions | -0.005 BPB; +0.18 bits/tok on long-range deps via 4-gram skip patterns | **world-novel-candidate** | 85 | 20260408T0720Z |
| 9 | NGR_neural_engram_hash_cache | C30 1141Z — DeepSeek Engram 2024 + ICLR memory work | learnable token-pair embeddings stored in hash table with TRAINABLE lookup weights; neural routing replaces fixed polynomial hash collisions with learnable resolution. Distinct from TABULATION_HASH (fixed XOR) | -0.007 to -0.012 train_loss; +0.28 bits/tok on cached patterns | **world-novel-candidate** (Engram not in any comp PR; trainable hash new) | 120 | 20260408T1141Z |
| 10 | NGR_modified_kneser_ney_discount | C30 1141Z — Chen & Goodman 1998 modern application | compute discount D per n-gram bucket dynamically: D = 1 − (count_distinct_contexts / count_total) applied at lookup; multiply bias by (1−D) before adding to logits. Distinct from existing #5 NGR_kneser_ney_logit_bias which uses fixed approximation; this builds proper distinct-context counters | -0.004 to -0.008 train_loss | comp-novel (KN published, never tested in comp) | 35 (lookup-time discount + 1-time aux buffer build) | 20260408T1141Z |
| 11 | NGR_position_vocab_adaptive_prune | C30 1141Z — APT arXiv:2405.12842 + n-gram synthesis | partition n-gram buckets into position classes [BOS, 0-32, 32-64, 64-128, 128+]; learn 2-layer gate per class to mute low-info buckets per position. Distinct from #3 (which partitions hash INPUT, not eval CONTEXT) | -0.005 to -0.009 train_loss; -0.3% inference latency | **world-novel-candidate** | 95 | 20260408T1141Z |

---

## L10 — Compression & eval candidates

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc |
|---|---|---|---|---|---|---|---|
| 1 | CMP_brotli11_wrapper | LESSONS §18 | brotli-11 over LZMA-9 wrapper; saves 1.47 MB on n-gram tables vs zstd-22 | -0.005 BPB indirect | comp-novel | 25 (serializer swap) | 20260408T0000Z |
| 2 | CMP_ar_self_gen_gptq | abaybektursun (top merged 1.1147 record) | autoregressive self-generated calibration data for GPTQ | -0.003 BPB | comp-novel | 100 (calibration loop) | 20260408T0000Z |
| 3 | CMP_per_row_hessian_rans_gptq | Plan-A novel | per-row Hessian-aware rANS coding on GPTQ int6 codes; rANS prior derived from per-row GPTQ Hessian | 0.5-1.0 MB savings → -0.004 BPB indirect | world-novel-candidate | 130 (rANS encoder + Hessian extraction) | 20260408T0000Z |
| 4 | CMP_custom_cuda_int6_dequant_fusion | stretch S1 | custom CUDA kernel for int6 GPTQ dequant + matmul fusion; skips int8 buffer materialization | step time -10 to -25% | comp-novel | 300 (CUDA kernel + bindings) | 20260408T0000Z |
| 5 | CMP_custom_brotli_dictionary | stretch S3 | train a custom Brotli pre-trained dictionary on a corpus of our checkpoints; saves 0.5-1.5 MB | -0.003 BPB indirect | comp-novel | 30 (dict training + serializer flag) | 20260408T0000Z |
| 6 | CMP_mixed_precision_per_layer_alloc | C30#3 — ITERA-LLM arXiv:2505.08981 + Hessian sensitivity | use Hessian variance per-layer to allocate mixed precision: high-variance → int6, low-variance → int4; recompute per GPTQ calibration run | -0.006 to -0.010 BPB (1.2-2.0 MB freed) | **world-novel-candidate** | 95 | 20260408T0349Z |
| 7 | CMP_trellis_coded_quantization_residual | C30#3 — Signal Processing IEEE 1989 + arXiv:2511.04684 (RAS accelerator) | apply trellis-coded quantization (Viterbi-decoded) to GPTQ int6 residuals → reduces per-layer quant noise by ~15-25% via lattice-path optimization | -0.004 to -0.008 BPB (0.8-1.6 MB savings) | **world-novel-candidate** | 120 | 20260408T0349Z |
| 8 | CMP_hadamard_pre_rotation_quant | C30#3 — extension of EMB hadamard rotation to dense weights | pre-compose Walsh-Hadamard rotation into MLP/attention weight matrices BEFORE GPTQ; spreads quant noise uniformly across spectrum | -0.003 to -0.007 BPB | comp-novel | 70 | 20260408T0349Z |
| 9 | CMP_vq_learned_codebook_multilayer | C30#4 — ERVQ arXiv:2410.12359 + ICCV 2025 PQ | apply Residual Vector Quantization with learned k-means codebooks per layer (e.g., 8-bit primary + 4-bit residual); entropy-code indices via rANS afterwards | -0.008 to -0.015 BPB (1.5-2.5 MB freed) | **world-novel-candidate** | 180 | 20260408T0426Z |
| 10 | CMP_asymmetric_numeric_systems_neural_prior | C30#4 — rANS + arXiv:2511.04684 RAS + custom hybrid | learn a tiny ~2KB neural network that predicts the rANS prior distribution conditioned on (layer_id, position, quantized_value); dynamic context-aware compression instead of static Gaussian | -0.006 to -0.012 BPB | **world-novel-candidate** | 150 | 20260408T0426Z |
| 11 | CMP_tensor_train_int4_cores_mixed_precision | C30#4 — PicoGPT memo §16 + TT (MPO) literature | decompose large weight matrices into Tensor Train format with rank-16 cores; store cores in mixed int4/int5 (attn int5, MLP int4); fused contraction kernel at inference time, no full retraining | -0.010 to -0.018 BPB (2.0-3.5 MB freed) | **world-novel-candidate** | 220 | 20260408T0426Z |
| 12 | CMP_hessian_bit_budget | C90#3 0620Z novel synthesis (Hessian-proxy clip quantile + zlib redundancy) | per-tensor INT8_CLIP_Q chosen by ||W||² rank in running buffer; high-importance tight clip preserves range, low-importance loose clip → more zeros → better zlib | -0.003 to -0.008 BPB indirect | **DEMOTED comp-novel C180 0915Z** (HAWQ ICCV 2019) **SHIPPED 0620Z** as CMP_HESSIAN_BIT_BUDGET_MARKER | 60 | 20260408T0620Z |
| 12b | CMP_quant_value_dedup | C90 1010Z novel synthesis — post-int8 alphabet snap for zlib LZ77 | snap int8 q values to multiples of step (default 2), halving effective alphabet from 255→128 distinct values; creates longer LZ77 byte runs in zlib payload; trades recoverable precision for entropy reduction | -0.003 to -0.008 BPB via 5-15% smaller serialized artifact → reallocate freed bytes | **world-novel-candidate** **SHIPPED 1010Z** as CMP_QUANT_VALUE_DEDUP_MARKER | 25 | 20260408T1010Z |
| 13 | CMP_entro_llm_huffman_cabac_hybrid | C30#8 — EntroLLM arXiv:2505.02380 + CABAC (H.264 video codec) hybrid | post-GPTQ int6: lightweight ~4KB NN predicts P(code\|layer,pos,prev_code) to drive CABAC adaptive Huffman with context bins | saves 0.8-1.2 MB → -0.0035 BPB indirect | **world-novel-candidate** | 110 | 20260408T0720Z |
| 14 | CMP_learned_elias_gamma_codes_rq | C30#8 — Elias gamma universal codes (1950s) + RQ stage-specific CDF training | replace fixed rANS with learned Elias-gamma parameters per RQ stage (primary + residual codebook); train CDF predictor on weight distribution of EACH quant stage | saves 0.6-1.0 MB → -0.003 BPB indirect | **world-novel-candidate** | 95 | 20260408T0720Z |
| 15 | CMP_context_adaptive_rANS_per_layer_predictor | C30 1127Z — RAS arXiv:2511.04684 + EntroLLM arXiv:2505.02380 | train tiny <2KB categorical NN predictor `P(quant_value \| layer_id, position, prev_code)` to drive rANS entropy coding for QUANTIZED INDICES (post-int8); learned context-adaptive CDF beats static zlib + Gaussian prior. Distinct from #10 (per-layer predictor, not single global) | -0.005 to -0.011 BPB (1.0-2.2 MB freed) | **world-novel-candidate** | 140 | 20260408T1127Z |
| 16 | CMP_learned_scalar_adaptive_clipping | C30 1127Z — EfficientQAT ACL 2025 + per-layer extension | learn per-layer scalar α ∈ [0,1] via val-set gradient; use clip = absmax(W) - α·std(W) during int8 (not fixed absmax); tighter, less outlier-dominated dist → zlib better compression (3-6% smaller artifact) | -0.003 to -0.008 BPB (0.6-1.6 MB freed) | **world-novel-candidate** | 65 | 20260408T1127Z |

---

---

## Speed/throughput world-novel candidates (cross-layer, added 20260408T0349Z)

**Rule**: each speed candidate is tagged to the layer it touches. Promotion gate = step-time reduction ≥15% AND no train_loss regression > 0.005 (n=2 seeds).

| priority | name | source | hypothesis | expected_delta | novelty_estimate | code_skeleton_loc | added_utc | layer |
|---|---|---|---|---|---|---|---|---|
| 1 | SPD_rmsnorm_fused_into_linear | mathematically equivalent, mirrors LayerNorm-fusion in TensorRT | the next linear after RMSNorm absorbs the RMS scale by precomputing `W_fused = W * (1/||x||)`; eliminates the RMSNorm op entirely on the forward path | -8 to -12% step time, 0 quality cost | **world-novel-candidate** for byte-LM application | 60 | 20260408T0349Z | L06 |
| 2 | SPD_ngram_bias_tile_cache | custom synthesis | precompute the top-K n-gram bias tile (most common contexts) into a fp16 cache; skip the gather entirely on cache hits → memory-bound op becomes register-resident | -10 to -20% step time on n-gram-heavy steps | **world-novel-candidate** | 90 | 20260408T0349Z | L09 |
| 3 | SPD_triton_attention_gqa_8h_4kv | Triton + our specific GQA shape (8h, 4kv, head_dim=64) | hand-tuned Triton kernel skips F.scaled_dot_product_attention's general-case overhead at our small batch; fused softmax + dropout + projection | -15 to -25% attention forward time | comp-novel (Triton GQA exists, our specific shape unknown) | 200 | 20260408T0349Z | L04 |
| 4 | SPD_quantized_intermediate_dequant_fused | NVIDIA W8A8 work + custom synthesis | store FFN intermediate as int8, dequant inside the next matmul kernel (no fp16 buffer materialization); cuts FFN memory traffic in half | -10 to -15% FFN step time | **world-novel-candidate** for byte-LM at this scale | 130 | 20260408T0349Z | L05 |
| 5 | SPD_pinned_prefetch_4x_dataloader | PyTorch dataloader best practice taken to extreme | pin host memory + prefetch_factor=4 + 4 worker threads; eliminates data-loader stalls on the GPU | -3 to -8% step time, mainly on small-batch warmup | comp-novel | 25 | 20260408T0349Z | L02 |
| 6 | SPD_torch_compile_dynamic_partial | PyTorch 2.x + careful subgraph selection | use `torch.compile(dynamic=True, fullgraph=False, mode='reduce-overhead')` ONLY on the FFN forward (skip n-gram + attention which break compile); selective compilation to capture safe wins | -5 to -12% step time | comp-novel (general torch.compile is known, this specific subgraph carve-out for our stack is not) | 40 | 20260408T0349Z | L05 |

**3 of these 6 are world-novel-candidate**: `SPD_rmsnorm_fused_into_linear` (L06), `SPD_ngram_bias_tile_cache` (L09), `SPD_quantized_intermediate_dequant_fused` (L05). The C90 build cron should ship them in that priority order (lowest LOC first).

---

## Backlog hygiene rules

- C30 cron appends to the BOTTOM of each layer's table.
- C5 cron POPS from the TOP when a pod's queue is empty.
- When a candidate transitions to `screened-fail` in `STACK_NOVELTY_TRACKER.md` Section A, its row in this file should be removed (or moved to a `## Failed candidates` section at the bottom of the layer block).
- Manual user injection: just `git push` a row at the desired priority. The next C5 fire picks it up.
