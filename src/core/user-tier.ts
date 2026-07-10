/**
 * User-tier policy — single source of truth for "what can this chat do".
 *
 * Three tiers, derived from access.json:
 *   - admin (access.admins): full access
 *   - trusted (access.trusted): full except destructive ops (relay to admin)
 *   - guest (allowed but not admin/trusted): reply + read only
 *
 * The TierProfile is daemon-defined; each provider's
 * `tierProfileToSdkOpts(profile)` is the only place that knows how to
 * translate the profile into its own SDK's permission knobs.
 *
 * See docs/superpowers/specs/2026-05-22-user-tier-permissions-design.md.
 */
import type { Access } from '../lib/access'
import type { PermissionMode } from './permission-mode'

export type UserTier = 'admin' | 'trusted' | 'guest'

export type ToolKind =
  | 'reply'
  | 'share_page'
  | 'memory_read'
  | 'memory_write'
  | 'memory_delete'
  | 'observations_read'
  | 'observations_write'
  | 'fs_read'
  | 'fs_write'
  | 'shell'
  | 'shell_destructive'  // virtual — set by classifyToolUse when Bash input matches a destructive pattern
  | 'network'
  | 'subagent'
  | 'a2a_send'
  | 'daemon_introspect'  // admin-only read-only self-diagnosis (turns / sessions / health / model_get)
  | 'daemon_remediate'   // admin-only mutating self-heal (session_release / model_set / daemon_restart)
  | 'file_locate'        // admin-only: locate files on the owner's computer (lib/locate-files)
  | 'plugin_tool'        // admin-only by default: ANY third-party plugin MCP tool (mcp__<plugin>__*). A plugin spawns arbitrary code and can expose owner-private data (e.g. wxvault = the owner's WeChat history), so fail closed — trusted/guest can't reach it.

const ALL_KINDS: ReadonlySet<ToolKind> = new Set([
  'reply', 'share_page', 'memory_read', 'memory_write', 'memory_delete',
  'observations_read', 'observations_write',
  'fs_read', 'fs_write', 'shell', 'shell_destructive', 'network', 'subagent',
  'a2a_send', 'daemon_introspect', 'daemon_remediate', 'file_locate', 'plugin_tool',
])

export interface TierProfile {
  /** Tools directly allowed without further check. */
  allow: ReadonlySet<ToolKind>
  /** Tools that require a permission prompt to the admin chat. */
  relay: ReadonlySet<ToolKind>
  /** Tools the SDK is told (or directed) to refuse outright. */
  deny: ReadonlySet<ToolKind>
}

function difference(a: ReadonlySet<ToolKind>, b: ReadonlySet<ToolKind>): Set<ToolKind> {
  const out = new Set<ToolKind>()
  for (const k of a) if (!b.has(k)) out.add(k)
  return out
}

// Admin tier still gets prompted in strict mode for genuinely
// destructive ops — they're admins, but accidents happen. The relay
// prompt goes to the admin themselves (per the sweep#6 fix in
// resolveAdminChatId), giving a "are you sure?" gate without
// inconveniencing day-to-day use. Operators who want zero prompts
// launch with `--dangerously`.
// daemon_remediate (session_release / model_set / daemon_restart) relays for
// admin too: these are destructive daemon ops, and a relay gives an "are you
// sure?" confirmation to the admin chat — defence against prompt-injection in
// an admin's own conversation steering the agent into a restart. Matches the
// tools' own "建议先确认" guidance. Operators wanting zero prompts use --dangerously.
const ADMIN_RELAY = new Set<ToolKind>(['shell_destructive', 'memory_delete', 'daemon_remediate'])

const TRUSTED_RELAY = new Set<ToolKind>(['shell_destructive', 'memory_delete', 'a2a_send'])

const GUEST_ALLOW = new Set<ToolKind>(['reply', 'share_page', 'memory_read', 'observations_read'])

// Admin-exclusive tools — the operator can ask the bot to inspect its own
// daemon (turn outcomes / live sessions / health). Denied for trusted and
// guest: daemon internals are an operator concern, and the later remediation
// tools (release session / restart) that build on this must never be reachable
// from a non-admin chat. guest already denies it via difference below; trusted
// would otherwise auto-allow (it's not destructive), so deny it explicitly.
// plugin_tool is admin-only too: third-party plugins spawn arbitrary code and
// can surface owner-private data (wxvault reads the owner's WeChat history), so
// they FAIL CLOSED — only the owner (admin) can call a plugin's tools by
// default. A plugin that genuinely wants trusted/guest reach must opt in
// explicitly (future: manifest `minTier`), not inherit it silently.
const ADMIN_ONLY = new Set<ToolKind>(['daemon_introspect', 'daemon_remediate', 'file_locate', 'plugin_tool'])

export const TIER_PROFILES: Record<UserTier, TierProfile> = {
  admin: {
    allow: difference(ALL_KINDS, ADMIN_RELAY),
    relay: ADMIN_RELAY,
    deny: new Set(),
  },
  trusted: {
    allow: difference(difference(ALL_KINDS, TRUSTED_RELAY), ADMIN_ONLY),
    relay: TRUSTED_RELAY,
    deny: ADMIN_ONLY,
  },
  guest: {
    allow: GUEST_ALLOW,
    relay: new Set(),
    deny: difference(ALL_KINDS, GUEST_ALLOW),
  },
}

/**
 * Recover the tier NAME from a resolved TierProfile. Used by providers to bake
 * `WECHAT_SESSION_TIER` into MCP child env (the non-secret companion to the
 * per-session token). Keys on capability, not object identity: admin is the
 * only tier that ALLOWS `daemon_introspect`; guest is the only one that DENIES
 * `fs_write`; everything else is trusted. Stays correct if a profile object is
 * reconstructed rather than referenced.
 */
export function tierNameFromProfile(tp: TierProfile): UserTier {
  if (tp.allow.has('daemon_introspect')) return 'admin'
  if (tp.deny.has('fs_write')) return 'guest'
  return 'trusted'
}

/**
 * The per-session env baked into a session's stdio MCP children:
 * `WECHAT_SESSION_TOKEN` (the env-only secret the children send as their
 * bearer; omitted when no token was minted) + `WECHAT_SESSION_TIER` (the
 * non-secret tier the wechat child gates admin-tool registration on). Computed
 * ONCE per spawn by the daemon (session-manager, which mints the token) and
 * threaded to providers via `SpawnContext.mcpEnv` — providers merge it blindly,
 * so a new provider carries the tier env for free and never re-derives it.
 */
export function sessionAuthEnv(tier: UserTier, sessionToken?: string): Record<string, string> {
  return {
    ...(sessionToken ? { WECHAT_SESSION_TOKEN: sessionToken } : {}),
    WECHAT_SESSION_TIER: tier,
  }
}

/**
 * Resolve a chatId's tier from access.json snapshot. Admin > trusted > guest.
 * A chatId not in any list still maps to guest — the assumption is the
 * upstream allowlist gate has already rejected outright-blocked users.
 */
export function resolveTier(chatId: string, access: Access): UserTier {
  if (access.admins?.includes(chatId)) return 'admin'
  if (access.trusted?.includes(chatId)) return 'trusted'
  return 'guest'
}

/**
 * Effective tier, honoring the daemon-wide `--dangerously` flag. When the
 * operator launched with `--dangerously` (`permissionMode === 'dangerously'`)
 * every chat is treated as admin — matching the pre-v0.6 behavior where
 * the dangerously flag uniformly bypassed sandbox / approval / canUseTool
 * for ALL chats. Without this override the per-tier sandbox/approval
 * derivation (codex guest → read-only + untrusted; claude trusted →
 * default+canUseTool) silently overrode the operator's intent on every
 * non-admin chat.
 */
export function resolveEffectiveTier(
  chatId: string,
  access: Access,
  permissionMode: PermissionMode,
): UserTier {
  if (permissionMode === 'dangerously') return 'admin'
  return resolveTier(chatId, access)
}

/**
 * Regex set for destructive Bash commands. Best-effort — a determined
 * adversary can `eval` or obfuscate. The intent is preventing
 * accidents and surface-level prompt injection, not stopping malice.
 *
 * Pattern guidelines:
 *   - Anchor to word boundaries so we don't over-fire on "rm" inside a path
 *     ("/var/farm/...").
 *   - Quote chars (`'` / `"`) ARE in the trigger class — `bash -c "rm -rf"`
 *     is a real attack/accident path (AI agents routinely chain commands
 *     via `bash -c "..."`). This means `echo "rm is dangerous"` also
 *     classifies as destructive; for a relay prompt that's an acceptable
 *     false positive — the doc-string above commits us to err on the
 *     side of triggering.
 *   - `\s+` between args so `rm  -rf` (multiple spaces) still matches.
 *
 * Extend by adding patterns; document the rationale next to each.
 */
const TRIGGER = String.raw`(?:^|[;&|\`$()\s'"])`
const DESTRUCTIVE_BASH_PATTERNS: ReadonlyArray<RegExp> = [
  new RegExp(`${TRIGGER}rm(?:\\s+-[a-zA-Z]*)*\\s+`),     // rm, rm -rf, rm -f, etc.
  new RegExp(`${TRIGGER}git\\s+reset\\s+--hard`),        // git reset --hard
  new RegExp(`${TRIGGER}git\\s+push\\b[^|]*--force`),    // git push --force / --force-with-lease
  new RegExp(`${TRIGGER}git\\s+branch\\s+-D\\b`),        // git branch -D
  new RegExp(`${TRIGGER}dd\\s+(?:if|of)=`),              // dd if=… of=…
]

function isDestructiveBash(command: string): boolean {
  return DESTRUCTIVE_BASH_PATTERNS.some(re => re.test(command))
}

/**
 * Map (toolName, input) to a daemon ToolKind. Unknown tools collapse to
 * 'subagent' (the most-restricted bucket) so adding a new tool without
 * a classifier update fails safe.
 */
export function classifyToolUse(toolName: string, input: Record<string, unknown>): ToolKind {
  // MCP-prefixed wechat tools
  if (toolName.startsWith('mcp__wechat__')) {
    const sub = toolName.slice('mcp__wechat__'.length)
    if (sub === 'reply') return 'reply'
    if (sub === 'share_page') return 'share_page'
    if (sub === 'memory_list' || sub === 'memory_read') return 'memory_read'
    if (sub === 'memory_write' || sub === 'memory_edit') return 'memory_write'
    if (sub === 'memory_delete') return 'memory_delete'
    if (sub === 'observations_list' || sub === 'observations_read') return 'observations_read'
    if (sub === 'observations_write' || sub === 'observations_archive') return 'observations_write'
    if (sub === 'a2a_send') return 'a2a_send'
    // Explicit write mapping — must NOT fall through to the fs_read default
    // below: set_chat_pref mutates chat_prefs.json (care level / split).
    if (sub === 'set_chat_pref') return 'memory_write'
    // Daemon-control family — classified by PREFIX (not exact name) so a future
    // rename or sibling tool (e.g. diagnostic_foo, daemon_bar, session_baz)
    // fails CLOSED into an admin-only kind instead of dropping to the
    // permissive fs_read default below. Read-only vs mutating split by name.
    if (sub.startsWith('diagnostic_') || sub === 'model_get') return 'daemon_introspect'
    if (sub.startsWith('daemon_') || sub.startsWith('session_') || sub === 'model_set') return 'daemon_remediate'
    // File-locate family — admin-only, classified by PREFIX so a sibling
    // (locate_dir, …) fails CLOSED into file_locate, not the fs_read default.
    if (sub.startsWith('locate_')) return 'file_locate'
    // Other wechat tools: classify as fs_read (safest non-reply default
    // for new wechat MCP tools — they tend to be query-like).
    return 'fs_read'
  }

  // Other MCP servers (non-wechat). `delegate` is the owner's own cross-provider
  // delegation (delegate_<peer>) — keep it trusted-capable (subagent). ANY other
  // MCP prefix is a THIRD-PARTY PLUGIN (mcp__<plugin>__<tool>): classify as the
  // admin-only `plugin_tool` so it FAILS CLOSED. Provider-agnostic — claude/codex/
  // cursor get plugin tools as `mcp__<plugin>__*` from their SDK, and the openai
  // provider's gate reconstructs the same shape from the real MCP server name.
  if (toolName.startsWith('mcp__delegate__')) return 'subagent'
  if (toolName.startsWith('mcp__')) return 'plugin_tool'

  // Built-in Claude Code tools
  if (toolName === 'Read' || toolName === 'Glob' || toolName === 'Grep' || toolName === 'LS') return 'fs_read'
  if (toolName === 'Write' || toolName === 'Edit' || toolName === 'NotebookEdit') return 'fs_write'
  if (toolName === 'Bash') {
    const cmd = typeof input.command === 'string' ? input.command : ''
    return isDestructiveBash(cmd) ? 'shell_destructive' : 'shell'
  }
  if (toolName === 'KillShell') return 'shell'
  if (toolName === 'WebFetch' || toolName === 'WebSearch') return 'network'
  if (toolName === 'Task') return 'subagent'

  // Unknown — fail safe. Subagent is in `guest.deny`, so guests can't
  // call a tool we haven't classified yet.
  return 'subagent'
}
