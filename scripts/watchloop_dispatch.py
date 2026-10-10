#!/usr/bin/env python3
# PEP 563: defer annotation evaluation so `X | None` style hints parse on any
# Python >=3.9 (the host python is 3.9; the test image is 3.10). Without this,
# `int | None` is a runtime TypeError on 3.9.
from __future__ import annotations

"""llgenie watch-loop DISPATCHER — host crontab entrypoint.

Model: each crontab tick runs THIS dispatcher, which:
  1. finalizes merge-ready PRs (green CI + APPROVED review + no open threads +
     NOT behind main), and
  2. for every open issue with no live branch/PR, spawns ONE dedicated background
     `project-manager` hermes worker in that issue's own worktree + own log, so
     issues are worked in PARALLEL and never serialize behind one another.

NEVER-MERGE-BEHIND GATE (issue #9): a PR whose head is behind `main` is NEVER
merged out of sync. The dispatcher does NOT merely skip such a PR — it
forward-merges `origin/main` into the PR branch (rebase/merge-and-resolve), then
re-attempts the gate after CI re-runs. Merge conflicts are surfaced to the
branch's worker, never silently auto-resolved or force-deleted.

PARALLEL-SAFETY:
  * every containerized `make` step inside a worker runs under a shared flock keyed
    on .watchloop/run/test.lock, so only one worker drives nerdctl at a time.
  * the loop-harness uses a dedicated image + orchestration; the dispatcher never
    starts/invokes it and workers are forbidden from running it.
  * each worker uses its OWN git worktree and writes its OWN log.

STALE-WORKTREE CLEANUP (issue #29 + issue #45): after a PR merges to `main`, the
merged branch's worktree + local branch + worker lock/prompt/log files become
stale and accumulate. Each tick, after the merge gate, the dispatcher cleans
every `feat/*` worktree under ../llgenie-wt/ whose HEAD is an ancestor of
origin/main (fully merged). In-flight worktrees and worktrees whose worker is
still alive are never touched; `--dry` reports what would be cleaned without
deleting. issue #45 closes the REMOTE gap: `merge_pr` passes
`delete_branch: true` in the merge API body, and the cleanup sweep is the
safety net — for every merged branch it cleans, it also deletes the REMOTE
branch (`git push origin --delete <branch>`) if `origin` still has it, never
touching `main`.

PRE-SPAWN MODEL PROBE (issue #37): when the effective worker provider is local
(empty/localhost/custom/llama.cpp), the dispatcher GETs
http://127.0.0.1:11434/v1/models and confirms the worker model is listed BEFORE
spawning. A down/unreachable server (or unlisted model) skips the spawn cleanly
(log + continue: no worker, no lock, no prompt file, no worktree) instead of
burning a doomed worker. Hosted providers (e.g. openrouter) are never probed.

No worker time limit => a big issue may span ticks and resume from its own log.
"""

import fcntl
import json
import os
import re
import signal
import subprocess
import sys
import time
import urllib.error
import urllib.request

# The llgenie checkout this script lives in (/Users/andy/repository/git/llgenie on
# the dev Mac, the runner's checkout in CI): never a hardcoded home path.
REPO = os.environ.get(
    "WATCHLOOP_REPO", os.path.dirname(os.path.dirname(os.path.abspath(__file__)))
)
LOGS = f"{REPO}/.watchloop/logs"
RUN = f"{REPO}/.watchloop/run"
WORKTREE_BASE = os.path.normpath(f"{REPO}/../llgenie-wt")
API = "https://api.github.com/repos/asimov-agent/llgenie"
HERMES = os.environ.get("HERMES_BIN", os.path.expanduser("~/.local/bin/hermes"))

# Worker model override. The profile default is `llm-local` (the local 35B), which
# is correct for serving but SLOW for agentic driving (~170s/call in practice),
# so spawned workers can stall far behind the loop cadence.
#
# Resolution order (so it is robust even when the crontab can't carry env vars):
#   1. env WATCHLOOP_WORKER_MODEL / WATCHLOOP_WORKER_PROVIDER (crontab/export), then
#   2. the file .watchloop/worker-model (two lines: MODEL, PROVIDER), in-repo,
#      editable without sudo / without fighting a wedged crontab.
# Empty = use the profile's configured default (keeps existing behaviour).
def _read_worker_model_config() -> tuple[str, str]:
    cfg = os.path.join(RUN, "worker-model")
    try:
        with open(cfg) as f:
            lines = [ln.strip() for ln in f if ln.strip() and not ln.strip().startswith("#")]
        model = lines[0] if lines else ""
        provider = lines[1] if len(lines) > 1 else ""
        return model, provider
    except OSError:
        return "", ""


_CFG_MODEL, _CFG_PROVIDER = _read_worker_model_config()
WORKER_MODEL = os.environ.get("WATCHLOOP_WORKER_MODEL", "").strip() or _CFG_MODEL
WORKER_PROVIDER = os.environ.get("WATCHLOOP_WORKER_PROVIDER", "").strip() or _CFG_PROVIDER

# Effective model id the spawned worker will use. When no override is set the
# profile default is `llm-local` (the local 35B on the llama.cpp server), so the
# pre-spawn probe (issue #37) checks THAT id against the local server.
WORKER_MODEL_EFFECTIVE = WORKER_MODEL or "llm-local"

# Providers that mean "the worker talks to the LOCAL llama.cpp server" (the one
# we can probe over loopback). An EMPTY provider falls back to the profile
# default, which is the local `custom`/llama.cpp provider — so empty is local.
LOCAL_PROVIDERS = {"", "localhost", "custom", "llama.cpp"}

# Local llama.cpp OpenAI-compatible endpoint. 127.0.0.1 (not `localhost`, which
# can resolve to IPv6 ::1 inside some host setups), matching the serving config.
LOCAL_MODEL_URL = "http://127.0.0.1:11434/v1/models"

# Activity-based worker liveness (issue #63, refined by issue #69). A worker whose
# PID is alive but whose own log has NOT grown for this many seconds is considered
# STUCK (hung, not dead): its process tree is killed and the issue is re-driven
# from its own log.
#
# issue #69 refinement: this horizon must be LONG (hours), because hermes chat
# `-Q`/`--oneshot` buffers ALL its stdout until the process EXITS — it never streams
# mid-run. A productive-but-slow worker (OpenSpec -> implement -> validate -> test ->
# push -> PR on the slow local `llm-local`) legitimately stays silent on its log for
# well over the old 40-min window, so a short horizon killed healthy workers every
# tick before they could commit. Liveness is instead guaranteed by the spawn-wrapper
# heartbeat (WORKER_LOG_HEARTBEAT_SECONDS below), which advances the worker's log
# every few minutes WHILE its hermes child is alive; a worker therefore only reaches
# this silence when its heartbeat has stopped (the process tree is gone/wedged).
# Dead-PID reclaim (issue #18) already handles an exited tree immediately. Injection
# point for hermetic tests.
STUCK_LOG_STALE_SECONDS = int(os.environ.get("STUCK_LOG_STALE_SECONDS", "14400"))

# Spawn-wrapper heartbeat cadence (issue #69). The worker launch command runs hermes
# in the background and appends a `[hb <epoch>]` line to the worker's own log every
# this-many seconds as long as the hermes child is alive. Because hermes -Q buffers
# stdout until exit, this heartbeat is what makes a live worker's log advance, so the
# stuck detector above never mistakes a productive-but-slow worker for a hung one.
WORKER_LOG_HEARTBEAT_SECONDS = int(os.environ.get("WORKER_LOG_HEARTBEAT_SECONDS", "300"))


def effective_provider_is_local() -> bool:
    """True if the effective worker provider targets the local llama.cpp server."""
    return WORKER_PROVIDER.strip().lower() in LOCAL_PROVIDERS


def probe_worker_model(model: str, url: str = LOCAL_MODEL_URL, timeout: int = 10) -> bool:
    """Pre-spawn probe (issue #37): is the local worker model actually served?

    GETs the llama.cpp OpenAI-compatible `v1/models` endpoint and returns True
    iff *model* appears in the returned `data[].id` (or `model`) list. Fails
    CLOSED — unreachable, non-2xx, non-JSON body, or model not listed all
    return False — and NEVER raises, so a down server skips the spawn cleanly
    instead of wedging the whole tick. Isolated to this one function so unit
    tests can monkeypatch it (or stub `urllib.request.urlopen`) hermetically.
    """
    try:
        req = urllib.request.Request(url, headers={"Accept": "application/json"})
        with urllib.request.urlopen(req, timeout=timeout) as resp:
            payload = json.loads(resp.read().decode() or "{}")
    except Exception:
        return False
    data = payload.get("data") if isinstance(payload, dict) else None
    if not isinstance(data, list):
        return False
    for entry in data:
        if isinstance(entry, dict) and (entry.get("id") == model or entry.get("model") == model):
            return True
    return False

os.makedirs(LOGS, exist_ok=True)
os.makedirs(RUN, exist_ok=True)


def load_token() -> str:
    for var in ("GITHUB_TOKEN", "GH_TOKEN"):
        if os.environ.get(var):
            return os.environ[var]
    try:
        with open(f"{REPO}/.env") as f:
            for line in f:
                line = line.strip()
                for var in ("GITHUB_TOKEN", "GH_TOKEN"):
                    if line.startswith(f"{var}="):
                        return line.split("=", 1)[1].strip().strip("\"'")
    except FileNotFoundError:
        pass
    raise SystemExit("[dispatch] no GITHUB_TOKEN found")


TOK = load_token()
HEADER = {"Authorization": f"Bearer {TOK}", "Accept": "application/vnd.github+json"}


def api(path: str, method: str = "GET", body=None):
    data = json.dumps(body).encode() if body is not None else None
    req = urllib.request.Request(API + path, data=data, headers=HEADER, method=method)
    try:
        with urllib.request.urlopen(req, timeout=30) as resp:
            raw = resp.read()
            return json.loads(raw) if raw else None
    except urllib.error.HTTPError:
        return None  # fail closed: any API problem -> don't act


def log(msg: str) -> None:
    line = f"[dispatch {time.strftime('%H:%M:%S')}] {msg}"
    print(line)
    with open(f"{RUN}/dispatch.log", "a") as f:
        f.write(line + "\n")


# ------------------------------------------------------------------ helpers
def pr_is_behind(pr) -> bool:
    """True if PR head is BEHIND main / unverifiable (never merge those)."""
    cmp = api(f"/compare/{pr['base']['sha']}...{pr['head']['sha']}")
    if not isinstance(cmp, dict):
        return True
    return cmp.get("status") not in ("identical", "ahead")


def pr_approved(pr_num: int) -> bool:
    rv = api(f"/pulls/{pr_num}/reviews")
    if not isinstance(rv, list):
        return False
    return any(r.get("state") == "APPROVED" for r in rv)


def pr_open_threads(pr_num: int) -> bool:
    comments = api(f"/pulls/{pr_num}/comments")
    reviews = api(f"/pulls/{pr_num}/reviews/comments")
    if not isinstance(comments, list):
        comments = []
    if not isinstance(reviews, list):
        reviews = []
    return any(not c.get("resolved", True) for c in comments + reviews)


def ci_green(pr) -> bool:
    checks = api(f"/commits/{pr['head']['sha']}/check-runs")
    if not isinstance(checks, dict) or "check_runs" not in checks:
        return False  # no checks data -> not green
    runs = checks["check_runs"]
    if not runs:
        return True  # no checks configured
    for cr in runs:
        if cr.get("status") == "completed" and cr.get("conclusion") in (
            "failure",
            "cancelled",
            "timed_out",
        ):
            return False
        if cr.get("status") in ("queued", "in_progress"):
            return False
    return True


def merge_pr(pr) -> None:
    n = pr["number"]
    log(f"MERGING PR #{n} ({pr['head']['ref']} -> main)")
    # issue #45: request branch deletion at merge time. GitHub's
    # delete_branch_on_merge repo setting only applies to UI-button merges,
    # NOT API merges, so the body flag is what kills the remote branch here;
    # cleanup_merged_worktrees is the safety net for anything that slips through.
    res = api(f"/pulls/{n}/merge", method="PUT",
              body={"merge_method": "merge", "delete_branch": True})
    log(f"  merge result: {str(res)[:160]}")


def run_git(*args) -> subprocess.CompletedProcess:
    return subprocess.run(["git", "-C", REPO, *args], capture_output=True, text=True)


def sync_pr_with_main(pr) -> bool:
    """Bring a behind PR's head up to date with latest origin/main (issue #9).

    issue #9: a PR that is behind main MUST NOT be merged out of sync. Instead of
    merely skipping it, forward-merge origin/main into the PR branch so it no longer
    drifts, then let CI re-run so the gate re-attempts on a later tick. Conflicts are
    never auto-resolved — if a merge conflict arises, leave the branch for its worker
    to resolve and return False (the PR stays NOT merged).
    Returns True if the PR head is now in sync with origin/main, False otherwise.
    """
    head_ref = pr["head"]["ref"]
    head_sha = pr["head"]["sha"]
    n = pr["number"]
    r = run_git("fetch", "origin", f"+refs/heads/{head_ref}:refs/remotes/origin/{head_ref}")
    if r.returncode != 0:
        log(f"  PR#{n}: sync fetch failed for {head_ref}: {r.stderr.strip()[:120]}")
        return False
    run_git("branch", "-D", "_dispatch_sync")  # clear any stale temp branch
    r = run_git("branch", "_dispatch_sync", f"origin/{head_ref}")
    if r.returncode != 0:
        log(f"  PR#{n}: cannot create temp sync ref: {r.stderr.strip()[:120]}")
        return False
    r = run_git(
        "merge", "origin/main", "--no-ff",
        "-m", f"chore: sync to latest origin/main before merge (issue #9, PR #{n})",
    )
    if r.returncode != 0:
        run_git("merge", "--abort")
        run_git("branch", "-D", "_dispatch_sync")
        log(f"  PR#{n}: merge conflict syncing {head_ref} onto origin/main -> needs manual "
            f"resolution, NOT merged (issue #9)")
        return False
    # Advance the PR branch to the synced head. force-with-lease pins to the known sha
    # so we never clobber newer commits a worker pushed concurrently.
    r = run_git(
        "push", "origin", "_dispatch_sync:" + head_ref,
        f"--force-with-lease={head_ref}:{head_sha}",
    )
    run_git("branch", "-D", "_dispatch_sync")
    if r.returncode != 0:
        log(f"  PR#{n}: sync push failed for {head_ref}: {r.stderr.strip()[:160]}")
        return False
    log(f"  PR#{n}: {head_ref} synced to origin/main (merge forward); CI must re-run, "
        "re-attempting gate next tick")
    return True


def process_merge_gate(prs) -> set:
    """Merge merge-ready PRs; return the set of issue numbers closed this tick."""
    resolved_this_tick: set = set()
    for pr in prs:
        if not isinstance(pr, dict):
            continue
        n = pr["number"]
        if pr_is_behind(pr):
            log(f"  PR#{n}: behind main (or unverifiable) -> NEVER merge as-is (issue #9)")
            if sync_pr_with_main(pr):
                log(f"  PR#{n}: synced to origin/main; will re-attempt gate after CI ")
            continue
        if not pr_approved(n):
            log(f"  PR#{n}: not approved -> NOT merged")
            continue
        if pr_open_threads(n):
            log(f"  PR#{n}: open threads -> NOT merged")
            continue
        if not ci_green(pr):
            log(f"  PR#{n}: CI not green -> NOT merged")
            continue
        merge_pr(pr)
        resolved_this_tick |= closing_issues(pr.get("body") or "")
    return resolved_this_tick


# ------------------------------------------------------------------ spawner
def closing_issues(body) -> set:
    """Return the set of issue numbers a PR body explicitly claims to close.

    Uses a deliberate closing keyword (Closes/Fixes/Resolves #N), NOT a bare
    `#N` substring — a PR may mention another issue in prose (e.g. "the issue
    #94 guard") without closing it, and a substring match would wrongly suppress
    spawning a worker for that issue.
    """
    if not body:
        return set()
    closes_re = re.compile(r"(?i)(close|closes|closed|fix|fixes|fixed|resolve|resolves|resolved)\s*#\s*(\d+)")
    return {int(m.group(2)) for m in closes_re.finditer(body)}


def pid_alive(pid: int) -> bool:
    """True only if *pid* is a live process on this host.

    A zombie still answers ``kill(pid, 0)`` until it is reaped. In the CI
    container nothing reaps the SIGKILLed worker, so the e2e check stayed red.
    ``ps -o stat=`` is Z for a zombie on both Linux and macOS.
    """
    if not pid or pid <= 0:
        return False
    try:
        out = subprocess.run(
            ["ps", "-o", "stat=", "-p", str(pid)],
            capture_output=True, text=True,
        )
    except Exception:
        return False
    stat = (out.stdout or "").strip()
    if out.returncode != 0 or not stat:
        return False
    return not stat.startswith("Z")


def _children_of(pid: int) -> list[int]:
    """Child PIDs of *pid* via `pgrep -P` — the single code path.

    `pgrep -P <pid>` lists the DIRECT children of *pid*; the recursive walk in
    `kill_process_tree` descends the whole tree. Both the macOS host and the Linux
    CI test container ship `/usr/bin/pgrep`, so this one invocation is sufficient
    everywhere — there is deliberately no second /proc implementation (AGENTS.md:
    no dual paths for the same resource). A missing/unrunnable pgrep yields no
    children and the caller simply gives up killing that branch.
    """
    try:
        out = subprocess.run(
            ["pgrep", "-P", str(pid)], capture_output=True, text=True
        ).stdout
        return [int(t) for t in (out or "").split() if t.strip().isdigit()]
    except Exception:
        return []


def kill_process_tree(pid: int, _seen: set[int] | None = None) -> None:
    """Best-effort kill of *pid* and every descendant (issue #63).

    The recorded `.running` PID is the /bin/bash -lc parent of the hermes worker,
    so killing it alone would orphan the hermes child. We first collect and kill
    all children (recursively) before the parent, so the whole tree dies. Any PID
    that is already gone or unkillable is silently tolerated.
    """
    seen = _seen if _seen is not None else set()
    if not pid or pid <= 0 or pid in seen:
        return
    seen.add(pid)
    for child in _children_of(pid):
        kill_process_tree(child, seen)
    try:
        os.kill(pid, signal.SIGKILL)
    except (ProcessLookupError, PermissionError, OSError):
        pass


def log_stale_seconds(branch_log: str, now: float | None = None) -> float | None:
    """Seconds since the worker's own log was last written; None if it doesn't exist.

    `None` (no log) means "no evidence of a hang" — a freshly spawned worker that
    hasn't flushed yet must never be mistaken for a stuck one. Takes an injectable
    `now` so hermetic tests can stub the clock.
    """
    now = now if now is not None else time.time()
    try:
        return now - os.path.getmtime(branch_log)
    except OSError:
        return None


def worker_is_stuck(live_pid: int, branch_log: str, now: float | None = None) -> bool:
    """One health predicate (issue #63): a live worker that is making NO progress.

    A worker is STUCK only when its PID is alive (the old issue #18 alive-check) AND
    its own log has not grown for more than `STUCK_LOG_STALE_SECONDS`. A dead PID is
    NOT ``stuck`` — the existing dead-PID clean+respawn path stays untouched. A
    missing or fresh log is NOT stuck (no kill), so slow-but-progressing workers
    (single `llm-local` call ~170s, large-model download) survive.
    """
    if not pid_alive(live_pid):
        return False
    stale = log_stale_seconds(branch_log, now)
    if stale is None:
        return False
    return stale > STUCK_LOG_STALE_SECONDS


def issue_has_pr(issue_num: int) -> bool:
    """True if ``some open PR's body CLOSES this issue (Closes/Fixes/Resolves #N).``"""
    prs = api("/pulls?state=open&per_page=100")
    if not isinstance(prs, list):
        return False
    return any(issue_num in closing_issues(pr.get("body") or "") for pr in prs)


def _branch_exists(branch: str) -> bool:
    """True if *branch* exists locally (refs/heads) or on origin (refs/remotes).

    Uses `git show-ref --verify --quiet` which exits 0 only when the exact
    ref exists — no network, no fuzzy matching.
    """
    for ref in (f"refs/heads/{branch}", f"refs/remotes/origin/{branch}"):
        r = subprocess.run(
            ["git", "-C", REPO, "show-ref", "--verify", "--quiet", ref],
            capture_output=True,
        )
        if r.returncode == 0:
            return True
    return False


def ensure_worktree(branch: str, slug: str) -> str:
    wd = f"{REPO}/../llgenie-wt/{slug}"
    # Always refresh the remote tip first so BOTH new and existing worktrees
    # branch/resume from the newest origin/main, not a stale one.  The fetch
    # also makes `origin/<branch>` visible so _branch_exists can see remote-only
    # branches (repair path, issue #46).
    subprocess.run(["git", "-C", REPO, "fetch", "--all", "--prune"], capture_output=True)
    subprocess.run(["git", "-C", REPO, "fetch", "origin", "main"], capture_output=True)

    def rebase_if_behind():
        """Rebase <branch> onto the latest origin/main if it is behind."""
        r = subprocess.run(
            ["git", "-C", wd, "merge-base", "--is-ancestor", "origin/main", "HEAD"],
            capture_output=True,
        )
        if r.returncode == 0:
            return  # already at/after main
        subprocess.run(["git", "-C", wd, "rebase", "origin/main"], capture_output=True)
        log(f"  rebased {branch} onto latest origin/main (was behind)")

    if not os.path.isdir(wd):
        if _branch_exists(branch):
            # Branch already exists (repair / resume): attach to it WITHOUT -b
            # so git never reports "a branch named ... already exists" (rc 255).
            r = subprocess.run(
                ["git", "-C", REPO, "worktree", "add", wd, branch],
                capture_output=True,
                text=True,
            )
            log(f"  worktree {wd} attach rc={r.returncode}: {r.stderr.strip()[:120]}")
        else:
            # Fresh orphan-issue spawn: create the branch from origin/main.
            r = subprocess.run(
                ["git", "-C", REPO, "worktree", "add", "-b", branch, wd, "origin/main"],
                capture_output=True,
                text=True,
            )
            log(f"  worktree {wd} add rc={r.returncode}: {r.stderr.strip()[:120]}")
    else:
        # Existing worktree: bump the branch to the current remote tip before
        # the worker resumes — never let an approved/PR branch sit behind main.
        rebase_if_behind()
    return wd


# ------------------------------------------------------------------ cleanup
def _read_pid(path: str) -> int:
    """Return the PID stored in *path*, or 0 if absent/unparseable."""
    try:
        return int((open(path).read() or "0").strip() or 0)
    except (ValueError, OSError):
        return 0


def _git_worktrees() -> list[dict]:
    """Parse `git worktree list --porcelain` -> [{path, branch|None}, ...]."""
    r = subprocess.run(
        ["git", "-C", REPO, "worktree", "list", "--porcelain"],
        capture_output=True, text=True,
    )
    entries: list[dict] = []
    cur: dict = {}
    for ln in r.stdout.splitlines():
        if ln.startswith("worktree "):
            if cur:
                entries.append(cur)
            cur = {"path": ln.split(maxsplit=1)[1]}
        elif ln.startswith("branch "):
            cur["branch"] = ln.split(maxsplit=1)[1].removeprefix("refs/heads/")
    if cur:
        entries.append(cur)
    return entries


def _merged_into_main(branch: str) -> bool:
    """True if <branch> is an ancestor of origin/main (its work already merged)."""
    r = subprocess.run(
        ["git", "-C", REPO, "merge-base", "--is-ancestor", branch, "origin/main"],
        capture_output=True, text=True,
    )
    return r.returncode == 0


def _worker_artifacts(slug: str) -> list[str]:
    """The per-worker lock/prompt/log files for a worktree slug (issue #29)."""
    stem = f"{RUN}/worker-feat_{slug}"
    return [f"{stem}.running", f"{stem}.prompt", f"{LOGS}/feat-{slug}.log"]


def _remote_branch_exists(branch: str) -> bool:
    """True if `origin` still has the named branch (issue #45)."""
    r = subprocess.run(
        ["git", "-C", REPO, "ls-remote", "--heads", "origin", branch],
        capture_output=True, text=True,
    )
    return r.returncode == 0 and bool(r.stdout.strip())


def _delete_remote_branch(branch: str, dry: bool = False) -> None:
    """Delete a merged branch from `origin` (issue #45) — the safety net.

    `merge_pr` already requests `delete_branch: true` at merge time, but the
    merge API does not always delete (UI merges, older behaviour), so this is
    the backstop. Only ever deletes branches that still exist on origin and is
    never called for `main` (its caller guards that). In dry-run it only logs.
    """
    if branch == "main":
        log(f"  [clean] {branch}: merged but it is main — never delete remote")
        return
    if not _remote_branch_exists(branch):
        log(f"  [clean] {branch}: remote branch already gone — skip remote delete")
        return
    if dry:
        log(f"  [dry] would delete remote origin/{branch}")
        return
    r = subprocess.run(
        ["git", "-C", REPO, "push", "origin", "--delete", branch],
        capture_output=True, text=True,
    )
    if r.returncode == 0:
        log(f"  [clean] {branch}: remote branch deleted from origin")
    else:
        log(f"  [clean] {branch}: remote delete failed (next tick retries): "
            f"{(r.stderr or r.stdout or '').strip()[:160]}")


def cleanup_merged_worktrees(dry: bool = False) -> set:
    """Auto-clean worktrees + branches of PRs already merged (issue #29).

    After a PR merges, its worktree + local branch + worker lock/prompt/log files
    become stale and accumulate. This sweep removes every `feat/*` worktree under
    WORKTREE_BASE whose HEAD is an ancestor of origin/main (fully merged), and
    NEVER touches:
      * in-flight worktrees (HEAD NOT merged into origin/main) — open PRs stay, and
      * a merged worktree whose per-worker .running PID is still alive.
    issue #45: it ALSO deletes the REMOTE branch of every cleaned branch
    (`git push origin --delete <branch>`) when origin still has it — the safety
    net for `merge_pr`'s `delete_branch: true` — and never deletes `main`.
    Returns the set of cleaned branches (also reported in dry-run).
    """
    # Freshen remotes so the ancestry check is against latest origin/main.
    subprocess.run(["git", "-C", REPO, "fetch", "--all", "--prune"], capture_output=True)
    subprocess.run(["git", "-C", REPO, "fetch", "origin", "main"], capture_output=True)

    base = os.path.abspath(WORKTREE_BASE)
    cleaned: set = set()
    for wt in _git_worktrees():
        path = wt.get("path")
        branch = wt.get("branch")
        if not path or not branch or not branch.startswith("feat/"):
            continue
        try:
            if os.path.commonpath([os.path.abspath(path), base]) != base:
                continue  # not one of the dispatcher's scratch worktrees
        except ValueError:
            continue  # different root -> not under base
        if not _merged_into_main(branch):
            log(f"  [clean] {branch}: not merged (in flight) — keep")
            continue
        slug = os.path.basename(path)
        # Post-worker-exit only: never delete anything a live worker still owns.
        if pid_alive(_read_pid(f"{RUN}/worker-feat_{slug}.running")):
            log(f"  [clean] {branch}: merged but worker still ALIVE — keep")
            continue
        if dry:
            log(f"  [dry] would clean merged {branch} worktree {path}")
            _delete_remote_branch(branch, dry=True)  # reports, does not delete
            cleaned.add(branch)
            continue
        log(f"  [clean] merged {branch} -> removing worktree {path}")
        subprocess.run(["git", "-C", REPO, "worktree", "remove", "--force", path],
                       capture_output=True, text=True)
        subprocess.run(["git", "-C", REPO, "branch", "-D", branch],
                       capture_output=True, text=True)
        for f in _worker_artifacts(slug):
            try:
                os.remove(f)
            except OSError:
                pass
        _delete_remote_branch(branch)  # issue #45: remote safety net
        cleaned.add(branch)
    return cleaned


def worker_prompt(num: int, title: str, slug: str, branch: str, wd: str, branch_log: str) -> str:
    return f"""You are the DEDICATED worker for llgenie issue #{num} ("{title}").

Context: repo={REPO}, worktree={wd}, branch={branch}. AGENTS.md is loaded (cwd)
and is your durable rulebook — follow its Background watch loop + OpenSpec-first
+ continuous sync rules. Work ONLY this one issue.

PARALLEL-SAFETY (MANDATORY, non-negotiable): this worker runs in PARALLEL with
other issue workers on the SAME machine. To avoid any collision on the shared
nerdctl test container or the loop-harness:
  * Run EVERY containerized `make` target (openspec-*, test-unit, test-install,
    lint, lint-fix, test) through the shared lock via the helper (macOS has no
    `flock` command):
        python3 {REPO}/scripts/serialized-make.py {REPO}/.watchloop/run/test.lock -- <target> <args>
    This blocks until the lock is free, so only one worker drives the container
    at a time.
  * NEVER run `make loop-harness`, `make test-install-host`, or `make test` — those
    are the harness's own orchestrated steps.
  * Work ONLY in {wd} on {branch}. Push only {branch} to origin.
  * If a run is interrupted, the lock auto-releases when the helper process ends.

Per the issue body + AGENTS.md:
1) OpenSpec change FIRST: cd {wd} && make openspec-new NAME={slug}. Write
   proposal.md/spec/tasks describing the change (docs-only => skip_specs:true).
2) Implement in {wd} on {branch}.
3) STAGE FIRST, then Validate (all via flock): git -C {wd} add -A; then
   openspec-validate NAME={slug} exit 0; lint-fix (scripts/lint_linefeeds.py --fix so
   any fresh file's missing trailing newline is repaired NOW); lint; test-unit. Run lint
   AGAIN after staging so freshly-written files are picked up by git ls-files.
4) Keep issue body, OpenSpec change, and code/files in sync.
5) Push: git -C {wd} push origin {branch} (use URL-embedded token from {REPO}/.env
   if the keyring token is revoked).
6) Open a PR against main referencing issue #{num} (curl, token from {REPO}/.env).
   PR body MUST reference it, and per issue #9 never merge if behind main.
7) APPEND your progress to {branch_log} (your own log only).

Resume: if a prior tick already scaffolded OpenSpec or opened partial work, continue
it (read {branch_log}); do not restart wasted. ALWAYS first bring the branch up to
date: run `git -C {wd} fetch origin main` and, if your branch tip is BEHIND
origin/main (`git merge-base --is-ancestor origin/main HEAD` fails), run
`git -C {wd} rebase origin/main` and resolve any conflicts yourself before
continuing work — never sit behind main (issue #9). If you rebased a branch that
already has an open PR, update it with `git push --force-with-lease`, never a
plain force-push and never push to main. End final answer with a
'WATCH-LOOP SUMMARY'. No time limit.
"""


# ------------------------------------------------------------------ stuck-PR repair
# issue #42: when an OPEN PR is NOT mergeable because of actionable, fixable
# reasons (unresolved review threads, or RED CI), the loop respawns the PR's
# dedicated worker (the configured model, e.g. local llm-local) bound to the
# PR's EXISTING branch/worktree to "repair" it: read the comments, fix root
# cause, add regression tests, commit + push (force-with-lease) so CI turns
# green and threads resolve, and the PR reaches the merge gate.
#
# NOT repairable (skipped — human-only):
#   * "not approved" alone: approval is a human decision, never auto-driven.
#   * "behind main": the merge gate owns syncing (issue #9), not the worker.
#   * no issue number in the PR body: cannot map back to a worker identity.
#
# The repair spawn reuses spawn_worker's ATOMIC O_CREAT|O_EXCL lock + the
# pre-spawn local-model probe, so it never duplicates a live worker and fails
# closed if the local llama.cpp server is down.

def slug_from_branch(branch: str) -> str:
    """The worktree/lock slug for a PR branch (drops the `feat/` prefix)."""
    return branch.removeprefix("feat/")


def pr_repairable(pr, n: int) -> str:
    """Classify an unmerged open PR. Returns '' if NOT actionable, else why.

    Actionable (worker can fix): unresolved review threads, or red CI.
    Ignored (human/merge-gate owns it): behind main, not-approved-only, or a
    PR with no closing-issue keyword. Never raises on incomplete PR dicts.
    """
    try:
        if pr_open_threads(n):
            return "unresolved review threads"
        if not ci_green(pr):
            return "CI is red"
    except (KeyError, TypeError):
        return ""
    return ""


def pr_issue_number(pr) -> int | None:
    """Map an open PR back to its issue via the closure keyword in its body."""
    closed = closing_issues(pr.get("body") or "")
    return max(closed) if closed else None


def repair_prompt(num: int, title: str, slug: str, branch: str, wd: str,
                  branch_log: str, reasons: list[str]) -> str:
    """Prompt for a REPAIR worker bound to an existing PR (issue #42)."""
    why = "; ".join(reasons)
    return f"""You are the DEDICATED REPAIR worker for llgenie issue #{num} ("{title}").

Context: repo={REPO}, worktree={wd}, branch={branch}. AGENTS.md is loaded (cwd)
and is your durable rulebook. An OPEN PR already exists for this work ({branch});
it is NOT mergeable and the loop asked you to REPAIR it.

WHY THIS PR IS STUCK: {why}.

PARALLEL-SAFETY (MANDATORY, non-negotiable): runs in PARALLEL with other workers.
  * Run EVERY containerized `make` target through the shared lock:
        python3 {REPO}/scripts/serialized-make.py {REPO}/.watchloop/run/test.lock -- <target> <args>
  * NEVER run `make loop-harness`, `make test-install-host`, or `make test`.
  * Work ONLY in {wd} on {branch}. Push only {branch} to origin.

REPAIR STEPS (do NOT reopen the issue / do NOT make a new PR):
1) FIRST bring the branch up to date: cd {wd} && git fetch origin main; if
   `git merge-base --is-ancestor origin/main HEAD` fails, run
   `git rebase origin/main` and resolve any conflicts yourself (issue #9).
2) Read the OPEN review threads on the PR (curl the PR comments endpoint,
   token from {REPO}/.env). For EACH comment: fix the root cause, add a
   regression test if applicable, and verify with the real `make` gates:
   openspec-validate NAME={slug} exit 0; lint-fix; lint; test-unit (all via flock).
3) Commit + push NORMAL (non-squashed) conventional commits; update the PR
   branch with `git push --force-with-lease` if you had to rebase — never a
   plain force-push, never push to main.
4) Reply to EVERY review thread with the fixing commit sha + root cause
   (curl POST /pulls/<N>/comments/<ID>/replies).
5) Repeat until CI is green and all threads are resolved. If a thread or a red
   check is NOT something you can fix (needs a human / external), say so plainly
   in your final summary and leave it — do NOT loop forever burning tokens.
6) APPEND your progress to {branch_log}. End final answer with a
   'REPAIR SUMMARY'. No time limit."""


def _spawn_worker_for_branch(branch: str, slug: str, wd: str, branch_log: str,
                             lk: str, prompt: str, log_prefix: str) -> bool:
    """Shared atomic lock + spawn for both fresh and repair workers. Returns True
    if a worker was spawned (or resumed), False if a live lock suppressed it."""
    lk_fd = None
    try:
        lk_fd = os.open(lk, os.O_CREAT | os.O_EXCL | os.O_WRONLY)
    except OSError:
        lk_fd = None

    if lk_fd is None:
        try:
            live_pid = int((open(lk).read() or "0").strip() or 0)
        except (ValueError, OSError):
            live_pid = 0
        if worker_is_stuck(live_pid, branch_log):
            # issue #63: a LIVE-but-HUNG worker — PID alive yet its own log has
            # not grown for > STUCK_LOG_STALE_SECONDS. Kill the process tree,
            # drop the lock, and let the orphan spawn re-drive the issue from
            # its (stale) log. worker_is_stuck already returns False for a dead
            # pid (pid_alive short-circuits) or an empty/missing log, so the
            # existing dead-PID path below stays the ONLY dead-PID resume path.
            log(f"  {log_prefix}: worker stuck (pid={live_pid}, log stale"
                f" > {STUCK_LOG_STALE_SECONDS}s); killing tree + resuming")
            kill_process_tree(live_pid)
            try:
                os.remove(lk)
                lk_fd = os.open(lk, os.O_CREAT | os.O_EXCL | os.O_WRONLY)
            except OSError:
                log(f"  {log_prefix}: lock re-acquired elsewhere; skip")
                return False
        elif pid_alive(live_pid):
            # issue #18: a LIVE worker with a FRESH log is healthy — suppress spawn.
            log(f"  {log_prefix}: worker already running (pid={live_pid}, {lk}); skip")
            return False
        else:
            # empty lock, unreadable, or a DEAD recorded pid => issue #18 clean + resume.
            try:
                os.remove(lk)
                lk_fd = os.open(lk, os.O_CREAT | os.O_EXCL | os.O_WRONLY)
            except OSError:
                log(f"  {log_prefix}: lock re-acquired elsewhere; skip")
                return False
            log(f"  {log_prefix}: stale lock pid={live_pid} dead; removing + resuming worker")

    # Invariant: by this point every branch that didn't return has acquired the
    # lock (initial os.open, or one of the remove+reopen paths above), so lk_fd
    # is open and we can record the fresh worker PID into it below.
    assert lk_fd is not None, "bug: reached spawn without holding the worker lock"

    ensure_worktree(branch, slug)
    prompt_file = f"{RUN}/worker-{branch.replace('/', '_')}.prompt"
    with open(prompt_file, "w") as f:
        f.write(prompt)
    # The worker log is this worker's liveness signal (issue #63/#69): the stuck
    # detector reclaims a live worker whose log has not grown for
    # STUCK_LOG_STALE_SECONDS. hermes chat -Q/--oneshot buffers ALL its stdout until
    # process exit (never streaming mid-run), so we launch hermes in the background
    # and a heartbeat loop appends a `[hb <epoch>]` line to the log every
    # WORKER_LOG_HEARTBEAT_SECONDS as long as the hermes child is alive. A live,
    # productive worker's log therefore advances every few minutes and can never
    # reach the (hours-long) stuck horizon; only when the child/wrapper tree dies or
    # wedges does the log go silent and the issue get re-driven. The recorded PID is
    # this wrapper bash, which stays alive until hermes exits, so kill_process_tree
    # on it (issue #63) still kills the whole tree.
    model_flag = f"-m {WORKER_MODEL} " if WORKER_MODEL else ""
    provider_flag = f"--provider {WORKER_PROVIDER} " if WORKER_PROVIDER else ""
    cmd = (
        f"cd {wd}\n"
        f"HERMES_PROFILE=project-manager {HERMES} chat "
        f"--query-file {prompt_file} -t terminal,file,web --yolo -Q "
        f"{model_flag}{provider_flag}"
        f">> {branch_log} 2>&1 &\n"
        f"CHILD=$!\n"
        f"while kill -0 \"$CHILD\" 2>/dev/null; do\n"
        f"  sleep {WORKER_LOG_HEARTBEAT_SECONDS}\n"
        f"  printf '[hb %s]\\n' \"$(date +%s)\" >> {branch_log} 2>/dev/null || break\n"
        f"done\n"
        f"wait \"$CHILD\"\n"
        f"exit $?\n"
    )
    log(f"  {log_prefix}: spawning worker branch={branch} log={branch_log}")
    proc = subprocess.Popen(["/bin/bash", "-lc", cmd], env=dict(os.environ))
    os.write(lk_fd, str(proc.pid).encode())
    os.close(lk_fd)
    return True


def spawn_worker(issue) -> None:
    num = issue["number"]
    title = issue["title"]
    slug = (re.sub(r"[^a-z0-9]+", "-", title.lower()).strip("-") or f"issue-{num}")[:50]
    branch = f"feat/{slug}"
    wd = f"{REPO}/../llgenie-wt/{slug}"
    branch_log = f"{LOGS}/feat-{slug}.log"
    lk = f"{RUN}/worker-{branch.replace('/', '_')}.running"

    # ATOMIC lock acquire: os.open with O_CREAT|O_EXCL is an atomic
    # check-and-create — exactly one of N concurrent dispatchers wins, the
    # rest get EEXIST. This closes the TOCTOU race where two dispatchers both
    # pass os.path.exists(lk) and both spawn a worker (issue #23 doubled tick).
    # We hold the lock file open until the worker's real PID is recorded.
    prompt = worker_prompt(num, title, slug, branch, wd, branch_log)
    _spawn_worker_for_branch(branch, slug, wd, branch_log, lk, prompt,
                             f"issue#{num}")


def spawn_repair_worker(pr) -> bool:
    """Respawn a worker to REPAIR an existing stuck PR (issue #42).

    Returns True if a repair worker was spawned/resumed. Uses the PR's EXISTING
    branch + worktree + lock (never a new branch/PR). Respects the .running PID
    lock and the pre-spawn local-model probe.
    """
    branch = pr.get("head", {}).get("ref", "")
    if not branch:
        log("  [repair] PR has no head ref; skip")
        return False
    num = pr_issue_number(pr)
    if num is None:
        log(f"  [repair] PR#{pr.get('number')} ({branch}): no closing issue in body; "
            "cannot map to a worker — skip")
        return False
    slug = slug_from_branch(branch)
    wd = f"{REPO}/../llgenie-wt/{slug}"
    branch_log = f"{LOGS}/feat-{slug}.log"
    lk = f"{RUN}/worker-{branch.replace('/', '_')}.running"
    reasons = pr.get("_repair_reasons", [])
    prompt = repair_prompt(num, pr["title"], slug, branch, wd, branch_log, reasons)
    return _spawn_worker_for_branch(
        branch, slug, wd, branch_log, lk, prompt, f"repair-PR#{pr['number']}")


def process_stuck_prs(prs, dry: bool = False) -> None:
    """issue #42: respawn a REPAIR worker for actionable stuck open PRs.

    Called AFTER the merge gate and the orphan-issue spawner. Skips PRs already
    merged this tick, live-workered PRs (handled by the atomic lock), and
    non-actionable PRs (behind only / not-approved only / no issue mapping, or
    an incomplete PR dict). Never crashes the tick on a malformed entry.
    """
    for pr in prs:
        if not isinstance(pr, dict):
            continue
        n = pr.get("number")
        if n is None:
            continue
        # Guard against minimal/incomplete PR dicts (tests, API edge cases).
        head = pr.get("head")
        if not isinstance(head, dict) or not head.get("ref"):
            continue  # no head ref -> can't bind a worker to a branch
        base = pr.get("base")
        try:
            if pr_is_behind(pr):
                # merge gate (issue #9) owns syncing behind PRs; never worker-repair
                continue
        except (KeyError, TypeError):
            continue  # incomplete base/head -> cannot classify; skip
        reason = pr_repairable(pr, n)
        if not reason:
            continue
        pr = dict(pr)
        pr["_repair_reasons"] = [reason]
        if dry:
            log(f"  [DRY] would spawn a repair worker for PR#{n} ({pr['head']['ref']}): {reason}")
            continue
        if effective_provider_is_local():
            if not probe_worker_model(WORKER_MODEL_EFFECTIVE):
                log(f"  repair-PR#{n}: worker model {WORKER_MODEL_EFFECTIVE} unreachable"
                    f" on {LOCAL_MODEL_URL} — skipping repair")
                continue
        spawn_repair_worker(pr)


# ---------------------------------------------------------------------- main
TICK_LOCK = f"{RUN}/dispatch.tick.lock"

# The cron slot fires every */20 minutes. Two cron fires in the same coarse
# interval bucket are "the same tick". A plain O_CREAT|O_EXCL lock that is
# released synchronously at main()'s end only catches a *tight* overlap window:
# once the first invocation finishes (and its finally-release deletes the lock),
# a re-fire in the same interval re-acquires and runs again -- the phantom
# double-fire. Holding the lock for the whole interval (released only when the
# bucket changes) is what makes "exactly one main() per cron tick" durable.
TICK_INTERVAL_SECONDS = 20 * 60

# The read -> decide -> write of TICK_LOCK MUST be one mutually-exclusive step
# (issue #62). The old reclaim path did `os.remove(TICK_LOCK)` followed by
# `os.open(TICK_LOCK, O_CREAT|O_EXCL)`, which is NOT atomic: a double cron-fire
# could let P2 remove the lock P1 JUST created, so BOTH processes ran main().
# We therefore take a SHORT-LIVED advisory flock on this separate meta-lock
# file around the whole decision. The meta-lock is released immediately after
# the write -- it is NOT the durable lock. The durable dedup remains the bucket
# recorded INSIDE TICK_LOCK (issues #27/#30), which a same-bucket re-fire reads
# and dedups on even after the meta-lock is free and the winner has exited.
TICK_LOCK_META = f"{RUN}/dispatch.tick.lock.meta"

# Bounded retries for the meta-lock decision. The critical section is a
# few-syscall read/write (microseconds), so a handful of immediate retries
# covers the normal case where a sibling recoverer is mid-decision.
META_LOCK_ATTEMPTS = 8


def _tick_meta_path() -> str:
    """Resolve the meta-lock path from the CURRENT TICK_LOCK value.

    Deriving it at call time (rather than reading the module-level
    `TICK_LOCK_META` constant, which is fixed at import from `RUN`) keeps the
    meta-lock file colocated with whatever lock file `TICK_LOCK` points at --
    so tests that monkeypatch `TICK_LOCK` onto a tmp dir automatically keep the
    meta-lock there too (fully hermetic, never touches the real `.watchloop/run`).
    """
    return TICK_LOCK + ".meta"


def _tick_meta_lock():
    """SHORT-LIVED advisory lock that makes the tick decision atomic (#62).

    Returns an open fd exclusively `flock`-ed on `_tick_meta_path()`, or None if
    the meta-lock could not be taken within the bounded retry budget. The fd
    must be closed by the caller (which releases the flock); the file itself is
    deliberately kept (unlinking the flock target would break mutual
    exclusion for a sibling holding the inode).

    The meta-lock is NOT the durable dedup lock -- it only serializes the
    read -> decide -> write of TICK_LOCK. The durable dedup remains the bucket
    recorded inside TICK_LOCK (issues #27/#30).
    """
    fd = os.open(_tick_meta_path(), os.O_RDWR | os.O_CREAT, 0o644)
    try:
        for _ in range(META_LOCK_ATTEMPTS):
            try:
                fcntl.flock(fd, fcntl.LOCK_EX | fcntl.LOCK_NB)
                return fd
            except OSError:
                continue  # a sibling is mid-decision; retry the bounded budget
    except BaseException:
        os.close(fd)
        raise
    return None  # budget exhausted -> caller must SKIP (dedup), never run


def _current_tick() -> str:
    """Coarse cron-interval bucket for the current wall-clock moment.

    Two cron fires in the same bucket are the 'same tick'. A monotonic string
    bucket (rather than a raw O_CREAT|O_EXCL file) is what makes the dedup
    durable: a finished invocation's lock-release no longer lets a re-fire in
    the same interval re-acquire -- the interval owns the lock until it changes.

    BOUNDARY ALIGNMENT (issue #73): the bucket boundary is shifted half an
    interval (`TICK_INTERVAL_SECONDS // 2`) FORWARD. The cron fires on `*/20`
    at wall-clock `:00`/`:20`/`:40`; a naive `int(time.time()) // 1200` puts
    the bucket boundary at exactly those instants (whole-hour timezone offset
    makes the epoch boundary coincide with the fire time). A doubled fire that
    straddles the boundary then computes DIFFERENT buckets and the second
    process reclaims the first as a 'finished prior interval' -> both run
    main(). Shifting the boundary half an interval moves it to `:10`/`:30`/
    `:50`, 10 minutes from every fire, so a same-slot double fire always lands
    in ONE bucket and dedups. A genuinely-new slot still maps to a distinct
    bucket and reclaims the previous one.
    """
    return f"tick-{(int(time.time()) + TICK_INTERVAL_SECONDS // 2) // TICK_INTERVAL_SECONDS}"


def _read_lock_owner() -> tuple[str, int]:
    """Return (bucket, pid) recorded in the tick lock, or ('', 0) if absent."""
    try:
        with open(TICK_LOCK) as f:
            lines = [ln.strip() for ln in f if ln.strip()]
    except OSError:
        return "", 0
    bucket = lines[0] if len(lines) >= 1 else ""
    try:
        pid = int(lines[1]) if len(lines) >= 2 else 0
    except ValueError:
        pid = 0
    return bucket, pid


def _tick_lock_acquire() -> bool:
    """Acquire the per-tick dedup lock for THIS cron interval.

    Robust against the phantom double-fire (issue #25): unlike a plain
    O_CREAT|O_EXCL lock that is released synchronously at main()'s end, this
    holds the lock for the whole interval so a phantom re-fire in the same bucket
    dedups EVEN IF the first invocation already finished. The lock is only
    released when a NEW interval (bucket) starts.

    ATOMICITY (issue #62): the ENTIRE read -> decide -> write of TICK_LOCK runs
    under a short-lived advisory meta-lock (TICK_LOCK_META, issues #27/#30 keep
    the durable bucket INSIDE TICK_LOCK). The old code did `os.remove(TICK_LOCK)`
    followed by `os.open(TICK_LOCK, O_CREAT|O_EXCL)`, which is NOT atomic: a
    double cron-fire could let a second process remove the lock the first JUST
    created (same path!) so BOTH ran main(). The meta-lock serializes the whole
    decision so at most one caller wins per interval. The meta-lock is released
    immediately after the write -- it is NOT the durable lock.

    Returns True if THIS tick should run:
      * fresh lock (no owner) -> win, write our bucket+PID
      * owner holds an OLDER bucket (finished previous interval) -> reclaim
      * owner holds THIS bucket -> dedup (return False, no tick start),
        REGARDLESS of whether that owner is still alive (a FINISHED/CRASHED
        same-bucket owner must NOT be reclaimed -- that is the #25/#30 invariant)
    There is NO fallback: if the meta-lock cannot be taken the tick is SKIPPED
    (dedup), never double-run.
    """
    # The read -> decide -> write MUST be one mutually-exclusive step (#62).
    # If we cannot take the meta-lock, SKIP (dedup) -- never run a second tick.
    meta_fd = _tick_meta_lock()
    if meta_fd is None:
        log("  [DEDUP] could not take the atomic tick decision; skipping this tick")
        return False
    try:
        bucket = _current_tick()

        # Reclaim a finished previous interval: an older-bucket lock is stale
        # for THIS tick, so clear it before the atomic create.
        old_bucket, old_pid = _read_lock_owner()
        if old_bucket and old_bucket != bucket and pid_alive(old_pid):
            log(f"  [DEDUP] reclaiming finished interval {old_bucket} for {bucket}")

        # Fresh lock: no owner yet -> win by creating it (O_EXCL).
        try:
            fd = os.open(TICK_LOCK, os.O_CREAT | os.O_EXCL | os.O_WRONLY)
        except OSError:
            # Lock exists. If the recorded owner holds THIS interval's bucket,
            # dedup REGARDLESS of whether that owner is still alive. The interval
            # owns the lock until its bucket changes, so even a FINISHED or
            # CRASHED same-bucket owner must keep this tick duplicable --
            # reclaiming it would let a same-bucket re-fire re-run the tick
            # (the #25/#30 phantom double). Only an OLDER bucket (a finished
            # prior interval) is stale for this tick.
            owner_bucket, _owner_pid = _read_lock_owner()
            if owner_bucket and owner_bucket == bucket:
                return False  # THIS interval already ran/was owned -> dedup, no tick start
            # Stale/foreign lock (different bucket, or no bucket): remove + recreate.
            # Both run UNDER the meta-lock, so no sibling can remove our fresh
            # lock between the remove and the create (the #62 TOCTOU).
            try:
                os.remove(TICK_LOCK)
                fd = os.open(TICK_LOCK, os.O_CREAT | os.O_EXCL | os.O_WRONLY)
            except OSError:
                return False  # raced with another recoverer
        os.write(fd, f"{bucket}\n{os.getpid()}\n".encode())
        os.close(fd)
        return True
    finally:
        # Release the SHORT-LIVED meta-lock (the durable dedup stays in
        # TICK_LOCK's recorded bucket -- issues #27/#30).
        os.close(meta_fd)


def _tick_lock_release(current_bucket: str) -> None:
    """Release the tick lock ONLY when a NEW interval (current_bucket) starts.

    An older-bucket holder is a finished previous interval; clear it so the new
    interval acquires cleanly. A same-bucket holder means we are mid-tick -- do
    NOT release (that would permit a phantom re-fire to steal this tick). The
    lock is intentionally NOT released at main()'s end, unlike the fragile
    version it replaces: durability for the whole interval is the point.
    """
    held_bucket, held_pid = _read_lock_owner()
    if held_bucket and held_bucket != current_bucket:
        try:
            os.remove(TICK_LOCK)
        except OSError:
            pass


def main() -> None:
    bucket = _current_tick()
    if not _tick_lock_acquire():
        log("[DEDUP] tick skipped: a previous invocation is already running this interval")
        return
    try:
        log("tick start")
        prs = api("/pulls?state=open&per_page=100")
        resolved_this_tick: set = set()
        if isinstance(prs, list):
            if "--dry" in sys.argv:
                log(f"  [DRY] skipping merge gate ({len(prs)} open PRs)")
            else:
                resolved_this_tick = process_merge_gate(prs)
        else:
            log("  could not list PRs (API error); skipping merge gate")

        # issue #29: after any merge this tick (and any accumulated older merge),
        # clean the now-stale worktree + branch + worker artifacts for merged PRs.
        dry_run = "--dry" in sys.argv
        cleaned = cleanup_merged_worktrees(dry=dry_run)
        if dry_run and cleaned:
            log("  [DRY] would clean %d stale merged worktree(s): %s"
                % (len(cleaned), ", ".join(sorted(cleaned))))

        issues = api("/issues?state=open&per_page=100")
        if isinstance(issues, list):
            for issue in issues:
                if not isinstance(issue, dict) or "pull_request" in issue:
                    continue
                num = issue["number"]
                if num in resolved_this_tick:
                    log(f"  issue#{num}: resolved by PR merged this tick; no spawn")
                    continue
                if issue_has_pr(num):
                    log(f"  issue#{num}: PR in flight, no spawn")
                    continue
                # Pre-spawn model probe (issue #37): if the worker model is served
                # by the LOCAL llama.cpp server and that server is down, fail
                # closed and skip cleanly — no doomed worker, no lock, no prompt
                # file, no worktree. Hosted providers (e.g. openrouter) are
                # unaffected: no local port is probed.
                if effective_provider_is_local():
                    if not probe_worker_model(WORKER_MODEL_EFFECTIVE):
                        log(f"  issue#{num}: worker model {WORKER_MODEL_EFFECTIVE} "
                            f"unreachable on {LOCAL_MODEL_URL} — skipping spawn")
                        continue
                if "--dry" in sys.argv:
                    log(f"  issue#{num}: [DRY] would spawn worker for '{issue['title']}'")
                    continue
                spawn_worker(issue)

        # issue #42: after merging ready PRs and spawning orphan-issue workers,
        # repair the PRs that are stuck (unresolved review threads / red CI) by
        # respawning their dedicated worker on the EXISTING PR branch. This runs
        # every tick so a stuck PR keeps getting repair attempts until it reaches
        # the merge gate. Approved/behind/no-issue PRs are never touched here.
        if isinstance(prs, list):
            dry_run = "--dry" in sys.argv
            process_stuck_prs(prs, dry=dry_run)
        log("tick done")
    except Exception:
        # Intentionally NO finally-release: the lock stays held for this interval
        # so a phantom re-fire in the same bucket dedups. A crash mid-tick leaves
        # a live-PID lock that the NEXT interval (different bucket) reclaims via
        # _tick_lock_acquire(), which removes it atomically.
        log("[DEDUP] tick crashed mid-run; lock stays held until next interval")
        raise


if __name__ == "__main__":
    main()
