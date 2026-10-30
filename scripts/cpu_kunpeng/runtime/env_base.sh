# Copyright 2026 Huawei Technologies Co., Ltd.
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.
# ==============================================================================

#!/bin/bash
# Base environment setup for env.sh: configuration variables, local config
# loading (.user_env.sh) and role-dependent defaults.
# This file is sourced by env.sh and should not be used directly.

SCRIPT_DIR="$(cd "$(dirname "${BASH_SOURCE[0]}")/.." && pwd)"

# Source helper functions (expand_ip_range, per-role config functions, etc.)
source "$SCRIPT_DIR/runtime/env_helper.sh"

# ------------------------------------------------------------
# Configuration variables (edit these as needed)
# ------------------------------------------------------------
# Deployment instances for `launch.sh all`: comma-separated entries, each
# "<role>" or "<role>_<instance>". Multiple entries per role are supported
# (e.g. "prefill,decode_64p,decode_64p_2"): each entry starts one server
# group via `launch_cluster.sh <role> [instance]`, one tokenizer HTTP
# server, and one gateway backend; the instance suffix selects
# per-instance user env overrides (runtime/.user_env_<role>_<instance>.sh),
# e.g. "decode_64p" reads .user_env_decode_64p.sh on every node.
# Each entry's router-node resources are auto-derived from its position
# in this list (see env_prefill.sh / env_decode.sh):
#   tokenizer HTTP port     30001 + global entry index
#   prefill bootstrap port  9001 + prefill entry index
#   tokenizer NUMA block    prefill entries: 0,4,...  decode entries: 8,12,...
#   master port             prefill: 5000+100*i, decode: 5010+100*i (the
#                           tokenizer's ZMQ port block is derived from it)
# (instance env files may still override TOK_PORT / BOOTSTRAP_PORT /
# NUMA_BASE / MASTER_PORT explicitly). Instances of the same role must run
# on disjoint node sets (stop_server.sh kills all sglang processes on an
# instance's nodes).
INSTANCES="prefill,decode"


# Router node IP (single IP for PD disaggregation router)
export ROUTER_IP="xxx.xxx.xxx.1"

# Gateway prefill routing policy (PD mode). Empty = use the main policy
# (cache_aware). Set to "bucket" to enable the bucket policy for prefill
# backends — requires >= 2 prefill entries in INSTANCES (e.g.
# "prefill,prefill_lc,decode"): the gateway sizes request buckets per
# prefill worker and rebalances them periodically.
export ROUTER_PREFILL_POLICY=""
# Bucket-policy tuning knobs (used only when ROUTER_PREFILL_POLICY=bucket):
export ROUTER_BALANCE_ABS_THRESHOLD=64
export ROUTER_BALANCE_REL_THRESHOLD=1.5
export ROUTER_BUCKET_ADJUST_INTERVAL_SECS=5
# Grouped mode (fixed short/long routing, used only when
# ROUTER_PREFILL_SHORT_COUNT > 0): requests shorter than the character
# threshold go to the first SHORT_COUNT prefill backends (by ascending
# backend URL = tokenizer port order in INSTANCES), longer ones to the
# rest. Leave SHORT_COUNT=0 for dynamic-boundary mode. Note the threshold
# counts CHARACTERS, not tokens (~1.5-2 chars/token Chinese).
export ROUTER_PREFILL_SHORT_COUNT=0
export ROUTER_PREFILL_LENGTH_THRESHOLD=4096

# Paths
LOG_BASE_DIR="/path-to-logs"
CONDA_ENV_NAME="my_env"
CONDA_BASE_PATH="/path-to-conda"
MODEL_PATH="/path-to-deepseek-r1-channel-int8"
SPECULATIVE_DRAFT_MODEL_PATH="/path-to-deepseek-r1-channel-int8_mtp"

export HPCKIT_PATH="/path-to-HPCKit"
export OpenBLAS_PATH="/path-to-OpenBLAS"
export KUPL_PATH="/path-to-KUPL"
export KUTACC_PATH="/path-to-KUTACC"
export SGLANG_PATH="/path-to-SGLang"
export DATASET_PATH="/path-to-dataset"
# Required when SGLANG_ENABLE_TOKENIZER_SEPERATE=1 (used by tokenizer-side HTTP servers)
export LIBPTHREAD_HOOK_PATH="/path/to/libpthread_hook.so"
# Kunpeng SDMA driver
export SDMA_KO_PATH="/path-to-sdma-ko"
# Required when SGLANG_ENABLE_KUCCL=1
export KUCCL_PATH="/path-to-KUCCL"

# Native TP/EP size
export TP_SIZE=256
export DP_SIZE=16
export EP_SIZE=${TP_SIZE}
export PP_SIZE=1  # >1 enable pp  eg: 2
export REDUNDANT_EXPERTS=0
export INIT_EXPERT_LOCATION=""
export EP_DISPATCH_ALGORITHM=""  # e.g. static, dynamic
# Dynamic redundant-expert remap shuffle mode: 0 = round-robin, 1 = random
export SGLANG_KUNPENG_MOE_SHUFFLE_MODE=0


# Communication
export GLOO_SOCKET_IFNAME=enp26s0f0
export MV2_COMM_WORLD_LOCAL_SIZE=16

# Thread
export OMP_NUM_THREADS=1
export OMP_PROC_BIND=false
export RAYON_NUM_THREADS=1
export KUPL_EXECUTOR_BACKEND=pthread
export KUPL_EXECUTOR_COUNT=33  # set to 32 when KUTACC_ASYNC_LAUNCH=0
export KUTACC_ASYNC_LAUNCH=1  # requires kutacc built from https://gitcode.com/zhengzhong722/kutacc/tree/br_sglang
export TORCH_COMPILE_DISABLE=1
export SGLANG_DISAGGREGATION_THREAD_POOL_SIZE=4
export SGLANG_SET_ZMQ_CPU_AFFINITY_OFFSET=18

# SGLang
export SGLANG_LOG_MS=1
export SGLANG_USE_CPU_ENGINE=1
export SGLANG_SET_CPU_AFFINITY=1
export SGLANG_ENABLE_TP_MEMORY_INBALANCE_CHECK=0
export SGLANG_WARMUP_TIMEOUT=1600
export PYTHONWARNINGS="ignore::FutureWarning"
export SGLANG_DISAGGREGATION_WAITING_TIMEOUT=1200
export SGLANG_DISAGGREGATION_BOOTSTRAP_TIMEOUT=1200
export SGLANG_SCHEDULER_SKIP_ALL_GATHER=0 # WARNING: Setting SGLANG_SCHEDULER_SKIP_ALL_GATHER=1 can affect correctness in long-prompt prefill.

# Kunpeng CPU
export SGLANG_USE_CPU_920F=1
export TOKENIZER_WORKER_NUM=1
export SGLANG_KUNPENG_PROFILE=0
export SGLANG_KUNPENG_PP_PROFILE=0  # 1 = enable decode pipeline profiling
export SGLANG_KUNPENG_DECODE_PROFILE=0  # 1 = per-step pp_perf timing for the decode loop
export SGLANG_KUNPENG_PREFILL_PROFILE=0  # 1 = flat pp_perf timing for each prefill forward
export SGLANG_KUNPENG_DRAFT_GRAPH_CAPTURE=0  # 1 = capture the attached MTP draft decode chain
export SGLANG_ENABLE_BINARY_LAUNCH=1
export SGLANG_ENABLE_NUMA_DUPLICATION=1
export SGLANG_KUNPENG_DISABLE_MLA_ALL2ALL=0
export SGLANG_KUNPENG_ALLTOALL_FENCE=0  # 1 = explicit kupl_shm_fence after MLA shm alltoall
export SGLANG_KUNPENG_ALLREDUCE_NAIVE=0  # 1 = non-kutacc naive shm allreduce
export SGLANG_KUNPENG_LC_DP_RANKS=""  # comma-separated DP ranks running long-context decode CP (e.g. "14,15"); empty = all regular; must be identical between prefill and decode instances
export SGLANG_KUNPENG_LC_MIN_SEQ_LEN=4096  # requests with input_len + max_new_tokens >= this go to LC DP ranks; must exceed every regular rank's max_req_input_len
export SGLANG_KUNPENG_RDMA_ALLGATHER=1  # requires kutacc built from https://gitcode.com/zhengzhong722/kutacc/tree/sglang_930
export SGLANG_KUNPENG_RDMA_BCAST=1  # requires kutacc built from https://gitcode.com/zhengzhong722/kutacc/tree/sglang_930
export SGLANG_KUNPENG_RDMA_PP_COMM=1  # 1 = enable RDMA communication between PP ranks for rids
export SGLANG_KUNPENG_PP_LAYOUT=0  # PP layout: 0 = node_block (a node maps to one PP stage, legacy); 1 = interleave (every node hosts all PP stages: rin 0..7 -> PP0, 8..15 -> PP1).
export SGLANG_KUNPENG_MOE_FORCE_LOAD_BALANCE=0  # 1 = forced MoE load balancing (perf-test only, correctness not preserved)
# SGLANG_KUNPENG_DEBUG_EXPERT_LOAD=1  # build-time only: set before building sgl-kernel to enable expert load debug recording
export SGLANG_ENABLE_MTP=0
export SGLANG_DISABLE_RADIX_CACHE=0  # 1 = append --disable-radix-cache to server args
export SGLANG_ENABLE_OVERLAP=0
export SGLANG_ENABLE_OVERLAP_TRACE=0
export SGLANG_ENABLE_KUCCL=0  # set to 1 to use kuccl backend instead of gloo
# Kunpeng SHM pool
export SGLANG_KUNPENG_ENABLE_SHM_FENCE=0
export KUPL_SHM_TYPE=sls
export KUPL_SHM_ON_PACKAGE=y  # requires kupl built from https://gitcode.com/kunpengcompute/kupl/tree/sglang_830
export KUPL_SHM_ENABLE_HUGEPAGE=y


# Kunpeng HBW pool
export SGLANG_ENABLE_HBW_POOL=1
export SGLANG_KUNPENG_MEMORY_ALIGNMENT=4096
export SGLANG_KUNPENG_WEIGHTS_HBW_POOL_SIZE_MB=3400
export SGLANG_KUNPENG_HBW_RESIDENT_NON_EXPERT_WEIGHTS=1
export SGLANG_KUNPENG_HBW_RESIDENT_EXPERT_WEIGHTS=0
export SGLANG_KUNPENG_HBW_RESIDENT_GRAPH=1
export SGLANG_KUNPENG_SWAP_EXPERT=0
export SGLANG_KUNPENG_SWAP_KV_IN=0
export SGLANG_KUNPENG_SWAP_KV_OUT=0
export SGLANG_KUNPENG_SWAP_KV_BLOCKWISE=0
export SGLANG_KUNPENG_SWAP_MAX_KV_BLOCKS=512


# Kunpeng SDMA parameters
export SGLANG_KUNPENG_SDMA_MAX_EVENTS=10
export SGLANG_KUNPENG_SDMA_THRESHOLD=5
# Kunpeng graph capture
export SGLANG_ENABLE_GRAPH_CAPTURE=1
export SGLANG_KUNPENG_GRAPH_CACHE_SIZE=10
export SGLANG_KUNPENG_EXTEND_POWER_2_PADDING=1 # Kunpeng prefill graph padding to power 2 size
export SGLANG_GRAPH_DEBUG_PRINT=0  # 1 = per-op debug print in eager/capture (ops.py) and graph replay (C++)
# Load format (e.g. "kunpeng_state", leave empty for default)
export LOAD_FORMAT=""
# Chat template / parsers: model-specific, opt-in. server.sh only passes
# the flag when the variable is non-empty — set them in .user_env*.sh for
# models that need them (e.g. DeepSeek-R1:
#   CHAT_TEMPLATE="$SGLANG_PATH/examples/chat_template/tool_chat_template_deepseekr1.jinja"
#   TOOL_CALL_PARSER=deepseekv3
#   REASONING_PARSER=deepseek-r1).
export CHAT_TEMPLATE=""
export TOOL_CALL_PARSER=""
export REASONING_PARSER=""
# Drop OS page cache (echo 3 > /proc/sys/vm/drop_caches) during stop.sh node
export DROP_CACHES=0
# Tokenizer-side cross-process batch timeline logging
export SGLANG_TOKENIZER_TIMELINE_LOG=0
# Scheduler stream interval (--stream-interval): flush a request's output every N tokens
export STREAM_INTERVAL=1
# Tokenizer backend: "huggingface" (default) or "fastokens" (fastokens requires transformers >= 5.12)
export SGLANG_TOKENIZER_BACKEND="huggingface"
# Tokenizer-separate mode: on by default for PD roles (prefill/decode/router), off for native.
# .user_env.sh can still override.
if [[ "${1:-native}" == "native" ]]; then
    export SGLANG_ENABLE_TOKENIZER_SEPERATE=0
else
    export SGLANG_ENABLE_TOKENIZER_SEPERATE=1
fi

export SGLANG_KUNPENG_MOE_TOKEN_MULTIPLE=2
export SGLANG_KUNPENG_SAVE_AT_TRACE=0 # set 1 to open record experts activation number
# ------------------------------------------------------------
# Load local config
# ------------------------------------------------------------
USER_ENV_ROLE="${1:-native}"

case "$USER_ENV_ROLE" in
    decode|router|tokenizer|mooncake|store) IS_PREFILL=0 ;;
    *) IS_PREFILL=1 ;;
esac
export IS_PREFILL

if [[ -f "$SCRIPT_DIR/.user_env.sh" ]]; then
    source "$SCRIPT_DIR/.user_env.sh" "$USER_ENV_ROLE"
fi

if [[ -f "$SCRIPT_DIR/runtime/.user_env_base.sh" ]]; then
    source "$SCRIPT_DIR/runtime/.user_env_base.sh" "$USER_ENV_ROLE"
fi

# ------------------------------------------------------------
# Derived paths, resolved after the user env files above so that both the
# inputs (CONDA_BASE_PATH / CONDA_ENV_NAME / SGLANG_PATH) and the derived
# values themselves can be overridden there: unset -> default, user-set wins.
# ------------------------------------------------------------
export CONDA_ENV_PATH="${CONDA_ENV_PATH:-$CONDA_BASE_PATH/envs/$CONDA_ENV_NAME}"
export PYINSTALL_PATH="${PYINSTALL_PATH:-$SGLANG_PATH/scripts/cpu_kunpeng/pyinstall}"
export GEMM_TILING_PLAN_FILE="${GEMM_TILING_PLAN_FILE:-$SGLANG_PATH/scripts/cpu_kunpeng/configs/gemm_32_tiling.csv}"

# ------------------------------------------------------------
# Mooncake master address (KUNPENG_HICACHE_BACKEND=mooncake). Resolved after
# .user_env.sh so an override there wins. Defaults to the router node, which is
# outside the prefill/decode node sets. This address is read by BOTH the master
# process and the prefill/native *clients* (mooncake_store.py), so it has to be
# visible to every role -- hence env_base.sh. The store-only knobs
# (STORE_NODE/PORT/SEGMENT_SIZE) live in runtime/env_store.sh.
# ------------------------------------------------------------
export MOONCAKE_MASTER_NODE="${MOONCAKE_MASTER_NODE:-$ROUTER_IP}"
export MOONCAKE_MASTER_PORT="${MOONCAKE_MASTER_PORT:-50061}"
export MOONCAKE_MASTER="${MOONCAKE_MASTER:-$MOONCAKE_MASTER_NODE:$MOONCAKE_MASTER_PORT}"

# RDMA device(s) for the transfer engine clients and the store service, plus the
# client's own hostname so the master can address it. Both are per-node, so they
# belong here (every role picks them up) rather than in a role file; env_store.sh
# still overrides the hostname for the store role.
export MOONCAKE_DEVICE="${MOONCAKE_DEVICE:-roceroh0,roceroh3,roceroh4,roceroh7}"
export MOONCAKE_LOCAL_HOSTNAME="${MOONCAKE_LOCAL_HOSTNAME:-$(ifconfig enp26s0f0 2>/dev/null | grep -oP '(?<=inet\s)\d+(\.\d+){3}')}"

# SSD offload is opt-in. Off by default keeps the DRAM-only store unchanged.
# When on, MOONCAKE_OFFLOAD_FILE_STORAGE_PATH must be set (see env_store.sh).
export MOONCAKE_ENABLE_SSD_OFFLOAD="${MOONCAKE_ENABLE_SSD_OFFLOAD:-0}"
export MOONCAKE_OFFLOAD_ON_EVICT="${MOONCAKE_OFFLOAD_ON_EVICT:-0}"
