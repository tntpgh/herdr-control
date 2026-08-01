#!/usr/bin/env bash
# lib/command-policy.sh — "is the shell command behind this prompt something
# peer automation may auto-answer, or does it need a human?"
#
# docs/control-plane-design.md's review correction 8: peer automation (an
# agent auto-pressing herdr-select.sh's option key on ANOTHER agent's
# behalf) may only answer OPERATIONAL prompts. Destructive, credential,
# production, or scope-changing prompts must ESCALATE to the human — never
# get auto-approved just because they happen to look like a tool-approval
# menu. This file is that boundary: it classifies the raw shell text behind
# a prompt, and every caller must treat anything but a bare "allow" as "do
# not auto-answer this."
#
# Provides: scannable_command <cmd>   -> normalized text on stdout
#           classify_command <cmd>    -> verdict token (allow|escalate|deny)
#           classify_reason           -> reason for the last classify_command
#
# Ported in spirit from yc-software/qm's src/policy/command-policy.ts — same
# five floor rules, same normalize-before-match shape — reimplemented here
# in bash because that is what herdr-select.sh is written in.
set -uo pipefail

# Every real caller captures classify_command's verdict via command
# substitution — `verdict=$(classify_command "$cmd")` — because the verdict
# token IS its stdout per the contract above. Command substitution forks a
# SUBSHELL: any plain variable classify_command sets there (e.g. a
# "last reason") dies with that subshell the instant `$(...)` returns, so a
# naive in-memory "last reason" reads back empty on the very next line —
# classify_reason runs back in the ORIGINAL shell, which never saw the
# assignment happen. `$$` is the one thing bash keeps stable across that
# fork (unlike $BASHPID, which is per-subshell), so a tiny file keyed by it
# bridges classify_command's subshell back to classify_reason's call in the
# parent. One file, overwritten every call — not a durable log, just enough
# to survive one fork; PIDs recycle, so nothing here grows unbounded.
_cp_reason_file() {
  printf '%s/herdr-command-policy.%s.reason\n' "${TMPDIR:-/tmp}" "$$"
}

# ---- rule-severity accumulator ---------------------------------------------
# deny(2) > escalate(1) > allow(0). classify_command evaluates EVERY rule
# (built-in and operator) rather than returning on the first hit, because an
# operator rule might raise a command that only matched a lesser built-in
# rule (or none) up to deny — see the operator-rules section below. Keeping
# the strictest match (and its reason) as we go, instead of returning early,
# is what makes that "only ever tightens" invariant hold structurally rather
# than needing a special case.
_cp_best_v=0
_cp_best_r=""
_cp_consider() {                        # severity reason -> updates the running max
  local v="$1" r="$2"
  if [ "$v" -gt "$_cp_best_v" ]; then
    _cp_best_v="$v"
    _cp_best_r="$r"
  fi
}

_cp_match()  { printf '%s' "$2" | grep -qE  "$1" 2>/dev/null; }   # pattern text
_cp_imatch() { printf '%s' "$2" | grep -qiE "$1" 2>/dev/null; }   # pattern text (case-insensitive)

# ---- scannable_command ------------------------------------------------------
# Normalizes raw shell text into something the floor rules below can pattern
# match against, undoing the cheapest obfuscations first: `"rm" -rf` and
# `rm -rf` must scan identically, or a single pair of quotes defeats every
# rule in this file.
scannable_command() {
  if [ "$#" -lt 1 ]; then
    printf 'command-policy: scannable_command requires a <command> argument\n' >&2
    return 2
  fi
  local raw="$1" text
  text="$(_cp_strip_heredocs "$raw")"
  text="$(_cp_decode_ansi_c "$text")"
  # Blunt global strip of literal quote characters, AFTER the ANSI-C pass
  # above (which needs its own $'...' quoting intact to find and decode) —
  # doing this first would eat the very quotes that mark an ANSI-C string
  # and turn `$'\x2drf'` into unparseable garbage instead of `-rf`. This is
  # deliberately not real shell tokenizing (no escape-awareness, no
  # respecting `\"` inside a double-quoted string): a scanner is supposed to
  # be MORE willing to see through quoting than a real shell, not less —
  # false positives here just mean a human reviews something safe, false
  # negatives mean a destructive command auto-executes.
  text="$(printf '%s' "$text" | sed "s/['\"]//g")"
  text="$(_cp_flatten_substitutions "$text")"
  printf '%s' "$text"
}

# Heredoc bodies are DATA to the enclosing command unless that command is
# itself a shell — `cat <<EOF` just prints its body (mentioning "rm -rf" in
# a warning message is not a warning we need to raise), but `bash <<EOF`
# EXECUTES its body as shell script, so pattern text living only inside that
# body ("rm -rf /") is exactly as real a command as if it were typed
# unindented on the outer line. Getting this backwards in either direction
# is a bug: strip-always lets an attacker hide `rm -rf /` inside a
# `bash <<EOF` body and sail through as "allow"; keep-always turns every
# innocent `cat <<EOF` usage-text heredoc into a false escalation.
_cp_strip_heredocs() {
  local raw="$1" line out="" first=1
  local in_heredoc=0 delim="" strip_tabs=0 keep_body=0
  local drop_buf="" drop_first=1 had_dropped=0
  local chk prefix
  while IFS= read -r line || [ -n "$line" ]; do
    if [ "$in_heredoc" -eq 1 ]; then
      chk="$line"
      if [ "$strip_tabs" -eq 1 ]; then                       # POSIX <<- strips leading tabs from body AND terminator
        while [ "${chk:0:1}" = "$(printf '\t')" ]; do chk="${chk#?}"; done
      fi
      if [ "$chk" = "$delim" ]; then
        in_heredoc=0
        continue
      fi
      if [ "$keep_body" -eq 1 ]; then
        if [ "$first" -eq 1 ]; then out="$line"; first=0; else out="$out"$'\n'"$line"; fi
      else
        # Buffered, not discarded outright — see the fail-closed fallback
        # after the loop: an inert-looking body we never confirmed the END
        # of is a parsing anomaly, not a body we're entitled to drop.
        had_dropped=1
        if [ "$drop_first" -eq 1 ]; then drop_buf="$line"; drop_first=0; else drop_buf="$drop_buf"$'\n'"$line"; fi
      fi
      continue
    fi
    if [ "$first" -eq 1 ]; then out="$line"; first=0; else out="$out"$'\n'"$line"; fi
    if printf '%s' "$line" | grep -qE '<<-?[[:space:]]*["'"'"']?[A-Za-z_][A-Za-z0-9_]*'; then
      delim="$(printf '%s' "$line" | sed -E -n "s/.*<<-?[[:space:]]*[\"']?([A-Za-z_][A-Za-z0-9_]*).*/\1/p")"
      if [ -n "$delim" ]; then
        in_heredoc=1
        strip_tabs=0
        printf '%s' "$line" | grep -qE '<<-' && strip_tabs=1
        # "Feeds a shell" = the text BEFORE this line's first << names a
        # shell binary (bash/sh/zsh/dash/ksh/ash), e.g. `bash <<EOF` or
        # `sh <<'EOF'`. Anything else (cat, tee, a custom function we can't
        # see inside) is treated as inert — a real limitation of a static
        # text scanner, not a parser, documented rather than hidden.
        keep_body=0
        prefix="${line%%<<*}"
        printf '%s' "$prefix" | grep -qE '\b(bash|sh|zsh|dash|ksh|ash)\b' && keep_body=1
      fi
    fi
  done <<CPEOF
$raw
CPEOF
  # Fail closed: input ended while still "inside" a heredoc whose terminator
  # never showed up — that is not a well-formed inert-data heredoc, it is
  # unparseable shell. Rather than have silently-buffered "inert" lines just
  # vanish (an attacker's easiest possible evasion: open a heredoc, never
  # close it), fold them back into the scan.
  if [ "$in_heredoc" -eq 1 ] && [ "$had_dropped" -eq 1 ]; then
    if [ "$first" -eq 1 ]; then out="$drop_buf"; else out="$out"$'\n'"$drop_buf"; fi
  fi
  printf '%s' "$out"
}

# Decodes $'...' ANSI-C strings (`$'\x2drf'` -> `-rf`) so a hex-escaped flag
# byte matches the same as a literal one — otherwise `rm $'\x2drf' /tmp/x`
# sails past the recursive-rm rule below untouched. Bounded to 64 quoted
# runs per command (generous for anything a human would write, and each
# iteration only ever consumes forward through the string, so it can't spin
# on adversarial input the way unbounded recursion could).
_cp_decode_ansi_c() {
  local rest="$1" out="" pre body decoded iter=0
  while [ "$iter" -lt 64 ]; do
    iter=$((iter + 1))
    case "$rest" in
      *\$\'*\'*) : ;;
      *) break ;;
    esac
    pre="${rest%%\$\'*}"
    rest="${rest#*\$\'}"
    body="${rest%%\'*}"
    rest="${rest#*\'}"
    decoded="$(printf '%b' "$body" 2>/dev/null)"
    out="$out$pre$decoded"
  done
  printf '%s' "$out$rest"
}

# Flattens $(...) and `...` command substitutions by dropping their syntax
# and leaving the inner source text inline, so a payload smuggled through a
# substitution ($(echo rm) -rf /tmp/x, `echo rm` -rf /tmp/x) is exposed to
# the same floor-rule matching as if it had been typed directly — we are
# NOT executing the substitution (that would run untrusted code just to
# decide whether to trust it), only exposing its literal source text.
#
# Bounded to 8 passes, matching the contract's documented depth limit. Each
# pass only rewrites INNERMOST, non-nested `$(...)`/`` `...` `` pairs
# ([^()]* / [^`]* admit no nested delimiter), so one pass unwinds exactly one
# level of nesting. 200 nested `$(` with no closing `)` never matches at
# all — the pass is a bounded, linear sed scan regardless — so this
# terminates promptly on adversarial input instead of trying to fully
# resolve arbitrary nesting depth.
_cp_flatten_substitutions() {
  local text="$1" depth=0
  while [ "$depth" -lt 8 ]; do
    depth=$((depth + 1))
    text="$(printf '%s' "$text" | sed -E 's/\$\(([^()]*)\)/ \1 /g; s/`([^`]*)`/ \1 /g')"
  done
  printf '%s' "$text"
}

# ---- the floor rule table (ported from qm's command-policy.ts) ------------
# Applies in EVERY posture — there is no "trusted mode" that skips these.
# Deny rules are checked ahead of require_approval ones so a command that
# happens to also match a lesser pattern is still denied, not merely
# escalated.
classify_command() {
  if [ "$#" -lt 1 ]; then
    printf 'command-policy: classify_command requires a <command> argument\n' >&2
    return 2
  fi
  local raw="$1" norm
  norm="$(scannable_command "$raw")"

  _cp_best_v=0
  _cp_best_r=""

  # deny — mkfs formats a block device with no confirmation of its own;
  # nothing downstream of "yes, run this" makes that reversible, so it is
  # never eligible for even a human-approved auto-answer.
  _cp_match '(^|[^A-Za-z0-9_./-])mkfs([.][A-Za-z0-9]+)?([[:space:]]|$)' "$norm" &&
    _cp_consider 2 "mkfs formats a block device outright — irreversible, never eligible for auto-approval"

  # deny — the classic `:(){ :|:& };:` fork-bomb function definition. No
  # legitimate command defines a function named ":"; matching just the
  # opener is enough and avoids depending on exact whitespace in the body.
  _cp_match ':\(\)[[:space:]]*\{' "$norm" &&
    _cp_consider 2 "fork-bomb function definition — exhausts the process table"

  # escalate — recursive rm (-r/-R/-rf/--recursive, any short-opt cluster
  # containing r/R) can delete an entire tree. Word- and flag-checked
  # independently (not "flag immediately after rm") so `rm file -r` and
  # obfuscated `$(echo rm) -rf x` (flattened above to `echo rm -rf x`) both
  # still trip it.
  { _cp_match '\brm\b' "$norm" &&
    _cp_match '(--recursive\b|(^|[[:space:]])-[A-Za-z]*[rR][A-Za-z]*([[:space:]]|$))' "$norm"; } &&
    _cp_consider 1 "recursive rm (-r/-R/--recursive) can delete an entire directory tree"

  # escalate — git push --force/-f rewrites remote history other people may
  # already have pulled; the target branch needs a human's eyes, not an
  # automated yes.
  { _cp_match '\bgit\b' "$norm" && _cp_match '\bpush\b' "$norm" &&
    _cp_match '(^|[[:space:]])(-f|--force(-with-lease)?)([[:space:]]|$)' "$norm"; } &&
    _cp_consider 1 "git push --force/-f rewrites remote history"

  # escalate — DROP/TRUNCATE TABLE, case-insensitive (SQL keywords are
  # conventionally upper- or lower-case interchangeably).
  _cp_imatch '\bdrop[[:space:]]+table\b|\btruncate[[:space:]]+table\b' "$norm" &&
    _cp_consider 1 "DROP/TRUNCATE TABLE is an irreversible schema/data change"

  # escalate — curl piping straight into a shell executes unreviewed remote
  # code with the invoking user's privileges; a human should read the
  # script before it runs, not after.
  { _cp_match '\bcurl\b' "$norm" && _cp_match '\|[[:space:]]*(sh|bash)\b' "$norm"; } &&
    _cp_consider 1 "piping a remote download into a shell executes unreviewed code"

  _cp_apply_operator_rules "$norm"

  case "$_cp_best_v" in
    2) printf 'deny\n' ;;
    1) printf 'escalate\n' ;;
    *) printf 'allow\n' ;;
  esac

  # Best-effort write-through for classify_reason (see _cp_reason_file's
  # header comment) — a TMPDIR write failure must never fail classification
  # itself, only degrade the audit reason to empty.
  _CP_LAST_REASON="$_cp_best_r"
  printf '%s\n' "$_cp_best_r" >"$(_cp_reason_file)" 2>/dev/null || true
  return 0
}

# ---- operator extension point ----------------------------------------------
# HERDR_POLICY_EXTRA_RULES: newline-separated records, each
# "<verdict><TAB><extended-regex><TAB><reason>", checked against the same
# normalized text as the floor rules. Operators use this to add site-local
# escalate/deny rules (e.g. "we never auto-answer kubectl delete in this
# shop") WITHOUT editing this file.
#
# INVARIANT, enforced structurally rather than by a special-cased check:
# operator rules can only ever ADD escalate/deny matches into the SAME
# _cp_consider() max-accumulator the built-in rules feed. `<verdict>` MUST
# be exactly "escalate" or "deny" — there is no operator verdict that means
# "allow", so there is no code path by which an operator rule can lower a
# built-in deny (or escalate). A malformed/unrecognized verdict is skipped
# with a stderr note, never silently treated as anything else.
_cp_apply_operator_rules() {
  local norm="$1" ov opat oreason osev
  while IFS=$'\t' read -r ov opat oreason || [ -n "$ov" ]; do
    [ -n "$ov" ] || continue
    case "$ov" in
      escalate) osev=1 ;;
      deny)     osev=2 ;;
      *)
        printf 'command-policy: ignoring malformed HERDR_POLICY_EXTRA_RULES verdict %s (want escalate|deny)\n' "$ov" >&2
        continue
        ;;
    esac
    [ -n "$opat" ] || continue
    if printf '%s' "$norm" | grep -qE "$opat" 2>/dev/null; then
      _cp_consider "$osev" "operator rule: ${oreason:-$opat}"
    fi
  done <<CPEOF2
${HERDR_POLICY_EXTRA_RULES:-}
CPEOF2
}

# The reason behind the LAST classify_command call on this $$, for audit
# records and the escalation message shown to the human. Empty when the
# verdict was "allow" (nothing needs explaining) or when classify_command
# has never run in this process.
classify_reason() {
  local f
  f="$(_cp_reason_file)"
  [ -r "$f" ] && cat "$f"
  return 0
}
