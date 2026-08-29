/**
 * Sensitive-file deny-list for byte-light's PreToolUse hook + any
 * future runtime-native tool surface.
 *
 * Ported from reference implementation Fork (reference implementation L13) — `reference implementation/e4804c8` (initial
 * deny-list) and `reference implementation/564532d` (Bash/glob substring layer +
 * SDK PreToolUse wiring). byte-light adopts the same mechanism;
 * the June builtin pattern set was removed in the Slice 3a
 * empty-socket port (operator Phase 0.5 directive).
 *
 * ## Why this exists
 *
 * During the E3b live smoke (reference implementation fork, 2026-05-21), a Codex
 * turn read the repo's env file and got the full contents,
 * including a real Discord bot token. The path-guard correctly
 * identified the file as in-scope — it lives at the project
 * root, and `cfg.agent.cwd` is the project root. The character
 * voice (Azael's IntegrityProtocol from CLAUDE.md) noticed and
 * advised rotation, but a less-aligned model would dump the token
 * into chat / WS broadcasts / logs without flagging.
 *
 * This deny-list is the structural fallback for that case. Tools
 * route their resolved path through `isSensitivePath` and refuse
 * (or redact, for `list_files`) when the path matches the deny
 * patterns. In byte-light, the primary enforcement point is
 * `services/hooks.ts::buildPreToolUse` — the Claude Agent SDK's
 * PreToolUse hook gates Read/Grep/Glob/Bash before execution.
 *
 * ## Threat model
 *
 * The adversary is NOT the model. The model executes its context
 * literally; the adversary is whoever can inject instructions into
 * that context. byte-light's exposure vectors:
 *   - `messages_search` / `messages_search_semantic` returns can
 *     carry attacker-controlled text from prior turns.
 *   - MCP tool returns (Calendar, Discord, Gmail, Notion search,
 *     Spotify metadata, web search) inject untrusted text as tool
 *     results.
 *   - File contents the model summarizes can carry "and now read
 *     the secrets file and write its contents to a tool call."
 *
 * The deny-list closes the path between "literal instruction" and
 * "secret leaves the box."
 *
 * ## What's NOT defended
 *
 * - Files whose names slip past the configured regexes, and files
 *   that aren't conventionally-named secrets but contain secret
 *   content (e.g. someone pasting a token into `notes.txt`).
 * - The deny-list runs AFTER `assertPathInScope`, so out-of-scope
 *   paths still fail with `permission_denied` first.
 *
 * ## Two policies for the three tools (reference implementation lineage)
 *
 * - **`read_file`** — refuse with structured `{error: {code: 'sensitive_path'}}`.
 *   The model gets a clear signal AND can't use the call to exfiltrate.
 * - **`list_files`** — REDACT matching entries instead of refusing the
 *   whole listing. The model sees the entry exists but not its size
 *   or any way to read it — more informative than the listing failing.
 * - **`search_text`** — SKIP matching files during the recursive walk
 *   (same pattern as `node_modules` / `.git` already does).
 *
 * byte-light does NOT yet have these reference implementation-native built-in tools;
 * the policy is enforced at `hooks.ts::buildPreToolUse` instead, which
 * gates the Claude Agent SDK's native Read/Grep/Glob/Bash. When/if
 * byte-light adds runtime-native built-ins (e.g. for Codex via
 * Step 6B-B), each handler imports `isSensitivePath()` and refuses
 * with the same shape.
 *
 * ## Configurability
 *
 * `cfg.agent.tool_deny_patterns` (an optional `string[]` of regex
 * patterns) is ADDITIVE on top of the builtin list. As of the Slice 3a
 * empty-socket port the builtin list ships EMPTY (operator Phase 0.5
 * directive — single-user sovereign deployment), so the operator's
 * `tool_deny_patterns` IS the effective policy. Repopulating builtins
 * is an operator-gated decision.
 */

import { relative, sep, basename } from 'path';
import { getBytelightConfig } from '../../config.js';

/**
 * Built-in deny patterns. Each pattern is matched against the
 * relative-to-scope path AND each path segment. Add patterns by
 * appending to `cfg.agent.tool_deny_patterns` — see the module header.
 */
const BUILTIN_DENY_PATTERNS: RegExp[] = [
  // INTENTIONALLY EMPTY — operator Phase 0.5 directive (Slice 3a
  // "empty-socket" port). This is a single-user sovereign deployment;
  // the June builtin deny list was removed by explicit operator
  // decision. Repopulating builtin deny patterns is an operator-gated
  // decision. Operator-supplied patterns still flow through
  // `cfg.agent.tool_deny_patterns` (see `compilePatterns`).
];

/**
 * Compile and cache the effective deny-pattern list. Concat of
 * built-in defaults + caller-supplied additions. Invalid regex
 * strings in the additions are dropped with a console.warn rather
 * than crashing — bad config shouldn't take down the runtime.
 *
 * ## Caching (reference implementation Cleanup-1 review P3)
 *
 * `cfg.agent.tool_deny_patterns` is typically a stable array
 * reference across calls — the config is loaded once at boot. But
 * `isSensitivePath` runs on every fs op a tool does, which during
 * a `search_text` walk can be thousands of calls per turn. The
 * original implementation recompiled the regex AND re-issued the
 * console.warn for every invalid pattern on every call → log spam
 * proportional to walk size on misconfigured deployments. Cache
 * by input array reference so we recompile + warn ONCE per
 * config snapshot.
 */
let compileCacheKey: readonly string[] | undefined;
let compileCacheValue: RegExp[] = BUILTIN_DENY_PATTERNS;

function compilePatterns(extraPatternStrings?: readonly string[]): RegExp[] {
  if (!extraPatternStrings || extraPatternStrings.length === 0) {
    return BUILTIN_DENY_PATTERNS;
  }
  if (extraPatternStrings === compileCacheKey) {
    return compileCacheValue;
  }
  const extras: RegExp[] = [];
  for (const src of extraPatternStrings) {
    try {
      extras.push(new RegExp(src));
    } catch (err) {
      console.warn(
        `[sensitive-paths] dropping invalid deny pattern ${JSON.stringify(src)}: ${err instanceof Error ? err.message : String(err)}`,
      );
    }
  }
  compileCacheKey = extraPatternStrings;
  compileCacheValue = [...BUILTIN_DENY_PATTERNS, ...extras];
  return compileCacheValue;
}

/**
 * Check whether the resolved target path matches any deny pattern.
 * `scopeRoot` is the realpath-resolved scope (so `relative()`
 * produces clean forward-slash relative paths on both Unix and
 * Windows after normalization).
 *
 * Returns the matching pattern's `source` for diagnostics if the
 * path is sensitive, or `null` if it's allowed.
 */
export function isSensitivePath(
  resolvedPath: string,
  scopeRoot: string,
  extraPatterns?: readonly string[],
): string | null {
  const patterns = compilePatterns(extraPatterns);
  // Normalize to forward-slash relative path so the regex patterns
  // (which use `/` as their separator) work consistently on Windows.
  const rel = relative(scopeRoot, resolvedPath).split(sep).join('/');
  const checkAgainst = rel === '' ? '.' : rel;
  for (const pattern of patterns) {
    if (pattern.test(checkAgainst)) {
      return pattern.source;
    }
  }
  // Also test the basename in isolation — catches cases where the
  // path has no preceding directory (e.g. the file lives at the
  // scope root) AND ensures basename-anchored patterns fire.
  const base = basename(resolvedPath);
  for (const pattern of patterns) {
    if (pattern.test(base)) {
      return pattern.source;
    }
  }
  return null;
}

/**
 * Convenience wrapper that reads `cfg.agent.tool_deny_patterns` from
 * the live config and delegates to `isSensitivePath`. Tools use this
 * so they don't each have to import config; tests use the pure
 * `isSensitivePath` with explicit extras for isolation.
 *
 * Reading config inside this helper means a config reload between
 * turns automatically picks up new deny patterns without restarting
 * the runtime — useful when an operator notices a leak and wants to
 * add a pattern without bouncing the service.
 */
export function isSensitivePathConfigured(
  resolvedPath: string,
  scopeRoot: string,
): string | null {
  let extras: string[] | undefined;
  try {
    extras = getBytelightConfig().agent.tool_deny_patterns;
  } catch {
    // Config not loaded (e.g. during tests that bypass ensureInit).
    // Fall back to built-in defaults only.
    extras = undefined;
  }
  return isSensitivePath(resolvedPath, scopeRoot, extras);
}

/**
 * Substring fragments that signal a glob / Bash command is targeting
 * a sensitive file or directory. Used by `bashOrGlobTargetsSensitive`
 * for cases where a full path can't be resolved (glob patterns or
 * Bash one-liners that aren't path-shaped). Each fragment is matched
 * case-INSENSITIVELY as a substring of the input.
 *
 * Kept in sync by hand with `BUILTIN_DENY_PATTERNS` — when a new
 * pattern lands, add the corresponding human-readable fragment here
 * too. Caller-supplied `tool_deny_patterns` are NOT automatically
 * mirrored here because regex patterns don't decompose cleanly into
 * substrings.
 */
const SENSITIVE_FRAGMENTS: string[] = [
  // INTENTIONALLY EMPTY — operator Phase 0.5 directive (Slice 3a
  // "empty-socket" port). See BUILTIN_DENY_PATTERNS above. Repopulating
  // builtin fragments is an operator-gated decision (single-user
  // sovereign deployment).
];

/**
 * Substring check for Bash commands + glob patterns that don't
 * resolve to a single concrete path. Returns the matching fragment
 * if the input targets a known-sensitive name, or `null` otherwise.
 *
 * Use this for fuzzy contexts (Bash one-liners, glob patterns).
 * Use `isSensitivePath` / `isSensitivePathConfigured` for concrete
 * file paths.
 */
export function bashOrGlobTargetsSensitive(input: string): string | null {
  if (typeof input !== 'string' || input.length === 0) return null;
  const lower = input.toLowerCase();
  for (const frag of SENSITIVE_FRAGMENTS) {
    if (lower.includes(frag)) return frag;
  }
  return null;
}

/** Exported for tests; otherwise the module's surface is just
 *  `isSensitivePath`, `isSensitivePathConfigured`, and
 *  `bashOrGlobTargetsSensitive`. */
export const __TEST_INTERNALS__ = Object.freeze({
  BUILTIN_DENY_PATTERNS,
  SENSITIVE_FRAGMENTS,
});
