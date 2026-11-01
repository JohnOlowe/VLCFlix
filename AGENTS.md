# AGENTS.md — Standing instructions for AI coding agents

**Scope:** these rules are task-agnostic. Anything project-specific belongs in a separate
file (`CONTEXT.md`, `README.md`) that this one points to. Where a rule came from a real
failure, the failure is named — that is the point of the rule.

**Tradeoff:** these bias toward caution over speed. For trivial tasks, use judgment — but
never skip §5 (verify) or §12 (disclose).

---

## 1. Think Before Coding

**Don't assume. Don't hide confusion. Surface tradeoffs.**

Before implementing:

- State your assumptions explicitly. If uncertain, ask.
- If multiple interpretations exist, present them — don't pick silently.
- If a simpler approach exists, say so. Push back when warranted.
- If something is unclear, stop. Name what's confusing. Ask.

---

## 2. Simplicity First

**Minimum code that solves the problem. Nothing speculative.**

- No features beyond what was asked.
- No abstractions for single-use code.
- No "flexibility" or "configurability" that wasn't requested.
- No error handling for impossible scenarios.
- If you write 200 lines and it could be 50, rewrite it.

Ask yourself: "Would a senior engineer say this is overcomplicated?" If yes, simplify.

---

## 3. Surgical Changes

**Touch only what you must. Clean up only your own mess.**

When editing existing code:

- Don't "improve" adjacent code, comments, or formatting.
- Don't refactor things that aren't broken.
- Match existing style, even if you'd do it differently.
- If you notice unrelated dead code, mention it — don't delete it.

When your changes create orphans:

- Remove imports/variables/functions that YOUR changes made unused.
- Don't remove pre-existing dead code unless asked.

The test: every changed line should trace directly to the user's request.

---

## 4. Goal-Driven Execution

**Define success criteria. Loop until verified.**

Transform tasks into verifiable goals:

- "Add validation" → "Write tests for invalid inputs, then make them pass"
- "Fix the bug" → "Write a test that reproduces it, then make it pass"
- "Refactor X" → "Ensure tests pass before and after"

For multi-step tasks, state a brief plan:

```
1. [Step] → verify: [check]
2. [Step] → verify: [check]
3. [Step] → verify: [check]
```

Strong success criteria let you loop independently. Weak criteria ("make it work") require
constant clarification.

---

## 5. Verify Empirically — Never Assert From Memory

**Run it. Look at it. Query it. Then say it.**

Before you state a fact about the system, prove it:

| Claim | Proof required |
|---|---|
| "The tests pass" | paste the runner output |
| "The image looks right" | **open the file and look at it** |
| "The push landed" | `git ls-remote` / API check on the remote SHA |
| "The token is scoped to one repo" | probe every other repo and the admin endpoints; show 403s |
| "The machine has X space" | `df -h`, `du -sh` — measure it |
| "This endpoint requires Y" | call it and read the status code |

Rules that follow from this:

- **Measure limits, don't recall them.** I once asserted a large file "couldn't live in the
  workspace" from memory of a documented cap. `df -h` showed 21 GB free — the cap was on
  turn-end snapshots, not disk. Wrong claim, avoidable. Run the measurement.
- **A blank or suspicious output is a bug, not a result.** If generated text is invisible,
  check pixel statistics (`alpha.max()`, non-zero count, bbox) before re-rendering blindly.
  Root cause was double-normalising an already-normalised array.
- **Test against throwaway fixtures.** Spin the test in `/tmp` with a local bare remote,
  stub server, or temp DB. Never test destructive paths against the real repo or datastore.
- **Give every safety check a negative control.** A guard that greps the script for a
  forbidden flag matched its own warning string and always fired. Test the detector against
  a known-bad input *and* a known-good one.
- **Never execute a test scaffold containing side-effecting commands.** Piping a scaffold
  into `bash` ran an appended `git push --force` for real. Compose test harnesses from
  inert parts; only execute what you have read.

---

## 6. Persistence and Crash Recovery

Assume the process can die **mid-turn**, without warning.

**At the start of every session, read the state files before doing anything:**

1. `CONTEXT.md` — human-readable current state, decisions, next steps
2. `TURN_LOG.md` — append-only log of what actually happened
3. `checkpoint.json` — machine-readable state (files, IDs, SHAs, next steps)

**Write to them often:**

- after every meaningful action, not only at the end
- before and after anything expensive or destructive
- a turn is not finished until the state files reflect it

**Keep a `RECOVERY` section** in `CONTEXT.md` listing, in order, what to read and where to
resume. Write it as if for a stranger — because after a crash, that is what it is for.

**Know what survives a restart:**

- regular files inside the workspace → yes
- installed packages, `.venv`, `node_modules`, build caches → **no**; re-install as needed
- shell variables, background processes, in-flight command output → **no**

**Never delete the memory files** when freeing space. They are kilobytes; the assets are not.

---

## 7. Git and Remote Work

**Pull at the start. Commit and push at the end. Push again mid-work when a step completes.**

- **Never `--force` and never `--force-with-lease`.** Not in a script, not in a test, not
  "just this once". If a push is rejected, `git pull --rebase --autostash`, resolve, retry.
- Make pushes plain fast-forwards: `git fetch` → `git rebase origin/<branch>` → `git push`.
- Commit before any long or risky operation, so the work exists off-disk.
- **Back up uncommitted work to a patch file before pulling.**
- **Commit small and often.** Each commit is a restore point. Write real messages.
- Set the commit identity deliberately (`user.name`, `user.email`) — the default agent
  identity will pollute history.
- `.gitignore` build/cache directories (`.cache/`, `.venv/`, `node_modules/`, `dist/`,
  `build/`, `out/`, `target/`, `__pycache__/`) before the first commit, not after.
- **Submodules/remotes:** use `-b <branch>` explicitly; a bare remote with no default branch
  makes a plain `clone` produce an empty checkout ("remote HEAD refers to nonexistent ref").
- **Verify what landed.** After a push, compare `git ls-remote origin <branch>` with your
  local HEAD.

---

## 8. Credentials and Least Privilege

**Request the narrowest credential that does the job, and prove it is narrow.**

- Prefer scoped tokens over broad ones. For GitHub: a **fine-grained PAT** limited to
  **one repository** with **Contents: read/write** only. Metadata is auto-granted; everything
  else — Administration, Actions, Workflows, Secrets, Issues — stays at *No access*.
- A credential that can edit repo settings can also **disable the safety rules you just
  set**. Keep `Administration` off the agent's token so protections cannot be undone by it.
- **Deploy keys** are an alternative: one repo only, never an admin, no expiry. Trade-offs:
  no API access, needs an SSH URL, one key per repo.
- **Verify scope by probing.** Attempt a write on a repo that should be forbidden and show
  the 403. Confirm the admin endpoints are refused. Report the status codes, not an opinion.
- **Never commit a credential.** `.gitignore` `.git-credentials`, `.netrc`, `.env`, `.ssh/`,
  `*.pem`, `*.key`, `id_ed25519*`. Keep secrets in files excluded from snapshots where
  possible, and say plainly which mechanism is protecting them.
- **`$HOME` may equal the repository root.** In several sandboxes it does — so
  `git config --global` writes a file *into the repo* which the next `git add -A` commits.
  Check before using `--global`; `.gitignore` `.gitconfig` if `$HOME` is the work tree.
- Ask the user to rotate any credential that has passed through chat.

---

## 9. Large Files and Storage Limits

Distinguish three different ceilings and respect each:

| Ceiling | Typical value | Consequence |
|---|---|---|
| Workspace snapshot | ~128 MB | files above it are not persisted; work dies at turn end |
| Git host per-file | 100 MB | push is **rejected** outright |
| Git host per-repo | ~1 GB soft | slow clones, warnings |

Rules:

- **Splitting does not reduce bytes.** 500 MB of chunks is still 500 MB. Decide where the
  bytes will *land*, not just how they are parcelled.
- **`.git` counts toward the workspace budget.** Committing a big file locally inflates the
  workspace by roughly its own size. Prefer keeping big blobs out of the working clone.
- **Default pattern for big binaries:** split into ≤90 MB chunks, commit them to a
  **separate branch** (e.g. `assets`), keep only a small manifest + checksum + restore script
  on the main branch. A normal clone of `main` then stays small, because `pull` on `main`
  never fetches the asset branch's objects.
- **Always ship a way back:** `manifest.txt` (bytes, chunk count, sha256), the `.sha256`
  file, and a `reassemble.sh` that concatenates, verifies the hash, and fails loudly.
  Verify the round-trip at least once from a fresh clone.
- **Scratch space outside the snapshot** (`/var/tmp` and similar) is the right place to
  assemble and split. `/tmp` is often a small RAM disk.
- Guard rails in the automation: refuse to commit a file above a threshold, and warn on the
  way up. Block *before* the commit, and unstage when you block.
- **Permanent artifacts need permanent care.** If force-push is disabled, anything pushed is
  irreversible — double-check before adding something huge.

---

## 10. Generated Assets and Layered Media

**Build in layers. One layer, one file, one commit.**

- Each layer is its own file with transparency preserved. Each stage gets a flattened
  composite snapshot so any point can be reviewed or rolled back.
- Keep a manifest listing every layer: id, path, what it is, and whether it must stay
  faithful to a reference ("must stay true") versus freely generated.
- Keep the build script in the repo. The script — not the PNG — is the source of truth;
  assets must be reproducible from it.
- Name drafts explicitly (`final/`, `final2/`, `layers3/`) and say which generation is
  current. Don't silently overwrite; don't silently keep everything either.
- **Look at what you produced** before reporting success (§5). If it is blank or wrong,
  diagnose the pipeline before adjusting aesthetics.
- Record the provenance of anything AI-generated next to the file: prompt, model, inputs,
  and which parts were preserved untouched.
- Respect the target format: canvas size, safe margins, and how it will be displayed
  (a projector, a thumbnail, a phone) are part of the spec.

---

## 11. Long-Running Processes and Previews

- Don't run servers, watchers, or anything long-lived inside a blocking command; use a
  supervised background process you can read logs from.
- Bind to `0.0.0.0`, not `127.0.0.1`, when the app must be reachable from outside.
- Browser-facing code uses relative URLs; it must never call `localhost` to reach a backend
  that lives elsewhere.
- Fix preview-breaking config (host/origin allowlists, iframe-blocking headers) in the same
  turn you notice it — don't leave the user with a broken preview.

---

## 12. Honesty and Accidents

- Report what you actually did, including anything that went wrong. State the blast radius
  and whether anything was damaged.
- Disclose side effects that happened during testing — a push that landed, a row written, a
  file deleted — even if the test "wasn't supposed to" do that.
- Never claim a check passed you did not run, and never describe output you did not read.
- Distinguish **verified**, **assumed**, and **unknown** explicitly.
- If a previous statement of yours turns out to be wrong, say so plainly, correct the
  artifact, and record the correction so it is not repeated in a summary.
- Ask before destructive or irreversible operations: deleting data, rewriting history,
  rotating credentials, changing billing or access.

---

## 13. Environment Notes (adapt or delete)

These reflect common sandbox behaviour; confirm rather than assume.

- Workspace root persists; generated/dependency/build directories are usually excluded from
  snapshots (`.cache`, `.local`, `node_modules`, `.venv`, `dist`, `build`, `out`, `target`,
  `__pycache__`).
- Credential paths (`~/.git-credentials`, `~/.netrc`) are typically excluded from snapshots —
  useful, but means the credential does not survive a restart; re-provision it.
- **`.git/config` itself may be excluded** as a sensitive path. Consequence: after a
  snapshot restore the repository has no `origin`, and every push mysteriously reports
  "no remote configured". Keep the **non-secret** remote URL in a tracked file
  (e.g. `.gitremote`) and have the tooling re-add it on demand; only the secret needs
  re-provisioning. Check `git remote -v` first when git behaves as if it is unconfigured.
- Check available disk with `df -h` and free memory with `free -m` before large operations.
- **File modes may not survive a snapshot restore** — a script can come back as `644` and
  fail with `Permission denied` even though git records it as `100755`. Re-`chmod +x` and
  `git update-index --chmod=+x` rather than assuming the checkout is broken.
- Prefer a browser-reportable file format and open it for the user when it is the deliverable.

---

## Pre-flight checklist

Before starting:

- [ ] Read the state/context files
- [ ] Pull from the remote
- [ ] Check available space and what is already built
- [ ] Restate the goal as a verifiable criterion

Before finishing:

- [ ] Ran the thing and looked at the output
- [ ] Checked the diff contains only intended changes
- [ ] State files updated with the new reality and next steps
- [ ] Committed and pushed, and confirmed the remote SHA
- [ ] Reported anything unfinished, unverified, or accidentally changed

---

**These guidelines are working if:** fewer unnecessary changes in diffs, fewer rewrites due
to overcomplication, clarifying questions come before implementation rather than after
mistakes, and no reader ever has to discover a side effect you forgot to mention.
