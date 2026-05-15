---
name: alliancecan
description: Alliance Canada Slurm clusters — default to L40S on Killarney, jobs, storage, modules, paths, and account pitfalls. Use when editing Slurm scripts, cluster setup, or HPC workflows for docs.alliancecan.ca systems.
---

# Alliance Canada HPC

Apply when working on Slurm job scripts, cluster setup, paths, or GPU requests for Alliance national systems (Killarney, Fir, Narval, Nibi, Rorqual, Trillium, etc.).

## Default GPU for this repo: **L40S (always prefer this first)**

For **Killarney**, treat **NVIDIA L40S** as the **default** GPU in new or edited Slurm scripts unless the user explicitly asks for H100/A100 or you know they need 80 GB VRAM.

**Why:** L40S usually has a **much shorter queue** than H100 performance tiers. H100 is overkill for many PoC / IPPO / probe workloads and can sit in `PD` for hours.

### How to request L40S (standard pattern)

In the job script, use **`--gres`** — **do not** put H100-only partitions (`gpubase_h100_*`) together with L40S `gres` (incompatible).

```bash
#SBATCH --gres=gpu:l40s:1
#SBATCH --cpus-per-task=8
#SBATCH --mem=50G
# Optional: shorter wall for faster scheduling
#SBATCH --time=1-00:00:00
```

Submit from the repo directory:

```bash
sbatch --account=<your-ccdb-group> your_job.sh
# or if #SBATCH --account= is already in the file:
sbatch your_job.sh
```

**Verify** what Slurm recorded (after submit):

```bash
scontrol show job=<JOBID> | egrep -i 'ReqTRES|TRES=|MinMem'
```

You should see **`l40s`** in the GRES line, not `h100`.

### When to use H100 instead (opt-in)

Use **H100** only when the workload needs **large GPU memory** (e.g. huge batches, very large models) or the user asks for the performance tier. Typical Killarney pattern:

```bash
#SBATCH --partition=gpubase_h100_b4
#SBATCH --gpus-per-node=h100:1
#SBATCH --cpus-per-task=16
#SBATCH --mem=64G
```

Match **`b1`…`b5`** partition letter to **max wall time** allowed on that queue (`sinfo -o "%P %G %l"`). **Never** mix `gpubase_h100_*` with `--gres=gpu:l40s:1`.

---

## Slurm account (read this first — common failure mode)

- **Every job** needs `#SBATCH --account=<group-name>` where `<group-name>` is the **Group Name** from [CCDB](https://ccdb.alliancecan.ca/) → My Projects → My Resources and Allocations. It is **not** a display title; it must match Slurm exactly.
- If `sbatch` says *Invalid account* and lists allowed accounts (e.g. `aip-boyuwang`), use **one of those strings verbatim**.
- **Never** instruct anyone to run `sed` that replaces a real account with a **placeholder** like `your-ccdb-group` or `YOURGROUP` — the job will fail. Either keep a real example account in the script or tell them to set the real name from CCDB / `sbatch`’s error list.
- Optional: `export SLURM_ACCOUNT=aip-boyuwang` and `export SBATCH_ACCOUNT=$SLURM_ACCOUNT` in `~/.bashrc`, or override per job: `sbatch --account=aip-boyuwang script.sh`.

## `$SCRATCH` and `$USER` (second common failure mode)

On **Killarney**, `$SCRATCH` is typically **already** your user scratch directory (e.g. `/scratch/ccao87`). It is **not** `/scratch` with a missing `$USER` segment that you must add by hand.

- **Wrong:** `cd $SCRATCH/$USER` when `$SCRATCH=/scratch/ccao87` → becomes `/scratch/ccao87/ccao87` → **No such file or directory**.
- **Right:** `cd $SCRATCH` and clone/checkout the repo there, e.g. **`$SCRATCH/drc-sokoban-ma`** (same pattern as `ts-sandbox` using `$SCRATCH/ts-sandbox`).

Repo job scripts in this project should resolve the working tree like:

```bash
if [ -d "$SCRATCH/drc-sokoban-ma" ]; then
  export PROJECT_ROOT="$SCRATCH/drc-sokoban-ma"
elif [ -d "$HOME/drc-sokoban-ma" ]; then
  export PROJECT_ROOT="$HOME/drc-sokoban-ma"
else
  echo "ERROR: clone repo to \$SCRATCH/drc-sokoban-ma (or \$HOME fallback)"
  exit 1
fi
```

Only use `$SCRATCH/$USER/<repo>` if **your site documentation** says scratch is the parent of per-user dirs (unusual on Killarney for the common case above).

## Accounts and Slurm basics

- **Scheduler:** Slurm only. No compute on login nodes except tiny tasks (~≤10 CPU-minutes, ~≤4 GB RAM). Everything else: `sbatch`, `salloc`, `srun`.
- **Minimum directives:** Always set **`#SBATCH --time=...`**. Add **`--mem`** or **`--mem-per-cpu`** on general-purpose clusters (default can be very small per core). `#SBATCH` lines must come **before** any shell commands in the script.
- **Do not** hammer Slurm with `squeue`/`sq` in tight loops; use mail notifications or reasonable polling.
- **Partitions:** Prefer **L40S + `--gres`** as default; only pin **`gpubase_h100_*`** when the user needs H100. Verify live with `sinfo` on the target system.

## Where to put files (storage hygiene)

- **HOME (`~`):** Small quota; keep **source, job scripts, tiny configs**. Not for large datasets or heavy I/O.
- **SCRATCH:** Large, fast for big sequential I/O; **not backed up**; old files may be **purged** (e.g. 60-day policy—check current docs). Use for **checkpoints during runs**, bulk output, datasets you can re-fetch, and **clone/run the repo** where policy requires (Killarney: **no GPU work from `/home`** — run from `$SCRATCH/...`).
- **PROJECT (`$PROJECT` / `~/projects/...`):** Shared by the allocation group, larger quota, backed up; intended for **relatively static** shared data—frequent churn hurts tape backup. For **your** artifacts, use a **per-user subdirectory**: `$PROJECT/$USER/<app>/` (venv, checkpoints, wandb, copied datasets), **not** the group root as a personal scratch pad.
- **`$SLURM_TMPDIR`:** Per-job local disk on the compute node; great for **many small files** and ephemeral shuffles; **deleted when the job ends**.
- **Python/R packages:** Often **not** full Lmod modules; use Alliance **Python + pip/wheel** docs, or install into **your** space (venv under `$PROJECT/$USER/...` or similar).
- **Modules:** Start job scripts with **`module purge`** then load what you need; prerequisites matter—use **`module spider <name>/<version>`** to see the load chain. Avoid relying on whatever was loaded in the interactive shell.

**Per-user working space (important):** Treat **group project space as shared infrastructure**. Keep **your** working data, venvs, and experiment outputs under **`$PROJECT/$USER/...`** and/or **`$SCRATCH/$USER/...`** (only when that path is valid on your site). Do **not** stash personal experiments or venvs directly under `$PROJECT/` without a `/$USER/` (or agreed team) path—avoids quota fights and policy issues.

## Repo-local `results/` on the cluster (Slurm + Python)

When you add or edit **Slurm job scripts** or **Python** that runs on Alliance login/compute nodes, put **all** run outputs the job creates—logs, checkpoints, generated datasets, exports—under **`./results/`** relative to **`SLURM_SUBMIT_DIR`** (the directory you were in when you ran `sbatch`). Do **not** put those artifacts under `$SCRATCH/...` or `$HOME` unless the user explicitly overrides. Do **not** anchor paths off the spool copy of the batch script.

**Allowed top-level layout under `results/` — nothing else at that level:**

| Path | Use |
|------|-----|
| `./results/logs/` | Job logs, traces, wandb offline roots, text/CSV that behave like logs, small generated helper scripts for a chain |
| `./results/ckpts/` | Checkpoints; use a **per-run subdirectory** when the training code expects multiple canonical filenames in one dir |
| `./results/datasets/` | Generated or copied data (symlinks to repo data are OK here) |

Do **not** create sibling trees like `./checkpoints/`, `./slurm_logs/`, or a separate `$STORE` root on scratch for repo jobs unless the user asks.

**Run stem (directory or file basename inside a bucket):**

```text
{MM-DD}-{last-4-characters-of-$SLURM_JOB_ID}-{short-descriptive-slug}
```

Use the **last four characters** of `SLURM_JOB_ID` (e.g. job `3249152` → `9152`). Pick a **short slug** that says what the job does (`gauss-pretrain`, `unet-fullvar-smoke`, `profile-1epoch`, …).

Examples:

- Single log file: `./results/logs/05-02-9152-gauss-pretrain.log`
- Pipeline checkpoint dir: `./results/ckpts/05-02-9152-gauss-pretrain/` (contains `pretrained_diffusion.pt`, etc.)

After `cd "$SLURM_SUBMIT_DIR"`, compute the stem **inside the batch job** (so `SLURM_JOB_ID` is known), then export it or pass to Python:

```bash
mkdir -p ./results/logs ./results/ckpts ./results/datasets
STEM="$(date +%m-%d)-${SLURM_JOB_ID: -4}-gauss-pretrain"
CKPT_DIR="./results/ckpts/${STEM}"
mkdir -p "$CKPT_DIR"
```

**Git:** keep `results/` **gitignored** (whole tree or per-bucket).

**Slurm: one combined log (stdout + stderr).** Never rely on separate `*.out` and `*.err` for the main job log.

- **Preferred:** at the top of the batch body (after `cd "$SLURM_SUBMIT_DIR"`), set `LOG=./results/logs/${STEM}.log`, `mkdir -p "$(dirname "$LOG")"`, then **`exec >>"$LOG" 2>&1`**, and in `#SBATCH` use **`--output=/dev/null`** and **`--error=/dev/null`** so Slurm does not also write split files.  
- **Alternative:** set **`#SBATCH --output`** and **`#SBATCH --error`** to the **identical** path under `./results/logs/` (Slurm merges when both are the same file). `#SBATCH` does not expand bash parameter expansion, so the `MM-DD-…-last4-…` shape usually needs the `exec` pattern or a path using only Slurm replacements (`%j`, `%x`, …).

## Resolving `$PROJECT` in job scripts (ts-sandbox pattern)

If `$PROJECT` is empty in the batch environment:

```bash
# Use nullglob — see Gotchas: `ls def-*` + `set -o pipefail` kills the job if globs miss.
if [ -z "$PROJECT" ] && [ -d "$HOME/projects" ]; then
  shopt -s nullglob
  _m=("$HOME"/projects/def-* "$HOME"/projects/aip-*)
  shopt -u nullglob
  if [ "${#_m[@]}" -gt 0 ]; then
    export PROJECT=$(readlink -f "${_m[0]}")
  fi
fi
```

Then set storage, e.g. `STORAGE_ROOT="$PROJECT/$USER/drc-sokoban-ma"` for checkpoints, wandb, venv.

If `$PROJECT` is **already set** but is **not** an absolute directory (e.g. it equals the Slurm `--account` string), treat it as invalid and run the same `~/projects` discovery above, or require an explicit absolute `PROJECT` in `sbatch --export=...`.

## Killarney — hardware reference (verify with `sinfo`)

This cluster is common for this repo. **Verify live** with `sinfo -o "%P %G %l"` and `scontrol show node | grep -i gres`—names and partitions change.

- **L40S (default tier for scripts in this repo):** Standard compute; request with `#SBATCH --gres=gpu:l40s:1`. Example scripts: `slurm_ci_latent_etth2.sh`, **`slurm_ma_tom.sh`** (default), `slurm_latent_experiment.sh`.
- **H100 (optional, heavy jobs):** Dell XE9680-class nodes, **8× H100 SXM 80GB** per node. Use `#SBATCH --partition=gpubase_h100_b*` + `#SBATCH --gpus-per-node=h100:N` — **not** mixed with L40S `gres`.

- **Code location:** Killarney **must not run GPU work from `/home`**; keep a checkout under **`$SCRATCH/<repo-name>`** (e.g. `$SCRATCH/drc-sokoban-ma`, same idea as `$SCRATCH/ts-sandbox` in the other repo).
- **Account prefix:** Allocations may show as **`aip-...`** on Killarney vs **`def-...`** elsewhere—use the CCDB **Group Name** for `--account`.

## Other clusters (quick reference)

Repo comments (`slurm_pipeline.sh`): **Narval** → e.g. A100; **Fir / Nibi / Rorqual** → e.g. H100-style requests. Always match **`--account`** to an allocation **valid on that cluster** (RAPs are not always portable). Default to **smaller / general GPU** when unsure, not the largest SKU.

## Software modules (typical ML stack)

Example stack used in this repo’s Slurm scripts:

```bash
module purge || true   # || true required — exits non-zero on sticky modules
module load StdEnv/2023
module load python/3.11
module load cuda/12.2
module load cudnn/8.9
```

Load **CUDA/cuDNN** versions compatible with your PyTorch build. If a module fails, use `module spider` to resolve prerequisites. **Docker** is not available; **Apptainer** is (`module load apptainer`).

### `module purge` and `set -e` (common silent failure)

On Alliance nodes, **`module purge` exits non-zero** (often code 2) when sticky modules
(`CCconfig`, `gentoo`, compiler stack) refuse to unload. With `set -e` or `set -euo pipefail`
this **kills the job immediately** — only the module warning appears in `.err`, no Python
output, `sacct` shows `FAILED ExitCode=2:0`.

**Always write `module purge || true`**, never bare `module purge` in scripts using `set -e`.

---

## Python virtual environments on compute nodes (critical)

**Never keep the active venv on `/scratch` or `/project` for a running job.**
Both are parallel (Lustre/GPFS) filesystems — fast for large sequential I/O but
**extremely slow at reading thousands of small files**. `import torch` touches hundreds of
`.so` and `.py` files; on a cold compute node this alone can take **5–15 minutes**. A 15-
or 20-minute smoke test times-out before a single line of user code runs.

### The fix: rebuild the venv on `$SLURM_TMPDIR` at job start

`$SLURM_TMPDIR` is a fast **node-local NVMe SSD** scoped to your job. Imports from there
take seconds. Canonical Alliance Canada pattern:

```bash
virtualenv --no-download "$SLURM_TMPDIR/env"
source "$SLURM_TMPDIR/env/bin/activate"
pip install --no-index --upgrade pip

# Heavy C-extension packages — Alliance CA pre-built wheel cache, no network needed
pip install --no-index torch numpy scikit-learn

# wandb: ALWAYS --no-index from the Alliance wheelhouse (see subsection below).
pip install --no-index wandb
```

`--no-download` skips fetching a new virtualenv wheel. `--no-index` uses only the pre-built
wheels exposed by `module load python/3.11`. Check availability: `avail_wheels <pkg>` on a
login node. **Do not `cp -r` an existing venv** — absolute paths in activation scripts break.

### **`wandb` must use `--no-index` (PyPI sdist → Go → silent pip death)**

If a job script does `pip install wandb` or `pip install "wandb>=…"` **without** `--no-index`, pip may pull a **PyPI source distribution**. Recent wandb builds run **metadata generation** that tries to compile **`wandb-core` in Go** (`Building wandb-core Go binary…`). Compute nodes typically **do not have `go`**, so pip errors with *Did not find the 'go' binary*. With **`set -e`** in the same shell, the batch script **exits immediately** after venv setup — logs look “empty”: only the first banner lines and `[setup] Building venv on $SLURM_TMPDIR`, then nothing until the job ends.

**Fix:** install wandb from the Alliance wheel cache only: **`pip install --no-index wandb`** (Alliance docs and internal wiki: same pattern). Pure-Python extras can use PyPI if needed; do **not** let wandb resolve from PyPI inside Slurm jobs.

**Related:** In bash **unquoted heredocs** used to write job bodies on the login node, **backticks** in comments still run **command substitution** (e.g. `` `import torch` `` can invoke ImageMagick’s `import`), and **`$SLURM_TMPDIR`** in comments still **expands** under `set -u` on the login node. Escape as `\$(…)` / `\$VAR` or avoid backticks in those heredocs.

**Symptom of the slow-import bug:** job output has only the first few `echo` lines, then
`TIMEOUT` in `sacct`. No Python output. Venv is on `/scratch`.

**Smoke-test wall time:** even with `$SLURM_TMPDIR`, request **≥20 min** — `pip install`
from the wheel cache takes 3–5 min; after that imports are <1 min.

## Patterns from this repository

- **`#SBATCH --account=aip-boyuwang`** — example only; **replace with your real CCDB group name** if different, never with a fake placeholder string.
- **Venv and bulky data:** `$PROJECT/$USER/<app>/venv` (and checkpoints/results under the same tree)—**per-user under project**, not the bare group directory.
- **`slurm_ma_tom.sh`:** defaults to **L40S** (`--gres=gpu:l40s:1`); H100 only via explicit `sbatch` overrides (see script header).
- **`slurm_unet_fullvar.sh` (ts-sandbox):** **L40S** for `--smoke-test`, **H100** + `gpubase_h100_b4` for full runs.
- **`PYTHONUNBUFFERED=1`** and **`python -u`** help with Slurm log latency (buffering).

## Gotchas (see also `AGENTS.md` — Notes space / repo context — and `.ai/cluster-paths.md`)

- **`ls ~/projects/def-*` under `set -euo pipefail` (silent job death):** Many job scripts use `set -euo pipefail` and then `FIRST=$(ls -d "$HOME"/projects/def-* ... 2>/dev/null | head -1)`. If **`~/projects` exists** but **no** `def-*` / `aip-*` match, **`ls` exits with status 2**. With **`pipefail`**, the pipeline fails → **`set -e` aborts the entire batch** in a few seconds. **`sacct`** shows `State=FAILED`, **`ExitCode=2:0`**, `.err` may only show `module purge` noise, `.out` stays nearly empty. **Fix:** use `shopt -s nullglob` and a bash array over the globs (see snippet above), or append `|| true` to the assignment in a way that cannot still fail the pipeline—**do not** rely on `ls` with possibly unmatched globs in a piped command.
- **`BASH_SOURCE[0]` inside `sbatch` scripts:** Slurm copies the submitted script to a spool path like `/cm/local/apps/slurm/var/spool/job<ID>/slurm_script`, so `BASH_SOURCE[0]` points at the spool copy, not the repo checkout. Sourcing helper files relative to it will fail. **Use `SLURM_SUBMIT_DIR`** when you need repo-local helper scripts or data, and add a guard that errors out if the submit directory is missing the file.
- **Empty/broken venv on cluster:** If jobs fail with missing `torch`, recreate or repair **`$PROJECT/$USER/.../venv`** (or delete and let the Slurm script reinstall).
- **Imports:** Run Python as **`python -m package.module`** from the repo root.
- **Slurm output buffering** can make logs look “stuck”; use unbuffered Python or interactive `salloc` to debug.
- **`module purge` in jobs** — always write `module purge || true`; bare `module purge` exits non-zero on sticky modules and kills the job when `set -e` is active (see Software modules section above).
- **`sbatch --wrap` uses `/bin/sh`, not bash:** `--wrap="source ..."` fails with `source: not found` because `/bin/sh` on Alliance nodes is `dash`, which uses `.` not `source`. **Always write a proper `#!/bin/bash` script** and pass it to `sbatch` — never use `--wrap` for anything involving `source`, bash arrays, or `[[ ]]`.
- **`sbatch` from scripts:** Do not submit thousands of jobs at once; prefer **arrays** or spacing submissions—Alliance warns this can harm Slurm.
- **`sbatch` stdin vs script file:** Prefer **`sbatch /path/to/job.sh`** (real file on disk, `#!/bin/bash`) over piping a heredoc into `sbatch`. Some sites log or handle stdin batch scripts inconsistently; file-based submission matches working patterns in this repo (e.g. self-submit scripts).
- **`sbatch --export=ALL` poisons `PROJECT` (ts-sandbox / venv jobs):** On login nodes, people often `export SLURM_ACCOUNT=aip-boyuwang` or confuse the CCDB **group name** with the filesystem **`$PROJECT`** used in `run.sh` (`~/projects/def-*` → absolute path). **`--export=ALL`** then injects `PROJECT=aip-boyuwang` into the job; scripts that build `$PROJECT/$USER/diffusion-tsf/venv` silently point at nonsense paths like `aip-boyuwang/ccao87/.../venv`. **Fix:** use **`sbatch --export=TS,R=...`** (list only needed vars), or in the batch script **ignore `PROJECT` unless it is an absolute path and a directory**, then fall back to the `~/projects/def-*` / `aip-*` glob discovery (see “Resolving `$PROJECT`” above).
- **Stale script on cluster:** If `squeue` still shows H100/64G after switching to L40S, **`git pull`** on the cluster clone and **resubmit** — old `#SBATCH` lines are baked in at submit time.

## Official docs

Prefer [docs.alliancecan.ca](https://docs.alliancecan.ca/) for authoritative quotas, partition names, and policy updates—this skill is a condensed assistant checklist, not a substitute for current site documentation.
