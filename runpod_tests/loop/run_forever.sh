#!/bin/bash
# run_forever.sh — autonomous experiment loop launcher
#
# Usage:
#   nohup bash runpod_tests/loop/run_forever.sh > runpod_tests/loop/run_forever.out 2>&1 &
#
# Kills any existing train_gpt.py / experiment_runner before taking over the GPU.
# Wraps the runner in an infinite restart loop — if Python dies for any reason,
# we sleep 5s and relaunch. No external cron/watchdog needed.

set -u
cd /workspace/paramgolf

# preflight() — branch hygiene + dirty-tree restore + GPU util sampler launch.
# Called at the top of every loop iteration so the campaign self-heals from:
#   - wrong-branch checkouts (the sota-prikshit-hymba11-muon regression)
#   - dirty trees from prior failed patcher runs
#   - missing gpu_util.log sampler (needed by Gate G2)
preflight() {
    # 1. Branch must be main
    BR=$(git branch --show-current 2>/dev/null || echo "?")
    if [ "$BR" != "main" ]; then
        echo "PREFLIGHT_WARN: branch=$BR expected=main — checking out main"
        git checkout main 2>&1 | tail -3 || true
    fi

    # 2. Restore train_gpt.py from backup if available (patcher will reapply)
    if [ -f train_gpt.py.bak ]; then
        cp train_gpt.py.bak train_gpt.py
    fi

    # 3. Launch the GPU util sampler if not already running.
    # Single long-lived process via PID file so we don't fork-bomb across loop cycles.
    PIDFILE=runpod_tests/loop/gpu_util.pid
    if [ ! -f "$PIDFILE" ] || ! kill -0 "$(cat "$PIDFILE" 2>/dev/null)" 2>/dev/null; then
        nohup nvidia-smi --query-gpu=utilization.gpu,memory.used \
            --format=csv,noheader -l 5 \
            >> runpod_tests/loop/gpu_util.log 2>/dev/null &
        echo $! > "$PIDFILE"
        echo "PREFLIGHT: launched gpu_util sampler pid=$(cat $PIDFILE)"
    fi

    # 4. Launch the CPU worker pool if not already running.
    # Addresses PD8 (max out CPU+RAM alongside GPU). Workers consume jobs from
    # data/cpu_jobs/pending/ and write results to data/cpu_jobs/done/. Idempotent
    # via PID file. Job emitter runs once per loop iter to top up the queue.
    CPU_PIDFILE=runpod_tests/loop/cpu_workers.pid
    if [ ! -f "$CPU_PIDFILE" ] || ! kill -0 "$(cat "$CPU_PIDFILE" 2>/dev/null)" 2>/dev/null; then
        nohup python3 -u runpod_tests/loop/cpu_workers.py \
            >> runpod_tests/loop/cpu_workers.log 2>&1 &
        sleep 1
        echo "PREFLIGHT: launched cpu_workers (pidfile=$CPU_PIDFILE)"
    fi
    # Top up the job queue every loop iteration (cheap, idempotent).
    python3 runpod_tests/loop/cpu_jobs_emitter.py 2>&1 | tail -3 || true
}

# Take over the GPU (only kill OTHER experiment_runner instances)
ME=$$
for pid in $(pgrep -f experiment_runner.py 2>/dev/null); do
    [ "$pid" != "$ME" ] && kill "$pid" 2>/dev/null || true
done
pkill -f 'python3 train_gpt.py' 2>/dev/null || true
sleep 2

mkdir -p runpod_tests/loop/logs
echo "=== run_forever launched at $(date -u) PID=$ME ==="

while true; do
    # PD5: pre-flight branch + tree + GPU sampler before pulling code.
    preflight
    # Auto-pull latest experiments / runner code before each restart.
    # --autostash because the patcher modifies train_gpt.py locally.
    git pull --rebase --autostash 2>&1 | tail -3 || true
    # Restore train_gpt.py from backup so patcher applies cleanly even after
    # the patcher itself was edited. The patcher is idempotent within a run
    # but doesn't auto-upgrade old patches when the upstream patcher source changes.
    if [ -f train_gpt.py.bak ]; then
        cp train_gpt.py.bak train_gpt.py
    fi
    bash runpod_tests/chore/08_patch_train_gpt.sh 2>&1 | tail -20 || true
    python3 -u runpod_tests/loop/experiment_runner.py
    echo "=== runner exited with code $? at $(date -u) — restart in 5s ==="
    sleep 5
done
