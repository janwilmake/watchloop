#!/bin/bash
# One gate for the whole tick. Prints a "NO" line with its reason when there is
# nothing for the model to do, otherwise prints a compact context block.
#
# Two modes:
#   gate.sh            one probe, print, exit — for a fixed-interval loop.
#   gate.sh --peek     the same probe, but never writes the state file — for a
#                      heartbeat tick that only wants to LOOK while a --wait
#                      waiter is alive. A plain run rewrites the hash the waiter
#                      compares against, so the waiter's next probe sees no
#                      change and the "world-changed: yes" it owed the model is
#                      swallowed. Use --peek whenever a waiter is running.
#   gate.sh --wait [s] block until there IS work, then print and exit — for an
#                      event-driven loop. Run it with run_in_background: the
#                      exit is what wakes the model, so a quiet night costs no
#                      turns at all instead of one every 5 minutes.
#   gate.sh --permissions  print the permissions file as merged on origin/BASE.
#
# Why a state hash: 94 consecutive ticks one night printed the same numbers and
# changed nothing. The model only needs to wake when the *world* changed, not
# when the clock did.
#
# Linear is included cheaply: only when slots > 0 (a new ticket the machine
# cannot start is not worth waking for), through the agent-codemode CLI, which
# inherits Claude Code's Linear OAuth (the macOS Keychain, or
# ~/.claude/.credentials.json on Linux) — no token, no model.
# The eligible-ticket ids fold into the state hash, so a new Urgent is seen on
# the next gate, not only on the 30-minute queue rebuild.

# --- config: put your values in .env next to this file (gitignored; see .env.example) ---
SELF="$(cd "$(dirname "${BASH_SOURCE[0]}")" && pwd)"
[ -f "$SELF/.env" ] && set -a && . "$SELF/.env" && set +a
REPO="${LO_REPO:-/path/to/your/repo}"
BASE="${LO_BASE:-dev}"
TEAM="${LO_TEAM:-Your Team}"        # Linear team name
PREFIX="${LO_PREFIX:-XXX}"          # ticket id prefix, e.g. HYR2
TIER1="${LO_TIER1:-}"               # preferred assignee DISPLAY name
TIER2="${LO_TIER2:-}"               # fallback assignee display name
# The same two people by Linear user id. A display name is a free text field:
# a member who renames to the loop's assignee would get tickets taken. When an
# id is set, the gate matches the id and ignores the name of that tier.
TIER1_ID="${LO_TIER1_ID:-}"
TIER2_ID="${LO_TIER2_ID:-}"
# Two opt-in widenings, both OFF by default. Unassigned and Backlog are work
# nobody handed to this loop: somebody who moves a ticket to Todo and puts a
# name on it has decided it is ready, and that decision is the whole signal.
# Taking either without being asked is how an orchestrator starts work its owner
# never queued — so each is a deliberate switch, not a default.
ALLOW_UNASSIGNED="${LO_ALLOW_UNASSIGNED:-0}"  # 1 = unassigned tickets count too
ALLOW_BACKLOG="${LO_ALLOW_BACKLOG:-0}"        # 1 = fall to Backlog when Todo is empty
# Which PRs are THIS loop's. Every watchloop writes the same bare 🌙
# marker, so on a repo with two of them running the marker cannot tell them
# apart: each reads the other's PRs as its own and reviews, re-drafts and
# answers feedback on them. LO_OWNER puts a per-instance tag in the marker and
# the gate matches on that. Empty keeps the bare marker — correct only when a
# single orchestrator touches the repo.
OWNER="${LO_OWNER:-}"
PR_MARKER="🌙${OWNER:+ lo:$OWNER}"
RAM_PER_AGENT="${LO_RAM_PER_AGENT:-2.5}"
# Ceiling on concurrent agents. 0 = unlimited, and unlimited is the default: the
# tick spawns every slot free RAM allows, so the loop reaches full capacity on
# the first tick with work instead of climbing one agent at a time.
MAX_AGENTS_CAP="${LO_MAX_AGENTS:-0}"
# --- platform: macOS and Linux report the same numbers through these ---
if [ "$(uname -s)" = Darwin ]; then
  mtime()      { stat -f %m "$1"; }
  ram_bytes()  { sysctl -n hw.memsize; }
  load1()      { sysctl -n vm.loadavg | awk '{print $2}'; }
  # Free + speculative + purgeable + inactive: what macOS hands out without swapping.
  free_gb()    { vm_stat | awk '/page size of/{ps=$8} /Pages free/{f=$3}
    /Pages speculative/{s=$3} /Pages purgeable/{p=$3} /Pages inactive/{i=$3}
    END{gsub("\\.","",f); gsub("\\.","",s); gsub("\\.","",p); gsub("\\.","",i)
        printf "%.1f", (f+s+p+i)*ps/1073741824}'; }
  iso_epoch()  { date -j -u -f "%Y-%m-%dT%H:%M:%SZ" "$1" +%s; }
  days_ago()   { date -u -v-"$1"d +%Y-%m-%dT%H:%M:%SZ; }
  hash16()     { shasum | cut -c1-16; }
else
  mtime()      { stat -c %Y "$1"; }
  ram_bytes()  { awk '/^MemTotal:/{print $2*1024}' /proc/meminfo; }
  load1()      { awk '{print $1}' /proc/loadavg; }
  free_gb()    { awk '/^MemAvailable:/{printf "%.1f", $2/1048576}' /proc/meminfo; }
  iso_epoch()  { date -u -d "$1" +%s; }
  days_ago()   { date -u -d "$1 days ago" +%Y-%m-%dT%H:%M:%SZ; }
  hash16()     { sha1sum | cut -c1-16; }
fi
cpu_cores()    { getconf _NPROCESSORS_ONLN; }
disk_free_gb() { df -Pk / | awk 'NR==2{print int($4/1048576)}'; }

# How many agent slots to probe for liveness. This must cover the most agents
# that can run at once or a busy agent above the scan reads as a free slot and
# the loop double-spawns onto it. Defaults to what total RAM allows, floor 8.
SLOT_SCAN="${LO_SLOT_SCAN:-$(awk -v r="$(( $(ram_bytes) / 1073741824 ))" \
  -v a="${LO_RAM_PER_AGENT:-2.5}" 'BEGIN{m=int(r/a); print (m<8?8:m)}')}"
WAIT_INTERVAL="${LO_WAIT_INTERVAL:-60}"   # --wait: seconds between probes
WAIT_MAX="${LO_WAIT_MAX:-2400}"           # --wait: give up and let the model re-arm
GATE_ERR_WAKE="${LO_GATE_ERR_WAKE:-3}"    # --wait: consecutive forge errors before waking
# Comments written before the loop started marking its own carry no marker, so
# they would all read as human. This floor is the day marking began: nothing
# before it is ever treated as feedback.
FEEDBACK_SINCE="${LO_FEEDBACK_SINCE:-2026-08-18T17:00:00Z}"
# Whose comments count as feedback. Comma-separated GitHub logins, case
# insensitive. Empty means every non-bot login counts.
FEEDBACK_LOGINS="${LO_FEEDBACK_LOGINS:-}"
# Spawn ceiling as a fraction of cores: refuse new agents when load1 exceeds
# cores*this. 0.7 was the conservative default; agents are mostly think-bound,
# so 1.0 trades transient build slowdown for throughput. RAM stays the bound.
LOAD_FACTOR="${LO_LOAD_FACTOR:-0.7}"

# One Linear read, filtered to the tickets this instance is allowed to take.
# $1 is the status TYPE, not the column name — `state:"Backlog"` also returns
# every other backlog-type status (Planned, Ideas, To Discuss on some
# workspaces), so this is a cheap shortlist and the model still filters to the
# exact column before it spawns anything.
#
# Assignee is the separation between two orchestrators on one tracker: each
# takes only its own tiers, so neither can claim the other's tickets. That is
# why an empty tier is dropped rather than matched — an unset LO_TIER2 would
# otherwise equal the empty assignee string and quietly re-admit every
# unassigned ticket that ALLOW_UNASSIGNED is meant to gate.
LINEAR_ERR=""
linear_ids() {
  local tj
  tj=$("$AC" call linear list_issues \
    --json "{\"team\":\"$TEAM\",\"state\":\"$1\",\"includeArchived\":false,\"fields\":[\"assignee\",\"assigneeId\",\"archivedAt\",\"status\"]}" \
    --text 2>/dev/null)
  if [ -z "$tj" ]; then
    LINEAR_ERR="linear query failed (token expired? claude mcp login linear)"
    return 0
  fi
  printf '%s' "$tj" | jq -r --arg t1 "$TIER1" --arg t2 "$TIER2" \
    --arg i1 "$TIER1_ID" --arg i2 "$TIER2_ID" \
    --argjson unassigned "$([ "$ALLOW_UNASSIGNED" = 1 ] && echo true || echo false)" '
    # Per tier: its id when set, else its name. An empty tier matches nothing.
    ([ (if $i1 != "" then {id: $i1} elif $t1 != "" then {name: $t1} else empty end),
       (if $i2 != "" then {id: $i2} elif $t2 != "" then {name: $t2} else empty end) ]) as $tiers
    | [ .issues[]?
        | select(.archivedAt == null)
        | (.assignee // "") as $a
        | (.assigneeId // "") as $ai
        | select( ($unassigned and $a == "" and $ai == "")
                  or ($tiers | any(.id == $ai and $ai != "" or .name == $a and $a != "")) )
        | .id ] | sort | join(",")' 2>/dev/null
}

mkdir -p ~/.claude/watchloop
STATE=~/.claude/watchloop/gate-state
# The drafts fingerprint lives apart from the main hash on purpose. The main
# hash covers the whole world, so anything at all moving it — an agent pushing
# a commit on an unrelated branch, CI starting on somebody else's PR — makes
# every open draft look new again. A draft is only work when something about
# THAT draft moved.
DSTATE=~/.claude/watchloop/gate-drafts-state
# Same reasoning for the de-gate list. REGATE normally clears itself: the model
# acts, the PR goes back to draft, and it drops off. It only persists when the
# model looks and deliberately declines — a conflict GitHub reports that does not
# exist, a layer whose base is mid-repair — and nothing in the gate records that
# decision, so an unconditional work=yes re-wakes on the entry forever.
RSTATE=~/.claude/watchloop/gate-regate-state
# Adopted PRs: PRs a person opened, not the loop, that the loop still looks
# after. LO_ADOPT_AUTHORS lists the GitHub logins (comma separated, case
# insensitive); LO_ADOPT_SINCE keeps it to PRs created after that instant, so
# turning the feature on does not sweep up a backlog nobody asked about. The
# loop reviews such a PR once, and only when no person reviewed it first; it
# merges the base in when the PR conflicts, and fixes a red CI. It never
# promotes, re-drafts, merges or rewrites the body of an adopted PR.
ADOPT_AUTHORS="${LO_ADOPT_AUTHORS:-}"
ADOPT_SINCE="${LO_ADOPT_SINCE:-}"
# The adopt fingerprint, kept apart for the same reason as DSTATE: an adopted PR
# wakes the loop only when what it needs changed.
ASTATE=~/.claude/watchloop/gate-adopt-state
QUEUE=~/.claude/watchloop/${PREFIX}-queue.json
AC="${AGENT_CODEMODE:-$(command -v agent-codemode 2>/dev/null || echo "$HOME/.local/node/bin/agent-codemode")}"

# --- Slack intake (off until LO_SLACK=1) ---
# The gate does not understand Slack. It takes a fingerprint of each watched
# channel and of each thread the tick left open, and names the ones whose
# fingerprint moved since the tick last acknowledged them. The tick reads those
# and decides what a message is. Parsing the message text here would tie the
# gate to the MCP server's output format.
#
# The read goes through agent-codemode, like Linear, so the server must be one
# Claude Code itself is logged in to (`claude mcp add`). A claude.ai connector
# is invisible here.
# There is no channel list to configure: the loop watches every channel, DM and
# group DM its Slack account is a member of. Invite the account to a channel to
# have it watched; remove it to stop.
SLACK_ON="${LO_SLACK:-0}"
SLACK_CHANLIST=~/.claude/watchloop/gate-slack-channels   # membership, refreshed hourly
SLACK_SERVER="${LO_SLACK_SERVER:-slack}"      # MCP server name in Claude Code
SLACK_INTERVAL="${LO_SLACK_INTERVAL:-300}"    # seconds between real reads; --wait probes every 60s
SLACK_THREADS=~/.claude/watchloop/${PREFIX}-slack.json   # the tick's own record of threads
SLACK_SEEN=~/.claude/watchloop/gate-slack-seen.json      # key -> fingerprint the tick acknowledged
SLACK_NOW=~/.claude/watchloop/gate-slack-now.json        # the last read, with its time
# What the model was last shown, kept apart for the same reason as DSTATE: a
# thread the tick failed to acknowledge wakes the loop once, not on every probe.
SLSTATE=~/.claude/watchloop/gate-slack-state
# The keys of the last SLACK line the model was shown. An ack covers these keys
# only: a channel that moved while the tick worked on another one was never
# read, and acknowledging it would hide a person's message for good.
SLACK_SHOWN=~/.claude/watchloop/gate-slack-shown.json
# The same for the FEEDBACK line: what the model was last shown.
FSTATE=~/.claude/watchloop/gate-feedback-state
SLACK_ERR=""
SLACK_SIGS='{}'

# slack_read [fresh]: fill SLACK_SIGS with {key: fingerprint}. A key is a
# channel id, or "<channel>/<thread ts>" for an open thread. A read that
# returns nothing leaves its key out, so an outage never reads as a change.
slack_read() {
  local now at out ch t key
  SLACK_ERR=""; SLACK_SIGS='{}'
  now=$(date +%s)
  if [ "$1" != fresh ] && [ -f "$SLACK_NOW" ]; then
    at=$(jq -r '.at // 0' "$SLACK_NOW" 2>/dev/null)
    if [ $(( now - ${at:-0} )) -lt "$SLACK_INTERVAL" ]; then
      SLACK_SIGS=$(jq -c '.sigs // {}' "$SLACK_NOW" 2>/dev/null || echo '{}')
      return 0
    fi
  fi
  if [ ! -s "$SLACK_CHANLIST" ] || [ $(( now - $(mtime "$SLACK_CHANLIST") )) -gt 3600 ]; then
    # The text content is one JSON string, so its line breaks arrive as a
    # literal backslash-n. Turn them into lines before picking out the ids.
    out=$("$AC" call "$SLACK_SERVER" slack_list_user_channels \
      --json '{"types":"public_channel,private_channel,im,mpim","format":"ids_only","exclude_archived":true,"limit":200}' \
      --text 2>/dev/null </dev/null | sed 's/\\n/\n/g' | grep -oE '^[CDG][A-Z0-9]{8,}' | sort -u)
    [ -n "$out" ] && printf '%s\n' "$out" > "$SLACK_CHANLIST"
  fi
  if [ ! -s "$SLACK_CHANLIST" ]; then
    SLACK_ERR="slack channel list failed (claude mcp login $SLACK_SERVER?)"
    return 0
  fi
  for ch in $(cat "$SLACK_CHANLIST"); do
    out=$("$AC" call "$SLACK_SERVER" slack_read_channel \
      --json "{\"channel_id\":\"$ch\",\"limit\":30}" --text 2>/dev/null </dev/null)
    # An answer without messages is an error text, such as a rate limit. It must
    # not count as a change, or every refused read would wake the loop.
    if ! printf '%s' "$out" | grep -q '"messages"'; then
      SLACK_ERR="slack read failed (claude mcp login $SLACK_SERVER?)"
      continue
    fi
    # A message from a bot is not news: an alert channel would wake the loop on
    # every alert, for the tick to skip it. Drop bot messages from the
    # fingerprint, but keep their "Thread:" line, so a person who replies under
    # an alert is still seen.
    # The header is "=== Message from <display name> [<email>] (<id>) at <time> ===".
    # Judge the author by the id and the email at the END of the line only: the
    # display name is free text, and a person who puts "botuser-" or
    # "slack-bots.com" in it must not drop out of the fingerprint. A bot is a
    # B… id, Slackbot, or a bot user, whose email Slack sets on slack-bots.com.
    quiet=$(printf '%s' "$out" | jq -r '.messages // empty' 2>/dev/null | awk '
      /^=== Message from / {
        bot = 0
        if (match($0, /(<[^<>]*> )?\([A-Z0-9]+\) at [^()<>]*===[ ]*$/)) {
          tail = substr($0, RSTART, RLENGTH)
          id = tail; sub(/^.*\(/, "", id); sub(/\).*$/, "", id)
          bot = (id ~ /^B/ || id == "USLACKBOT" || tail ~ /^<[^<>]*@slack-bots\.com> /)
        }
      }
      !bot || /^Thread: / { print }')
    [ -n "$quiet" ] && out="$quiet"
    SLACK_SIGS=$(printf '%s' "$SLACK_SIGS" | jq -c --arg k "$ch" \
      --arg v "$(printf '%s' "$out" | hash16)" '.[$k] = $v')
  done
  if [ -f "$SLACK_THREADS" ]; then
    while read -r ch t; do
      [ -n "$ch" ] && [ -n "$t" ] || continue
      out=$("$AC" call "$SLACK_SERVER" slack_read_thread \
        --json "{\"channel_id\":\"$ch\",\"message_ts\":\"$t\"}" --text 2>/dev/null </dev/null)
      printf '%s' "$out" | grep -q '"messages"' || continue
      SLACK_SIGS=$(printf '%s' "$SLACK_SIGS" | jq -c --arg k "$ch/$t" \
        --arg v "$(printf '%s' "$out" | hash16)" '.[$k] = $v')
    done < <(jq -r '.threads[]? | select(.status != "closed") | "\(.channel) \(.ts)"' \
               "$SLACK_THREADS" 2>/dev/null)
  fi
  [ "$PEEK" = 1 ] || jq -nc --argjson at "$now" --argjson sigs "$SLACK_SIGS" \
    '{at: $at, sigs: $sigs}' > "$SLACK_NOW"
}

# --- Inbox watch: one person's new emails, meetings and calls in Hyre ---
# Off until LO_INBOX_EMAIL names the mailbox. Same shape as the Slack watch: the
# gate fingerprints the newest rows through agent-codemode and names the kinds
# that moved; the tick reads them, decides what is relevant and tells the person
# in a Slack DM. Fingerprints hold ids only, never a subject or a name.
INBOX_EMAIL="${LO_INBOX_EMAIL:-}"            # the mailbox to watch
INBOX_USER_ID="${LO_INBOX_USER_ID:-}"        # that person's Hyre user id, for meetings and calls
INBOX_SERVER="${LO_INBOX_SERVER:-hyre}"      # MCP server name in Claude Code
INBOX_INTERVAL="${LO_INBOX_INTERVAL:-120}"   # seconds between real reads
INBOX_SEEN=~/.claude/watchloop/gate-inbox-seen.json
INBOX_NOW=~/.claude/watchloop/gate-inbox-now.json
ISTATE=~/.claude/watchloop/gate-inbox-state
INBOX_SHOWN=~/.claude/watchloop/gate-inbox-shown.json   # the kinds of the last INBOX line shown
INBOX_ERR=""
INBOX_SIGS='{}'

# --- Schedules: recurring agent jobs declared in the repo ---
# lo-schedule.sh reads `.agents/schedules/*.md` from origin/<BASE> and says which
# jobs are due; the gate only passes that on. What the model was last shown is
# kept apart, like DSTATE: a due job wakes the loop once, not on every probe.
SCSTATE=~/.claude/watchloop/gate-schedules-state

# inbox_read [fresh]: fill INBOX_SIGS with {emails, meetings, calls: fingerprint}.
# A read that fails leaves its key out, so an outage never reads as a change.
inbox_read() {
  local now at out
  INBOX_ERR=""; INBOX_SIGS='{}'
  now=$(date +%s)
  if [ "$1" != fresh ] && [ -f "$INBOX_NOW" ]; then
    at=$(jq -r '.at // 0' "$INBOX_NOW" 2>/dev/null)
    if [ $(( now - ${at:-0} )) -lt "$INBOX_INTERVAL" ]; then
      INBOX_SIGS=$(jq -c '.sigs // {}' "$INBOX_NOW" 2>/dev/null || echo '{}')
      return 0
    fi
  fi
  inbox_one() {  # $1 key, $2 tool, $3 json args, $4 jq filter that lists the ids
    out=$("$AC" call "$INBOX_SERVER" "$2" --json "$3" --text 2>/dev/null </dev/null \
      | jq -c "$4" 2>/dev/null)
    if [ -z "$out" ] || [ "$out" = null ]; then
      INBOX_ERR="hyre read failed (claude mcp login $INBOX_SERVER?)"
      return 0
    fi
    INBOX_SIGS=$(printf '%s' "$INBOX_SIGS" | jq -c --arg k "$1" \
      --arg v "$(printf '%s' "$out" | hash16)" '.[$k] = $v')
  }
  inbox_one emails emails \
    "{\"method\":\"get_emails\",\"response_format\":\"json\",\"params\":{\"user_email\":\"$INBOX_EMAIL\",\"perPage\":10}}" \
    '[.emails[] | select(.direction == "inbound") | .id]'
  if [ -n "$INBOX_USER_ID" ]; then
    # Ordered by updated_at: a meeting shows up here when its transcript lands,
    # which is later than its start and later than a shorter meeting after it.
    inbox_one meetings meetings \
      "{\"method\":\"get_meetings\",\"response_format\":\"json\",\"params\":{\"user_id\":\"$INBOX_USER_ID\",\"perPage\":10,\"order_by\":\"updated_at\"}}" \
      '[.meetings[] | .id]'
    inbox_one calls phone_calls \
      "{\"method\":\"get_calls\",\"response_format\":\"json\",\"params\":{\"user_id\":\"$INBOX_USER_ID\",\"perPage\":10}}" \
      '[.calls[] | [.id, .call_status, (.summary != null)]]'
  fi
  [ "$PEEK" = 1 ] || jq -nc --argjson at "$now" --argjson sigs "$INBOX_SIGS" \
    '{at: $at, sigs: $sigs}' > "$INBOX_NOW"
}

# --- Sweep: mail, messages and calendar once an hour (off until LO_SWEEP=1) ---
# Slack wants an answer within minutes; mail and the calendar are fine read once
# an hour. So the gate does not read them: it keeps the time of the last sweep,
# says SWEEP-DUE on any wake once an hour has passed, and in --wait wakes for the
# sweep alone when nothing else did. The model sweeps with whatever tools the
# session has (Hyre, Gmail, Outlook...) and marks it with `gate.sh --swept`, so
# the gate needs no code per mail provider, and an interrupted sweep is asked
# for again.
SWEEP_ON="${LO_SWEEP:-0}"
SWEEP_EVERY="${LO_SWEEP_EVERY:-3600}"   # seconds between sweeps
SWEEP_AT=~/.claude/linear-orchestrator/gate-sweep-at        # last sweep the model finished
SWEEP_SHOWN=~/.claude/linear-orchestrator/gate-sweep-shown  # last wake for the sweep alone
# A wake for the sweep alone at most this often: a model that never runs
# --swept must not turn every re-arm into a wake.
SWEEP_REWAKE=900

sweep_age() {  # seconds since the last sweep; a large number when there was none
  local at; at=$(cat "$SWEEP_AT" 2>/dev/null)
  echo $(( $(date +%s) - ${at:-0} ))
}
sweep_due() { [ "$SWEEP_ON" = 1 ] && [ "$(sweep_age)" -ge "$SWEEP_EVERY" ]; }
sweep_line() {
  local age; age=$(sweep_age)
  local when="never swept"; [ "$age" -lt 31536000 ] && when="last sweep $(( age / 60 ))m ago"
  echo "SWEEP-DUE: $when - check mail, messages and the calendar, then run gate.sh --swept"
}

if [ "$1" = "--swept" ]; then
  mkdir -p ~/.claude/linear-orchestrator
  date +%s > "$SWEEP_AT"
  echo "sweep marked done; next one due in $(( SWEEP_EVERY / 60 ))m"
  exit 0
fi

# --- Permissions: the merged file, never the working tree ---
# The permissions file must change only through a PR that a person merges. A
# checkout is a working copy: a branch checked out by hand, or an edit nobody
# committed, would widen who may ask for what at once. So when the file lies in
# a git checkout, read it from that checkout's origin/BASE, after a fetch. A
# fetch leaves the working tree alone, so it is safe on a dirty checkout too. A
# file outside any checkout is the operator's own, like .env: read it as is.
PERMISSIONS="${LO_PERMISSIONS:-$REPO/.agents/permissions.md}"

# permissions_show: print the file and return 0, or print the reason on stderr
# and return 1. A 1 means: fall back to the LO_SLACK_*_EMAILS lists.
permissions_show() {
  local dir rel
  dir=$(dirname "$PERMISSIONS")
  [ -d "$dir" ] || { echo "permissions: $PERMISSIONS is missing" >&2; return 1; }
  # Git resolves symlinks itself, so a link into a checkout still reads as one.
  if ! rel=$(git -C "$dir" rev-parse --show-prefix 2>/dev/null); then
    [ -f "$PERMISSIONS" ] || { echo "permissions: $PERMISSIONS is missing" >&2; return 1; }
    cat "$PERMISSIONS"; return 0
  fi
  rel="$rel$(basename "$PERMISSIONS")"
  # A failed fetch keeps the last origin/BASE: that is still a merged file.
  git -C "$dir" fetch --quiet origin "$BASE" 2>/dev/null \
    || echo "permissions: fetch of origin/$BASE failed; using the last one fetched" >&2
  git -C "$dir" show "origin/$BASE:$rel" 2>/dev/null \
    || { echo "permissions: $rel is not on origin/$BASE" >&2; return 1; }
}

if [ "$1" = "--permissions" ]; then
  permissions_show; exit $?
fi

MODE=once
PEEK=0
[ "$1" = "--peek" ] && PEEK=1

# Every state write goes through here. --peek makes it a no-op, so a look never
# moves the world forward for the waiter that is watching it.
save_state() { [ "$PEEK" = 1 ] || printf '%s' "$1" > "$STATE"; }
# Written from the same places as save_state, so the two never drift: a probe
# the model did not see must move neither of them.
save_drafts_state() { [ "$PEEK" = 1 ] || printf '%s' "$1" > "$DSTATE"; }
save_regate_state() { [ "$PEEK" = 1 ] || printf '%s' "$1" > "$RSTATE"; }
save_adopt_state() { [ "$PEEK" = 1 ] || printf '%s' "$1" > "$ASTATE"; }

# --slack-ack: the tick has read Slack and acted. Read it again, because the
# tick's own replies moved the fingerprints, and record that as seen.
if [ "$1" = "--slack-ack" ]; then
  [ "$SLACK_ON" = 1 ] || { echo "slack: off (LO_SLACK is not 1)"; exit 0; }
  slack_read fresh
  seen=$(cat "$SLACK_SEEN" 2>/dev/null); [ -n "$seen" ] || seen='{}'
  shift
  if [ "$1" = all ]; then
    # The baseline, on the day the watch is switched on: everything is seen.
    keys=$(printf '%s' "$SLACK_SIGS" | jq -c 'keys')
  else
    # What the last SLACK line showed, plus any key named here (a thread the
    # tick just opened, as "<channel>/<ts>").
    shown=$(cat "$SLACK_SHOWN" 2>/dev/null); [ -n "$shown" ] || shown='[]'
    keys=$(jq -nc --argjson a "$shown" '$a + $ARGS.positional' --args "$@")
  fi
  jq -nc --argjson s "$seen" --argjson n "$SLACK_SIGS" --argjson k "$keys" \
    '$s + ($n | with_entries(select(.key as $x | $k | index($x))))' > "$SLACK_SEEN"
  echo '[]' > "$SLACK_SHOWN"
  left=$(jq -nc --argjson n "$SLACK_SIGS" --slurpfile s "$SLACK_SEEN" '[ $n | to_entries[] | select($s[0][.key] != .value) | .key ] | length')
  echo "slack: acknowledged $(printf '%s' "$keys" | jq 'length') key(s); $left still unread${SLACK_ERR:+; $SLACK_ERR}"
  exit 0
fi

# --inbox-ack: the tick has read the inbox watch and told the person.
if [ "$1" = "--inbox-ack" ]; then
  [ -n "$INBOX_EMAIL" ] || { echo "inbox: off (LO_INBOX_EMAIL is empty)"; exit 0; }
  inbox_read fresh
  seen=$(cat "$INBOX_SEEN" 2>/dev/null); [ -n "$seen" ] || seen='{}'
  if [ "$2" = all ]; then
    keys=$(printf '%s' "$INBOX_SIGS" | jq -c 'keys')
  else
    keys=$(cat "$INBOX_SHOWN" 2>/dev/null); [ -n "$keys" ] || keys='[]'
  fi
  jq -nc --argjson s "$seen" --argjson n "$INBOX_SIGS" --argjson k "$keys" \
    '$s + ($n | with_entries(select(.key as $x | $k | index($x))))' > "$INBOX_SEEN"
  echo '[]' > "$INBOX_SHOWN"
  echo "inbox: acknowledged $keys${INBOX_ERR:+; $INBOX_ERR}"
  exit 0
fi
NOREASON=""

# probe: measure the world once. Prints the context block and returns 0 when
# there is work; prints nothing and returns 1 when there is not, leaving the
# reason in $NOREASON for the caller to print or swallow.
probe() {
  # Set when the forge could not be read at all. It is not work, and in --wait
  # the caller decides whether an outage has lasted long enough to wake for.
  GATE_ERR=""

  # --- hourly base-branch refresh (refuses, never forces) ---
  stamp=~/.claude/watchloop/last-fetch
  notes=""
  if [ ! -f "$stamp" ] || [ $(( $(date +%s) - $(mtime "$stamp") )) -gt 3600 ]; then
    if [ -z "$(git -C $REPO status --porcelain --untracked-files=no)" ] \
       && [ "$(git -C $REPO branch --show-current)" = "$BASE" ]; then
      before=$(git -C $REPO rev-parse --short HEAD)
      git -C $REPO pull --ff-only --quiet origin $BASE 2>/dev/null
      after=$(git -C $REPO rev-parse --short HEAD)
      [ "$before" != "$after" ] && notes="dev $before -> $after"
      touch "$stamp"
    else
      notes="dev NOT refreshed: repo is dirty or not on $BASE"
    fi
  fi

  # --- reap leaked dev servers from dead slots ---
  for n in $(seq 1 "$SLOT_SCAN"); do
    p=$(cat ~/.claude/agents/agent-$n.lock 2>/dev/null)
    if [ -z "$p" ] || ! kill -0 "$p" 2>/dev/null; then
      pids=$(pgrep -f "/.claude/agents/agent-$n/" 2>/dev/null)
      if [ -n "$pids" ]; then
        notes="$notes${notes:+; }reaped agent-$n"
        kill $pids 2>/dev/null
      fi
    fi
  done
  sleep 2

  # --- capacity ---
  cores=$(cpu_cores)
  ramgb=$(( $(ram_bytes) / 1073741824 ))
  load=$(load1)
  freegb=$(free_gb)
  diskgb=$(disk_free_gb)
  # A live agent's branch is not work: it is work in progress. Collect the
  # branches here so the PR lists below can drop them, or the waiter exits the
  # instant an agent drafts its own PR and every re-arm spins on the same PR.
  busy=0
  live_branches=""
  for n in $(seq 1 "$SLOT_SCAN"); do
    p=$(cat ~/.claude/agents/agent-$n.lock 2>/dev/null)
    if [ -n "$p" ] && kill -0 "$p" 2>/dev/null; then
      busy=$((busy+1))
      b=$(git -C ~/.claude/agents/agent-$n branch --show-current 2>/dev/null)
      [ -n "$b" ] && live_branches="$live_branches$b
"
    fi
  done
  held=$(printf '%s' "$live_branches" | jq -Rsc 'split("\n") | map(select(length>0))')

  # --- PRs already in an agent's hands ---
  # The branch test above cannot see an agent that has not run `gh pr checkout`
  # yet, and "yet" can be half an hour: an agent sent to answer a question reads
  # the code long before it touches the branch. Guessing a grace period was
  # wrong twice, so the marker names the exact fact instead — a dispatch writes
  # the agent's SLOT into a file named after the PR, and the PR is in hand for
  # precisely as long as that slot's lock is alive. An agent that dies frees its
  # PR on the next probe; one that finishes frees it the moment its lock goes.
  # The 10-minute floor covers only the seconds between the spawn and the marker.
  dispatch_dir="$HOME/.claude/watchloop/dispatched"
  mkdir -p "$dispatch_dir"
  now_s=$(date +%s)
  inhand=""
  for f in "$dispatch_dir"/*; do
    [ -f "$f" ] || continue
    slot=$(cat "$f" 2>/dev/null)
    lp=$(cat ~/.claude/agents/agent-$slot.lock 2>/dev/null)
    if { [ -n "$lp" ] && kill -0 "$lp" 2>/dev/null; } \
       || [ $(( now_s - $(mtime "$f") )) -lt 600 ]; then
      inhand="$inhand$(basename "$f")
"
    else
      rm -f "$f"
    fi
  done
  inhand=$(printf '%s' "$inhand" | jq -Rsc '[ split("\n")[] | select(length>0) | tonumber ]')

  # c=0 is "no ceiling": total RAM is then the only bound on how many can run.
  max_agents=$(awk -v r=$ramgb -v a=$RAM_PER_AGENT -v c=$MAX_AGENTS_CAP 'BEGIN{m=int(r/a); print (c>0 && m>c?c:m)}')
  # What the ceiling is doing, in words, for the lines that report capacity.
  if [ "$MAX_AGENTS_CAP" -gt 0 ] 2>/dev/null; then capnote=" (LO_MAX_AGENTS=$MAX_AGENTS_CAP)"; else capnote=" (uncapped)"; fi
  slots=$(awk -v m=$max_agents -v b=$busy -v f=$freegb -v a=$RAM_PER_AGENT -v l=$load \
              -v c=$cores -v d=$diskgb -v lf=$LOAD_FACTOR 'BEGIN{
    if (l > c*lf || d < 10) { print 0; exit }
    byram = int(f/a); bycap = m-b; s = (byram<bycap?byram:bycap)
    print (s<0?0:s) }')

  # Every `gh` call below names the repo. Without --repo, gh reads the CALLER's
  # working directory, so a gate run from anywhere but the checkout silently
  # reports on a different repo — and reports it as an empty, healthy board.
  slug=$(git -C "$REPO" remote get-url origin 2>/dev/null \
         | sed -e 's#.*github.com[:/]##' -e 's#\.git$##')

  # --- the world, in one gh call ---
  # NOT filtered by --base: a stacked layer's base is the layer below it, never
  # $BASE, so filtering here made every layer above the first invisible to the
  # gate — it would sit open and unreviewed until a human found it by hand.
  # `.mine` below is what keeps this to the loop's own PRs, and `main` is
  # excluded so a release PR is never mistaken for work.
  # `gh pr list` returns newest first, so a limit that binds silently drops the
  # OLDEST open PRs, and an invisible PR is absent from REGATE, DRAFTS and
  # RESTACK alike — which reads exactly like a clean board.
  PR_LIMIT="${LO_PR_LIMIT:-400}"
  # Keep stderr: a discarded one makes every GATE-ERROR undiagnosable, and this
  # is the call that fails. It is ~5s of GraphQL over every open PR, and GitHub
  # refuses it intermittently while the agents hammer the same API. `jq` decides
  # whether the reply is a board, because `gh` exits 0 on some of these.
  # Three attempts over ~25s, because the failure arrives in clusters rather
  # than singly: api.github.com resolves to a NAT64 address as well as an IPv4
  # one, and while that path is down every call inside the same few seconds
  # times out together. One retry at 5s sat inside one cluster and woke the loop
  # a minute after arming. A wake that costs a tick is worth more than 25s here.
  pr_try=""
  for pr_delay in 0 5 20; do
    [ "$pr_delay" -gt 0 ] && sleep "$pr_delay"
    pr_try=$(gh pr list --repo "$slug" --state open --limit "$PR_LIMIT" \
      --json number,isDraft,mergeable,body,labels,statusCheckRollup,headRefName,baseRefName,author,createdAt 2>&1)
    printf '%s' "$pr_try" | jq -e 'type == "array"' >/dev/null 2>&1 && break
  done
  # A broken gh is worth waking for, but only once it is more than a blip — the
  # wait loop counts them. A single probe still says so and exits.
  if ! printf '%s' "$pr_try" | jq -e 'type == "array"' >/dev/null 2>&1; then
    GATE_ERR="gh pr list failed — $(printf '%s' "$pr_try" | tr '\n' ' ' | cut -c1-200)"
    [ "$MODE" != "wait" ] && echo "GATE-ERROR: $GATE_ERR"
    # The forge being down does not stop mail and the calendar.
    [ "$MODE" != "wait" ] && sweep_due && sweep_line
    return 0
  fi
  prs="$pr_try"

  # And say so if it ever binds again, rather than truncating quietly.
  pr_count=$(printf '%s' "$prs" | jq 'length')
  if [ "$pr_count" -ge "$PR_LIMIT" ]; then
    echo "GATE-WARN: open PRs hit the query limit ($pr_count >= $PR_LIMIT) — the oldest are invisible. Raise LO_PR_LIMIT."
  fi

  verdicts=$(printf '%s' "$prs" | jq -c --arg m "$PR_MARKER" '[ .[] | {
      pr: .number, draft: .isDraft, merge: .mergeable, head: .headRefName,
      base: .baseRefName, author: ((.author.login // "") | ascii_downcase),
      created: (.createdAt // ""),
      mine: ((.body // "") | contains($m)),
      invalid: ([.labels[]?.name] | index("invalid") != null),
      waiting: (((.body // "") | test("(?m)^## Blocked on")) or ([.labels[]?.name] | index("needs human") != null)),
      # Only a real verdict counts. Three things look like one and are not:
      #   ""         a run still QUEUED or IN_PROGRESS. GitHub returns an empty
      #              string here, NOT null, so a `!= null` guard lets it through
      #              and every in-flight check reads as a failure.
      #   CANCELLED  a run superseded by a newer push. A force-push cancels the
      #              runs in flight and starts fresh ones, and the rollup returns
      #              BOTH for the same check name. Cancelled is "no verdict yet",
      #              never "failed" — treating it as failure re-drafts a healthy PR.
      #   SKIPPED / NEUTRAL — never ran, or ran and declined to judge.
      # Both of the first two were found on 26 Aug, when a restack force-pushed
      # five promoted PRs and the gate reported them as failing CI.
      ci: ( [ .statusCheckRollup[]? | select(.conclusion != null and .conclusion != ""
                and .conclusion != "SKIPPED" and .conclusion != "NEUTRAL"
                and .conclusion != "CANCELLED") ] as $c
            | if   ([ $c[] | select((.name // "") | startswith("Test (shard")) ] | length) == 0 then "not-run"
              elif ([ $c[] | select(.conclusion != "SUCCESS") ] | length) > 0 then "failing"
              else "green" end ) } ] | map(select(.base != "main")) | sort_by(.pr)')

  regate=$(printf '%s' "$verdicts" | jq -c --argjson held "$held" --argjson inhand "$inhand" '[ .[]
            | select(.draft==false and .mine)
            | select(.merge=="CONFLICTING" or .ci=="failing")
            | .pr as $p | select($inhand | index($p) | not)
            | .head as $h | select($held | index($h) | not) ]')
  # invalid is deliberately NOT filtered by $held: the label is the only durable
  # record that a reclaim is owed, and steps 2a.1-4 need no slot.
  invalid=$(printf '%s' "$verdicts" | jq -c '[ .[] | select(.invalid and .mine) | .pr ]')
  # .mine matters as much as $held here: a human's draft PR is not the loop's to
  # push commits to.
  # A layer whose base is itself an unpromoted draft is not work: 2c promotes a
  # stack bottom-up, so the model declines it every time and the wake is spent.
  # Seen on 1 Sep: #1088 sat behind #1082 and woke the waiter six times in three
  # minutes, each wake a model turn that decided nothing.
  drafts=$(printf '%s' "$verdicts" | jq -c --argjson held "$held" --argjson inhand "$inhand" '. as $all | [ .[]
            | select(.draft and .mine)
            | .pr as $p | select($inhand | index($p) | not)
            | .head as $h | select($held | index($h) | not)
            | select(.base as $b | ($all | map(select(.head == $b and .draft)) | length) == 0) | .pr ]')

  # A layer whose base is another branch is part of a stack. It appears in DRAFTS
  # like any other draft, but the model cannot review a stack in an arbitrary
  # order — layer 2 is unreadable before layer 1 — so name the base here and let
  # it sort them bottom-up.
  # A stack BOTTOM (base == $BASE) belongs here too: nothing refreshes a layer
  # against $BASE on its own, so a bottom that falls behind blocks its whole
  # stack while every per-PR signal still reads green. Including it hands the
  # RESTACK sweep below a dev...bottom compare, which is the only thing that
  # notices.
  stack=$(printf '%s' "$verdicts" | jq -c --arg b "$BASE" '. as $all | [ .[]
            | select(.mine)
            | select(.base != $b or (.head as $h | ($all | map(select(.base == $h)) | length) > 0))
            | {pr, base, draft, head} ]')

  # A layer goes stale the moment its base layer takes a commit — and NOTHING
  # else here notices. `mergeable` compares the layer against its base and stays
  # MERGEABLE, because being behind is not a conflict. So a fix pass on layer 1
  # silently leaves layers 2..6 built on a head that no longer exists, and the
  # forge refuses to merge the stack while every gate here still reads green.
  # Seen on the HYR2-993 stack: one fix commit on layer 1 put four layers behind.
  #
  # `behind_by` from the compare API is the only signal that says so. One call
  # per layer, and only when a stack exists at all — which is almost never, so
  # the common probe pays nothing. Failures leave the layer out rather than
  # inventing a zero: a restack claimed on a failed lookup is worse than silence.
  restack="[]"
  if [ "$(printf '%s' "$stack" | jq 'length')" -gt 0 ]; then
    restack=$(printf '%s' "$stack" | jq -c '.[] | [.pr, .base, .head] | @tsv' -r | while IFS=$'\t' read -r p b h; do
      # A stack BOTTOM is behind the trunk constantly — the trunk moves all day — and that
      # only blocks a merge where the strict up-to-date rule is on. GitHub says so itself:
      # `mergeStateStatus` reads BEHIND exactly then, and CLEAN when being behind costs
      # nothing. Without this the bottom of every stack sits on RESTACK forever and the
      # waiter wakes the loop on it every probe, which is what it did.
      #
      # Asked per bottom rather than in the bulk list above: `mergeStateStatus` computes
      # mergeability, and adding it to a 400-PR query answers
      # "Resource limits for this query exceeded". A stack is rare, so this costs nothing
      # on the common probe.
      if [ "$b" = "$BASE" ]; then
        ms=$(gh pr view "$p" --repo "$slug" --json mergeStateStatus --jq '.mergeStateStatus' 2>/dev/null)
        [ "$ms" = "BEHIND" ] || continue
      fi
      cmp=$(gh api "repos/$slug/compare/$b...$h" --jq '.behind_by' 2>/dev/null)
      # A non-numeric answer is a failed lookup, and [ -gt ] returns false for it
      # rather than treating it as a number. `case` cannot be used here: bash
      # mis-parses a case pattern's `)` inside a command substitution.
      if [ -n "$cmp" ] && [ "$cmp" -gt 0 ] 2>/dev/null; then
        printf '{"pr":%s,"base":"%s","behind":%s}\n' "$p" "$b" "$cmp"
      fi
    done | jq -s -c '.')
  fi

  # --- human feedback: comments on the loop's PRs that nobody answered ---
  # The agents post through the user's own `gh`, so every comment carries the
  # user's login and the author field can never separate a person from a machine.
  # So the loop marks its OWN instead — every comment it writes contains "🌙" —
  # and an unmarked comment on one of its PRs is a person talking to it.
  #
  # "Already answered" is not a local flag either: the reply carries
  # "ack:<comment-id>", so the record lives on GitHub and survives a deleted
  # cache, a /clear, a restart and a compaction. The id in the ack is what makes
  # it safe — without it, an agent posting its own fix-pass comment would mask a
  # question the user asked while that agent was working.
  #
  # The scan is repo-wide (PRs are issues, so one endpoint covers both), which is
  # what catches a comment on an already-merged PR. It IS limited to PRs the loop
  # opened, because ordinary review chatter between two people on their own PR is
  # not an instruction to a machine.
  #
  # FEEDBACK_LOGINS narrows it further: only those logins steer the loop. Set it
  # when the repo has people who comment but must not dispatch work. Leave it
  # empty and every non-bot login counts.
  since="$FEEDBACK_SINCE"
  win=$(days_ago 14)
  # ISO-8601 sorts lexically, so the later of the two is just the bigger string.
  [ "$win" \> "$since" ] && since="$win"
  cmts=$(gh api "repos/$slug/issues/comments?since=$since&sort=created&direction=desc&per_page=100" \
    --jq '[ .[] | select((.user.type // "") != "Bot")
            | { id, body, who: .user.login, pr: (.issue_url | sub(".*/"; "")) } ]' 2>/dev/null)
  [ -z "$cmts" ] && cmts='[]'
  acked=$(printf '%s' "$cmts" | jq -c '[ .[] | select(.body | test("🌙"))
            | .body | [ scan("ack:([0-9]+)") ] ] | flatten | map(tonumber)')
  pending=$(printf '%s' "$cmts" | jq -c --argjson acked "$acked" --arg allow "$FEEDBACK_LOGINS" '
            ($allow | ascii_downcase | split(",") | map(sub("^ +";"") | sub(" +$";""))
              | map(select(length > 0))) as $who
            | [ .[]
            | select((.body | test("🌙")) | not)
            | select(($who | length) == 0 or ((.who | ascii_downcase) as $w | $who | index($w) != null))
            | .id as $i | select($acked | index($i) | not) ]')

  # SUBMITTED REVIEWS are a second human surface the comments endpoint never
  # returns: a review submitted from the Files-changed tab is not an issue
  # comment, so a reviewer can write twenty of them and the loop sees nothing.
  # Seen on a real run (2026-08-31): 29 reviews in one morning, zero surfaced.
  # There is no repo-wide reviews endpoint, so one GraphQL query sweeps the 100
  # most recently updated open+merged PRs and their last 10 reviews each.
  # A review by the loop cannot exist — agents post plain comments by rule — so
  # the 🌙 test is only a guard. Acks reuse the same ack:<id> comment mechanism
  # (review ids and comment ids are both numeric and never collide in practice).
  # FEEDBACK entries from here carry kind:"review": the tick reads the body via
  # `gh api repos/<slug>/pulls/<pr>/reviews/<id>`, not the comments endpoint.
  rowner=${slug%%/*}; rname=${slug##*/}
  rpending=$(gh api graphql \
    -f owner="$rowner" -f name="$rname" \
    -f query='query($owner:String!,$name:String!){repository(owner:$owner,name:$name){pullRequests(states:[OPEN,MERGED],first:100,orderBy:{field:UPDATED_AT,direction:DESC}){nodes{number reviews(last:10){nodes{databaseId submittedAt bodyText author{login __typename}}}}}}}' \
    --jq '.data.repository.pullRequests.nodes' 2>/dev/null)
  [ -z "$rpending" ] && rpending='[]'
  rpending=$(printf '%s' "$rpending" | jq -c --argjson acked "$acked" \
      --arg allow "$FEEDBACK_LOGINS" --arg since "$since" '
      ($allow | ascii_downcase | split(",") | map(sub("^ +";"") | sub(" +$";""))
        | map(select(length > 0))) as $who
      | [ .[] | .number as $n | .reviews.nodes[]?
      | select((.bodyText // "") != "")
      | select(.author != null and .author.__typename != "Bot")
      | select(.submittedAt >= $since)
      | select((.bodyText | test("🌙")) | not)
      | select(($who | length) == 0 or ((.author.login | ascii_downcase) as $w | $who | index($w) != null))
      | .databaseId as $i | select($acked | index($i) | not)
      | { id: $i, who: .author.login, pr: ($n|tostring), kind: "review" } ]' 2>/dev/null)
  [ -z "$rpending" ] && rpending='[]'
  pending=$(jq -c -n --argjson a "$pending" --argjson b "$rpending" '$a + $b')

  # The acked-scan above reads ONE page of the newest repo-wide comments. On a
  # busy day the loop writes hundreds, so an ack posted hours ago rolls off the
  # page and its review resurfaces as unanswered — seen flapping on a real run
  # (2026-08-31). Pending is tiny, so verify each candidate against ITS OWN
  # PR's comments, where the ack lives and cannot be crowded out.
  if [ "$(printf '%s' "$pending" | jq 'length')" -gt 0 ]; then
    # id:pr pairs carry no spaces, so the for-loop word-split is safe — the
    # first version iterated whole JSON rows, and comment bodies shattered.
    ackdrop=""
    for pair in $(printf '%s' "$pending" | jq -r '.[] | "\(.id):\(.pr)"'); do
      vid=${pair%%:*}; vpr=${pair##*:}
      if gh api "repos/$slug/issues/$vpr/comments?per_page=100" \
           --jq '.[].body' 2>/dev/null | grep -q "ack:$vid"; then
        ackdrop="$ackdrop $vid"
      fi
    done
    if [ -n "$ackdrop" ]; then
      pending=$(printf '%s' "$pending" | jq -c --arg drop "$ackdrop" \
        '($drop | split(" ") | map(select(length>0))) as $d
         | [ .[] | select((.id|tostring) as $i | ($d | index($i)) | not) ]')
    fi
  fi

  feedback='[]'
  if [ "$(printf '%s' "$pending" | jq 'length')" -gt 0 ]; then
    # Only now is it worth asking which PRs are the loop's. Ask per PR, not via
    # a newest-100 page: a review on an old PR joined against that page matched
    # nothing and was dropped without a trace — Studioraodev's blocker review on
    # #964 sat unanswered for hours that way (31 Aug). Pending is tiny, so one
    # `gh pr view` per unique PR is cheap, reaches merged PRs, and the 🌙 body
    # test still keeps a human's own PR out.
    minepr='[]'
    for vpr in $(printf '%s' "$pending" | jq -r '[.[].pr] | unique | .[]'); do
      row=$(gh pr view "$vpr" --repo "$slug" --json number,body,state 2>/dev/null \
        | jq -c --arg m "$PR_MARKER" 'select((.body // "") | contains($m))
            | { pr: (.number|tostring), state }')
      [ -n "$row" ] && minepr=$(printf '%s' "$minepr" | jq -c --argjson r "$row" '. + [$r]')
    done
    feedback=$(printf '%s' "$pending" | jq -c --argjson mine "$minepr" '[ .[]
      | .pr as $p | ($mine[] | select(.pr == $p)) as $m
      | { pr: ($p|tonumber), id, who, kind: (.kind // "comment"), state: $m.state } ]')
  fi
  n_feedback=$(printf '%s' "$feedback" | jq 'length')

  n_regate=$(printf '%s' "$regate"  | jq 'length')
  n_invalid=$(printf '%s' "$invalid" | jq 'length')
  n_drafts=$(printf '%s' "$drafts"  | jq 'length')
  n_stack=$(printf '%s' "$stack"   | jq 'length')
  n_restack=$(printf '%s' "$restack" | jq 'length')

  # --- adopted PRs (LO_ADOPT_AUTHORS) ---
  # Candidates come from the one board read above; only they cost a second call,
  # for their reviews and comments. "Reviewed" means a formal review, or a
  # comment, from a person who is not the author, not a bot and not this loop.
  # The loop's own review carries `adopt-review` in its marker line, so it
  # counts once and the PR is never reviewed twice.
  adopt='[]'
  if [ -n "$ADOPT_AUTHORS" ]; then
    cands=$(printf '%s' "$verdicts" | jq -c --arg who "$ADOPT_AUTHORS" --arg since "$ADOPT_SINCE" \
        --argjson held "$held" --argjson inhand "$inhand" '
        ($who | ascii_downcase | split(",") | map(gsub("^ +| +$";"")) | map(select(length>0))) as $w
        | [ .[] | select(.mine | not) | select(.author as $a | $w | index($a) != null)
            | select($since == "" or .created >= $since)
            | .pr as $p | select($inhand | index($p) | not)
            | .head as $h | select($held | index($h) | not) ]')
    for row in $(printf '%s' "$cands" | jq -c '.[]'); do
      n=$(printf '%s' "$row" | jq -r .pr)
      au=$(printf '%s' "$row" | jq -r .author)
      detail=$(gh pr view "$n" --repo "$slug" --json reviews,comments 2>/dev/null) || continue
      reviewed=$(printf '%s' "$detail" | jq -r --arg au "$au" --arg m "$PR_MARKER" '
        ([ .reviews[]? | select((.author.login // "" | ascii_downcase) != $au)
             | select((.author.login // "") | test("\\[bot\\]$") | not) ]
         + [ .comments[]? | select((.author.login // "" | ascii_downcase) != $au)
             | select((.author.login // "") | test("\\[bot\\]$|^(github-actions|linear|blacksmith-sh|traces-github-app)"; "i") | not)
             | select((.body // "") | contains($m) | not) ]) | length > 0')
      loopreviewed=$(printf '%s' "$detail" | jq -r --arg m "$PR_MARKER adopt-review" \
        '[ .comments[]? | select((.body // "") | contains($m)) ] | length > 0')
      needs=$(printf '%s' "$row" | jq -c --arg r "$reviewed" --arg l "$loopreviewed" '
        [ (if .merge == "CONFLICTING" then "mergeable" else empty end),
          (if .ci == "failing" then "ci" else empty end),
          (if $r == "false" and $l == "false" then "review" else empty end) ]')
      [ "$needs" = "[]" ] && continue
      adopt=$(printf '%s' "$adopt" | jq -c --argjson r "$row" --argjson nd "$needs" \
        '. + [ { pr: $r.pr, head: $r.head, author: $r.author, merge: $r.merge, ci: $r.ci, needs: $nd } ]')
    done
  fi
  n_adopt=$(printf '%s' "$adopt" | jq 'length')

  # --- Slack: channels and open threads that moved since the tick's last ack ---
  # Read at any slot count: a ticket order in a thread needs no agent.
  slack='[]'
  if [ "$SLACK_ON" = 1 ]; then
    if [ -x "$AC" ] || command -v "$AC" >/dev/null 2>&1; then
      slack_read
      slack_seen=$(cat "$SLACK_SEEN" 2>/dev/null); [ -n "$slack_seen" ] || slack_seen='{}'
      slack=$(jq -nc --argjson n "$SLACK_SIGS" --argjson s "$slack_seen" '
        [ $n | to_entries[] | select($s[.key] != .value)
          | (.key | split("/")) as $p
          | if ($p | length) > 1 then {channel: $p[0], thread: $p[1]} else {channel: $p[0]} end ]' \
        2>/dev/null || echo '[]')
      [ -n "$SLACK_ERR" ] && notes="$notes${notes:+; }$SLACK_ERR"
    else
      notes="$notes${notes:+; }agent-codemode CLI not found; Slack check skipped"
    fi
  fi
  n_slack=$(printf '%s' "$slack" | jq 'length')
  slacksig=$(printf '%s' "$slack" | hash16)
  prevslack=$(cat "$SLSTATE" 2>/dev/null)

  # --- Inbox watch: which of emails, meetings, calls moved since the last ack ---
  inbox='[]'
  if [ -n "$INBOX_EMAIL" ]; then
    if [ -x "$AC" ] || command -v "$AC" >/dev/null 2>&1; then
      inbox_read
      inbox_seen=$(cat "$INBOX_SEEN" 2>/dev/null); [ -n "$inbox_seen" ] || inbox_seen='{}'
      inbox=$(jq -nc --argjson n "$INBOX_SIGS" --argjson s "$inbox_seen" \
        '[ $n | to_entries[] | select($s[.key] != .value) | .key ]' 2>/dev/null || echo '[]')
      [ -n "$INBOX_ERR" ] && notes="$notes${notes:+; }$INBOX_ERR"
    fi
  fi
  n_inbox=$(printf '%s' "$inbox" | jq 'length')
  inboxsig=$(printf '%s' "$inbox" | hash16)
  previnbox=$(cat "$ISTATE" 2>/dev/null)

  # --- Schedules: jobs whose run time has come (lo-schedule.sh) ---
  # Read at any slot count, so a NO line can say a job waits for a slot. A peek
  # does not fetch: it reads origin/<BASE> as the last fetch left it.
  sched='[]'
  sjson=$("$SELF/lo-schedule.sh" due $([ "$PEEK" = 1 ] && echo --no-fetch) 2>&1)
  if printf '%s' "$sjson" | jq -e '.due | type == "array"' >/dev/null 2>&1; then
    sched=$(printf '%s' "$sjson" | jq -c '.due')
    serr=$(printf '%s' "$sjson" | jq -r '.errors | join("; ")')
    [ -n "$serr" ] && notes="$notes${notes:+; }schedules: $serr"
  else
    notes="$notes${notes:+; }schedules unreadable: $(printf '%s' "$sjson" | tail -1 | cut -c1-120)"
  fi
  n_sched=$(printf '%s' "$sched" | jq 'length')
  schedsig=$(printf '%s' "$sched" | hash16)
  prevsched=$(cat "$SCSTATE" 2>/dev/null)

  # --- Linear ready column, but only when a slot could take it ---
  # Cheap pre-filter (assignee tier + not archived); the model still applies the
  # judgment drop-rules and dedups against open PRs. New candidate -> hash change.
  todo_ids=""
  todo_source=""
  if [ "$slots" -gt 0 ]; then
    if [ -x "$AC" ] || command -v "$AC" >/dev/null 2>&1; then
      LINEAR_ERR=""
      todo_ids=$(linear_ids Todo)
      [ -n "$todo_ids" ] && todo_source=Todo
      # Backlog is opt-in AND strictly second. A Todo ticket outranks a Backlog
      # one at any priority, because somebody deliberately moved it to Todo — so
      # the fall happens only when Todo yields nothing eligible at all. Reading
      # it here rather than leaving it to the model is what lets the gate WAKE
      # on backlog-only work: the wake conditions below all need a non-empty
      # candidate list, so a backlog pass the gate never saw could not run on an
      # otherwise idle night.
      if [ -z "$todo_ids" ] && [ "$ALLOW_BACKLOG" = 1 ] && [ -z "$LINEAR_ERR" ]; then
        todo_ids=$(linear_ids Backlog)
        [ -n "$todo_ids" ] && todo_source=Backlog
      fi
      [ -n "$LINEAR_ERR" ] && notes="$notes${notes:+; }$LINEAR_ERR"
    else
      notes="$notes${notes:+; }agent-codemode CLI not found; Linear check skipped"
    fi
    # Subtract the ids the model has already judged un-runnable. They live in
    # QUEUE's `skipped` list, written by the last rebuild. Without this a ticket
    # the loop will never take stays in todo_ids forever, and the rule below
    # ("ids present AND the world hash moved") then fires on every commit, CI
    # transition and PR comment that the running agents produce — a wake every
    # couple of minutes with nothing to do. Seen on a real run with HYR2-972.
    if [ -n "$todo_ids" ] && [ -f "$QUEUE" ]; then
      skipped=$(jq -r '[.skipped[]?.id] | join(",")' "$QUEUE" 2>/dev/null)
      if [ -n "$skipped" ]; then
        todo_ids=$(printf '%s' "$todo_ids" | tr ',' '\n' \
          | grep -vxF -f <(printf '%s' "$skipped" | tr ',' '\n') \
          | paste -sd, - )
      fi
    fi
  fi

  # queue staleness only matters when there is somewhere to put an agent
  queue_stale=no
  if [ "$slots" -gt 0 ]; then
    if [ ! -f "$QUEUE" ]; then queue_stale=yes
    else
      built=$(jq -r '.builtAt // ""' "$QUEUE" 2>/dev/null)
      age=$(( $(date +%s) - $(iso_epoch "${built%.*}Z" 2>/dev/null || echo 0) ))
      [ "$age" -gt 1800 ] && queue_stale=yes
    fi
  fi

  # --- did anything change since last tick? (PR verdicts + eligible ticket ids) ---
  hash=$(printf '%s|%s|%s' "$verdicts" "$todo_ids" "$feedback" | hash16)
  prev=$(cat "$STATE" 2>/dev/null)

  # A fingerprint of the DRAFTS only, so a draft wakes the loop when something
  # about that draft moved and not when the world moved around it. It carries
  # the verdict fields a draft is judged on, not just the numbers: a draft whose
  # CI turned green or whose `mergeable` flipped must still wake, or a PR that
  # became promotable would sit unnoticed until the next unrelated change.
  # A held draft (a `## Blocked on` notice or the `needs human` label) waits for a
  # person, so its verdict moving is not news: a `dev` merge flips every
  # `mergeable` and would wake the loop for drafts it must leave alone. It still
  # shows on the DRAFTS line, so a wake for anything else still reviews it.
  draftsig=$(printf '%s' "$verdicts" | jq -Sc --argjson d "$drafts" \
      '[ .[] | select(.pr as $p | $d | index($p)) | select(.waiting | not) | {pr,draft,merge,ci,base} ]' \
      2>/dev/null)
  prevdrafts=$(cat "$DSTATE" 2>/dev/null)
  # A draft is news when it is new on the list or its verdict moved. A list that
  # only got shorter is not: the tick just dispatched one, and waking for that
  # costs a tick with nothing to do after every single dispatch.
  drafts_news=$(jq -nc --argjson n "${draftsig:-[]}" --arg p "$prevdrafts" \
    '($p | try fromjson catch []) as $prev | [ $n[] | select(. as $e | $prev | index($e) | not) ] | length' \
    2>/dev/null || echo 1)

  # The same fingerprint for the de-gate list, over the fields a REGATE entry is
  # judged on. A PR that goes red or starts conflicting still wakes the model at
  # once, because its verdict changed; only an entry already seen and unchanged
  # stops re-waking.
  regatesig=$(printf '%s' "$regate" | jq -Sc '[ .[] | {pr,draft,merge,ci,invalid} ]' \
      2>/dev/null | hash16)
  prevregate=$(cat "$RSTATE" 2>/dev/null)
  adoptsig=$(printf '%s' "$adopt" | jq -Sc '[ .[] | {pr,merge,ci,needs} ]' 2>/dev/null | hash16)
  prevadopt=$(cat "$ASTATE" 2>/dev/null)

  # --- decide ---
  work=no
  # Still acted on at slots 0 — a de-gate needs no agent — but only once per
  # change. See RSTATE above for why the unconditional form spun.
  [ "$n_regate"  -gt 0 ] && [ "$regatesig" != "$prevregate" ] && work=yes
  [ "$n_invalid" -gt 0 ] && work=yes
  # Feedback needs no slot to act on: a reply, a re-draft and a follow-up ticket
  # are all free. Only the rework behind it needs an agent.
  # Once per change, like REGATE. A comment the tick cannot answer (a hook
  # denies the post, a ticket write fails) stays on the FEEDBACK line, and the
  # unconditional form then wakes the waiter on every probe, one tick a minute.
  fbsig=$(printf '%s' "$feedback" | hash16)
  prevfb=$(cat "$FSTATE" 2>/dev/null)
  [ "$n_feedback" -gt 0 ] && [ "$fbsig" != "$prevfb" ] && work=yes
  # Slack wakes once per change. The tick clears it with --slack-ack.
  [ "$n_slack" -gt 0 ] && [ "$slacksig" != "$prevslack" ] && work=yes
  [ "$n_inbox" -gt 0 ] && [ "$inboxsig" != "$previnbox" ] && work=yes
  # A due job is agent work: it waits for a slot, and wakes once per change.
  [ "$slots" -gt 0 ] && [ "$n_sched" -gt 0 ] && [ "$schedsig" != "$prevsched" ] && work=yes
  # A draft already surfaced on a prior probe is not work again on its own — only
  # a draft whose verdict actually changed since the state file was last saved.
  # Without the hash check, a draft the model has already looked at and can do
  # nothing more with (still `CONFLICTING` against a base that has not moved,
  # blocked on another PR to merge first) reports "work=yes" on every probe
  # forever: `--wait` never sleeps its `WAIT_INTERVAL`, and instead re-runs the
  # full forge-reading probe back to back. Seen for real on HYR2-1339's stack:
  # a held draft woke the waiter roughly every 28s (the probe's own runtime)
  # for as long as it sat there.
  [ "$slots" -gt 0 ] && [ "$n_drafts" -gt 0 ] && [ "${drafts_news:-1}" -gt 0 ] && work=yes
  # An adopted PR is agent work, so it waits for a slot like a draft does.
  [ "$slots" -gt 0 ] && [ "$n_adopt" -gt 0 ] && [ "$adoptsig" != "$prevadopt" ] && work=yes
  # A stale queue is only work when Linear has something to rebuild it FROM.
  # Without this the loop wakes every 30 minutes on an empty ready column, to
  # rebuild an empty file into an identical empty file.
  [ "$slots" -gt 0 ] && [ "$queue_stale" = yes ] && [ -n "$todo_ids" ] && work=yes
  [ "$slots" -gt 0 ] && [ -n "$todo_ids" ] && [ "$hash" != "$prev" ] && work=yes
  # A note is NOT work. A reap frees RAM, which the slot count already shows; an
  # hourly `dev` refresh matters only through what it breaks, which REGATE finds
  # on its own; and a refused refresh would otherwise wake the model every hour
  # for the rest of the night. The note still reaches the user either way — the
  # block prints it below, and the NO line carries it.

  if [ "$work" = no ]; then
    # Say WHY there is nothing to wake for. A bare "NO" hides the difference
    # between "the board is empty" and "the board has work the machine cannot
    # start", and those two want opposite responses from the user.
    # No extra calls: every number below is already measured above.
    if [ "$slots" -eq 0 ]; then
      bycap=$(( max_agents - busy ))
      if awk -v l=$load -v c=$cores -v lf=$LOAD_FACTOR 'BEGIN{exit !(l > c*lf)}'; then
        why="load $load over $(awk -v c=$cores -v lf=$LOAD_FACTOR 'BEGIN{printf "%.1f", c*lf}')"
      elif [ "$diskgb" -lt 10 ]; then
        why="disk ${diskgb}gb free, under 10"
      elif [ "$bycap" -le 0 ]; then
        why="all $max_agents agent slots busy$capnote"
      else
        why="ram ${freegb}gb free, ${RAM_PER_AGENT}gb per agent, busy=$busy"
      fi
      why="no slot: $why"
      [ "$n_drafts" -gt 0 ] && why="$why; $n_drafts draft(s) waiting"
      [ "$n_adopt" -gt 0 ] && why="$why; $n_adopt adopted PR(s) waiting"
      [ "$n_sched" -gt 0 ] && why="$why; $n_sched schedule(s) due"
      # Linear is queried only when a slot exists, so at slots=0 a new ticket is
      # invisible to this gate by design. Say so, or the NO reads as "no work".
      why="$why; linear not read"
    else
      why="slots=$slots, nothing to take"
      [ "$n_drafts" -eq 0 ] && why="$why; no drafts"
      if [ -z "$todo_ids" ]; then
        why="$why; linear Todo empty for ${TIER1:-<no tier set>}"
        [ "$ALLOW_UNASSIGNED" = 1 ] || why="$why, unassigned off"
        [ "$ALLOW_BACKLOG" = 1 ] || why="$why, backlog off"
      elif [ "$hash" = "$prev" ]; then why="$why; same todo ids as last tick"; fi
    fi
    NOREASON="$why"
    [ -n "$notes" ] && NOREASON="$NOREASON; notes: $notes"
    [ "$hash" != "$prev" ] && NOREASON="$NOREASON; board changed, nothing actionable"

    # A changed hash with no work is not work. The fixed-interval mode still
    # shows the block below — the model is awake anyway and the numbers are
    # free. The waiter must not exit on it: CI flipping on a draft it has no
    # slot for would wake the model every few minutes, which is the whole cost
    # --wait exists to remove.
    #
    # Only a probe the MODEL saw may move the state forward. In --wait the
    # quiet probes leave it alone, so a world that changed while the machine
    # was full is still "changed" on the probe that finally wakes.
    [ "$MODE" != once ] && return 1
    if [ "$hash" = "$prev" ]; then
      save_state "$hash"
      save_drafts_state "$draftsig"
      save_regate_state "$regatesig"
      save_adopt_state "$adoptsig"
      [ "$PEEK" = 1 ] || printf '%s' "$slacksig" > "$SLSTATE"
      [ "$PEEK" = 1 ] || printf '%s' "$fbsig" > "$FSTATE"
      [ "$PEEK" = 1 ] || printf '%s' "$inboxsig" > "$ISTATE"
      [ "$PEEK" = 1 ] || printf '%s' "$schedsig" > "$SCSTATE"
      return 1
    fi
  fi

  save_state "$hash"
  save_drafts_state "$draftsig"
  save_regate_state "$regatesig"
  save_adopt_state "$adoptsig"
  [ "$PEEK" = 1 ] || printf '%s' "$slacksig" > "$SLSTATE"
  [ "$PEEK" = 1 ] || printf '%s' "$fbsig" > "$FSTATE"
  [ "$PEEK" = 1 ] || printf '%s' "$inboxsig" > "$ISTATE"
  [ "$PEEK" = 1 ] || printf '%s' "$schedsig" > "$SCSTATE"

  # --- otherwise: everything the model needs, nothing it does not ---
  echo "load1=$load freegb=$freegb diskgb=$diskgb busy=$busy slots=$slots max=$max_agents$capnote"
  [ -n "$notes" ]           && echo "notes: $notes"
  [ "$hash" != "$prev" ]    && echo "world-changed: yes"
  [ "$n_regate"  -gt 0 ]    && echo "REGATE: $regate"
  [ "$n_feedback" -gt 0 ]   && echo "FEEDBACK: $feedback"
  [ "$n_slack" -gt 0 ]      && echo "SLACK: $slack"
  if [ "$n_slack" -gt 0 ] && [ "$PEEK" != 1 ]; then
    printf '%s' "$slack" | jq -c '[ .[] | if .thread then "\(.channel)/\(.thread)" else .channel end ]' > "$SLACK_SHOWN"
  fi
  [ "$n_inbox" -gt 0 ]      && echo "INBOX: $inbox"
  [ "$n_inbox" -gt 0 ] && [ "$PEEK" != 1 ] && printf '%s' "$inbox" > "$INBOX_SHOWN"
  [ "$n_invalid" -gt 0 ]    && echo "INVALID: $invalid"
  [ "$n_drafts"  -gt 0 ]    && echo "DRAFTS: $drafts"
  [ "$n_stack"   -gt 0 ]    && echo "STACK: $stack"
  [ "$n_restack" -gt 0 ]    && echo "RESTACK: $restack"
  [ "$n_adopt"   -gt 0 ]    && echo "ADOPT: $adopt"
  [ "$n_sched"   -gt 0 ]    && echo "SCHEDULES-DUE: $sched"
  [ "$slots" -gt 0 ] && [ -n "$todo_ids" ] && echo "TODO-CANDIDATES: $todo_ids (from ${todo_source:-Todo})"
  [ "$queue_stale" = yes ]  && echo "queue: stale, rebuild before 2d"
  sweep_due && sweep_line
  return 0
}

# seconds -> "45s" / "12m", so a short test does not report "0m"
dur() { [ "$1" -lt 60 ] && echo "${1}s" || echo "$(( $1 / 60 ))m"; }

# --- one probe, the fixed-interval mode ---
if [ "$1" != "--wait" ]; then
  probe || { echo "NO - $NOREASON"; sweep_due && sweep_line; }
  exit 0
fi

# --- block until there is work, the event-driven mode ---
# Print a heartbeat when the CAUSE changes, and once every 10 minutes anyway.
# The dedup key drops the digits: load and free memory drift on every probe, so
# a literal comparison prints every line and the trace is unreadable. What the
# user needs to see is "still the load" turning into "still the ram", plus a
# pulse often enough to prove the waiter is alive.
MODE=wait
[ -n "$2" ] && WAIT_MAX="$2"
started=$(date +%s)
echo "waiting for work - probe every ${WAIT_INTERVAL}s, give up after $(dur $WAIT_MAX)"
lastkey=""; lastprint=0; gate_errs=0
while :; do
  if probe; then
    if [ -z "$GATE_ERR" ]; then
      echo "--- woke after $(dur $(( $(date +%s) - started ))) ---"
      exit 0
    fi
    # A forge that cannot be read is not work. Waking on one costs a tick and
    # hands the model nothing to act on: `probe` has already tried three times,
    # and a hand-run `gh` a minute later succeeds every time. api.github.com
    # resolves to a NAT64 address as well as an IPv4 one, and outages on that
    # path outlast any retry window worth putting inside a probe. So count them
    # instead: GATE_ERR_WAKE probes in a row is an outage a person should see.
    gate_errs=$(( gate_errs + 1 ))
    [ "$gate_errs" -eq 1 ] && echo "$(date -u +%H:%MZ) forge unreadable, still waiting - $GATE_ERR"
    if [ "$gate_errs" -ge "$GATE_ERR_WAKE" ]; then
      echo "GATE-ERROR: $GATE_ERR"
      echo "--- woke after $(dur $(( $(date +%s) - started ))) ---"
      exit 0
    fi
  else
    gate_errs=0
    key=$(printf '%s' "$NOREASON" | tr -d '0-9.')
    if [ "$key" != "$lastkey" ] || [ $(( $(date +%s) - lastprint )) -ge 600 ]; then
      echo "$(date -u +%H:%MZ) NO - $NOREASON"
      lastkey="$key"; lastprint=$(date +%s)
    fi
  fi
  now=$(date +%s)
  # The hour is up and nothing else woke the model: wake for the sweep alone,
  # unless one such wake went unanswered in the last SWEEP_REWAKE seconds.
  if sweep_due && [ $(( now - $(cat "$SWEEP_SHOWN" 2>/dev/null || echo 0) )) -ge "$SWEEP_REWAKE" ]; then
    printf '%s' "$now" > "$SWEEP_SHOWN"
    sweep_line
    echo "--- sweep due after $(dur $(( now - started ))) ---"
    exit 0
  fi
  if [ $(( now - started )) -ge "$WAIT_MAX" ]; then
    # Never wait forever. A bounded waiter that dies costs one idle turn; an
    # unbounded one that dies costs the whole night.
    sweep_due && sweep_line
    echo "--- still nothing after $(dur $(( now - started ))), re-arm ---"
    exit 0
  fi
  sleep "$WAIT_INTERVAL"
done
