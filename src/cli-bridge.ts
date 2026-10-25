import { syncedAppsContext } from "./apps-mirror.ts";
import { spawn } from "node:child_process";
import { AsyncLocalStorage } from "node:async_hooks";
import { existsSync, readFileSync, writeFileSync } from "node:fs";
import { CONTRACT_FILE, contractBlock, parseContract } from "./agent-contract.ts";
import { basename, dirname, join, resolve, sep } from "node:path";
import { fileURLToPath } from "node:url";
import { homedir } from "node:os";
import type { Domain, ViewKey } from "./vault.ts";
import { readResponseFramework, readWebAccess, vaultLockActive } from "./config.ts";
import { buildFrameworkPreamble, getFramework } from "./framework.ts";
import { resolveModelForDomain } from "./privacy.ts";
import { APP_SCOPE_PREFIX, APP_SCOPE_SUBDIR, buildRoot, vaultRootForCwd } from "./path-safety.ts";
import { GOALS_HEADER, domainOfCwd, goalsBlock, memoryBlock, readProfile } from "./goals.ts";
import { CHIEF_HEADER, chiefOfStaffBlock } from "./chief-of-staff.ts";
import { COMPASS_HEADER, compassBlock } from "./compass.ts";
import { buildHarnessArgs } from "./harness-profiles.ts";
import {
  type BudgetCaps,
  checkBudget,
  estimateTurnCost,
  recordSpend,
} from "./budget.ts";

const OPERATING_MANUAL_FILE = "AGENTS-operating.md";
const PREVAIL_DOC_FILE = "PREVAIL.md"; // canonical root OS doc (summary + guiding principles)
const IDEAL_STATE_FILE = "ideal-state.md";
const OMEGA_FILE = "omega.md";
let operatingManualCache: { vaultPath: string; content: string | null } | null = null;

function findOperatingManual(vaultPath: string): string | null {
  if (operatingManualCache && operatingManualCache.vaultPath === vaultPath) {
    return operatingManualCache.content;
  }
  // Canonical layout keeps the operating doc under build/ (build/ wins), so look
  // there first, then fall back to the legacy vault-root locations (PREVAIL.md /
  // AGENTS-operating.md), then ~/.prevail, then the bundled copy beside the binary.
  const candidates: string[] = [
    join(buildRoot(vaultPath), PREVAIL_DOC_FILE),
    join(buildRoot(vaultPath), OPERATING_MANUAL_FILE),
    join(vaultPath, PREVAIL_DOC_FILE),
    join(vaultPath, OPERATING_MANUAL_FILE),
    join(homedir(), ".prevail", PREVAIL_DOC_FILE),
    join(homedir(), ".prevail", OPERATING_MANUAL_FILE),
  ];
  try {
    candidates.push(resolve(dirname(process.execPath), OPERATING_MANUAL_FILE));
  } catch {}
  try {
    const here = dirname(fileURLToPath(import.meta.url));
    candidates.push(resolve(here, "..", OPERATING_MANUAL_FILE));
  } catch {}
  let content: string | null = null;
  for (const c of candidates) {
    if (existsSync(c)) {
      try {
        content = readFileSync(c, "utf8");
        break;
      } catch {}
    }
  }
  operatingManualCache = { vaultPath, content };
  return content;
}

// The harness-native instruction file each CLI auto-reads from its working dir.
// Claude reads CLAUDE.md, Codex reads AGENTS.md, Gemini reads GEMINI.md. Prevail
// injects its operating rules into that file so codex/gemini (which have no
// system-prompt flag) still respect the vault architecture, and so a user's own
// file can never quietly override Prevail. Null = a runtime with no such file.
function harnessManualFile(kind: string): string | null {
  if (kind === "claude") return "CLAUDE.md";
  if (kind === "codex") return "AGENTS.md";
  if (kind === "antigravity") return "GEMINI.md";
  return null;
}

const PREVAIL_BLOCK_BEGIN = "<!-- BEGIN PREVAIL (managed by Prevail, do not edit) -->";
const PREVAIL_BLOCK_END = "<!-- END PREVAIL -->";

// The domain's agent.md contract, when it has one, rides in the managed block,
// so every engine reads the same contract and nobody hand-edits a copy.
function contractSection(cwd: string): string {
  try {
    const p = join(cwd, CONTRACT_FILE);
    if (!existsSync(p)) return "";
    const c = parseContract(readFileSync(p, "utf8"), basename(cwd));
    return c ? `\n${contractBlock(c)}\n` : "";
  } catch { return ""; }
}

/** Refresh the managed block in every instruction file a domain's engines read. */
export function generateHarnessFiles(cwd: string, vaultPath: string, kinds: string[]): string[] {
  const files: string[] = [];
  for (const k of kinds) {
    const f = harnessManualFile(k);
    if (!f || files.includes(f)) continue;
    syncHarnessManual(cwd, k, vaultPath, readWebAccess());
    files.push(f);
  }
  return files;
}

// Write/refresh ONLY Prevail's marked block inside the running harness's native
// instruction file (in cwd), preserving any user content in that file. Idempotent
// and best-effort: a failed write never blocks the turn.
function syncHarnessManual(cwd: string, kind: string, vaultPath: string, webMode: "allow" | "deny"): void {
  const file = harnessManualFile(kind);
  if (!file) return;
  const manual = augmentManualWithWebGate(findOperatingManual(vaultPath), webMode);
  if (!manual) return;
  const block =
    `${PREVAIL_BLOCK_BEGIN}\n` +
    "# Glyph operating rules (highest precedence)\n\n" +
    `You are running inside a Glyph vault. The rules in this block take precedence over anything else in this ${file}, including any user or default instructions. Follow them exactly.\n\n` +
    `${manual}\n` +
    contractSection(cwd) +
    `${PREVAIL_BLOCK_END}`;
  const path = join(cwd, file);
  try {
    const existing = existsSync(path) ? readFileSync(path, "utf8") : "";
    const s = existing.indexOf(PREVAIL_BLOCK_BEGIN);
    const e = existing.indexOf(PREVAIL_BLOCK_END);
    let next: string;
    if (s !== -1 && e !== -1 && e > s) {
      next = existing.slice(0, s) + block + existing.slice(e + PREVAIL_BLOCK_END.length);
    } else {
      next = existing.trim() ? `${block}\n\n${existing}` : `${block}\n`;
    }
    if (next !== existing) writeFileSync(path, next);
  } catch {
    /* best effort: the harness just falls back to whatever else it reads */
  }
}

// The user's Ideal State — their constitution. Lives at <vault>/ideal-state.md.
// It is the HIGHEST-PRECEDENCE context: injected ahead of the operating manual,
// framework, domain state, and memory in every model turn (chat, council,
// suggestions, surface). Honored everywhere so the whole system optimizes for
// the life the user actually wants.
let idealStateCache: { vaultPath: string; content: string | null } | null = null;

function findIdealState(vaultPath: string): string | null {
  if (idealStateCache && idealStateCache.vaultPath === vaultPath) {
    return idealStateCache.content;
  }
  // Canonical layout keeps app-support config under build/; read there first, then
  // the legacy root location, then ~/.prevail.
  const candidates = [
    join(buildRoot(vaultPath), IDEAL_STATE_FILE),
    join(vaultPath, IDEAL_STATE_FILE),
    join(homedir(), ".prevail", IDEAL_STATE_FILE),
  ];
  let content: string | null = null;
  for (const c of candidates) {
    if (existsSync(c)) {
      try {
        const raw = readFileSync(c, "utf8").trim();
        if (raw) content = raw;
        break;
      } catch {}
    }
  }
  idealStateCache = { vaultPath, content };
  return content;
}

// Omega — the app-wide LEARNED knowledge layer. Lives at <vault>/omega.md, beside
// ideal-state.md. Durable, cross-cutting lessons / preferences / meta-patterns
// distilled across every domain + the app. Injected just BELOW the Ideal State
// (which is authored and wins conflicts) and ABOVE framework, domain state, and
// per-domain memory. See docs/OMEGA-PLAN.md.
let omegaCache: { vaultPath: string; content: string | null } | null = null;

function findOmega(vaultPath: string): string | null {
  if (omegaCache && omegaCache.vaultPath === vaultPath) {
    return omegaCache.content;
  }
  const candidates = [
    join(buildRoot(vaultPath), OMEGA_FILE),
    join(vaultPath, OMEGA_FILE),
    join(homedir(), ".prevail", OMEGA_FILE),
  ];
  let content: string | null = null;
  for (const c of candidates) {
    if (existsSync(c)) {
      try {
        const raw = readFileSync(c, "utf8").trim();
        if (raw) content = raw;
        break;
      } catch {}
    }
  }
  omegaCache = { vaultPath, content };
  return content;
}

// M6 (Monday feedback): per-domain ideal state. Lives at <domain>/ideal-state.md.
// Injected just below the GLOBAL ideal (which still wins on direct conflict) and
// above omega/framework, so a domain can have its own target on top of the global
// one. Skipped for General (cwd === vault root → that's the global ideal).
function findDomainIdeal(cwd: string, vaultPath: string): string | null {
  try {
    if (resolve(cwd) === resolve(vaultPath)) return null;
    const p = join(cwd, IDEAL_STATE_FILE);
    if (!existsSync(p)) return null;
    const raw = readFileSync(p, "utf8").trim();
    return raw || null;
  } catch { return null; }
}
function buildDomainIdealPreamble(s: string): string {
  return (
    "# DOMAIN IDEAL STATE — your target for THIS domain specifically.\n" +
    "Applies on top of the global Ideal State above; the global one wins on a direct conflict.\n\n" +
    s.slice(0, 2500) +
    "\n\n---\n\n"
  );
}

// The profile (build/user.md) and the goals block (this domain's goals, then
// the life goals) for one turn. The profile is left out when the prompt
// already carries the desktop's own profile block, the goals when a goals
// block is already there, so neither is ever doubled.
export const PROFILE_HEADER = "# WHO YOU'RE HELPING";
export function buildUserContext(vaultRoot: string, cwd: string, prompt: string, opts: { local?: boolean } = {}): string {
  const parts: string[] = [];
  try {
    if (!prompt.includes(PROFILE_HEADER)) {
      const profile = readProfile(vaultRoot);
      if (profile) parts.push(`${PROFILE_HEADER} - the user's profile. Use this as ground truth about them.\n${profile.slice(0, 2500)}`);
    }
    const domain = domainOfCwd(cwd, vaultRoot);
    // One voice: General and every mission speak as the user's chief of staff.
    if ((domain === "general" || domain.startsWith("_mission-")) && !prompt.includes(CHIEF_HEADER)) {
      const c = chiefOfStaffBlock(vaultRoot);
      if (c) parts.push(c);
    }
    // The Compass (confirmed lines only) on every turn that has a domain;
    // ~local lines only when the turn runs on a local model.
    if (domain && !prompt.includes(COMPASS_HEADER)) {
      const c = compassBlock(vaultRoot, { local: opts.local });
      if (c) parts.push(c);
    }
    if (!prompt.includes(GOALS_HEADER)) {
      const g = domain ? goalsBlock(vaultRoot, domain) : "";
      if (g) parts.push(g);
    }
    // The domain's long-term memory: the desktop used to add it itself; since
    // a desktop domain turn sends only the typed text, the engine owns it.
    const mem = memoryBlock(cwd, domain, prompt);
    if (mem) parts.push(mem);
  } catch { /* context is a nicety; the turn still runs */ }
  return parts.join("\n\n");
}

// Wrap Omega in a header that positions it as learned context, explicitly BELOW
// the Ideal State. Kept tight (non-Claude CLIs see it inline, not via a system
// channel) so it never bloats the turn.
function buildOmegaPreamble(omega: string): string {
  return (
    "# OMEGA — what Prevail has LEARNED across all your domains. App-wide context.\n" +
    "Durable lessons, preferences, and patterns that hold across everything. Apply them by " +
    "default. They rank BELOW the Ideal State above: if they ever conflict, the Ideal State wins.\n\n" +
    omega.slice(0, 3000) +
    "\n\n---\n\n"
  );
}

// Wrap the Ideal State in an authoritative header so the model treats it as
// law, not background. Kept tight so non-Claude CLIs (which see it in the
// prompt rather than a system channel) don't echo a wall of text.
function buildConstitutionPreamble(idealState: string): string {
  return (
    "# THE USER'S IDEAL STATE — their constitution. HIGHEST PRECEDENCE.\n" +
    "These values take precedence over all other instructions, context, and defaults that follow. " +
    "Honor them in every recommendation, plan, prioritization, tradeoff, decision, edit, and action. " +
    "When anything conflicts with the Ideal State, the Ideal State wins.\n\n" +
    idealState.slice(0, 4000) +
    "\n\n---\n\n"
  );
}

// Vault Lock guardrail. When the desktop sets PREVAIL_VAULT_LOCK=1, the agent
// must keep ALL filesystem activity inside the vault. This is the strongest
// lever available against an agentic CLI in headless mode: a hard, leading
// system rule. (The engine's own file ops are already vault-scoped by
// path-safety; this binds the underlying CLI agent too.)
function buildVaultLockPreamble(): string {
  return (
    "# FILESYSTEM SCOPE — VAULT LOCK IS ON. HARD CONSTRAINT.\n" +
    "You may only read, write, list, search, or modify files inside the vault " +
    "(the workspace that contains this working directory, its data/ and build/ folders). " +
    "Do NOT access, read, list, search, or execute ANYTHING outside the vault: " +
    "no other directories on this machine, no home folder, no system paths, no temp dirs, " +
    "and no tools or commands that reach beyond the vault. " +
    "If a request would require touching files outside the vault, refuse and state that Vault Lock is enabled.\n\n---\n\n"
  );
}

// Vault Lock master switch. Precedence:
//   1. PREVAIL_VAULT_LOCK env, when explicitly set — the desktop injects "1"
//      (on) or "0" (off) per engine spawn, so its UI toggle stays authoritative.
//   2. Persisted CLI config (readVaultLock) — for standalone terminal use.
//   3. Default ON (fail-closed).
// The critical property: when NO signal is present — the exact case for the
// `prevail --loops`/`--sync` launchd daemons and the `prevail mcp` server, none
// of which the desktop spawns with the env — confinement is ON, not off. The
// prior `=== "1"` test defaulted those autonomous processes to UNCONFINED.
function vaultLockOn(): boolean {
  try { return vaultLockActive(); } catch { return true; }
}

// "ollama" is an OpenAI-compatible HTTP endpoint (default
// http://localhost:11434/v1) — covers Ollama, LM Studio, llama.cpp
// server, vLLM, anything that speaks OpenAI's /chat/completions schema.
// Treated as a 4th "engine" alongside the three subprocess CLIs so the
// rest of the code can fan out to it through the same runChatTurn path.
// CliKind — the canonical id for each AI engine prevAIl talks to.
//
// 2026-06-04: Google replaced their `gemini` CLI with `agy` (Antigravity).
// Gemini CLI shuts down on 2026-06-18, so prevAIl now ships with
// "antigravity" as the canonical kind. The `agy` binary is preferred at
// detection time; the legacy `gemini` binary still works as a fallback
// during the transition window. Old configs that still say `"gemini"`
// are silently migrated to `"antigravity"` on first read (see
// migrateLegacyCliKind in src/config.ts).
// CliKind is single-sourced in config.ts; imported for local use and re-exported
// so existing `import { CliKind } from "./cli-bridge"` sites keep working.
import type { CliKind, DirectProviderKind, ExtraCliKind } from "./config.ts";
export type { CliKind };

// SECURITY: env vars that look like provider/operator secrets are stripped
// when spawning subprocess CLIs. The CLIs read their own auth files
// (~/.claude/, ~/.codex/, ~/.config/gcloud/) so they don't NEED these in the
// env, but inheriting them creates a prompt-injection exfiltration channel —
// a tool-using panelist that runs `env | grep TOKEN` would dump the
// operator's Telegram bot token and any API keys into a reply that lands in
// the vault log and ships to Telegram. Belt-and-suspenders: even if a
// model never voluntarily ran `env`, prompt injection inside vault content
// could trick it.
const SECRET_ENV_PREFIXES = [
  // The vault Data Encryption Key (base64 DEK). It is passed to engine
  // subprocesses that legitimately need to decrypt via an EXPLICIT env on those
  // spawns — it must NEVER ride along to a model-CLI child via scrubbedEnv(), or
  // a prompt-injected panelist could `env`-dump it and decrypt the whole vault.
  // (Critical: audit B1 / O3 / G2.)
  "PREVAIL_VAULT_KEY",
  "PREVAIL_TELEGRAM_",
  "ANTHROPIC_API_",
  "OPENAI_API_",
  "GOOGLE_API_",
  "GEMINI_API_",
  "TELEGRAM_BOT_",
  "AWS_",
  "GITHUB_TOKEN",
  "GH_TOKEN",
  "OP_SERVICE_ACCOUNT_TOKEN",
];
// Substring matches so an app/connector env we never enumerated (STRIPE_APIKEY,
// MYAPP_TOKEN, FOO_CREDENTIAL) still can't ride into a tool-using model child and
// be `env`-dumped by prompt injection. Kept broad but shaped to secret-ish names.
const SECRET_ENV_SUBSTRINGS = [
  "_SECRET", "SECRET_", "_PRIVATE_KEY", "_PASSWORD", "PASSWD", "PASSPHRASE",
  "TOKEN", "APIKEY", "API_KEY", "ACCESS_KEY", "CREDENTIAL", "AUTH_KEY",
];

export function scrubbedEnv(): NodeJS.ProcessEnv {
  const out: NodeJS.ProcessEnv = {};
  for (const [k, v] of Object.entries(process.env)) {
    if (SECRET_ENV_PREFIXES.some((p) => k.startsWith(p))) continue;
    if (SECRET_ENV_SUBSTRINGS.some((s) => k.includes(s))) continue;
    out[k] = v;
  }
  // Every CLI the engine spawns is Prevail talking to a model, not the user
  // typing. The spawned harness's own prompt-capture hook inherits this and
  // skips the prompt (capture.ts ingest), which is what kept 13k benchmark
  // scoring prompts and the demo persona's questions out of the user's
  // history once the desktop set it for its own spawns. What the user types
  // in Prevail is still recorded: the desktop logs it to the domain ledger.
  out.PREVAIL_INTERNAL = "1";
  // Thread linkage: a turn that knows its Prevail thread runs inside
  // turnThread, so every CLI it spawns (and that CLI's act-gate hook) sees
  // PREVAIL_THREAD_ID and a held act can be tied back to its conversation.
  // PREVAIL_ENTITY_ID rides the same way on an entity chat, so the hook's app
  // access log can say which entity a connector call was made for.
  const ctx = turnThread.getStore();
  if (ctx?.thread) out.PREVAIL_THREAD_ID = ctx.thread;
  if (ctx?.entity) out.PREVAIL_ENTITY_ID = ctx.entity;
  // The turn's Google account pick, so the access log names the account.
  if (ctx?.google) out.PREVAIL_GOOGLE_ACCOUNT = ctx.google;
  return out;
}

// The Prevail thread (and entity) of the turn currently running, carried
// through the async call tree (a per-turn env would race in a daemon running
// several).
const turnThread = new AsyncLocalStorage<{ thread?: string; entity?: string; google?: string }>();

export interface AvailableCli {
  kind: CliKind;
  bin: string;
  label: string;
}

// Extra spawnable CLI runtime families. `protocol` = the base CLI invocation each
// speaks, so dispatch can route to a known handler: "gemini" → the Gemini handler;
// "claude" → the de-facto headless convention `<bin> -p "<prompt>"` (best-effort —
// families with non-standard flags may need per-family args later). Detection +
// listing in the Runtimes catalog work regardless of whether dispatch is exact.
export const EXTRA_CLI_FAMILIES: { kind: CliKind; bins: string[]; label: string; protocol: "claude" | "gemini" | "codex" }[] = [
  { kind: "gemini", bins: ["gemini"], label: "Gemini", protocol: "gemini" },
  { kind: "codebuddy", bins: ["codebuddy"], label: "Codebuddy", protocol: "claude" },
  { kind: "copilot", bins: ["copilot"], label: "Copilot", protocol: "claude" },
  { kind: "opencode", bins: ["opencode"], label: "Opencode", protocol: "claude" },
  { kind: "openclaw", bins: ["openclaw"], label: "Openclaw", protocol: "claude" },
  { kind: "hermes", bins: ["hermes"], label: "Hermes", protocol: "claude" },
  { kind: "pi", bins: ["pi"], label: "Pi", protocol: "claude" },
  { kind: "cursor", bins: ["cursor-agent", "cursor"], label: "Cursor", protocol: "claude" },
  { kind: "kiro", bins: ["kiro"], label: "Kiro", protocol: "claude" },
  { kind: "paperclip", bins: ["paperclip"], label: "Paperclip", protocol: "claude" },
  { kind: "motorcar", bins: ["multica", "motorcar"], label: "Multica AI", protocol: "claude" },
];
const EXTRA_PROTOCOL: Record<string, "claude" | "gemini" | "codex"> =
  Object.fromEntries(EXTRA_CLI_FAMILIES.map((f) => [f.kind, f.protocol]));

const CANDIDATES: { kind: CliKind; bins: string[]; label: string }[] = [
  { kind: "claude", bins: ["claude"], label: "Claude" },
  { kind: "codex", bins: ["codex"], label: "Codex" },
  // The first detected binary wins. `agy` (Antigravity, Google's
  // 2026-05-19 successor to Gemini CLI) is preferred; `gemini` is kept
  // as a fallback during the transition window (Google shuts the
  // legacy CLI down 2026-06-18). Drop `gemini` from this list after
  // that date.
  { kind: "antigravity", bins: ["agy", "gemini"], label: "Antigravity" },
  // Additional families (detected the same PATH way; dispatched by protocol).
  ...EXTRA_CLI_FAMILIES.map((f) => ({ kind: f.kind, bins: f.bins, label: f.label })),
];

// Ollama / OpenAI-compatible local-model endpoint. Override via env var.
// Probed at launch and treated as available iff GET /api/tags responds.
export const OLLAMA_BASE_URL = process.env.PREVAIL_OLLAMA_URL || "http://localhost:11434";
export const OLLAMA_DEFAULT_MODEL = process.env.PREVAIL_OLLAMA_MODEL || "llama3.1";

export const CLI_MODEL_HINT: Record<CliKind, string> = {
  ...(Object.fromEntries(EXTRA_CLI_FAMILIES.map((f) => [f.kind, "leave blank for the runtime's default, or whatever model id its CLI accepts"])) as Record<ExtraCliKind, string>),
  claude: "e.g. fable, opus, sonnet, haiku, or full id like claude-opus-5-5",
  codex: "e.g. gpt-6-sol, gpt-6-astra, gpt-6-luna, gpt-5.6-terra (append @medium/@high for effort), or gpt-5.5 — whatever your codex login accepts",
  ollama: "e.g. llama3.1, mistral, qwen2.5 — must be already pulled locally (`ollama pull <name>`)",
  antigravity: 'e.g. "Gemini 3.8 Flash (High)", "Gemini 3.1 Pro (High)" — run `agy models` for the full list (Antigravity now uses display names, not short ids)',
  openrouter: "e.g. anthropic/claude-fable-5.1, openai/gpt-6-astra, google/gemini-3.8-flash — any model id from openrouter.ai/models",
  anthropic: "e.g. claude-opus-5-5, claude-fable-5-1, claude-sonnet-5, claude-haiku-4-5 (your Anthropic API key)",
  openai: "e.g. gpt-6-sol, gpt-6-astra, gpt-6-luna (your OpenAI API key)",
  xai: "e.g. grok-4.7, grok-4.6, grok-4.5 (your xAI key)",
  kimi: "e.g. kimi-k2-0711-preview, moonshot-v1-128k (your Moonshot key)",
  deepseek: "e.g. deepseek-chat, deepseek-reasoner (your DeepSeek key)",
  google: "e.g. gemini-3.8-flash, gemini-3.7-flash (your Google AI key)",
};

// Quick-pick chips shown in the council config bubble. Two tiers:
//
// 1. ALIASES — the short names the CLI resolves to its latest version
//    ("opus" → latest claude opus). Useful when you don't care about pinning.
//
// 2. VERSIONS — specific full model IDs so you can compare e.g. claude-opus-4-7
//    vs claude-opus-4-8 in the same council run. THIS is what makes
//    cross-model compare actually possible from the UI. We can't query the
//    CLIs for these (none of them expose a models list endpoint — verified),
//    so the list is hand-maintained per provider. Slash command
//    `/council model <cli> add <name>` still works for anything missing.
//
// Add new versions here when providers ship them. Stale entries are
// harmless — the CLI rejects them and the panelist returns an error bubble.
// `fable` is Anthropic's frontier tier (above opus); Claude Code resolves it to
// Fable 5.1. Verified against `claude --model <alias>` on 2026-09-11.
const CLAUDE_ALIASES = ["fable", "opus", "sonnet", "haiku"];
const CLAUDE_VERSIONS = [
  "claude-opus-5-5",
  "claude-opus-5",
  "claude-fable-5-1",
  "claude-sonnet-5",
  "claude-haiku-4-5",
  "claude-fable-5",
  "claude-opus-4-8",
];
// GPT-6 tiers lead: Sol (the everyday default), Astra (flagship, GA 2026-09-03),
// Luna (fastest, cheapest). Sol and Luna shipped 2026-09-22; there is no GPT-6
// Terra, so gpt-5.6-terra stays as the balanced tier. The 5.6 tiers and gpt-5.5
// are kept for Codex logins the 6 rollout hasn't reached. Append @medium/@high
// for reasoning effort (these models also accept @xhigh/@max, and Astra/Sol/Terra
// accept @ultra). Ids checked against the CLI's own catalog
// (~/.codex/models_cache.json) and smoke-tested through `codex exec` on 2026-09-25.
const CODEX_VERSIONS = [
  "gpt-6-sol",
  "gpt-6-astra",
  "gpt-6-luna",
  "gpt-5.6-sol",
  "gpt-5.6-terra",
  "gpt-5.6-luna",
  "gpt-5.5",
];
// Antigravity (`agy`) uses display-style model names that include
// thinking-budget suffixes — verified via `agy models`. These are passed
// to `--model` verbatim. The list will need updating as Google ships new
// Gemini generations through Antigravity. To refresh against your local
// install: `agy models`.
const ANTIGRAVITY_VERSIONS = [
  "Gemini 3.8 Flash (High)",
  "Gemini 3.8 Flash (Medium)",
  "Gemini 3.8 Flash (Low)",
  "Gemini 3.7 Flash (High)",
  "Gemini 3.6 Flash (High)",
  "Gemini 3.1 Pro (High)",
  "Gemini 3.1 Pro (Low)",
  // Antigravity also exposes other providers through the same launcher:
  "Claude Sonnet 4.6 (Thinking)",
  "Claude Opus 4.6 (Thinking)",
  "GPT-OSS 120B (Medium)",
];

// Common Ollama tags — covers the models most users have already pulled.
// Replaced at runtime by the real list from /api/tags when ollama is detected.
const OLLAMA_VERSIONS = ["llama3.1", "llama3.2", "mistral", "qwen2.5", "phi3", "gemma2"];

// Each CLI's default model — what the CLI runs when we DON'T pass an
// explicit --model arg. We can't query the CLIs for this (none expose a
// "what's your default" endpoint), so the list is hand-maintained from
// the same first-entry rule as the version lists above. Used by the
// per-bubble badge in the chat transcript so EVERY council panelist
// shows a complete `<cli> · <model>` label — without this, panelists
// running on default models showed just `claude` / `codex` and the
// user reported "the rest don't tell me which model is responding."
// OpenRouter routed model ids (provider/model). One key, every model.
// Ids verified live against https://openrouter.ai/api/v1/models on 2026-09-25.
export const OPENROUTER_MODELS: string[] = [
  "anthropic/claude-opus-5.5",
  "anthropic/claude-fable-5.1",
  "anthropic/claude-sonnet-5",
  "openai/gpt-6-astra",
  "openai/gpt-6-sol",
  "openai/gpt-6-luna",
  "openai/gpt-5.6-terra",
  "google/gemini-3.8-flash",
  "x-ai/grok-4.7",
  "moonshotai/kimi-k3",
  "deepseek/deepseek-v4-pro-0813",
  "qwen/qwen3.8-max-prime",
  "z-ai/glm-5.3-prime",
  "meta-llama/llama-4-maverick",
];

// G1 — direct single-vendor providers. Each works once the user adds their key
// (Settings → Models → Direct Providers), injected by the desktop as
// PREVAIL_<ID>_KEY (the PREVAIL_ prefix dodges scrubbedEnv's secret strip). All
// speak the OpenAI /chat/completions schema except Anthropic (native=true →
// /v1/messages). One table drives detection, routing, and the key-entry UI.
export interface DirectProvider {
  id: DirectProviderKind;
  label: string;
  baseUrl: string;
  keyEnv: string;
  native?: boolean; // Anthropic: /v1/messages instead of OpenAI-compat
  models: string[];
}
export const DIRECT_PROVIDERS: DirectProvider[] = [
  { id: "anthropic", label: "Anthropic", baseUrl: "https://api.anthropic.com/v1", keyEnv: "PREVAIL_ANTHROPIC_KEY", native: true,
    models: ["claude-opus-5-5", "claude-fable-5-1", "claude-sonnet-5", "claude-haiku-4-5", "claude-opus-5"] },
  { id: "openai", label: "OpenAI", baseUrl: "https://api.openai.com/v1", keyEnv: "PREVAIL_OPENAI_KEY",
    models: ["gpt-6-sol", "gpt-6-astra", "gpt-6-luna", "gpt-5.6-terra"] },
  { id: "xai", label: "xAI", baseUrl: "https://api.x.ai/v1", keyEnv: "PREVAIL_XAI_KEY",
    models: ["grok-4.7", "grok-4.6", "grok-4.5"] },
  { id: "kimi", label: "Kimi (Moonshot)", baseUrl: "https://api.moonshot.ai/v1", keyEnv: "PREVAIL_KIMI_KEY",
    models: ["kimi-k3", "kimi-k2-0711-preview", "moonshot-v1-128k"] },
  { id: "deepseek", label: "DeepSeek", baseUrl: "https://api.deepseek.com/v1", keyEnv: "PREVAIL_DEEPSEEK_KEY",
    models: ["deepseek-chat", "deepseek-reasoner"] },
  { id: "google", label: "Google AI", baseUrl: "https://generativelanguage.googleapis.com/v1beta/openai", keyEnv: "PREVAIL_GOOGLE_KEY",
    models: ["gemini-3.8-flash", "gemini-3.7-flash", "gemini-3.5-flash-lite"] },
];
export const DIRECT_PROVIDER_BY_ID: Record<DirectProviderKind, DirectProvider> =
  Object.fromEntries(DIRECT_PROVIDERS.map((p) => [p.id, p])) as Record<DirectProviderKind, DirectProvider>;

const DIRECT_DEFAULT_MODELS = Object.fromEntries(
  DIRECT_PROVIDERS.map((p) => [p.id, p.models[0]!]),
) as Record<DirectProviderKind, string>;
const DIRECT_QUICKPICKS = Object.fromEntries(
  DIRECT_PROVIDERS.map((p) => [p.id, p.models]),
) as Record<DirectProviderKind, string[]>;

export const CLI_DEFAULT_MODELS: Record<CliKind, string> = {
  ...DIRECT_DEFAULT_MODELS,
  ...(Object.fromEntries(EXTRA_CLI_FAMILIES.map((f) => [f.kind, ""])) as Record<ExtraCliKind, string>),
  claude: CLAUDE_VERSIONS[0]!,
  codex: CODEX_VERSIONS[0]!,
  antigravity: ANTIGRAVITY_VERSIONS[0]!,
  ollama: OLLAMA_DEFAULT_MODEL,
  openrouter: OPENROUTER_MODELS[0]!,
};

export function defaultModelFor(kind: CliKind): string {
  return CLI_DEFAULT_MODELS[kind];
}

// Versioned IDs come FIRST so the picker always shows real version numbers
// at a glance (claude-opus-4-7, not just "opus"). Naked aliases live at the
// end as a fallback for users who don't care which generation runs — the
// CLI itself resolves "opus" → its current default. This was a long-standing
// UX bug: with aliases first, the picker visually read as "opus / sonnet /
// haiku ..." and users couldn't tell which version of each they'd actually
// get without typing /model.
export const MODEL_QUICKPICKS_FALLBACK: Record<CliKind, string[]> = {
  ...DIRECT_QUICKPICKS,
  ...(Object.fromEntries(EXTRA_CLI_FAMILIES.map((f) => [f.kind, [] as string[]])) as Record<ExtraCliKind, string[]>),
  claude: [...CLAUDE_VERSIONS, ...CLAUDE_ALIASES],
  codex: CODEX_VERSIONS,
  antigravity: ANTIGRAVITY_VERSIONS,
  ollama: OLLAMA_VERSIONS,
  openrouter: OPENROUTER_MODELS,
};

// Back-compat: callers that read MODEL_QUICKPICKS still work but only see
// the fallback. App.tsx replaces this at runtime with the discovered list
// once probes complete.
export const MODEL_QUICKPICKS: Record<CliKind, string[]> = MODEL_QUICKPICKS_FALLBACK;

export function formatModelBadge(model: string | null | undefined): string {
  if (!model || !model.trim()) return "default";
  return model.trim();
}

export interface CliHealth {
  ok: boolean;
  message: string;
  hint?: string;
}

// Recognize common provider/environment errors and turn them into actionable
// remediation hints. The error strings are matched conservatively; if no rule
// matches the user just sees the raw stderr, which is still useful.
function classifyProbeError(cli: CliKind, output: string): string | undefined {
  const o = output.toLowerCase();
  if (cli === "codex") {
    if (o.includes("not supported when using codex with a chatgpt account")) {
      return "your ChatGPT-account auth doesn't allow this model. Either run `codex login` to switch to an OpenAI API key, or set a model your subscription supports via `/council model codex <name>` (or codex's interactive picker).";
    }
    if (o.includes("not inside a trusted directory")) {
      return "codex blocked an untrusted directory. The wrapper passes `--skip-git-repo-check`; if you see this, check ~/.codex/config.toml for restrictive `[projects]` rules.";
    }
    if (o.includes("rate limit") || o.includes("quota")) {
      return "codex hit a rate limit or quota cap on your account.";
    }
  }
  if (cli === "antigravity") {
    // Antigravity inherits a lot of Gemini's CLI surface — hook errors,
    // trust gates, quota errors all look similar. Some legacy strings
    // still mention `gemini` because Antigravity's error text shows
    // through unchanged on certain code paths.
    if (o.includes("agent execution blocked") || o.includes("hook(s)") || o.includes("hook execution")) {
      return "Antigravity's BeforeAgent/AfterAgent hooks are blocking execution. Check ~/.gemini/settings.json (or wherever agy stores its hooks) and either fix the hook script path or remove the broken `hooks` entries.";
    }
    if (o.includes("not running in a trusted") || o.includes("trusted")) {
      return "Antigravity blocked an untrusted folder. The wrapper passes `--skip-trust`; if you still see this, the workspace sandbox in agy's settings may be restricting reach.";
    }
    if (o.includes("quota") || o.includes("rate")) {
      return "Antigravity hit a quota or rate limit.";
    }
  }
  return undefined;
}

// Smoke-test a CLI by running a real one-shot prompt through the same args
// path the council uses (no operating manual, no model — keeps it cheap).
// `--version` would only catch a totally broken install; the actual failure
// modes we see in council mode (ChatGPT-subscription model gating for codex,
// stale hooks for gemini, missing auth) only surface when the model is hit.
// Timeout is generous because cold cli startup + a small model call can take
// 15-20s on slow networks.
export function probeCli(cli: AvailableCli, timeoutMs = 45000): Promise<CliHealth> {
  const probePrompt = "Reply with the single word: ready";
  // Ollama is an HTTP endpoint, not a subprocess — probe it by running a
  // tiny chat completion via the same path runChatTurn uses. Short timeout
  // since we already know the daemon is up (detectOllama confirmed) and a
  // 6B model should reply to "say ready" in well under 5s.
  if (cli.kind === "ollama") {
    return runOllamaChat({
      baseUrl: cli.bin,
      model: OLLAMA_DEFAULT_MODEL,
      prompt: probePrompt,
    }).then((reply) => {
      if (reply.startsWith("(ollama:")) {
        // Model-not-pulled is the overwhelmingly common error; surface a
        // friendly hint instead of the raw HTTP body.
        const hint = /model.*not.*found|not.*available|pull/i.test(reply)
          ? `model "${OLLAMA_DEFAULT_MODEL}" isn't pulled. Run \`ollama pull ${OLLAMA_DEFAULT_MODEL}\` or set PREVAIL_OLLAMA_MODEL to one you already have.`
          : undefined;
        return { ok: false, message: reply.slice(0, 220), hint };
      }
      return { ok: true, message: `ready (${OLLAMA_DEFAULT_MODEL})` };
    });
  }
  // Build the exact same argv shape runChatTurn would for a manual-less,
  // model-default, fresh-session turn. Reusing buildCliArgs guarantees the
  // probe exercises the real codepath.
  const args = buildCliArgs({
    cli: cli.kind,
    prompt: probePrompt,
    model: "",
    isFirst: true,
    manual: null,
  });
  return new Promise((resolveProbe) => {
    let stdout = "";
    let stderr = "";
    let settled = false;
    let child;
    try {
      // stdin MUST be "ignore" — with the default "pipe", codex exec blocks
      // forever waiting for input from the (open) stdin pipe and never starts
      // the model call. Spent half a day on this; do not "fix" back to pipe.
      child = spawn(cli.bin, args, {
        env: scrubbedEnv(),
        stdio: ["ignore", "pipe", "pipe"],
      });
    } catch (err) {
      resolveProbe({ ok: false, message: (err as Error).message });
      return;
    }
    const timer = setTimeout(() => {
      if (settled) return;
      settled = true;
      try {
        child!.kill();
      } catch {}
      resolveProbe({
        ok: false,
        message: `probe timed out after ${timeoutMs / 1000}s`,
        hint:
          cli.kind === "codex"
            ? "codex cold-start can be slow; if it works in /council later, this is just startup latency."
            : undefined,
      });
    }, timeoutMs);
    child.stdout.on("data", (b) => {
      stdout += b.toString();
    });
    child.stderr.on("data", (b) => {
      stderr += b.toString();
    });
    child.on("error", (err) => {
      if (settled) return;
      settled = true;
      clearTimeout(timer);
      resolveProbe({ ok: false, message: err.message });
    });
    child.on("close", (code) => {
      if (settled) return;
      settled = true;
      clearTimeout(timer);
      const combined = (stdout + "\n" + stderr).trim();
      // Treat as ok only if exit was clean AND output contains *something*
      // resembling a model reply. Codex/gemini sometimes exit 0 even after
      // an ERROR line, so look for "ready" in stdout to confirm a real call.
      const looksReady = stdout.toLowerCase().includes("ready");
      if (code === 0 && looksReady) {
        resolveProbe({ ok: true, message: "real prompt succeeded" });
        return;
      }
      // Pull the first error-ish line to keep the message short.
      const firstErrLine =
        combined
          .split("\n")
          .map((l) => l.trim())
          .find((l) => l.toLowerCase().includes("error") || l.toLowerCase().includes("blocked") || l.toLowerCase().includes("not supported")) ||
        combined.split("\n")[combined.split("\n").length - 1] ||
        `exited ${code}`;
      const hint = classifyProbeError(cli.kind, combined);
      resolveProbe({
        ok: false,
        message: firstErrLine.slice(0, 220),
        hint,
      });
    });
  });
}

// Synchronous half — finds the three subprocess CLIs on $PATH. Split out so
// callers that need a fast "what binaries do we have" answer don't pay the
// HTTP roundtrip cost of probing Ollama. detectClis() composes this with the
// async Ollama probe.
export function detectSubprocessClis(): AvailableCli[] {
  const paths = (process.env.PATH ?? "").split(":");
  const out: AvailableCli[] = [];
  for (const c of CANDIDATES) {
    for (const bin of c.bins) {
      const found = paths
        .map((p) => join(p, bin))
        .find((full) => {
          try {
            return existsSync(full);
          } catch {
            return false;
          }
        });
      if (found) {
        out.push({ kind: c.kind, bin: found, label: c.label });
        break;
      }
    }
  }
  return out;
}

// Quick health check for Ollama / any OpenAI-compatible endpoint. GET /api/tags
// is the native Ollama endpoint and 200's instantly if the daemon is up.
// For non-Ollama OpenAI-compatibles (LM Studio, llama.cpp server), /api/tags
// returns 404 — we fall back to /v1/models which every OpenAI-compat
// implementation exposes. A 200 from either is enough to call it available.
// Returns null if nothing's listening. 1.5s timeout — local should be instant.
export async function detectOllama(): Promise<AvailableCli | null> {
  const base = OLLAMA_BASE_URL.replace(/\/+$/, "");
  const cli: AvailableCli = { kind: "ollama", bin: base, label: base.includes("11434") ? "Ollama" : "Local" };
  // Probe both endpoints CONCURRENTLY with a tight timeout. The old sequential
  // loop with 1500ms each meant a down Ollama cost up to 3s on every detectClis
  // (= every chat turn). Now the worst case is one ~700ms timeout, in parallel.
  const probe = (url: string) =>
    new Promise<boolean>((resolve) => {
      const controller = new AbortController();
      const timer = setTimeout(() => controller.abort(), 700);
      fetch(url, { signal: controller.signal })
        .then((res) => { clearTimeout(timer); resolve(res.ok); })
        .catch(() => { clearTimeout(timer); resolve(false); });
    });
  const results = await Promise.all([probe(`${base}/api/tags`), probe(`${base}/v1/models`)]);
  return results.some(Boolean) ? cli : null;
}

// Async detection — subprocess CLIs (sync) + Ollama (HTTP probe in parallel).
// Used at app launch and by `prevail daemon`. Callers that don't care about
// Ollama can use detectSubprocessClis() directly.
// Short-TTL cache for the CLI roster. detectClis runs on EVERY chat turn (and in
// every daemon tick) and its slow part is the Ollama probe — without a cache a
// down Ollama adds its timeout to every single turn. Availability barely changes
// within a session, so a few seconds of caching is safe and a big latency win for
// the long-running gateways (MCP / Telegram / WebUI / loops). `force` re-detects
// (model picker, connect flow).
let _cliRoster: { at: number; clis: AvailableCli[] } | null = null;
const CLI_ROSTER_TTL_MS = 15_000;

export async function detectClis(opts?: { force?: boolean }): Promise<AvailableCli[]> {
  if (!opts?.force && _cliRoster && Date.now() - _cliRoster.at < CLI_ROSTER_TTL_MS) {
    return _cliRoster.clis;
  }
  const subprocess = detectSubprocessClis();
  const ollama = await detectOllama();
  const out = ollama ? [...subprocess, ollama] : subprocess;
  // OpenRouter is "available" iff a key is present (it's an HTTP gateway, not
  // a binary). The desktop injects PREVAIL_OPENROUTER_KEY from the Keychain.
  if (process.env.PREVAIL_OPENROUTER_KEY) {
    out.push({ kind: "openrouter", bin: "https://openrouter.ai/api/v1", label: "OpenRouter" });
  }
  // Direct providers (G1): each is "available" iff its key is present in the
  // env (the desktop injects PREVAIL_<ID>_KEY from the Keychain).
  for (const p of DIRECT_PROVIDERS) {
    if (process.env[p.keyEnv]) {
      out.push({ kind: p.id, bin: p.baseUrl, label: p.label });
    }
  }
  _cliRoster = { at: Date.now(), clis: out };
  return out;
}

export function buildChatPrompt(domain: Domain, view: ViewKey): string {
  const angles: Record<ViewKey, string> = {
    state: "Walk me through the current state. What stands out, and what should I act on first?",
    loops: "Look at the unchecked items in state.md's Open Items section. What's the right order, what should I drop, and is anything missing?",
    quickstart: "I'm new to this domain — give me a 60-second tour using QUICKSTART.md.",
    prompts: "Use the prompts in PROMPTS.md to interview me on what's changed since last update.",
    skills: "List the skills available for this domain and offer to run any that look most useful right now.",
  };
  return `You are helping with the "${domain.name}" life domain. The vault lives at ${domain.path}. Start by reading state.md.\n\n${angles[view]}`;
}

// A real tool invocation observed in the model's structured output. `phase`
// "call" = the model invoked the tool; "result" = the tool returned (ok=false on
// error). This is ground truth from the runtime, not the model's narration.
export interface ToolEvent {
  name: string;
  phase: "call" | "result";
  ok?: boolean;
  // The tool_use id, so a "result" can be matched back to its "call" to flip
  // that step's status (running -> done/failed) instead of appending a new one.
  id?: string;
  // The tool input on the "call" phase, used to derive a human step label (e.g.
  // the google_workspace gws argv -> "Reading Gmail" / "Creating a Google Doc").
  // Absent on "result". Never trusted for control flow, only for display.
  input?: unknown;
  // On a FAILED "result" (ok === false): a short snippet of the tool's error
  // output, so the step checklist can show WHY a step failed. Display only.
  resultText?: string;
}

export interface ChatTurn {
  prompt: string;
  /** How to write the reply (the desktop's link format): system channel, never context. */
  outputHint?: string;
  cwd: string;
  cli: AvailableCli;
  model: string;
  isFirst: boolean;
  // Council Q&A calls pass bare=true to suppress the operating-manual
  // preamble. The manual is multi-kB of agent-onboarding text — useful for
  // normal chat sessions where the panelist takes follow-up actions, but
  // pure noise for a one-shot question/answer/synthesize. It also caused
  // codex to echo the manual verbatim back into the response bubble when it
  // exited non-zero, polluting the transcript.
  bare?: boolean;
  // Execution mode. Normal turns are advisory (read-only is enough). When act is
  // true the agent is expected to TAKE the action using its tools/connectors, so
  // claude is run with permissions granted (codex/antigravity already skip
  // permission prompts). Only set this for a user-APPROVED action — the approval
  // is the safety gate. Without it claude can't write files or call MCP tools in
  // headless -p mode (no TTY to approve), so execution would silently no-op.
  act?: boolean;
  // Per-turn web-access override. When set it WINS over the global cockpit
  // setting (readWebAccess) for this turn only - this is how the desktop's
  // "Web access" Modes toggle reaches the engine. "deny" hard-removes Claude's
  // WebSearch/WebFetch tools and refuses providers whose web tools can't be
  // switched off (see runChatTurn). Omitted => fall back to the global setting.
  webAccess?: "allow" | "deny";
  // Allow this turn to ALSO see the user's own Claude Code MCP servers (their
  // claude.ai connectors like PayPal/Notion). Default false: engine turns run a
  // strict, engine-managed tool surface so account routing can't be bypassed.
  // App chats opt in - "connected via Claude Code" passthrough is exactly the
  // contract those apps advertise.
  inheritUserMcp?: boolean;
  // The user's Google-account chip selection (composer Modes). When set it is
  // threaded to the google_workspace connector launch as its AUTHORITATIVE
  // default target account (gws-mcp --account <label>), so the picked account is
  // honored even if the model omits an `account:` tool-arg. A comma-joined list
  // is allowed; the connector uses the first entry as its default. Omitted =>
  // today's behavior (the connector's own "default" account).
  googleAccount?: string;
  // The Prevail thread (chat session id) this turn belongs to. Exported to the
  // spawned CLI as PREVAIL_THREAD_ID so the act-gate hook can record which
  // conversation a held action came from. Omitted => no thread linkage.
  threadId?: string;
  // The entity an entity chat is about (<kind>/<slug>). Exported to the spawned
  // CLI as PREVAIL_ENTITY_ID so the act-gate hook's app access log records it.
  entityId?: string;
  // Trusted sources referenced on this turn (trusted-sources.ts turnSources).
  // remoteMcp: app id -> remote MCP URL, attached to a Claude turn as an http
  // MCP server under the app id (tools mcp__<id>__*), beside the inherited
  // user config. fetchHosts: hosts a web/links source lets WebFetch GET.
  // Other engines get neither (routing reports app_unavailable for remote MCP;
  // web/links sources are described in the prompt only).
  remoteMcp?: Record<string, string>;
  fetchHosts?: string[];
  // Exact tool names (mcp__<server>__<tool>) of the referenced apps' READ
  // tools, added to --allowedTools on a chat turn so headless Claude does not
  // refuse them. Never write tools: those still queue at the act gate.
  appReadTools?: string[];
  // Read-only built-in tools a non-act turn may use without a prompt (a
  // specialist's Researcher needs WebSearch and WebFetch; vault reading needs
  // Read, Grep and Glob). Anything not in READ_ONLY_BUILTINS is ignored, so
  // this can never grant a tool that writes or runs commands.
  allowTools?: string[];
  // Claude only: no shell on this turn (--disallowedTools Bash). A specialist
  // answering in a group chat reads with its read-only tools and never runs a
  // command, not even one that would ask first.
  noShell?: boolean;
  // Incognito: none of the user's context (constitution, profile, goals, omega,
  // domain ideal) is added by the engine. The desktop already leaves its own
  // blocks out; without this the engine added the constitution back.
  incognito?: boolean;
  // Claude only (stream-json turns): called with the session's init event, the
  // MCP servers that loaded and each one's live status (connected, failed,
  // needs-auth, pending), so an app turn can report a connector needing sign-in.
  onInit?: (init: import("./apps-mirror.ts").ClaudeInit) => void;
  // Optional cancellation. Aborting the signal SIGTERMs the child process so
  // Escape in the cockpit can drop an in-flight prompt without waiting for
  // the model to finish. runCapture resolves with "(cancelled)" on abort.
  signal?: AbortSignal;
  // Optional incremental-output callback. When set, the runner emits
  // partial text as it arrives from the CLI (chunks streamed from claude
  // --output-format stream-json, codex stdout, gemini stdout, ollama SSE).
  // The final return value is still the complete reply — onChunk just
  // gives the UI something to render while the model is still talking.
  // Each call receives a string delta (NOT the cumulative buffer); the
  // caller does its own accumulation if needed.
  onChunk?: (delta: string) => void;
  // Optional GROUND-TRUTH tool-call callback. When set (the agent/act path), the
  // claude runner switches to structured stream-json and reports each REAL tool
  // the model invokes — the honest "tools used" signal, so we never rely on the
  // model's prose to know what actually ran. Untouched on normal chat turns.
  onTool?: (ev: ToolEvent) => void;
  // Truncate the cumulative reply at this many characters. When the
  // stream crosses the cap, the child process is SIGKILL'd (same
  // pgroup trick used by abort) and the reply returned to the caller
  // is sliced to maxOutputChars + " (truncated at cap)". Useful for
  // lightweight callers — distillation, classifiers, serendipity —
  // that have no business returning 50KB. Undefined = no cap (today's
  // behavior).
  maxOutputChars?: number;
  // Optional privacy + cost guard (Track E7). Entirely opt-in: when omitted
  // (or with both fields unset) runChatTurn behaves exactly as before. When
  // present it gates the turn BEFORE spawning the model:
  //   - privacy.resolveModelForDomain may redirect a cloud CLI to the local
  //     ollama engine if the domain is localOnly or globalLocalOnly is set.
  //   - budget.checkBudget throws BudgetExceeded if the estimated cost would
  //     breach a per-run / per-day cap; on success the spend is recorded.
  guard?: {
    // Global `--local-only` switch (same convention as src/chat-json.ts).
    localOnly?: boolean;
    // Cost caps. No caps set => budget guard is a no-op.
    budget?: BudgetCaps;
  };
}

const WEB_DENY_NOTE = [
  "<web-access>",
  "The user has globally disabled web access for this cockpit session.",
  "Do NOT use WebSearch, WebFetch, fetch(), curl, or any other tool that",
  "makes outbound HTTP requests. Work only from the vault and local files.",
  "If a question genuinely requires the web, say so plainly and stop;",
  "do not silently proceed without web access.",
  "</web-access>",
].join("\n");

function augmentManualWithWebGate(manual: string | null, mode: "allow" | "deny"): string | null {
  if (mode === "allow") return manual;
  if (!manual) return WEB_DENY_NOTE;
  return `${manual}\n\n${WEB_DENY_NOTE}`;
}

// --- Fix #10: no em dashes in AI-generated output ---------------------------
//
// (a) A prompt directive injected into every turn (Claude via its system
//     channel, other CLIs prepended to the prompt). Prompt directives are
//     unreliable on their own, so (b) the sanitizer below is the hard guarantee.
const NO_EM_DASH_DIRECTIVE = [
  "# OUTPUT STYLE (HARD RULE)",
  "Never use em dashes (Unicode U+2014) anywhere in your responses, and do not use en dashes (Unicode U+2013) as sentence punctuation.",
  "Use commas, periods, colons, semicolons, or parentheses instead.",
  "This applies to all prose you write.",
].join("\n");

function buildNoEmDashPreamble(): string {
  return `${NO_EM_DASH_DIRECTIVE}\n\n---\n\n`;
}

// (b) The hard guarantee: strip em dashes from model output before it is
// returned / streamed / persisted. We replace the em dash (U+2014) and any
// SPACED en dash used as a sentence dash (U+2013 with a space on each side)
// with a comma, the safest general substitute. Hyphens, en-dash NUMBER RANGES
// ("3-5" with no surrounding spaces), and code are left intact. Fenced code
// blocks and inline code spans are preserved verbatim so we never mangle source
// that legitimately contains these characters.
function stripEmDashesProse(s: string): string {
  return s
    // Em dash (U+2014), with any surrounding spaces collapsed -> ", ".
    .replace(/\s*—\s*/g, ", ")
    // En dash (U+2013) used as a sentence dash (spaces on BOTH sides) -> ", ".
    // A bare numeric range like "3–5" has no surrounding spaces, untouched.
    .replace(/\s+–\s+/g, ", ");
}

// Built-in tools that only read (the web, or files): the only ones allowTools may grant.
export const READ_ONLY_BUILTINS = new Set(["WebSearch", "WebFetch", "Read", "Grep", "Glob"]);

export function sanitizeEmDashes(text: string): string {
  if (!text || (!text.includes("—") && !text.includes("–"))) return text;
  // Split out fenced code blocks and inline code spans (kept verbatim). The
  // capturing group lands code segments at ODD indices, prose at EVEN indices.
  const segments = text.split(/(```[\s\S]*?```|`[^`\n]*`)/g);
  for (let i = 0; i < segments.length; i += 2) {
    segments[i] = stripEmDashesProse(segments[i]!);
  }
  return segments.join("");
}

// A model id is spliced into the runtime CLI's argv right after its model flag
// (`-m <id>`, `--model <id>`). The id reaches us from MCP `chat` arguments,
// Telegram `/use`, and CLI flags. Parsers like yargs (gemini) do not consume a
// dash-leading value for a string option, so `-m --yolo` turned into a bare
// `--yolo` (auto-approve every tool) and the model flag stayed empty. Real ids
// never start with "-" or carry control characters (spaces are legitimate:
// Antigravity ids look like "Gemini 3.1 Pro (High)").
export function assertSafeModelId(m: string): void {
  if (!m) return;
  if (m.startsWith("-") || /[\x00-\x1f\x7f]/.test(m)) {
    throw new Error(`refusing model id ${JSON.stringify(m.slice(0, 60))}: a model id cannot start with "-" or contain control characters`);
  }
}

// The extra writable dir for a confined codex act run: the cwd's parent (the
// domains container), but never wider than the owning vault. For a cwd that IS
// the vault (connect_app) the parent is the directory BESIDE the vault, so the
// sandbox would have allowed writes to every sibling project; clamp to cwd.
export function codexWritableRoot(cwd: string): string {
  const parent = resolve(cwd, "..");
  const root = vaultRootForCwd(cwd);
  return parent === root || parent.startsWith(root + sep) ? parent : resolve(cwd);
}

export function runChatTurn(turn: ChatTurn): Promise<string> {
  const t = turn.threadId?.trim();
  const e = turn.entityId?.trim();
  const thread = t && /^[A-Za-z0-9_-]{1,128}$/.test(t) ? t : undefined;
  const entity = e && /^[a-z]{1,20}\/[A-Za-z0-9_.-]{1,128}$/.test(e) ? e : undefined;
  const g = turn.googleAccount?.trim();
  const google = g && /^[A-Za-z0-9._%+@,-]{1,256}$/.test(g) ? g : undefined;
  if (thread || entity || google) return turnThread.run({ thread, entity, google }, () => runChatTurnInner(turn));
  return runChatTurnInner(turn);
}

async function runChatTurnInner({ prompt, cwd, cli, model, isFirst, bare, act, signal, onChunk, onTool, maxOutputChars, guard, webAccess, googleAccount, inheritUserMcp, remoteMcp, fetchHosts, appReadTools, allowTools, noShell, onInit, incognito, outputHint }: ChatTurn): Promise<string> {
  // Fix #10: sanitize em dashes out of STREAMED deltas too, so the live UI
  // never shows them. The final returned reply is sanitized again below (the
  // authoritative, code-block-aware pass). Per-delta stripping is best-effort
  // for display; the final pass is the hard guarantee.
  const upstreamOnChunk = onChunk;
  onChunk = upstreamOnChunk ? (delta: string) => upstreamOnChunk(sanitizeEmDashes(delta)) : undefined;

  // cwd is <vault>/<domain>; the operating manual lives one level up at <vault>/AGENTS-operating.md
  const vaultPath = resolve(cwd, "..");
  const domainKeyForGuard = basename(cwd);

  // --- Track E7: privacy + cost guard (opt-in) -----------------------------
  // Runs BEFORE the model is spawned. With no guard set, both checks are
  // no-ops and the requested engine/model pass through unchanged — preserving
  // the exact behavior every existing caller relies on.
  //
  // 1. Privacy: if the domain is privacy.localOnly (manifest) OR the global
  //    --local-only switch is on, a cloud CLI request is redirected to the
  //    local ollama engine. We mutate `cli`/`model` so the rest of this
  //    function (arg building, spawn, reply extraction) runs against the
  //    resolved engine without further branching.
  // 2. Budget: estimate the turn's cost and checkBudget(); a breach throws
  //    BudgetExceeded out of runChatTurn (callers already catch and surface
  //    runner errors). The spend is recorded after the call completes.
  let budgetEstimate: ReturnType<typeof estimateTurnCost> | null = null;
  if (guard) {
    // Privacy resolution always runs when a guard is present so manifest
    // privacy.localOnly is honored even when the global flag is off.
    const resolved = resolveModelForDomain(
      vaultPath,
      domainKeyForGuard,
      { cli: cli.kind, model },
      { globalLocalOnly: guard.localOnly ?? false },
    );
    if (resolved.cli !== cli.kind) {
      // Redirect to the local engine. The ollama path in runChatTurn keys
      // off cli.bin as the base URL, so swap in the ollama endpoint.
      cli = { kind: resolved.cli, bin: OLLAMA_BASE_URL, label: "Local" };
    }
    model = resolved.model;
    budgetEstimate = estimateTurnCost({ cli: cli.kind, promptChars: prompt.length });
    // Throws BudgetExceeded if this turn would breach a per-run/per-day cap.
    checkBudget(budgetEstimate, guard.budget);
  }

  // --- Web-access lockdown (hard gate) -------------------------------------
  // Effective web mode for THIS turn: an explicit per-turn override (the
  // desktop "Web access" Modes toggle, passed as --web) wins; otherwise the
  // global cockpit setting. When "deny" we must GUARANTEE no outbound web -
  // a polite prompt note is NOT enough, since the model can ignore it.
  const webMode: "allow" | "deny" = webAccess ?? readWebAccess();
  if (webMode === "deny") {
    // A turn is web-safe under "deny" when it CANNOT reach the web:
    //  - claude: its WebSearch/WebFetch tools are removed via --disallowedTools.
    //  - plain HTTP completions (ollama, openrouter, and the single-vendor direct
    //    API providers): they're a bare /chat/completions call with NO agentic
    //    web tools at all, so there's nothing to reach the web with.
    // Only the AGENTIC CLIs that ship their own uncontrollable web tools - codex,
    // gemini/antigravity, and the claude/gemini/codex "extra family" CLIs - get
    // refused, so a denied turn never silently calls out.
    const plainCompletion =
      cli.kind === "ollama" ||
      cli.kind === "openrouter" ||
      !!DIRECT_PROVIDER_BY_ID[cli.kind as DirectProviderKind];
    const webSafe = cli.kind === "claude" || plainCompletion;
    if (!webSafe) {
      throw new Error(
        `Web access is OFF, and it can't be guaranteed off for the "${cli.kind}" engine (its web tools can't be disabled headlessly). ` +
        `Switch to Claude, a local model, or an API/OpenRouter model — or turn Web access back on.`,
      );
    }
  }

  const m = model.trim();
  assertSafeModelId(m);
  // Only claude gets the manual — it has a real --append-system-prompt
  // channel that the model treats as system context (not echoed in output).
  // codex and gemini have no system-prompt flag in their CLIs, so the manual
  // would have to be prepended to the user prompt — and both (codex
  // especially) echo it verbatim into the response bubble, eating screen
  // space. Better to send them a clean prompt.
  const manualForClaude =
    bare || cli.kind !== "claude"
      ? null
      : augmentManualWithWebGate(findOperatingManual(vaultPath), webMode);
  // Every file-based harness (claude/codex/gemini) also gets Prevail's rules via
  // its native instruction file in cwd, so codex/gemini respect the architecture
  // (they have no system-prompt flag) and no stray user file can override us. Only
  // for real turns (not the cheap bare classifier/council calls).
  if (!bare) syncHarnessManual(cwd, cli.kind, vaultPath, webMode);
  // Response framework preamble (BLUF, WIN, SCQA, ...). When set, prepend
  // a bracketed instruction so the model structures its answer in that
  // style. Applies to every CLI and to both single-chat + council. Short
  // enough that even codex (which would otherwise echo) renders cleanly.
  //
  // Resolution: cwd is <vault>/<domain>, so basename(cwd) is the domain
  // key. The lookup checks for a per-domain override first and falls
  // back to the global default. Per-domain overrides are set by the
  // workspace bar chip on a domain workspace.
  const domainKey = basename(cwd);
  const framework = getFramework(readResponseFramework(domainKey));
  // The Ideal State is the user's constitution — highest precedence, injected
  // ahead of everything. Claude receives it through its system channel (clean,
  // not echoed); CLIs without a system-prompt flag get it prepended to the
  // prompt instead, so it still governs the turn. It applies even in bare mode
  // (council panelists), where the operating manual is intentionally skipped.
  // The desktop assembles its own prompt and already inlines the Ideal State
  // and Omega (helpers2.tsx buildIdealStatePreamble / buildOmegaPreamble) before
  // handing the turn to the engine. Injecting them again here doubled both
  // blocks on every desktop turn (and for Claude sent one copy inline plus one
  // via the system channel). Detect the desktop's headers and skip ours.
  const promptHasConstitution = /^# THE USER'S IDEAL STATE/m.test(prompt);
  const promptHasOmega = /^# OMEGA/m.test(prompt);
  // The real vault root. `vaultPath` above is cwd's parent, which on a v4
  // vault (data/domains/<d>) is data/domains: the constitution lookup missed
  // build/ideal-state.md there and fell back to ~/.prevail.
  const vaultRoot = vaultRootForCwd(cwd);
  const noContext = incognito || process.env.PREVAIL_INCOGNITO === "1";
  const idealState = promptHasConstitution || noContext ? null : findIdealState(vaultRoot);
  const constitution = idealState ? buildConstitutionPreamble(idealState) : null;
  const promptConstitution = constitution && cli.kind !== "claude" ? constitution : "";
  // Omega — learned app-wide context, injected just below the constitution and
  // above the framework/domain/memory. Applies in every turn, including bare
  // (council) mode, same as the constitution.
  const omega = promptHasOmega || noContext ? null : findOmega(vaultRoot);
  const omegaPreamble = omega ? buildOmegaPreamble(omega) : null;
  const promptOmega = omegaPreamble && cli.kind !== "claude" ? omegaPreamble : "";
  // M6: per-domain ideal, just below the global ideal and above omega/framework.
  const domainIdeal = noContext ? null : findDomainIdeal(cwd, vaultPath);
  const domainIdealPreamble = domainIdeal ? buildDomainIdealPreamble(domainIdeal) : null;
  const promptDomainIdeal = domainIdealPreamble && cli.kind !== "claude" ? domainIdealPreamble : "";
  // Who the user is and what they are working toward, on every real chat
  // path (desktop, CLI, MCP, Telegram). The desktop sends its own profile
  // block; the goals block is added only here. Skipped for bare calls
  // (council panelists, classifiers) and incognito.
  const userBlocks = !bare && !noContext ? buildUserContext(vaultRoot, cwd, prompt, { local: ["ollama", "lmstudio", "mlx"].includes(cli.kind) }) : "";
  const goalsPreamble = userBlocks ? `${userBlocks}\n\n---\n\n` : null;
  const promptGoals = goalsPreamble && cli.kind !== "claude" ? goalsPreamble : "";
  // Synced app data: the newest pull per mirrored connector recipe that feeds
  // this domain (<domain>/source/apps/<id>/<date>.json), size-capped. Real turns
  // only (not bare council/classifier calls), and never for General (vault root).
  const syncedApps = !bare && resolve(cwd) !== resolve(vaultPath) ? syncedAppsContext(cwd) : "";
  const syncedAppsPreamble = syncedApps ? `${syncedApps}\n\n---\n\n` : null;
  const promptSyncedApps = syncedAppsPreamble && cli.kind !== "claude" ? syncedAppsPreamble : "";
  // Vault Lock leads everything (a security guardrail outranks even the
  // constitution). Claude gets it via the system channel below; CLIs without a
  // system-prompt flag get it prepended to the prompt so it still governs.
  const vaultLockPreamble = vaultLockOn() ? buildVaultLockPreamble() : null;
  const promptVaultLock = vaultLockPreamble && cli.kind !== "claude" ? vaultLockPreamble : "";
  // Fix #10 (a): the no-em-dash style directive. Claude gets it via the system
  // channel (in claudeSystem below); CLIs without a system-prompt flag get it
  // prepended to the prompt so it still governs the turn.
  const promptNoEmDash = cli.kind !== "claude" ? buildNoEmDashPreamble() : "";
  const promptOutputHint = outputHint && cli.kind !== "claude" ? `${outputHint}\n\n` : "";
  let framedPrompt = promptVaultLock + promptConstitution + promptDomainIdeal + promptGoals + promptOmega + promptSyncedApps + promptNoEmDash + promptOutputHint + buildFrameworkPreamble(framework) + prompt;
  // A prompt that begins with '-' makes the runtime CLI's option parser treat the
  // whole thing as an unknown flag (e.g. `claude -p` -> "unknown option '---...'",
  // codex's positional, agy/gemini -p). Our injected context headers ("--- extra:
  // ... ---", "--- PRIOR TURNS ---") and markdown frontmatter ('---') routinely
  // start with dashes, so this is hit on ordinary turns. A single leading space
  // turns it back into a plain value/positional and is invisible to the model.
  // (buildCliArgs already guarded this; the live dispatch path was missing it.)
  if (/^\s*-/.test(framedPrompt)) framedPrompt = " " + framedPrompt;

  // Run the dispatch, then (Track E7) commit the estimated spend to the
  // run/day ledgers. recordSpend is a no-op for free local turns and when no
  // guard was supplied, so this preserves existing behavior. We record AFTER
  // the call resolves so a cancelled / failed-to-spawn turn that never billed
  // still adds to the ledger conservatively (the estimate is pre-flight; exact
  // billing isn't available from the CLIs). Recording on the estimate keeps
  // the per-day wall honest against a runaway loop.
  const reply = await dispatchTurn();
  if (budgetEstimate && guard) recordSpend(budgetEstimate, guard.budget);
  // Fix #10 (b): the hard guarantee. Strip em dashes from the complete reply
  // before it is returned to ANY caller (persisted to the vault, rendered, fed
  // into a council/skill). Code-block aware so code is never mangled.
  return sanitizeEmDashes(reply);

  async function dispatchTurn(): Promise<string> {
  // CONFINEMENT GUARD (fail-closed). An `act` run hands the model its full
  // tool surface under a skip-permissions flag. Only two engines can be
  // technically confined: `claude` (the PreToolUse act-gate hook, wired below)
  // and `codex` (its own OS sandbox, scoped to the vault below). Every other
  // provider — antigravity/gemini, the harness families (hermes/pi/opencode/…),
  // and the best-effort `-p` fallbacks — gets full agency with NO Prevail gate
  // and NO OS sandbox; the Vault Lock preamble is only a soft prompt request an
  // injected instruction can override. So when Vault Lock is ON we refuse an
  // act run on an unconfinable engine rather than execute it unconfined. (A
  // normal chat/council turn — act=false — is unaffected: no agency is granted.)
  // Turning Vault Lock OFF is the explicit, visible way to opt into this.
  if (act && vaultLockOn()) {
    const confinable = cli.kind === "claude" || cli.kind === "codex";
    if (!confinable) {
      throw new Error(
        `Vault Lock is on, but the "${cli.label || cli.kind}" engine cannot be confined for an action run ` +
        `(no execution gate and no OS sandbox — only Claude and Codex support confined acting). ` +
        `This action was NOT run. Use Claude or Codex for acting, or turn Vault Lock off in Privacy to allow unconfined agency on this engine.`,
      );
    }
  }
  if (cli.kind === "claude") {
    const head = isFirst ? ["-p", framedPrompt] : ["--continue", "-p", framedPrompt];
    const args: string[] = [];
    if (m) args.push("--model", m);
    // --append-system-prompt is only meaningful on the first turn; --continue
    // inherits it. The constitution leads (highest precedence), then the
    // operating manual. The constitution is included even in bare mode, where
    // the manual is intentionally null.
    const claudeSystem = [vaultLockPreamble, constitution, domainIdealPreamble, goalsPreamble, omegaPreamble, syncedAppsPreamble, NO_EM_DASH_DIRECTIVE, outputHint ?? null, manualForClaude].filter(Boolean).join("\n\n");
    if (claudeSystem && isFirst) args.push("--append-system-prompt", claudeSystem);
    // Execution turns for a user-approved action: let the agent actually use its
    // tools/connectors (file ops, bash, MCP). In headless -p there's no TTY to
    // approve prompts, so without this the action silently no-ops. Gated by the
    // explicit per-action approval upstream.
    if (act) args.push("--dangerously-skip-permissions");
    // Web lockdown: remove the web tools from the model's context entirely.
    // --disallowedTools wins over --dangerously-skip-permissions (a denied tool
    // stays unavailable even in skip-permissions mode), so this is a HARD block,
    // not a request. WebSearch + WebFetch are the only built-ins that make
    // outbound requests. The WEB_DENY_NOTE in the system prompt is belt-and-braces.
    const deny = [...(webMode === "deny" ? ["WebSearch", "WebFetch"] : []), ...(noShell ? ["Bash"] : [])];
    if (deny.length) args.push("--disallowedTools", ...deny);
    // Agent-facing MCP servers: connected stdio MCP servers (the user's own
    // local MCP apps, integration "mcp" with a mcpSetup.command) plus the gated
    // google_workspace connector and prevail_acts, injected on EVERY turn so the
    // model can see their tools. We do NOT add --dangerously-skip-permissions
    // for chat, so on a non-act turn the tools are visible but still subject to
    // the normal permission model (safety unchanged).
    // agentMcpConfigForClaude materializes ~/.prevail/agent-mcp.json and returns
    // its path, or null when there is nothing to inject, so this stays a
    // byte-for-byte no-op otherwise.
    // Whether any MCP tools were actually injected this turn. Gates the switch to
    // the structured (stream-json) runner below: a chat turn with tools streams
    // real step events for the checklist; a tool-less chat turn stays on the
    // plain runCapture path, byte-for-byte unchanged.
    let toolsInjected = false;
    const mcpConfigs: string[] = [];
    const allowed: string[] = [];
    try {
      const { agentMcpConfigForClaude, agentMcpServerIds } = await import("./agent-mcp.ts");
      const gwsAccount = googleAccount?.trim() || undefined;
      const mcpCfg = agentMcpConfigForClaude(vaultPath, { googleAccount: gwsAccount });
      if (mcpCfg) {
        toolsInjected = true;
        mcpConfigs.push(mcpCfg);
        // Engine-managed turn = engine-managed tool surface. Without this,
        // claude also loads the USER'S global MCP config (claude.ai Gmail /
        // Calendar / Drive connectors, authenticated as whatever claude.ai
        // holds), and the model can reach for those instead of the injected
        // google_workspace server - silently bypassing Prevail's account
        // routing (the picked/bound identity) and failing with wrong-account
        // errors like "entity not found". Restrict MCP to exactly what we
        // injected; builtins (WebSearch/WebFetch/files) are unaffected.
        // EXCEPTION: app chats opt in to ALSO inherit the user's own Claude
        // Code MCP servers - the "connected via Claude Code" passthrough those
        // apps advertise (PayPal etc.). Scoped: domain chats stay strict.
        if (!inheritUserMcp) args.push("--strict-mcp-config");
        // In headless `-p` there is no TTY to approve tool use, so on a non-act
        // (chat) turn the injected MCP tools would be auto-denied and the agent
        // could never call them. Explicitly allow exactly the servers we
        // injected (mcp__<serverId> permits all of that server's tools). This is
        // additive - it does not disable the model's other behavior - and safe:
        // the google_workspace tool gates its own writes (it only QUEUES them
        // for approval), and connected stdio MCP servers are user-added. On act
        // runs --dangerously-skip-permissions already allows everything, so we
        // only need this on chat turns.
        if (!act) {
          const ids = agentMcpServerIds(vaultPath, { googleAccount: gwsAccount });
          // Also allow TodoWrite: it is a local planning tool with no external
          // effect, and letting the model maintain a todo list is how we surface a
          // "Plan" header for a multi-step job (the engine turns each TodoWrite
          // into a plan event). Harmless when the model never plans.
          if (ids.length) allowed.push(...ids.map((id) => `mcp__${id}`), "TodoWrite");
        }
      }
    } catch { /* never let MCP wiring break a turn */ }
    // Trusted sources: a referenced remote MCP source joins this turn as an
    // http server keyed by its app id, merged with whatever else is loaded
    // (the inherited user config on app turns). Its calls pass the act gate
    // below like any connector: registered reads run and are logged, anything
    // else queues. A web/links source lets WebFetch GET its hosts only.
    try {
      const { remoteMcpConfig, remoteMcpTokens } = await import("./trusted-sources.ts");
      const inline = remoteMcpConfig(remoteMcp ?? {}, vaultPath ? remoteMcpTokens(vaultPath, Object.keys(remoteMcp ?? {})) : {});
      if (inline) {
        toolsInjected = true;
        mcpConfigs.push(inline);
        if (!act) allowed.push(...Object.keys(remoteMcp ?? {}).map((id) => `mcp__${id}`));
      }
      if (!act && webMode === "allow") allowed.push(...(fetchHosts ?? []).filter((h) => /^[a-z0-9.-]+(:\d+)?$/.test(h)).map((h) => `WebFetch(domain:${h.replace(/:\d+$/, "")})`));
    } catch { /* never let source wiring break a turn */ }
    if (!act && appReadTools?.length) allowed.push(...appReadTools);
    if (!act && allowTools?.length) allowed.push(...allowTools.filter((t) => READ_ONLY_BUILTINS.has(t) && (webMode === "allow" || !/^Web/.test(t))));
    if (mcpConfigs.length) args.push("--mcp-config", ...mcpConfigs);
    if (allowed.length) args.push("--allowedTools", ...new Set(allowed));
    // ACTION GATEWAY (G1): every claude turn that can see MCP tools carries the
    // PreToolUse act-gate hook, so connector writes (inherited claude.ai
    // connectors, any user MCP server) queue for approval and pass
    // the egress guard - the same spine gws writes already use. Verified to
    // fire even under --dangerously-skip-permissions. Engine-owned servers
    // (google_workspace, prevail) self-gate and pass through.
    if (toolsInjected || inheritUserMcp || act) {
      try {
        const { actGateSettingsPath } = await import("./act-gate.ts");
        // An app's own chat space (data/apps/<id>/_scope) is keyed _app-<id>,
        // not "_scope", so its acts and access-log lines name the app scope.
        const scopeKey = basename(cwd) === APP_SCOPE_SUBDIR ? `${APP_SCOPE_PREFIX}${basename(dirname(cwd))}` : basename(cwd) || "general";
        args.push("--settings", actGateSettingsPath(vaultRootForCwd(cwd), scopeKey, vaultLockOn()));
      } catch { /* the gws spine still holds for Google; never break the turn */ }
    }
    // Ground-truth tool capture: switch to structured stream-json so we can
    // report the REAL tools the model invokes (including runtime-native
    // connectors like AllTrails). This runs on the Act/agent path AND on a normal
    // chat turn that injected tools (so the desktop can render a live step
    // checklist). A tool-less chat turn keeps the plain-text runCapture stream
    // byte-for-byte unchanged.
    // An app chat that inherits the user's connectors has tools too (the ones
    // the act gate holds), so it streams steps as well: that is how a held
    // act's [prevail-act:<id>] marker reaches the desktop's approval card.
    if (onTool && (act || toolsInjected || inheritUserMcp)) {
      args.push("--output-format", "stream-json", "--verbose");
      args.push(...head);
      return runClaudeStream(cli.bin, args, cwd, signal, onChunk, onTool, maxOutputChars, onInit);
    }
    args.push(...head);
    return runCapture(cli.bin, args, cwd, signal, onChunk, maxOutputChars);
  }
  if (cli.kind === "codex") {
    // --skip-git-repo-check: vault dirs aren't git repos; without this codex
    // refuses to run with 'Not inside a trusted directory'.
    const base = ["exec", "--skip-git-repo-check"];
    // Codex's built-in system prompt frames it as a software engineering
    // agent — it refuses non-coding asks with "I'm a coding agent, I can't
    // help with that." For council Q&A (bare=true) this is wrong: the user
    // is asking life-domain advisory questions, not requesting code. Codex
    // doesn't expose a system-prompt override flag, but if the user prompt
    // opens with framing it generally cooperates. Kept short so it doesn't
    // dominate the prompt or leak noticeably in the reply.
    const codexPrompt = bare
      ? `(This is a general advisory question — not a software/coding task. Engage with it directly and give your real opinion.)\n\n${framedPrompt}`
      : framedPrompt;
    // Split a "model@effort" id (e.g. "gpt-5.5@high") into the base model + a
    // reasoning-effort config flag, exactly like the desktop chat path. Passing
    // the raw "gpt-5.5@high" as -m makes the provider reject it ("model not
    // supported") - which is why such benchmark runs scored all zeros.
    const modelArgs: string[] = [];
    if (m) {
      const at = m.indexOf("@");
      const mBase = at >= 0 ? m.slice(0, at) : m;
      const effort = at >= 0 ? m.slice(at + 1).trim() : "";
      modelArgs.push("-m", mBase);
      if (effort) modelArgs.push("-c", `model_reasoning_effort=${effort}`);
    }
    // Agent/act path: unlock Codex's tools so a user-approved run can actually
    // act. Codex exec exposes its OWN connectors (mcp__codex_apps__*) plus file/
    // shell tools, but gates them behind approvals+sandbox; the bypass flag is
    // Codex act runs (C1 fix): use Codex's OWN OS sandbox, scoped to the vault,
    // instead of --dangerously-bypass-approvals-and-sandbox (which disabled the
    // sandbox entirely - an injected instruction could then run any command).
    // `workspace-write` confines file writes to the working root (cwd = the
    // domain dir) and denies network by default, while still letting an act run
    // write to the vault. When Vault Lock is OFF the user has chosen unconfined
    // access, so we fall back to full access. --skip-git-repo-check already set
    // in `base`; -a on-failure keeps it non-interactive without disabling the box.
    const codexActArgs = act
      ? (vaultLockOn()
          ? ["--sandbox", "workspace-write", "--add-dir", codexWritableRoot(cwd)]
          : ["--dangerously-bypass-approvals-and-sandbox"])
      : [];
    const args = [...base, ...modelArgs, ...codexActArgs, codexPrompt];
    const raw = await runCapture(cli.bin, args, cwd, signal, onChunk, maxOutputChars);
    return extractCodexReply(raw);
  }
  if (cli.kind === "antigravity" || EXTRA_PROTOCOL[cli.kind] === "gemini") {
    // Antigravity (`agy`) and the Gemini CLI (`gemini`) have
    // DIFFERENT flag surfaces, even though prevAIl exposes them as the
    // same panelist:
    //
    //   agy:    --dangerously-skip-permissions    --model <name>   -p
    //   gemini: --skip-trust                      -m <name>        -p
    //
    // Dispatch on the resolved binary basename so the args are right
    // either way. Both invocations produce stdout in the same shape, so
    // extractGeminiReply is reused for both. After 2026-06-18 when
    // Google sunsets the legacy binary, drop the gemini branch.
    const isAgy = /(^|\/)agy$/.test(cli.bin);
    // Antigravity/Gemini narrate their planning + tool steps as plain stdout with
    // no thinking channel (verified: `agy` has no json/output-format flag). Ask the
    // model to fence that reasoning in <thinking>…</thinking> so the desktop can
    // collapse it (splitThinking) and show only the final answer, expandable.
    const geminiPrompt = `${framedPrompt}\n\n--- OUTPUT FORMAT ---\nPut ALL of your planning, reasoning, and step narration inside one <thinking>…</thinking> block at the very start. After </thinking>, write ONLY the final answer in clean markdown. If you have no reasoning to show, skip the block and just answer.`;
    const args: string[] = [];
    if (isAgy) {
      args.push("--dangerously-skip-permissions");
      if (m) args.push("--model", m);
      args.push("-p", geminiPrompt);
    } else {
      args.push("--skip-trust");
      if (m) args.push("-m", m);
      args.push("-p", geminiPrompt);
    }
    const raw = await runCapture(cli.bin, args, cwd, signal, onChunk, maxOutputChars);
    return extractGeminiReply(raw);
  }
  if (EXTRA_PROTOCOL[cli.kind] === "claude") {
    // Harnesses with a known headless invocation (hermes/pi/opencode) get their
    // real, verified flags from HARNESS_PROFILES — the old guessed `<bin> -p`
    // convention only happened to be valid for pi. `act` (an approved/auto run)
    // maps to the harness's own full-agency switch (e.g. hermes --yolo); a normal
    // turn maps to its safe/propose mode (--safe-mode). Families without a
    // profile (codebuddy/copilot/openclaw/cursor/kiro/paperclip/motorcar) keep
    // the best-effort `-p` fallback; a wrong-flag turn surfaces as a visible
    // error, never a silent or data-losing failure.
    const profileArgs = buildHarnessArgs(cli.kind, {
      prompt: framedPrompt,
      model: m,
      autonomy: act ? "auto" : "safe",
    });
    let args: string[];
    if (profileArgs) {
      args = profileArgs;
    } else {
      args = [];
      if (m) args.push("--model", m);
      args.push("-p", framedPrompt);
    }
    return runCapture(cli.bin, args, cwd, signal, onChunk, maxOutputChars);
  }
  if (cli.kind === "ollama") {
    return runOllamaChat({
      baseUrl: cli.bin,
      model: m || OLLAMA_DEFAULT_MODEL,
      prompt: framedPrompt,
      signal,
      onChunk,
      maxOutputChars,
    });
  }
  if (cli.kind === "openrouter") {
    // OpenRouter is an OpenAI-compatible HTTP gateway — one key, every model.
    // The key arrives via PREVAIL_OPENROUTER_KEY (set by the desktop on the
    // child; named to avoid scrubbedEnv's OPENAI_/ANTHROPIC_ strip list).
    return runOpenAICompatChat({
      label: "openrouter",
      baseUrl: "https://openrouter.ai/api/v1",
      apiKey: process.env.PREVAIL_OPENROUTER_KEY ?? "",
      model: m || OPENROUTER_MODELS[0]!,
      prompt: framedPrompt,
      signal,
      onChunk,
      maxOutputChars,
      extraHeaders: { "HTTP-Referer": "https://prevail.sh", "X-Title": "Prevail" },
    });
  }
  // Direct providers (G1): single-vendor keys. Anthropic uses its native API;
  // the rest are OpenAI-compatible and share runOpenAICompatChat.
  const direct = DIRECT_PROVIDER_BY_ID[cli.kind as DirectProviderKind];
  if (direct) {
    const apiKey = process.env[direct.keyEnv] ?? "";
    const model = m || direct.models[0]!;
    if (direct.native) {
      return runAnthropicChat({ apiKey, model, prompt: framedPrompt, signal, onChunk, maxOutputChars });
    }
    return runOpenAICompatChat({
      label: direct.id,
      baseUrl: direct.baseUrl,
      apiKey,
      model,
      prompt: framedPrompt,
      signal,
      onChunk,
      maxOutputChars,
    });
  }
  return `(no handler for ${cli.kind})`;
  }
}

// Anthropic's native Messages API (/v1/messages) — not OpenAI-compatible: it
// uses x-api-key + anthropic-version headers and a {content:[{text}]} response.
// Mirrors runOpenAICompatChat's contract (errors returned as the reply string,
// optional SSE streaming, output cap) so a panelist failure never throws.
interface AnthropicChatArgs {
  apiKey: string;
  model: string;
  prompt: string;
  signal?: AbortSignal;
  onChunk?: (delta: string) => void;
  maxOutputChars?: number;
}
export async function runAnthropicChat(args: AnthropicChatArgs): Promise<string> {
  const { apiKey, model, prompt, signal, onChunk, maxOutputChars } = args;
  if (!apiKey) return "(anthropic: no API key configured — add it in Settings → Models → Direct Providers)";
  const stream = !!onChunk;
  const body = {
    model,
    max_tokens: 4096,
    stream,
    messages: [{ role: "user", content: prompt }],
  };
  try {
    const res = await fetch("https://api.anthropic.com/v1/messages", {
      method: "POST",
      headers: {
        "content-type": "application/json",
        "x-api-key": apiKey,
        "anthropic-version": "2023-06-01",
      },
      body: JSON.stringify(body),
      signal,
    });
    if (!res.ok) {
      const text = await res.text().catch(() => "");
      return `(anthropic: HTTP ${res.status} — ${truncate(text, 200)})`;
    }
    if (!stream) {
      const data = (await res.json()) as {
        content?: Array<{ text?: string }>;
        error?: { message?: string };
      };
      if (data.error?.message) return `(anthropic: ${data.error.message})`;
      return (data.content ?? []).map((c) => c.text ?? "").join("");
    }
    // SSE stream: Anthropic emits content_block_delta events with {delta:{text}}.
    let acc = "";
    const reader = res.body?.getReader();
    if (!reader) return "(anthropic: no response body)";
    const decoder = new TextDecoder();
    let buf = "";
    for (;;) {
      const { done, value } = await reader.read();
      if (done) break;
      buf += decoder.decode(value, { stream: true });
      const lines = buf.split("\n");
      buf = lines.pop() ?? "";
      for (const line of lines) {
        const t = line.trim();
        if (!t.startsWith("data:")) continue;
        const payload = t.slice(5).trim();
        if (!payload || payload === "[DONE]") continue;
        try {
          const ev = JSON.parse(payload) as { delta?: { text?: string } };
          const delta = ev.delta?.text;
          if (delta) {
            acc += delta;
            onChunk?.(delta);
            if (maxOutputChars && acc.length >= maxOutputChars) {
              try { await reader.cancel(); } catch { /* ignore */ }
              return `${acc.slice(0, maxOutputChars)} ... (truncated at ${maxOutputChars} chars)`;
            }
          }
        } catch { /* skip malformed SSE frame */ }
      }
    }
    return acc;
  } catch (e) {
    if (signal?.aborted) return "(anthropic: request aborted)";
    return `(anthropic: ${e instanceof Error ? e.message : String(e)})`;
  }
}

interface OllamaChatArgs {
  baseUrl: string;
  model: string;
  prompt: string;
  signal?: AbortSignal;
  onChunk?: (delta: string) => void;
  // Same semantics as the runCapture cap — abort the in-flight fetch
  // once the cumulative reply crosses the threshold and return the
  // sliced reply with a " ... (truncated at N chars)" suffix.
  maxOutputChars?: number;
}

// One-shot chat completion against an OpenAI-compatible endpoint (Ollama,
// LM Studio, llama.cpp server, vLLM — all speak the same /v1/chat/completions
// schema). When onChunk is set, uses SSE streaming so the UI can render
// tokens as they arrive; otherwise falls back to the simpler non-stream
// path. Errors are returned as the reply string (prefixed `(ollama: ...)`)
// instead of thrown, so a single panelist failure doesn't blow up the
// whole council fanout.
export async function runOllamaChat(args: OllamaChatArgs): Promise<string> {
  const { baseUrl, model, prompt, signal, onChunk, maxOutputChars } = args;
  const url = `${baseUrl.replace(/\/+$/, "")}/v1/chat/completions`;
  const stream = !!onChunk;
  const body = {
    model,
    stream,
    messages: [{ role: "user", content: prompt }],
  };
  try {
    const res = await fetch(url, {
      method: "POST",
      headers: { "content-type": "application/json" },
      body: JSON.stringify(body),
      signal,
    });
    if (!res.ok) {
      const text = await res.text().catch(() => "");
      return `(ollama: HTTP ${res.status} — ${truncate(text, 200)})`;
    }
    if (!stream) {
      const data = (await res.json()) as {
        choices?: Array<{ message?: { content?: string } }>;
        error?: { message?: string };
      };
      if (data.error?.message) return `(ollama: ${data.error.message})`;
      const content = data.choices?.[0]?.message?.content;
      if (!content) return "(ollama: empty reply)";
      if (typeof maxOutputChars === "number" && content.length > maxOutputChars) {
        return content.slice(0, maxOutputChars) + " ... (truncated at " + maxOutputChars + " chars)";
      }
      return content.trim();
    }
    // SSE stream — each event is `data: { ... }\n\n`, terminated by
    // `data: [DONE]`. Concatenate every choices[0].delta.content into the
    // full reply, emitting each delta as it arrives.
    if (!res.body) return "(ollama: response had no body)";
    const reader = res.body.getReader();
    const decoder = new TextDecoder();
    let buffer = "";
    let full = "";
    while (true) {
      const { done, value } = await reader.read();
      if (done) break;
      buffer += decoder.decode(value, { stream: true });
      // Process complete SSE events (delimited by \n\n).
      let idx: number;
      while ((idx = buffer.indexOf("\n\n")) !== -1) {
        const event = buffer.slice(0, idx);
        buffer = buffer.slice(idx + 2);
        for (const line of event.split("\n")) {
          if (!line.startsWith("data:")) continue;
          const payload = line.slice(5).trim();
          if (payload === "[DONE]") continue;
          try {
            const j = JSON.parse(payload) as {
              choices?: Array<{ delta?: { content?: string }; finish_reason?: string | null }>;
              error?: { message?: string };
            };
            if (j.error?.message) return `(ollama: ${j.error.message})`;
            const delta = j.choices?.[0]?.delta?.content;
            if (delta) {
              full += delta;
              onChunk!(delta);
            }
          } catch {
            /* malformed event — skip */
          }
        }
      }
      // Output cap. Abort the SSE read once cumulative reply crosses
      // the threshold — same intent as the runCapture pgroup-kill, but
      // for the fetch path. cancel() rejects the reader; we exit cleanly
      // via the truncated-return below.
      if (typeof maxOutputChars === "number" && full.length > maxOutputChars) {
        try { await reader.cancel(); } catch { /* already closed */ }
        return full.slice(0, maxOutputChars) + " ... (truncated at " + maxOutputChars + " chars)";
      }
    }
    return full.trim() || "(ollama: empty reply)";
  } catch (err) {
    const e = err as { name?: string; message?: string };
    if (e?.name === "AbortError") return "(cancelled)";
    return `(ollama: ${e?.message ?? "request failed"})`;
  }
}

// Generalized OpenAI-compatible chat (OpenRouter + future direct providers).
// Same SSE handling as runOllamaChat, plus an Authorization header and a
// configurable label/base URL. Keeping one implementation means adding the
// direct providers later is just a base-URL + key-account entry.
interface OpenAICompatArgs {
  label: string;
  baseUrl: string;
  apiKey: string;
  model: string;
  prompt: string;
  signal?: AbortSignal;
  onChunk?: (delta: string) => void;
  maxOutputChars?: number;
  extraHeaders?: Record<string, string>;
}
export async function runOpenAICompatChat(args: OpenAICompatArgs): Promise<string> {
  const { label, baseUrl, apiKey, model, prompt, signal, onChunk, maxOutputChars, extraHeaders } = args;
  if (!apiKey) return `(${label}: no API key configured — add it in Settings → Providers)`;
  const url = `${baseUrl.replace(/\/+$/, "")}/chat/completions`;
  const stream = !!onChunk;
  const headers: Record<string, string> = {
    "content-type": "application/json",
    authorization: `Bearer ${apiKey}`,
    ...(extraHeaders ?? {}),
  };
  try {
    const res = await fetch(url, { method: "POST", headers, body: JSON.stringify({ model, stream, messages: [{ role: "user", content: prompt }] }), signal });
    if (!res.ok) {
      const text = await res.text().catch(() => "");
      return `(${label}: HTTP ${res.status} — ${truncate(text, 200)})`;
    }
    if (!stream) {
      const data = (await res.json()) as { choices?: Array<{ message?: { content?: string } }>; error?: { message?: string } };
      if (data.error?.message) return `(${label}: ${data.error.message})`;
      const content = data.choices?.[0]?.message?.content;
      if (!content) return `(${label}: empty reply)`;
      return typeof maxOutputChars === "number" && content.length > maxOutputChars
        ? content.slice(0, maxOutputChars) + " ... (truncated at " + maxOutputChars + " chars)"
        : content.trim();
    }
    if (!res.body) return `(${label}: response had no body)`;
    const reader = res.body.getReader();
    const decoder = new TextDecoder();
    let buffer = "";
    let full = "";
    while (true) {
      const { done, value } = await reader.read();
      if (done) break;
      buffer += decoder.decode(value, { stream: true });
      let idx: number;
      while ((idx = buffer.indexOf("\n\n")) !== -1) {
        const event = buffer.slice(0, idx);
        buffer = buffer.slice(idx + 2);
        for (const line of event.split("\n")) {
          if (!line.startsWith("data:")) continue;
          const payload = line.slice(5).trim();
          if (payload === "[DONE]") continue;
          try {
            const j = JSON.parse(payload) as { choices?: Array<{ delta?: { content?: string } }>; error?: { message?: string } };
            if (j.error?.message) return `(${label}: ${j.error.message})`;
            const delta = j.choices?.[0]?.delta?.content;
            if (delta) { full += delta; onChunk!(delta); }
          } catch { /* malformed event — skip */ }
        }
      }
      if (typeof maxOutputChars === "number" && full.length > maxOutputChars) {
        try { await reader.cancel(); } catch { /* already closed */ }
        return full.slice(0, maxOutputChars) + " ... (truncated at " + maxOutputChars + " chars)";
      }
    }
    return full.trim() || `(${label}: empty reply)`;
  } catch (err) {
    const e = err as { name?: string; message?: string };
    if (e?.name === "AbortError") return "(cancelled)";
    return `(${label}: ${e?.message ?? "request failed"})`;
  }
}

function truncate(s: string, n: number): string {
  return s.length > n ? s.slice(0, n) + "…" : s;
}

// Codex's `exec` mode wraps every reply in a noisy envelope:
//
//   reasoning effort: xhigh
//   reasoning summaries: none
//   session id: 019e889d-…
//   --------
//   user
//   <our prompt — including the entire operating-manual block>
//   codex
//   <the actual model reply, possibly multi-line>
//   tokens used
//   1,985
//
// Returning that whole thing as the panelist's "answer" is what the user is
// seeing as "codex talking about don't-do-this preamble" — the preamble is
// our manual being echoed back. Strip everything except the model's reply:
// the section between the line "codex" and the next envelope keyword (or
// EOF). If the markers aren't present (unusual output, an error case),
// return the raw output as a fallback so we never silently drop content.
export function extractCodexReply(raw: string): string {
  if (!raw) return raw;
  // Detect the runCapture exit-code prefix — if codex exited non-zero,
  // runCapture wraps the stderr in `(<bin> exited <code>)\n<stderr>` and
  // gives us that. The envelope below is just noise; surface the actual
  // error line instead.
  const exitPrefix = raw.match(/^\((?:\S+\s+)?exited\s+\d+\)/);
  if (exitPrefix) {
    const errLine = extractCodexErrorLine(raw);
    return errLine ?? raw.split("\n")[0]!;
  }
  const lines = raw.split("\n");
  // Find the "codex" line — must be on its own line, possibly with trailing
  // whitespace. Walk from the bottom so we get the LAST one (in case codex
  // ever interleaves intermediate "codex" markers).
  let start = -1;
  for (let i = lines.length - 1; i >= 0; i--) {
    if (lines[i]!.trim() === "codex") {
      start = i + 1;
      break;
    }
  }
  if (start === -1) {
    // No "codex" marker line. Two cases:
    //
    // 1. Codex 0.136+ split the streams: the model reply goes to stdout,
    //    the envelope (workdir / model / session id / the "codex" marker
    //    itself / "tokens used") goes to stderr. runCapture only feeds us
    //    stdout when it's non-empty, so `raw` here is just the bare reply.
    //    Returning a no-reply fallback would discard the actual answer.
    //
    // 2. Codex failed silently and dumped only the envelope. In that case
    //    `raw` will contain envelope markers like "workdir:" or "session
    //    id:" or the "--------" separator.
    //
    // Distinguish by checking for envelope tells. If none are present, the
    // stdout we received IS the reply — pass it through.
    const looksLikeEnvelope = /\b(workdir|provider|sandbox|session id|reasoning effort)\s*:|^-{4,}$/m.test(raw);
    if (!looksLikeEnvelope) return raw.trim();
    // Otherwise it's the failure case — surface a real error line if
    // present, else a concise placeholder so we don't dump the envelope.
    const errLine = extractCodexErrorLine(raw);
    return errLine ?? "(codex produced no reply)";
  }
  // Stop at the next envelope keyword we know about. The colon-suffixed keys
  // come from codex's startup envelope; matching them protects against the
  // rare case where codex re-prints envelope info after the reply. We require
  // the colon (and an `^`) so a reply that mentions "model: gpt-5" in prose
  // doesn't get truncated.
  const stopRe = /^(tokens used\s*$|-{4,}\s*$|(?:session id|reasoning effort|reasoning summaries|workdir|model|provider|approval|sandbox):)/i;
  let end = lines.length;
  for (let i = start; i < lines.length; i++) {
    if (stopRe.test(lines[i]!.trim())) {
      end = i;
      break;
    }
  }
  const body = lines.slice(start, end).join("\n").trim();
  return body || "(codex produced no reply)";
}

function extractCodexErrorLine(raw: string): string | null {
  for (const line of raw.split("\n")) {
    const t = line.trim();
    if (!t) continue;
    if (/^error[:\s]/i.test(t)) return t;
    if (/not supported when using codex/i.test(t)) return t;
    if (/^stream error[:\s]/i.test(t)) return t;
  }
  return null;
}

// Gemini CLI dumps a full Node.js stack trace on any API error: 30 lines of
// "at classifyGoogleError (file:///opt/homebrew/Cellar/gemini-cli/.../...)"
// frames after the actual human-readable error. The signal we want is
// usually one line like "TerminalQuotaError: You have exhausted your
// capacity...". This function pulls that out and drops the stack.
//
// On success (no error), Gemini's `-p` mode just prints the reply text — no
// envelope to strip — so we return it unchanged.
export function extractGeminiReply(raw: string): string {
  if (!raw) return raw;
  // runCapture prefixes non-zero exits with "(<bin> exited <code>)". When
  // present, dig out the meaningful error line instead of the whole dump.
  const exitPrefix = raw.match(/^\((?:\S+\s+)?exited\s+\d+\)/);
  // Stack-trace markers — once we hit one, stop including the rest.
  const stackRe = /^\s*at\s+[\w.<>$]+\s*\(/;
  const lines = raw.split("\n");
  const kept: string[] = [];
  let sawError = false;
  for (const line of lines) {
    if (stackRe.test(line)) break;
    // Strip Gemini's "Full report available at: /var/folders/...json"
    // breadcrumb — points at a temp file the user can't read in context.
    const cleaned = line.replace(/\s*Full report available at:\s*\S+/g, "").trimEnd();
    if (!cleaned.trim()) continue;
    kept.push(cleaned);
    if (/error\b|exhausted|quota|429/i.test(cleaned)) sawError = true;
  }
  const body = kept.join("\n").trim();
  if (exitPrefix && sawError) {
    // Promote the most specific error line. Prefer a *Error: pattern.
    const errLine = kept.find((l) =>
      /^\s*\w*Error:|^\s*Error\b|exhausted/i.test(l),
    );
    if (errLine) {
      // Often the prefix and the error line are concatenated on one line
      // from gemini; if so, just return the error portion.
      const idx = errLine.search(/\w*Error:|Error\b/);
      return idx > 0 ? errLine.slice(idx).trim() : errLine.trim();
    }
  }
  return body || raw;
}

// Exposed for tests: returns the exact argv we would pass to spawn for a
// given CLI. Lets us assert the command shape (skip-git-repo-check flag,
// --skip-trust flag, -m model passing, etc) without actually spawning.
export function buildCliArgs({
  cli,
  prompt,
  model,
  isFirst,
  manual,
}: {
  cli: CliKind;
  prompt: string;
  model: string;
  isFirst: boolean;
  manual: string | null;
}): string[] {
  const m = model.trim();
  assertSafeModelId(m);
  // A prompt that begins with "-" (e.g. an injected context block that leads with
  // "--- Label ---", or a pasted markdown list) is otherwise parsed by the CLI's
  // arg parser as an unknown OPTION ("error: unknown option '--- Profile ...'").
  // A single leading space makes the token no longer look like a flag and the
  // model ignores it. Cheap, universal guard for every CLI below.
  const safe = /^\s*-/.test(prompt) ? ` ${prompt}` : prompt;
  if (cli === "claude") {
    const args: string[] = [];
    if (m) args.push("--model", m);
    if (manual && isFirst) args.push("--append-system-prompt", manual);
    if (isFirst) args.push("-p", safe);
    else args.push("--continue", "-p", safe);
    return args;
  }
  // codex and gemini have no system-prompt channel; manual is intentionally
  // dropped (it would otherwise be echoed back into the response bubble).
  if (cli === "codex") {
    const base = ["exec", "--skip-git-repo-check"];
    return m ? [...base, "-m", m, safe] : [...base, safe];
  }
  if (cli === "antigravity") {
    // Probe path can't easily detect which binary is in use here (this
    // function only sees the kind). Default to the agy flag set since
    // that's the post-2026-06-18 reality. The probe is only used to
    // build display hints — actual invocation in runChatTurn dispatches
    // on the resolved binary correctly.
    const base = ["--dangerously-skip-permissions"];
    return m ? [...base, "--model", m, "-p", prompt] : [...base, "-p", prompt];
  }
  return [];
}

// Absolute safety ceiling for a single model invocation's captured output.
// A normal reply is a few KB; even a very long answer stays well under 1MB.
// This default ONLY engages for a genuinely runaway / looping model — it kills
// the child the moment cumulative output crosses it, so one wedged process can
// never balloon the engine (and the desktop buffering its stdout) toward OOM.
// Callers that pass an explicit, smaller maxOutputChars keep that tighter cap.
const DEFAULT_OUTPUT_CEILING = 8_000_000;
// stderr is diagnostics only; we never return it as content, so truncating it
// past this point is lossless for the user and bounds a runaway stack dump.
const MAX_STDERR_CHARS = 256_000;

function runCapture(
  bin: string,
  args: string[],
  cwd: string,
  signal?: AbortSignal,
  onChunk?: (delta: string) => void,
  maxOutputChars?: number,
): Promise<string> {
  return new Promise((resolve) => {
    let stdout = "";
    let stderr = "";
    let child;
    let truncated = false;
    // Always bounded: an explicit cap if given, otherwise the safety ceiling.
    const effectiveCap = typeof maxOutputChars === "number" ? maxOutputChars : DEFAULT_OUTPUT_CEILING;
    if (signal?.aborted) {
      resolve("(cancelled)");
      return;
    }
    try {
      child = spawn(bin, args, {
        cwd,
        env: scrubbedEnv(),
        stdio: ["ignore", "pipe", "pipe"],
        // Run the child as its OWN process-group leader so abort can
        // signal the entire tree, not just the launcher. Required for
        // `gemini`: its CLI is a shell wrapper that installs no-op
        // handlers for SIGTERM/SIGINT/SIGHUP and spawns the real
        // worker as a separate PID with inherited stdio. A plain
        // child.kill("SIGTERM") hits the wrapper, gets swallowed, and
        // the worker runs to the 120s timeout — so ESC in the TUI
        // visibly cancels claude/codex/ollama but Gemini keeps going.
        //
        // We do NOT call child.unref() here: detached only creates a
        // new pgroup, it does not background the process.
        detached: true,
      });
    } catch (err) {
      resolve(`(error spawning ${bin}: ${(err as Error).message})`);
      return;
    }
    let cancelled = false;
    const onAbort = () => {
      cancelled = true;
      try {
        // Negative pid = signal the whole process group (the wrapper
        // AND its real worker). SIGKILL because gemini's wrapper
        // ignores SIGTERM. If for some reason we don't have a pid,
        // fall back to direct SIGKILL on the handle.
        if (typeof child!.pid === "number") {
          process.kill(-child!.pid, "SIGKILL");
        } else {
          child!.kill("SIGKILL");
        }
      } catch {
        try { child!.kill("SIGKILL"); } catch {}
      }
    };
    signal?.addEventListener("abort", onAbort);
    child.stdout.on("data", (b) => {
      const chunk = b.toString();
      stdout += chunk;
      // Streaming: emit raw stdout chunks to the caller. Per-CLI parsers
      // (extractCodexReply, extractGeminiReply, claude stream-json) still
      // run on the FINAL aggregate — that's how we strip envelopes /
      // stack traces from the returned reply. The streamed bubble shows
      // the same text the user would have seen in a terminal, which is
      // good enough for the "feels live" UX.
      if (onChunk) onChunk(chunk);
      // Output cap. Once the cumulative stdout crosses the effective cap,
      // SIGKILL the whole pgroup (same trick as the abort path — gemini's
      // wrapper ignores SIGTERM). Distinct from abort: not a user cancel,
      // just a "this output has gone runaway" guard.
      if (!truncated && stdout.length > effectiveCap) {
        truncated = true;
        try {
          if (typeof child!.pid === "number") {
            process.kill(-child!.pid, "SIGKILL");
          } else {
            child!.kill("SIGKILL");
          }
        } catch {
          try { child!.kill("SIGKILL"); } catch {}
        }
      }
    });
    child.stderr.on("data", (b) => {
      // Bound the diagnostic buffer so a runaway stack dump / no-newline blob
      // can't grow stderr without limit. Diagnostics only, so dropping the
      // overflow is lossless for the returned reply.
      if (stderr.length < MAX_STDERR_CHARS) stderr += b.toString();
    });
    child.on("close", (code) => {
      signal?.removeEventListener("abort", onAbort);
      if (cancelled) {
        resolve("(cancelled)");
        return;
      }
      if (truncated) {
        resolve(stdout.slice(0, effectiveCap) + " ... (truncated at " + effectiveCap + " chars)");
        return;
      }
      const out = stdout.trim();
      if (out.length > 0) {
        resolve(out);
      } else if (code !== 0) {
        resolve(`(${bin} exited ${code})\n${stderr.trim()}`);
      } else {
        resolve("(no output)");
      }
    });
    child.on("error", (err) => {
      signal?.removeEventListener("abort", onAbort);
      if (cancelled) {
        resolve("(cancelled)");
      } else if (truncated) {
        resolve(stdout.slice(0, effectiveCap) + " ... (truncated at " + effectiveCap + " chars)");
      } else {
        resolve(`(error running ${bin}: ${err.message})`);
      }
    });
  });
}

// Run claude in `--output-format stream-json --verbose` and parse the NDJSON
// event stream: emit text deltas to onChunk (so the bubble still fills in) and
// REAL tool invocations to onTool (ground truth — the model's own narration is
// never trusted for "what ran"). Returns the final assistant text. Used only on
// the agent/act path; normal chat keeps runCapture's plain-text stream.
export function runClaudeStream(
  bin: string,
  args: string[],
  cwd: string,
  signal: AbortSignal | undefined,
  onChunk: ((delta: string) => void) | undefined,
  onTool: (ev: ToolEvent) => void,
  maxOutputChars?: number,
  onInit?: (init: import("./apps-mirror.ts").ClaudeInit) => void,
): Promise<string> {
  return new Promise((resolve) => {
    if (signal?.aborted) { resolve("(cancelled)"); return; }
    let child;
    try {
      child = spawn(bin, args, { cwd, env: scrubbedEnv(), stdio: ["ignore", "pipe", "pipe"], detached: true });
    } catch (err) {
      resolve(`(error spawning ${bin}: ${(err as Error).message})`);
      return;
    }
    let cancelled = false;
    const onAbort = () => {
      cancelled = true;
      try {
        if (typeof child!.pid === "number") process.kill(-child!.pid, "SIGKILL");
        else child!.kill("SIGKILL");
      } catch { try { child!.kill("SIGKILL"); } catch { /* noop */ } }
    };
    signal?.addEventListener("abort", onAbort);
    const cap = typeof maxOutputChars === "number" ? maxOutputChars : DEFAULT_OUTPUT_CEILING;
    let buf = "";
    let finalText = "";
    const acc: string[] = [];
    let accLen = 0;
    const toolNames = new Map<string, string>();
    // Narration blocks arrive as SEPARATE text blocks with tool calls between
    // them ("checking X" -> tool -> "found Y"). Joined raw they render as one
    // run-on blob ("...exposes.Yes, I can."); insert a paragraph break when a
    // new text block follows tool activity so streamed narration reads as the
    // distinct thoughts it actually was. Applied to acc AND onChunk so the
    // streamed view and the saved reply agree.
    let sawToolSinceText = false;
    // eslint-disable-next-line @typescript-eslint/no-explicit-any
    const handleEvent = (ev: any) => {
      if (!ev || typeof ev !== "object") return;
      // The session's init event: which MCP servers loaded and their live status.
      if (onInit && ev.type === "system" && ev.subtype === "init") {
        try {
          const servers = Array.isArray(ev.mcp_servers) ? ev.mcp_servers.filter((x: unknown) => x && typeof x === "object").map((x: { name?: unknown; status?: unknown }) => ({ name: String(x.name ?? ""), status: String(x.status ?? "") })).filter((x: { name: string }) => x.name) : [];
          const tools = Array.isArray(ev.tools) ? ev.tools.filter((t: unknown): t is string => typeof t === "string") : [];
          onInit({ tools, servers });
        } catch { /* never break on callback */ }
        return;
      }
      if (ev.type === "assistant" && ev.message && Array.isArray(ev.message.content)) {
        for (const b of ev.message.content) {
          if (b && b.type === "text" && typeof b.text === "string" && b.text) {
            const prev = acc.length ? acc[acc.length - 1]! : "";
            const needBreak = acc.length > 0 && sawToolSinceText && !prev.endsWith("\n") && !b.text.startsWith("\n");
            const chunk = (needBreak ? "\n\n" : "") + b.text;
            sawToolSinceText = false;
            acc.push(chunk); accLen += chunk.length;
            if (onChunk && accLen <= cap) onChunk(chunk);
          } else if (b && b.type === "tool_use" && b.name) {
            sawToolSinceText = true;
            if (b.id) toolNames.set(String(b.id), String(b.name));
            try { onTool({ name: String(b.name), phase: "call", id: b.id ? String(b.id) : undefined, input: b.input }); } catch { /* never break on callback */ }
          }
        }
      } else if (ev.type === "user" && ev.message && Array.isArray(ev.message.content)) {
        for (const b of ev.message.content) {
          if (b && b.type === "tool_result") {
            sawToolSinceText = true;
            const nm = toolNames.get(String(b.tool_use_id)) ?? "tool";
            // On failure, pull a short error snippet from the result content so
            // the step checklist can show WHY (debuggability for multi-step runs).
            let resultText: string | undefined;
            if (b.is_error === true) {
              try {
                const parts = Array.isArray(b.content) ? b.content : [];
                const txt = parts.map((p: { type?: string; text?: string }) => (p && p.type === "text" && typeof p.text === "string" ? p.text : "")).join(" ").trim()
                  || (typeof b.content === "string" ? b.content : "");
                if (txt) {
                  // The act gate's machine marker sits at the end of a long
                  // deny reason; keep it through the cut so the desktop can
                  // still render the in-chat approval card.
                  const snippet = txt.slice(0, 200);
                  const marker = txt.match(/\[prevail-act:[A-Za-z0-9_-]+\]/);
                  resultText = marker && !snippet.includes(marker[0]) ? `${snippet} ${marker[0]}` : snippet;
                }
              } catch { /* display only */ }
            }
            try { onTool({ name: nm, phase: "result", ok: b.is_error !== true, id: b.tool_use_id ? String(b.tool_use_id) : undefined, resultText }); } catch { /* noop */ }
          }
        }
      } else if (ev.type === "result" && typeof ev.result === "string") {
        finalText = ev.result;
      }
    };
    child.stdout.on("data", (b) => {
      buf += b.toString();
      let idx: number;
      while ((idx = buf.indexOf("\n")) !== -1) {
        const line = buf.slice(0, idx).trim();
        buf = buf.slice(idx + 1);
        if (!line) continue;
        try { handleEvent(JSON.parse(line)); } catch { /* partial / non-JSON line */ }
      }
    });
    child.stderr.on("data", () => { /* diagnostics only */ });
    const finish = () => {
      signal?.removeEventListener("abort", onAbort);
      const t = buf.trim();
      if (t) { try { handleEvent(JSON.parse(t)); } catch { /* noop */ } }
      if (cancelled) { resolve("(cancelled)"); return; }
      resolve(finalText || acc.join("").trim() || "(no output)");
    };
    child.on("close", finish);
    child.on("error", finish);
  });
}
