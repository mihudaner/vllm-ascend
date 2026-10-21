#!/usr/bin/env bash
set -euo pipefail

SCRIPT_DIR="$(cd "$(dirname "${BASH_SOURCE[0]}")" && pwd)"
source "${SCRIPT_DIR}/../config.sh"

visible_devices="$1"
vllm_engine_port="$2"
dp_size="$3"
dp_rank="$4"
dp_address="$5"
dp_rpc_port="$6"
tp_size="$7"

if [[ ! -d "${PREFILL_MODEL_PATH}" ]]; then
  printf 'Model path not found: %s\n' "${PREFILL_MODEL_PATH}" >&2
  exit 2
fi

unset https_proxy
unset http_proxy
export LD_LIBRARY_PATH="${LD_LIBRARY_PATH:-}:/usr/local/lib/"
local_ip="$(detect_local_ip)"
nic_name="$(detect_nic_name "${local_ip}")"
unset HOST_IP
export VLLM_HOST_IP="${VLLM_HOST_IP:-${local_ip}}"
export HCCL_IF_IP="${local_ip}"
export GLOO_SOCKET_IFNAME="${nic_name}"
export TP_SOCKET_IFNAME="${nic_name}"
export HCCL_SOCKET_IFNAME="${nic_name}"
export VLLM_RPC_TIMEOUT=3600000
export VLLM_EXECUTE_MODEL_TIMEOUT_SECONDS=30000
export HCCL_EXEC_TIMEOUT=204
export HCCL_CONNECT_TIMEOUT=120
export OMP_PROC_BIND=false
export OMP_NUM_THREADS=10
export PYTORCH_NPU_ALLOC_CONF=expandable_segments:True
export HCCL_BUFFSIZE=1024
export TASK_QUEUE_ENABLE=1
export HCCL_OP_EXPANSION_MODE="AIV"
export VLLM_ASCEND_ENABLE_FUSED_MC2=1
export VLLM_PREFIX_CACHE_RETENTION_INTERVAL=4096
export ASCEND_RT_VISIBLE_DEVICES="${visible_devices}"

kv_transfer_config="{\"kv_connector\":\"MooncakeHybridConnector\",\"kv_role\":\"kv_producer\",\"kv_port\":\"30000\",\"engine_id\":\"${local_ip}\",\"kv_connector_extra_config\":{\"prefill\":{\"dp_size\":${PREFILL_DP_SIZE},\"tp_size\":4,\"pp_size\":${PREFILL_PP_SIZE}},\"decode\":{\"dp_size\":${KV_DECODE_DP_SIZE},\"tp_size\":1}}}"
speculative_config="{\"num_speculative_tokens\": ${SPECULATIVE_TOKENS}, \"method\": \"${SPECULATIVE_METHOD}\", \"enforce_eager\": true}"

profile_dir="${PROFILE_ROOT:-${SCRIPT_DIR}/profiling}/${local_ip//./_}_${vllm_engine_port}"
profiler_config='{}'
if [[ -n "${profile_dir:-}" ]]; then
  mkdir -p "${profile_dir}"
  profiler_config="{\"profiler\":\"torch\",\"torch_profiler_dir\":\"${profile_dir}\"}"
fi

dp_args=()
if (( dp_size > 1 )); then
  dp_args=(
    --data-parallel-rank "${dp_rank}"
    --data-parallel-address "${dp_address}"
    --data-parallel-rpc-port "${dp_rpc_port}"
  )
fi

exec vllm serve "${PREFILL_MODEL_PATH}" \
  --host 0.0.0.0 \
  --port "${vllm_engine_port}" \
  --data-parallel-size "${dp_size}" \
  "${dp_args[@]}" \
  --tensor-parallel-size "${tp_size}" \
  --pipeline-parallel-size "${PREFILL_PP_SIZE}" \
  --enable-expert-parallel \
  --seed 1024 \
  --served-model-name "${SERVED_MODEL_NAME}" \
  --max-model-len 1048576 \
  --max-num-batched-tokens 8192 \
  --max-num-seqs 16 \
  --no-disable-hybrid-kv-cache-manager \
  --model-loader-extra-config '{"enable_multithread_load": true, "num_threads": 128}' \
  --speculative-config "${speculative_config}" \
  --trust-remote-code \
  --block-size 32 \
  --tokenizer-mode deepseek_v4 \
  --tool-call-parser deepseek_v4 \
  --enable-auto-tool-choice \
  --reasoning-parser deepseek_v4 \
  --gpu-memory-utilization 0.9 \
  --quantization ascend \
  --enforce-eager \
  --enable-prefix-caching \
  --profiler-config "${profiler_config}" \
  --additional-config '{
    "draft_window_size": 4096,
    "enable_cpu_binding": true,
    "enable_flashcomm1":true,
    "enable_dsa_cp": true,
    "enable_fused_mc2": true
  }' \
  --kv-transfer-config "${kv_transfer_config}"
