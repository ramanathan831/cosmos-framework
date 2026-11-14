# Native GR00T N1.7 backbone adaptation

This integration connects native LIBERO action flow matching to ordinary LoRA on a frozen
language backbone. The implementation is available; task quality, performance and device support
must be read from the accompanying qualification evidence. CPU tests and configuration acceptance
alone do not establish accelerator support or robotic task success.

The initial architecture is `nvidia/GR00T-N1.7-LIBERO` at
`2ea293aa20ba7cf5bbf3ba17a5fbcb1a01cbfe21`, LIBERO-spatial policy, with the checkpoint's
16 retained Cosmos-Reason2-2B language layers, 2048 hidden width and 40 × 132 action head.
The native processor supplies the `libero_sim` embodiment, state/action statistics, two RGB cameras
and 16 valid embodiment action slots. The selected prepared demonstration has ten supervised
7-dimensional environment-action steps. State is xyz, axis-angle and two finger positions;
training converts environment gripper `[-1,1]` to native `[0,1]`, then uses checkpoint normalization.
Action evaluation reverses normalization and gripper conversion. Native four-step flow sampling
is unchanged. Offline action error is not rollout success or a real-robot safety result.

The language allowlist contains exactly 112 bias-free matrices: q/k/v/o and gate/up/down in each
retained layer. Vision, embeddings, norms, output head and all action components are excluded
from NF4. The source architecture is built on meta and official safetensors are read one tensor at
a time into their final owned CUDA representation. This avoids loading a dense base on the GPU.
Both precision arms store the remaining backbone in BF16; selected trainable action-head/projector
parameters and ordinary rank-32/alpha-64 LoRA are FP32, with FP32 fused AdamW moments. Task state/action inputs and training noise/time math retain native FP32 precision; the
backbone embedding dtype does not change the native action noise schedule. Native BF16
autocast also applies to adapter GEMMs; FP32 parameter storage does not imply FP32 GEMM execution.
TF32 controls are explicitly enabled as in the upstream head-training path and recorded in identity.

`model.backbone_adaptation.mode` selects four distinct controls:

| Mode | Language weights | Trainable language adapters | Native action projector/DiT |
|---|---|---|---|
| `nf4_lora` | frozen NF4, nested quantization, uint8 storage, BF16 compute | ordinary FP32 LoRA | trained FP32 by default |
| `bf16_lora` | frozen BF16 | identical LoRA | identical policy |
| `nf4_frozen` | frozen NF4 | none | trained FP32 |
| `bf16_frozen` | frozen BF16 | none | trained FP32 |

`train_action_head=false` is permitted only with adapters. It is a separate learning recipe,
not the selected jointly adapted recipe. The old cached-feature PPO path is rejected for backbone
adaptation because its no-grad features bypass language adapters. The flow-BC forward retains the
original noise distribution, time sampling, velocity objective and masked denominator. No language
SFT surrogate is used. The matched head-only controls above use fused AdamW and a single decay group;
the older native official recipe uses unfused AdamW and HF decay groups, and remains a distinct
comparison rather than an interchangeable control.

The separate `gr00t_n1d7_libero_official_head.py` native action-SFT recipe makes that existing
control executable. It streams the same pinned base into **FP32 backbone/head storage with BF16
autocast**, trains only the native head, and uses `adamw_torch` with HF decay/no-decay groups.
The actual pinned finetune launcher overrides its generic training-config fused-AdamW default;
this control follows the launcher and the existing Cosmos optimizer recipe. Training uses the
checkpoint's random crop/color jitter and 0.2 processor state dropout, while evaluation uses the
native deterministic transforms. Albumentations 1.4.18 is required: its transform randomness uses
the checkpointed global Python/NumPy streams, verified with actual nonzero augmentations.

This control explicitly adjusts the generic upstream batch-64/10,000-update defaults to batch one and
300 updates, with 15 warmup updates and the pinned HF cosine scheduler (including zero endpoints).
The same prepared ten-action supervision prefix remains explicit. It is a separate practical
control, not a replacement for matched BF16 LoRA or the already frozen development protocol.
Use the normal training command below with `--config
cosmos_framework/posttrain/configs/gr00t_n1d7_libero_official_head.py`, replace the
`model.backbone_adaptation.*` overrides with `data.backbone_path=/staged/Cosmos-Reason2-2B-metadata`,
and retain the dataset overrides. Native checkpoint/recovery and complete head-artifact reload
use the same entrypoints; dense export is explicitly unavailable for this additional control.
CPU optimizer/scheduler, augmentation and alias contracts are covered. A100 job `38509993`
also passed ten real updates, exact fresh checkpoint/portable scores, update-5-to-10 recovery,
frozen-source and optimizer-membership checks, eight shared CUDA cases, and fresh reload of
the earlier NF4 artifact. These checks establish lifecycle behavior; the separate 300-update
practical comparison is still required for this control's task quality and performance.

This is not a reproduction of the published LIBERO training benchmark. The pinned
[upstream Spatial recipe](https://github.com/NVIDIA/Isaac-GR00T/blob/51d4c89f72fda44cbf77285c6a8114b52676b8a1/examples/LIBERO/README.md#fine-tune-libero-spatial)
uses eight GPUs, global batch 640 and 20,000 updates from the generic
`nvidia/GR00T-N1.7-3B` base on the IPEC Spatial no-noops dataset. The present study
continues an already LIBERO-specialized checkpoint on the separately identified
HuggingFaceVLA export. Its outcome cannot be compared directly with the published
success rate or attributed to quantization without the matched BF16 LoRA arm.

Use pinned Isaac-GR00T source `51d4c89f72fda44cbf77285c6a8114b52676b8a1`, Transformers 4.57.6,
and bitsandbytes 0.49.2 for NF4. Construction verifies the upstream source digest and content-bound
checkpoint/processor identity. No missing-kernel, dense-weight or alternate-backend fallback occurs.
The shared [native action source profile](../../docker/posttrain/native_action/README.md)
reproduces the retained CUDA 12.8 package versions for both GR00T and Alpamayo without
changing Qwen's runtime:

```bash
python docker/posttrain/native_action/install.py \
  --uv /path/to/uv-0.11.29 --venv /durable/venvs/cosmos-native-action
source /durable/venvs/cosmos-native-action/native-action-env.sh
```

The initial native strategy is one CUDA process, BF16-capable hardware, no FSDP/DTensor/TP/PP/CP,
no gradient accumulation and no compilation. Only configurations with completed accelerator and
task evidence can be described as qualified. Other embodiments, model revisions and online PPO
are outside this initial integration.

```bash
export IMAGINAIRE_OUTPUT_ROOT=/durable/path/gr00t-runs
export PYTHONHASHSEED=17 CUBLAS_WORKSPACE_CONFIG=:4096:8

torchrun --standalone --nproc-per-node=1 \
  -m cosmos_framework.posttrain.entrypoints.action_sft \
  --config cosmos_framework/posttrain/configs/gr00t_n1d7_libero_qlora.py -- \
  model.checkpoint_path=/staged/GR00T-N1.7-LIBERO/libero_spatial \
  model.backbone_adaptation.backbone_path=/staged/Cosmos-Reason2-2B-metadata \
  model.backbone_adaptation.mode=nf4_lora \
  data.train_path=/prepared/gr00t/train.jsonl \
  data.validation_path=/prepared/gr00t/validation.jsonl \
  rl.max_steps=100 rl.evaluation_every=25 rl.save_every=25 rl.seed=17
```

Prepared JSONL rows require `id`, independent `episode_id`, `observation`, `actions` and `media`.
The loader binds every row and image/packed-media payload to the data cursor identity, rejects
train/validation episode, row or media overlap, and detects source mutation. It does not establish
independence between semantically related episodes; provenance screening remains necessary.

The entrypoint uses the existing `LLMTrainer`, flow-BC objective, optimizer/scheduler and DCP
publication. Resident evaluation preserves all RNG streams and mixed module modes, uses a separate
validation traversal and leaves the training cursor unchanged, including when scoring raises.
Each claimed target is checked after checkpoint publication/readback. Set target metric/threshold
before measuring outcomes; no target is inferred from candidate performance. Resumed runs explicitly
report process-only timing and do not reconstruct missing uninterrupted clocks.

For a deliberate recovery check, keep `rl.max_steps` fixed and first set `rl.pause_after_step=50`.
Rerun against the same native run identity with `rl.pause_after_step=0` and `rl.resume=auto`.
Only committed optimizer boundaries are resumable; a mid-update interruption restarts from the last
committed checkpoint. Optimizer, scheduler, RNG, data cursor and evaluation history are restored.
No simulator state is captured, so this is not a claim of exact online rollout continuation.

Build `cbe368d` additionally binds 25 explicit training/recovery source files in the
checkpoint's training contract. A changed or missing source contract refuses resume
before data preparation and model construction; the checkpoint codec checks it again
before restoring state. Resume older checkpoints with their original qualified build.
Do not edit metadata to bypass this restriction. Portable inference reload remains a
separate contract and accepts compatible older artifacts. The guard has 67 passing
CPU lifecycle tests; current-build full-model accelerator recovery is being qualified
separately from the retained `4cba88f` recovery evidence.
The current inventory has 28 files: it also binds shared flow-dataset row lookup,
media decoding and the opt-in evaluator helper. Those execution paths can change
without changing dataset bytes; the evaluator cache remains off by default.
Earlier 25-file contracts still require their original build; they are not rewritten
or upgraded during resume. This extension does not bind portable inference to training code.

Every checkpoint/portable policy includes all trained action-head/projector tensors alongside LoRA,
with source, model, quantization, processor/statistics, embodiment, action settings, resolved targets,
implementation hashes and dtype identities. Portable reload reconstructs the same quantized base.
Use a new output directory for a fresh-process native action evaluation:

```bash
torchrun --standalone --nproc-per-node=1 \
  -m cosmos_framework.posttrain.entrypoints.action_eval \
  --config cosmos_framework/posttrain/configs/gr00t_n1d7_libero_qlora.py \
  --checkpoint /run/checkpoints/iter_000100 \
  --output /durable/path/fresh-action-evaluation -- \
  model.checkpoint_path=/staged/GR00T-N1.7-LIBERO/libero_spatial \
  model.backbone_adaptation.backbone_path=/staged/Cosmos-Reason2-2B-metadata \
  data.validation_path=/prepared/gr00t/validation.jsonl
```

The same command accepts the portable path printed in `completion.json`. It verifies the commit,
parameter inventory and complete numerical identity before loading trained components. It reports
masked normalized-action MSE, per-component decoded environment-action MAE and native teacher-forced
flow loss separately. Prediction never receives demonstration actions as RTC conditioning. Generic
HF language-model loading and serving acceleration are not established by this portable loader.

The native dense export path separately reconstructs `dequantize(Q(W)) + (alpha/rank) B A` with
FP32 CPU accumulation and declared BF16 or FP32 merged-language storage. Non-target tensors retain
their native dtype, including FP32 trained action components. Standard indexed shards have a
configurable payload limit (512 MiB by default; a larger individual tensor gets its own shard).
The commit-last manifest includes per-tensor/file digests and copied native processor, embodiment,
statistics and backbone-tokenizer metadata. Fresh dense reconstruction needs no original base weights.

```bash
# Set these to the exact installed build identities, not guessed values.
export COSMOS_TRAINING_CODE_REVISION=<40-character-code-revision>
export COSMOS_TRAINING_WHEEL_SHA256=<64-character-wheel-sha256>
torchrun --standalone --nproc-per-node=1 \
  -m cosmos_framework.posttrain.checkpoint.tools.export_family_dense \
  --config cosmos_framework/posttrain/configs/gr00t_n1d7_libero_qlora.py \
  --checkpoint /run/checkpoints/iter_000100 --output /durable/gr00t-dense \
  --merged-backbone-dtype bfloat16 --max-shard-size-bytes 536870912 \
  --override model.checkpoint_path=/staged/GR00T-N1.7-LIBERO/libero_spatial \
  --override model.backbone_adaptation.backbone_path=/staged/Cosmos-Reason2-2B-metadata

torchrun --standalone --nproc-per-node=1 \
  -m cosmos_framework.posttrain.entrypoints.action_eval \
  --config cosmos_framework/posttrain/configs/gr00t_n1d7_libero_qlora.py --dense \
  --checkpoint /durable/gr00t-dense --output /durable/dense-evaluation -- \
  data.validation_path=/prepared/gr00t/validation.jsonl
```

This effective-base dense artifact is a different numerical execution from separate BF16-autocast
LoRA arithmetic. A further BF16 merge cast also changes the numerical model. Dense tensor checks,
fresh native task-output tolerances and task-quality evaluation are separate qualification gates;
implementation or file conversion alone does not establish their pass. Merging onto the untouched
original BF16 base, requantization, generic serving and deployment-latency improvements remain outside
this export contract. Dense artifacts cannot resume training.

An explicit **dequantized, unmerged** artifact is implemented on `8c64b5a`.
It stores the actual BF16 effective base, the separate FP32 LoRA factors, all
trained action components and native sidecars. Native loading rebuilds the same
separate adapter GEMMs and cast order without reading the original base or running
a quantizer. It uses a distinct commit manifest; `--dense` continues to mean the
existing merged representation. This is dense-base deployment, not four-bit
inference, and it does not turn the failed merged-output gates below into passes.

Use the export command above with `--unmerged` in place of
`--merged-backbone-dtype bfloat16`, then use `action_eval --unmerged` or
`gr00t_rollout --unmerged` instead of `--dense`. Preserve the original mode,
rank/alpha/dropout/adapter seed and task configuration. The two representation
flags are mutually exclusive. Source training metadata is preserved; the exporter
build is recorded separately. CPU checks cover exact factors/heads, aliases,
interrupted publication, corrupt artifacts and fresh loading without the source
weights or quantizer.

Full-model job `38522604` passed on exporter/inference build `64ea823` for both
selected `4cba88f` LR `1e-5`, seed-17, update-300 policies. Fresh native loading
exactly reproduced all 160 primary evaluation rows and controlled first/last-row
flow losses and action outputs, including input identities. All 537 FP32 trained
head tensors, 224 FP32 adapter factors, 112 BF16 effective backbone matrices and
the tied embedding/output-head ownership were preserved. The fresh containers
verified both original `fsw`/`fs11` checkpoint/backbone paths unavailable and
blocked quantizer imports before loading. The installed runtime still contains
bitsandbytes; this is not qualification of a bitsandbytes-free installation.

Each artifact contains 21 weight shards and 10,247,208,358 bytes across its
manifest-listed files. Three tensors exceed the 512 MiB payload limit and each
occupies its own shard, as declared by the format. The complete artifact-only
allocation consumed 1,240 GPU-seconds. Fresh loading/scoring peaked at 9.043 GiB
allocated and 9.695 GiB sampled GPU-process memory in both arms. All observed host
samples were complete; sampled peaks remain lower bounds between observations.
The [raw receipts and phase measurements](evidence/native_qlora_family_engineering_4cba88f.json)
separate source capture, export, loading, evaluation and publication costs. This
establishes fidelity for these selected checkpoints, not rollout quality or an
inference-speed improvement. The failed merged conversion gates remain unchanged.

Build `64ea823` additionally emits opt-in allocator records from native
`action_eval` when `COSMOS_QLORA_METRICS_FILE` is set. Loading includes portable
inventory verification; scoring, frozen-state verification and result publication
have separate reset-delimited intervals. The existing external sampler is still
needed for device allocations outside PyTorch and process-tree host memory.
The historical JSON workflow clock ends before result publication; the new phase
records expose that publication cost without rewriting old measurements.

An observation-only native rollout adapter and `entrypoints.gr00t_rollout` also connect a loaded
portable or dense policy to the existing isolated LIBERO simulator gateway. The separate
`gr00t_qlora_spatial_8_v1` profile executes eight supervised actions, allows 256 control steps and
keeps the native 15-step reset; legacy spatial's 16-action protocol is unchanged. Canonical simulator
images are already oriented correctly, and the simulator alone binarizes/inverts native gripper
commands. The policy adapter performs neither conversion a second time.

```bash
# cases.json is a prospectively fixed list of {suite, task_id, init_state_id} objects.
# The simulator interpreter must satisfy the existing pinned LIBERO runtime and asset preflight.
torchrun --standalone --nproc-per-node=1 \
  -m cosmos_framework.posttrain.entrypoints.gr00t_rollout \
  --config cosmos_framework/posttrain/configs/gr00t_n1d7_libero_qlora.py \
  --checkpoint /run/checkpoints/iter_000100 \
  --sim-python /verified/libero-venv/bin/python --cases /protocol/cases.json \
  --seed 17 --output /durable/rollout-seed17 -- \
  model.checkpoint_path=/staged/GR00T-N1.7-LIBERO/libero_spatial \
  model.backbone_adaptation.backbone_path=/staged/Cosmos-Reason2-2B-metadata
```

For dense policy inference, add `--dense` and point `--checkpoint` to the effective-base dense
artifact. The separate official-head control uses this same rollout entrypoint with its
`gr00t_n1d7_libero_official_head.py` config and `data.backbone_path` override; it accepts committed
native or portable head artifacts, but rejects `--dense`. Each loader checks the pinned source
and complete native parameter/processor identity before applying trained tensors.
For a source-policy control, replace `--checkpoint ...` with `--base`. The matched recipe
requires `model.backbone_adaptation.mode=bf16_frozen` or `nf4_frozen`; the separate official-head
recipe loads its original FP32 source directly. This path creates no adapter/checkpoint artifact
and refuses LoRA configurations or `--dense`. The rollout receipt distinguishes source from
trained artifacts and records the complete immutable model/processor identity. Actual source
rollout outcomes remain a separate measurement from training quality.
The training runtime does not itself contain the pinned simulator stack. With the isolated
pinned LIBERO/EGL runtime, job `38510600` completed both predeclared engineering episodes for
each retained ten-update portable policy. Both precision arms had zero successes out of two.
This verifies native policy/simulator execution only; it establishes neither task preservation
nor deployment-latency improvement. The artifact-output probe in
`model/gr00t/qualification.py` separately captures actual normalized and decoded actions, native
flow loss and processed-input digests; its comparison requires explicit predeclared tolerances.

Source-policy job `38514573` subsequently completed those same two exposed cases
with both frozen precision arms and the separate original FP32 source: all three
achieved 2/2 successes. This confirms that the observation/action bridge can execute
successful policies on these cases; it does not qualify adaptation or a success-rate
margin. NF4/BF16 sampled process peaks were 11.088/12.139 GiB. Mean response times
after five warmup calls were 0.286/0.262 s, including native preparation and action
sampling but excluding simulator rendering/control and gateway IPC. Policy-dependent
observations and unequal call counts prevent a matched-input latency claim.
The earlier attempt `38513829` remains failed: its wrapper incorrectly rejected a
valid early success. The corrected wrapper accepts the recorded successful control
count, checks sampler health even on exceptions, and verifies the allocated CPUs.

The prospective `gr00t-development-v1` study compares `nf4_lora`, `bf16_lora` and `bf16_frozen`
with the same FP32 action-head policy, fused AdamW, learning rate `1e-4`, constant schedule,
effective batch one and training seeds 17/42/123. It fixes 300 committed updates, full resident
validation at updates 0/100/200/300, and publication at updates 100/200/300 (also update zero if it
already meets the target); there is no quality-based early stop.
Arm order rotates across seeds. The outcome-blind cohort contains all ten spatial tasks:
eight training episodes per task with sixteen time-spaced windows (1,280 rows), and four validation
episodes per task with four windows (160 rows). Its manifest SHA256 is
`c726e37725c2d4be88efb17e8f96b956d018a07db9f72bde1f6825084392dd00`.
All 2,880 source images are RGB 256 × 256 with verified PNG payloads/content hashes.
The source is `HuggingFaceVLA/libero@86958911c0f959db2bbbdb107eb3e17c5f9c798e`;
its [immutable metadata](https://huggingface.co/datasets/HuggingFaceVLA/libero/blob/86958911c0f959db2bbbdb107eb3e17c5f9c798e/meta/info.json)
declares 10 Hz. Cosmos preserves consecutive source action rows without temporal
resampling, but no retained upstream conversion attestation establishes their
physical clock. The pinned official and Cosmos LIBERO simulators use 20 Hz control.
These are separate recorded facts: do not infer 20 Hz dataset equivalence or convert
the ten supervised action indices into a claimed physical horizon. Source conversion
provenance remains required for that broader temporal claim.

A separate CPU provenance probe compared the already-exposed training episode
1347 with `physical-intelligence/libero@a4336d589d589045d1c56423ffdf3b88a0e19b1f`.
All 92 source state/action rows, indices and timestamps matched exactly; all 16
prepared training windows retained the same FP32 states and consecutive ten-action
sequences. The export's episode metadata points to the wrong parquet file for this
episode, but Cosmos enumerates the actual rows and does not use that locator.
The [scoped receipts](evidence/native_qlora_family_engineering_4cba88f.json) retain
both observations. This probe found no reason to resample actions; it does not
attest the original simulator clock or establish whole-dataset provenance.

A processor-only census of one real row per instruction covered all ten fixed instructions
in both splits: 151–156 tokens, `pixel_values=[512,1536]`, two image grids `[1,16,16]`,
state `[1,1,132]`, and action/mask `[1,40,132]` with exactly 70 supervised elements.
This used the pinned deterministic native processor without model weights or CUDA.
The remaining rows share these instructions and admitted image geometry; this establishes
processor shape coverage, not additional GPU training or quality coverage. Actual GPU evidence
remains the traced updates described below and completed portions of the 300-update study.

The first complete seed-17 study (`38511256`, native `4cba88f`) retained all three
300-update runs and exact fresh portable scoring on the full 160-row development set:

| Mode | Source normalized action MSE | Update 300 MSE | Native workflow | Sampled GPU-process peak |
|---|---:|---:|---:|---:|
| BF16 head-only | 0.055068 | 0.225794 | 665.66 s | 31.154 GiB |
| BF16 LoRA + head | 0.055068 | 0.378767 | 665.15 s | 31.516 GiB |
| NF4 LoRA + head | 0.055654 | 0.286100 | 626.78 s | 30.412 GiB |

All targets were unreached. Every task slice and all seven action-axis MAEs
worsened from the source; favorable NF4-versus-trained-BF16 means therefore do
not establish useful adaptation. Training loss also rose, and 296/296/295 of 300
updates were clipped respectively, with no skipped/nonfinite updates. A checked
audit found no new loss-normalization, mask, source-action truncation or cursor
defect. The next prospectively bounded learning screen reduces LR from 1e-4 to 1e-5
for all three arms while preserving the data, loss, heads, horizon and fixed target.
It must reach that target and satisfy the 5% paired precision point guard before
additional seeds are considered; this screen cannot establish recipe noninferiority.

The allocation included separate fresh scoring after each native workflow; its
per-arm totals were 1344.40/1240.98/1205.89 s in the table's order. These are one-seed,
fixed-order observations on one GPU, not a time-to-quality improvement. Requested
CPU allocation was 16, but measured pre-native process affinity was only two logical
CPUs. Future paired launchers must explicitly request and verify the step CPUs;
cross-study timing changes cannot be attributed solely to LR. The measured NF4
memory reduction was only 1.104 GiB versus matched BF16 LoRA because full FP32 head
training dominates. Host PSS sampling was incomplete during process teardown in
2/861, 2/850 and 1/872 samples; retain its lower-bound peaks and incomplete flags.
The [terminal evidence](evidence/native_qlora_family_engineering_4cba88f.json)
contains clocks, phase distinctions, task diagnostics, identities and failed targets.
Episode, row and media-content splits are disjoint.
These previously exposed episodes provide development evidence, not independent confirmation.

The bounded **LR `1e-5` screen completed** in job `38515136` on the same sealed
native `4cba88f` implementation. Reducing LR was the only learning change for all
three arms. The launcher also explicitly requested and verified 16 logical CPUs;
therefore timing differences from the earlier two-CPU run are not attributed to LR.
All 900 updates applied, with zero nonfinite/skipped updates, exact fresh portable
primary scores, and 112/110/106 clipped updates for NF4/BF16-LoRA/BF16-head.
Each arm first reached the unchanged target at update 200 after verified publication.

| Mode | Update 300 action MSE | Time to target, including launch preflight | Native workflow | Workflow with three fresh scores | Sampled GPU-process peak |
|---|---:|---:|---:|---:|---:|
| NF4 LoRA + head | 0.04154305 | 519.39 s | 620.85 s | 1191.01 s | 30.412 GiB |
| BF16 LoRA + head | 0.04244151 | 499.52 s | 588.84 s | 1147.34 s | 31.516 GiB |
| BF16 head-only | 0.03983719 | 432.40 s | 488.65 s | 1005.88 s | 31.154 GiB |

Updates 101–300 averaged 0.4913/0.4527/0.3162 s in the table's order. Native
workflow includes preparation, all scheduled validation/checkpointing and portable
export; the next column adds the fixed fresh-process scores at noise seeds
123/456/789 and wrapper costs. Only seed 123 supplies the primary quality metric.
The complete allocation consumed 3,358 GPU-seconds, including shared setup/teardown.
Source calibration and the earlier failed learning trial remain additional costs.

NF4's MSE point estimate is 2.12% below matched BF16 LoRA at the same 300 updates,
but its preflight-inclusive time to target is 3.98% longer. The head-only control
is stronger on both metrics. These single-seed, fixed-order development results
pass the prospective screen for considering further qualification; they establish
neither recipe noninferiority nor superiority at equal training compute. The sampled
1.104 GiB saving is only about 3.5% of the matched BF16 peak. The 805,306,368 eligible
language weights permit at most 1.125 GiB of raw BF16-to-four-bit weight saving before
metadata; full FP32 head training dominates the footprint. Substantial total-memory
savings remain an unmet GR00T requirement for this policy.

All three arms retain incomplete host-PSS samples during native process teardown
(2/851, 1/818 and 1/712 respectively); measured peaks remain lower bounds.
NF4's decoded gripper MAE improves, while its decoded x/y/z MAEs increase relative
to its source. This decomposition of decoded MAE does not decompose normalized MSE
or establish rollout behavior. The separately completed 100-case simulator check
below rejects promotion of this 300-update recipe. The previous LR `1e-4` failures,
unchanged quality margins and independent-confirmation requirement remain intact.

Selected-build recovery job `38521659` completed on the same `4cba88f` source:
both LoRA arms resumed from their committed update-200 checkpoints through update
300 with exact model/optimizer tensors, RNG, data cursor and evaluation state.
Only the new publication destination, identifier and manifest fields differ.
Fresh native checkpoint and portable loads preserved all 537 trained head tensors
and 224 LoRA factors and exactly reproduced all 160 primary evaluation rows and
metrics. Restored target crossings keep the original update-200 checkpoint and
report no reconstructed elapsed time. This is recovery evidence for the same
trained policies, not another seed or a change to the failed rollout decision.
The allocation consumed 1,331 GPU-seconds. Both resume stages retain incomplete
host-PSS sampling; all four fresh scoring stages have complete sampled host
receipts. Old-build `action_eval` emitted no allocator phase records, so those
fresh-scoring GPU/host peaks remain sampled lower bounds. The
[terminal receipts](evidence/native_qlora_family_engineering_4cba88f.json) preserve
these limitations and the separate resume allocator measurements.

Job `38518798` completed all 400 prospectively fixed rollouts: ten Spatial tasks,
ten initial states per task, seed 17, four flow-sampling steps, eight executed
actions per chunk and at most 256 controls. The same native simulator/reset and
observation-only policy path was used for every arm.

| Policy | Successes / 100 |
|---|---:|
| Original frozen BF16 source | 99 |
| Original frozen NF4 source | 99 |
| Trained BF16 LoRA + head, update 300 | 92 |
| Trained NF4 LoRA + head, update 300 | 93 |

The original additional-seed screen **fails**: trained NF4 loses six percentage
points against its own source, above the predefined two-point allowance. Its
one-point advantage over trained BF16 does not establish preservation: the paired
whole-task one-sided 95% upper loss bound is **3 points**. Corresponding bounds
against each arm's frozen source are 9 points for NF4 and 13 for BF16. These are
fixed-checkpoint development bounds from ten tasks, not recipe-level intervals
across training seeds or independent confirmation. The earlier offline-MSE screen
passed its own criteria; that result is preserved and does not override this
failed behavior gate. No further learning seeds are promoted from this endpoint.

The allocation consumed 3,733 GPU-seconds. All 2,780 host samples were complete;
trained NF4/BF16 sampled compute-process GPU peaks were 11.203/12.252 GiB.
Total-device peaks were also recorded separately. The
[retained evidence](evidence/native_qlora_family_engineering_4cba88f.json) includes
every case outcome, task-level comparison and response-time distribution.
On-policy observations and response counts differ, so these response timings do
not establish an inference acceleration claim. Offline time to the action-MSE
target above is not time to preserved rollout success.

The separate first-target stopping screen (`38523598`, 2,901 GPU-seconds) loaded
existing update-200 DCPs without retraining. All three arms had first met the
unchanged offline target at that update. On the same 100 development cases,
NF4 LoRA + head scored **98/100**, BF16 LoRA + head **97/100**, and the matched
BF16 trained-head-only control **97/100**. The prospective joint point screen
passes; keep first-target stopping as a development candidate. The original
update-300 failure above remains unchanged.

The paired whole-task bootstrap (10,000 draws, seed 6809) gives NF4 upper loss
bounds of **3 points versus BF16 LoRA** and **4 points versus its frozen source**,
which do not meet the unchanged two-point preservation guard. Both LoRA arms
improve five points over their own update-300 policies; their upper loss bounds
for that comparison are −2 points (NF4) and −1 point (BF16). BF16 head-only
loses two points against its source, with an upper bound of four points. These
are fixed-checkpoint development comparisons, not independent or paired-training-seed
qualification, superiority, or evidence of improved time to rollout quality.
Original offline target clocks are retained; no rollout target clock is reconstructed.

All 2,149 host samples were complete. NF4/BF16 LoRA sampled owned-process peaks
through checkpoint loading and rollout were 11.646/12.697 GiB; they remain sampled
lower bounds. The source-relative comparisons and all case outcomes are retained
in the [terminal evidence](evidence/native_qlora_family_engineering_4cba88f.json).
On-policy response inputs differ, so these timings do not establish inference
acceleration. The previously verified update-300 portable and standalone artifacts
validate their own tensors; selected update-200 publication and fresh scoring remain
separate pending checks.

To reproduce this screen through the native training command above, use the
admitted `gr00t-development-v1` JSONL files and these overrides in **each** arm:

```text
rl.optimizer.lr=1e-5 rl.optimizer.weight_decay=1e-5 rl.optimizer.grad_clip_norm=1.0
rl.max_steps=300 rl.evaluation_every=100 rl.save_every=100 rl.seed=17
model.backbone_adaptation.rank=32 model.backbone_adaptation.alpha=64
model.backbone_adaptation.seed=17
rl.target_metric=normalized_action_mse rl.target_threshold=0.049561327725898344
rl.target_direction=min rl.stop_on_target=false
```

The numeric target is bound to that cohort and its recorded frozen-source scoring;
it is not a universal target for other data. Select `nf4_lora`, `bf16_lora` or
`bf16_frozen` explicitly. No optimizer-precision change is included.

Before either LoRA candidate runs, use native `action_eval --base` with `mode=bf16_frozen` and
`rl.evaluation_seed=123` on the locked validation cohort. Freeze the offline action-quality target
as `0.90 * M0`, where `M0` is that original source model's `normalized_action_mse`; record the
reference evaluation, identities and threshold before admission. Training uses
`rl.target_metric=normalized_action_mse`, the frozen `rl.target_threshold`, and
`rl.stop_on_target=false`. Count target time through verified checkpoint publication, retain
nonattainment at update 300, and charge the reference scoring cost explicitly. This is time to an
offline action-error target, not time to closed-loop success. Equal update counts are a controlled
work comparison, not proof of equal-compute quality or faster learning.

Prospective preservation guards are a one-sided 95% upper bound of 5% relative normalized action-MSE
increase and two percentage points of closed-loop success loss against the matched BF16 LoRA arm.
The first permits at most 2.47% relative RMSE amplitude increase; the second permits at most one
additional failure per fifty episodes. Neither is inherited from WTS answer accuracy. Weight tasks
equally, then episodes/windows equally. Use a paired crossed bootstrap of training seeds and tasks,
with episode resamples shared across all seeds and precision arms; repeated frames or scoring seeds
are not independent tasks. Three training seeds and ten task clusters may be insufficient to establish
these bounds. The separate planned rollout comparison uses ten fixed initial states per task under
the eight-action profile and must pass actual simulator preflight first. Improvement, preservation,
and useful adaptation over the source are separate claims; retain all failed trials.

Before inspecting dense-conversion outputs, its numerical gates are fixed at maximum absolute
error 0.02 on the valid 16 × 7 normalized actions and decoded controller commands, plus both
0.002 absolute and 2% relative masked flow-loss error (relative denominator floor `1e-6`).
The full 40 × 132 latent output is shape-checked and its unused-slot error reported separately.
Every decoded gripper command must preserve `sign(2*g-1)` exactly, and trained auxiliary tensors
and processed-input identities must match exactly. At the pinned OSC_POSE scales, a 0.02 command
difference corresponds to at most 1 mm position-command or 0.01 rad orientation-command difference
per step; this is a numerical budget, not a safety or rollout-quality claim. Same-quantized-base
portable reload retains zero numerical tolerances. A failed conversion gate is retained as a failure.

## Completed native engineering checks

The [sealed `4cba88f` engineering receipts](evidence/native_qlora_gr00t_engineering_4cba88f.json)
record ten real LIBERO action updates in both precision arms on A100 80GB. Job
`38507341` passed exact fresh-process checkpoint and portable-policy task scores,
and update-5-to-10 recovery of model, optimizer, RNG, data cursor and evaluation
state. BF16's uninterrupted reference comes from job `38506697`; its original
outer qualification checker failed after training completed. The later checks
verify those retained artifacts and do not rewrite that job's failed status.

The small engineering set's normalized action MSE increased from 0.04976 to
0.17405 for NF4 and from 0.04870 to 0.15470 for BF16. This adverse ten-update
result establishes neither useful adaptation nor recipe quality. Warm update
means over steps 3–10 were 0.495/0.445 seconds, and native workflows took
142.45/143.80 seconds. Different placement and one short trial prevent a speed
claim; startup, scoring and checkpoint I/O dominate these workflows.

The trainable FP32 action head dominates total memory. The measured allocator
reduction is approximately 1.1 GiB, much smaller than Qwen's savings. Historical
external GPU-process samples are missing: Torch 2.10 returned a bare UUID and
the sampler expected NVML's `GPU-` prefix. Native allocator and process-RSS
records remain valid. UUID normalization and sampler-health checks must pass
before the larger comparison's memory claims; missing historical samples cannot
be recreated. Full development, dense conversion and rollout qualification remain
separate gates.

The subsequent [family engineering receipts](evidence/native_qlora_family_engineering_4cba88f.json)
preserve an actual process loss during update-six backward in both arms. Partial publication
was rejected, and restart from committed update five reproduced model, optimizer, RNG, cursor,
evaluation state and task scores at update ten exactly. Job `38507907` later failed before its
profile began because the launcher precreated the profiler's output directory; that job remains
failed and its completed recovery checks remain valid.

Dense BF16 conversion **failed** the unchanged controlled-output gates in job `38508290`.
NF4 had a 0.10645 maximum normalized-action difference on one probe and a 0.002462 flow-loss
difference on another; the BF16 control's two action maxima were 0.03418 and 0.03711.
The limits remain 0.02 action error and both 0.002/2% flow-loss error. All auxiliary tensors
and tied-weight aliases were preserved, and fresh native evaluation completed, but small mean
task-metric differences do not override failed probe gates. Both approximately 10.17 GB dense
artifacts and negative decisions are retained. Native portable reload and dense
conversion are separate capabilities.

Follow-up `38514034` isolated the conversion difference: dequantized but unmerged
execution matched the portable policy exactly on both probes and common-input
layer replays; all 112 merged matrices exactly matched the declared FP32 accumulation
followed by BF16 cast. Auxiliary tensors and standalone reconstruction were also exact.
This implicates changed finite-precision arithmetic in the observed drift, rather
than missing task state or a different quantized base. A bounded FP32 merged-compute
prototype (`38514818`) also failed the unchanged gates in both arms and increased
the sampled diagnostic process peak from 12.316 to 13.826 GiB. It is rejected;
no FP32 execution option is promoted. These two diagnostic allocations cost
1,037 GPU-seconds and do not constitute a training or serving benchmark. The
[retained decisions](evidence/native_qlora_family_engineering_4cba88f.json) preserve
every failed probe. GR00T merged-artifact fidelity remains unresolved.

Paired profile job `38509185` completed 24 native updates per arm on the same A100
and CPU allocation, tracing updates 21–24 after warmup. Actual inputs contained
151–156 tokens, two images packed as `[512,1536]`, and 70 supervised action elements
in `[1,40,132]` tensors. Gradient-finiteness validation consumed approximately
104.7/106.4 ms of traced NF4/BF16 update wall time; clipping was another distinct
region. The unused vocabulary projection took only about 0.59 ms of GPU time per
update. CPU and GPU regions overlap, and trace overhead prevents treating these
numbers as production throughput. The next single intervention is a read-only
batched gradient check, shared by both precision arms, subject to correctness and
unprofiled timing gates.

That profile measured sampled owned-process GPU peaks of 30.404/31.490 GiB and
native training allocator peaks of 27.221/28.334 GiB. These new samples are valid;
they do not recreate the missing earlier samples. The 1.62-billion-parameter FP32
action head and its gradients/moments dominate memory. The approximately 1.1 GiB
saving remains modest, so substantial GR00T memory savings and task-quality/time-to-target
benefits remain open requirements.

The source-policy calibration scored all 160 development rows before candidate training.
Frozen BF16/NF4 normalized action MSE was 0.05506814/0.05565446, respectively; these are
point estimates without a preservation claim. The unchanged target rule fixes the common
threshold at **0.049561327725898344**. Calibration jobs `38509654`/`38509843`, target identity
and exact metrics are retained in the family evidence. The seed-17 three-arm study uses that
target; later outcomes cannot redefine it.

The batched gradient-check candidate `3c96ce8` passed 22 real CUDA cases on each of the
Torch 2.10 family and Torch 2.11 Qwen runtimes in job `38510926`, with no skips. Those tests
cover finite/NaN/Inf detection, unmodified gradient bytes/RNG and tiny native updates/recovery.
Full-model GR00T gate `38517306` subsequently passed exact model, optimizer,
RNG/data/control and task-score comparisons with `4cba88f` at updates five and ten
in both precision arms. Each candidate arm also passed actual process loss during
backward six, rejection of a partial save, and exact own-build recovery from five
to ten. Compatible fresh-artifact evidence was reused only through exact trained
tensors and unchanged native model/scorer/codec hashes; this gate does not claim
a new fresh-process reload. It consumed 1,403 GPU-seconds, with incomplete host-PSS
sampling retained. Alpamayo full-model parity and sustained unprofiled workflow
benefit remain promotion gates; selected family training still uses `4cba88f`.


The first sustained timing attempt (`38527266`) failed before model loading, using
66 GPU-seconds. Python's native-source working directory shadowed the separately
hashed measurement package; the observer identity guard correctly refused it.
The versioned dispatch correction sets Python safe-path mode and explicit observer
sibling imports for both native builds and the final comparison. All scientific,
training and observer code, target and acceptance gates remain unchanged. Sixty-one
CPU checks reproduced the failure and verified corrected parent, child and monitor
imports. Replacement `38528318` is pending qualification; admission is not a speed result.
