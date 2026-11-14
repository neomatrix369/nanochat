"""Modal app: nanochat on Modal, in one of two modes.

  --mode cpu (default): runs/runcpu.sh on a heavy CPU machine (no GPU, no payment gate).
  --mode gpu:           runs/speedrun.sh on 8×H100 (needs a GPU payment method).

Both modes: prefetch dataset shards to the Volume, train with wait-for-ack commits,
then download tokenizer + chat checkpoints to the local machine.

CRITICAL: Do not import nanochat.dataset at module level (binds DATA_DIR at import time).
Set NANOCHAT_BASE_DIR in environment before any python -m calls.
"""

import json
import os
import resource
import subprocess
import threading
import time

import modal
from modal_stats import parse_memory_max, summarize_run

# ─────────────────────────────────────────────────────────────────────────────
# Modal app, Volume and sizing

app = modal.App(name="nanochat-speedrun")

# Shared Volume: mounted at BASE_DIR (= NANOCHAT_BASE_DIR on Modal)
BASE_DIR = "/data/nanochat-modal"
vol = modal.Volume.from_name("nanochat-modal", create_if_missing=True)

PREFETCH_TIMEOUT = 2 * 60 * 60
PREFETCH_SHARDS_GPU = 170  # speedrun.sh needs ~170 shards
PREFETCH_SHARDS_CPU = 8  # runcpu.sh needs 8 shards
GPU_TRAIN_TIMEOUT = 4 * 60 * 60
CPU_TRAIN_TIMEOUT = 3 * 60 * 60
CPU_CORES = 64  # heavy machine: CPU mode is meant to use every core the account allows
CPU_MEMORY_MIB = 131072  # 128 GiB

# GPU functions are only defined in GPU mode. Modal checks every function in the app at
# start-up, so a GPU function in a CPU run fails the whole run (H100 payment gate).
MODAL_MODE = os.environ.get("NANOCHAT_MODAL_MODE", "cpu")


def _nanochat_image(extra: str) -> modal.Image:
    """Image with the uv-synced deps for one extra (gpu or cpu). Local source is the last layer."""
    return (
        modal.Image.debian_slim(python_version="3.11")
        .pip_install("uv")
        .add_local_file("pyproject.toml", remote_path="/root/nanochat/pyproject.toml", copy=True)
        .add_local_file("uv.lock", remote_path="/root/nanochat/uv.lock", copy=True)
        .run_commands(f"cd /root/nanochat && uv sync --no-install-project --extra {extra} --frozen")
        .env(
            {
                "PATH": "/root/nanochat/.venv/bin:/usr/local/bin:/usr/bin:/bin",
                "PYTHONPATH": "/root/nanochat",
                "NANOCHAT_MODAL_MODE": extra,  # gates GPU function definitions in containers too
            }
        )
        # Local source is the LAST layer: Modal rejects build steps after add_local_*.
        .add_local_dir(
            ".",
            remote_path="/root/nanochat",
            ignore=[".venv", ".git", "**/.pytest_cache", "**/__pycache__"],
        )
    )


image = _nanochat_image("gpu")  # GPU mode (speedrun)
image_cpu = _nanochat_image("cpu")  # CPU mode (runcpu), CPU torch wheels, no CUDA

# ─────────────────────────────────────────────────────────────────────────────
# Environment helpers


def _modal_env(base_dir: str) -> dict[str, str]:
    """Build the Modal environment dict for subprocess calls."""
    return {
        "NANOCHAT_BASE_DIR": base_dir,
        "HF_HOME": os.path.join(base_dir, "hf_home"),
        "SKIP_SETUP": "1",
        "NANOCHAT_POST_STAGE_HOOK": "bash /root/nanochat/runs/modal_hook.sh",
        "PYTHONPATH": "/root/nanochat",
    }


def _available_cores() -> int:
    """Cores this container may use (respects cgroup/affinity limits, not the host count)."""
    return len(os.sched_getaffinity(0))


# ─────────────────────────────────────────────────────────────────────────────
# Wait-for-ack daemon (runs in background during a training function)


def _commit_daemon(volume: modal.Volume, base_dir: str) -> None:
    """
    Daemon thread: watch for commit requests, run vol.commit(), update heartbeat.

    Protocol:
    - On .modal_commit_request file: write heartbeat, run commit in worker thread,
      update heartbeat every 10s while commit runs.
    - On success: remove request file.
    - On failure: write .modal_commit_failed and leave request file.
    """
    heartbeat_file = os.path.join(base_dir, ".modal_commit_heartbeat")
    request_file = os.path.join(base_dir, ".modal_commit_request")
    failed_file = os.path.join(base_dir, ".modal_commit_failed")
    heartbeat_interval = 10  # seconds between heartbeat updates

    def _write_heartbeat() -> None:
        try:
            with open(heartbeat_file, "w") as f:
                f.write(str(int(time.time())))
        except Exception as e:  # noqa: BLE001 - a heartbeat failure must not kill the daemon
            print(f"[daemon] WARNING: heartbeat write failed: {e}")

    def _commit_worker() -> list[bool]:
        result = [False]
        try:
            volume.commit()
            result[0] = True
        except Exception as e:  # noqa: BLE001 - any commit error must become a failed ack
            print(f"[daemon] ERROR: commit failed: {e}")
        return result

    while True:
        # Check for request
        if os.path.exists(request_file):
            # Write initial heartbeat and start commit in background
            _write_heartbeat()
            result_box: list[bool] = []

            def _run_commit(out: list[bool]) -> None:
                out.extend(_commit_worker())

            commit_thread = threading.Thread(target=_run_commit, args=(result_box,), daemon=False)
            commit_thread.start()

            # Update heartbeat every 10s until commit finishes
            last_heartbeat = time.time()
            while commit_thread.is_alive():
                time.sleep(1)
                now = time.time()
                if now - last_heartbeat >= heartbeat_interval:
                    _write_heartbeat()
                    last_heartbeat = now

            # Commit finished; check success
            commit_thread.join()
            success = result_box[0] if result_box else False

            if success:
                # Remove request on success (hook checks this to know we're done)
                try:
                    os.remove(request_file)
                    print("[daemon] commit succeeded, request removed")
                except FileNotFoundError:
                    pass
            else:
                # Write failure marker and leave request file
                try:
                    with open(failed_file, "w") as f:
                        f.write(str(int(time.time())))
                    print("[daemon] commit failed, marker written")
                except Exception as e:  # noqa: BLE001 - keep the daemon loop alive
                    print(f"[daemon] WARNING: failed to write failure marker: {e}")
                # Rate-limit retries while the hook sees the failed marker, instead of spinning.
                time.sleep(2)
        else:
            # No request yet; sleep and retry
            time.sleep(0.5)


# ─────────────────────────────────────────────────────────────────────────────
# Shared run helpers (used by both modes)


def _run_prefetch(shards: int) -> None:
    """Download ClimbMix shards into the Volume (skip-if-exist), then commit."""
    modal_env = _modal_env(BASE_DIR)

    print(f"[prefetch] Starting dataset prefetch ({shards} shards)...")
    result = subprocess.run(
        ["python3", "-m", "nanochat.dataset", "-n", str(shards)],
        cwd="/root/nanochat",
        env={**os.environ, **modal_env},
        check=False,
    )

    if result.returncode != 0:
        raise RuntimeError(f"prefetch dataset failed with exit code {result.returncode}")

    print("[prefetch] Dataset complete, committing volume...")
    vol.commit()
    print("[prefetch] Volume committed.")


def _run_training(script: str, extra_env: dict[str, str]) -> None:
    """Run one stage script with the commit daemon, marker cleanup and final commit."""
    os.chdir("/root/nanochat")

    # Set environment: Modal hooks and stage markers go in Volume
    modal_env = {**_modal_env(BASE_DIR), **extra_env}
    for key, value in modal_env.items():
        os.environ[key] = value

    # Start commit daemon in background
    daemon_thread = threading.Thread(
        target=_commit_daemon,
        args=(vol, BASE_DIR),
        daemon=True,
    )
    daemon_thread.start()
    print("[train] Commit daemon started")

    print(f"[train] Running {script}...")
    result = subprocess.run(
        ["bash", script],
        cwd="/root/nanochat",
        env={**os.environ, **modal_env},
        check=False,
    )

    # Clean up hook files BEFORE final commit
    for marker in [".modal_commit_request", ".modal_commit_failed", ".modal_commit_heartbeat"]:
        try:
            os.remove(os.path.join(BASE_DIR, marker))
        except FileNotFoundError:
            pass

    # Always commit final state (even if the script failed)
    print(f"[train] {script} finished (exit code {result.returncode}); final volume commit...")
    vol.commit()

    if result.returncode != 0:
        raise RuntimeError(f"{script} failed with exit code {result.returncode}")


def _read_memory_limit() -> int | None:
    """Container memory limit from cgroup v2, or None if unlimited or unreadable."""
    try:
        with open("/sys/fs/cgroup/memory.max") as f:
            return parse_memory_max(f.read())
    except OSError:
        return None


def _report_run(started: float, cores: int, timeout_s: int, name: str) -> None:
    """Print and store what the run used vs what was configured, so sizing can be tuned."""
    children = os.times()
    report = summarize_run(
        wall_s=time.time() - started,
        child_cpu_s=children.children_user + children.children_system,
        cores_requested=cores,
        peak_rss_kb=resource.getrusage(resource.RUSAGE_CHILDREN).ru_maxrss,
        memory_limit_bytes=_read_memory_limit(),
        timeout_s=timeout_s,
    )
    report["cores_configured"] = CPU_CORES
    report["memory_configured_gib"] = CPU_MEMORY_MIB / 1024
    print("[report] " + json.dumps(report, indent=2))
    out_dir = os.path.join(BASE_DIR, "run_stats")
    os.makedirs(out_dir, exist_ok=True)
    with open(os.path.join(out_dir, f"{name}.json"), "w") as f:
        json.dump(report, f, indent=2)
    vol.commit()


# ─────────────────────────────────────────────────────────────────────────────
# CPU mode: runcpu.sh on a heavy CPU machine (no GPU)


@app.function(timeout=PREFETCH_TIMEOUT, volumes={BASE_DIR: vol}, image=image_cpu)
def prefetch_cpu() -> None:
    """CPU-mode prefetch: 8 shards (what runcpu.sh needs)."""
    _run_prefetch(PREFETCH_SHARDS_CPU)


@app.function(
    image=image_cpu,
    cpu=CPU_CORES,
    memory=CPU_MEMORY_MIB,
    timeout=CPU_TRAIN_TIMEOUT,
    volumes={BASE_DIR: vol},
)
def train_cpu() -> None:
    """CPU train: runcpu.sh using every core in this container, same commit protocol."""
    cores = _available_cores()
    started = time.time()
    try:
        _run_training("runs/runcpu.sh", {"OMP_NUM_THREADS": str(cores)})
    finally:
        _report_run(started, cores, CPU_TRAIN_TIMEOUT, "cpu_train")


# ─────────────────────────────────────────────────────────────────────────────
# GPU mode: speedrun.sh on 8×H100 (defined only when NANOCHAT_MODAL_MODE=gpu)

if MODAL_MODE == "gpu":

    @app.function(timeout=PREFETCH_TIMEOUT, volumes={BASE_DIR: vol}, image=image)
    def prefetch() -> None:
        """GPU-mode prefetch: 170 shards (what speedrun.sh needs)."""
        _run_prefetch(PREFETCH_SHARDS_GPU)

    @app.function(
        image=image,
        gpu="H100:8",
        timeout=GPU_TRAIN_TIMEOUT,
        volumes={BASE_DIR: vol},
    )
    def train() -> None:
        """GPU train: speedrun.sh with SKIP_SETUP=1 and wait-for-ack hooks."""
        _run_training("runs/speedrun.sh", {})


# ─────────────────────────────────────────────────────────────────────────────
# Local entrypoint: prefetch → train → download → tip

MODES = ("cpu", "gpu")


def _download_artifacts() -> None:
    """Pull tokenizer and chat checkpoints from the Volume into ~/.cache/nanochat-modal."""
    cache_dir = os.path.expanduser("~/.cache/nanochat-modal")
    os.makedirs(cache_dir, exist_ok=True)
    for remote, local in [("/tokenizer", f"{cache_dir}/tokenizer"), ("/chatsft_checkpoints", f"{cache_dir}/chatsft_checkpoints")]:
        print(f"  → {remote} → {local}")
        if subprocess.run(["modal", "volume", "get", "nanochat-modal", remote, local, "--force"], check=False).returncode:
            raise RuntimeError(f"volume get failed for {remote}")
    tokenizer_path, checkpoints_path = f"{cache_dir}/tokenizer", f"{cache_dir}/chatsft_checkpoints"
    if not os.path.exists(tokenizer_path) or not os.path.exists(checkpoints_path):
        raise RuntimeError("SFT incomplete: missing tokenizer or checkpoints")
    model_files = [f for f in os.listdir(checkpoints_path) if f.startswith("model_") and f.endswith(".pt")]
    if not model_files:
        raise RuntimeError("SFT incomplete: no model checkpoints")
    print(f"[local] Found {len(model_files)} checkpoint(s)\n" + "═" * 80)


@app.local_entrypoint()
def main(mode: str = "cpu") -> None:
    if mode not in MODES:
        raise SystemExit(f"Unknown mode {mode!r}: use --mode cpu or --mode gpu")
    if mode != MODAL_MODE:
        raise SystemExit(f"--mode {mode} needs NANOCHAT_MODAL_MODE={mode}; use runs/runmodal.sh")
    prefetch_fn, train_fn = (prefetch_cpu, train_cpu) if mode == "cpu" else (prefetch, train)
    label = "CPU (runcpu, heavy machine)" if mode == "cpu" else "GPU (speedrun, 8×H100)"
    print("═" * 80)
    print(f"nanochat on Modal, mode={mode}: {label}")
    print("═" * 80)
    print("\n[local] Step 1: prefetch...")
    prefetch_fn.remote()
    print(f"[local] Step 2: train ({mode})...")
    train_fn.remote()
    print("\n[local] Step 3: Downloading chat artifacts...")
    _download_artifacts()
    print("SUCCESS: training complete and artifacts downloaded.")
    print("═" * 80)
    print("\nTo chat locally, run:")
    print("  NANOCHAT_BASE_DIR=~/.cache/nanochat-modal python3 -m scripts.chat_cli -p \"Why is the sky blue?\"")
    print("\nSee docs/MODAL.md for details.")


if __name__ == "__main__":
    raise SystemExit("Use: modal run runs/modal_run.py --mode cpu|gpu")
