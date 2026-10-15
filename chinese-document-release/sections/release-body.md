<!-- AUTO-GENERATED from release-body.md.tmpl — do not edit directly -->
<!-- Regenerate: bun run gen:skill-docs -->
## Step 2: Per-File Documentation Audit

**Ship-owned documentation mode:** 在 audit-scope 的 edit boundary 之下,执行 Step 1 与 1.5 之后,只跑 Steps 2–4 与 6,然后返回其 JSON 结果;其下方的所有 standalone metadata、review、commit 与 PR 步骤对该 child 不可用。

Read each documentation file and cross-reference it against the diff. Use these generic heuristics
(adapt to whatever project you're in — these are not gstack-specific):

**README.md:**
- Does it describe all features and capabilities visible in the diff?
- Are install/setup instructions consistent with the changes?
- Are examples, demos, and usage descriptions still valid?
- Are troubleshooting steps still accurate?

**ARCHITECTURE.md:**
- Do ASCII diagrams and component descriptions match the current code?
- Are design decisions and "why" explanations still accurate?
- Be conservative — only update things clearly contradicted by the diff. Architecture docs
  describe things unlikely to change frequently.

**CONTRIBUTING.md — New contributor smoke test:**
- Walk through the setup instructions as if you are a brand new contributor.
- Are the listed commands accurate? Would each step succeed?
- Do test tier descriptions match the current test infrastructure?
- Are workflow descriptions (dev setup, operational learnings, etc.) current?
- Flag anything that would fail or confuse a first-time contributor.

**CLAUDE.md / project instructions:**
- Does the project structure section match the actual file tree?
- Are listed commands and scripts accurate?
- Do build/test instructions match what's in package.json (or equivalent)?

**Other relevant docs and authored templates (including nested declared roots):**
- Read the file, determine its purpose and audience.
- Cross-reference against the diff to check if it contradicts anything the file says.

For each file, classify needed updates as:

- **Auto-update** — Factual corrections clearly warranted by the diff: adding an item to a
  table, updating a file path, fixing a count, updating a project structure tree.
- **Ask user** — Narrative changes, section removal, security model changes, large rewrites
  (more than ~10 lines in one section), ambiguous relevance, adding entirely new sections.

---

## Step 3: Apply Auto-Updates

Make all clear, factual updates directly using the Edit tool after reading the full
file. In ship-owned read-only mode, propose them as blockers without editing. Preserve
pre-existing user edits; ambiguity about overlapping content goes back to the parent.

For each file modified, output a one-line summary describing **what specifically changed** — not
just "Updated README.md" but "README.md: added /new-skill to skills table, updated skill count
from 9 to 10."

**Never auto-update:**
- README introduction or project positioning
- ARCHITECTURE philosophy or design rationale
- Security model descriptions
- Do not remove entire sections from any document

---

## Step 4: Ask About Risky/Questionable Changes

In ship-owned mode, record the specific decision and affected paths as blockers for
the parent, leave the questionable content alone, and finish the remaining safe audit.
Do not call AskUserQuestion or auto-choose any recommendation. Standalone mode follows
the existing gate below.

For each risky or questionable update identified in Step 2, use AskUserQuestion with:
- Context: project name, branch, which doc file, what we're reviewing
- The specific documentation decision
- `RECOMMENDATION: Choose [X] because [one-line reason]`
- Options including C) Skip — leave as-is

Apply approved changes immediately after each answer.

---

## Step 5: CHANGELOG Voice Polish

This step polishes voice only. It does not rewrite, replace, or regenerate CHANGELOG
content: the entries are the release record, and a replaced entry loses facts nobody
notices until after the release.

**Rules:**
1. Read the entire CHANGELOG.md first. Understand what is already there.
2. Only modify wording within existing entries. Never delete, reorder, or replace entries.
3. Never regenerate a CHANGELOG entry from scratch. The entry was written by `/ship` from the
   actual diff and commit history. It is the source of truth. You are polishing prose, not
   rewriting history.
4. If an entry looks wrong or incomplete, use AskUserQuestion — do NOT silently fix it.
5. Use Edit tool with exact `old_string` matches — never use Write to overwrite CHANGELOG.md.

**If CHANGELOG was not modified in this branch:** skip this step.

**If CHANGELOG was modified in this branch**, review the entry for voice:

- **Sell test (Diataxis):** a good entry answers "What changed?" (names the
  feature/fix), "Why should I care?" (user impact, pain removed) and "How do I use
  it?" (command, flag, or link to docs). An entry that answers fewer than two of these needs
  attention, not replacement: report the missing facts or user impact, and polish
  existing wording only.
- Lead with what the user can now **do** — not implementation details.
- "You can now..." not "Refactored the..."
- Flag commit-message-style entries and polish wording without removing facts.
- Flag misplaced internal/contributor details for the author; do not move them out of an existing entry.
- Auto-fix minor voice adjustments. Ask about missing or incorrect facts, but never replace an entry, even with approval. Report larger rewrite requests as deferred author work.

---

## Step 6: Cross-Doc Consistency & Discoverability Check

After auditing each file individually, do a cross-doc consistency pass:

1. Does the README's feature/capability list match what CLAUDE.md (or project instructions) describes?
2. Does ARCHITECTURE's component list match CONTRIBUTING's project structure description?
3. Does CHANGELOG's latest version match the VERSION file?
4. **Discoverability:** Is every documentation file reachable from README.md or CLAUDE.md? If
   ARCHITECTURE.md exists but neither README nor CLAUDE.md links to it, flag it. Every doc
   should be discoverable from one of the two entry-point files.
5. Flag any contradictions between documents. Auto-fix clear factual inconsistencies (e.g., a
   version mismatch). Use AskUserQuestion for narrative contradictions.

In ship-owned mode, protected metadata/manifests stay untouched even for factual
inconsistencies, and narrative contradictions return as blockers. This is the last
ship-child step: output the doc-health summary and audit-scope's JSON result, then
STOP. A partial audit or unresolved required correction is `blocked`, never `current`.

---

## Step 7: TODOS.md Cleanup

This is a second pass that complements `/ship`'s Step 14. Read `review/TODOS-format.md` (if
available) for the canonical TODO item format.

If TODOS.md does not exist, skip this step.

1. **Completed items not yet marked:** Cross-reference the diff against open TODO items. If a
   TODO is clearly completed by the changes in this branch, move it to the Completed section
   with a date-only `**Completed:** YYYY-MM-DD` marker for now. Step 9 adds the final version after Step 8 resolves it; if VERSION is absent, use the completion date only. Be conservative — only mark items with clear evidence in the diff.

2. **Items needing description updates:** If a TODO references files or components that were
   significantly changed, its description may be stale. Use AskUserQuestion to confirm whether
   the TODO should be updated, completed, or left as-is.

3. **New deferred work:** Check the diff for `TODO`, `FIXME`, `HACK`, and `XXX` comments. For
   each one that represents meaningful deferred work (not a trivial inline note), use
   AskUserQuestion to ask whether it should be captured in TODOS.md.

---

## Step 8: VERSION Bump Question

**Ask before changing VERSION** — the version number is the user's release decision.

1. **Read the version source** (the same signal `/ship` uses):
   ```bash
   bun run ~/.claude/skills/gstack/bin/gstack-version-bump classify --base <base>
   ```
   `state: NO_VERSION` means no version source is configured or release automation owns
   it: print `VERSION: not applicable (<versionSource.reason>)`, skip this step, and never
   create VERSION. Exit 2 means a configured version file is broken: show stderr and
   skip this step without guessing a version. Otherwise `versionSource.path` is the
   version file (VERSION unless pinned); read it wherever this step says VERSION.

2. Check if VERSION was already modified on this branch:

```bash
git diff <diff-base> HEAD -- VERSION
```

3. **If VERSION was NOT bumped:** Use AskUserQuestion:
   - RECOMMENDATION: Choose C (Skip) because docs-only changes rarely warrant a version bump
   - A) Bump PATCH (X.Y.Z+1) — if doc changes ship alongside code changes
   - B) Bump MINOR (X.Y+1.0) — if this is a significant standalone release
   - C) Skip — no version bump needed

4. **If VERSION was already bumped:** Do NOT skip silently. Instead, check whether the bump
   still covers the full scope of changes on this branch:

   a. Read the CHANGELOG entry for the current VERSION. What features does it describe?
   b. Read the full diff (`git diff <diff-base> HEAD --stat` and `git diff <diff-base> HEAD --name-only`).
      Are there significant changes (new features, new skills, new commands, major refactors)
      that are NOT mentioned in the CHANGELOG entry for the current version?
   c. **If the CHANGELOG entry covers everything:** Skip — output "VERSION: Already bumped to
      vX.Y.Z, covers all changes."
   d. **If there are significant uncovered changes:** Use AskUserQuestion explaining what the
      current version covers vs what's new, and ask:
      - RECOMMENDATION: Choose A because the new changes warrant their own version
      - A) Bump to next patch (X.Y.Z+1) — give the new changes their own version
      - B) Keep current version — add new changes to the existing CHANGELOG entry
      - C) Skip — leave version as-is, handle later

   **Spawned sessions** (per the spawned-dispatch contract at the top of this skill): the
   recommendation flips — choose C (leave version as-is) and record the uncovered scope in
   your completion report. Ship-owned children stopped at Step 6 and never reach this step.
   A spawned run must never change VERSION: the dispatching workflow owns version numbering.

   The key insight: a VERSION bump set for "feature A" should not silently absorb "feature B"
   if feature B is substantial enough to deserve its own version entry.

---

## Codex Documentation Review (default-on)

After the documentation updates above are written, run an independent cross-model pass that
checks the docs against what actually shipped. This is a standard part of /document-release,
not an opt-in. The user turns it off only by asking explicitly
(`gstack-config set codex_reviews disabled`).

**Spawned-session skip** (per the spawned-dispatch contract at the top of this skill): in a
spawned session, skip this entire section — the dispatching workflow owns its own review
passes, and the apply gate below needs a human. Note the skip in the upcoming Step 9 doc
health summary and continue to Step 9. Ship-owned children already stopped at Step 6.

**Preflight — decide whether and how the doc review runs:**

```bash

# Codex preflight: the probe runs as a command, so any shell works.
_CODEX_PROBE=~/.claude/skills/gstack/bin/gstack-codex-probe
_CODEX_CFG=$(~/.claude/skills/gstack/bin/gstack-config get --stored codex_reviews 2>/dev/null)
_gstack_helper_error=""
[ -x "$_CODEX_PROBE" ] || _gstack_helper_error="gstack: cannot load gstack-codex-probe; re-run ./setup. https://github.com/garrytan/gstack/blob/main/docs/troubleshooting.md#sourced-helper-location"
if [ "$_CODEX_CFG" = "disabled" ] || [ "$_CODEX_CFG" = "unreadable" ]; then
  _CODEX_MODE="disabled"
elif { [ -n "${CODEX_THREAD_ID:-}" ] || [ -n "${CODEX_SANDBOX:-}" ] || [ "${GSTACK_ACTIVE_HOST:-}" = codex ]; }; then
  _CODEX_MODE="under_codex"
elif ! command -v codex >/dev/null 2>&1; then
  _CODEX_MODE="not_installed"; "$_CODEX_PROBE" log-event codex_cli_missing 2>/dev/null || true
elif [ -n "$_gstack_helper_error" ]; then
  _CODEX_MODE="helper_unavailable"; echo "$_gstack_helper_error"
elif ! "$_CODEX_PROBE" check-auth >/dev/null 2>&1; then
  _CODEX_MODE="not_authed"; "$_CODEX_PROBE" log-event codex_auth_failed 2>/dev/null || true
else
  # Free sandbox check before the paid probe; probe exit 2 = the CLI cannot run.
  _CODEX_MP=0; _CODEX_PS=""
  "$_CODEX_PROBE" check-sandbox || _CODEX_MP=3
  for _CODEX_KIND in exec; do
    [ "$_CODEX_MP" -eq 0 ] || break
    _CODEX_PO=$("$_CODEX_PROBE" probe-model $_CODEX_KIND); _CODEX_MP=$?; printf '%s\n' "$_CODEX_PO"
    case "$_CODEX_PO" in *"STATE: inconclusive"*) _CODEX_PS=inconclusive ;; *"STATE: rate_limited"*) _CODEX_PS=rate_limited ;; esac
  done
  if [ "$_CODEX_MP" -eq 3 ]; then
    _CODEX_MODE="sandbox_unavailable"
  elif [ "$_CODEX_MP" -eq 2 ]; then
    _CODEX_MODE="broken_install"
  elif [ "$_CODEX_MP" -eq 4 ]; then
    _CODEX_MODE="quota_exhausted"
  elif [ "$_CODEX_MP" -ne 0 ]; then
    _CODEX_MODE="model_unusable"
  elif [ "$_CODEX_PS" = inconclusive ]; then
    _CODEX_MODE="unverified"
  elif [ "$_CODEX_PS" = rate_limited ]; then
    _CODEX_MODE="unverified (rate_limited)"
  else
    _CODEX_MODE="ready"; "$_CODEX_PROBE" check-version || true
  fi
fi
echo "CODEX_MODE: $_CODEX_MODE"
```

Branch on the echoed `CODEX_MODE`:
- **`disabled`** (or a send's `consent_missing` line) — `codex_reviews` is off or unreadable. Skip this section entirely; do NOT fall back to a Claude subagent — disabled means no extra review step. Print: "Codex review skipped (codex_reviews disabled). Re-enable: `gstack-config set codex_reviews enabled`."
- **`helper_unavailable`** — the probe is missing or not executable; relay the line above (cause and fix). Fall back to the Claude subagent path.
- **`not_installed`** — Codex CLI absent. Print: "Codex not installed; outside coverage unavailable. Install: `npm install -g @openai/codex`." Fall back to the Claude subagent path.
- **`under_codex`** — stale artifact selected its own harness. Print: "Codex outside review unavailable: harness mismatch; no outside process started. Missing coverage. Repair: setup --host codex." Skip the outside invocation and follow the workflow's native-review instructions below. Conflicting inherited harness markers are not grounds to guess another provider.
- **`not_authed`** — installed but no credentials. Print: "Codex not authenticated; outside coverage unavailable. Run `codex login` or set `$CODEX_API_KEY`." Fall back to the Claude subagent path.
- **`broken_install`** — the CLI is on PATH but cannot execute (spawn ENOENT, non-executable binary, missing vendor payload). Print: "Codex is installed but its binary cannot run — Codex passes skipped. Reinstall: `npm install -g @openai/codex`." Relay the probe's HINT lines. Fall back to the Claude subagent path.
- **`model_unusable`** — the selected model (see `CODEX_MODEL:`) is invalid or unavailable to the account (HTTP 400 on every call). Relay the probe's HINT lines and the fix (`GSTACK_CODEX_MODEL=<supported-model>` or config.toml `model`); never substitute a model. Fall back to the Claude subagent path. The ~10s round trip is cached for 1h.
- **`quota_exhausted`** — Codex usage limit: relay the probe's lines verbatim (reset time, retry); no more Codex calls this run. Fall back to the Claude subagent path.
- **`sandbox_unavailable`** — Codex's sandbox cannot start here (containers without user namespaces); the probe printed the reason and fix. No paid call ran; outside coverage is unavailable. Fall back to the Claude subagent path.
- **`ready`** or **`unverified`** — run the Codex pass below. `unverified` means the model check timed out or, with `(rate_limited)`, hit a 429; say so, and let the pass's own verdict decide.

**Disabled is a terminal branch for this section.** If the preflight prints
`CODEX_MODE: disabled`, persist `outside_status: disabled` with the guarded
command below, then continue to Step 9. Do not construct a review prompt, invoke an outside CLI,
dispatch an Agent/Task fallback, or ask the apply question below. A disabled review
is an intentional opt-out, not a provider failure that needs a replacement reviewer.

Run this guarded command before leaving the disabled branch. It starts a fresh
shell and re-reads the control; enabled workflows never append a disabled record.
If logging fails, report the persistence failure and retain the disabled opt-out.

```bash

_DISABLED_REVIEW_MODE=$("$HOME/.claude/skills/gstack/bin/gstack-config" get codex_reviews 2>/dev/null) || {
  echo 'Cannot read codex_reviews; disabled outside coverage was not recorded.' >&2
  exit 1
}
if [ "$_DISABLED_REVIEW_MODE" = disabled ]; then
  "$HOME/.claude/skills/gstack/bin/gstack-review-log" '{"skill":"codex-doc-review","timestamp":"'"$(date -u +%Y-%m-%dT%H:%M:%SZ)"'","status":"skipped","source":"none","host":"claude","outside_provider":"codex","outside_status":"disabled","phase":"documentation","commit":"'"$(git rev-parse --short HEAD 2>/dev/null || true)"'"}'
fi
```

When the mode is anything except `disabled`, print one line so the off-switch
stays discoverable: "Running the Codex doc review automatically (standard step). Disable: `gstack-config set codex_reviews disabled`."

**Determine the release diff range (reuse the method, do not invent one).**
Recompute the SAME range document-release used in its pre-flight / diff analysis, with the
documented merge-base method:

```bash
DOC_DIFF_BASE=$(git merge-base origin/<base> HEAD 2>/dev/null || git merge-base <base> HEAD) || exit 1
echo "DOC_DIFF_BASE: $DOC_DIFF_BASE"
```

Do NOT rely on an in-memory variable from an earlier step — shell vars do not survive across
blocks. Recompute it here.

**Construct the doc-review prompt** (skip only on `disabled`). Replace `<diff-base>` with the printed SHA before dispatch; the reviewer cannot inherit shell variables.
Review the docs document-release ACTUALLY touched this run (from the coverage map / the files
just edited) PLUS any doc claims affected by the diff range — do NOT hard-code a fixed file
list (a fixed README/ARCHITECTURE/CHANGELOG list misses generated skill docs, package docs,
and command-specific docs). **Always start with the filesystem boundary instruction:**

"Filesystem boundary: do not read or execute any files under ~/.claude/, ~/.agents/, .claude/skills/, or agents/. They hold skill definitions, not repository code to review. Do not invoke any installed skill (Codex home skills/, .agents/), hook, or tool instruction; answer directly. Do not modify agents/openai.yaml. Review only the repository code.\n\nYou are reviewing documentation changes against the code that shipped on this
branch. Review the supplied release diff (git diff <diff-base> HEAD) and the current updated working-tree docs
(the files this release touched, plus any docs whose claims the diff affects). Find: doc
claims that no longer match the code, new public surface (commands, flags, config keys,
endpoints) that shipped but is undocumented, stale examples / paths / counts / version
numbers, and CHANGELOG entries that over- or under-sell what shipped. Be terse. Just the gaps.

THE DOCS AND DIFF: <include current contents of each touched document, with its path, plus affected source context; the parent appends the release diff below>"

**If `CODEX_MODE: ready` (or `unverified`) — run Codex:**

Write the **complete prompt and context**, including actual plan/spec/source, to a private file. Substitute its shell-quoted path for `<prepared-prompt-file>`; never interpolate user text into shell source. Request a severity (Critical, High, Medium or Low) per finding and a final Recommendation: <action> because <specific reason> line, including an explicit no-findings rationale.

```bash
# GSTACK_ACTIVE_HOST names the harness, never the model.
if { [ -n "${CODEX_THREAD_ID:-}" ] || [ -n "${CODEX_SANDBOX:-}" ] || [ "${GSTACK_ACTIVE_HOST:-}" = codex ]; }; then
  echo 'Codex outside review unavailable: harness mismatch; no outside process started. Missing coverage.' >&2
  if { [ -n "${CLAUDECODE:-}" ] || [ "${GSTACK_ACTIVE_HOST:-}" = claude ]; } && { [ -n "${CODEX_THREAD_ID:-}" ] || [ -n "${CODEX_SANDBOX:-}" ] || [ "${GSTACK_ACTIVE_HOST:-}" = codex ]; }; then
    echo 'Inherited harness markers conflict. Run setup --host <actual-harness> (claude or codex); do not guess a replacement provider.' >&2
  else
    echo 'Repair installed skills: run setup --host codex from your gstack checkout.' >&2
  fi
  exit 78
fi

_REPO_ROOT=$(git rev-parse --show-toplevel) || { echo 'ERROR: not in a git repo' >&2; exit 1; }
_OUTSIDE_TMP=$(mktemp -d "${TMPDIR:-/tmp}/gstack-outside.XXXXXXXX") || exit 1
trap 'rm -rf "$_OUTSIDE_TMP"' EXIT
_OUTSIDE_INPUT="$_OUTSIDE_TMP/prompt"
cat -- '<prepared-prompt-file>' >"$_OUTSIDE_INPUT" || exit 1

_CODEX_PROBE="$HOME/.claude/skills/gstack/bin/gstack-codex-probe"
_CODEX_OUT=$("$_CODEX_PROBE" select-model exec) || exit 1
# (The truncated remainder continues here — Codex invocation, outside-result parser, and apply gate. The translation above preserves every code block, quoted prompt text, and `CODEX_MODE` branch verbatim.)
```

When you take this path, say so in the output header — `CODEX SAYS (documentation review):` — and note that the CLI does not accept custom instructions
alongside the diff range, so the scope was expressed in the prompt instead.

**Apply gate:** when the Codex pass returns, summarize PREFERRED change, severity, location; AskUserQuestion "Is this right?" A confirmed final recommendation permits Write of the listed doc fix; B returns to Step 3 with the fix applied; C returns to the relevant Step 4 question. No silent apply; the apply gate below needs a human.

**If `CODEX_MODE` was anything except `disabled` — persist the result:**

```bash
~/.claude/skills/gstack/bin/gstack-review-log '{"skill":"codex-doc-review","timestamp":"'"$(date -u +%Y-%m-%dT%H:%M:%SZ)"'","status":"STATUS","source":"codex","host":"claude","outside_provider":"codex","outside_status":"completed|unavailable|disabled|skipped","phase":"documentation","commit":"'"$(git rev-parse --short HEAD 2>/dev/null || true)"'"}'
```

Substitute `STATUS` based on actual outcome: `clean` for a usable review with no remaining doc gaps; `issues_found` for unresolved doc gaps; `unavailable` for any non-ready outcome. Both accepted-run records carry the actual CLI outcome; `outside_provider`/`outside_status` describe external coverage, not each record's source. Preserve the historical skill identifier.

---

## Step 9: Doc Health Summary

Output the final doc health summary that will appear in the deploy report. Format:

```
DOCUMENTATION HEALTH (for PR/MERGE notes):
  Files reviewed: [N from coverage map]
  Auto-updated:   [list of files with brief one-line summary each]
  Asked (deferred to user): [list, with skip count if user chose C)
  Cross-doc inconsistencies: [N fixed | 0]
  Discoverability: [OK | gaps flagged]
  CHANGELOG voice: [OK | N entries polished | N flagged for author]
  TODOS.md: [N moved to completed | N updated | new TODOs captured: N]
  VERSION: [vX.Y.Z covers all changes | unchanged (docs-only) | not applicable]
  Codex doc review: [PASS / N findings applied / SKIPPED (disabled) / unavailable]
```

In ship-owned mode, output the audit-scope JSON result on its own LAST nonempty line
instead of this block. The deploy report will pick it up there.

If there are unresolved clarification questions from Step 4, summarize them with the
file, the specific decision, and the `RECOMMENDATION` text so the user can resolve
them at their pace without the auto-reviewer blocking the merge.

---

