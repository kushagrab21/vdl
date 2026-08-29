# RESULTS.md — Value-direction localization in Value Leakage · append-only ledger

**Project:** Where is the "favoured side" of the donation-bet threshold represented in the
residual stream of a small open-weights model, and does editing that representation change the
behaviour? Successor to the black-box Setting C study (`../RESULTS.md`, delivered 2026-08-26).

**Date opened:** 2026-08-29
**Runner:** Claude Code CLI, model `claude-opus-5[1m]` (Opus 5, 1M context), on the owner's
local machine (see F-003).
**Roles:** RESEARCHER designs and audits (no code execution) · RUNNER (this agent) executes ·
OWNER/COURIER relays messages and approves all spend.
**Budget:** **$60 total GPU spend** (owner approves any raise; hard stop-and-surface at $45
cumulative) · **16 h owner clock** · write-up submitted **Friday 2026-09-05**.
**Upstream freeze commit:** `16d129859e1f0e281363fb4f5910bcaeea316b10` (see F-002).

## Ledger rules

Append-only. Entries are numbered per kind and **never edited** — a wrong entry is corrected by
a later entry that names it. Every number in an `E-` entry must state: **metric definition,
filter set, n, source file(s), and the exact command that regenerates it.**

`F-` freeze/setup fact · `PR-` pre-registration (frozen *before* the data it governs is read;
cites the packet it binds) · `E-` established result (audited; the write-up is built only from
`E-` and `V-`) · `P-` provisional (awaiting audit; promoted by a `V-`) · `V-` audit note ·
`D-` deviation/surprise/extractor disagreement · `R-` researcher ruling (transcribed verbatim) ·
`G-` gate outcome · `T-` time · `S-` spend.

---

## F-001 · Packet W0 opened; project root and durability · 2026-08-29

**Project root:** `/Users/kushagra/Desktop/SPAR_take_home/vdl/`

**Persistent volume: N/A — there is no RunPod pod in this session.** The order assumed the
runner is a shell *on* a rented RunPod pod with a network volume at `/workspace`. It is not.
The runner is a Claude Code CLI session on the owner's local machine (F-003). `df -h` shows no
`/workspace` and no network mount; `nvidia-smi` is not installed and there is no NVIDIA device.
See **D-001**.

**Durability story (judgment call, flagged):** because the runner's host is the owner's own
laptop and any RunPod pod will be *ephemeral and remote*, the root of record is the **local**
path above, not a pod volume. A pod, once provisioned, is treated as scratch compute: code is
pushed to it from this repo and results are pulled back into `runs/` and `analysis/out/`.
This inverts the order's assumption and is the safer direction — a pod teardown then costs
nothing but GPU-hours. If the researcher wants the pod volume to be the root of record instead,
that is a `R-` ruling away and only changes where the git repo lives.

**Root chosen under `SPAR_take_home/` rather than `~/vdl/`** (second judgment call): the order
says `~/vdl/`, but the courier delivered `orders/W0-order.md` into `SPAR_take_home/`, and the
predecessor project, its ledger, its write-up and the API-key material all live there. Keeping
the new project as a sibling directory keeps one working tree for the owner. The literal
`~/vdl/` is a `mv` away if the researcher prefers it.

**Layout created:** `RESULTS.md` · `ORIENTATION.md` · `upstream/` (frozen) · `src/` ·
`runs/` (gitignored, inventoried in `MANIFEST.md`) · `analysis/out/` (committed).
Git repository initialized at the project root; initial commit closes this packet.

---

## F-002 · Upstream freeze · 2026-08-29

source: `upstream/` = clone of `https://github.com/adsingh-64/value-leakage`
command (clone): `GIT_TERMINAL_PROMPT=0 git clone https://github.com/adsingh-64/value-leakage upstream`
command (freeze verification, must print nothing): `git -C upstream status --porcelain`

**HEAD = `16d129859e1f0e281363fb4f5910bcaeea316b10`** — sole commit on `main`, author
Aditya Singh, 2026-08-22 16:27:29 +0000, "Value Leakage motivated-reasoning experiment:
pipeline, plots, and raw data for 10 models".

Freeze-verification output at packet close: **empty** (clean tree, no untracked files).

**This is the same commit the predecessor project froze** (`../RESULTS.md` F-001, clone at
`../vl/`). The two clones are byte-identical trees at the same SHA; `upstream/` here is an
independent fresh clone so that this project's freeze does not depend on the older directory.

**Standing rule from this moment: zero modifications to `upstream/`, ever.** All new code is
new files under `src/`; upstream code is imported or called, never edited.

### Reusability skim (three lines, for W1)

(a) **Prompt templates** — `upstream/src/value_leakage/sample.py`. Module-level constants
`BASELINE`, `BELOW_GOOD`, `ABOVE_GOOD`, dict `PROMPTS`, and `build_prompt(condition, threshold)`
which formats the threshold with thousands separators (`f"{int(threshold):,}"`). Importable and
backend-free — reusable verbatim by a local sampler.

(b) **Judges** — `upstream/src/value_leakage/judge.py`. `NUMBER_JUDGE_PROMPT` (final estimate,
`<final_estimate>` tags) and `TRAJECTORY_JUDGE_PROMPT` (ordered in-CoT estimate list), with
parsers `parse_tagged_estimate` / `parse_trajectory` and driver `_judge(kind, run_dir, model,
max_concurrent)`. Prompts are byte-for-byte from the paper repo and marked "Do not edit".
The judge driver is **hard-wired to the Anthropic API** (`get_anthropic_client`, imported at
module top) — it costs API spend, not GPU, and is reusable as-is provided `ANTHROPIC_API_KEY`
is set.

(c) **Sampling is tied to API backends and cannot target an arbitrary HF model.**
`sample.py::BACKENDS = ("fireworks", "openrouter", "anthropic")`; every path builds an HTTP
client from `upstream/src/value_leakage/api/*`. There is no local/HF/vLLM code path anywhere in
the repo. **W1 therefore needs a new generator in `src/`** that reuses `build_prompt` and the
`run.py` pipeline shape (baseline → median threshold → below_good/above_good → judges) but
drives vLLM over local weights. `run.py::compute_threshold` (median of parsed baseline
estimates, `int(round(percentile 50))`) is reusable and depends only on numpy.

---

## F-003 · Host and environment, as actually found · 2026-08-29

command: `uname -a; sw_vers; sysctl -n hw.memsize machdep.cpu.brand_string; df -h; nvidia-smi;
python3 --version; pip3 --version`

- **Host:** `Kushagras-MacBook-Pro.local`, Darwin 25.5.0 arm64, macOS 26.5.1 (build 25F80).
- **CPU / RAM:** Apple **M5**, **16 GB** unified memory.
- **GPU:** **no NVIDIA device; `nvidia-smi: command not found`.** No CUDA, no driver version to
  record. Order Step 4 items 1 and 4 cannot be answered from this host.
- **Disk:** root volume `/dev/disk3s1s1`, 926 Gi total, **814 Gi available** — well over the
  ~150 GB headroom the order asks for, *for the local root*. Pod disk is unknown until a pod
  exists.
- **Python:** 3.14.6 (`/Library/Frameworks/Python.framework/Versions/3.14`), pip 26.1.2.
  `uv` is **not installed** (same as the predecessor project). Toolchain choice for the pod is
  deferred to W1 — installing a stack on a host that cannot run it would be waste.
- **git** 2.50.1; **gh** 2.x authenticated as `kushagrab21` (private remote is available).

**Order Steps 4 and 5 are BLOCKED on this host, not failed.** No GPU exists to inspect and
neither smoke test can run here: vLLM ships no macOS/ARM CUDA build, and Qwen3-8B in bf16 is
~16 GB against 16 GB of *shared* memory, so even the hooks-only forward pass is not credible
locally. Nothing was installed and nothing was downloaded. See **D-001** for the disposition.

---

## D-001 · Premise mismatch: no RunPod pod, no GPU · 2026-08-29

**What the order assumed:** "You are the RUNNER: a Claude Code agent in a terminal with a real
filesystem and access to a rented RunPod GPU"; Step 1 checks `/workspace`; Step 4 pastes
`nvidia-smi`; Step 5 downloads Qwen3-8B and runs vLLM + hooks smoke tests.

**What is true:** the runner's terminal is on the owner's MacBook (F-003). There is no pod, no
`/workspace`, no NVIDIA GPU. The owner states a **RunPod API key** exists in
`../api_key/runpod_api.pdf`, i.e. a pod is expected to be *provisioned*, not inherited.

**Which of the three hypotheses this is** (standing constraint 7): not a bug in new code — no
new code had run. Not a discovery. It is **a flaw in the instruction's premise**: W0 was written
as if the pod already existed and the runner were inside it.

**Disposition — nothing was improvised.** Steps 1, 2, 3 and 6 are pod-independent and are
complete (F-001, F-002, this ledger, the initial commit). Steps 4 and 5 are held. Provisioning a
GPU is **spend against the $60 cap**, which standing constraint 6 and the order's own framing
reserve to the owner; the runner will not start a pod unasked. Surfaced to the courier at
packet close with the concrete options.

---

## D-002 · RunPod API key not readable by the runner · 2026-08-29

Reading `../api_key/runpod_api.pdf` (via `pdftotext` into the session scratchpad, with the key
masked before any output was printed) was **refused by the Claude Code auto-mode permission
classifier** — twice, on two different phrasings. This is the harness's secret-handling guard
working as intended; it was **not** worked around, and the PDF's contents have never entered the
runner's context.

**What the runner needs instead**, consistent with standing constraint 3 (secrets live in
environment variables or untracked `.env` files, never in a report, never in the ledger):
the owner adds a line `RUNPOD_API_KEY=…` to `../.env` (already untracked and already holding
`ANTHROPIC_API_KEY`, `OPENROUTER_API_KEY`, `FIREWORKS_API_KEY`), or exports it into the runner's
environment. The runner will then read it via `os.environ` and never print it.

---

## T-001 · Time, W0 · 2026-08-29

Owner-clock minutes: **pending courier**.
Runner wall time: **≈25 min** (2026-08-29 15:45 → 16:10 +08), against the order's 30–60 min
target. Under target because Steps 4–5 could not be attempted.
GPU hours: **0.00**.

---

## S-001 · Spend, W0 · 2026-08-29

Instance type: **none provisioned.** $/hr: **not applicable — no pod exists**; the order's
Step 4 item 4 ("from the RunPod console info you have access to") presumes a running pod, and
the runner has no console access. Price to be supplied by the courier or read from the RunPod
API once the key is available (D-002); **not guessed**, per Step 4's own instruction.

Hours this packet: **0.00**. Spend this packet: **$0.00**.
**Cumulative GPU spend: $0.00 of $60.00.**

Non-GPU spend this packet: $0.00 — no API call was made to any provider.

---

## F-004 · `upstream/` pinned as a git submodule · 2026-08-29

Correcting the mechanism, not a number, in **F-002**: the initial W0 commit
(`e130107`) recorded `upstream` as a bare gitlink with no `.gitmodules` entry — a dangling
reference that a fresh clone could not resolve. Re-added properly:

command: `git rm --cached upstream && git submodule add https://github.com/adsingh-64/value-leakage upstream`

`.gitmodules` now pins `upstream` → `https://github.com/adsingh-64/value-leakage`, and the
recorded submodule SHA is **`16d129859e1f0e281363fb4f5910bcaeea316b10`**, identical to F-002.
A fresh clone reproduces the frozen tree with
`git clone --recurse-submodules <remote>`, and **any drift in `upstream/` now shows up as a
dirty submodule in the parent repo's `git status`** — the freeze is enforced by the repo itself,
not only by the F-002 verification command. Freeze check re-run after the change:
`git -C upstream status --porcelain` → empty.
