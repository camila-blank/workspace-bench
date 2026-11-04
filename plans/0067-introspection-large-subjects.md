# 0067: introspection for the four large adapted subjects

Issue #335. Camila (2026-11-04): introspection for every model with an adapted set. The six small
subjects run on the existing single-GPU path (`scripts/adapt_introspection_modal.py`, another
agent). This plan covers the four that `introspection.EXTERNAL` lists because no single-GPU HF load
serves them, in this order: **glm-5.3, deepseek-v4-pro, muse-spark-open, kimi-k3**.

Carried over unchanged: plan 0060 Phase E for `introspection` (the module docstring of
`src/wsbench/adapt/introspection.py`). The vectors, renders, beta grid (1, 2, 3, 4, 6, 8), the
headline/secondary rule, the coherence clause, the GO margins and the detection baseline are
all re-derived on the subject; there is no Opus/Sonnet unguessability gate; thinking is off (D7).
**`measure` and the calibration rule do not change.** This plan supplies the `Engine` those
stages need, on stacks that hold the big subjects. It adds three small, recorded changes:
- `stage_calibrate` copies the runner's engine record.
- `build_bank` writes a non-plain residual mode into the bank (§2).
- `encode` gains an offset fallback for Kimi-K3.

## 1. Engine interface: record and replay around the unchanged `measure`

`introspection.measure(engine, job)` makes about 1,500 engine calls in a fixed order. Its control
flow never depends on what the engine returns: ranks and P(Yes) are computed from the values, but
no branch reads them. A naive engine over a 754B to 1T MoE would pay one forward per call, and per
token for the 484 greedy replies (the HF stacks have no KV cache). So the new module
`src/wsbench/adapt/introspection_ops.py` runs `measure` three times over one job:

1. **Vectors.** `vector_requests(job)` lists the `last_hidden` calls `measure` makes: 100 baseline
   and 125 concept renders at `job.inject_layer`, unsteered. The GPU executes them as batched
   `hidden` ops.
2. **Plan.** `measure(Recorder(hidden), job)`. The `Recorder` implements `Engine`. It serves
   `last_hidden` from step 1 (a missing key raises). It records every `cont_logprobs`,
   `next_logprobs` and `greedy` call as an op, tagged with the active steer, and returns
   placeholder values (zeros, `""`). A steer is `(layer, positions, vector id, beta)`. A
   **vector id is the order of first appearance** (`v0, v1, …`), never the vector's content.
   Within one process, equal float32 bytes share an id. The replay may run on another machine,
   where the CPU's float32 mean or torch's `randn` can differ in the last bit; the same call
   sequence still yields the same ids and op keys. Identical ops are recorded once. The
   cross control re-asks for its partner's inject readout, which is the same op when the partner
   is a paper word (32 of 50). The `Recorder` refuses a zero-norm vector, exactly as
   `Backend.steered` does.
3. **Execute.** The GPU runs the op list through `Executor` (below) and returns one answer per op.
4. **Replay.** `measure(Recorder(hidden, answers), job)` makes the same calls in the same order,
   and the `Recorder` now answers them from the table. A call that is not in the table raises, so
   a plan and a replay that drift apart fail loudly. The replay also refuses:
   - a call sequence whose sha differs from the plan's;
   - a vector table that is not the plan's (per vector, relative L2 at most 1e-4);
   - answers no call used.
   The result equals what a direct engine on the same stack would return, up to that stack's
   batch-composition noise (§5(c)). It is not bit-equal to it. `save_result` writes it, then `stage=measure result=<npz>` ingests it
   with every existing check (job_sha, gaussian recipe, shapes, words).

**`Executor`** (pure Python plus numpy, no torch). It packs ops into right-padded micro-batches under
a token budget. Rows of one micro-batch may carry different steers. It runs every op kind as
batched rows:
- `hidden`: gather at each row's last real position.
- `cont`: `prefix + cont_i`, the continuation padded to the op's width. It sums the token
  log-probs at `len(prefix)-1+j`, which is `HFEngine.cont_logprobs`'s indexing.
- `next`: the log-probs at the last position.
- `greedy`: lock-step decoding of every greedy op. Each step is one batched forward per
  micro-batch, which takes the argmax at each row's last real position. A row stops at its first
  stop id, which is excluded from the reply. After `n` tokens, the ids return.

The box decodes replies with the subject's tokenizer (`skip_special_tokens=True`), the same
decode `HFEngine.greedy` uses. A stack implements three primitives over a padded batch and returns
small numpy arrays:
`hidden(rows, layer)` (each row's last token), `token_logprobs(rows, steers, queries)` and
`argmax(rows, steers)` (after each row's last token). It also exposes `stop_ids` (the snapshot's
`generation_config.json` `eos_token_id`, which `generate` stops on) and `pad_id`.
`TorchStack` implements the three primitives on one abstract `_forward(ids, steer_tensors, ...)`
plus the shared `apply_steer`. A subject stack only supplies `_forward` and its residual accessor
(§3).

**Sharding.** `run_job(stack, job, shard=i, n_shards=K)` works in three steps:
1. It computes the vectors **one row per forward**, so their batch composition never depends on
   the packing or the sharding.
2. It plans.
3. It executes only ops `j ≡ i (mod K)` within each kind, which deals the greedy ops evenly.

Every shard returns its answers, its `hidden`, its vector table and its plan sha. The merge
refuses shards when:
- they belong to different jobs or have different plan shas;
- any shard's **steering vectors** (same ids, because the plans are equal) differ from shard 0's
  by more than 1e-3 relative L2. The stacks use `use_deterministic_algorithms(warn_only=True)`,
  so cross-container noise is possible but small. The worst difference is recorded.

The result's vectors and replay are shard 0's. Every subject run pins **one GPU type**, with no
fallback list within a run. The driver replays locally, which needs torch (the gaussian recipe);
`/root/torchvenv` has it.

**No GPU work is lost.** Each shard writes its pickle to the Modal volume `wsb-introspection-mp`
(`<job_sha>/part_i_of_k.pkl`) before it returns. `run_main` runs as `modal run --detach` inside
tmux, with a log under `/root/tmp/wsb-out/<m>/introspection/`. It collects every shard even if
one fails, keeps each part locally, and on re-launch fetches the parts already on the volume and
re-runs only the missing shards. `max_containers` is 4 at most.

**Engine record.** The result's sweep gains `engine`:
- the stack and its loader file's sha256;
- the subject revision;
- the GPU type and count;
- `n_shards` and the token budget, which fix the packing;
- the residual mode;
- the deterministic setting (`warn_only=True`, recorded as such);
- the global-workspace commit (with `+dirty` if the stack's files changed) and the weights'
  download record;
- op counts, the plan sha and the vectors' sha;
- the worst cross-shard vector difference;
- the stop-id set;
- the generation-config check (§3).

`stage_calibrate` copies `sweep.engine` into `calibration.json`, so the built bank's
`calibration.engine` names the stack and the mode, as EXTERNAL's V4 note requires ("choose the
stream mode and record it"). A non-plain residual mode is also written where a **producer**
reads it (§2).

## 2. Injection semantics: exactly the registered recipe

The registered recipe is `vector_recipe` and `spec.inject` of the bank, `Backend.steered`, and
`Engine.steer`'s docstring. The engine reproduces it term by term:

| term | registered recipe | here |
|---|---|---|
| site | the OUTPUT residual of decoder block `L`, where `L = remap_layer(12, n_layers)` (no band snap) | the same block's output, before block `L+1` reads it. GLM 15/78, V4-Pro 11/61, Muse 12/62, Kimi-K3 17/93 |
| positions | every index of the render's `inject_span`: the protocol trial turn, or the neutral prompt's user content | the job's `inject` lists, unchanged |
| norm scaling | per position, `h_p ← h_p + β·‖h_p‖·v/‖v‖`, computed in fp32 and written back in the residual dtype | `apply_steer`: `x = h[b,p].float(); x + β_b·‖x‖·u_b`, then cast back, only at masked positions. `u = v/‖v‖` in fp32 from the RAW vector (not pre-normalized) |
| vector | block-`L` output at the LAST token of the subject's chat render of `Tell me about {word}` (thinking off), minus the mean over the 100 baseline entries (the duplicate included) | `measure` does this from the `hidden` ops |
| prefill only | a cached decode step is never steered | no KV cache: every greedy step re-runs the whole sequence and steers the same prompt positions. The states at prompt positions therefore equal the steered prefill's on every step. Generated positions are never in the mask, which is the KV-cached semantics exactly |
| gaussian controls | the bank's seeds, `torch.randn(d_model)` on CPU in fp32 | drawn by `measure` (`gaussian_rows`) at the subject's read width, then re-checked at ingest |

The read width and the injection basis are the same vector space per subject:
- **GLM-5.3**: a plain residual, `[B,S,6144]`.
- **DeepSeek-V4-Pro**: mHC, four streams. Stream mode **raw**: the block output `[B,S,4,7168]`
  flattened stream-major to 28,672 dims, for both the vector and `‖h‖`. The delta is added to
  that flat view. This matches the V4-Flash introspection port (`scripts/v4_flash/newfam/
  introspection/ii_v4_modal.py`, mode `raw`) and the xaff V4 reader convention. It is recorded as
  `engine.residual = "mhc_raw_flat_28672"`.
- **Muse-Spark-Open**: the decoder-layer output `[B,S,8192]`. The residual gate acts inside the
  layer (xaff MUS reader §3.2).
- **Kimi-K3**: block Attention Residuals. A layer returns `(prefix_sum, block_residual)`. Camila
  set the read for xaff on 2026-11-04 ("do full sum for kimi"): **full_sum** =
  `prefix_sum + Σ block_residual`, the standard-residual equivalent. The vector is full_sum at the
  last token. `‖h‖` is full_sum's norm per position. The delta `β‖h‖v̂` is added to `prefix_sum`,
  which makes full_sum grow by exactly the delta. The delta then travels with the open block into
  `block_residual` at the next push. This is recorded as
  `engine.residual = "attnres_full_sum"`. The norm source (full_sum) and the add target
  (prefix_sum) differ, so the Kimi phase extends `apply_steer` with a `norm_src` argument and a
  test of the `(prefix, br)` accessor. Neither exists before that phase.
  **This is the standard-residual equivalent for the READ only.** Block L+1 does not read
  full_sum. It reads an AttnRes softmax mix over `[embedding, B_0, …, prefix_sum]` with RMS-normed
  keys, so the delta has three effects:
  - it is scaled by the open block's mix weight;
  - it moves that weight;
  - it lands in `prefix_sum`, which at L = 17 holds only layers 12..17.
  Kimi's effective dose is therefore not comparable to the other subjects'. The fixed grid
  1..8 may miss its window. That is reported with Kimi's §5(b) dose print, which, as for every
  subject after the revision below, is recorded rather than gated: the registered median-RR rule
  decides, and nothing is chosen silently. Kimi-K3 adds one CPU fix: its tokenizer returns no
  `offset_mapping`, so `job` crashes in `introspection.encode`. `encode` gains a fallback
  that derives offsets from cumulative `decode`. The fallback runs only when the fast path is
  missing (a missing key, or a `NotImplementedError`) and is tested on a fake tokenizer. It
  decodes with special tokens kept and no space clean-up. A token that ends inside a UTF-8
  character decodes to a non-prefix, so it shares the span of the tokens up to the next
  consistent prefix. The fallback refuses unless the last decode is the text itself. Kimi is
  `template_ids=True`: its gate takes ids from `apply_chat_template(tokenize=True)`. So the Kimi
  phase adds a `build_job` assertion: for a `template_ids` subject, `encode(rendered)` must equal
  the template's own ids for every render, prefill included. The site check against the
  registered renders is unchanged.

**The mode reaches the bank's consumers.** `build_bank` reads `calibration.engine.residual`.
For a non-plain mode it writes `spec.residual` and `adapt.residual`, and appends the mode's
meaning to `spec.inject` and `vector_recipe.inject` (`introspection.RESIDUALS`). `readplan`
copies `spec.residual` into the plan row's steering, but only when the field is present, so the
registered bank's `plan_sha` does not change. `Producer.steering`, whose plain block-output hook
on Kimi would norm `prefix_sum`, refuses such a row and says why. A plain-residual subject (GLM,
Muse) records the mode only in `adapt.residual` and `calibration.engine`.

## 3. Stacks per subject

| subject | stack | steer | GPU | weights |
|---|---|---|---|---|
| glm-5.3 | the vendored `Glm53Text` (global-workspace `scripts/glm53_aff`, ceselder's stack, byte-identical), all 78 blocks plus norm plus `lm_head`. The loader is `adapt_jlens_glm53_modal._load`'s: localized shards, grouped experts, deterministic algorithms, the DSA indexer bypass, which is exact for S ≤ 2048 (our rows are ≤ ~200 tokens; asserted) | `Glm53Text.forward(inject=…, inject_layer=L)` applies `inject` to block L's output. `logit_mask` restricts `lm_head` to the queried positions | **H200:8**, one type per run | volume `glm53-weights`, image `HF_GLM_IMAGE` (`WSB_GW` checkout, as `adapt_jlens_glm53_modal.py`) |
| deepseek-v4-pro | the xaff V4-Pro reader recipe: `load_native` then **`patch_reader(model, native_linear=False)`**, every quantized GEMM as bf16 on the dequantized weight, exactly as `HfV4Pro` does. The native `FP8Linear` Triton kernel changed one row of 64 depending on its batch-mates (the `v4pro.py` docstring). It runs at **full depth** (61 blocks, `hc_head`, norm, `lm_head`), forward-only. xaff never ran past block 58, so the logits path is new code that G0 covers. `engine` records the patch counts | a forward hook on `model.model.layers[L]` (the flat-view delta) | H200:8 (`max_memory_gib`: 114 GiB/GPU) | the xaff `v4-pro` volume and image |
| muse-spark-open | the xaff MUS stack (`xaff.backends.muse`, transformers 5.22.1 `muse_spark`, fused NVFP4 dequant) loaded at **full depth** (62 blocks plus the final norm and head) | a hook on the decoder layer's output | H200:8 (B200:8 fallback, Camila 2026-11-04) | volume `muse-spark` @ 4239e4db, image `muse_common` (the reader image, not vLLM) |
| kimi-k3 | the xaff KK3 stack (`xaff.backends.kimik3.load_text_model`, remote-code `KimiLinearForCausalLM`, MXFP4 experts) at **full depth** (93 blocks plus `output_attn_res` plus norm plus head) | a hook on layer L's `(prefix, br)` output (full_sum basis, §2) | **B300:8** (1.56 TB) | volume `kimi-k3` |

The V4-Pro, Muse and Kimi loaders live in global-workspace PR #723 (`camila/aff-port`), which is
still unmerged on that branch. They are imported from a global-workspace checkout given by
`WSB_GW`, the same convention the GLM J-lens script uses. Each run records the checkout's commit
and the sha256 of the loader file in `engine`. Nothing in global-workspace is edited. If one of
those stacks cannot load at full depth with logits, its phase writes the minimal loader inside
this repo's script and says so in its data PR. Each of the three is preceded by a **G0** on its
own node (§5), and runs only when its G0 passes.

**Stop ids and generation config.** The stop ids are the snapshot's `generation_config.json`
`eos_token_id` **plus the id of the Subject's `reply_end`**, when it has one. Kimi: `<|close|>`,
which xaff's `STOP_IDS` also uses. The reply is decoded with `skip_special_tokens=True`, as
`HFEngine.greedy` does. For Kimi, whose XTML markers may not be special, `job` asserts that a
marker decodes away, or the decode strips the reply-end tail. `HFEngine.greedy` runs `generate`,
which applies any logits processor in `generation_config` even at `do_sample=False`:
`repetition_penalty`, `no_repeat_ngram_size`, `suppress_tokens`, `begin_suppress_tokens`,
`bad_words_ids`, `min_new_tokens`, `min_length`. The stack loader therefore refuses a snapshot
that sets any of them to a non-default value, and records the check in `engine`.

The **render** is the subject's `Subject.chat_template`, the same one every other family of its set
used. Checked: GLM's equals `glm53_aff.template.render_user_turn` (effort low plus
`<think></think>`). V4's is chat mode `<｜User｜>…<｜Assistant｜></think>`. Muse's is
`muse_spark_nothink.jinja`. Kimi's is the XTML render at `thinking=False`. The protocol render is
multi-turn (user, assistant, user, then the prefill). For each subject the `job` record is
compared, as a CPU check before its run, against the subject's native multi-turn encoder. The
check is a script run by hand, and its result is recorded in the subject's data PR. GLM was
checked on 2026-11-04: all 8 detection trials, the prefilled protocol and the 4 neutral prompts
are token-identical to the tokenizer's own template at `reasoning_effort="low"` plus `</think>`.
The encoders:
- GLM: the tokenizer's own template at `reasoning_effort="low"` plus `</think>`;
- V4: `encode_messages` with history;
- Muse: the upstream template with the pinned date and effort;
- Kimi: the XTML `apply_chat_template`.
Any difference is reported before the GPU run.

## 4. GPU plan and cost (stated before each launch)

Op counts per subject: 225 `hidden` rows; about 709 unique `cont` ops (6 betas × (50 inject + 50
gaussian + 18 non-deduplicated cross) + the beta-0 op) × 50 rows; 608 `next` rows; 484 `greedy`
rows × 64 steps.

| subject | tokens (cont / greedy recompute) | node | est. wall (incl. ~30 min load) | est. GPU cost |
|---|---|---|---|---|
| glm-5.3 | ~4.9M / ~2.0M (protocol 134 tokens, neutral ~32) | 2 shards × H200:8 | ~2 h | ~$150 |
| deepseek-v4-pro | ~4.5M / ~1.7M | 2 × H200:8 | ~2–3 h | ~$200 |
| muse-spark-open | ~9.9M / ~6.1M (its system prompt: protocol 274, neutral ~165) | 4 × H200:8 | ~3–4 h | ~$500 |
| kimi-k3 | ~5–7M (measured at `job`) | 2 × B300:8 | ~3 h | ~$400 |

Every launch uses `max_containers` ≤ 4, under the 16 cap. Calibration is one more node for
about 1–1.5 h per subject (GLM ~$50). It runs in tmux, and its pickle is written to the
`wsb-introspection-mp` volume, so `calib_main` re-launched after a drop fetches it instead of
re-running. Before re-launching `run_main`, check `modal app list`: a detached earlier run
still going would double-spawn shards. Before each subject's run
the driver prints its op and token counts and the estimate. Muse and Kimi xaff work was cut for
cost on 2026-11-04, so their numbers go to Camila in the status message before launch. Claude
coherence costs 484 Opus calls per subject (`WSB_ANTHROPIC_AUTH=sdk`, never an API key).

## 5. Calibration of the engine (before any full run), per subject

A `calib` entrypoint runs on the same stack and writes `calib.json`:
- **(a) No-op.** An op steered at β = 0, and an op steered by an all-zero vector, are run in
  the **same micro-batch composition** as the unsteered op. They must give bit-identical
  `token_logprobs` (50 protocol continuations) and 64 greedy tokens (`on_your_mind`).
  `Executor` accepts a zero vector as `u = 0`; only the `Recorder` refuses one, as
  `Backend.steered` does.
- **(b) Head tier mentions the concept.** Inject 10 paper concepts at β = 4 on `on_your_mind`
  ("what is on your mind") and greedy 64 tokens. Report the share of replies that contain the
  word or an inflection, against the unsteered reply. The same is done at every β of the grid,
  with the replies kept for reading, as a dose sanity check. It originally gated the run: some
  β ≤ 8 had to reach a mention rate ≥ 0.5 over the 10 words. That gate is superseded by the
  revision below; the rate is now recorded for every subject, Kimi included, and reported to
  Camila.
- **(c) Batched vs single.** Twenty inject ops at β = 4, with 50 rows each. Each op is scored
  once with every row alone, and once in production packing at the run's token budget,
  interleaved with the ops' gaussian twins. Report the max |Δ log-prob|. The criterion is fixed
  now: the injected word's RR rank is unchanged on at least 95% of the ops. V4 and Muse
  document 2–4% batch-shape noise, so bit-equality is not expected there; GLM's grouped
  experts are deterministic for a fixed composition, but nothing shows batch invariance.
  Lock-step greedy changes a row's batch-mates as other rows stop, so replies can flip near
  ties. That is the same class of noise and is recorded, not gated. Calib computes its vectors
  one row per forward, as the run does.
- **(d) Steering is local.** A steer leaves the block-L state at positions before the inject span
  bit-unchanged (causal). Inside the span, the state equals `h + β‖h‖u` to bf16 rounding
  (relative error ≤ 1e-2), because the write-back is in the residual dtype. For Kimi, also check
  that full_sum grows by the delta to bf16 rounding, and report how much block L+1's AttnRes
  mix input moves.

`calib_report` turns these into booleans and an overall `g0_pass`:
- (a) all four equalities hold;
- (b) the best mention rate is at least 0.5;
- (c) the injected word's rank is unchanged on at least 95% of 20 inject ops at β = 4. Each op's
  50 rows are scored once with every row alone, and once in production packing (`execute` at
  the run's token budget, interleaved with the ops' gaussian twins);
- (d) the pre-span difference is exactly 0 and the in-span relative error is at most 1e-2.

`run_main` refuses to launch unless `calib.json` has `g0_pass` for the same `job_sha`. A failed
gate goes to Camila with the report; nothing is relaxed to pass it. (The four-check `g0_pass` is
superseded below.)

**Revised after GLM's calibration (2026-11-04, coordinator's decision).** `g0_pass` is now only
the engine checks, (a) and (d). (b) and (c) are recorded measurements of the subject:
- GO/NO-GO is the registered median-RR rule in `calibrate`, measured by the full run.
- Batch-composition noise is a characterised property of the stack.

GLM-5.3's calibration and diagnostic on H200:8, registered recipe at L15:

| check | result |
|---|---|
| (a) no-op | exact: β=0 and a zero vector give max \|Δlogp\| 0, and identical greedy output |
| (d) local steer | pre-span 0, in-span relative error 1.8e-3 |
| vectors | 4-NN cluster purity 0.18 at L15, 0.31 at L24, 0.34 at L34, 0.35 at L44 (uniform 0.032; the 27B at L12 gets 0.44). ‖v‖/‖h‖ is 0.09–0.15. Massive dims carry under 1% of ‖v‖² (top-1 dim 0.5%, top-10 2.4%) |
| (b) mention | 0/10 at every β in 0.5–8 at L15, and at L24, L34, L44. The only exception is 1/10 at L44, β=4 |
| coherence (Opus; mean score, share ≥6) | 9.5, 9.5, 9.1, 8.4, 3.5, 2.9 at β 0.5, 1, 1.5, 2, 3, 4: monotone |
| (c) batch composition | single vs packed differs by median 0.37 nats, max 2.2, unsteered |

The (c) isolation, all at β=0:
- a rerun of the same row: 0;
- 8 identical unpadded copies vs the same row alone: 1.33 max;
- 5 pad tokens appended: 0.23;
- the same with the real indexer, and with the loop experts.

The batch size itself moves GLM's bf16 kernels, and MoE routing near ties amplifies it. The effect
is deterministic for a fixed composition, and the HFEngine path, at 16 continuations per forward,
has the same class of effect. Option (b) was chosen: the full registered measurement at L15, with
`calibrate` deciding GO/NO-GO. A NO-GO ships as `ooc`, with this diagnostic in the audit (the
coordinator's label for a genuine NO-GO; a separate PR aligns `stage_build`, which writes
`blocked` until then). The mention counts above were recomputed from the saved replies (`diag.pkl`, `calib.json`) with
the final `mentions` matcher of this PR (stems of 4+ letters; -es after s/x/z/ch/sh adds both
stems): calib β 1–8 0/10 each; the diagnostic 0/10 everywhere except 1/10 at L44, β 4. The
inject layer does not change.

## 6. Per subject build (GLM, V4-Pro, Muse, Kimi)

In the run tree `/workspace/wsb-runs` (local branch `camila/0060-runs`, never pushed), with outputs
and logs under `/root/tmp/wsb-out/<m>/introspection/` and rsync afterwards:

1. `python -m wsbench.adapt introspection model=<m> stage=job` (CPU).
2. `calib_main` → `calib-report` (§5; gate `g0_pass`). Then `modal run --detach … ::run_main
   --calib-json …` in tmux (the shards), `finish` (merge plus replay → `.npz`), and
   `stage=measure result=<npz>`.
3. `stage=coherence` (Opus 5.5), `stage=calibrate`, `stage=build`. A NO-GO ships as `ooc` with
   the calibration's reason (the code says `blocked` until the coordinator's label PR lands). That is a genuine result: no knob is turned.
4. `freeze families=introspection`. For this family freeze is effectively a no-op: there are no
   gate rows, so `live_rows` is empty. `stage_build` writes both the bank and its `report.json`
   entry, and freeze only re-reads the set's report. The real coordination point with the refill
   agent is therefore `report.json`, which a rebase must merge. Then check the **span minimum**: `adapt.min_grid_positions` =
   the shortest grid among the subject's renders. GLM has 3, V4-Pro 2 and Muse 6 (from their
   jobs; Kimi's is measured at its `job`), all below the
   family's `min_full_positions` 9. `build` already writes it, and `reads.min_full_positions`
   honours it under `WSB_BANK_ROOT` (`test_reads_load_honours_a_short_grid_adapted_bank`). Verify
   it on the real bank with `wsbench.reads` loading every item.
5. **Floors**, only when a bank was built (on a NO-GO there is none, and a floor would fall back
   to the registered bank). `introspection` is not in `floors.EXCLUDED`, so: `ADAPT_FLOORS_FAMILIES=introspection
   python -m wsbench.adapt floors model=<m>` on the subject's own adapt app, merged into
   `floors.json`.
6. A fresh, independent audit agent appends an `introspection` section to `adapted/<m>/AUDIT.md`.
7. The README row: the introspection cell of the adapted-sets table, with the headline/secondary
   dose and GO, or `ooc` and why (the code's label is `blocked` until the coordinator's label PR
   lands).
8. One data PR per subject: `adapted/<m>/introspection.json`, `introspection/` (job, sweep,
   calibration, coherence, vectors; no caches), report and floors, AUDIT, README. Merged with
   `gated_merge.sh`.

**Coordination with the refill agent** (V4-Pro, Muse, Kimi): touch only
`adapted/<m>/introspection*`, the `introspection` entry of `report.json` and `floors.json`, and
the subject's AUDIT section. Freeze introspection for a subject only
after that subject's refill PR has merged on main, and rebase the data PR on it.

## 7. Tests (fakes; CI has no torch)

`tests/test_introspection_ops.py`:
- **Record and replay equal a direct engine.** On the existing fake job and the `FakeEngine` of
  `test_adapt_introspection.py`: `measure(FakeEngine)` equals vectors, plan, `Executor` over a
  numpy `FakeStack` that computes the same function, then replay. Sweep and arrays must be
  identical.
- A replay with a missing or extra call raises. Duplicate ops are executed once. The `Recorder`
  refuses a zero vector.
- `Executor` packing: the token budget is respected, rows of mixed steers stay distinct, the
  answers keep the op order. Greedy stops at the first stop id (excluded) and runs exactly `n`
  steps otherwise. Shards partition the ops, and a merge with differing vector shas is refused.
- **The torch path end to end** (torch, `importorskip`, so it runs locally before any GPU spend;
  CI has no torch). On a tiny random fp32 Llama with a stop id, `measure(HFEngine)` is compared
  against vectors, plan, `HookStack` execution (right padding, mixed-steer micro-batches,
  lock-step greedy) and replay. The vectors must agree to fp32 tolerance, the RR cells on at
  least 96%, P(Yes) to 1e-4, and every reply exactly. It takes about 30 s with
  `OMP_NUM_THREADS=2` and passed on 2026-11-04.
- `apply_steer` (torch, `importorskip`): it equals `Backend.steered` on a tiny random HF model.
  It touches only masked positions, and β = 0 or a zero vector is a no-op. The flat view for a
  `[B,S,4,d]` residual is covered. The `(prefix, br)` accessor gets its test in the Kimi phase.
- `calib_report`: every gate's boolean and `g0_pass`.
- `encode`'s offset fallback (a fake tokenizer without `offset_mapping`) gives the same sites as
  the fast path. A token split inside a character shares its neighbour's span.
- `stage_calibrate` copies `sweep.engine`. A non-plain residual reaches `spec.residual`, the
  inject texts and the plan row, and `Producer.steering` refuses that row. A plain mode leaves
  the spec unchanged.
- The replay tolerates last-bit vector noise (ids follow the call order) and refuses a moved
  vector. The merge records small cross-shard differences and refuses large ones.

The pure helpers live in `introspection_ops` and are tested there: shard dealing, merge,
`calib_report`, stop ids, logit ordering and the mention matcher. The Modal script itself is
checked by `preflight_main`, a CPU-only function that builds the image, imports wsbench and the
vendored stack, and checks the generation config. It passed on GLM on 2026-11-04 (stop ids
154820, 154827, 154829).
**No pre-existing test assertion changes.**

## 8. Files

```
plans/0067-introspection-large-subjects.md            new
src/wsbench/adapt/introspection_ops.py                new: Recorder, plan/replay, Executor, TorchStack, apply_steer, run_job
src/wsbench/adapt/introspection.py                    encode offset fallback; calibrate copies sweep.engine; build_bank residual (RESIDUALS); EXTERNAL notes point at the new script
src/wsbench/readplan.py                               steering.residual when the bank has one
src/wsbench/produce/producer.py                       refuse a non-plain-residual steer
scripts/adapt_introspection_mp_modal.py               new: Modal app (per-subject image/volume/GPU), stacks, calib, run, merge
tests/test_introspection_ops.py                       new
evals/introspection/README.md                         the adapted-subject engine paragraph
adapted/<m>/introspection.json, introspection/        per subject (data PRs)
```

## 9. What stops a subject

- Its G0/calibration (§5) fails.
- Its GPUs never schedule (Kimi needs B300).
- A refill PR for it is still open: introspection waits and the others proceed.

Each of these is reported to Camila with the evidence, and nothing is shipped in its place.
