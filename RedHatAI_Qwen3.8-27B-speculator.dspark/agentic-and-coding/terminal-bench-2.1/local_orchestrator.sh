#!/usr/bin/env bash
# Local glue, specific to one server: venvs, GPUs, serve in background, eval, tear down.
# Treat this as a template and adapt paths/GPUs to your own environment.
#
# This host is shared: never touch the GPUs without a canhazgpu reservation. This script therefore
# refuses to run without CUDA_VISIBLE_DEVICES and tells you how to reserve. Launch it as:
#   canhazgpu run --gpus 4 --note "TB-2.1 DSpark spec-decode POC" -- ./local_orchestrator.sh --limit 2
# (or hold a manual reservation with `canhazgpu reserve` and export exactly the reserved GPU ids).
if [[ -z "${CUDA_VISIBLE_DEVICES:-}" ]]; then
  echo "CUDA_VISIBLE_DEVICES is not set. Reserve GPUs first, e.g.:" >&2
  echo "  canhazgpu run --gpus 4 -- ./local_orchestrator.sh \"\$@\"" >&2
  exit 1
fi
# serve.sh defaults to TP=4 x DP=1; refuse to start a server that needs more GPUs than were reserved.
TP="${TP:-4}"
DP="${DP:-1}"
NGPU=$(awk -F',' '{print NF}' <<< "$CUDA_VISIBLE_DEVICES")
if (( NGPU < TP * DP )); then
  echo "TP=$TP x DP=$DP needs $((TP * DP)) GPUs, but CUDA_VISIBLE_DEVICES=$CUDA_VISIBLE_DEVICES has $NGPU." >&2
  echo "Reserve more (canhazgpu run --gpus $((TP * DP)) -- ...) or lower TP." >&2
  exit 1
fi
# Rootless Docker (image store under ~/.local/share/docker); the rootful daemon lives on a 70 GB root disk.
# Its daemon.json sets a runc runtime with NoNewKeyring: non-root users get 200 kernel keys, one per container otherwise.
export DOCKER_HOST="${DOCKER_HOST:-unix:///run/user/$(id -u)/docker.sock}"
PORT="${PORT:-8000}"
mkdir -p logs

source ~/.venvs/vllm/bin/activate
# setsid: serve.sh and its vLLM workers get their own process group, so teardown can kill the whole
# tree. A bare `kill $SERVE_PID` only signals the launcher; EngineCore/Worker grandchildren survive
# and keep their GPU memory while canhazgpu has already released the reservation.
setsid ./serve.sh > logs/serve.log 2>&1 &
SERVE_PID=$!

wait_healthy() {
  until curl -sf "http://localhost:${PORT}/health" >/dev/null; do
    if ! kill -0 "$SERVE_PID" 2>/dev/null; then
      echo "vLLM server died during startup; see logs/serve.log" >&2
      tail -40 logs/serve.log >&2
      exit 1
    fi
    sleep 10
  done
}
wait_healthy

source ~/.venvs/inspect-harbor/bin/activate
./run_eval.sh "$@"
STATUS=$?

# Teardown: SIGKILL the whole process group (vLLM ignores SIGTERM and hangs), then wait until *our*
# GPUs really show 0 MiB before exiting, so canhazgpu's auto-release does not hand out GPUs that our
# own workers are still occupying. Only CUDA_VISIBLE_DEVICES is checked: this host is shared, so
# summing all 8 GPUs would never reach zero while other tenants hold the rest.
echo "teardown: killing vLLM process group $SERVE_PID"
kill -9 -- "-$SERVE_PID" 2>/dev/null || kill -9 "$SERVE_PID" 2>/dev/null || true
if command -v nvidia-smi >/dev/null 2>&1; then
  IFS=',' read -ra OUR_GPUS <<< "$CUDA_VISIBLE_DEVICES"
  for _ in $(seq 1 60); do
    busy=0
    for id in "${OUR_GPUS[@]}"; do
      m=$(nvidia-smi --id="$id" --query-gpu=memory.used --format=csv,noheader,nounits 2>/dev/null | tr -d ' ')
      [[ -n "$m" ]] && (( m > 0 )) && busy=1
    done
    (( busy == 0 )) && break
    sleep 2
  done
  echo "teardown: GPUs $CUDA_VISIBLE_DEVICES now hold: $(for id in "${OUR_GPUS[@]}"; do nvidia-smi --id="$id" --query-gpu=memory.used --format=csv,noheader | tr -d ' '; done | paste -sd' ')"
fi
exit "$STATUS"
