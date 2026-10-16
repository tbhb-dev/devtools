#!/usr/bin/env bash
# skill-tokens — measure what a skill costs in context, and record it
# beside the skill.
#
# The two halves of a skill are paid for differently. A frontmatter
# description sits in context for every turn of every session, whether
# or not anyone invokes the skill, so its cost is constant and shared.
# The body loads only on invocation, and a bundled script costs nothing
# until something reads it. Measuring them together hides that split,
# so this reports each separately.
#
# Counts come from each harness's tokenizer rather than from a
# characters-per-token guess. Claude skills use the Anthropic API through
# ant. Codex skills use OpenAI's tiktoken locally, so they need no API key.
#
# Each Anthropic request carries a fixed envelope of its own. A baseline
# call measures it once and subtracts it. tiktoken counts the text directly.
#
# The body budget is the platform's own guidance: keep the SKILL.md body
# under 5k tokens and push reference material into bundled files, which
# cost nothing until something reads them. Exceeding it is a warning
# rather than a refusal, because the number is a recommendation and no
# upload rejects a body for being long. The hard limits on name and
# description live in tools/skill-limits.sh, which stays offline.
#
# Usage: skill-tokens.sh [skill-dir ...]
#        (default: packages/agents/*/.apm/skills/*/)
# Env:   CLAUDE_MODEL or MODEL to count Claude skills against another model.
#        CODEX_MODEL to label Codex counts for another model.
#        CODEX_ENCODING to select its tiktoken encoding.
#        BODY_BUDGET to move the warning threshold.
set -euo pipefail

# --- environment hardening -------------------------------------------
# Output here feeds an agent and a committed artifact, so the operator's
# locale must not reorder it. PYTHONUTF8 is the companion: under LC_ALL=C
# python would otherwise read these files as ASCII and raise on the first
# non-ASCII character.
export LC_ALL=C
export PYTHONUTF8=1
unset CDPATH GREP_OPTIONS
IFS=$' \t\n'

readonly BODY_BUDGET=${BODY_BUDGET:-5000}

CLAUDE_MODEL=${CLAUDE_MODEL:-${MODEL:-claude-opus-5}}
CODEX_MODEL=${CODEX_MODEL:-gpt-5.6-sol}
CODEX_ENCODING=${CODEX_ENCODING:-o200k_base}
export CLAUDE_MODEL CODEX_MODEL CODEX_ENCODING

root=$(git rev-parse --show-toplevel)
cd "$root"

# One scratch area for the whole run, cleaned once. The loop below used
# to set and clear its own trap per skill, which would have dropped this
# one on the first pass.
scratch=$(mktemp -d)
trap 'rm -rf "$scratch"' EXIT
request="$scratch/request.yaml"

# count prints the token count of the text on stdin. The text goes in as
# a YAML literal block, which survives punctuation that would otherwise
# need quoting.
#
# The request is written to a file and redirected rather than piped in.
# ant decides at startup whether stdin carries a request, and a producer
# slower to start than ant loses that race: ant sees an empty pipe,
# concludes nothing was piped, and asks for the flags instead.
count_claude() {
  command -v ant >/dev/null 2>&1 || {
    printf 'skill-tokens: ant is required for Claude skills. See the Claude Developer Platform CLI.\n' >&2
    exit 1
  }
  python3 -c '
import os, sys
print("model: " + os.environ["CLAUDE_MODEL"])
print("messages:")
print("  - role: user")
print("    content: |")
for line in sys.stdin.read().split("\n"):
    print("      " + line)
' >"$request"
  ant messages count-tokens <"$request" 2>/dev/null |
    python3 -c 'import json,sys; print(json.load(sys.stdin)["input_tokens"])'
}

count_codex() {
  uv run --quiet --with 'tiktoken==0.13.0' python -c '
import sys, tiktoken
encoding = tiktoken.get_encoding(sys.argv[1])
print(len(encoding.encode(sys.stdin.read())))
' "$CODEX_ENCODING"
}

# net and the callers below do arithmetic on what count prints, and an
# empty string evaluates to zero there rather than stopping. Checking the
# text keeps a failed request from reaching tokens.json as a negative.
require_count() {
  case $1 in
  '' | *[!0-9]*)
    printf 'skill-tokens: token count failed for %s (got %s)\n' "$2" "${1:-empty}" >&2
    exit 1
    ;;
  esac
}

# The envelope every request pays, measured with a one-token payload.
claude_baseline=""

prepare_backend() {
  if [ "$TOKEN_BACKEND" != claude ] || [ -n "$claude_baseline" ]; then
    return
  fi
  claude_baseline=$(printf 'x' | count_claude) || {
    printf 'skill-tokens: the ant call failed. Check what ant auth status reports.\n' >&2
    exit 1
  }
  claude_baseline=$((claude_baseline - 1))
  printf 'model %s, request envelope %s tokens\n\n' "$CLAUDE_MODEL" "$claude_baseline"
}

# net prints the token count of a file with the envelope removed.
net() {
  local raw
  if [ "$TOKEN_BACKEND" = codex ]; then
    count_codex <"$1"
    return
  fi
  raw=$(count_claude <"$1")
  printf '%s\n' "$((raw - claude_baseline))"
}

budget_exceeded=0
dirs=("$@")
if [ ${#dirs[@]} -eq 0 ]; then
  dirs=(packages/agents/*/.apm/skills/*/)
fi

for dir in "${dirs[@]}"; do
  dir=${dir%/}
  skill=$(basename "$dir")
  manifest="$dir/SKILL.md"
  [ -f "$manifest" ] || {
    printf 'skip %s: no SKILL.md\n' "$dir" >&2
    continue
  }
  case $dir in
  packages/agents/codex/* | */packages/agents/codex/* | .agents/skills/* | */.agents/skills/*)
    TOKEN_BACKEND=codex
    MODEL=$CODEX_MODEL
    TOKENIZER=$CODEX_ENCODING
    ;;
  *)
    TOKEN_BACKEND=claude
    MODEL=$CLAUDE_MODEL
    TOKENIZER=""
    ;;
  esac
  prepare_backend

  # Split the manifest so the always-loaded part can be told apart from
  # the part that loads on invocation.
  tmp="$scratch/split"
  rm -rf "$tmp"
  mkdir -p "$tmp"
  python3 - "$manifest" "$tmp" <<'PY'
import pathlib, re, sys
text = pathlib.Path(sys.argv[1]).read_text()
out = pathlib.Path(sys.argv[2])
m = re.match(r"^---\n(.*?)\n---\n(.*)$", text, re.S)
frontmatter, body = (m.group(1), m.group(2)) if m else ("", text)
d = re.search(r"^description: >-\n((?:  .*(?:\n|$))+)", frontmatter, re.M)
description = re.sub(r"\s+", " ", d.group(1)).strip() if d else ""
(out / "frontmatter").write_text(frontmatter)
(out / "body").write_text(body)
(out / "description").write_text(description)
PY

  total=$(net "$manifest")
  fm=$(net "$tmp/frontmatter")
  desc=$(net "$tmp/description")
  body=$(net "$tmp/body")
  require_count "$total" "$skill manifest"
  require_count "$fm" "$skill frontmatter"
  require_count "$desc" "$skill description"
  require_count "$body" "$skill body"

  # Bundled files, which cost nothing until something opens them.
  #
  # The list comes from git rather than a filesystem walk. A walk reaches
  # whatever sits in the directory, ignored build artifacts included, and
  # the token counter returns nothing for a binary file. net then
  # subtracts the request envelope from that empty result and writes a
  # negative into tokens.json. Nothing catches it: require_count guards
  # the manifest figures, and a bundled row has no threshold to trip.
  # --others keeps a brand new file in the measurement before anyone
  # stages it, and --exclude-standard is what drops the ignored ones.
  #
  # The text check is the second half of the same guard, covering a
  # tracked binary. A count is only meaningful for something the agent
  # could read, and nothing else belongs in the total.
  bundled=""
  while IFS= read -r file; do
    [ -n "$file" ] || continue
    case $file in
    */SKILL.md | */tokens.json) continue ;;
    esac
    if ! grep -Iq . "$file" 2>/dev/null; then
      printf 'skip %s: not text, so no reader ever pays for it\n' "$file" >&2
      continue
    fi
    bundled="${bundled}${file}	$(net "$file")	$(wc -c <"$file" | tr -d ' ')
"
  done <<EOF
$(command git -c core.quotePath=false ls-files --cached --others --exclude-standard -- "$dir" | sort)
EOF

  MODEL="$MODEL" TOKENIZER="$TOKENIZER" SKILL="$skill" SKILL_DIR="$dir" TOTAL="$total" FM="$fm" DESC="$desc" BODY="$body" \
    BUNDLED="$bundled" MANIFEST_BYTES="$(wc -c <"$manifest" | tr -d ' ')" \
    python3 - "$dir/tokens.json" <<'PY'
import json, os, sys

rows = []
for line in os.environ["BUNDLED"].split("\n"):
    if not line.strip():
        continue
    path, tokens, size = line.split("\t")
    # Relative to the skill directory, so the record reads the same in
    # the packaged source and in the copy apm deploys under .claude.
    rows.append({
        "path": os.path.relpath(path, os.environ["SKILL_DIR"]),
        "tokens": int(tokens),
        "bytes": int(size),
    })

# No timestamp on purpose. This file is a deployed artifact, and a
# regenerated timestamp would read as drift to the packaging gate on
# every run even when nothing about the skill changed.
doc = {
    "skill": os.environ["SKILL"],
    "model": os.environ["MODEL"],
    "generated_by": "tools/skill-tokens.sh",
    "manifest": {
        "tokens": int(os.environ["TOTAL"]),
        "bytes": int(os.environ["MANIFEST_BYTES"]),
        "frontmatter_tokens": int(os.environ["FM"]),
        "body_tokens": int(os.environ["BODY"]),
    },
    "always_loaded": {
        "description_tokens": int(os.environ["DESC"]),
    },
    "bundled_files": rows,
    "bundled_files_tokens": sum(r["tokens"] for r in rows),
}
if os.environ["TOKENIZER"]:
    doc["tokenizer"] = os.environ["TOKENIZER"]
with open(sys.argv[1], "w") as fh:
    json.dump(doc, fh, indent=2, sort_keys=True)
    fh.write("\n")
PY

  over=""
  if [ "$body" -ge "$BODY_BUDGET" ]; then
    over="  OVER the ${BODY_BUDGET}-token body budget"
    budget_exceeded=1
  fi
  printf '%-24s description %5s   manifest %6s   bundled %6s%s\n' \
    "$skill" "$desc" "$total" \
    "$(printf '%s' "$bundled" | awk -F'\t' '{ s += $2 } END { print s + 0 }')" "$over"

done

printf '\nDescriptions load every turn. Manifests load on invocation.\n'
printf 'Bundled files cost nothing until something reads them.\n'

if [ "$budget_exceeded" = 1 ]; then
  printf '\nAt least one body sits past the %s-token budget. Move reference\n' "$BODY_BUDGET"
  printf 'material into a bundled file, which costs nothing until read.\n'
fi
