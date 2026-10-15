---
name: git-repo-coordination
description: Multi-writer Git repository coordination — prevent conflicts from concurrent cron jobs, manual edits, and multi-agent workflows. File-based locking, schedule offsets, retry patterns, and automated conflict resolution.
tags: [git, devops, cron, multi-agent, coordination, conflict-resolution]
---

# Git Repo Coordination

**Problem:** Multiple processes writing to the same Git repository simultaneously → conflicts, push failures, manual intervention required.

**Common Pattern:** Cron jobs, manual edits, and multiple agents all pushing to the same repo without knowing about each other.

---

## Trigger

Use this skill when:
- Git conflicts happen frequently in a repo
- Multiple cron jobs write to the same files
- "remote contains work you do not have locally" errors recur
- Jobs fail with `git push` conflicts
- You need to coordinate writers across multiple processes

---

## Diagnosis Workflow

### 1. Identify All Writers

List all cron jobs and workflows that write to the repo:

```bash
# List cron jobs
cronjob action=list | grep -i "sync\|push\|deploy"

# Check schedules
cronjob action=list | grep -E "(schedule|Script)"

# Find scripts that use git push
grep -r "git push" ~/.hermes/profiles/gentech/scripts/
```

**Document for each writer:**
- Job name/ID
- Schedule (cron expression)
- Files written
- Script path
- Dependencies

### 2. Map Timing Collisions

Create a schedule grid showing when jobs run:

```
Time   | Job A | Job B | Job C | Collision?
-------|-------|-------|-------|----------
12:00  | ✅    | ✅    | ❌    | YES (A+B)
12:15  | ❌    | ✅    | ✅    | YES (B+C)
18:00  | ✅    | ❌    | ❌    | Safe
```

**High-risk patterns:**
- Same minute (00:00, 12:00, 18:00)
- Every 6h overlapping (00:00 vs 00:15)
- No offsets between independent jobs

### Workdir-lock starvation (TERMINAL_CWD read lock) — Aug 11, 2026

A distinct failure mode from git repo locks: **jobs with `workdir` set hold the Hermes terminal working-directory lock**, and a job WITHOUT a workdir that fires in the same minute can starve on it. Symptom in cron output:

```
TimeoutError: Timed out waiting for the TERMINAL_CWD read lock after 660s —
another cron job (a workdir writer, or long-running readers) has held it
longer than the cron inactivity limit.
```

This looks like a provider timeout but is a **scheduling collision**, not an outage. Workdir jobs serialize; a non-workdir job at the same minute waits and dies.

**Fix — stagger the non-workdir job off the workdir cluster minute:**
```bash
# Revenue Monitor fired at :00 alongside API Safety Suite / Vault Watcher / Rate Limit Monitor (all workdir jobs)
cronjob action=update job_id=1cd4dd8b3cf0 schedule="5 8,20 * * *"   # moved to :05
```
**Rule:** audit the full job list for the target minute — if 2+ jobs carry `workdir`, move non-workdir jobs to `:05`/`:15` offsets, or remove `workdir` from jobs that don't strictly need it.

### 3. Check Git Log for Evidence

Look for conflict patterns in recent commits:

```bash
cd /path/to/repo
git log --oneline --since="2 weeks ago" | head -20

# Look for:
# - Two commits within seconds
# - "rebase" messages
# - "fix conflicts" messages
# - Multiple "sync" commits at same time
```

**Conflict signatures:**
```
2026-07-05 15:24:35 - Sync POE2 builds (9 files)
2026-07-05 15:24:27 - feat: update Jordan's Monk character
          ↑ TWO COMMITS WITHIN 8 SECONDS → RACE CONDITION
```

---

## Solution Pattern

### Phase 1: Emergency Stabilization

#### Fix 1: Reschedule Conflicting Jobs

Add 15-minute offsets to eliminate overlaps:

```bash
# Example: Portfolio Health was colliding at 12:00
cronjob action=update job_id=ce23c5df747b schedule="15 12 * * *"

# Example: POE2 Build Health was colliding at 09:00
cronjob action=update job_id=02461aa0a77b schedule="15 9 * * *"

# Example: Vanito Music Sync needed 15-min offset
cronjob action=update job_id=f3e90d867b9c schedule="15 */6 * * *"
```

**Offset rule:** Independent jobs must not share the same minute slot.

#### Fix 2: Add File-Based Locking

Create `git_repo_lock.py` in `${PROFILE_DIR}/scripts/`:

```python
#!/usr/bin/env python3
"""Git repo lock utility for concurrent operations."""

import fcntl
import os
import time
from pathlib import Path

LOCK_FILE = "/tmp/protojay-repo.lock"
LOCK_TIMEOUT = 60
LOCK_STALE_TIMEOUT = 300  # 5 minutes

class GitRepoLock:
    """Context manager for atomic Git repo locking."""

    def __init__(self, timeout=LOCK_TIMEOUT):
        self.timeout = timeout
        self.lock_file = None

    def __enter__(self):
        lock_path = Path(LOCK_FILE)

        # Clean stale locks
        if lock_path.exists():
            lock_age = time.time() - lock_path.stat().st_mtime
            if lock_age > LOCK_STALE_TIMEOUT:
                lock_path.unlink()

        self.lock_file = lock_path.open('w')
        start_time = time.time()

        while time.time() - start_time < self.timeout:
            try:
                fcntl.flock(self.lock_file.fileno(), fcntl.LOCK_EX | fcntl.LOCK_NB)
                self.lock_file.write(str(os.getpid()))
                self.lock_file.flush()
                return self
            except (IOError, OSError):
                time.sleep(1)
                continue

        self.lock_file.close()
        raise TimeoutError(f"Failed to acquire lock after {self.timeout}s")

    def __exit__(self, exc_type, exc_val, exc_tb):
        if self.lock_file:
            fcntl.flock(self.lock_file.fileno(), fcntl.LOCK_UN)
            self.lock_file.close()
            Path(LOCK_FILE).unlink(missing_ok=True)
        return False

def push_with_retry(max_retries=3, base_delay=30):
    """Push with exponential backoff on conflict.

    Handles unstaged changes by stashing before pull --rebase.
    Reverts stash after successful push. Conflicts on stash pop
    are reported but do not fail the push itself.
    """
    import subprocess

    for attempt in range(max_retries):
        try:
            # Stash any unstaged changes so pull --rebase can proceed
            stash_result = subprocess.run(
                ["git", "stash", "push", "-m", "auto-stash-before-push"],
                capture_output=True, text=True
            )
            stashed = stash_result.returncode == 0 and "No local changes" not in stash_result.stdout

            subprocess.run(["git", "pull", "--rebase", "origin", "main"],
                          check=True, capture_output=True)
            subprocess.run(["git", "push", "origin", "main"],
                          check=True, capture_output=True)

            # Pop stash after successful push
            if stashed:
                subprocess.run(["git", "stash", "pop"],
                              capture_output=True)
            return True
        except subprocess.CalledProcessError as e:
            if attempt < max_retries - 1:
                time.sleep(base_delay * (2 ** attempt))
            else:
                return False
    return False
```

#### Fix 3: Update Sync Scripts

Add locking to each sync script:

```python
import sys
import os
sys.path.insert(0, '${PROFILE_DIR}/scripts')
from git_repo_lock import GitRepoLock

def sync_function():
    """Your sync workflow here."""
    with GitRepoLock():
        # All Git operations inside lock
        # ...
        from git_repo_lock import push_with_retry
        if not push_with_retry():
            print("Failed to push after retries")
            return False
    return True
```

**Test each script:**
```bash
python3 ${PROFILE_DIR}/scripts/script-name.py
```

### Phase 2: Robust Coordination

#### Centralized Sync Manager

Create a single `repo-sync-manager.py` that:
- Runs all sync operations in sequence
- Maintains job queue
- Handles conflicts automatically
- Provides status reporting

**Benefits:**
- No coordination needed between independent jobs
- Single lock covers all operations
- Better error handling and reporting
- Easier debugging

#### Pre-Push Conflict Detection

Check for concurrent jobs before pushing:

```python
def check_safe_to_push():
    """Check if safe to push to repo."""
    if os.path.exists("/tmp/protojay-repo.lock"):
        return False  # Another job holds lock

    local_sha = subprocess.run(["git", "rev-parse", "HEAD"], capture_output=True).stdout.strip()
    fetch_sha = subprocess.run(["git", "rev-parse", "@{u}"], capture_output=True).stdout.strip()

    if local_sha != fetch_sha:
        # Need to pull first
        subprocess.run(["git", "pull", "--rebase", "origin", "main"], check=True)

    return True
```

---

## Pitfalls

### Pitfall 1: Ignoring Stale Locks

**Symptom:** Jobs hang forever waiting for lock, even when no job is running.

**Cause:** Process crashed while holding lock file.

**Fix:** Implement stale lock cleanup:
```python
if lock_path.exists():
    lock_age = time.time() - lock_path.stat().st_mtime
    if lock_age > 300:  # 5 minutes
        lock_path.unlink()
```

### Pitfall 2: Lock File Not in Shared Location

**Symptom:** Locking works but jobs still collide.

**Cause:** Lock file created in `/tmp/` but jobs run in different workdirs.

**Fix:** Use absolute path for lock file:
```python
LOCK_FILE = "/tmp/protojay-repo.lock"  # Always absolute
```

### Pitfall 3: Same Script, Different Cron Jobs

**Symptom:** Conflicts still happen after adding locking.

**Cause:** Two different cron jobs call the same script independently.

**Fix:** Either consolidate jobs or ensure schedule offsets (see Phase 1).

### Pitfall 4: Missing Import Path for git_repo_lock

**Symptom:** `ModuleNotFoundError: No module named 'git_repo_lock'`

**Cause:** Script path not in `sys.path`.

**Fix:** Add script directory to path:
```python
sys.path.insert(0, '${PROFILE_DIR}/scripts')
from git_repo_lock import GitRepoLock
```

### Pitfall 5: Script Hangs After Lock Acquisition

**Symptom:** Script acquires lock, then never proceeds. Cron job times out with zero output.

**Cause:** Blocking call inside lock, dead lock, or unhandled exception, **compounded by Python stdout buffering** — when not connected to a TTY (cron jobs, subprocess.run), Python block-buffers stdout (4KB default). Print statements execute but the output stays in the buffer and is lost when the process is killed by timeout or crashes mid-way. A script that hangs 5 seconds in may show zero output because nothing was flushed.

**Fix:**
1. **Add logging with `flush=True`** to identify where script hangs:
```python
def sync_function():
    print("Acquiring lock...", flush=True)
    with GitRepoLock():
        print("Lock acquired, starting sync...", flush=True)
        # ... sync operations
        print("Sync complete, releasing lock...", flush=True)
```

2. **Or disable output buffering at the interpreter level:**
   - Run with `python -u` (unbuffered): `python -u script.py`
   - Set `PYTHONUNBUFFERED=1` env variable in cron job config
   - Add `import sys; sys.stdout.reconfigure(line_buffering=True)` at script top

3. **Debugging a script that produces zero output:**
   ```
   1. Suspected hang location → search for blocking calls (network, file locks, subprocess)
   2. Add print(..., flush=True) before each blocking call
   3. Run with shorter timeout to confirm hang location
   4. Check for stale lock files that may interact unexpectedly with fcntl:
      ls -la /tmp/*.lock
      # If present, remove and retry: rm -f /tmp/protojay-repo.lock
   ```

**Note on stale lock files:** Even if `/tmp/protojay-repo.lock` exists from a crashed process, `fcntl.flock` is released by the kernel when the process dies. The lock acquisition itself should NOT block. If it does, the lock file's `open('w')` may be blocking on something else (NFS, filesystem issue, permissions). Best practice: always clean stale lock files before investigating other causes.

### Pitfall 6: push_with_retry Fails Due to Unstaged Changes

**Symptom:** `push_with_retry` exhausts all retries and returns `False`, even though remote is reachable. Log shows push rejection but no helpful error.

**Cause:** `git pull --rebase` fails because another writer or concurrent job left unstaged changes (e.g., `DeFi/defi-data.json` modified by a different sync running nearby). The retry loop retries the same failing pull instead of cleaning the working tree first.

**Trace in logs:**
```
Failed to push after retries
```

The push fails silently — the script reports failure but gives no hint about unstaged changes blocking the rebase.

**Fix (incorporated into push_with_retry in this skill):**

`push_with_retry` now auto-stashes before `git pull --rebase` and pops after push:

```python
# Inside push_with_retry:
stash_result = subprocess.run(
    ["git", "stash", "push", "-m", "auto-stash-before-push"],
    capture_output=True, text=True
)
stashed = stash_result.returncode == 0 and "No local changes" not in stash_result.stdout

subprocess.run(["git", "pull", "--rebase", "origin", "main"], check=True, capture_output=True)
subprocess.run(["git", "push", "origin", "main"], check=True, capture_output=True)

if stashed:
    subprocess.run(["git", "stash", "pop"], capture_output=True)
```

**Manual recovery if you hit this:**
```bash
cd /path/to/repo
# Check for unstaged changes
git status --short

# Stash, pull, push, then handle any stash pop conflict
# Stash pop may conflict if the rebase changed files you also modified
# — that's a genuine conflict needing manual resolution
git stash push -m "pre-push-cleanup"
git pull --rebase origin main
git push origin main
git stash pop  # resolve conflicts if they appear
```

**Cleaner one-liner — autostash (preferred, Jul 2026):**
```bash
git -c rebase.autoStash=true pull --rebase
```
This stashes, rebases, and reapplies automatically — no manual stash/pop, no "cannot pull with rebase: You have unstaged changes" errors. Use it anywhere a sync step (ob sync, rsync, generator) touches the working tree before the pull. Verified fixing `nightly-maintenance.py`'s repeated Git Pull failures (Jul 31, 2026).

### Pitfall 7: Hash-Based Change Detection False Positives

**Symptom:** A sync script reports "Detected N changes" on EVERY run, even when the data hasn't actually changed. No real changes are pushed, but the script wastes time committing (or failing to commit identical content) and running push_with_retry retries.

**Cause:** The change-detection hash function uses raw input field values which may be empty/missing, while the write/normalization step fills in defaults for those same fields. Every run compares raw (no defaults) vs normalized (with defaults) — they always differ.

**Example from vanito-music-sync.py (Jul 8, 2026):**

Hub data songs had `{title, style, added}` — no `duration` or `genre` fields. The hash computed:
```python
# Raw input has no duration/genre → hash("TITLE__")
hashlib.md5("TITLE__".encode()).hexdigest()
```

But local songs (already normalized by a previous run) had `{title, duration: "0:00", genre: "Unknown"}`:
```python
# Previous normalization added defaults → hash("TITLE_0:00_Unknown")  
hashlib.md5("TITLE_0:00_Unknown".encode()).hexdigest()
```

These hashes never match, so every run detects "2 new/changed songs", even though the *normalized output* would be identical.

**Fix:** The hash function must use the same defaults as the normalization/write step:

```python
# ❌ WRONG — uses raw input fields (may be missing/empty)
def calculate_song_hash(song):
    song_str = f"{song['title']}_{song.get('duration', '')}_{song.get('genre', '')}"
    return hashlib.md5(song_str.encode()).hexdigest()

# ✅ CORRECT — normalizes to same defaults as write step
def calculate_song_hash(song):
    title = song.get('title', '')
    duration = song.get('duration', '0:00')    # same default as normalization
    genre = song.get('genre', 'Unknown')        # same default as normalization
    song_str = f"{title}_{duration}_{genre}"
    return hashlib.md5(song_str.encode()).hexdigest()
```

**Prevention pattern:**
1. When building a sync script with hash-based change detection, the hash function and the normalization function must share default values
2. Extract defaults to a named constant to ensure they stay in sync:
```python
DURATION_DEFAULT = "0:00"
GENRE_DEFAULT = "Unknown"

def get_song_values(song):
    return {
        'title': song.get('title', ''),
        'duration': song.get('duration', DURATION_DEFAULT),
        'genre': song.get('genre', GENRE_DEFAULT),
    }

def calculate_song_hash(song):
    v = get_song_values(song)
    return hashlib.md5(f"{v['title']}_{v['duration']}_{v['genre']}".encode()).hexdigest()

def normalize_song(song):
    v = get_song_values(song)
    return {
        'id': song.get('id', v['title'].lower().replace(' ', '-')),
        'title': v['title'],
        'duration': v['duration'],
        'genre': v['genre'],
        # ... other fields
    }
```

3. **Test:** Force-hash both the raw input AND the normalized output — they should produce the same hash when defaults match:
```python
assert calculate_song_hash(raw_input) == calculate_song_hash(normalized_output)
```

### Pitfall 9: In-Progress Rebases from Other Agents

**Symptom:** Your `git add -A && git commit` fails with `"interactive rebase in progress"`. The `.git/rebase-merge/` directory exists.

**Cause:** Another agent (e.g., Forge) left an interactive rebase in progress — the rebase was interrupted mid-way, or the writing agent's session ended before it ran `git rebase --continue`.

**Danger:** Running `git rebase --abort` destroys the other agent's uncommitted work. In a multi-writer vault, this is silent data loss.

**Detection (always check before git operations):**

```bash
if [ -d ".git/rebase-merge" ]; then
    echo "⚠️ In-progress rebase detected"
    DONE=$(wc -l < .git/rebase-merge/done 2>/dev/null || echo 0)
    TODO=$(wc -l < .git/rebase-merge/git-rebase-todo 2>/dev/null || echo 0)
    echo "  Done: $DONE, Remaining: $TODO"
    MTIME=$(stat -c %Y .git/rebase-merge/done 2>/dev/null || echo 0)
    AGE=$(( $(date +%s) - MTIME ))
    echo "  Age: ${AGE}s"
fi
```

**Python detection for scripts:**

```python
import os, time

def check_in_progress_rebase(repo_path):
    """Detect in-progress rebase. Returns (has_rebase, reason, age_seconds)."""
    rebase_dir = os.path.join(repo_path, '.git', 'rebase-merge')
    if not os.path.isdir(rebase_dir):
        return False, "no rebase", 0
    done_file = os.path.join(rebase_dir, 'done')
    mtime = os.path.getmtime(done_file) if os.path.exists(done_file) else 0
    age = time.time() - mtime
    done_count = 0
    with open(done_file) as f: done_count = sum(1 for _ in f) if os.path.exists(done_file) else 0
    return True, f"{age:.0f}s old ({done_count} done)", int(age)

# In your sync function:
has_rebase, reason, age = check_in_progress_rebase("${VAULT_DIR}")
if has_rebase:
    if age < 900:  # < 15 min — likely active, another agent may be working
        print(f"⚠️ Skipping vault sync: {reason}")
        return  # Defer to next run
    else:
        print(f"⚠️ Stale rebase ({reason}) — aborting to unblock")
        import subprocess
        subprocess.run(["git", "rebase", "--abort"], cwd=repo_path, capture_output=True)
```

**Decision guide:**

| Context | Age | Action |
|---------|-----|--------|
| Cron job | < 15 min | **Skip.** Do not abort — another agent may be active. |
| Cron job | ≥ 15 min | **Abort** stale rebase (assume other agent crashed). |
| Interactive | Any | **Ask the user** before aborting. If unreachable, skip. |

**Session source:** Jul 17, 2026 — PR scout cron found Forge's in-progress rebase in the vault, aborted it (losing Forge's uncommitted work), then hit a secret-scan push block on an old commit from that aborted work.

### Pitfall 10: GitHub Secret-Scan Blocked Push After Force Push

**Symptom:** `git push --force` is rejected with `"GH013: Push cannot contain secrets"` pointing to a commit hash.

**Cause:** GitHub's push protection scans EVERY commit in the branch history during a force push. If any commit (even one from another session or agent) contains a flagged secret, the push is blocked.

**Fix options (ordered by safety):**

1. **Skip secret scanning** (for genuine false positives, e.g., a revoked test token):
   ```bash
   git push --force -o "secret_scanning.skip=true"
   ```

2. **Remove the offending commit from history** (for real secrets):
   ```bash
   # From the GitHub error, find the offending commit hash
   # Then rebase to drop it:
   git rebase --onto <offending>^ <offending>
   git push --force
   ```

3. **Allow the secret via GitHub UI** (for intentional test-only tokens):
   Follow the URL GitHub provides in the error message.

**Prevention — review before force-push:**

```bash
git log --oneline -10  # Verify every commit belongs
```

If the branch contains auto-merged or stashed commits from other sessions, rebase interactively to clean them before force-push.

**Session source:** Jul 17, 2026 — PR scout cron aborted Forge's rebase, then hit secret-scan block on Forge's commit containing a Cloudflare API token in a handoff doc.

### Pitfall 8: Structural JSON Corruption from Rebase Auto-Resolution

**Symptom:** A sync script reports "JSON invalid after post-rebase clean" and the pre-push validation blocks the push. The file has the right line count and looks structurally close to valid, but a brace count shows `{` count ≠ `}` count — typically one extra opening brace. Key sections appear duplicated or nested inside the wrong parent object.

**Diagnostic pattern (from hub-sync-nightly.py, Jul 14, 2026):**
```
🔴 JSON still invalid after post-rebase clean: Expecting ',' delimiter: line 753 col 2
🔴 Pre-push JSON validation failed — data not pushed
```

Running a brace count confirms the structural imbalance:
```python
with open('data.json') as f:
    content = f.read()
print(f'{{ : {content.count("{")}')
print(f'}} : {content.count("}")}')
# { : 108, } : 107 → 1 unclosed brace
```

Drilling in with a depth trace reveals nested corruption:
```
Line 1:   {        → depth 1 (top-level opens)
Line 120: supportResistance → depth 2
Line 136: }        → depth 1 (closes correctly)
Line 137: curveData → depth 2 (same level — should be sibling, not nested)
Line 162: lpPosition → depth 3 (INSIDE curveData!)
Line 651: }        → depth 2
...
Line 764: }        → depth 1 (never reaches 0)
```

Top-level sections that should be siblings (lpPosition, hero, fees, ilCalculator) are nested inside `curveData`, and the top-level `{` is never matched.

**Cause:** Git's file-level merge during `git pull --rebase` encountered a conflict on a structured JSON file. The auto-resolve (`git add -u`) staged the **file-level merged result** — git's 3-way merge algorithm combined both versions by inserting the remote's additions into the local file at the conflict boundary. For JSON files with the same top-level keys but different inner structure, this produces a structurally wrong composite: duplicate sections, keys nested inside the wrong parent, and unclosed braces.

```
Conceptual picture:
Local file had:
  { key1, key2, key3 }
Remote file had:
  { key1, key4, key5 }
Git merge at file level produces:
  { key1, key2, key4, key3, key5 }
  — keys interleaved, sometimes inside wrong brace levels
```

The `sanitize_json_text()` function (which strips `<<<<<<<` / `=======` / `>>>>>>>` markers and removes trailing commas) correctly handles merge markers but **cannot fix structural corruption** caused by the file-level merge — because the issue isn't markers, it's the arrangement of braces and keys.

**Fix — restore from ground-truth copy, don't try to repair the merge:**

```bash
cd /path/to/repo

# 1. Identify the ground-truth copy (the data source the script writes from)
#    For hub-sync-nightly.py → ${VAULT_DIR}/defi-data.json

# 2. Verify the ground-truth copy is valid
python3 -c "import json; json.load(open('DeFi/defi-data.json')); print('VALID')"

# 3. Replace the corrupted file with the clean copy
cp ${VAULT_DIR}/defi-data.json /root/repos/gentechlabs.github.io/DeFi/defi-data.json

# 4. Re-commit (amend the failed sync commit)
git add DeFi/defi-data.json
git commit --amend --no-edit

# 5. Push
git push
```

**Prevention in sync scripts:**

After a rebase conflict on a data file that's always regenerated from a source of truth, restore from ground truth rather than trusting the auto-merge:

```python
if rebase_rc != 0:
    import shutil
    if os.path.exists(VAULT_DEFI_JSON):
        shutil.copy2(VAULT_DEFI_JSON, f"{GITHUB_PAGES_REPO}/DeFi/defi-data.json")
        subprocess.run(f"cd {GITHUB_PAGES_REPO} && git add DeFi/defi-data.json",
                      shell=True, capture_output=True)
    subprocess.run(f"cd {GITHUB_PAGES_REPO} && GIT_EDITOR=true git rebase --continue",
                  shell=True, timeout=30)
```

Simpler alternative — accept theirs during conflict resolution:
```bash
git checkout --theirs DeFi/defi-data.json && git add . && git rebase --continue
```

**Validation checklist after recovery:**
1. `python3 -c "import json; json.load(open('data.json')); print('VALID')"` — parses without error
2. `content.count('{') == content.count('}')` — braces balanced
3. All required top-level keys present (per template or schema)
4. No keys nested inside the wrong parent (spot-check a depth trace)

**Session source:** Jul 14, 2026 — hub-sync-nightly.py failed after rebase conflict. Clean vault copy (8376 bytes) restored over corrupted GitHub Pages copy.

### Pitfall 11: Concurrent Build Queue Edits Across Sessions

**Symptom:** Your build queue items (IDs, statuses, priorities) disappear after another session commits. The file on disk is a different version than what you wrote.

**Cause:** Multiple agents (cron jobs, nightly maintenance, interactive sessions) all write `${VAULT_DIR}/scripts/build_queue.json` concurrently. Last writer overwrites without seeing other session's changes.

**Diagnosis:**
```bash
cd ${VAULT_DIR}
git log --oneline -5 -- scripts/build_queue.json  # recent changes
grep -c '"id": 69' scripts/build_queue.json         # check if items survived
head -5 scripts/build_queue.json                     # check format version
```

**Fix — commit immediately after editing, never batch with other work:**
```bash
git add scripts/build_queue.json && git commit -m "queue: ..." && git push vault main
```

**Recovery — re-add lost items:**
```python
with open("scripts/build_queue.json") as f:
    q = json.load(f)
existing = {i["id"] for i in q["items"]}
missing = [{"id": 69, "name": "...", ...}]  # your items
for item in missing:
    if item["id"] not in existing:
        q["items"].append(item)
json.dump(q, open("scripts/build_queue.json", "w"), indent=2)
```

**Prevention:** Commit queue changes in same turn they're made. Check item count before/after. One primary writer per file.

**Session source:** Jul 17, 2026 — Gentech added items 66-74. Nightly maintenance overwrote. Recovered via Python script.

### Pitfall 14: Prefer Merge/Soft-Reset Over Rebase for Single-File Updates

**Symptom:** You edited ONE file (e.g., `build_queue.json`), committed cleanly, but `git push` is rejected because the remote has advanced. You try `git pull --rebase`, which cascades into conflict after conflict across 15+ old commits — many of which don't even touch your file but trigger conflicts on unrelated auto-generated data files.

**Cause:** `git pull --rebase` replays EVERY commit from the remote branch against your local HEAD. If any of those old commits touched the same file you modified (even in a completely different section — e.g., an old queue version), git will try to merge them and conflict. For single-file updates where the remote has N new unrelated commits, rebase does Nx the work and risks N cascading conflicts.

**Fix — Skip rebase entirely for single-file changes. Use soft-reset directly to remote HEAD:**

```bash
git fetch origin                  # get latest remote state
git reset --soft origin/main      # keep your changes staged, move HEAD to remote
git commit -m "queue: update"     # commit on top of remote HEAD
git push                          # fast-forward push
```

**Alternative — merge (if you prefer a visible merge commit):**

```bash
git pull --no-rebase -X theirs    # merge, auto-accept remote on conflicts
```

**Decision guide:**

| Remote state | Your state | Best approach |
|-------------|-----------|---------------|
| Remote advanced, your change is the only local change | Committed | `git fetch && git reset --soft origin/main && git commit -m "..." && git push` |
| Remote advanced, your change is the only local change | Uncommitted | `git stash && git pull --no-rebase -X theirs && git stash pop` |
| Remote advanced AND touched the same file | Both versions matter | Manual merge with `git mergetool` |
| Remote unchanged | Everything fine | Straight `git push` |

**Context:** Refined Jul 27, 2026 — overnight queue maintenance. Queue file was the only local change; remote had 15+ new commits. `git pull --rebase` failed on commit 3 of 16. Recovery: abort rebase → soft-reset to origin → re-commit → push (fast-forward).

**Refinement (Jul 31, 2026) — merge beats rebase when BOTH sides have many commits:**
When local is 10+ commits ahead AND remote advanced (e.g. 18 local vs 1 remote, from sibling sessions), `git pull --rebase` replays the entire local stack and can hit 6+ conflicts on old sibling commits that don't even touch your work (e.g. a stale queue version from Jul 27 colliding with today's v54). The clean resolution:
```bash
git fetch origin
git merge origin/main --no-edit    # ort strategy — single merge commit, no stack replay
# resolve any conflicts, then:
git push
```
A merge resolves the divergence in one pass instead of replaying N commits. If `git merge` also conflicts, resolve per-file: for generated files (build_queue.json, JSON data) keep the NEWER version (highest version number / most recent `updated` field) — an old sibling commit's stale queue must never overwrite the current one.

### Pitfall 12: Stale Token in Git Remote URL Causes Push Failures Despite Valid `gh` Auth

**Symptom:** `gh auth status` shows ✅ logged in, `gh api rate_limit` shows valid quota, but `git push origin main` fails with:
```
remote: Invalid username or token. Password authentication is not supported for Git operations.
fatal: Authentication failed for 'https://github.com/Gentech-Labs/repo.git'
```

**Cause:** The git remote URL has an old/baked-in token that expired, even though `gh` CLI has the current valid token stored in `~/.config/gh/hosts.yml`. Git uses the remote URL's embedded credentials, not the `gh` CLI config.

**Diagnosis:**
```bash
# Check remote URL for embedded tokens
git remote -v
# If URL contains "ghp_..." or "gho_...", the token is baked in

# Compare with gh's working token
gh auth status  # Should show "Logged in"
gh api rate_limit  # Should show remaining quota
```

**Fix — Update remote URL with current token:**
```bash
TOKEN=$(gh auth token)
git remote set-url origin "https://GentechLabs:${TOKEN}@github.com/Gentech-Labs/repo.git"
git push origin main
```

**For multiple repos, fix all:**
```bash
TOKEN=$(gh auth token)
for repo in /root/repos/genTech-agent-kit /root/builds/genTech-agent-kit ${VAULT_DIR}; do
    if [ -d "$repo/.git" ]; then
        cd "$repo"
        git remote set-url origin "https://GentechLabs:${TOKEN}@github.com/Gentech-Labs/$(basename $(git rev-parse --show-toplevel)).git"
        echo "✅ Updated: $repo"
    fi
done
```

**Sessions source:** Jul 26, 2026 & earlier. Token existed in `.env`, `secrets/github-token`, and `gh` config, but git remote URLs had baked-in stale tokens. Fix: update remote URL via `$(gh auth token)`.

### Pitfall 13: GitHub API Rate Limiting Blocks Operations

**Symptom:** `gh repo fork`, `gh repo create`, or `git push` fails with `HTTP 403: rate limit exceeded` or `GraphQL: API rate limit already exceeded`.

**Cause:** GitHub enforces per-hour rate limits on both the REST API (core, 60 req/h for unauthenticated, 5000 for authenticated) and GraphQL API (used by `gh repo fork`, 0 points/h when exhausted). The limit resets on a rolling window.

**Pattern — Build local, push when clear:**

```bash
# 1. Check rate limit first before any GitHub operation
gh api rate_limit | python3 -c "import json,sys,datetime; d=json.load(sys.stdin); r=d['resources']['core']; g=r['graphql']; reset=datetime.datetime.fromtimestamp(r['reset']); print(f'Core: {r[\"remaining\"]}/{r[\"limit\"]}'); print(f'GraphQL: {g[\"remaining\"]}/{g[\"limit\"]}'); print(f'Reset: {reset.strftime(\"%H:%M:%S UTC\")}')"

# 2. If rate limited, build locally and queue the push
#    Use cronjob action=create with a one-shot schedule matching the reset time
cronjob action=create \
  name="push-fork-after-rate-limit" \
  schedule="2026-07-25T13:50:00" \
  prompt="Push the local repo at /path/to/repo to GitHub. gh repo create ... && git push -u origin main"

# 3. When the cron fires, it auto-executes the push
```

**Rate limit checks for different operations:**

| Operation | API Used | Check Command |
|-----------|----------|---------------|
| `gh repo fork` | GraphQL | `gh api rate_limit --jq '.resources.graphql.remaining'` |
| `gh repo create` | GraphQL | Same as above |
| `git push` | REST (core) | `gh api rate_limit --jq '.resources.core.remaining'` |
| `gh pr create` | GraphQL | `gh api rate_limit --jq '.resources.graphql.remaining'` |

**Pitfall — GraphQL and Core limits are separate.** `gh repo fork` uses GraphQL, which has its own rate limit (0 points default, resets independently of core). Even when core has 55 remaining, GraphQL can be at 0. Always check both.

**Bulk PR sweep — prefer REST over GraphQL (proven Aug 6, 2026):** For overnight maintenance ("mark items shipped where PRs merged"), do the whole sweep with the REST API, not `gh pr list`. GraphQL exhausts its bucket fast across many repos; REST has its own bucket and is usually still available. When `gh pr list` returns `GraphQL: API rate limit already exceeded`, switch to REST — it worked with 60/60 remaining while GraphQL was at 0:
```bash
TOKEN=$(gh auth token)
for repo in Gentech-Labs/repo-a Gentech-Labs/repo-b; do
  curl -s -H "Authorization: token $TOKEN" \
    "https://api.github.com/repos/$repo/pulls?state=all&per_page=10" \
    | python3 -c "import sys,json; d=json.load(sys.stdin); print('(no PRs)' if d==[] else '\n'.join(f\"#{p['number']} [{p['state']}] {p['title']} merged={p.get('merged_at')}\" for p in d))"
done
```
An empty `[]` array is a valid "no PRs on this repo" result — not an error. Check the REST bucket with `curl -s -H "Authorization: token $TOKEN" https://api.github.com/rate_limit`. Use REST for bulk checks; reserve GraphQL for richer PR metadata.

**Pitfall — `gh repo fork` can fail with "You cannot fork this repository at this time"** even when rate limits are fine. This is a repository-level restriction (the owner may have disabled forking). Workaround: push as a new repo instead:
```bash
cd /path/to/local-clone
git remote remove origin 2>/dev/null
gh repo create owner/new-repo --private --description "..." 2>/dev/null || true
git remote add origin https://github.com/owner/new-repo.git 2>/dev/null
git push -u origin main
```

**Real example (Jul 25, 2026):** Forking MengTo/Skills failed — GraphQL rate limit was 0, and then GitHub returned "cannot fork this repository." Solution: cron job pushed as a new private repo `ProtoJay4789/gentech-arcade-skills` at the next rate limit window.

### Pitfall 15: Stale `GITHUB_TOKEN` in `.env` shadows a valid hosts.yml login

**Symptom (proven Aug 2, 2026):** `gh auth status` prints `X Failed to log in to github.com using token (GITHUB_TOKEN)` — the token is "invalid" — while REST calls with `secrets/github-token` work fine and `gh api user --jq '.login'` returns the right account.

**Cause:** Hermes loads the profile `.env` into every session, and a dead/expired `GITHUB_TOKEN` there takes precedence over the valid credential in `~/.config/gh/hosts.yml` (which matches `secrets/github-token`). `gh auth status` compares the env var against the login and reports it as invalid, even though the real credential is fine.

**Diagnosis — verify IDENTITY, not the token:**
```bash
# If this returns the account login, the credential is fine — the env var is shadowing:
gh api user --jq '.login'
# Confirm the stale env var:
grep -n "GITHUB_TOKEN" ${PROFILE_DIR}/.env
```

**Fix:** sync the valid token into `.env` (or remove the line and `unset GITHUB_TOKEN` before gh work):
```bash
VALID=$(cat ${PROFILE_DIR}/secrets/github-token | tr -d '\n')
# Replace the GITHUB_TOKEN= line in .env with $VALID, or:
unset GITHUB_TOKEN && gh auth status   # falls back to hosts.yml
```
The token sources (env → secrets/github-token → gh auth token) must stay in sync; the `.env` copy is the one that silently poisons every Hermes session. Always verify with `gh api user` (identity check) rather than trusting `gh auth status` (which lies when env shadows hosts.yml).

### Pitfall 18: `git add -A` on a multi-writer tree sweeps another seat's in-flight work

**Symptom:** A commit you wrote shows files you never touched — another agent's script, a log, a half-wired test.
The message is about your work; the diff is partly theirs. Worst case: a *money-path* file lands in a
commit that a job wrote automatically and neither agent chose.

**Cause:** The vault (`/root/vaults/gentech`) is a **single shared working tree** that gentech,
gentech-treasury, gizmo and pixel all write to — and they all author commits as the **same git identity**,
so a swept file is indistinguishable from the sweeper's after the fact. `git add -A` stages whatever
anyone has in flight. This is not a merge conflict; it is a **transaction nobody intended**.

**Rule:** `git add -A` is never safe on a shared vault. Name your paths.

Use the purpose-built tool:
```bash
python3 /root/.hermes/scripts/vault-commit.py -m "msg" -- <path> [<path> ...]
python3 /root/.hermes/scripts/vault-commit.py --status    # show foreign dirty files, commit nothing
```
It refuses to run without an explicit path list, refuses paths that look like another writer's live work
(unless `--force`), and prints every dirty file it did **not** commit — so nothing is swept or forgotten silently.

**For scripts that must commit automatically,** drive the exclusion from the ownership registry rather than
hardcoding names, so it cannot drift and it binds whoever edits the registry next:
```python
import json
excl = ""
try:
    with open(f"{VAULT_DIR}/00-System/FILE-OWNERSHIP.json") as f:
        for p in json.load(f)["money_path"]["files"]:
            excl += f" ':(exclude)10-Labs/agent-kit-self-tracking/{p}'"
except Exception:
    excl = " ':(exclude)10-Labs/agent-kit-self-tracking/'"   # fail CLOSED, never sweep blind
subprocess.run(f"cd {VAULT_DIR} && git add -- .{excl} && git commit -m '{msg}'", shell=True)
```
Then print what was left behind. **A sweep must never be silent.**

**Prove it with a negative control** — on a scratch repo, dirty one money-path and two ordinary files:
```
OLD (git add -A):        STAGED  ordinary_a, money_path_file, ordinary_b
NEW (registry exclude):  STAGED  ordinary_a,                   ordinary_b
```
If the money-path file appears in the NEW staged set, the exclusion string is wrong (check the pathspec
is relative to the repo root, and that `-- .` is present — `git add -- <excludes>` alone stages nothing useful).

**Why it is worse than it looks:** on the money path a half-written file that gets committed is not a
conflict to resolve later — it is the state of a system that signs transactions. The blast radius is a
transaction, not a merge.

**Session source:** Sep 27, 2026 — `nightly-maintenance.py` (04:30 UTC cron) ran `git add -A` on the vault
while Treasury had `sync-treasury-scripts.sh` + an untracked test in flight; the job would have committed
and pushed them under `nightly: <date>`. Found during a self-audit against the new file-ownership rule.
Two earlier commits had already swept Treasury's work under an unrelated message — content intact,
attribution wrong.

### Pitfall 19: Your staged work can be ABSORBED by another seat's commit, and your own commit then reports success while doing nothing

**Symptom:** You stage a file, run `git commit`, see no error, and report a commit hash — but your commit message
**does not exist in history anywhere** (`git log --all --grep "<your msg>"` → 0), and `git log -1 --format=%s HEAD`
shows *another seat's* message. Your file content IS present, committed under someone else's commit.

**Cause:** Pitfall 18 in reverse, on the same shared tree. `git add <path>` then `git commit` is **not atomic across
writers**. If another agent (all four seats commit as the *same* git identity) runs a commit between your `add` and
your `commit` — and their command stages the whole index, e.g. `git commit` with no path list or `git add -A` — the
commit picks up **your already-staged file** and records it under **their** message. Your own `git commit` then finds
an empty index and exits 1. Measured: my `add` at 02:23:57, their commit at 02:24:00 carrying my file; my commit
message: 0 occurrences in history.

**Why it goes unnoticed — two independent traps:**
1. `git commit` exits **1** on an empty index, but if you pipe it (`git commit ... | head -1`), `$?` reads the
   *pipe's* exit (0), not git's. A piped exit code is not git's exit code. Never read `$?` after a pipe.
2. Printing `$(git rev-parse --short=9 HEAD)` labelled "committed:" proves only that **HEAD exists** — not that the
   commit is yours, not that it happened. It is a *plausible-looking* receipt for a no-op.

**Rule:** After any commit, verify the commit is *yours*, not merely that a HEAD exists:
```bash
git log -1 --format=%s | grep -qF "<a distinctive phrase from your message>" \
  && echo "OK: my commit landed" \
  || echo "FAILED: my commit was absorbed or did not happen — check git log -1 --format=%s"
```
Then confirm **content** landed too (`git show HEAD:<path> | grep <your change>`) — content on the remote under a
foreign message is recoverable; a message-only check on an empty commit is not.

**Prevention:** Use `vault-commit.py` (Pitfall 18) and never leave work merely *staged* across a gap — stage and
commit in the **same command**, and re-check the message afterwards. A staged file is not a safe resting state on a
multi-writer tree; it is an open invitation to be swept.

**The message check is the protection — command atomicity is only damage reduction.** Reproduced live
(2026-09-28, Pixel seat): the command was already `git add <path> && git commit -m "…"`, staged and committed
together, and it **still** lost the race — `&&` chains two processes and the gap between them is the window. A
peer's commit swept the staged file; the local `git commit` exited 1; the message had **0 occurrences** in
history. The content was safe; only the check revealed it. So run this after **every** commit — it is the
load-bearing step, not the single-command form:
```bash
git log -1 --format=%s | grep -qF "<phrase from my message>" && echo OK || echo "FAILED: absorbed"
```
Prefer `vault-commit.py`, which reports `LEFT UNTOUCHED` for other writers' paths and prints the hash it made.

### Pitfall 16: One-shot cron sweeps for rate-limited GitHub work

When a batch of GitHub API work (repo create + fork + PR + list) is blocked by the GraphQL bucket, don't retry in-session. Schedule a one-shot cron for ~3 min after the bucket reset (`gh api graphql -f query='query { rateLimit { resetAt } }'` gives the exact time) with the full task list, `unset GITHUB_TOKEN` as step 0, and a verify-after-every-task requirement. Report remaining quota at the end. This turns a rate-limit wait into an autonomous batch.

### Pitfall 17: GitHub account-level bot flag — root cause is multi-key burst pacing

**Symptom (ProtoJay4789, persistent):** authenticated REST drops to the anonymous **60 req/hr** tier (a normal PAT gets 5,000), GraphQL is hard-capped **0/0**, and forks return **403 "cannot fork"** — even with a valid token that `gh api user` identifies correctly. This is NOT a token expiry and NOT a transient rate-limit; it's an **account-level abuse-detection flag**.

**Root cause (diagnosed Aug 3, 2026):** GitHub's bot-detection flags accounts showing automated high-volume API behavior. The trigger on this account was giving **multiple agents (Gentech + Forge + Jintech) each their own key** that made rapid bulk calls (forking, creating repos, cloning, pushing) in parallel. The 403-on-fork + GraphQL-0/0 + rest-dropped-to-60 signature is the classic bot-throttle fingerprint.

**Key facts:**
- It's automated defense, not personal/punitive. It does NOT delete the account's repos.
- **git push/clone does NOT consume API quota** — brain backup, vault syncs, hub syncs run free even on a flagged account.
- The flag is **visible to recruiters** (blocked features, low limits) — a clean account matters for employer-facing GitHub.

**Prevention (a fresh account gets flagged the same way if behavior repeats):**
- **Pace agent access**: never give multiple agent keys simultaneous write access that bursts. Space API operations out; no 50-forks-in-a-burst.
- Prefer **read-only or minimal-scope tokens** for agents that don't need write.
- Never run several agent keys hammering the same account in parallel.
- The fix is **behavioral pacing**, not just creating a new account.
- For a clean employer-facing account: keep it human-paced, push projects via `git push`, and point recruiters at the VPS-hosted portfolio (portfolio.gentechlabs.net) rather than GitHub API state.

**Diagnosis to confirm it's the account flag, not a token:**
```bash
# If this returns the login, the credential is fine — the account is throttled:
curl -s -H "Authorization: token $TOKEN" "https://api.github.com/user" | python3 -c "import json,sys; print(json.load(sys.stdin).get('login'))"
# Rate limit via token — if it shows 60/60 while authenticated, the account is flagged:
curl -s -H "Authorization: token $TOKEN" "https://api.github.com/rate_limit" | python3 -c "import json,sys; r=json.load(sys.stdin)['resources']['core']; print('core:', r['limit'], 'remaining:', r['remaining'])"
```
A valid token returning the login but showing 60/hr = account flag, not token issue.

---

### Pitfall 20: Your commit sweeps a peer's staged work, with no `add -A` anywhere

**Symptom:** You name two paths, commit, and the commit carries ten — another writer's staged files ride
into it under your message, attributed to you. No `git add -A` appears anywhere in your command.

**Cause:** `git add -- <paths>` then `git commit -m msg` with **no path list** commits the **entire
index**, not what you just staged. Any writer who left files staged — a crashed `add && commit`, an
`git add -A` before an early exit — has them swept in. This is Pitfall 18's mechanism **without** the
`-A`, which is why nobody saw it coming: the rule "never `git add -A`, name your paths" was followed
exactly, and the sweep happened anyway. Pitfall 19 is the *victim* side of the same tree; this is the
*sweeper* side, and the sweeper is the one who looks like they did something wrong.

**Measured (one seat's own commit):** 2 paths named, 10 carried — 4 gate scripts another writer had
staged, 4 handoff notes never touched. The commit that *reported* those scripts as untracked was itself
the commit that committed them.

**Fix — always pass the path list through to the commit:**
```bash
git commit -m "msg" -- <path> [<path> ...]     # commits ONLY these, leaves a peer's staging intact
```
Then verify scope from the **file list, not the exit code** — a commit that exits 0 can still carry the
wrong content:
```bash
git show --name-only --format= HEAD             # must list exactly what you named
```
A tool that stages for you should do all three: pass paths to `commit`, warn about a peer's
already-staged files before committing, and diff the resulting file list against what was requested.

**Falsify it with a NEGATIVE CONTROL:** stage a peer's file in a scratch repo, then run a bare
`git commit -m` and assert it DOES sweep it. Without that direction the passing test could pass because
the hazard never occurred. Test: `10-Labs/tooling/test-vault-commit-index-sweep.py` (7/7, includes the
control).

**Session source:** Sep 28, 2026 — `vault-commit.py` staged named paths then ran `git commit -m msg`
with no path list; measured in a real commit (2 named, 10 carried).

### Pitfall 21: A domain/ownership guard that matches by SUBSTRING cannot express "X except Y" — use LONGEST-MATCH

**Symptom:** An ownership guard reports a gap ("seat S owns nothing, so nothing refuses anyone at
`<dir>/`"). The obvious repair — add the broad directory prefix for that seat — is a **trap**: it starts
refusing paths *inside* that directory that belong to someone else.

**Cause:** Substring matching (`any(prefix in path for prefix in FOREIGN)`) cannot say
"`10-Labs/**` **outside** `10-Labs/agent-kit-self-tracking/`". Adding the broad `"10-Labs/"` makes it a
foreign hint for *every other seat*, and the money-path owner's own files live inside it:
```
treasury -> 10-Labs/agent-kit-self-tracking/lfj_recenter.py    REFUSED  <-- FALSE BLOCK
treasury -> 10-Labs/agent-kit-self-tracking/steward_key.py     REFUSED  <-- FALSE BLOCK
```
A guard that blocks an owner from its own signing files is worse than the gap it closed, and it teaches
the owner to pass `--force` every time — the "useless, therefore bypassed" failure that defeats the guard.

**Fix — most-specific-prefix wins.** Sort all prefixes longest-first and let the first match decide:
```python
_SEAT_PREFIXES = tuple(sorted(((p, s) for s, ds in SEAT_DOMAINS.items() for p in ds),
                              key=lambda t: -len(t[0])))
def domain_owner(path):
    for pref, seat in _SEAT_PREFIXES:
        if pref in path:
            return seat          # longest-first: the most specific prefix decides
    return None
```
No-match means unclaimed — leave it **permissive** (registry silent ⇒ allow) rather than inventing
ownership. Keep the conservative all-foreign answer only when the seat itself is unknown.

**Two more traps, both measured:**
1. **Lane prefixes collide.** A registry pattern like `01-HANDOFFS/gentech-*` also matches
   `01-HANDOFFS/gentech-treasury-to-x/` as a substring, refusing a peer its **own** handoff lanes. Prose
   lane patterns need a path-segment rule, not a substring.
2. **A guard list is a SECOND hand-typed copy of the registry and will drift.** Measured drifted in both
   directions — protecting dirs assigned to nobody while missing dirs that were assigned. Compare guard
   prefixes against the registry and fail loudly on divergence; better, derive them.

**Falsify both ways:** make `seat` injectable so one process can test every seat, then assert the
carve-out case directly (`domain_owner(money_path) == <owner>`). The guard's own seat is often `""` when
run from a shared script path, so a seat-blind test asserts the wrong seat's domain and passes while
proving nothing. Reverting to a flat list must turn the test RED.

### Pitfall 22: `git reset --hard <remote>/<branch>` on a multi-writer tree is a deletion, not a reconcile — verify the premise first

**Symptom:** A handoff or command says "the divergence is purely a re-hash, so reset --hard to make
local match remote." It looks like housekeeping. It deletes files that exist nowhere else.

**Cause:** On a shared tree, local HEAD can hold both **patch-equivalent commits** (the re-hash) AND
**unique commits/files** (real work done since the fork). A reset keeps the remote side and discards the
local side. If the local side is non-empty, the reset is data loss — not a sync. The fact that the numbers
match (e.g. "6654 behind / 6317 ahead") only says the branches diverged; it does not say the local side
is empty.

**Verification before any destructive reconcile:**

```bash
# 1. How much of the divergence is patch-equivalent (re-hash) vs unique?
git cherry <remote>/<branch> HEAD~<n>..HEAD | awk '{print $1}' | sort | uniq -c
# '+' = unique to local, no equivalent on remote
# '-' = patch-equivalent to a remote commit

# 2. Are the files in local HEAD but not on the remote actually present on disk?
for p in $(git diff --name-status HEAD <remote>/<branch> | awk '$1=="D"{print $2}'); do
  [ -f "$p" ] && echo "DISK-ONLY: $p"
done

# 3. Are any of those files read by a live process from this tree?
grep -R "$(pwd)/<relative-dir>" /path/to/live/scripts/ /etc/systemd/system/ /proc/*/cwd 2>/dev/null
```

**Decision rule:**

| local side | remote side | safe reconcile |
|---|---|---|
| empty (0 unique commits, 0 unique files) | real commits | `git reset --hard <remote>/<branch>` |
| real commits OR real files | real commits | **merge** (merge base exists) or manual reconciliation |
| real files referenced by live processes | anything | merge, **and** keep the live paths intact during the window |

**Rule:** if `git cherry` shows any `+` commits, or `git diff --name-status HEAD <remote>/<branch>`
shows any `D` files that exist on disk, **refuse `reset --hard`**. The correct tool is a normal merge
(if the merge base exists) or a documented manual reconciliation. A `--keep` reset is not a safe
substitute: it refuses when the tree is dirty, but on a clean tree it still moves the branch and strands
the local-only files under a moved ref.

**Rescue before refusing:** snapshot the at-risk state so the merge can proceed without anyone fearing
loss:
```bash
git tag -f rescue-pre-reset-$(date +%Y%m%d) HEAD
tar czf /tmp/vault-reset-backup-$(date +%Y%m%d).tar.gz $(git diff --name-status HEAD <remote>/<branch> | awk '$1=="D" && -f $2 {print $2}')
```

**Why this keeps happening:** "re-hash" is a believable story for a single-writer repo. On a
multi-writer tree it is a half-truth — the patch-equivalent part is real, but the unique part is what
matters. Always measure the unique part before agreeing to a destructive command.

### Pitfall 23: "Rate-limited by GitHub" and "throttled by our own gate" are different outages with different unblocks

**Symptom:** A push or API call fails and the diagnosis is "GitHub rate-limited us." The fix proposed is
"wait for the bucket to reset."

**Cause:** Two distinct throttles wear the same error costume. A local write gate (`github-write-gate.py`,
max 20/hr) rejects or queues work long before GitHub's 5000/hr authenticated bucket is exhausted. Treating a
local gate as a remote rate limit means waiting instead of spacing our own calls, and it hides the real
constraint.

**Check both before diagnosing:**

```bash
# GitHub account-level (remote)
curl -s -H "Authorization: token $(gh auth token)" https://api.github.com/rate_limit \
  | python3 -c "import sys,json; r=json.load(sys.stdin)['resources']['core']; print(f'GitHub core: {r[\"remaining\"]}/{r[\"limit\"]}')"

# Local gate (ours)
python3 /root/.hermes/scripts/github-write-gate.py status
```

**Rule:** Only call it a GitHub rate limit when GitHub's own `rate_limit` endpoint shows a low
remaining count. If our gate is the bottleneck, report `remaining=<n>/20` and the next available slot —
that is a different fix (spacing, batching, or raising the local limit), not a wait on GitHub.

### Pitfall 24: Two writers converging on one canonical artifact will each DELETE THEIR OWN copy — name the survivor out loud

**Symptom:** An artifact that two agents both correctly judged redundant ends up with **zero** copies. Neither
made a mistake; both made the same reasonable one.

**Measured 2026-09-28:** Labs and HQ each wrote a regression test for the same guard. Labs saw HQ's first and
deleted its own, naming HQ's canonical. HQ ran Labs' test, judged it stronger, and deleted its own. For several
minutes the guard had **no test at all** — and neither agent was placed to notice, because each was looking at
the *other's* copy as the survivor.

**Cause:** *"Yours is canonical, so I removed mine"* is a correct decision made on an assumption about the other
writer's copy that the other writer is simultaneously invalidating. The remove-the-duplicate rule and the
announce rule collide, and the losing artifact is the one nobody is watching.

**Rule — name the survivor OUT LOUD, in writing, and delete only after the peer has named theirs:**

1. **Deleting a duplicate is a decision about a PAIR.** State it as *"X survives; Y (mine) is deleted because X
   is canonical"* — never "I deleted the duplicate."
2. **Announce BEFORE the delete, not after.** The peer needs the window in which they would otherwise delete
   theirs. A post-hoc "I deleted mine too" is a collision report, not a prevention.
3. **Never delete your own copy on the strength of the other's EXISTENCE.** Delete on the strength of the
   other's *survival declaration*.
4. **After any concurrent-edit episode on a shared artifact, verify the survivor exists AND RUNS.** The shape
   this leaves behind is a **tracked-but-missing file**: present in `git ls-files`, absent from disk, so it
   looks alive in every listing that consults git and dead to anything that runs it. Check both.
5. **Prefer a commit pin over a `.bak` for the survivor.** A `.bak` can be cleaned up mid-session by either
   writer (one was, while a test was running, silently degrading a negative control); `git show <sha>:<path>`
   is immutable and both writers can reach it.

## Verification Steps

### 1. Test Locking Mechanism

```bash
# Test 1: Basic import
cd ${PROFILE_DIR}/scripts
python3 -c "from git_repo_lock import GitRepoLock, push_with_retry; print('Import successful')"

# Test 2: Lock acquisition
python3 -c "
from git_repo_lock import GitRepoLock
import time
with GitRepoLock():
    print('Lock acquired')
    time.sleep(5)
print('Lock released')
"
```

### 2. Test Each Sync Script

```bash
# Test gaming hub sync
cd /root/repos/gentechlabs.github.io
python3 ${PROFILE_DIR}/scripts/gaming-hub-sync.py

# Test hub nightly sync
python3 ${PROFILE_DIR}/scripts/hub-sync-nightly.py

# Test vanito music sync
cd /root/my-music
python3 vanito-music-sync.py
```

**Expected output:** Success messages, no hangs, lock file cleaned up.

### 3. Verify Cron Schedules

```bash
# List all jobs
cronjob action=list | grep -E "(schedule|name)"

# Check for overlapping schedules
# (Manual review of job schedules)
```

### 4. Monitor Git Log

```bash
# Watch for conflict patterns over 1 week
git log --oneline --since="1 week ago" --format="%H %ad %s" --date=iso | grep -E "sync|push"

# Look for:
# - Multiple sync commits at same time (still colliding)
# - No sync commits (lock blocking jobs)
# - Fewer conflicts (fix working)
```

---

## Estimated Impact

| Metric | Before | After Phase 1 | After Phase 2 |
|--------|--------|---------------|---------------|
| Conflicts/week | 5+ | 1-2 (70% reduction) | Near-zero |
| Manual intervention | Always | Rare | Never |
| Data loss risk | High | None | None |
| Deployment delay | Minutes | Seconds | Instant |

---

## References

- **Git conflict analysis:** `/root/git-conflict-analysis.md`
- **Fix summary:** `/root/git-conflict-fixes-summary.md`
- **Lock utility:** `${PROFILE_DIR}/scripts/git_repo_lock.py`

---

## Session History

**July 5, 2026 — Gentech VPS:**
- GLM-5.2 delegated to analyze Git conflicts
- Found 5 cron jobs writing concurrently
- 12:00 UTC collision zone (Portfolio Health + Gaming Hub Sync)
- Implemented file locking, schedule offsets, retry logic
- Testing: gaming-hub-sync.py ✅, hub-sync-nightly.py ✅, vanito-music-sync.py ⚠️ (hangs)

**Key learning:** 15-minute schedule offsets + atomic file locking = 70% conflict reduction.

**July 8, 2026 — Cron job (second session):**
- Vanito music sync (vanito-music-sync.py) produced ZERO output and timed out twice
- Root cause (part 1): Python stdout buffering hid where the script hung — `print()` output was block-buffered and lost on timeout. Even though the script printed progress, nothing appeared in the terminal output because no flush happened before the timeout killed the process.
- Root cause (part 2): Hash-based change detection false positives — the hash used `song.get('duration', '')` and `song.get('genre', '')` (empty defaults for missing fields) while the normalization step wrote `'0:00'` and `'Unknown'`. Every run detected 2 "changes" even though output was identical. Fix: align hash defaults with normalization defaults.
- **Outcome:** Pitfall 5 expanded with buffering guidance. Pitfall 7 added for hash mismatch pattern.

**July 14, 2026 — Cron job (hub sync):**
- hub-sync-nightly.py failed: `git pull --rebase` conflict produced structurally corrupted JSON via file-level merge (108 `{` vs 107 `}`, sections nested inside wrong parent)
- `sanitize_json_text()` stripped conflict markers but couldn't fix structural corruption — different problem class than conflict markers
- Pre-push validation correctly blocked the corrupt data from reaching remote
- Recovery: restored from vault ground-truth copy → amend commit → push
- **Outcome:** Pitfall 8 added for structural JSON corruption from rebase auto-resolution, with diagnostic techniques (brace count, depth trace) and recovery pattern (restore from ground truth, don't repair merge).