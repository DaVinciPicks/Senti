# senti shared config — sourced by every script.
# Edit values here to retune the whole system.
#
# NOTE: install.sh only copies this file if it is MISSING, so your local edits
# survive a `git pull`. When the schema changes, WF_CONFIG_VERSION is bumped and
# install.sh backs your old file up to config.sh.bak rather than silently keeping
# stale settings. Model IDs deliberately do NOT live here anymore — they are
# defaults at the point of use in each script, so an upgrade actually upgrades.
# Override one anyway by uncommenting it below.
# v3: WF_EFFORT default low→none (2.2x cheaper, 1.8x faster at equal quality), plus
#     per-mode WF_JUDGE_EFFORT / WF_VISION_EFFORT and a tunable WF_SHOT_PX.
# v4: default model gpt-5.4-mini → gpt-5.6-luna (newer, 3-4.5x cheaper, eval 8.12 vs 8.00).
# v5: Best mode deleted (unreachable from the live path, never measured better, 2x latency);
#     second-brain bridge added (WF_BRAIN* — Obsidian vault digests in prompt mode).
# v6: model fallback (a config pinning a model that isn't on disk no longer kills
#     dictation) + WF_AUDIO_CTX* short-clip speedup knobs. Behavioural, so it needs the
#     bump — install.sh only replaces config.sh when this number changes.
# v7: Senti → Sanele rename. Every path in this file moved (~/.config/senti →
#     ~/.config/sanele, ~/.cache/senti → ~/.cache/sanele, senti.log → sanele.log), so a
#     migrated v6 config would silently point the whole system at the old directories.
#     The bump forces install.sh to replace it (yours is kept at config.sh.bak).
# v8: renamed back, Sanele → Senti. Same reason as v7, paths reversed (~/.config/sanele →
#     ~/.config/senti, ~/.cache/sanele → ~/.cache/senti, sanele.log → senti.log).
# v9: three AI providers (WF_AI_PROVIDER pins; keys in the macOS Keychain), the audio_ctx
#     gate moved from 10 s to 14 s (measured), WF_URL can be overridden (the self-test
#     points it at a dead port to prove the transcription check fails), and the notes
#     digest refresh is gone (WF_BRAIN_REFRESH no longer exists).
# v10: Notion as a second notes source beside Obsidian (WF_BRAIN_NOTION, off by default; the
#     token lives in the Keychain like the AI keys), with its timeout and cache settings.
WF_CONFIG_VERSION=10

# --- Model ---
# Selected via the menu bar (Fast/Accurate); persisted in model.pref.
#   accurate = large-v3-turbo-q5  (~0.8s, best accuracy, handles proper nouns)
#   fast     = base.en            (~0.3s, English-only, great for clear speech)
WF_MODELS_DIR="$HOME/.local/share/whisper-models"
WF_MODEL_ACCURATE="$WF_MODELS_DIR/ggml-large-v3-turbo-q5_0.bin"
WF_MODEL_FAST="$WF_MODELS_DIR/ggml-base.en.bin"
WF_MODEL_PREF="$HOME/.cache/senti/model.pref"
if [ -z "${WF_MODEL:-}" ]; then
  # builtin read: no spawn. It returns 1 on an empty file or a last line with no newline,
  # and senti-serve.sh sources this under set -e, so the || true is load-bearing.
  _wf_pref=""
  if [ -f "$WF_MODEL_PREF" ]; then IFS= read -r _wf_pref < "$WF_MODEL_PREF" || true; fi
  case "$_wf_pref" in
    fast) WF_MODEL="$WF_MODEL_FAST" ;;
    *)    WF_MODEL="$WF_MODEL_ACCURATE" ;;
  esac
  # Fall back to whichever model is actually on disk. Without this, a fresh install
  # that downloaded only one model points whisper-server at a missing file and
  # dictation is dead on arrival with no obvious cause.
  if [ ! -f "$WF_MODEL" ]; then
    if   [ -f "$WF_MODEL_ACCURATE" ]; then WF_MODEL="$WF_MODEL_ACCURATE"
    elif [ -f "$WF_MODEL_FAST" ];     then WF_MODEL="$WF_MODEL_FAST"
    fi
  fi
fi

# --- Server ---
WF_HOST="${WF_HOST:-127.0.0.1}"
WF_PORT="${WF_PORT:-8090}"
WF_URL="${WF_URL:-http://${WF_HOST}:${WF_PORT}}"

# --- Language --- ("auto" to autodetect, or "en", "es", etc.)
WF_LANG="${WF_LANG:-en}"

# --- Custom dictionary (fixes mistranscriptions like "cloud md" → CLAUDE.md) ---
WF_REPLACEMENTS="${WF_REPLACEMENTS:-$HOME/.config/senti/replacements.txt}"

# --- Runtime files ---
WF_RUN="${WF_RUN:-$HOME/.cache/senti}"
WF_AUDIO="$WF_RUN/capture.wav"
WF_PIDFILE="$WF_RUN/sox.pid"
WF_LOG="$HOME/Library/Logs/senti.log"

# --- AI modes (prompt / command / context) ---
# Three providers behind one adapter (senti-ai.sh): OpenAI, Anthropic and OpenRouter. The
# menu bar writes the choice to ~/.config/senti/ai.pref; keys live in the macOS Keychain
# (senti-key.sh). Defaults: OpenAI gpt-6-luna ($0.10/$0.50 per 1M), Anthropic
# claude-opus-5-5, OpenRouter openai/gpt-6-luna. ai-models.json lists every model, its
# price and the efforts it accepts.
# Pins below OUTRANK the menu choice, which is why they are commented out. Provider and
# model always resolve as a pair, so a pinned model is never sent to another provider:
# WF_AI_PROVIDER=anthropic          # openai | anthropic | openrouter
# WF_TEXT_MODEL="claude-haiku-5-5"  # claude-* means Anthropic, an id with "/" OpenRouter
# WF_VISION_MODEL="claude-haiku-5-5"
# Key file paths, used only when the Keychain holds no key (defaults shown):
# WF_ANTHROPIC_KEY="$HOME/.config/senti/anthropic-key"
# WF_OPENROUTER_KEY="$HOME/.config/senti/openrouter-key"
# Anthropic refusal fallbacks (Opus and Sonnet; Haiku has none): a declined request is
# re-run server-side on the model Anthropic recommends. On by default (owner, 13 Nov 2026).
# WF_ANTHROPIC_FALLBACKS=0
# OpenRouter: data_collection "deny" is always sent. Zero-data-retention routing is
# stricter and can leave a model with no endpoint (the request then fails):
# WF_OPENROUTER_ZDR=1
# Measured on this Mac (8-case eval + per-call cost):
#   gpt-4o-mini   vision 3.30s  37k tok  $0.00560   (the old vision model)
#   deepseek-chat text   1.37s           $0.00003   (the old text model — still cheapest)
#   gpt-5.4-mini  8.00   text  $0.00155  vision $0.00177
#   gpt-5.6-luna  8.12   text  $0.00049  vision $0.00039   (default until 2026-10-17)
#   gpt-6-luna    2026-10-17 A/B vs gpt-5.6-luna, 8 cases, no KB layer: pairwise 5-0-3 for
#                 gpt-6-luna (judged BY 5.6-luna), median 2.00s vs 2.08s, $0.000054 vs
#                 $0.000165 per text call (~3x cheaper, shorter prompts)   ← default
#   deepseek-flash 2026-10-17: same speed, not cheaper per call (2.2x the output), and
#                 4 of 8 outputs leaked its 'silent deconstruction' notes — not adopted
#   gpt-5.6-terra 8.25   text  $0.00568   (+0.25 eval for ~12x luna's cost — not worth it)
# Eval granularity is integer scores over 8 cases, so ±0.25 is noise; luna is chosen
# because it is newer and 3-4.5x cheaper at indistinguishable quality, not because 8.12>8.00.
# For a one-off quality push: SENTI_PROVIDER=openai SENTI_MODEL=gpt-6.1-sol bash senti-prompt.sh ...
WF_OPENAI_KEY="${WF_OPENAI_KEY:-$HOME/.config/senti/openai-key}"
# Reasoning depth: none | low | medium | high | xhigh   ('minimal' is REJECTED by gpt-5.x)
# Measured on the prompt-rewrite task (2 runs each): none 2.05s/$0.00115 ·
# low 3.68s/$0.00254 · medium 8.43s/$0.00597. Rewriting a prompt is a transformation,
# not a reasoning problem, so `none` is 2.2x cheaper AND 1.8x faster at the same quality —
# the 269 reasoning tokens `low` spends here are pure overhead.
WF_EFFORT="${WF_EFFORT:-none}"
# The judge (eval harness / pairwise compare) does comparative reasoning — pay for depth there.
WF_JUDGE_EFFORT="${WF_JUDGE_EFFORT:-low}"
# Vision: reading a screen benefits from a little reasoning and it's cheap there
# (~45 output tokens either way).
WF_VISION_EFFORT="${WF_VISION_EFFORT:-low}"
# Screenshot long edge sent to the vision model. Measured cost/quality:
#   1024 → 843 tok / $0.00088 (reads on-screen text, misses fine detail)
#   1536 → 1880 tok / $0.00161 (reads exact commands/filenames — the default)
#   2048 → 2814 tok / $0.00233 (no material gain over 1536)
# Drop to 1024 to roughly halve vision cost if you don't need fine text read back.
WF_SHOT_PX="${WF_SHOT_PX:-1536}"

# --- Local transcription speed ---
# Shrinking whisper's encoder window ~halves latency on short clips (measured 833ms →
# 420ms on a 6s clip, byte-identical transcript) but TRUNCATES longer ones: at 16s the
# transcript diverged and ran 3x slower; at 18.8s the end of the recording was silently
# lost. So it only applies below WF_AUDIO_CTX_MAX_SEC. 768 frames of 20 ms cover 15.36 s;
# b2 measured identical words up to 14.61 s and a lost ending at 16.17 s (13 Nov 2026), and
# moving the gate from 10 to 14 took 10.8 to 12.9 s dictations from about 1.15 s to 0.73 s.
# Set WF_AUDIO_CTX_MAX_SEC=0 to disable the optimisation entirely.
WF_AUDIO_CTX="${WF_AUDIO_CTX:-768}"
WF_AUDIO_CTX_MAX_SEC="${WF_AUDIO_CTX_MAX_SEC:-14}"

WF_OPERATING_PROMPT="${WF_OPERATING_PROMPT:-$HOME/.config/senti/prompts/operating.md}"
# Model-aware prompting knowledge base: prompt mode reads the guidance file for
# whichever model you're actually about to paste into. See prompts/models/.
WF_MODEL_KB="${WF_MODEL_KB:-$HOME/.config/senti/prompts/models}"
# Optional manual pin for the target-model family (no UI writes this — it's an
# escape hatch): `echo anthropic > ~/.cache/senti/target.pref`. Absent/"auto" =
# detect from the frontmost app / browser tab title.
WF_TARGET_PREF="${WF_TARGET_PREF:-$HOME/.cache/senti/target.pref}"

# --- Second brain (Obsidian) ---
# Off by default. When on, a heavy Prompt turn (one that opens with "think hard" or
# "today let's work on") adds a capped digest of YOUR vault note for the current project
# to the AI call; that is the point and the risk. Only the folders you list are searched,
# size is capped, and senti.log records "sent: vault '<note>' N chars" for every digest
# that joins a request. See what would be sent, locally:
#   bash ~/.config/senti/senti-brain.sh --preview <project>
# To turn it on, set both:
# WF_BRAIN=1
# WF_BRAIN_DIRS=$'Projects\nWork'              # vault folders it may read, one per line
# WF_VAULT="$HOME/Documents/Obsidian Vault"
# WF_BRAIN_MAX=700                            # digest cap, chars

# --- Second brain (Notion) ---
# Off by default, and independent of the Obsidian switch above. When on, a heavy Prompt turn
# for a project you mapped to a Notion page adds a capped digest of that page (its "Senti"
# heading section, else "For future Claude", else its first lines) to the AI call. Senti
# reads only pages you map in brain-map.txt, one line per project:
#   myproject|notion:https://www.notion.so/My-Page-0123456789abcdef0123456789abcdef
# and your integration can only read pages you shared with it in Notion. Senti never uses
# Notion's search. The page is read after you speak, on heavy turns only, never at key-down.
# Add your integration token (it goes to the macOS Keychain):
#   bash ~/.config/senti/senti-key.sh set notion
# See what would be sent, locally: bash ~/.config/senti/senti-brain.sh --preview <project>
# WF_BRAIN_NOTION=1
# WF_NOTION_KEY="$HOME/.config/senti/notion-key"  # token file, used only when the Keychain holds none
# WF_NOTION_TIMEOUT=2.5                         # seconds for the whole read, 0.5 to 3; a slow or
#                                               # failed read sends no Notion digest at all
# WF_NOTION_TTL_MIN=10                          # minutes a read digest is reused before Senti reads
#                                               # the page again (0 = read it on every heavy turn)
# WF_NOTION_API=http://127.0.0.1:8765           # tests only: a local mock server. Any host other
#                                               # than api.notion.com or 127.0.0.1/localhost is refused

# --- Binaries (absolute paths — Hammerspoon/launchd have a minimal PATH) ---
WF_SOX="${WF_SOX:-/opt/homebrew/bin/sox}"
WF_SERVER="${WF_SERVER:-/opt/homebrew/bin/whisper-server}"
WF_CURL="${WF_CURL:-/usr/bin/curl}"

# --- Audio cues (macOS system sounds; set WF_SOUNDS=0 to silence) ---
WF_SOUNDS="${WF_SOUNDS:-1}"
WF_SOUND_START="${WF_SOUND_START:-/System/Library/Sounds/Tink.aiff}"
WF_SOUND_STOP="${WF_SOUND_STOP:-/System/Library/Sounds/Pop.aiff}"

# 700 every time, not only at install: a cache wiped by a disk cleanup was recreated 755
# here, and it holds audio, screenshots and selected text while a turn runs.
{ { [ -d "$WF_RUN" ] || mkdir -p "$WF_RUN"; } && chmod 700 "$WF_RUN"; } 2>/dev/null || true
