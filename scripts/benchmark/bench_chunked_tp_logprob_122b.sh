#!/bin/bash
# Benchmark: baseline vs chunked TP logprob on Qwen3.5-122B-A10B.
#
# A/B comparison at configurable context length on single-node 8xH200.
# Each variant runs 10 training steps with identical config.
#
# Usage:
#   bash scripts/benchmark/bench_chunked_tp_logprob_122b.sh
#   NUM_ROLLOUT=10 MAX_TRAINING_STEPS=5 bash scripts/benchmark/bench_chunked_tp_logprob_122b.sh
#   ROLLOUT_MAX_RESPONSE_LEN=16384 RUN_FUSED_SELECTED_VARIANT=1 bash scripts/benchmark/bench_chunked_tp_logprob_122b.sh

set -euo pipefail
set -x

NUM_ROLLOUT="${NUM_ROLLOUT:-10}"
MAX_TRAINING_STEPS="${MAX_TRAINING_STEPS:-10}"
SEQ_CHUNK_SIZE="${SEQ_CHUNK_SIZE:-512}"
GPUS_PER_NODE="${GPUS_PER_NODE:-8}"
ROLLOUT_MAX_RESPONSE_LEN="${ROLLOUT_MAX_RESPONSE_LEN:-4096}"
RUN_FUSED_SELECTED_VARIANT="${RUN_FUSED_SELECTED_VARIANT:-0}"

cleanup() {
    pkill -9 sglang 2>/dev/null || true
    sleep 3
    ray stop --force 2>/dev/null || true
    pkill -9 ray 2>/dev/null || true
    pkill -9 python 2>/dev/null || true
    sleep 3
    pkill -9 ray 2>/dev/null || true
    pkill -9 python 2>/dev/null || true
}

cleanup

if [ ! -f /root/Qwen3.5-122B-A10B/config.json ]; then
    echo "Downloading Qwen3.5-122B-A10B..."
    python3 -c "from huggingface_hub import snapshot_download; snapshot_download('Qwen/Qwen3.5-122B-A10B', local_dir='/root/Qwen3.5-122B-A10B')"
fi

if [ ! -f /root/gsm8k/train.parquet ] || ! python3 -c "import pandas as pd; df = pd.read_parquet('/root/gsm8k/train.parquet'); assert 'messages' in df.columns" 2>/dev/null; then
    echo "Preparing gsm8k (chat format)..."
    rm -f /root/gsm8k/train.parquet /root/gsm8k/test.parquet
    python3 examples/lora/prep_gsm8k.py
fi

export PYTHONBUFFERED=16
unset http_proxy https_proxy HTTP_PROXY HTTPS_PROXY

NVLINK_COUNT=$(nvidia-smi topo -m 2>/dev/null | grep -o 'NV[0-9][0-9]*' | wc -l)
if [ "${NVLINK_COUNT}" -gt 0 ]; then
    HAS_NVLINK=1
else
    HAS_NVLINK=0
fi

SCRIPT_DIR="$(cd -- "$(dirname -- "${BASH_SOURCE[0]}")" &>/dev/null && pwd)"
source "${SCRIPT_DIR}/../models/qwen3.5-122B-A10B.sh"

CKPT_ARGS=(
   --hf-checkpoint /root/Qwen3.5-122B-A10B/
   --megatron-to-hf-mode bridge
)

LORA_ARGS=(
   --lora-rank 32
   --lora-alpha 32
   --lora-dropout 0.0
   --target-modules "all-linear"
)

ROLLOUT_ARGS=(
   --prompt-data /root/gsm8k/train.parquet
   --input-key messages
   --label-key label
   --apply-chat-template
   --rollout-shuffle
   --rm-type math
   --num-rollout "${NUM_ROLLOUT}"
   --rollout-batch-size 8
   --n-samples-per-prompt 4
   --rollout-max-response-len "${ROLLOUT_MAX_RESPONSE_LEN}"
   --rollout-temperature 1
   --global-batch-size 32
)

PERF_ARGS=(
   --tensor-model-parallel-size 2
   --sequence-parallel
   --pipeline-model-parallel-size 1
   --context-parallel-size 1
   --expert-model-parallel-size 8
   --expert-tensor-parallel-size 1
   --recompute-granularity full
   --recompute-method uniform
   --recompute-num-layers 1
   --micro-batch-size 1
   --qkv-format bshd
)

GRPO_ARGS=(
   --advantage-estimator grpo
   --kl-loss-coef 0.01
   --kl-loss-type low_var_kl
   --kl-coef 0.00
   --entropy-coef 0.00
   --eps-clip 0.2
   --eps-clip-high 0.28
)

OPTIMIZER_ARGS=(
   --optimizer adam
   --lr 5e-5
   --clip-grad 1.0
   --lr-decay-style constant
   --weight-decay 0.1
   --adam-beta1 0.9
   --adam-beta2 0.98
   --optimizer-cpu-offload
   --overlap-cpu-optimizer-d2h-h2d
   --use-precision-aware-optimizer
)

MLFLOW_ARGS=(
   --use-mlflow
   --mlflow-experiment-name slime-kernel-optimization
)

SGLANG_ARGS=(
   --rollout-num-gpus-per-engine 8
   --sglang-mem-fraction-static 0.4
   --sglang-ep-size 8
   --sglang-cuda-graph-bs 1 2 4 8 $(seq 16 8 256)
   --sglang-max-running-requests 256
   --offload-train
)

MISC_ARGS=(
   --attention-dropout 0.0
   --hidden-dropout 0.0
   --accumulate-allreduce-grads-in-fp32
   --attention-softmax-in-fp32
   --attention-backend flash
   --moe-token-dispatcher-type alltoall
   --max-training-steps "${MAX_TRAINING_STEPS}"
)

export MASTER_ADDR="${MASTER_ADDR:-127.0.0.1}"
export no_proxy="127.0.0.1,${MASTER_ADDR}"

RUNTIME_ENV_JSON="{
  \"env_vars\": {
    \"PYTHONPATH\": \"/root/Megatron-LM/\",
    \"CUDA_DEVICE_MAX_CONNECTIONS\": \"1\",
    \"NCCL_NVLS_ENABLE\": \"${HAS_NVLINK}\",
    \"SGLANG_DISABLE_CUDNN_CHECK\": \"1\",
    \"no_proxy\": \"${no_proxy}\"
  }
}"

run_variant() {
    local label="$1"
    shift
    local logfile="/tmp/bench_chunked_tp_122b_${label}.log"

    echo ""
    echo "========================================"
    echo "  Run: ${label}"
    echo "========================================"

    cleanup
    ray start --head --node-ip-address "${MASTER_ADDR}" --num-gpus "${GPUS_PER_NODE}" \
        --disable-usage-stats --dashboard-host=0.0.0.0 --dashboard-port=8265

    ray job submit --address="http://127.0.0.1:8265" \
        --runtime-env-json="${RUNTIME_ENV_JSON}" \
        -- python3 train.py \
        --actor-num-nodes 1 \
        --actor-num-gpus-per-node "${GPUS_PER_NODE}" \
        --colocate \
        --calculate-per-token-loss \
        "${MODEL_ARGS[@]}" \
        "${CKPT_ARGS[@]}" \
        "${LORA_ARGS[@]}" \
        "${ROLLOUT_ARGS[@]}" \
        "${OPTIMIZER_ARGS[@]}" \
        "${GRPO_ARGS[@]}" \
        "${MLFLOW_ARGS[@]}" \
        "${PERF_ARGS[@]}" \
        "${SGLANG_ARGS[@]}" \
        "${MISC_ARGS[@]}" \
        "$@" \
        2>&1 | tee "${logfile}"

    ray stop --force
    sleep 5
}

run_variant "baseline" \
    --mlflow-run-name "122b-baseline-${ROLLOUT_MAX_RESPONSE_LEN}-lora" \
    --log-probs-chunk-size 4096

run_variant "chunked_seq${SEQ_CHUNK_SIZE}" \
    --mlflow-run-name "122b-chunked-${ROLLOUT_MAX_RESPONSE_LEN}-lora" \
    --use-chunked-tp-logprob-loss \
    --chunked-tp-logprob-seq-chunk-size "${SEQ_CHUNK_SIZE}"
if [ "${RUN_FUSED_SELECTED_VARIANT}" = "1" ]; then
    run_variant "fused_seq${SEQ_CHUNK_SIZE}" \
        --mlflow-run-name "122b-fused-${ROLLOUT_MAX_RESPONSE_LEN}-lora" \
        --use-chunked-tp-logprob-loss \
        --chunked-tp-logprob-seq-chunk-size "${SEQ_CHUNK_SIZE}" \
        --use-fused-selected-tp-logprob
fi

echo ""
echo "========================================"
echo "  Results Summary"
echo "========================================"

for label in baseline "chunked_seq${SEQ_CHUNK_SIZE}"; do
    echo ""
    echo "--- ${label} ---"
    grep -E "actor_train_time|log_probs_time|train_wait_time|sleep_time|wake_up_time|update_weights_time|tflops|peak_gb|tok_per_s" "/tmp/bench_chunked_tp_122b_${label}.log" || true
done
if [ "${RUN_FUSED_SELECTED_VARIANT}" = "1" ]; then
    echo ""
    echo "--- fused_seq${SEQ_CHUNK_SIZE} ---"
    grep -E "actor_train_time|log_probs_time|train_wait_time|sleep_time|wake_up_time|update_weights_time|tflops|peak_gb|tok_per_s" "/tmp/bench_chunked_tp_122b_fused_seq${SEQ_CHUNK_SIZE}.log" || true
fi
