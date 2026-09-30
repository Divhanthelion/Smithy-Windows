#!/usr/bin/env bash
# Smithy's launch of Qwen3.8-Flash-Next on a Jetson AGX Thor.
#
# Adapted from serving/start-qwen38-flash-next-fast.sh in NemoClaw-Thor
# (https://github.com/pastoriomarco/NemoClaw-Thor, commit dd07dcc), which is
#   MIT License. Copyright (c) 2026 JetsonHacks. Copyright (c) 2026 Marco Pastorio.
# Build the image and prepare the FP8-hybrid snapshot with that repository first
# (see thor/THOR.md); this script only starts the server.
#
# What differs from the original: the defaults below (FP8-hybrid checkpoint:
# +19-27% decode, -2.7 GiB; port 8000, three slots, 256k, 0.75 memory,
# detached, container "flash-next"), per-request cache reporting
# (--enable-prompt-tokens-details), and a fixed-size KV cache
# (FLASHNEXT_KV_GIB, default 8 = ~290k tokens) rather than what is left of
# FLASHNEXT_GPU_MEM: on the Thor, CUDA counts page cache as used, so after
# reading 126 GB of weights the fraction-based budget came out at -0.71 GiB.
#
# FLASHNEXT_NO_RM=1 keeps a stopped container (and its logs); pass a new
# FLASHNEXT_CONTAINER name to start again while an old one still exists.
cd "${NEMOCLAW_DIR:-$HOME/NemoClaw-Thor}"
export FLASHNEXT_MODEL_REV=${FLASHNEXT_MODEL_REV:-7b719225242aacd3dbd3f9407468c2ee9a9d2594-fp8hybrid}
export FLASHNEXT_PORT=${FLASHNEXT_PORT:-8000} FLASHNEXT_MAX_SEQS=${FLASHNEXT_MAX_SEQS:-3} FLASHNEXT_CONTEXT=${FLASHNEXT_CONTEXT:-262144}
export FLASHNEXT_KV_GIB=${FLASHNEXT_KV_GIB:-8}
export FLASHNEXT_GPU_MEM=${FLASHNEXT_GPU_MEM:-0.75} FLASHNEXT_DETACH=${FLASHNEXT_DETACH:-1} FLASHNEXT_CONTAINER=${FLASHNEXT_CONTAINER:-flash-next}
# Thin, offline launcher for the separately built Thor fast-path image.
# Does not replace an existing named container. By default, this container is
# removed automatically after it exits. See docs/QWEN38-FLASH-NEXT-FAST-THOR.md.
set -euo pipefail
HF_CACHE=${HF_CACHE:-$HOME/thor-hf-cache}
VLLM_CACHE=${VLLM_CACHE:-$HOME/thor-vllm-cache}
TORCH_CACHE=${TORCH_CACHE:-$HOME/thor-torch-cache}
FLASHINFER_CACHE=${FLASHINFER_CACHE:-$HOME/thor-flashinfer-cache}
FLASHNEXT_IMAGE=${FLASHNEXT_IMAGE:-nemoclaw-thor/qwen38-flash-next-vllm:sm110-fast-v3}
FLASHNEXT_BASE_REV=${FLASHNEXT_BASE_REV:-7b719225242aacd3dbd3f9407468c2ee9a9d2594}
FLASHNEXT_MODEL_REV=${FLASHNEXT_MODEL_REV:-${FLASHNEXT_BASE_REV}-fp8hybrid}
FLASHNEXT_CONTAINER=${FLASHNEXT_CONTAINER:-qwen38-flash-next-fast-v3-fp8hybrid}
FLASHNEXT_PORT=${FLASHNEXT_PORT:-8050}
FLASHNEXT_MTP=${FLASHNEXT_MTP:-3}
FLASHNEXT_GPU_MEM=${FLASHNEXT_GPU_MEM:-0.90}
FLASHNEXT_KV=${FLASHNEXT_KV:-auto}
FLASHNEXT_GDN=${FLASHNEXT_GDN:-cuda}
FLASHNEXT_SSM_CACHE=${FLASHNEXT_SSM_CACHE:-bfloat16}
FLASHNEXT_DRAFT_VOCAB=${FLASHNEXT_DRAFT_VOCAB:-/opt/llm/draft_vocab_code_47149.npy}
FLASHNEXT_MAX_SEQS=${FLASHNEXT_MAX_SEQS:-3}
FLASHNEXT_CONTEXT=${FLASHNEXT_CONTEXT:-262144}
model_rel="hub/models--RadixArk--Qwen3.8-Flash-Next-NVFP4/snapshots/$FLASHNEXT_MODEL_REV"
test -s "$HF_CACHE/$model_rel/config.json" || {
    echo "Local model snapshot missing: $HF_CACHE/$model_rel" >&2; exit 1;
}
hybrid_env=()
if [[ "$FLASHNEXT_MODEL_REV" == *-fp8hybrid* ]]; then
    test -f "$HF_CACHE/$model_rel/.prepared" || {
        echo "FP8-hybrid snapshot is incomplete (missing .prepared): $HF_CACHE/$model_rel" >&2
        exit 1
    }
    # Dispatch converted dense side layers through vLLM's blockwise-FP8 path.
    # DeepGEMM is not the supported FP8 backend on Jetson Thor (SM110).
    hybrid_env=(-e VLLM_FP8_HYBRID=1 -e VLLM_USE_DEEP_GEMM=0)
fi
mkdir -p "$VLLM_CACHE" "$TORCH_CACHE" "$FLASHINFER_CACHE"
split_ops='["vllm::unified_attention_with_output","vllm::unified_mla_attention_with_output","vllm::mamba_mixer2","vllm::mamba_mixer","vllm::short_conv","vllm::qwen3_8_flash_next_ple_short_conv","vllm::qwen3_8_flash_next_qsa_with_output","vllm::linear_attention","vllm::qwen_gdn_attention_core","vllm::qwen_gdn_attention_core_fused_norm_packed","vllm::sparse_attn_indexer","vllm::ple_mmap_lookup"]'
run_mode=(-it)
if [[ ${FLASHNEXT_DETACH:-0} == 1 ]]; then run_mode=(-d); fi
docker_rm=(--rm)
if [[ ${FLASHNEXT_NO_RM:-0} == 1 ]]; then docker_rm=(); fi
exec docker run "${run_mode[@]}" "${docker_rm[@]}" --pull never \
    --name "$FLASHNEXT_CONTAINER" --runtime nvidia --gpus all \
    --ipc host --network host --shm-size 16g \
    -v "$HF_CACHE:/hf" -v "$VLLM_CACHE:/root/.cache/vllm" \
    -v "$TORCH_CACHE:/root/.cache/torch" -v "$FLASHINFER_CACHE:/root/.cache/flashinfer" \
    -e HF_HOME=/hf -e HF_HUB_OFFLINE=1 \
    "${hybrid_env[@]}" \
    -e VLLM_DISABLE_COMPILE_CACHE=1 -e VLLM_USE_AOT_COMPILE=1 \
    -e CUTE_DSL_ARCH=sm_110a -e TORCH_CUDA_ARCH_LIST=11.0a \
    -e VLLM_PLE_MMAP=1 -e VLLM_PLE_MMAP_WORKERS=14 -e VLLM_PLE_MMAP_PREWARM=0 \
    -e VLLM_PLE_MMAP_MADV_RANDOM="${VLLM_PLE_MMAP_MADV_RANDOM:-1}" \
    -e VLLM_PLE_MMAP_FAST_ROWS="${VLLM_PLE_MMAP_FAST_ROWS:-0}" \
    -e VLLM_PLE_MMAP_PREFETCH="${VLLM_PLE_MMAP_PREFETCH:-1}" \
    -e VLLM_PLE_MMAP_PREFETCH_MIN_ROWS="${VLLM_PLE_MMAP_PREFETCH_MIN_ROWS:-512}" \
    -e VLLM_QSA_DET_TOPK=1 -e VLLM_QSA_DET_LIB=/opt/llm/kernel-det/_C_det.so \
    -e VLLM_QSA_EXACT_TOPK=0 -e VLLM_USE_FLASHINFER_SAMPLER=1 \
    -e VLLM_GDN_DECODE_KERNEL="$FLASHNEXT_GDN" \
    -e VLLM_MTP_DRAFT_VOCAB="$FLASHNEXT_DRAFT_VOCAB" \
    --entrypoint vllm "$FLASHNEXT_IMAGE" serve "/hf/$model_rel" \
    --served-model-name qwen3.8-flash-next --host 0.0.0.0 --port "$FLASHNEXT_PORT" \
    --load-format safetensors --max-model-len "$FLASHNEXT_CONTEXT" \
    --max-num-seqs "$FLASHNEXT_MAX_SEQS" --gpu-memory-utilization "$FLASHNEXT_GPU_MEM" \
    --kv-cache-memory-bytes "$((FLASHNEXT_KV_GIB * 1024 * 1024 * 1024))" \
    --enable-prefix-caching --enable-chunked-prefill --max-num-batched-tokens 8192 \
    -cc.cudagraph_mode=PIECEWISE "-cc.splitting_ops=$split_ops" \
    --no-enable-flashinfer-autotune --moe-backend flashinfer_cutlass \
    --mamba-ssm-cache-dtype "$FLASHNEXT_SSM_CACHE" \
    --kv-cache-dtype "$FLASHNEXT_KV" --enable-auto-tool-choice \
    --tool-call-parser qwen3_coder --reasoning-parser qwen3 \
    --enable-prompt-tokens-details \
    --speculative-config "{\"method\":\"mtp\",\"num_speculative_tokens\":$FLASHNEXT_MTP}"
