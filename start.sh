#!/usr/bin/env bash
# One-command launcher for the FedIT-FL experiments.
#
#   bash start.sh fetch-model    # download Qwen2.5-0.5B into model_cache/ (once, ~1 GB)
#   bash start.sh lr-probe       # no-attack runs at several learning rates (LRS), in parallel
#   bash start.sh pilot          # pilot: seed 42, IID + alpha=0.1, no attack + 30% attacks
#   bash start.sh full           # formal matrix: 4 partitions x 10 conditions x 3 seeds
#   bash start.sh full-parallel  # the same 120 runs, one process per partition at once
#   bash start.sh status         # show whether a run is active and the log tail
#   bash start.sh stop           # stop the active run (resume later with the same command)
#
# Every run scores all Shapley groupings on the same client updates: LLM
# knowledge units (primary), size-matched random units, native Dolly
# categories, random groups, TF-IDF clusters, and "global" (no classes).
# Runs in the background with nohup and logs to logs/<mode>_<time>.log.
# Re-running the same mode resumes: finished runs are skipped and an
# interrupted run continues from its last finished round.
#
# Environment overrides: FORCE_DEVICE (default cuda), SEEDS, TASKS,
# RESULTS_ROOT, PYTHON_BIN, PIP_INDEX_URL, MODEL_PATH, SHAPLEY_AXES (comma
# list, first = primary), EVAL_TOKEN_BUDGET.  FOREGROUND=1 runs in the terminal.
# LOCAL_LR: local learning rate (default 1e-4); any other value adds
# _lr<value> to the results folder, so runs of different rates never mix.
# GLOBAL_SIZE: rows of the global axis (default 480; 0 = no global axis; any
# other value adds _g<value> to the results folder).
# full-parallel: THREADS_PER_RUN (default: CPU cores / number of partitions).
set -euo pipefail
PROJECT_DIR="$(cd "$(dirname "$0")" && pwd)"
cd "$PROJECT_DIR"
MODE="${1:-pilot}"
LOG_DIR="$PROJECT_DIR/logs"
PID_FILE="$LOG_DIR/run.pid"
CURRENT="$LOG_DIR/current_logs.txt"   # logs of the most recent launch
mkdir -p "$LOG_DIR"

running() { [ -f "$PID_FILE" ] && kill -0 "$(cat "$PID_FILE")" 2>/dev/null; }
kill_tree() {   # stop a process and all of its descendants
    local child
    for child in $(pgrep -P "$1" 2>/dev/null || true); do kill_tree "$child"; done
    kill -TERM "$1" 2>/dev/null || true
}

export LOCAL_LR="${LOCAL_LR:-1e-4}"
case "$LOCAL_LR" in 1e-4|1e-04|0.0001) TAG="" ;; *) TAG="_lr$LOCAL_LR" ;; esac
if [ -n "${GLOBAL_SIZE:-}" ] && [ "$GLOBAL_SIZE" != 480 ]; then TAG="${TAG}_g$GLOBAL_SIZE"; fi
[ -z "${GLOBAL_SIZE:-}" ] || export GLOBAL_SIZE

case "$MODE" in
    status)
        if running; then echo "running (pid $(cat "$PID_FILE"))"; else echo "not running"; fi
        if [ -f "$CURRENT" ] && [ "$(wc -l < "$CURRENT")" -gt 1 ]; then
            while read -r log; do   # parallel launch: last progress lines per log
                echo "== $log"
                grep -E "round|done|skip|resume|Error|Traceback|failed|finished" "$log" \
                    2>/dev/null | tail -n 3 || true
            done < "$CURRENT"
        else
            LATEST="$(ls -t "$LOG_DIR"/*.log 2>/dev/null | head -1 || true)"
            [ -n "$LATEST" ] && { echo "== $LATEST"; tail -n 20 "$LATEST"; }
        fi
        if [ -f "$CURRENT" ] && grep -q lr-probe "$CURRENT"; then   # one log per rate
            for log in "${RESULTS_ROOT:-results/lr_probe}"/lr_*.log; do
                [ -f "$log" ] || continue
                echo "== $log"; grep -E "round|Error|Traceback" "$log" | tail -n 1 || true
            done
        fi
        exit 0 ;;
    stop)
        if running; then
            PID="$(cat "$PID_FILE")"
            kill_tree "$PID"
            echo "stopped pid $PID; run 'bash start.sh <mode>' again to resume"
        else
            echo "not running"
        fi
        rm -f "$PID_FILE"
        exit 0 ;;
    fetch-model) exec bash fetch_model.sh ;;
    pilot)    STEPS=(run_pilot.sh); export RESULTS_ROOT="${RESULTS_ROOT:-results/pilot$TAG}" ;;
    lr-probe) STEPS=(run_lr_probe.sh) ;;
    full)     STEPS=(run_full_experiments.sh); export RESULTS_ROOT="${RESULTS_ROOT:-results/full$TAG}" ;;
    full-parallel) STEPS=(); export RESULTS_ROOT="${RESULTS_ROOT:-results/full$TAG}" ;;
    -h|--help|help) sed -n 2,28p "$0"; exit 0 ;;
    *) echo "unknown mode: $MODE (fetch-model|lr-probe|pilot|full|full-parallel|status|stop)" >&2; exit 2 ;;
esac

if running; then
    echo "another run is active (pid $(cat "$PID_FILE")); use 'bash start.sh stop' first" >&2
    exit 1
fi

export FORCE_DEVICE="${FORCE_DEVICE:-cuda}"
EXTRA=()
if [ "$FORCE_DEVICE" = "cuda" ]; then EXTRA=(--require-cuda); fi
LOG="${FEDIT_LOG:-$LOG_DIR/${MODE}_$(date +%Y%m%d_%H%M%S).log}"
export FEDIT_LOG="$LOG"
PARALLEL_TASKS="${TASKS:-iid dirichlet:0.1 dirichlet:0.5 dirichlet:1.0}"
partition_dir() { case "$1" in iid) echo iid ;; dirichlet:*) a="${1#dirichlet:}"; echo "dirichlet_alpha${a//./p}" ;; esac; }

job() {
    for step in "${STEPS[@]}"; do
        echo "===== $(date '+%F %T') start $step ====="
        bash "$step" ${EXTRA[@]+"${EXTRA[@]}"} || { echo "===== $step failed; fix and rerun to resume ====="; return 1; }
        echo "===== $(date '+%F %T') finished $step ====="
    done
}

# full-parallel: one run_full_experiments.sh per partition, all at once on the
# same GPU.  Every run keeps its seed, partition and schedule, so results
# equal the sequential ones; only the combined workbook is merged at the end.
job_parallel() {
    local root="$RESULTS_ROOT"
    local count; count=$(echo $PARALLEL_TASKS | wc -w)
    local cores; cores=$(nproc 2>/dev/null || sysctl -n hw.ncpu)
    local threads="${THREADS_PER_RUN:-$(( cores / count > 1 ? cores / count : 1 ))}"
    echo "===== $(date '+%F %T') dependency and model check ====="
    bash run.sh --help > /dev/null || { echo "===== dependency setup failed ====="; return 1; }
    local pids=() task plog fail=0
    for task in $PARALLEL_TASKS; do
        plog="${LOG%.log}_$(partition_dir "$task").log"
        echo "$plog" >> "$CURRENT"
        echo "===== $(date '+%F %T') start $task ($threads CPU threads) -> $plog ====="
        TASKS="$task" PER_PARTITION_SUMMARY=1 SKIP_FINAL_SUMMARY=1 \
            bash run_full_experiments.sh ${EXTRA[@]+"${EXTRA[@]}"} --torch-threads "$threads" \
            > "$plog" 2>&1 &
        pids+=($!)
    done
    for pid in "${pids[@]}"; do wait "$pid" || fail=1; done
    echo "===== $(date '+%F %T') partitions finished (failures: $fail); merging ====="
    PYTHONPATH="$PROJECT_DIR/pip_pkgs${PYTHONPATH:+:$PYTHONPATH}" \
        "${PYTHON_BIN:-python3}" summarize.py --results-root "$root" || fail=1
    [ "$fail" = 0 ] || echo "===== some partition failed; check its log, then rerun to resume ====="
    return "$fail"
}

if [ "${FEDIT_DETACHED:-0}" = "1" ]; then   # the background copy of this script
    echo $$ > "$PID_FILE"
    trap 'rm -f "$PID_FILE"' EXIT
    if [ "$MODE" = full-parallel ]; then job_parallel; else job; fi
    exit $?
fi
echo "$LOG" > "$CURRENT"

if [ "${FOREGROUND:-0}" = "1" ]; then
    if [ "$MODE" = full-parallel ]; then job_parallel 2>&1 | tee "$LOG"; else job 2>&1 | tee "$LOG"; fi
    exit "${PIPESTATUS[0]}"
fi

# nohup first so SIGHUP is ignored before anything else happens, then setsid
# to leave the terminal / Jupyter kernel session; the run survives both.
LAUNCH=(nohup)
if command -v setsid >/dev/null 2>&1; then LAUNCH=(nohup setsid); fi
FEDIT_DETACHED=1 "${LAUNCH[@]}" bash "$PROJECT_DIR/start.sh" "$MODE" > "$LOG" 2>&1 < /dev/null &
sleep 5
if running; then
    echo "started $MODE (pid $(cat "$PID_FILE"), device $FORCE_DEVICE, LOCAL_LR=$LOCAL_LR)"
    echo "log:    tail -f $LOG"
    if [ "$MODE" = full-parallel ]; then
        echo "        one log per partition: ${LOG%.log}_<partition>.log"
    fi
    [ -z "${RESULTS_ROOT:-}" ] || echo "results: $RESULTS_ROOT"
    echo "status: bash start.sh status    stop: bash start.sh stop"
else
    echo "the run stopped right after starting; log follows:" >&2
    cat "$LOG" >&2
    exit 1
fi
