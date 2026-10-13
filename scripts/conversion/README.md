# Checkpoint conversion launcher

`convert.sh` is the supported command-line entry point for Hugging Face ↔
Megatron checkpoint conversion. It uses NeMo Run for both local execution and
Slurm submission and selects one of two conversion backends:

- `--device cpu`: CPU conversion, with optional distributed export across
  Gloo ranks for checkpoints that cannot be exported on one host;
- `--device gpu`: distributed conversion with one process per GPU and TP, PP,
  EP, and ETP support.

Run `./scripts/conversion/convert.sh import --help`,
`./scripts/conversion/convert.sh export --help`, or
`./scripts/conversion/convert.sh roundtrip --help` for the complete CLI.

### Megatron-LM checkpoint compatibility

Training with Megatron-LM and later relying on Megatron Bridge for Hugging Face
export is **not recommended**. Megatron-LM checkpoints normally store their
arguments in `common.pt` instead of the `run_config.yaml` used by the supported
Bridge export launcher, so the launcher cannot consume them directly. For an
existing trusted checkpoint, the
[best-effort compatibility guidance](../../docs/megatron-lm-to-megatron-bridge.md#best-effort-export-of-an-existing-megatron-lm-checkpoint)
describes how to generate and validate the required provider configuration. It
does not guarantee compatibility, and any unclassified metadata mismatch must
stop the export.

Output from `scripts/translate_mlm_to_bridge.py` is best-effort configuration
guidance for a new Bridge run. It is not checkpoint metadata and must not be
renamed or inserted as `run_config.yaml`.

## Local CPU conversion

### Apertus2 routing contract

Apertus2 conversion supports quantile balancing only. HF configs must declare
`use_quantile_balancing=True`; native checkpoint routing must include
`quantile_balancing`, with `moe_router_enable_expert_bias=False`. Both sigmoid
and legacy raw-logit QB score spaces are preserved.

Native `marin_histogram` routing currently exports
`moe_router_quantile_balancing_method="legacy"` in the HF config. The name
`"legacy"` is a temporary compatibility label for the existing HF/vLLM option:
expert selection uses raw `logits - qb_beta`, while mixture weights use the
unbiased sigmoid scores. The `qb_beta` tensor mapping and FP32 preservation
are unchanged.
The HF `"legacy"` value describes inference routing, not the Marin training
estimator; importing it defaults to `legacy_average`. To continue Marin training,
explicitly select `marin_histogram` and its estimator settings with a compatible
MCore version. Bridge accepts the native method name but does not add Marin
support to an older MCore. The HF reference modeling code must support raw-logit
QB selection as well.

### Explicit Apertus2 KDA layout settings

Supply the KDA gate-bias and `A_log` layout flags explicitly. Bridge does not
infer them from checkpoint tensor shapes or model names. The HF reference
`config.json` used for conversion must declare both
`linear_attn_output_gate_bias` and `linear_attn_a_log_per_channel`; config
conformance drops fields absent from that reference.

| Checkpoint | `kda_legacy_gate_out_proj_bias` | `linear_attn_a_log_per_channel` |
| --- | ---: | ---: |
| Chonk (legacy gate bias) | `True` | `False` |
| Megachonk | `False` | `True` |

For a native checkpoint, set the provider fields through the explicit
`mp_overrides` argument. Keep the HF reference config values aligned with the
overrides so the synthesized config retains the same layout:

```python
from megatron.bridge import AutoBridge

bridge = AutoBridge.from_auto_config(
    megatron_path="/path/to/native-checkpoint",
    hf_model_id="/path/to/apertus2-hf-reference",
    trust_remote_code=True,  # Only use trusted reference Python code.
    mp_overrides={
        "kda_legacy_gate_out_proj_bias": True,  # Chonk; use False for Megachonk
        "linear_attn_a_log_per_channel": False,  # Chonk; use True for Megachonk
    },
)
```

Pass the same `mp_overrides` to `load_megatron_model` when loading native weights.

The config-only `save_hf_weights` path collects the full exported state dict in
rank-0 CPU memory before sharding, even when distributed saving is requested.
Successful validation with a bounded scratch writer does not establish that
this unchanged public saver can fit Megachonk in rank-0 RAM.

For HF import, set `linear_attn_output_gate_bias` and
`linear_attn_a_log_per_channel` in the source HF config. The
Apertus2 provider and builder translate the explicit `A_log` config value to
MCore's `KDA_ALOG_PER_CHANNEL` environment setting during construction; callers
should not set that environment variable to guess checkpoint layout.

Use the QB-only configuration and modeling files from the updated hfconverter
as the HF reference assets. Bridge copies custom Python code from the supplied
reference; updating Bridge does not update the code bundled in an existing
HF export directory.

### Running locally

Local execution uses the current Megatron Bridge environment and waits for the
conversion to finish.

```bash
./scripts/conversion/convert.sh import \
  --executor local \
  --device cpu \
  --hf-model meta-llama/Llama-3.2-1B \
  --megatron-path /workspace/models/llama32-1b

./scripts/conversion/convert.sh export \
  --executor local \
  --device cpu \
  --hf-model meta-llama/Llama-3.2-1B \
  --megatron-path /workspace/models/llama32-1b/iter_0000000 \
  --hf-path /workspace/models/llama32-1b-hf
```

CPU import and the default CPU export use one process on one node. Distributed
CPU export is available through the Slurm workflow below for checkpoints that
cannot be loaded on one host within the available memory or wall-time limit.

## Distributed GPU conversion on Slurm

The GPU backend uses NeMo Run's torchrun launcher for local execution and
srun-native tasks for Slurm. Users should not wrap the command in `torchrun`,
`srun`, or `sbatch`.

The requested topology must satisfy `nodes * gpus-per-node % (TP * PP) == 0` and
`nodes * gpus-per-node % (ETP * EP * PP) == 0`. Expert parallelism is an
alternative slicing of the same ranks rather than an extra multiplicand, so it
is not part of the first product. Ranks left over after either split form
data-parallel replicas.

```bash
export HF_TOKEN="$(<${HOME}/HF_TOKEN)"

./scripts/conversion/convert.sh import \
  --executor slurm \
  --device gpu \
  --nodes 1 \
  --gpus-per-node 8 \
  --account ACCOUNT \
  --partition PARTITION \
  --time 01:00:00 \
  --container-image /path/to/megatron-bridge.sqsh \
  --mount /workspace \
  --mount /path/to/Megatron-Bridge:/opt/Megatron-Bridge \
  --env HF_TOKEN \
  --hf-model Qwen/Qwen3-30B-A3B \
  --megatron-path /workspace/models/qwen3-30b-a3b \
  --tp 1 --pp 1 --ep 8 --etp 1
```

For export, add `--hf-path`. Distributed Hugging Face saving is enabled by
default for the GPU backend to avoid gathering the full model on rank zero.
Use `--no-distributed-save` only when the model fits comfortably on rank zero.

GPU import uses the faster checkpoint save path by default. For models that
would otherwise run out of GPU memory while saving the imported checkpoint,
add `--low-memory-save`. This releases model shards as they are saved, but can
increase conversion time, so enable it only when the default path does not fit:

```bash
./scripts/conversion/convert.sh import \
  --executor slurm \
  --device gpu \
  --nodes 1 \
  --gpus-per-node 8 \
  --hf-model MODEL \
  --megatron-path /workspace/models/large-model \
  --tp 1 --pp 1 --ep 8 --etp 1 \
  --low-memory-save
```

No cluster-specific `srun` flags are added by default. If the target cluster
requires extra flags, repeat `--srun-arg=ARG`. For example, a Pyxis/Enroot
cluster may use:

```bash
--srun-arg=--mpi=pmix \
--srun-arg=--no-container-mount-home \
--srun-arg=--container-writable
```

The `=` form is required when `ARG` begins with `-`.

## Distributed round-trip validation

Like `import` and `export`, the `roundtrip` command runs the shared
`scripts/conversion/run_conversion.py` worker through the NeMo Run local or
Slurm executor. It compares weights after the Hugging Face → Megatron → Hugging
Face conversion and requires the GPU backend. The standalone
`examples/conversion/hf_megatron_roundtrip_multi_gpu.py` example remains
available for direct `torch.distributed.run` usage.

```bash
./scripts/conversion/convert.sh roundtrip \
  --executor local \
  --device gpu \
  --gpus-per-node 8 \
  --hf-model Qwen/Qwen3-30B-A3B \
  --tp 1 --pp 1 --ep 8 --etp 1 \
  --trust-remote-code
```

`--hf-model` and `--hf-model-id` are aliases. Round-trip validation converts the
Hugging Face weights into a distributed Megatron model, exports them back in
memory, and compares them with the original weights. It does not read or write
Megatron checkpoints or write a Hugging Face output; use the `import` and
`export` commands for persistent conversion. For long multi-node validations, set
`--distributed-timeout-minutes` to raise the NCCL process-group timeout.

## CPU conversion on Slurm

CPU mode submits one task and does not request GPUs or GRES:

```bash
./scripts/conversion/convert.sh import \
  --executor slurm \
  --device cpu \
  --nodes 1 \
  --mem 1T \
  --account ACCOUNT \
  --partition CPU_PARTITION \
  --container-image /path/to/megatron-bridge.sqsh \
  --mount /workspace \
  --mount /path/to/Megatron-Bridge:/opt/Megatron-Bridge \
  --env HF_TOKEN \
  --hf-model meta-llama/Llama-3.2-1B \
  --megatron-path /workspace/models/llama32-1b
```

For a very large Megatron checkpoint, distribute only the export load and save
across CPU processes. This uses Gloo, initializes every model shard on CPU, and
enables distributed Hugging Face saving by default. It does not request GPUs:

```bash
./scripts/conversion/convert.sh export \
  --executor slurm \
  --device cpu \
  --nodes 4 \
  --cpu-processes-per-node 8 \
  --cpus-per-task 16 \
  --mem 0 \
  --exclusive \
  --account ACCOUNT \
  --partition CPU_PARTITION \
  --container-image /path/to/megatron-bridge.sqsh \
  --mount /workspace \
  --hf-model MODEL \
  --megatron-path /workspace/models/model/iter_0000000 \
  --hf-path /workspace/models/model-hf \
  --tp 1 --pp 4 --ep 8 --etp 1
```

The topology must satisfy
`nodes * cpu-processes-per-node % (TP * PP) == 0` and
`nodes * cpu-processes-per-node % (ETP * EP * PP) == 0`. Distributed CPU
conversion currently supports export only and requires distributed saving.

`--env` accepts names only. Export values in the launcher environment so
secrets are inherited by Slurm without being materialized in generated job
scripts. Use `--submission-dry-run` to inspect a rendered job and `--detach`
when a Slurm command should return immediately after submission. Local execution
always waits so worker failures propagate to the launcher.
