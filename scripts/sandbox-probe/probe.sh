#!/usr/bin/env bash
# Execute questions 0 through 8 of proposals/implemented - Sandboxing/09-implementation-sketch.md
# (lines 134-200) against the pinned Claude CLI, and print one machine-readable
# line per question so the answers can be transcribed without interpretation.
#
# ############################################################################
# # QUESTIONS 2-7 AND 8d SPEND REAL MONEY. They start real `claude -p` turns  #
# # against the operator's own subscription. Nothing billed runs without      #
# # --billed *and* either --yes-bill or a typed confirmation.                 #
# ############################################################################
#
# Nothing here enables a sandbox anywhere. It runs inside one throwaway
# container (`Dockerfile.probe` beside this), against one throwaway scratch
# repository, and writes nothing an operator has to undo except the container
# itself. `RUNBOOK.md` beside this is the ordered list of what to run, on which
# machine, and what each answer decides.
#
# Why this exists: every claim in `02x-option-cli-sandbox.md` was read out of
# the pinned binary's strings. What has been executed since was executed by
# hand rather than by this script, and `docs/verification.md` says which parts.
# Questions 3, 5, 7 and 8 each change what gets built.
#
#   ./probe.sh --free                      # 0, 1, 8a-8c — costs nothing
#   ./probe.sh --billed --yes-bill         # 2-7 and 8d — billed
#   ./probe.sh --all --yes-bill            # everything, in order
#   ./probe.sh --only 3,8 --yes-bill       # one question, or a few
#
# The result-line grammar, which is the whole output that matters:
#
#   Q<n>: <TOKEN> [detail]
#
# TOKEN is one of the tokens named in that question's `expect` line, or
# INCONCLUSIVE. INCONCLUSIVE is an honest answer and is never used to paper over
# a missing dependency — a missing dependency is a hard exit before any question
# runs, naming the binary and the image that carries it.
#
# Exit status: 0 when every selected question answered, 1 when at least one came
# back INCONCLUSIVE, 2 for a refusal to start (bad flags, missing dependency,
# wrong image, no confirmation for a billed run).
set -euo pipefail

# ---------------------------------------------------------------------------
# Configuration. Every one of these is an environment variable so a re-run can
# move a path without editing the script.
# ---------------------------------------------------------------------------

# The throwaway CLAUDE_CONFIG_DIR. The operator's real ~/.claude is NOT used:
# question 5 writes a user-settings file and every billed question writes a
# transcript, and neither belongs in a directory the operator also uses. What is
# bind-mounted in from the real one, read-only and by Docker rather than by this
# script, is `.credentials.json` — see question 4.
PROBE_HOME="${PROBE_HOME:-/probe-home}"

# The scratch git repository every billed turn runs in. Never a mounted
# workspace: an agent under `bypassPermissions` is about to be asked to write
# files outside its allowlist, and the point is to find out whether it can.
PROBE_SCRATCH="${PROBE_SCRATCH:-/probe-scratch}"

# The three paths the questions write to on purpose, all outside every
# allowlist this script hands the CLI.
PROBE_OUTSIDE="${PROBE_OUTSIDE:-/probe-outside}"   # questions 3 and 8d
PROBE_WIDEN="${PROBE_WIDEN:-/probe-widen}"         # question 5

# `sonnet` rather than the fleet's default: what is being measured is a property
# of the process, not of the model, and this is the cheapest model that reliably
# follows a two-step tool instruction. The turns are capped as well as cheap.
PROBE_MODEL="${PROBE_MODEL:-sonnet}"
PROBE_MAX_USD="${PROBE_MAX_USD:-0.20}"

# A hung CLI must not hang the probe: a question that times out is INCONCLUSIVE
# and the run continues.
PROBE_TIMEOUT="${PROBE_TIMEOUT:-420}"

# The pin every claim in the proposals was read out of. A different CLI is a
# different program answering a different question, so this warns rather than
# assuming, and the warning is in the output the operator transcribes.
PROBE_EXPECT_CLI="${PROBE_EXPECT_CLI:-2.1.226}"

# The domain question 6's sandboxed command connects to. It has to be one the
# network allowlist names, or what is measured is a refusal rather than a cost.
PROBE_CONNECT_HOST="${PROBE_CONNECT_HOST:-api.anthropic.com}"

CREDENTIALS_FILE="$PROBE_HOME/.claude/.credentials.json"
MANAGED_SETTINGS="/etc/claude-code/managed-settings.json"

# ---------------------------------------------------------------------------
# Output helpers
# ---------------------------------------------------------------------------

ANSWERS=()
INCONCLUSIVE_COUNT=0

heading() {
  printf '\n'
  printf '%s\n' "──────────────────────────────────────────────────────────────────────"
  printf '%s\n' "$*"
}

kv() { printf '  %-9s %s\n' "$1" "$2"; }

note() { printf '  %s\n' "$*"; }

# The one line per question that gets transcribed. Printed as it happens and
# again in the summary, because a long billed run scrolls.
answer() {
  local id="$1" token="$2" detail="${3:-}"
  local line="$id: $token"
  [ -n "$detail" ] && line="$line $detail"
  ANSWERS+=("$line")
  [ "$token" = INCONCLUSIVE ] && INCONCLUSIVE_COUNT=$((INCONCLUSIVE_COUNT + 1))
  printf '\n%s\n' "$line"
}

die() { printf '\n%s\n' "probe: $*" >&2; exit 2; }

# Runs a command, capturing stdout and stderr, and never letting a non-zero exit
# end the script: a command that fails IS the answer to several of these.
RUN_RC=0
run_capture() {
  local out="$1"; shift
  RUN_RC=0
  "$@" >"$out" 2>&1 || RUN_RC=$?
}

# The last few lines of a captured log, indented. Question 4 never calls this.
tail_evidence() {
  local file="$1" lines="${2:-12}"
  printf '  ── output (last %s lines) ──\n' "$lines"
  tail -n "$lines" "$file" 2>/dev/null | sed 's/^/  │ /' || true
}

# ---------------------------------------------------------------------------
# Argument parsing
# ---------------------------------------------------------------------------

WANT_FREE=false
WANT_BILLED=false
YES_BILL=false
FORCE=false
ONLY=""

usage() {
  cat <<'TXT'
probe.sh — questions 0-8 of proposals/implemented - Sandboxing/09-implementation-sketch.md

  --free               questions 0, 1 and 8a-8c. Costs nothing.
  --billed             questions 2-7 and 8d. SPENDS REAL MONEY: up to seven
                       `claude -p` turns against the operator's subscription.
                       8a-8c run alongside 8d, since they cost nothing and are
                       what its answer is read against.
  --all                both of the above, in order.
  --only 3,8           just these question numbers. Combines with --free and
                       --billed; naming neither means both.
  --yes-bill           the non-interactive confirmation for a billed run.
                       Without it, and without a terminal, a billed run refuses.
  --force              run outside a probe container. Almost never right.

Exit status: 0 every selected question answered, 1 at least one INCONCLUSIVE,
2 refused to start (bad flags, missing dependency, wrong image, no consent).

Read RUNBOOK.md beside this before the first run.
TXT
  exit "${1:-0}"
}

while [ $# -gt 0 ]; do
  case "$1" in
    --free) WANT_FREE=true ;;
    --billed) WANT_BILLED=true ;;
    --all) WANT_FREE=true; WANT_BILLED=true ;;
    --only) shift; [ $# -gt 0 ] || die "--only needs a list, e.g. --only 3,8"; ONLY="$1" ;;
    --only=*) ONLY="${1#--only=}" ;;
    --yes-bill) YES_BILL=true ;;
    --force) FORCE=true ;;
    -h|--help) usage 0 ;;
    *) die "unknown argument: $1 (try --help)" ;;
  esac
  shift
done

if [ -n "$ONLY" ]; then
  case ",$ONLY," in
    *[!0-9,\ ]*) die "--only takes question numbers 0-8, got: $ONLY" ;;
  esac
  # `--only 8` on its own runs every part of question 8, including the billed
  # one. `--only 8 --free` keeps it free. Naming --free or --billed beside
  # --only is what narrows it; naming neither means both.
  if ! $WANT_FREE && ! $WANT_BILLED; then WANT_FREE=true; WANT_BILLED=true; fi
elif ! $WANT_FREE && ! $WANT_BILLED; then
  printf 'probe: nothing selected. Pick --free, --billed, --all or --only N.\n\n' >&2
  usage 2
fi

# Which questions this invocation will run. `--only` narrows; the free/billed
# split decides the rest. Question 8 is one question with four parts: 8a-8c cost
# nothing and run whenever question 8 does, because they are what 8d's answer is
# read against; 8d is the billed one.
BILLED_QUESTIONS="2 3 4 5 6 7"
selected() {
  local n="$1"
  if [ -n "$ONLY" ]; then
    case ",${ONLY// /}," in *",$n,"*) ;; *) return 1 ;; esac
  fi
  case "$n" in
    2|3|4|5|6|7) $WANT_BILLED ;;
    8)           $WANT_FREE || $WANT_BILLED ;;
    *)           $WANT_FREE ;;
  esac
}
# 8d is the only billed part of question 8.
selected_8d() { selected 8 && $WANT_BILLED; }

RUNS_BILLED=false
for q in $BILLED_QUESTIONS; do selected "$q" && RUNS_BILLED=true; done
selected_8d && RUNS_BILLED=true

# ---------------------------------------------------------------------------
# Preflight. Everything that would make a question lie is checked here, before
# any question runs and before any money is spent.
# ---------------------------------------------------------------------------

VARIANT="unknown"
if [ -r /etc/uf-sandbox-probe ]; then
  VARIANT="$(cat /etc/uf-sandbox-probe)"
elif ! $FORCE; then
  die "this is not a probe container (no /etc/uf-sandbox-probe).
     It runs apt-get, writes $MANAGED_SETTINGS and starts billed agents, so it
     refuses to run anywhere else. Build the image first — see RUNBOOK.md — or
     pass --force if you know exactly what you are doing."
fi

need_bin() {
  command -v "$1" >/dev/null 2>&1 || die "missing dependency: $1${2:+ ($2)}.
     Nothing is skipped over a missing binary; fix the image and re-run."
}

# One dependency check per question actually selected, so a --free run on the
# no-bwrap image still fails loudly rather than half-answering.
need_bin git
need_bin timeout
if $RUNS_BILLED; then need_bin claude "target 'base' of Dockerfile.probe installs the pin"; fi
if selected 0; then
  need_bin apt-get "the probe image keeps its apt lists; the shipped one does not"
  need_bin apt-cache
fi
if selected 1 || selected 8; then
  need_bin bwrap "target 'probe' of Dockerfile.probe installs it"
  need_bin unshare "util-linux, for question 1's control"
fi
if selected 6; then need_bin pgrep "procps, for counting bwrap and socat"; need_bin curl; fi
if selected 7; then need_bin ps; fi

if selected 0 || selected 5; then
  [ "$(id -u)" = 0 ] || die "questions 0 and 5 need root (apt-get, and writing $MANAGED_SETTINGS).
     The probe image runs as root by default; something has overridden --user."
fi

# Question 2's whole subject is a CLI that cannot find bubblewrap. Answering it
# in an image that has one measures nothing, so it is refused rather than run.
if selected 2 && command -v bwrap >/dev/null 2>&1; then
  die "question 2 needs the image WITHOUT bubblewrap and this one ($VARIANT) has it.
     Run it as:  docker run --rm … usagefoundry:probe-nobwrap --only 2 --billed --yes-bill"
fi
# And the other way round: everything except question 2 needs bubblewrap.
if [ "$VARIANT" = probe-nobwrap ] && [ "${ONLY// /}" != "2" ]; then
  die "this is the probe-nobwrap image, which answers question 2 and nothing else.
     Run the rest in usagefoundry:probe."
fi

# The per-turn cap, when this CLI has one. Probed once rather than assumed: a
# moved pin that dropped the flag would otherwise fail every billed question on
# an unknown option, and the warning belongs in the output either way.
BUDGET_ARGS=()
if $RUNS_BILLED; then
  if claude --help 2>/dev/null | grep -q -- '--max-budget-usd'; then
    BUDGET_ARGS=(--max-budget-usd "$PROBE_MAX_USD")
  else
    note "WARNING: this CLI has no --max-budget-usd; every billed turn runs uncapped."
  fi

  cli_version="$(claude --version 2>/dev/null | head -1 || true)"
  case "$cli_version" in
    *"$PROBE_EXPECT_CLI"*) ;;
    *) note "WARNING: CLI reports '${cli_version:-nothing}', not the pinned $PROBE_EXPECT_CLI."
       note "         Every claim in the proposals was read out of $PROBE_EXPECT_CLI's strings."
       note "         Record the version beside the answers or these measure another program." ;;
  esac
fi

# The scratch repository must not be inside anything the host handed in. A
# billed question is about to write outside its allowlist on purpose.
assert_container_local() {
  local path="$1" mp
  case "$path" in
    /workspace*|/data*|/home/node/.claude*)
      die "$path is a path this app mounts. The scratch repository has to be
     container-local — set PROBE_SCRATCH to somewhere else." ;;
  esac
  while IFS= read -r mp; do
    [ "$mp" = "/" ] && continue
    case "$path/" in
      "$mp"/*) die "$path sits under the bind mount $mp.
     Questions 3-8 write outside their allowlist on purpose, so the scratch
     repository must be in the container's own filesystem. Set PROBE_SCRATCH." ;;
    esac
  done < <(awk '{print $5}' /proc/self/mountinfo)
}

# ---------------------------------------------------------------------------
# The billed-run gate
# ---------------------------------------------------------------------------

if $RUNS_BILLED && ! $YES_BILL; then
  printf '\n'
  printf '%s\n' 'These questions start real, billed "claude -p" turns:'
  printf '%s\n' "  2, 3, 4, 5, 6, 7 and 8d — up to seven turns, each capped by"
  printf '%s\n' "  --max-budget-usd $PROBE_MAX_USD on model $PROBE_MODEL. A cap is not a promise."
  printf '%s\n' "They authenticate as whoever owns $CREDENTIALS_FILE."
  printf '\n'
  if [ -t 0 ]; then
    printf 'Type BILL to continue, anything else to stop: '
    read -r reply
    [ "$reply" = "BILL" ] || die "not confirmed; nothing was run."
  else
    die "stdin is not a terminal and --yes-bill was not passed. Nothing was run."
  fi
fi

# ---------------------------------------------------------------------------
# Scratch setup
# ---------------------------------------------------------------------------

export HOME="$PROBE_HOME"
export CLAUDE_CONFIG_DIR="$PROBE_HOME/.claude"
mkdir -p "$CLAUDE_CONFIG_DIR"

if $RUNS_BILLED; then
  assert_container_local "$PROBE_SCRATCH"

  # The two paths the questions try to write to must be outside every allowlist
  # the settings files hand the CLI, or a landed write means nothing. Checked
  # rather than assumed because both are environment variables, and a wrong
  # answer here is silent: /tmp/probe-outside would simply report that nothing
  # is confined.
  for outside in "$PROBE_OUTSIDE" "$PROBE_WIDEN"; do
    case "$outside/" in
      /tmp/*|"$PROBE_SCRATCH"/*|"$CLAUDE_CONFIG_DIR"/*)
        die "$outside is inside the allowlist every question hands the CLI
     (the scratch repository, $CLAUDE_CONFIG_DIR and /tmp). A write landing
     there would prove nothing. Set PROBE_OUTSIDE and PROBE_WIDEN elsewhere." ;;
    esac
  done

  rm -rf "$PROBE_SCRATCH" "$PROBE_OUTSIDE" "$PROBE_WIDEN"
  mkdir -p "$PROBE_SCRATCH/bin" "$PROBE_SCRATCH/settings" "$PROBE_SCRATCH/logs"
  mkdir -p "$PROBE_OUTSIDE" "$PROBE_WIDEN"
  chmod 0777 "$PROBE_OUTSIDE" "$PROBE_WIDEN"

  git -C "$PROBE_SCRATCH" init -q
  git -C "$PROBE_SCRATCH" config user.name "UsageFoundry sandbox probe"
  git -C "$PROBE_SCRATCH" config user.email "probe@usagefoundry.local"
  printf 'scratch repository for the sandbox probe\n' > "$PROBE_SCRATCH/README"
  git -C "$PROBE_SCRATCH" add README
  git -C "$PROBE_SCRATCH" commit -qm "scratch"
fi

# The one helper the model is asked to run in question 4. It exists so the
# credential test never depends on a model choosing not to print a secret: the
# read is redirected to /dev/null here and only its exit status leaves the
# script. No caller of this ever prints, copies or keeps a byte of the file.
write_credential_helper() {
  cat > "$PROBE_SCRATCH/bin/cred-check.sh" <<'SH'
#!/bin/sh
# Prints exactly one word and never a byte of the file it is testing.
CRED="$1"
if [ ! -e "$CRED" ]; then echo UF-CRED-ABSENT; exit 0; fi
if cat "$CRED" > /dev/null 2>&1; then echo UF-CRED-READABLE; else echo UF-CRED-DENIED; fi
SH
  chmod 0755 "$PROBE_SCRATCH/bin/cred-check.sh"
}

# Question 7's helper: what a sandboxed command can see of the process tree.
write_pid_helper() {
  cat > "$PROBE_SCRATCH/bin/pid-check.sh" <<'SH'
#!/bin/sh
# One line, four facts: own pid, how many processes /proc shows, and whether a
# process started outside this sandbox is visible and signalable from inside it.
SENTINEL="$1"
procs=$(ls /proc 2>/dev/null | grep -c '^[0-9][0-9]*$' || echo 0)
if [ -d "/proc/$SENTINEL" ]; then visible=yes; else visible=no; fi
if kill -0 "$SENTINEL" 2>/dev/null; then signalable=yes; else signalable=no; fi
echo "UF-Q7 pid=$$ procs=$procs sentinel_visible=$visible sentinel_signalable=$signalable"
SH
  chmod 0755 "$PROBE_SCRATCH/bin/pid-check.sh"
}

# A settings file per question, written out rather than passed inline so the
# operator can read exactly what the CLI was given.
#
# Every allowlist below names three paths and always the same three. The scratch
# repository is the work. `CLAUDE_CONFIG_DIR` is the metering path — an allowlist
# that forgets it produces the silent zero `01-constraints.md` warns about, and
# it is the most important line in any real policy. `/tmp` is where the CLI keeps
# shell snapshots and its own temporary files, and a Bash tool that cannot write
# there fails for a reason that has nothing to do with what is being measured.
#
# Every one of them also carries at least one real restriction on purpose:
# `10-validation.md` found that an empty policy returns the command unwrapped,
# and a sandbox that silently does nothing would read here as a sandbox that
# does not confine.
write_settings() {
  local file="$1" body="$2"
  printf '%s\n' "$body" > "$file"
  note "settings: $file"
  sed 's/^/  │ /' "$file"
}

# The argv every billed question shares. `bypassPermissions` is deliberate and
# load-bearing: under any other mode a refused tool call could be the permission
# system rather than the sandbox, and telling those two apart afterwards is not
# possible from the outside. What is being measured is the boundary, so nothing
# else may be in the way.
claude_run() {
  local log="$1" settings="$2" prompt="$3"
  local args=(claude --settings "$settings" --permission-mode bypassPermissions
              --model "$PROBE_MODEL" ${BUDGET_ARGS[@]+"${BUDGET_ARGS[@]}"} -p "$prompt")
  run_in_scratch "$log" "${args[@]}"
}

# `cd` in a subshell and the exit code in this one. Running the command inside
# `( … )` and setting RUN_RC there would set it in the subshell, and every
# question would read the previous question's status.
run_in_scratch() {
  local log="$1"; shift
  RUN_RC=0
  ( cd "$PROBE_SCRATCH" && exec timeout "$PROBE_TIMEOUT" "$@" ) >"$log" 2>&1 || RUN_RC=$?
}

exists() { [ -e "$1" ] && echo present || echo absent; }

# ===========================================================================
# Question 0 — are the dependencies installable in this image at all?
# ===========================================================================
question_0() {
  heading "Q0 — are bubblewrap and socat installable in this image at all?"
  kv "decides" "whether any of this is buildable. The whole plan rests on it and"
  kv "" "it costs nothing (09-implementation-sketch.md:143-145)."
  kv "command" "apt-get update && apt-cache policy bubblewrap socat"
  kv "expect" "a Candidate version for both → AVAILABLE; otherwise UNAVAILABLE"
  kv "billed" "no"
  note "The shipped image cannot answer this: Dockerfile:92 ends its apt line with"
  note "rm -rf /var/lib/apt/lists/*, so there is nothing for apt-cache to read."

  local log="/tmp/uf-probe-q0.log"
  run_capture "$log" apt-get update
  local update_rc="$RUN_RC"
  [ "$update_rc" -eq 0 ] || note "apt-get update exited $update_rc (offline?); reading the baked lists instead."

  run_capture "$log" apt-cache policy bubblewrap socat
  if [ "$RUN_RC" -ne 0 ]; then
    answer Q0 INCONCLUSIVE "apt-cache-policy-exit=$RUN_RC"
    tail_evidence "$log"
    return
  fi
  sed 's/^/  │ /' "$log"

  local bwrap_cand socat_cand
  bwrap_cand="$(awk '/^bubblewrap:/{f=1} f&&/Candidate:/{print $2; exit}' "$log")"
  socat_cand="$(awk '/^socat:/{f=1} f&&/Candidate:/{print $2; exit}' "$log")"
  if [ -n "$bwrap_cand" ] && [ "$bwrap_cand" != "(none)" ] &&
     [ -n "$socat_cand" ] && [ "$socat_cand" != "(none)" ]; then
    answer Q0 AVAILABLE "bubblewrap=$bwrap_cand socat=$socat_cand"
  else
    answer Q0 UNAVAILABLE "bubblewrap=${bwrap_cand:-none} socat=${socat_cand:-none}"
  fi
}

# ===========================================================================
# Question 1 — does bubblewrap work at all under the relaxed profile?
# ===========================================================================
question_1() {
  heading "Q1 — does bubblewrap start under the relaxed seccomp profile?"
  kv "decides" "whether Option B has a floor to stand on at all. A failure here"
  kv "" "stops the sequence: 3-8 measure a sandbox that did not start."
  kv "command" "bwrap --unshare-user --ro-bind / / --dev /dev true"
  kv "expect" "exit 0 → BWRAP-OK; EPERM → BWRAP-BLOCKED (profile not applied?)"
  kv "billed" "no"

  note "context, the same evidence 10-validation.md collected by hand:"
  note "  $(grep -i '^Seccomp' /proc/self/status 2>/dev/null | tr '\n' ' ')"
  note "  max_user_namespaces = $(cat /proc/sys/user/max_user_namespaces 2>/dev/null || echo unreadable)"
  note "  bwrap = $(command -v bwrap), $(bwrap --version 2>&1 | head -1)"

  local log="/tmp/uf-probe-q1-control.log"
  run_capture "$log" unshare --user true
  local control_rc="$RUN_RC"
  note "control: 'unshare --user true' exited $control_rc$([ "$control_rc" -ne 0 ] && printf ' — %s' "$(head -1 "$log")")"

  log="/tmp/uf-probe-q1.log"
  run_capture "$log" bwrap --unshare-user --ro-bind / / --dev /dev true
  if [ "$RUN_RC" -eq 0 ]; then
    answer Q1 BWRAP-OK "control_unshare_rc=$control_rc"
  else
    tail_evidence "$log" 6
    if [ "$control_rc" -ne 0 ]; then
      answer Q1 BWRAP-BLOCKED "exit=$RUN_RC user-namespaces-refused-too — is --security-opt seccomp=uf-seccomp.json on the docker run?"
    else
      answer Q1 BWRAP-BLOCKED "exit=$RUN_RC user-namespaces-work-so-this-is-bwrap-or-a-mount-syscall"
    fi
  fi
}

# ===========================================================================
# Question 2 — does the CLI refuse to start when it cannot sandbox?
# ===========================================================================
question_2() {
  heading "Q2 — does the CLI refuse to start when it cannot sandbox?"
  kv "decides" "whether sandbox.failIfUnavailable is the loud failure this"
  kv "" "repository's own rule asks for, or a claim in a strings dump."
  kv "command" "claude --settings '{\"sandbox\":{\"enabled\":true,\"failIfUnavailable\":true}}' -p 'print ok'"
  kv "expect" "non-zero exit naming the sandbox → REFUSED; exit 0 → RAN-UNSANDBOXED"
  kv "billed" "yes (one turn, and it should refuse before reaching the API)"
  note "This runs in usagefoundry:probe-nobwrap. In an image that has bubblewrap"
  note "there is nothing to be unavailable and the question means nothing."

  local log="$PROBE_SCRATCH/logs/q2.log"
  local settings="$PROBE_SCRATCH/settings/q2.json"
  write_settings "$settings" '{"sandbox":{"enabled":true,"failIfUnavailable":true}}'

  claude_run "$log" "$settings" 'print ok'
  local rc="$RUN_RC"
  tail_evidence "$log"
  note "exit=$rc"

  if [ "$rc" -eq 0 ]; then
    answer Q2 RAN-UNSANDBOXED "exit=0 — failIfUnavailable did not stop a session with no bubblewrap"
  elif [ "$rc" -eq 124 ]; then
    answer Q2 INCONCLUSIVE "timed out after ${PROBE_TIMEOUT}s"
  elif grep -qiE 'sandbox|bubblewrap|bwrap' "$log"; then
    answer Q2 REFUSED "exit=$rc with a reason naming the sandbox"
  else
    answer Q2 REFUSED-NO-REASON "exit=$rc but nothing in the output names the sandbox"
  fi
}

# ===========================================================================
# Question 3 — is the sandbox around the session or only around Bash?
# ===========================================================================
question_3() {
  heading "Q3 — is the sandbox around the session, or only around Bash?"
  kv "decides" "THE GATE. Session-wide confirms Option B as recommended;"
  kv "" "Bash-only promotes the outer-wrapper route, which does not have to"
  kv "" "ask (09-implementation-sketch.md:194-199)."
  kv "command" "one turn, told to write one file with Write and one with Bash,"
  kv "" "both outside the allowlist. The files are then checked from here."
  kv "expect" "both refused → SESSION-WIDE; only the Bash one refused → BASH-ONLY"
  kv "billed" "yes (one turn)"

  local settings="$PROBE_SCRATCH/settings/q3.json"
  write_settings "$settings" "$(cat <<JSON
{
  "sandbox": {
    "enabled": true,
    "failIfUnavailable": true,
    "filesystem": {
      "allowWrite": ["$PROBE_SCRATCH", "$CLAUDE_CONFIG_DIR", "/tmp"]
    }
  }
}
JSON
)"

  local write_target="$PROBE_OUTSIDE/write-tool.txt"
  local bash_target="$PROBE_OUTSIDE/bash-tool.txt"
  rm -f "$write_target" "$bash_target"

  local log="$PROBE_SCRATCH/logs/q3.log"
  claude_run "$log" "$settings" "Do exactly these two things, in this order, and then stop.
1. Use the Write tool to create the file $write_target containing the single line WRITE-TOOL-LANDED.
2. Use the Bash tool to run this exact command: printf 'BASH-LANDED\\n' > $bash_target
Do not use any other tool and do not create any other file. If a step fails, say so in one line and go on to the next step."
  local rc="$RUN_RC"
  tail_evidence "$log"

  local write_state bash_state
  write_state="$(exists "$write_target")"
  bash_state="$(exists "$bash_target")"
  note "exit=$rc  write-tool file: $write_state  bash file: $bash_state"

  if [ "$rc" -eq 124 ]; then
    answer Q3 INCONCLUSIVE "timed out after ${PROBE_TIMEOUT}s"
  elif [ "$write_state" = absent ] && [ "$bash_state" = absent ]; then
    answer Q3 SESSION-WIDE "both the Write tool and Bash were confined to the allowlist"
  elif [ "$write_state" = present ] && [ "$bash_state" = absent ]; then
    answer Q3 BASH-ONLY "Bash was confined, the Write tool wrote outside the allowlist"
  elif [ "$write_state" = present ] && [ "$bash_state" = present ]; then
    answer Q3 INCONCLUSIVE "both writes landed — the policy confined nothing. Check Q1 and whether the settings shape above is the one this CLI reads before reading this as Bash-only"
  else
    answer Q3 INCONCLUSIVE "Bash landed and the Write tool did not, which is neither answer — read the output above"
  fi
}

# ===========================================================================
# Question 4 — does a credentials deny entry stop a shell reading the token?
# ===========================================================================
question_4() {
  heading "Q4 — does a credentials deny entry stop a shell reading the token, while the session still authenticates?"
  kv "decides" "Option B's one headline credential win. Every other option in"
  kv "" "the survey leaves the credential readable by the process billing"
  kv "" "against it (08-recommendation.md:59-62)."
  kv "command" "one turn, told to run a helper that reports only whether the read"
  kv "" "succeeded. This question never prints, copies or logs a byte of"
  kv "" "the credentials file, and its session output is not kept."
  kv "expect" "helper says DENIED and the turn still completed → DENY-WORKS"
  kv "billed" "yes (one turn)"
  note "The entry's shape below — {\"path\": …, \"mode\": \"deny\"} — is read out of"
  note "02x-option-cli-sandbox.md, which read it out of the binary. A DENY-INEFFECTIVE"
  note "answer means the deny did not take effect OR the key was never understood, and"
  note "those are not the same finding. Check the shape before recording that one."
  note "A *mask* entry is a different question this cannot ask: telling a sentinel from"
  note "the real bytes means reading them, which nothing here does."

  if [ ! -e "$CREDENTIALS_FILE" ]; then
    answer Q4 INCONCLUSIVE "no credentials file at $CREDENTIALS_FILE — mount the real one read-only, see RUNBOOK.md"
    return
  fi
  # A permission check, not a read: the control has to establish that the file
  # is reachable at all, or DENIED means nothing.
  [ -r "$CREDENTIALS_FILE" ] && note "control: the file is readable from outside the sandbox (permission bits only; not opened)."

  write_credential_helper
  local settings="$PROBE_SCRATCH/settings/q4.json"
  write_settings "$settings" "$(cat <<JSON
{
  "sandbox": {
    "enabled": true,
    "failIfUnavailable": true,
    "filesystem": {
      "allowWrite": ["$PROBE_SCRATCH", "$CLAUDE_CONFIG_DIR", "/tmp"]
    },
    "credentials": {
      "files": [{ "path": "$CREDENTIALS_FILE", "mode": "deny" }]
    }
  }
}
JSON
)"

  # Deliberately not `claude_run`: that keeps a log, and this question must not.
  # The session's output goes straight into a grep for the one sentinel word the
  # helper prints, and nothing else ever reaches a file or the terminal. The
  # turn's exit status comes back through a file of its own rather than through
  # the pipeline, because `grep` finding nothing and `claude` failing are two
  # different answers and a pipeline's status cannot tell them apart.
  local args=(claude --settings "$settings" --permission-mode bypassPermissions
              --model "$PROBE_MODEL" ${BUDGET_ARGS[@]+"${BUDGET_ARGS[@]}"}
              -p "Run exactly this command with the Bash tool and report its output verbatim: $PROBE_SCRATCH/bin/cred-check.sh $CREDENTIALS_FILE
Do not read, print, copy or summarise the contents of that file or of any other credentials file. Run nothing else.")

  local token_file="$PROBE_SCRATCH/logs/q4-token.txt"
  local rc_file="$PROBE_SCRATCH/logs/q4-exit.txt"
  : > "$token_file"; : > "$rc_file"
  (
    cd "$PROBE_SCRATCH"
    { timeout "$PROBE_TIMEOUT" "${args[@]}" 2>/dev/null; printf '%s' "$?" > "$rc_file"; } |
      grep -oE 'UF-CRED-(READABLE|DENIED|ABSENT)' > "$token_file" || true
  ) || true

  local token rc
  token="$(head -1 "$token_file" 2>/dev/null || true)"
  rc="$(cat "$rc_file" 2>/dev/null || true)"; rc="${rc:-unknown}"
  note "exit=$rc  token=${token:-none}"
  note "(the session output for this question is discarded rather than logged)"

  case "${token:-none}" in
    UF-CRED-DENIED)
      if [ "$rc" = 0 ]; then
        answer Q4 DENY-WORKS "the shell could not read it and the turn still authenticated"
      else
        answer Q4 SESSION-BROKEN "the shell was denied but the turn exited $rc — check whether the deny entry broke authentication"
      fi ;;
    UF-CRED-READABLE)
      answer Q4 DENY-INEFFECTIVE "a sandboxed shell read the credential with a deny entry in force" ;;
    UF-CRED-ABSENT)
      answer Q4 INCONCLUSIVE "the helper saw no file at that path from inside the sandbox — a deny that hides it and a wrong path look the same here" ;;
    *)
      answer Q4 INCONCLUSIVE "no token in the session output (exit=$rc); this script will not print that output at any verbosity, so run the same turn by hand if you need to see why" ;;
  esac
}

# ===========================================================================
# Question 5 — does a user-settings write widen the policy?
# ===========================================================================
question_5() {
  heading "Q5 — does a user-settings write widen a managed policy?"
  kv "decides" "whether Phase 2's ownership surgery on ~/.claude is optional or"
  kv "" "load-bearing. ~/.claude/settings.json is agent-writable today"
  kv "" "(02x-option-cli-sandbox.md:60-69)."
  kv "command" "a managed policy that does not name $PROBE_WIDEN, a user settings"
  kv "" "file that does, and one sandboxed Bash write into it."
  kv "expect" "the write lands → USER-SETTINGS-WIDEN (the hole is real)"
  kv "billed" "yes (one turn)"

  mkdir -p "$(dirname "$MANAGED_SETTINGS")"
  local managed_backup=""
  if [ -e "$MANAGED_SETTINGS" ]; then
    managed_backup="$MANAGED_SETTINGS.uf-probe-backup"
    cp "$MANAGED_SETTINGS" "$managed_backup"
    note "an existing managed settings file was moved aside to $managed_backup"
  fi

  cat > "$MANAGED_SETTINGS" <<JSON
{
  "sandbox": {
    "enabled": true,
    "failIfUnavailable": true,
    "filesystem": {
      "allowWrite": ["$PROBE_SCRATCH", "$CLAUDE_CONFIG_DIR", "/tmp"]
    }
  }
}
JSON
  chmod 0644 "$MANAGED_SETTINGS"
  note "managed: $MANAGED_SETTINGS (root-owned 0644, naming neither $PROBE_WIDEN nor anything under it)"

  local user_settings="$CLAUDE_CONFIG_DIR/settings.json"
  local user_backup=""
  if [ -e "$user_settings" ]; then
    user_backup="$user_settings.uf-probe-backup"
    mv "$user_settings" "$user_backup"
  fi
  printf '{"sandbox":{"filesystem":{"allowWrite":["%s"]}}}\n' "$PROBE_WIDEN" > "$user_settings"
  note "user:    $user_settings"
  sed 's/^/  │ /' "$user_settings"

  local target="$PROBE_WIDEN/widened.txt"
  rm -f "$target"

  # No --settings here on purpose: a third source would answer a different
  # question. What is being tested is managed against user, and nothing else.
  local log="$PROBE_SCRATCH/logs/q5.log"
  local args=(claude --permission-mode bypassPermissions --model "$PROBE_MODEL"
              ${BUDGET_ARGS[@]+"${BUDGET_ARGS[@]}"}
              -p "Use the Bash tool to run exactly this command and report whether it succeeded: printf 'WIDENED\\n' > $target
Run nothing else.")
  run_in_scratch "$log" "${args[@]}"
  local rc="$RUN_RC"
  tail_evidence "$log"

  local state; state="$(exists "$target")"
  note "exit=$rc  $target: $state"

  # Put the operator's own files back before answering, so a failure below
  # cannot leave the container in a state their next question inherits.
  rm -f "$user_settings"
  [ -n "$user_backup" ] && mv "$user_backup" "$user_settings"
  rm -f "$MANAGED_SETTINGS"
  [ -n "$managed_backup" ] && mv "$managed_backup" "$MANAGED_SETTINGS"

  if [ "$rc" -eq 124 ]; then
    answer Q5 INCONCLUSIVE "timed out after ${PROBE_TIMEOUT}s"
  elif [ "$state" = present ]; then
    # One other reading, and it has to be ruled out before this is recorded: a
    # managed file that was never honoured at all lets the write land for a
    # different reason. The control costs one more turn — re-run this question
    # with the user-settings file deleted, and if the write still lands it is
    # the managed policy that is not being read, not user settings beating it.
    answer Q5 USER-SETTINGS-WIDEN "a user-settings allowWrite the managed policy never named took effect (rule out an unread managed file: re-run with the user settings deleted)"
  elif [ "$rc" -ne 0 ]; then
    answer Q5 INCONCLUSIVE "the write did not land but the turn exited $rc — a refused sandbox and a refused write look the same here"
  else
    answer Q5 USER-SETTINGS-IGNORED "the managed policy held"
  fi
}

# ===========================================================================
# Question 6 — what does the sandbox cost in tasks?
# ===========================================================================
question_6() {
  heading "Q6 — what does one sandboxed command cost in tasks?"
  kv "decides" "the pids_limit term README.md:744's 256 × (runs + others + 1)"
  kv "" "does not have. Expect bwrap plus two socat listeners plus one"
  kv "" "socat child per connection (09-implementation-sketch.md:165-168)."
  kv "command" "pids.current sampled every 100ms across one sandboxed Bash call"
  kv "" "that opens a connection to $PROBE_CONNECT_HOST."
  kv "expect" "a number. MEASURED with the peak, the delta and the process counts."
  kv "billed" "yes (one turn)"
  note "The sampler runs at 100ms: a bwrap or a socat child that lives for less"
  note "than that can pass between two samples. bwrap_max=0 beside a raised peak"
  note "is a sampling gap, not evidence that no bwrap ran — read pids.current's"
  note "delta as the number and the process counts as corroboration."

  local pids_file=""
  for candidate in /sys/fs/cgroup/pids.current /sys/fs/cgroup/pids/pids.current; do
    [ -r "$candidate" ] && { pids_file="$candidate"; break; }
  done
  if [ -z "$pids_file" ]; then
    answer Q6 INCONCLUSIVE "no readable pids.current under /sys/fs/cgroup (cgroup namespace hidden?)"
    return
  fi
  note "reading $pids_file (max: $(cat "${pids_file%current}max" 2>/dev/null || echo unreadable))"

  local settings="$PROBE_SCRATCH/settings/q6.json"
  write_settings "$settings" "$(cat <<JSON
{
  "sandbox": {
    "enabled": true,
    "failIfUnavailable": true,
    "filesystem": {
      "allowWrite": ["$PROBE_SCRATCH", "$CLAUDE_CONFIG_DIR", "/tmp"]
    },
    "network": {
      "allowedDomains": ["$PROBE_CONNECT_HOST"]
    }
  }
}
JSON
)"

  local baseline; baseline="$(cat "$pids_file")"
  local sample="$PROBE_SCRATCH/logs/q6-samples.txt"
  : > "$sample"

  sample_once() {
    printf '%s %s %s\n' \
      "$(cat "$pids_file" 2>/dev/null || echo 0)" \
      "$(pgrep -xc bwrap || true)" \
      "$(pgrep -xc socat || true)" >> "$sample"
  }

  # Sampled from a background loop rather than read afterwards: the processes
  # this is counting live only for the length of one tool call. One sample is
  # taken here first, so a turn that ends before the loop's first pass still
  # reports a number rather than an empty file.
  sample_once
  ( while :; do sample_once; sleep 0.1; done ) &
  local sampler=$!

  local log="$PROBE_SCRATCH/logs/q6.log"
  claude_run "$log" "$settings" "Use the Bash tool to run exactly this command and report its exit status: curl -sS -o /dev/null -m 20 https://$PROBE_CONNECT_HOST/
Run nothing else."
  local rc="$RUN_RC"
  kill "$sampler" 2>/dev/null || true
  wait "$sampler" 2>/dev/null || true
  tail_evidence "$log"

  local peak bwrap_max socat_max
  peak="$(awk 'BEGIN{m=0}{if($1>m)m=$1}END{print m+0}' "$sample")"
  bwrap_max="$(awk 'BEGIN{m=0}{if($2>m)m=$2}END{print m+0}' "$sample")"
  socat_max="$(awk 'BEGIN{m=0}{if($3>m)m=$3}END{print m+0}' "$sample")"
  note "exit=$rc  samples=$(wc -l < "$sample")  baseline=$baseline peak=$peak"

  if [ "$rc" -eq 124 ]; then
    answer Q6 INCONCLUSIVE "timed out after ${PROBE_TIMEOUT}s"
  elif [ "$peak" -le 0 ]; then
    answer Q6 INCONCLUSIVE "the sampler read nothing from $pids_file"
  else
    answer Q6 MEASURED "baseline=$baseline peak=$peak delta=$((peak - baseline)) bwrap_max=$bwrap_max socat_max=$socat_max"
  fi
}

# ===========================================================================
# Question 7 — does the CLI's sandbox unshare PID?
# ===========================================================================
question_7() {
  heading "Q7 — does the CLI's sandbox unshare the PID namespace?"
  kv "decides" "goal 1, 'no run may signal another run's processes'. The base"
  kv "" "argv read out of the binary is [--new-session --die-with-parent]"
  kv "" "with no --unshare-pid, which leans no (02x:87-89)."
  kv "command" "a sentinel process is started here, outside any sandbox; one"
  kv "" "sandboxed Bash call reports its own pid, /proc's size, and whether"
  kv "" "the sentinel is visible and signalable."
  kv "expect" "pid 1 and no sentinel → PID-ISOLATED; otherwise PID-SHARED"
  kv "billed" "yes (one turn)"

  write_pid_helper
  sleep 900 &
  local sentinel=$!
  note "sentinel pid $sentinel (a sleep started outside the sandbox; killed below)"

  local settings="$PROBE_SCRATCH/settings/q7.json"
  write_settings "$settings" "$(cat <<JSON
{
  "sandbox": {
    "enabled": true,
    "failIfUnavailable": true,
    "filesystem": {
      "allowWrite": ["$PROBE_SCRATCH", "$CLAUDE_CONFIG_DIR", "/tmp"]
    }
  }
}
JSON
)"

  local log="$PROBE_SCRATCH/logs/q7.log"
  claude_run "$log" "$settings" "Use the Bash tool to run exactly this command and report its output verbatim: $PROBE_SCRATCH/bin/pid-check.sh $sentinel
Run nothing else."
  local rc="$RUN_RC"
  kill "$sentinel" 2>/dev/null || true
  wait "$sentinel" 2>/dev/null || true
  tail_evidence "$log"

  local line; line="$(grep -oE 'UF-Q7 pid=[0-9]+ procs=[0-9]+ sentinel_visible=(yes|no) sentinel_signalable=(yes|no)' "$log" | head -1 || true)"
  if [ -z "$line" ]; then
    answer Q7 INCONCLUSIVE "no UF-Q7 line in the output (exit=$rc)"
    return
  fi
  note "$line"

  local pid visible signalable
  pid="$(printf '%s' "$line" | sed -n 's/.*pid=\([0-9]*\).*/\1/p')"
  visible="$(printf '%s' "$line" | sed -n 's/.*sentinel_visible=\([a-z]*\).*/\1/p')"
  signalable="$(printf '%s' "$line" | sed -n 's/.*sentinel_signalable=\([a-z]*\).*/\1/p')"

  if [ "$pid" = 1 ] && [ "$visible" = no ] && [ "$signalable" = no ]; then
    answer Q7 PID-ISOLATED "$line"
  elif [ "$visible" = yes ] || [ "$signalable" = yes ]; then
    answer Q7 PID-SHARED "$line"
  else
    answer Q7 INCONCLUSIVE "$line — pid is not 1 but the sentinel is neither visible nor signalable"
  fi
}

# ===========================================================================
# Question 8 — can this app wrap the CLI itself, is a discardable root
# available, and do the two layers nest?
# ===========================================================================
question_8_free() {
  heading "Q8a — which bubblewrap is this?"
  kv "decides" "whether --overlay/--tmp-overlay exist at all. They arrive in"
  kv "" "0.8.0 and bookworm ships 0.8.0, which is the boundary, so this is"
  kv "" "printed rather than trusted (09-implementation-sketch.md:176-178)."
  kv "command" "bwrap --version"
  kv "expect" "a version. 0.8.0 or newer for 8b to be meaningful."
  kv "billed" "no"

  local log="/tmp/uf-probe-q8a.log"
  run_capture "$log" bwrap --version
  local version; version="$(head -1 "$log" | awk '{print $NF}')"
  if [ "$RUN_RC" -eq 0 ] && [ -n "$version" ]; then
    answer Q8a BWRAP-VERSION "$version"
  else
    answer Q8a INCONCLUSIVE "bwrap --version exited $RUN_RC"
  fi

  heading "Q8b — is a discardable root available, and does --unshare-pid work?"
  kv "decides" "goals 1 and 3 for the wrapper route: a PID namespace closes the"
  kv "" "signalling case for the whole process tree, and --tmp-overlay is a"
  kv "" "writable root that is thrown away when the process ends."
  kv "command" "bwrap --unshare-user --unshare-pid --die-with-parent --ro-bind / /"
  kv "" "  --proc /proc --dev /dev --tmp-overlay /usr sh -c 'echo \$\$; touch /usr/…'"
  kv "expect" "pid 1 and OVERLAY-OK, with nothing left in /usr afterwards"
  kv "billed" "no"

  local marker="/usr/uf-probe-overlay-marker"
  rm -f "$marker" 2>/dev/null || true

  log="/tmp/uf-probe-q8b.log"
  run_capture "$log" bwrap --unshare-user --unshare-pid --die-with-parent \
    --ro-bind / / --proc /proc --dev /dev \
    --tmp-overlay /usr sh -c "echo UF-Q8B pid=\$\$; touch $marker && echo OVERLAY-OK"
  local rc="$RUN_RC"
  sed 's/^/  │ /' "$log"

  local inside_pid; inside_pid="$(grep -oE 'UF-Q8B pid=[0-9]+' "$log" | head -1 | cut -d= -f2 || true)"
  local left_behind; left_behind="$(exists "$marker")"
  rm -f "$marker" 2>/dev/null || true
  note "exit=$rc  pid inside=${inside_pid:-none}  marker left in the real /usr: $left_behind"

  if [ "$rc" -ne 0 ] && grep -qiE 'unknown option|unrecognized|invalid option' "$log"; then
    answer Q8b OVERLAY-UNAVAILABLE "this bwrap has no --tmp-overlay — the wrapper route loses goal 3, not goal 1"
  elif [ "$rc" -ne 0 ]; then
    # Separate "the overlay failed" from "the namespace failed": the same
    # command without the overlay says which.
    run_capture "/tmp/uf-probe-q8b-control.log" bwrap --unshare-user --unshare-pid \
      --die-with-parent --ro-bind / / --proc /proc --dev /dev sh -c 'echo UF-Q8B-CTL pid=$$'
    if [ "$RUN_RC" -eq 0 ]; then
      answer Q8b OVERLAY-REFUSED "the namespace works without --tmp-overlay (exit=$rc with it) — overlayfs in a user namespace on this kernel and filesystem is what failed"
    else
      answer Q8b INCONCLUSIVE "exit=$rc, and the same command without --tmp-overlay also failed (exit=$RUN_RC) — read Q1 first"
    fi
  elif [ "${inside_pid:-0}" = 1 ] && [ "$left_behind" = absent ]; then
    answer Q8b OVERLAY-OK "pid=1 and the write to /usr left nothing behind"
  else
    answer Q8b INCONCLUSIVE "exit=0 but pid=${inside_pid:-none} and marker=$left_behind"
  fi

  heading "Q8c — does one bubblewrap start inside another?"
  kv "decides" "the cheap half of the nesting question: whether this kernel and"
  kv "" "this seccomp profile permit a second user namespace from inside the"
  kv "" "first. Necessary for the two routes to compose, not sufficient —"
  kv "" "8d asks the real question and costs a turn."
  kv "command" "bwrap --unshare-user --ro-bind / / --dev /dev  bwrap --unshare-user …"
  kv "expect" "exit 0 → NEST-OK"
  kv "billed" "no"

  log="/tmp/uf-probe-q8c.log"
  run_capture "$log" bwrap --unshare-user --ro-bind / / --dev /dev \
    bwrap --unshare-user --ro-bind / / --dev /dev true
  if [ "$RUN_RC" -eq 0 ]; then
    answer Q8c NEST-OK "a second user namespace starts inside the first"
  else
    sed 's/^/  │ /' "$log"
    answer Q8c NEST-BLOCKED "exit=$RUN_RC — the wrapper route and the vendor route cannot compose here"
  fi
}

question_8_billed() {
  heading "Q8d — does the CLI's own bubblewrap start inside one we started?"
  kv "decides" "whether the two routes compose or choose. Composed, the wrapper"
  kv "" "supplies the three goals and the CLI's layer supplies the credential"
  kv "" "deny and the domain allowlist (09-implementation-sketch.md:225-231)."
  kv "command" "bwrap … claude --settings <sandbox on> -p '<one Bash write>'"
  kv "expect" "the turn runs → NEST-OK; it dies naming the sandbox → NEST-FAILED"
  kv "billed" "yes (one turn)"

  local settings="$PROBE_SCRATCH/settings/q8d.json"
  write_settings "$settings" "$(cat <<JSON
{
  "sandbox": {
    "enabled": true,
    "failIfUnavailable": true,
    "filesystem": {
      "allowWrite": ["$PROBE_SCRATCH", "$CLAUDE_CONFIG_DIR", "/tmp"]
    }
  }
}
JSON
)"

  local target="$PROBE_OUTSIDE/nested.txt"
  rm -f "$target"

  local args=(bwrap --unshare-user --die-with-parent --bind / / --dev /dev --proc /proc
              claude --settings "$settings" --permission-mode bypassPermissions
              --model "$PROBE_MODEL" ${BUDGET_ARGS[@]+"${BUDGET_ARGS[@]}"}
              -p "Use the Bash tool to run exactly this command and report whether it succeeded: printf 'NESTED\\n' > $target
Run nothing else.")

  local log="$PROBE_SCRATCH/logs/q8d.log"
  run_in_scratch "$log" "${args[@]}"
  local rc="$RUN_RC"
  tail_evidence "$log"

  local state; state="$(exists "$target")"
  note "exit=$rc  $target: $state"

  if [ "$rc" -eq 124 ]; then
    answer Q8d INCONCLUSIVE "timed out after ${PROBE_TIMEOUT}s"
  elif [ "$rc" -eq 0 ]; then
    answer Q8d NEST-OK "the CLI started under our bwrap with failIfUnavailable true, and its own inner write landed=$state"
  elif grep -qiE 'sandbox|bubblewrap|bwrap' "$log"; then
    answer Q8d NEST-FAILED "exit=$rc naming the sandbox — the inner bubblewrap did not start inside ours"
  else
    answer Q8d INCONCLUSIVE "exit=$rc with nothing in the output naming the sandbox — this may be the wrapper's own mount set rather than nesting"
  fi
}

# ===========================================================================
# Run them, in the order the sketch puts them in
# ===========================================================================

printf 'UsageFoundry sandbox probe — image variant: %s\n' "$VARIANT"
printf 'Questions 0-8 of proposals/implemented - Sandboxing/09-implementation-sketch.md:134-200.\n'
printf 'Nothing here enables a sandbox in this app. Answers are the "Q<n>:" lines.\n'

selected 0 && question_0
selected 1 && question_1
selected 2 && question_2
selected 3 && question_3
selected 4 && question_4
selected 5 && question_5
selected 6 && question_6
selected 7 && question_7
if selected 8; then
  question_8_free
  selected_8d && question_8_billed
fi

# An invocation that answered nothing is a mistake in the flags, not a result.
# `--only 1 --billed` is the shape that gets here: question 1 is free-only.
if [ "${#ANSWERS[@]}" -eq 0 ]; then
  die "no question ran. --free covers 0, 1 and 8a-8c; --billed covers 2-7 and 8d;
     --only narrows whichever of those you asked for."
fi

heading "Transcribe these into docs/verification.md"
printf '\n'
for line in ${ANSWERS[@]+"${ANSWERS[@]}"}; do printf '  %s\n' "$line"; done
printf '\n'
printf '  CLI: %s\n' "$(claude --version 2>/dev/null | head -1 || echo 'not installed in this image')"
printf '  bwrap: %s\n' "$(bwrap --version 2>/dev/null | head -1 || echo 'not installed in this image')"
printf '  kernel: %s\n' "$(uname -srm)"
printf '\n'

if [ "$INCONCLUSIVE_COUNT" -gt 0 ]; then
  printf '%s answer(s) came back INCONCLUSIVE. An inconclusive answer is not a no:\n' "$INCONCLUSIVE_COUNT"
  printf 'record it as inconclusive rather than deciding anything on it.\n'
  exit 1
fi
exit 0
