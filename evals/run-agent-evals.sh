#!/usr/bin/env bash
# run-agent-evals.sh runs optional, maintainer-only real-agent evaluations of the
# fast-track-ai workflow through the Kiro adapter in disposable repositories.
# It is never called by run-evals.sh and never gates it.
#
# Usage: run-agent-evals.sh <selector> [--model MODEL] [--effort EFFORT]
#                           [--timeout SECONDS] [--keep-dir DIR]
# Selectors: compat revision approval failed-validation material-change resume all
# Environment defaults: FAST_TRACK_AI_AGENT_MODEL, FAST_TRACK_AI_AGENT_EFFORT,
#   FAST_TRACK_AI_AGENT_TIMEOUT (seconds per turn, default 900), KIRO_CLI (default kiro-cli).
#
# Each scenario prints one line: RESULT: <scenario> <pass|fail|inconclusive|prerequisite-unavailable>: <reason>
# Exit codes: 0 no assertion failed (pass, inconclusive, or prerequisite-unavailable),
#             1 at least one scenario failed an assertion, 2 usage error.
set -euo pipefail

repo_root="$(cd "$(dirname "$0")/.." && pwd)"
agent_dir="$repo_root/evals/agent"
adapter="$agent_dir/kiro-adapter.sh"
fixtures="$agent_dir/fixtures"
init_script="$repo_root/skills/fast-track-ai-init/scripts/fast-track-ai-init.sh"
index_script="$repo_root/skills/fast-track-ai-init/scripts/fast-track-ai-index.sh"
gate="$repo_root/skills/fast-track-ai-spec/scripts/fast-track-ai-gate.sh"

kiro_cli="${KIRO_CLI:-kiro-cli}"
model="${FAST_TRACK_AI_AGENT_MODEL:-}"
effort="${FAST_TRACK_AI_AGENT_EFFORT:-}"
timeout_seconds="${FAST_TRACK_AI_AGENT_TIMEOUT:-900}"
keep_dir=""
selector=""
all_scenarios="compat revision approval failed-validation material-change resume"
# Scenarios that need a resumed headless session with a subsequent prompt, or a
# material decision, run only after the compat spike reports `supported`.
continuation_scenarios="revision approval material-change"

usage() {
  echo "ERROR: $1" >&2
  echo "Usage: run-agent-evals.sh <compat|revision|approval|failed-validation|material-change|resume|all> [--model MODEL] [--effort EFFORT] [--timeout SECONDS] [--keep-dir DIR]" >&2
  exit 2
}

while [ $# -gt 0 ]; do
  case "$1" in
    --model) model="${2:-}"; shift 2;;
    --effort) effort="${2:-}"; shift 2;;
    --timeout) timeout_seconds="${2:-}"; shift 2;;
    --keep-dir) keep_dir="${2:-}"; [ -n "$keep_dir" ] || usage "--keep-dir needs a directory"; shift 2;;
    -h|--help) usage "help requested";;
    -*) usage "unknown option: $1";;
    *) [ -z "$selector" ] || usage "only one selector is allowed"; selector="$1"; shift;;
  esac
done

[ -n "$selector" ] || usage "a selector is required"
case "$timeout_seconds" in ''|*[!0-9]*) usage "timeout must be a positive integer: $timeout_seconds";; esac
[ "$timeout_seconds" -gt 0 ] || usage "timeout must be a positive integer: $timeout_seconds"
if [ "$selector" = "all" ]; then
  selected="$all_scenarios"
else
  case " $all_scenarios " in *" $selector "*) selected="$selector";; *) usage "unknown selector: $selector";; esac
fi

if [ -n "$keep_dir" ]; then
  mkdir -p "$keep_dir"
  diag_root="$(cd "$keep_dir" && pwd)"
else
  tmp_base="${TMPDIR:-/tmp}"
  diag_root="$(mktemp -d "${tmp_base%/}/fast-track-ai-agent-evals.XXXXXX")"
fi

count_pass=0
count_fail=0
count_inconclusive=0
count_prereq=0
retained=0

finish() {
  echo "SUMMARY: pass=$count_pass fail=$count_fail inconclusive=$count_inconclusive prerequisite-unavailable=$count_prereq"
  if [ "$retained" -eq 0 ] && [ -z "$keep_dir" ]; then
    rm -rf "$diag_root"
  else
    echo "DIAGNOSTICS ROOT: $diag_root"
  fi
  [ "$count_fail" -eq 0 ] || exit 1
  exit 0
}

# record_result <scenario> <classification> <reason>
record_result() {
  local scenario="$1" classification="$2" reason="$3" scenario_dir
  echo "RESULT: $scenario $classification: $reason"
  case "$classification" in
    pass) count_pass=$((count_pass + 1));;
    fail) count_fail=$((count_fail + 1));;
    inconclusive) count_inconclusive=$((count_inconclusive + 1));;
    prerequisite-unavailable) count_prereq=$((count_prereq + 1));;
  esac
  scenario_dir="$diag_root/$scenario"
  if [ -d "$scenario_dir" ]; then
    jq -n -c --arg scenario "$scenario" --arg result "$classification" --arg reason "$reason" \
      --arg model "$model" --arg effort "$effort" --argjson timeout "$timeout_seconds" \
      '{scenario: $scenario, result: $result, reason: $reason, model: $model, effort: $effort, timeoutSeconds: $timeout}' >"$scenario_dir/result.json"
    if [ "$classification" = "pass" ] && [ -z "$keep_dir" ]; then
      rm -rf "$scenario_dir"
    else
      retained=1
      echo "DIAGNOSTICS: $scenario $scenario_dir"
    fi
  fi
}

prerequisite_reason() {
  command -v "$kiro_cli" >/dev/null 2>&1 || { echo "Kiro CLI not found: $kiro_cli"; return; }
  for tool in jq rsync shasum git; do
    command -v "$tool" >/dev/null 2>&1 || { echo "required tool not found: $tool"; return; }
  done
  "$kiro_cli" whoami >/dev/null 2>&1 </dev/null || { echo "Kiro CLI is not authenticated ($kiro_cli whoami failed); run kiro-cli login"; return; }
  echo ""
}

missing_prerequisite="$(prerequisite_reason)"
if [ -n "$missing_prerequisite" ]; then
  for selected_scenario in $selected; do
    record_result "$selected_scenario" prerequisite-unavailable "$missing_prerequisite"
  done
  finish
fi

# ---------------------------------------------------------------------------
# Per-scenario assertion state. Verdicts come only from checkpoints, method
# artifacts, frontmatter, task state, command outcomes, and recorded actions.

s_fail_count=0
s_inconclusive_count=0
s_pass_count=0
s_first_fail=""
s_first_inconclusive=""
s_prereq=""

reset_assertions() {
  s_fail_count=0; s_inconclusive_count=0; s_pass_count=0
  s_first_fail=""; s_first_inconclusive=""; s_prereq=""
}

assert_ok() {
  s_pass_count=$((s_pass_count + 1)); echo "PASS $1" >>"$sdir/assertions.log"
}

assert_bad() {
  s_fail_count=$((s_fail_count + 1)); echo "FAIL $1" >>"$sdir/assertions.log"
  [ -n "$s_first_fail" ] || s_first_fail="$1"
}

assert_unknown() {
  s_inconclusive_count=$((s_inconclusive_count + 1)); echo "INCONCLUSIVE $1" >>"$sdir/assertions.log"
  [ -n "$s_first_inconclusive" ] || s_first_inconclusive="$1"
}

verdict() {
  local scenario="$1"
  if [ -n "$s_prereq" ]; then
    record_result "$scenario" prerequisite-unavailable "$s_prereq"
  elif [ "$s_fail_count" -gt 0 ]; then
    record_result "$scenario" fail "$s_first_fail ($s_fail_count failed, $s_inconclusive_count inconclusive; see assertions.log)"
  elif [ "$s_inconclusive_count" -gt 0 ]; then
    record_result "$scenario" inconclusive "$s_first_inconclusive ($s_inconclusive_count inconclusive; see assertions.log)"
  else
    record_result "$scenario" pass "$s_pass_count assertions passed"
  fi
}

# prepare_workspace <scenario> <method|plain>
prepare_workspace() {
  local scenario="$1" kind="$2"
  sdir="$diag_root/$scenario"
  rm -rf "$sdir"
  mkdir -p "$sdir"
  ws="$sdir/workspace"
  evidence="$sdir/evidence"
  mkdir -p "$ws"
  : >"$sdir/assertions.log"
  if [ "$kind" = "method" ]; then
    "$init_script" "$ws" >/dev/null
    if [ -d "$fixtures/$scenario/workspace" ]; then
      rsync -a "$fixtures/$scenario/workspace/" "$ws/"
    fi
    "$index_script" "$ws" >/dev/null
    mkdir -p "$ws/.kiro/skills"
    for skill in "$repo_root"/skills/fast-track-ai-*; do
      cp -R "$skill" "$ws/.kiro/skills/"
    done
  fi
  git -C "$ws" init -q
  printf '.kiro/\n' >>"$ws/.git/info/exclude"
  git -C "$ws" add -A
  git -C "$ws" -c user.name=fast-track-ai-eval -c user.email=eval@example.invalid commit -q --allow-empty -m "fixture baseline"
}

run_turns() {
  local scenario="$1"
  adapter_args=(--workspace "$ws" --turns-dir "$fixtures/$scenario/turns" --out "$evidence" --timeout "$timeout_seconds")
  [ -n "$model" ] && adapter_args+=(--model "$model")
  [ -n "$effort" ] && adapter_args+=(--effort "$effort")
  adapter_rc=0
  KIRO_CLI="$kiro_cli" "$adapter" "${adapter_args[@]}" >"$sdir/adapter.log" 2>&1 || adapter_rc=$?
  [ "$adapter_rc" -eq 0 ] || assert_unknown "adapter exited $adapter_rc"
  return "$adapter_rc"
}

turn_field() {
  jq -r --argjson n "$1" --arg field "$2" 'select(.turn == $n) | .[$field] // empty | tostring' "$evidence/turns.jsonl" 2>/dev/null || true
}

# require_turns <count>: every turn up to count succeeded; otherwise records why.
require_turns() {
  n=1
  while [ "$n" -le "$1" ]; do
    outcome="$(turn_field "$n" outcome)"
    case "$outcome" in
      success) ;;
      "") assert_unknown "turn $n did not run"; return 1;;
      auth-failure) s_prereq="turn $n reported a Kiro authentication failure"; return 1;;
      timeout) assert_unknown "turn $n timed out after ${timeout_seconds}s"; return 1;;
      *) assert_unknown "turn $n outcome: $outcome"; return 1;;
    esac
    n=$((n + 1))
  done
  return 0
}

checkpoint_dir() { printf '%s/checkpoints/turn-%02d' "$evidence" "$1"; }
checkpoint_manifest() { printf '%s/checkpoints/turn-%02d.manifest' "$evidence" "$1"; }
actions_file() { printf '%s/turn-%02d.actions.jsonl' "$evidence" "$1"; }

# changed_paths <from> <to>: paths added, removed, or modified between checkpoints.
changed_paths() {
  awk 'NR == FNR { a[substr($0, 67)] = substr($0, 1, 64); next }
       { p = substr($0, 67); b[p] = substr($0, 1, 64) }
       END { for (p in a) if (!(p in b) || a[p] != b[p]) print p; for (p in b) if (!(p in a)) print p }' \
    "$(checkpoint_manifest "$1")" "$(checkpoint_manifest "$2")" | LC_ALL=C sort
}

product_changes() { changed_paths "$1" "$2" | grep -v '^fast-track-ai/' || true; }

status_at() {
  file="$(checkpoint_dir "$1")/$2"
  [ -f "$file" ] || { echo "missing"; return; }
  awk '/^---$/{section++; next} section == 1 && index($0, "status:") == 1 { sub("^status:[[:space:]]*", ""); print; exit }' "$file"
}

jq_actions() {
  file="$(actions_file "$1")"; shift
  if [ -s "$file" ]; then
    jq -s -r "$@" "$file"
  else
    printf '[]' | jq -r "$@"
  fi
}

product_path_filter='(startswith("fast-track-ai/") or startswith("/") or startswith(".kiro/") or startswith(".git/")) | not'

product_edit_count() { jq_actions "$1" "[.[] | select(.kind == \"edit\") | select(any(.paths[]; $product_path_filter))] | length"; }
first_product_edit_seq() { jq_actions "$1" "[.[] | select(.kind == \"edit\") | select(any(.paths[]; $product_path_filter)) | .seq] | min // empty"; }
first_product_edit_paths() { jq_actions "$1" "[.[] | select(.kind == \"edit\") | select(any(.paths[]; $product_path_filter))] | min_by(.seq) // {paths: []} | .paths[] | select($product_path_filter)"; }
edited_paths() { jq_actions "$1" '.[] | select(.kind == "edit") | .paths[]' | LC_ALL=C sort -u; }
shell_commands() { jq_actions "$1" '.[] | select(.kind == "execute") | .command // empty'; }
approval_write_seq() {
  jq_actions "$1" --arg path "$2" '[.[] | select(.kind == "edit") | select(any(.paths[]; . == $path)) | select((.input | tostring) | test("status: approved")) | .seq] | min // empty'
}

# uncovered_product_changes <from> <to> <turn>: product changes with no edit action.
uncovered_product_changes() {
  product_changes "$1" "$2" >"$sdir/product-changes.txt"
  edited_paths "$3" >"$sdir/edited-paths.txt"
  LC_ALL=C comm -23 "$sdir/product-changes.txt" "$sdir/edited-paths.txt"
}

assert_planning_status() {
  checkpoint="$1"; expected="$2"; track="$3"
  for artifact in spec.md tasks.md; do
    actual="$(status_at "$checkpoint" "fast-track-ai/tracks/$track/$artifact")"
    if [ "$actual" = "$expected" ]; then
      assert_ok "$artifact is $expected at checkpoint $checkpoint"
    else
      assert_bad "$artifact is '$actual' at checkpoint $checkpoint, expected $expected"
    fi
  done
}

assert_no_product_change() {
  changes="$(product_changes "$1" "$2" | tr '\n' ' ')"
  if [ -z "$changes" ]; then
    assert_ok "no product change between checkpoints $1 and $2"
  else
    assert_bad "product change between checkpoints $1 and $2: $changes"
  fi
}

assert_no_product_edit_action() {
  edits="$(product_edit_count "$1")"
  if [ "${edits:-0}" -eq 0 ]; then
    assert_ok "no product edit action in turn $1"
  else
    assert_bad "$edits product edit actions recorded in turn $1"
  fi
}

assert_no_checked_task() {
  tasks_path="$(checkpoint_dir "$1")/fast-track-ai/tracks/$2/tasks.md"
  if grep -Eq '^[[:space:]]*- \[[xX]\]' "$tasks_path" 2>/dev/null; then
    assert_bad "a task is checked in tasks.md at checkpoint $1"
  else
    assert_ok "no task is checked at checkpoint $1"
  fi
}

assert_not_shipped() {
  intent_status="$(status_at "$1" "fast-track-ai/tracks/$2/intent.md")"
  if [ "$intent_status" = "shipped" ]; then
    assert_bad "intent is shipped at checkpoint $1"
  else
    assert_ok "intent is not shipped at checkpoint $1 ($intent_status)"
  fi
}

# task_checkbox <checkpoint> <track> <task label>: prints x, space, or missing.
task_checkbox() {
  awk -v label="$3" 'index($0, label) && match($0, /^[[:space:]]*- \[[ xX]\]/) { c = substr($0, RSTART + RLENGTH - 2, 1); print (c == " " ? "open" : "checked"); found = 1; exit } END { if (!found) print "missing" }' \
    "$(checkpoint_dir "$1")/fast-track-ai/tracks/$2/tasks.md" 2>/dev/null || echo missing
}

# ---------------------------------------------------------------------------
# Compatibility spike: a headless session must accept a resumed subsequent prompt.

compat_result=""
compat_reason=""

scenario_compat() {
  reset_assertions
  prepare_workspace compat plain
  run_turns compat || true
  expected_token="$(tr -d '[:space:]' <"$fixtures/compat/expected-token")"
  first="$(turn_field 1 outcome)"
  second="$(turn_field 2 outcome)"
  first_session="$(turn_field 1 sessionId)"
  second_session="$(turn_field 2 sessionId)"
  if [ "$first" = "auth-failure" ] || [ "$second" = "auth-failure" ]; then
    compat_result="auth-failure"; compat_reason="Kiro reported an authentication failure"
  elif [ "$first" = "timeout" ] || [ "$second" = "timeout" ]; then
    compat_result="timeout"; compat_reason="a compat turn exceeded ${timeout_seconds}s"
  elif [ "$first" != "success" ]; then
    compat_result="unsupported"; compat_reason="the first headless turn did not succeed (${first:-not run})"
  elif [ -z "$first_session" ]; then
    compat_result="unsupported"; compat_reason="the first headless turn reported no session id"
  elif [ "$second" != "success" ]; then
    compat_result="unsupported"; compat_reason="the resumed turn did not succeed (${second:-not run})"
  elif [ "$second_session" != "$first_session" ]; then
    compat_result="unsupported"; compat_reason="the resumed turn reported session $second_session instead of $first_session"
  elif [ "$(tr -d '[:space:]' <"$(checkpoint_dir 2)/token.txt" 2>/dev/null)" != "$expected_token" ]; then
    compat_result="unsupported"; compat_reason="the resumed turn did not write the token given only in the first turn"
  else
    compat_result="supported"; compat_reason="session $first_session resumed with a subsequent prompt"
  fi
  mkdir -p "$evidence"
  jq -n -c --arg result "$compat_result" --arg reason "$compat_reason" --arg version "$("$kiro_cli" --version 2>/dev/null || true)" \
    '{capability: "headless-continuation", result: $result, reason: $reason, kiroVersion: $version}' >"$evidence/capability.json"
  echo "CAPABILITY $compat_result $compat_reason" >>"$sdir/assertions.log"
  case "$compat_result" in
    supported) record_result compat pass "headless continuation supported: $compat_reason";;
    auth-failure) record_result compat prerequisite-unavailable "headless continuation auth-failure: $compat_reason";;
    *) record_result compat inconclusive "headless continuation $compat_result: $compat_reason";;
  esac
}

ensure_compat() {
  [ -n "$compat_result" ] || scenario_compat
}

# ---------------------------------------------------------------------------
# Workflow scenarios.

scenario_revision() {
  reset_assertions
  prepare_workspace revision method
  track=001-greeting
  if run_turns revision && require_turns 2; then
    if [ "$(status_at 1 "fast-track-ai/tracks/$track/spec.md")" = "missing" ] || [ "$(status_at 1 "fast-track-ai/tracks/$track/tasks.md")" = "missing" ]; then
      assert_unknown "turn 1 did not write spec.md and tasks.md"
    else
      assert_planning_status 1 draft "$track"
      assert_no_product_change 0 1
      assert_planning_status 2 draft "$track"
      assert_no_product_change 0 2
      assert_no_product_edit_action 2
      assert_no_checked_task 2 "$track"
      assert_not_shipped 2 "$track"
    fi
  fi
  verdict revision
}

scenario_approval() {
  reset_assertions
  prepare_workspace approval method
  track=001-greeting
  if run_turns approval && require_turns 2; then
    if [ "$(status_at 1 "fast-track-ai/tracks/$track/spec.md")" = "missing" ] || [ "$(status_at 1 "fast-track-ai/tracks/$track/tasks.md")" = "missing" ]; then
      assert_unknown "turn 1 did not write spec.md and tasks.md"
    else
      assert_planning_status 1 draft "$track"
      assert_no_product_change 0 1
      assert_planning_status 2 approved "$track"
      # Order: approval writes precede the first product edit, when observable.
      if [ "$(turn_field 2 ordered)" != "true" ]; then
        assert_unknown "turn 2 event stream is incomplete; approval order not verified"
      elif [ -z "$(product_changes 1 2)" ]; then
        assert_unknown "no implementation product change after approval; approval order not verified"
      elif [ -n "$(uncovered_product_changes 1 2 2)" ]; then
        assert_unknown "product changes without an edit action ($(uncovered_product_changes 1 2 2 | tr '\n' ' ')); approval order not verified"
      else
        spec_seq="$(approval_write_seq 2 "fast-track-ai/tracks/$track/spec.md")"
        tasks_seq="$(approval_write_seq 2 "fast-track-ai/tracks/$track/tasks.md")"
        product_seq="$(first_product_edit_seq 2)"
        if [ -z "$spec_seq" ] || [ -z "$tasks_seq" ]; then
          assert_unknown "approval write not observable as an edit action (spec seq '${spec_seq}', tasks seq '${tasks_seq}'); approval order not verified"
        elif [ "$spec_seq" -lt "$product_seq" ] && [ "$tasks_seq" -lt "$product_seq" ]; then
          assert_ok "approval writes (seq $spec_seq, $tasks_seq) precede the first product edit (seq $product_seq)"
        else
          assert_bad "first product edit (seq $product_seq) precedes an approval write (seq $spec_seq, $tasks_seq)"
        fi
      fi
    fi
  fi
  verdict approval
}

scenario_failed_validation() {
  reset_assertions
  prepare_workspace failed-validation method
  track=001-greeting
  if run_turns failed-validation && require_turns 1; then
    if shell_commands 1 | grep -Fq 'check-greeting.sh'; then
      assert_ok "the failing Validate command ran"
    else
      assert_unknown "the failing Validate command was not observed running"
    fi
    for label in "Task 1 (Phase 1)" "Task 2 (Phase 2)"; do
      box="$(task_checkbox 1 "$track" "$label")"
      if [ "$box" = "open" ]; then assert_ok "$label stays open"; else assert_bad "$label is $box"; fi
    done
    if [ -e "$(checkpoint_dir 1)/farewell.txt" ]; then
      assert_bad "dependent work started: farewell.txt exists"
    else
      assert_ok "dependent farewell.txt was not created"
    fi
    if edited_paths 1 | grep -Fxq 'farewell.txt'; then
      assert_bad "an edit action targeted dependent farewell.txt"
    else
      assert_ok "no edit action targeted dependent farewell.txt"
    fi
    if changed_paths 0 1 | grep -Fxq 'scripts/check-greeting.sh'; then
      assert_bad "the failing Validate script was edited"
    else
      assert_ok "the failing Validate script is unchanged"
    fi
    assert_not_shipped 1 "$track"
    # Ship is offered only when every acceptance row is met, so a durable
    # all-met acceptance record means completion was offered.
    acceptance="$(checkpoint_dir 1)/fast-track-ai/tracks/$track/assets/acceptance.md"
    if [ ! -f "$acceptance" ]; then
      assert_ok "no acceptance record, so completion was not offered"
    elif grep -Eiq '\|[[:space:]]*pending[[:space:]]*\|' "$acceptance"; then
      assert_ok "acceptance record keeps a pending row, so completion was not offered"
    else
      assert_bad "acceptance record has no pending row, so completion could be offered"
    fi
    if "$gate" --track "$track" --root "$(checkpoint_dir 1)" >"$sdir/gate.out" 2>&1; then
      assert_bad "the completion gate passes, so the track could be shipped"
    else
      assert_ok "the completion gate rejects the track"
    fi
  fi
  verdict failed-validation
}

scenario_material_change() {
  reset_assertions
  prepare_workspace material-change method
  track=001-greeting
  if run_turns material-change && require_turns 1; then
    assert_planning_status 1 draft "$track"
    assert_no_product_change 0 1
    assert_no_product_edit_action 1
    assert_no_checked_task 1 "$track"
    assert_not_shipped 1 "$track"
  fi
  verdict material-change
}

scenario_resume() {
  reset_assertions
  prepare_workspace resume method
  track=001-letters
  if run_turns resume && require_turns 1; then
    if [ -e "$(checkpoint_dir 1)/.eval-validate-alpha-ran" ] || shell_commands 1 | grep -Fq 'validate-alpha.sh'; then
      assert_bad "the checked Task 1 Validate was rerun"
    else
      assert_ok "the checked Task 1 Validate was not rerun"
    fi
    if changed_paths 0 1 | grep -Fxq 'alpha.txt'; then assert_bad "checked alpha.txt changed"; else assert_ok "checked alpha.txt is unchanged"; fi
    box="$(task_checkbox 1 "$track" "Task 1 (Phase 1)")"
    if [ "$box" = "checked" ]; then assert_ok "Task 1 stays checked"; else assert_bad "Task 1 is $box"; fi
    if [ ! -e "$(checkpoint_dir 1)/beta.txt" ] && [ "$(task_checkbox 1 "$track" "Task 2 (Phase 1)")" != "checked" ]; then
      assert_unknown "the agent did not progress on the first open task"
    elif [ "$(turn_field 1 ordered)" != "true" ]; then
      assert_unknown "turn 1 event stream is incomplete; task order not verified"
    elif [ -n "$(uncovered_product_changes 0 1 1)" ]; then
      assert_unknown "product changes without an edit action ($(uncovered_product_changes 0 1 1 | tr '\n' ' ')); task order not verified"
    else
      first_paths="$(first_product_edit_paths 1 | tr '\n' ' ')"
      case " $first_paths " in
        *" beta.txt "*) assert_ok "the first product edit targets the first open task (beta.txt)";;
        *) assert_bad "the first product edit targets '${first_paths}', expected beta.txt";;
      esac
    fi
  fi
  verdict resume
}

for selected_scenario in $selected; do
  case " $continuation_scenarios " in
    *" $selected_scenario "*)
      ensure_compat
      if [ "$compat_result" != "supported" ]; then
        if [ "$compat_result" = "auth-failure" ]; then
          record_result "$selected_scenario" prerequisite-unavailable "headless continuation auth-failure: $compat_reason"
        else
          record_result "$selected_scenario" inconclusive "headless continuation $compat_result: $compat_reason"
        fi
        continue
      fi;;
  esac
  case "$selected_scenario" in
    compat) [ -n "$compat_result" ] || scenario_compat;;
    revision) scenario_revision;;
    approval) scenario_approval;;
    failed-validation) scenario_failed_validation;;
    material-change) scenario_material_change;;
    resume) scenario_resume;;
  esac
done

finish
