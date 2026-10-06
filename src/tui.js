// hncode TUI — raw-TTY renderer (no blessed).
//
// Why raw TTY instead of blessed: blessed cannot render to a non-TTY stream on
// Windows and mis-parses escape sequences here (arrows leak as `[A`, widgets fill
// with `undefined`, Windows Terminal ignores blessed's cursor-shape control).
// That is what produced the garbled screen you saw. kimi-code-cli itself renders
// with raw escape sequences + precise cursor placement, so this module does the
// same using the project's own escape primitives (colors.js / term.js). This
// gives byte-exact control over the block cursor (DECSCUSR), the caret position
// inside the input line, and full-screen redraws on every change/resize.
//
// The renderer is split into a PURE `composeFrame(state, cols, rows)` (returns
// the ANSI bytes — no TTY side effects, fully unit-testable) and `startTUI`
// (the raw-mode loop + key parser + agent wiring).

import path from 'node:path';
import fs from 'node:fs';
import os from 'node:os';
import cp from 'node:child_process';
import {
  C, TRUECOLOR, blockCursor, showCursor, hideCursor, alternateScreen, clearScreen, clearAndSetBg, setTheme, setLightBackground, currentTheme, THEME_NAMES, THEME_LABELS, isLightTheme, hasTheme, lerpColor, bgRgb,
} from './colors.js';
import { copyText, readText, warmClipboard, readClipboardContentAsync, cleanupPastedImages } from './clipboard.js';
import { visualWidth, estimateTokens, estimateMessagesTokens, estimateMessageTokens, messageTokens, expandTabs } from './term.js';
// The picker is composited onto the frame as a cell layer rather than assigned over
// The picker is composited onto the frame as a cell layer rather than assigned over
// it (see src/cell-buffer.js), so the transcript BESIDE the card survives.
import { parseCells, renderCells, drawFrameBuffer } from './cell-buffer.js';
// Streaming text is paced through a backlog so a coalescing provider (Anthropic) looks
// as smooth as a token-level one (OpenAI); see src/stream-buffer.js.
import { StreamBuffer, StreamOp } from './stream-buffer.js';
// What the terminal can actually do, ASKED rather than guessed (synchronized output,
// the Kitty keyboard protocol, a readable theme for the detected background).
import { probeTerminal, terminalCaps, syncOutputUsable, kittyKeysUsable, isLightBg, stripProbeReplies } from './term-caps.js';
// Makes "the terminal has that frame" observable, so the geometry consumers stop assuming
// it. See src/flush-tick.js.
import { noteTerminalFlush, getTerminalFlushTick } from './flush-tick.js';
import { forkOf } from './fork.js';
// Rendered rows live in a shared, bounded store rather than on the message objects.
// See src/row-cache.js for why the bound is by USE, not by position, and why the key
// is content: a key that missed one layout input would serve rows drawn for a
// different frame, which is a mis-drawn screen rather than a stale cache.
import { makeRowKey, rowCacheGet, rowCacheSet } from './row-cache.js';
import { renderContextBar, segmentCaption } from './context-bar.js';
import { runDoctor, formatDoctor } from './doctor.js';
import { profileMemory, renderMemoryProfile } from './memory-profile.js';
import { loadKeybindings, resolveKey, describeKeybindings, readOrEmpty, writeKeybindings, normalizeKey } from './keybindings.js';
import { describeRuns, listRuns, sendToRun, interruptRun, interruptAll, closeRun } from './subagent-control.js';
import { buildTree, visibleRows, allDirs, renderTree, moveSel } from './file-tree.js';
import { walkFiles } from './tools/ignore.js';


import { Agent, SYSTEM_PROMPT, addUsage } from './agent.js';
import { LLM } from './llm.js';
import * as sess from './session.js';
import { convRowFor } from './session.js';
import { resolveProvider, resolveModelArg, addProvider, removeProvider, addModel, upsertModel, replaceProviderModels, fetchModels, fetchCatalog, modelKey, modelLabel, bareModelId, effortOptions, effortWire, effortsFromReasoning, rememberModel, hncodeConfigFile, resolveConfig, setConfigString, setConfigBool, readPersonalPrompt, readPersonalPromptRaw, writePersonalPrompt, personalPromptFile, readAgentsMd, agentsFilesFor, readMemory, readMemoryRaw, writeMemoryRaw, memoryFile, ensureWebToken, effectiveSnapshot, costFromCatalog, modelCost, usageCost } from './config.js';
import { pluginCommands, renderWidgets, runHooks, runPatch, runPatchSync, runKeybindsSync, pluginKeybinds } from './plugin.js';
import { OTHER_LABEL, SUPPLEMENT_LABEL } from './tools/ask-user-question.js';
import { getTool, toolNames } from './tools/index.js';
import { decideFromRules, describeRules, selfTestRules, describeSelfTest } from './permissions.js';
import { isDestructiveCommand as shellIsDestructiveCommand, isReadOnlyCommand as shellIsReadOnlyCommand } from './shell-safety.js';
import { usdRate, syncRate, convert, normalizeCurrency, SUPPORTED_CURRENCIES } from './fx.js';
import { approvalKey, sessionApprovalLabel, isApprovedForSession, rememberApproval, describeSessionApprovals } from './session-approvals.js';
import { listStyles, findStyle, styleReminder, writeStyleTemplate, styleDirs, nameFromFile } from './output-styles.js';
import { EXPERIMENTS, experimentState, enabledExperiments, mergeExperiments, pruneUnknown, describeExperiments, isExperiment } from './experiments.js';
import { forkMessages, SideThread, recapMessages, digestStats, SIDE_RO_TOOLS, SIDE_TOOL_REFUSAL, sideToolAllowed } from './side-thread.js';
import { listSchedules, dueSchedules, markRun, describeSchedules, validateEntry, dueWithHistory, readHistory as readScheduleHistory, writeHistory as writeScheduleHistory } from './schedule.js';
import { packSession, serializeTeleport, parseTeleport, unpackInto, teleportFileName, describeTeleport } from './teleport.js';
import { buildSteps, renderStep, replaySummary, stateAtStep } from './rollout.js';
import { renderBtwPanel, btwPanelHeight } from './btw-panel.js';
import { SessionHub } from './session-hub.js';
import { startWebServer } from './web.js';
import { FAMILIES, TASKS, buildPreset, presetLabel } from './prompt-presets.js';
import * as upd from './update.js';
import { renderTasksBrowser, handleTasksBrowserKey, visibleTasks } from './tasks-browser.js';
import { renderRegistryBrowser, handleRegistryBrowserKey } from './registry-browser.js';
import {
  SETTINGS_SCHEMA, SETTING_BY_KEY, populatedTabs, settingsForTab,
  coerceSetting, effectiveValue, isSet, displayValue, changedSettings,
} from './settings-schema.js';
import { renderTaskOutputViewer, handleViewerKey, makeViewerState } from './task-output-viewer.js';
import { renderSwarmProgress } from './swarm-progress.js';
import { sortedTasks, getTask, settleTask, STATUS_LABEL, backgroundTaskCard } from './agent-task.js';
import { localVersion } from './version.js';
import { listSkills, readSkill, importSkill, deleteSkill, skillPrompt, skillCompletions, normalizeSkillName, SKILL_PREFIX, skillsDir } from './skills.js';
import { loadHooks, describeHooks, runShellHooks, HOOK_EVENTS } from './hooks.js';
import { beginTurn, rewind as rewindFiles, describeRewind, listCheckpoints, restoreCheckpoint, describeCheckpoints, checkpointDelta } from './file-history.js';
import { trimToolResults } from './tool-result.js';
import * as gitmod from './git.js';
import { reviewLines, savePlan, filesReferenced, planStats, listPlans, plansDir } from './plan.js';
import { loadMcpConfig, describeServers, getLiveConnections } from './mcp.js';
import { startControlServer } from './ci.js';
import { attachToDaemon } from './web-daemon-client.js';

const ESC = '\x1b';
const VERSION = localVersion();

// Well-known base URLs for catalog providers that do not publish an `api` field
// (notably the first-party anthropic / openai entries in models.dev — they are
// addressed by SDK, not by URL). Keyed by models.dev provider id.
const CATALOG_DEFAULT_URLS = {
  anthropic: 'https://api.anthropic.com/v1',
  openai: 'https://api.openai.com/v1',
  google: 'https://generativelanguage.googleapis.com/v1beta/openai',
  'google-vertex': 'https://aiplatform.googleapis.com/v1',
  groq: 'https://api.groq.com/openai/v1',
  mistral: 'https://api.mistral.ai/v1',
  deepseek: 'https://api.deepseek.com/v1',
  xai: 'https://api.x.ai/v1',
  openrouter: 'https://openrouter.ai/api/v1',
  together: 'https://api.together.xyz/v1',
  cerebras: 'https://api.cerebras.ai/v1',
  perplexity: 'https://api.perplexity.ai/v1',
  deepinfra: 'https://api.deepinfra.com/v1/openai',
};
function catalogDefaultUrl(id) {
  return CATALOG_DEFAULT_URLS[String(id || '').toLowerCase()] || '';
}

// The Type field's label <-> the wire protocol. Three protocols: chat/completions
// ("OpenAI Compatible" — dozens of non-OpenAI vendors implement it), the Responses
// API ("OpenAI Responses"), and Anthropic ("Anthropic"). The label list lives in
// ONE place so the form, its default, and the keyboard cycle cannot drift.
const PROTOCOL_TYPES = ['OpenAI Compatible', 'OpenAI Responses', 'Anthropic'];
function typeToProtocol(type) {
  const t = String(type || '').toLowerCase();
  if (t === 'anthropic') return 'anthropic';
  if (t.includes('responses')) return 'responses';
  return 'openai';
}
function protocolToType(protocol) {
  if (protocol === 'anthropic') return 'Anthropic';
  if (protocol === 'responses') return 'OpenAI Responses';
  return 'OpenAI Compatible';
}

function cfgCnyPerUsd(cfg) {
  const raw = cfg && ((cfg.raw && cfg.raw.cny_per_usd) ?? cfg.cnyPerUsd);
  const n = Number(raw);
  return Number.isFinite(n) && n > 0 ? n : undefined;
}

// A model entry's pricing fields, ready to spread into `cfg.raw.models[key]`.
// config.js owns the TOML key names; this keeps the in-memory shape and the
// written shape from drifting apart.
function costEntry(cost) {
  if (!cost) return {};
  return {
    cost_input: cost.input,
    cost_output: cost.output,
    cost_cache_read: cost.cacheRead,
    cost_cache_write: cost.cacheWrite,
  };
}

// ---- Slash command registry ----
// Mirrors kimi-code-cli's BUILTIN_SLASH_COMMANDS (registry.ts): name, aliases,
// description, and an argument hint. Commands are sorted by priority so the
// most useful appear first in the `/` menu.
// Monotonic counter for /search: each query bumps it so a slow ripgrep result
// from an earlier keystroke is discarded instead of overwriting newer hits.
let searchSeq = 0;
export const COMMANDS = [
  { name: 'yolo', aliases: ['yes'], desc: 'Yolo mode: anything inside the workspace (edits, writes, commands) runs automatically; paths outside it, destructive commands, questions and plans still ask.', priority: 101 },
  { name: 'permission', desc: 'Select permission mode', priority: 100 },
  { name: 'settings', aliases: ['config'], desc: 'Browse and change every setting, grouped by area', priority: 100, argumentHint: '[tab|filter]' },
  { name: 'set', desc: 'Set one config value by key, or list what differs from the default', priority: 100, argumentHint: '[<key> [value]]' },
  { name: 'plan', desc: 'Toggle plan mode', priority: 100, argumentHint: '[on|off|clear]' },
  { name: 'focus', desc: 'Toggle Focus mode (minimal tools first, full tools after)', priority: 98, argumentHint: '[on|off]' },
  { name: 'auto', desc: 'Auto mode: never interrupts you; everything runs and is decided automatically.', priority: 99 },
  { name: 'ask', aliases: ['manual'], desc: 'Ask mode: read-only runs automatically; every other action asks first.', priority: 99 },
  { name: 'model', desc: 'Switch LLM model', priority: 100 },
  // The argument hint is a PLACEHOLDER, not the level list: the real levels come
  // from the current model (models.dev), so they are completed live by
  // setArgCompletionProvider rather than hardcoded here.
  { name: 'effort', aliases: ['thinking'], desc: 'Switch thinking effort', priority: 95, argumentHint: '[level]' },
  { name: 'provider', aliases: ['providers'], desc: 'Manage AI providers (add / delete)', priority: 95 },
  { name: 'help', aliases: ['h', '?'], desc: 'Show available commands and shortcuts', priority: 80 },
  { name: 'new', aliases: ['clear'], desc: 'Start a fresh session in the current workspace', priority: 80 },
  { name: 'sessions', aliases: ['resume'], desc: 'Browse and resume sessions', priority: 80 },
  { name: 'all-sessions', desc: 'Browse sessions from EVERY workspace', priority: 79 },
  { name: 'tasks', aliases: ['task'], desc: 'Browse background tasks (full-screen panel)', priority: 80 },
  { name: 'swarm', desc: 'Toggle swarm mode: decompose work across parallel subagents', priority: 80, argumentHint: '[on|off]' },
  { name: 'swarm-sub-agent', aliases: ['sub-agent-model'], desc: 'Choose the model subagents run on (default = this session\u2019s model)', priority: 79, argumentHint: '[model|default]' },
  { name: 'compact', desc: 'Compact the conversation context (AI summary + keep last 20%)', priority: 80, argumentHint: '[ratio]' },
  { name: 'goal', aliases: ['objective'], desc: 'Start or manage an autonomous goal', priority: 80, argumentHint: '[status|pause|resume|cancel|replace <text>] | <objective>' },
  { name: 'init', desc: 'Generate or update AGENTS.md from the codebase', priority: 70, argumentHint: '[instructions]' },
  { name: 'fork', desc: 'Fork the current session into a copy without switching to it', priority: 80 },
  { name: 'undo', desc: 'Withdraw the last prompt: transcript + files it changed', priority: 80, argumentHint: '[count]' },
  { name: 'trim', desc: 'Trim old tool results now, down to the keep ratio (manual)', priority: 40, argumentHint: '[keep-ratio]' },
  { name: 'auto-trim', aliases: ['autotrim'], desc: 'Auto tool-result trimming: the threshold is a share of the WINDOW, `keep` a share of the tool-result TEXT', priority: 40, argumentHint: '[on|off | threshold <n> | keep <n>]' },
  { name: 'title', aliases: ['rename'], desc: 'Set or show session title (also sets window title)', priority: 60, argumentHint: '<title>' },
  { name: 'status', desc: 'Show current session and runtime status', priority: 60 },
  { name: 'doctor', desc: 'Diagnose the environment: config, store, MCP, hooks, disk, git, terminal', priority: 60, argumentHint: '[--all] [--probe]' },
  { name: 'memory-profile', aliases: ['memprof'], desc: 'Where this session’s memory goes: text vs tool results vs tool arguments', priority: 60, argumentHint: '[--verbose]' },
  { name: 'usage', desc: 'Show real token totals (provider-reported) + context window', priority: 60 },
  { name: 'cost', desc: 'Show what this session has spent, in USD or CNY', priority: 60, argumentHint: '[usd|cny]' },
  { name: 'context', aliases: ['ctx'], desc: 'Break down what fills the context window', priority: 60 },
  { name: 'raw', desc: 'Show assistant replies verbatim: no Markdown, no wrapping', priority:50, argumentHint: '[on|off]' },
  { name: 'reduced-motion', desc: 'Replace all animation with a slow-breathing indicator', priority: 50, argumentHint: '[on|off]' },
  { name: 'shimmer-edge', desc: 'Sweep edge: cosine (soft both sides) or linear (hard leading edge)', priority: 40, argumentHint: '[cosine|linear]' },
  { name: 'output-style', aliases: ['style'], desc: 'Apply an output style loaded from ~/.hncode/output-styles/*.md', priority: 50, argumentHint: '[name | off | new <name> | edit]' },
  { name: 'experiments', desc: 'List or toggle unfinished features', priority: 50, argumentHint: '[name on|off]' },
  { name: 'btw', aliases: ['aside'], desc: 'Ask a question in a side thread that does not enter the conversation', priority: 55, argumentHint: '[question]' },
  { name: 'recap', desc: 'Say where this session got to, without changing it', priority: 55 },
  { name: 'secondary-model', aliases: ['small-model'], desc: 'Pick the model used for side questions and recaps', priority: 45, argumentHint: '[model | off]' },
  { name: 'replay', aliases: ['rollout'], desc: 'Step back through this session: what the model saw at each step', priority: 45, argumentHint: '[step | next | prev | last]' },
  { name: 'schedule', desc: 'Recurring prompts queued on a running session', priority: 45, argumentHint: '[list | run <id>]' },
  { name: 'teleport', desc: 'Export or import this session for another machine or checkout', priority: 45, argumentHint: '[export [path] | import <file>]' },
  { name: 'search', aliases: ['grep'], desc: 'Search the project and insert the hit into the composer', priority: 60, argumentHint: '[query]' },
  { name: 'mcp', desc: 'Show MCP server status', priority: 60, argumentHint: '[tools]' },
  { name: 'mcp-config', desc: 'Manage MCP servers (interactive, or list / add / remove)', priority: 60, argumentHint: '[list] | add <name> <command|url> [args…] | remove <name>' },
  { name: 'statusline', desc: 'Configure which items appear in the status line', priority: 60 },
  { name: 'theme', desc: 'Switch the colour theme', priority: 60, argumentHint: `[${THEME_NAMES.join('|')}]` },
  { name: 'keybindings', aliases: ['keys'], desc: 'Remap a key to another key or to a slash command', priority: 55, argumentHint: '[list | add <key> <key|/command> | remove <key> | edit]' },
  { name: 'agents', aliases: ['subagents'], desc: 'List running subagents, and message, interrupt or close them', priority: 55, argumentHint: '[list | message <id> <text> | interrupt [id|all] | close <id>]' },
  { name: 'files', aliases: ['tree'], desc: 'Browse the workspace as a tree; Enter inserts the path', priority: 60, argumentHint: '[path-filter]' },
  { name: 'checkpoints', aliases: ['cp'], desc: 'List per-file checkpoints and restore one file on its own', priority: 55, argumentHint: '[list | restore <n> | diff <n>]' },
  { name: 'save-history', desc: 'Keep the display-only transcript (notices, warnings, compaction, plan cards, reasoning) in the saved session', priority: 60, argumentHint: '[on|off|thinking|nothinking]' },
  { name: 'save-history', desc: 'Keep the display-only transcript (notices, warnings, compaction, plan cards, reasoning) in the saved session', priority: 60, argumentHint: '[on|off|thinking|nothinking]' },
  
  { name: 'export-md', aliases: ['export'], desc: 'Export current session as a Markdown file', priority: 40, argumentHint: '[output-path]' },
  { name: 'import-session', aliases: ['import'], desc: 'Attach a Markdown file to the prompt so the AI reads it without a tool call', priority: 40, argumentHint: '<file.md>' },
  { name: 'copy', desc: 'Copy the last assistant message to the clipboard', priority: 40 },
  { name: 'set-system-prompt', aliases: ['system-prompt'], desc: 'Edit the system prompt, or load one of the model-family presets', priority: 60 },
  { name: 'personal', aliases: ['preferences'], desc: 'Edit personal preferences injected into every prompt (global or per-project)', priority: 60, argumentHint: '[global|project]' },
  { name: 'permissions', aliases: ['rules'], desc: 'Show or edit standing allow/ask/deny rules for tools', priority: 60, argumentHint: '[edit]' },
  { name: 'external', aliases: ['allow-external'], desc: 'Toggle access to paths outside the workspace (persisted)', priority: 60, argumentHint: '[on|off]' },
  { name: 'web', desc: 'Serve this session to a browser (token-protected; loopback by default)', priority: 60, argumentHint: '[bindIp] [port] | off' },
  { name: 'calm-mode', desc: 'Terse replies: stop the model narrating what it will do and why unless asked', priority: 60, argumentHint: '[on|off]' },
  { name: 'add-dir', desc: 'Add or list an additional workspace directory', priority: 60, argumentHint: '[list] | <path>' },
  { name: 'move', desc: 'Move current session to another directory (must exist)', priority: 60, argumentHint: '<path>' },
  { name: 'reload', desc: 'Reload config and plugins without restart', priority: 60 },
  { name: 'reload-config', desc: 'Reload config.toml settings only', priority: 60 },
  { name: 'plugins', desc: 'Open the plugin manager (installed + available in the repo)', priority: 60, argumentHint: '[install <name> | remove <name> | reload]' },
  { name: 'skills', desc: 'Open the skill manager (installed + available in the repo)', priority: 60, argumentHint: '[install <name> | remove <name>]' },
  { name: 'import-skill', desc: 'Import a Markdown file as a skill (a duplicate name is overwritten)', priority: 60, argumentHint: '<file.md> [name]' },
  { name: 'hooks', desc: 'Show configured shell hooks, or test one', priority: 60, argumentHint: '[list | test <event>]' },
  { name: 'git', desc: 'Show repository status (branch, changes, remote)', priority: 62 },
  { name: 'commit', desc: 'Stage and commit with a message (or let the agent draft one)', priority: 62, argumentHint: '[message]' },
  { name: 'branch', desc: 'List, create, or switch git branches', priority: 62, argumentHint: '[list | <name> | -c <name>]' },
  { name: 'worktree', desc: 'List, create, or remove git worktrees for parallel work', priority: 60, argumentHint: '[list | new [name] [--branch] | add <dir> [branch] | remove <dir>]' },
  { name: 'pr', desc: 'Show the URL to open a pull request for the current branch', priority: 60, argumentHint: '[base]' },
  { name: 'add', aliases: ['stage'], desc: 'Stage changes (all by default, or given paths)', priority: 62, argumentHint: '[<path> ...]' },
  { name: 'diff', desc: 'Show uncommitted changes', priority: 62, argumentHint: '[--staged|--cached] [<path>]' },
  { name: 'log', desc: 'Show recent commits', priority: 62, argumentHint: '[count] [<path>]' },
  { name: 'push', desc: 'Push the current branch (asks first)', priority: 62, argumentHint: '[branch] [-f]' },
  { name: 'stash', desc: 'Stash changes: list / push / pop', priority: 60, argumentHint: '[list | push [msg] | pop]' },
  { name: 'rebase', desc: 'Rebase the current branch onto another (asks first)', priority: 60, argumentHint: '<branch>' },
  { name: 'cache', desc: 'Toggle prompt caching for long stable prefixes (saves input tokens)', priority: 58, argumentHint: '[on|off]' },
  { name: 'logout', aliases: ['disconnect'], desc: 'Log out of a configured provider', priority: 40 },
  { name: 'feedback', aliases: ['bug'], desc: 'Open a prefilled GitHub issue (title + body)', priority: 60, argumentHint: '<title> | <body>' },
  { name: 'update', desc: 'Check for and install a newer version', priority: 40, argumentHint: '[-y]' },
  { name: 'auto-update', desc: 'Toggle automatic background updates (check at startup + every 30 min)', priority: 40, argumentHint: '[on|off]' },
  { name: 'auto-compact', aliases: ['autocompact'], desc: 'Auto context compaction: toggle, or set the trigger/keep ratios', priority: 40, argumentHint: '[on|off | threshold <n> | keep <n>]' },
  { name: 'version', desc: 'Show version information', priority: 20 },
  { name: 'exit', aliases: ['quit', 'q'], desc: 'Exit the application', priority: 20 },
].sort((a, b) => (b.priority || 0) - (a.priority || 0) || a.name.localeCompare(b.name));

// The shortcuts the web UI shows as buttons. They are ordinary slash commands —
// the browser runs them through the same `dispatch` the keyboard uses, so nothing
// here needs its own implementation.
export const QUICK_COMMANDS = [
  { label: 'compact', cmd: '/compact' },
  { label: 'usage', cmd: '/usage' },
  { label: 'status', cmd: '/status' },
  { label: 'git', cmd: '/git' },
  { label: 'diff', cmd: '/diff' },
  { label: 'permissions', cmd: '/permissions' },
  { label: 'external', cmd: '/external' },
  { label: 'memory', cmd: '/memory' },
  { label: 'tasks', cmd: '/tasks' },
  { label: 'plan', cmd: '/plan' },
];


// Plugin commands are merged into the built-in list at runtime. Plugins are
// loaded before the TUI starts, so this reflects any registered commands.
function allCommands() {
  return [...COMMANDS, ...pluginCommands.map((c) => ({
    name: c.name, description: c.description, desc: c.description, aliases: c.aliases,
    argumentHint: c.argumentHint, priority: c.priority || 50,
    _plugin: true, run: c.run,
  }))].sort((a, b) => (b.priority || 0) - (a.priority || 0) || a.name.localeCompare(b.name));
}

// Resolve a typed name (or alias) to a registry entry.
export function findCommand(name) {
  const n = String(name || '').replace(/^\//, '');
  return COMMANDS.find((c) => c.name === n || (c.aliases || []).includes(n))
    || pluginCommands.find((c) => c.name === n || (c.aliases || []).includes(n));
}

// Check if a command name refers to a plugin command.
export function isPluginCommand(name) {
  const n = String(name || '').replace(/^\//, '');
  return !!pluginCommands.find((c) => c.name === n || (c.aliases || []).includes(n));
}

// Appended to the system prompt while CALM MODE is on (/calm-mode). The point is
// to suppress the model's running commentary — the "I'll now look at X because Y"
// narration — without suppressing the answer or the tool calls themselves.
export const CALM_MODE_INSTRUCTION =
  'CALM MODE is ON. Do not narrate.\n'
  + '- Skip announcing what you are about to do, why you are doing it, or what you\n'
  + '  have just finished. No preamble, no play-by-play, no restating the request.\n'
  + '- Just do the work and report the OUTCOME, briefly. Keep tool calls as normal.\n'
  + '- Explain reasoning only if the user explicitly asks for it, or if a genuine\n'
  + '  blocker/decision needs their input.';

// Appended to the system prompt while PLAN MODE is on (/plan). Without this the
// mode only removed the write tools, leaving the model with no idea what it was
// supposed to PRODUCE — it just read files and stopped. The instruction gives it
// the deliverable and the exact shape it must arrive in.
export const SWARM_MODE_INSTRUCTION =
  'SWARM MODE is ON. The user expects large parallel decomposition.\n'
  + '- First do a SMALL amount of exploratory work to decide how to split the task.\n'
  + '- Then do not handle the main work yourself. Use AgentSwarm with a\n'
  + '  prompt_template containing the {{item}} placeholder and an items array\n'
  + '  partitioning the problem, so each subagent gets a distinct part.\n'
  + '- Give each subagent a distinct scope; avoid duplicating work or assigning\n'
  + '  conflicting changes.\n'
  + '- Do not conserve agents: AgentSwarm queues launches automatically. Decompose\n'
  + '  as finely as the work allows while keeping scopes non-conflicting.\n'
  + '- This mode IS the explicit permission to delegate: the rule against spawning\n'
  + '  subagents unprompted still applies everywhere else.\n'
  + '- If after exploring you conclude no subagent is needed, say why and stop.';

export const PLAN_MODE_INSTRUCTION =
  'PLAN MODE is ON. You are in a read-only planning phase.\n'
  + '- The write tools (Write, Edit, Bash, ...) are NOT available. Investigate with\n'
  + '  the read-only tools you do have, then produce a PLAN.\n'
  + '- Do NOT try to make the changes. Your job this turn is the plan, not the code.\n'
  + '- End your reply with the plan wrapped in <|plan|> and </|plan|> tags, on their\n'
  + '  own lines. Everything between them is shown to the user verbatim and is what\n'
  + '  they approve. Only the LAST such block is used.\n'
  + '- Inside the block, use short Markdown: a heading per step, and bullets for the\n'
  + '  files to touch and why. Be concrete enough that the plan can be executed as\n'
  + '  written — name files, functions and commands.\n'
  + '- Keep any text OUTSIDE the tags to a one-line summary of what you found.\n'
  + '- Once the plan is approved the mode turns off and you get the write tools, so\n'
  + '  the plan must stand on its own.\n'
  + '\n'
  + 'Example shape:\n'
  + '<|plan|>\n'
  + '## Add the /personal command\n'
  + '- `src/config.js`: add readPersonalPrompt() merging global + project files.\n'
  + '- `src/tui.js`: register /personal, inject the text each turn.\n'
  + '## Verify\n'
  + '- Write a temp workspace, check both scopes merge in order.\n'
  + '</|plan|>';

// Sent back to the model once the user approves a plan. Plan mode is off by then,
// so it has the write tools; this frames the approved text as an instruction
// rather than as another question, and forbids re-planning.
export const PLAN_EXECUTE_PREFIX =
  'The user approved the plan. Plan mode is OFF — you now have the write tools.\n'
  + 'Execute the plan you produced. Do not produce another plan and do not re-ask\n'
  + 'for approval; if a step turns out to be impossible, do the rest and report\n'
  + 'plainly what you could not do.\n\n';

// The plan block's delimiters. Pipe-delimited on purpose: `<plan>` is a bare word in
// angle brackets, so a reply that merely mentions the word "plan" in prose — or shows
// HTML — could match it, and a tag the model writes inside a code fence is
// indistinguishable from one that delimits the block. The extra bars make an accidental
// match effectively impossible while staying plain text in every model's output.
export const PLAN_OPEN_TAG = '<|plan|>';
export const PLAN_CLOSE_TAG = '</|plan|>';

// Pull the LAST <|plan|>…</|plan|> block out of an assistant reply. Returns null when
// there is none, so callers can tell "no plan offered" from "empty plan".
export function extractPlan(text) {
  const s = String(text || '');
  const open = /<\|plan\|>\s*/gi;
  let match = null, m;
  while ((m = open.exec(s)) !== null) match = m;
  if (!match) return null;
  const start = match.index + match[0].length;
  // The CLOSE is matched case-insensitively too: a model that capitalises the opening
  // tag capitalises the closing one, and a case-sensitive search for the close then
  // runs past it to the end of the reply — so the whole tail, closing tag included,
  // became the "plan".
  const close = /<\/\|plan\|>/i.exec(s.slice(start));
  const body = (close ? s.slice(start, start + close.index) : s.slice(start)).trim();
  return body || null;
}

export const TIPS = [
  // Kept short on purpose: a tip shares the status line with the model, cwd, git
  // badge and tokens, and `justify()` TRUNCATES it when the two sides do not fit.
  // A tip long enough to be cut mid-word ("Old tool results are elided from the
  // request at 50% of the wi…") reads as a rendering bug, so every entry below
  // states ONE idea and stays under ~60 visual columns.
  'Press Esc to interrupt the current turn',
  '!git status runs a shell command directly',
  '/init writes an AGENTS.md from your codebase',
  'Use /mcp to manage MCP servers',
  'The context line shows live token usage',
  '/goal starts a self-driving objective',
  'Paste multiline content — it becomes one token',
  '/usage shows token and context statistics',
  'Ctrl+C aborts the current turn',
  'The spinner cycles status messages while working',
  '/model opens a picker — Tab switches providers',
  '/provider lets you add or switch AI providers',
  'Tool calls stream their arguments live',
  '/think adds inline reasoning instructions',
  'The todo list updates live as the agent progresses',
  '/focus gives the agent Read, Write, Edit, and Bash',
  'System messages are green — instructions, not chat',
  'Queued messages wait for the turn to finish',
  '/steer injects a message into the running turn',
  'Ctrl+R reloads the current session from disk',
  '/help shows available commands at any time',
  '/undo rolls back the transcript AND the files',
  '/fork copies the session so you can branch',
  '/sessions lists saved conversations here',
  '/all-sessions lists them from every workspace',
  '/title names the current session',
  '/compact [ratio] summarizes older history',
  '/tasks lists background Bash jobs',
  '/status prints model, provider, endpoint',
  '/statusline toggles the bottom status bar items',
  '/memory shows or edits notes for later sessions',
  '/personal edits your standing preferences',
  '/permissions shows allow/ask/deny rules for tools',
  '/external toggles access outside the workspace',
  '/web serves this session to a browser',
  '/add-dir grants access to another directory',
  '/reload re-reads config.toml without restarting',
  '/skills install <name> pulls one from the repo',
  '/logout clears the stored API key',
  '/version prints the hncode version string',
  '/feedback opens a prefilled GitHub issue',
  '/copy puts the last answer on the clipboard',
  '/export-md writes the session to a Markdown file',
  '/import-session attaches a Markdown file',
  '/new starts a fresh conversation',
  '/goal pause pauses the objective',
  '/goal resume resumes the objective',
  '/plan on makes every tool read-only',
  '/focus on gives the agent Write tools and Bash',
  '/permission opens the picker for Ask / Yolo / Auto',
  '/settings opens the combined settings menu',
  '/yolo auto-approves anything inside the workspace',
  '/auto never interrupts you; everything runs',
  '/usage shows the real token totals, not an estimate',
  '/cost [usd|cny] shows what this session has spent',
  'The session cost appears in the status row once prices are known',
  'Shift+Arrow selects text in the composer',
  'Shift+Enter inserts a newline without sending',
  'Ctrl+T expands or collapses the todo panel',
  'Ctrl+P opens the command palette',
  'Ctrl+O expands tool output and Edit diffs',
  'Ctrl+B backgrounds a running Bash command',
  'Ctrl+Shift+V pastes as a bracketed paste',
  'Ctrl+Shift+C copies the selection or last answer',
  'Ctrl+L expands or collapses the plugin load log',
  'Ctrl+Up / Ctrl+Down scroll the AI output area',
  '↑ recalls the newest queued message',
  '↑/↓ walks through your input history',
  'PgUp / PgDn scroll the transcript',
  'Mouse-wheel over the composer scrolls the chat',
  'Drag the right-edge scrollbar to jump',
  'Double-click a row to select the whole line',
  'Right-click a row for the copy / paste menu',
  'Esc closes any open picker, form, or menu',
  'Esc aborts the in-flight model request',
  'Ctrl+C twice exits hncode',
  'Ctrl+C with a dialog open closes the dialog',
  'The `/` menu filters as you type',
  'Enter on a `/` item runs it',
  'Tab on a `/` item completes its name',
  'The context gauge turns red near the limit',
  'Auto-compaction triggers at 85% of the context',
  'Old tool results are elided at 50% of the window',
  '/compact summarizes older history, keeping 20%',
  'Long tool results collapse — Ctrl+O expands them',
  'A red bullet means the command exited non-zero',
  'A green bullet means the tool succeeded',
  'The `[turn took …]` line shows the turn duration',
  '/provider add picks a provider from models.dev',
  '/model groups models by provider — Tab cycles',
  'Typing `/` opens the command palette'
];

// Layout constants (kimi-code-cli style: no top chrome; the chat fills to the
// top, and the bottom stack is: input box (bottom) / menu / status line /
// context line — the context line is the very last row of the screen).
// Below the composer, top to bottom: status line, the context bar, then the notice/tip
// row. `CTX_H` covers the last TWO of those: the bar and the row under it.
const CTX_H = 2;                 // context bar + the notice/tip row beneath it
const STATUS_H = 1;              // status line (above the context bar)
const INPUT_BASE_H = 3;          // input box: top border + input line + bottom border
const MAX_MENU = 6;              // menu rows shown (matches the ~6 you see)
const MAX_PICKER = 12;            // max picker list rows shown at once
// How many of the MOST RECENT messages keep their wrapped-row cache. The cache
// makes a re-render cheap, but it holds a full copy of the message's rows and used
// to live forever (see the eviction in renderChatLines): 8000 messages held 42000
// cached rows (~20 MB of heap) and only grew. Keeping the tail covers everything
// the viewport shows; older messages re-render on demand when scrolled back to,
// which costs one layout pass instead of permanent memory.
const CACHE_KEEP = 300;
const TIP_INTERVAL = 15000;
// Braille spinner frames for the "Working" indicator (orange).
const SPINNER = ['⠋', '⠙', '⠹', '⠸', '⠼', '⠴', '⠦', '⠧', '⠇', '⠏'];
// The REDUCED-MOTION spinner: a single dot that breathes on a slow cycle, rather
// than a rotating glyph. Claude Code does this (`REDUCED_MOTION_CYCLE_MS = 2000`,
// "1s visible, 1s dim") and the reasoning is worth keeping: a fully static glyph
// reads as "hung", so the slow brightness change is what says "still working"
// without any motion. Two seconds is slow enough not to draw the eye.
const REDUCED_MOTION_DOT = '●';
const REDUCED_MOTION_CYCLE_MS = 2000;
// Stand-in for the LIVE spinner glyph inside a CACHED row. A pending thinking
// block must not be re-wrapped by the 80ms spin tick (see renderChatLines), so
// its preview is cached with this sentinel and the real frame is substituted in
// afterwards. It occupies 0 columns, so the swap never disturbs the layout.
const SPIN_PLACEHOLDER = '\u0000';

/** Is reduced motion on for this session? Read from config, or the env override. */
export function reducedMotionOn(state) {
  if (!state) return false;
  if (state.reducedMotion !== undefined) return !!state.reducedMotion;
  const env = process.env.HNCODE_REDUCED_MOTION;
  if (env !== undefined) return /^(1|true|yes|on)$/i.test(env);
  return !!(state.cfg && state.cfg.reducedMotion);
}

/**
 * The frames a SPINNER-style animation shows: { glyph, dim }.
 *
 * In normal mode the glyph rotates and is never dim. In reduced motion the glyph is
 * a constant dot whose brightness flips once per second — the same 2-second cycle
 * Claude uses. Returning both pieces means every caller (the Working row, a pending
 * tool, a thinking preview) gets the same treatment from one place.
 */
export function spinnerFrame(state, tick) {
  if (reducedMotionOn(state)) {
    const t = tick !== undefined ? tick : (state && state.spin) || 0;
    return { glyph: REDUCED_MOTION_DOT, dim: Math.floor(t / (REDUCED_MOTION_CYCLE_MS / 80)) % 2 === 1 };
  }
  const n = SPINNER.length;
  const i = ((tick !== undefined ? tick : (state && state.spin) || 0) % n + n) % n;
  return { glyph: SPINNER[i], dim: false };
}

/**
 * A sweep that SETTLES: a character the band has passed stays at 1.
 *
 * This is the shape the Working row's colour phase needs, and the two previous
 * attempts both got it wrong by reusing a travelling PULSE:
 *
 *   * the original `(head - charAt) / BAND` ramps DOWN as the head passes, so a
 *     character lit up and then went DARK again — the phrase never became orange;
 *   * the cosine `0.5 * (1 + cos(PI * d / half))` is a bell centred on the band, so
 *     every character dimmed again once the band left it. Measured over one colour
 *     phase it animated `[ ] -> [ :#@#: ] -> [ :#] -> [ ]`: a light sweeping across
 *     and leaving nothing behind.
 *
 * The convention that fixes it, stated once here:
 *
 *   `dist >= 0`          the band is past this character -> 1 (settled)
 *   `-half < dist < 0`   the band is on it -> ramp 0 -> 1
 *   `dist <= -half`      not reached yet -> 0
 *
 * `dist` is `head - position`, so a LARGER `dist` means "further behind the head".
 * `edge` shapes only the transition band:
 *   `cosine` — a raised cosine, so both ends of the ramp are gentle;
 *   `linear` — a straight ramp, sharpest at the settle point.
 */
export function sweepSettle(dist, half, edge = 'cosine') {
  const h = Math.max(1e-6, half);
  if (dist >= 0) return 1;              // passed: stays lit
  if (dist <= -h) return 0;             // not yet reached
  const x = (dist + h) / h;             // 0 at the far edge, 1 at the settle point
  return edge === 'linear' ? x : 0.5 * (1 - Math.cos(Math.PI * x));
}

// ---------------------------------------------------------------------------
// Sweep parameters — ONE set of numbers for every animated row
// ---------------------------------------------------------------------------
// The parameter that decides whether a sweep reads as a GRADIENT or as a SNAP is
// frames-per-character: how many 80ms ticks a character spends crossing the band.
//
//     framesPerChar = BAND * ticks / travel        (BAND = bandChars / n)
//
// With the old `travel = 1 + 2*BAND` this approached `ticks / 2` as the band grew, so
// the half-sweep's tick count ALONE capped the smoothness: the previous values (band
// 3.3 chars, 6 ticks) gave 1.20 frames per character, meaning each character changed
// colour inside a single frame — a snap, not a fade. The comment claiming "a 3-char
// band gives each char ~3 frames" was simply wrong.
//
// The geometry also wasted margin at both ends: the head only has to run from the far
// edge of the band to the settle point, i.e. `travel = 1 + BAND`, not `1 + 2*BAND`.
// Correcting that buys ~25% more frames for free, because the extra was spent sweeping
// through empty space before and after the row.
export const SWEEP_TICKS = 10;          // ticks per half-sweep (0.8s, so a 3.2s cycle)
const SWEEP_TRAVEL_PAD = 1;             // head runs from -BAND to 1

/**
 * Band width in characters, scaled to the row so every row is equally smooth.
 *
 * HALF THE ROW, with a floor of 3 characters. Because the band is then always `n/2`,
 * `BAND = 0.5` for every row of 6+ characters, so frames-per-character — and therefore
 * the visual smoothness — is the SAME for a 6-char tool name and a 60-char phrase.
 *
 * An earlier version capped the band at 6 characters, which made BAND shrink as the row
 * grew: a 30-char row got 1.67 frames per character and snapped, so the cap defeated the
 * very scaling it was part of. The floor matters for very short rows, where half the row
 * would be a 2-char band — a flash rather than a sweep.
 */
export function bandCharsFor(n) {
  return Math.max(3, n / 2);
}

/** Frames each character spends inside the band — the smoothness measure. */
export function framesPerChar(n, ticks = SWEEP_TICKS) {
  const BAND = bandCharsFor(n) / n;
  return (BAND * ticks) / (1 + BAND * SWEEP_TRAVEL_PAD);
}

// How long a foreground Bash command runs before its card advertises Ctrl+B, and
// the hint text itself. Mirrors kimi-code's tool-call card (DETACH_HINT_*).
const DETACH_HINT_DELAY_MS = 10_000;
const DETACH_HINT_TEXT = 'Press Ctrl+B to run in background';

// Rotating status messages for the "Working..." line — all mean "the agent is
// thinking / working", but vary the wording so it doesn't look stuck.
const WORKING_MESSAGES = [
  // ---- A (100) ----
  'Accelerating...', 'Accessing...', 'Acclaiming...', 'Acclimating...', 'Accommodating...', 'Accompanying...', 'Accomplishing...', 'Accounting...', 'Accrediting...', 'Accruing...',
  'Accumulating...', 'Achieving...', 'Acknowledging...', 'Acquainting...', 'Acquiring...', 'Acting...', 'Activating...', 'Actualizing...', 'Adapting...', 'Adding...',
  'Addressing...', 'Adhering...', 'Adjusting...', 'Administering...', 'Admiring...', 'Adopting...', 'Adorning...', 'Advancing...', 'Advocating...', 'Affirming...',
  'Affording...', 'Aggregating...', 'Agreeing...', 'Aiding...', 'Aiming...', 'Aligning...', 'Alleviating...', 'Allocating...', 'Allowing...', 'Alluring...',
  'Altering...', 'Amalgamating...', 'Amassing...', 'Amending...', 'Amplifying...', 'Analyzing...', 'Anchoring...', 'Animating...', 'Annotating...', 'Announcing...',
  'Answering...', 'Anticipating...', 'Appealing...', 'Applauding...', 'Applying...', 'Appointing...', 'Appraising...', 'Appreciating...', 'Approaching...', 'Approving...',
  'Architecting...', 'Archiving...', 'Arranging...', 'Articulating...', 'Ascending...', 'Ascertaining...', 'Aspiring...', 'Assembling...', 'Asserting...', 'Assessing...',
  'Assigning...', 'Assimilating...', 'Assisting...', 'Assuring...', 'Astonishing...', 'Attaining...', 'Attempting...', 'Attending...', 'Attracting...', 'Auditing...',
  'Augmenting...', 'Authenticating...', 'Authoring...', 'Authorizing...', 'Automating...', 'Awakening...', 'Awarding...', 'Attuning...', 'Absorbing...', 'Accenting...',
  'Acquiescing...', 'Adjudicating...', 'Adventuring...', 'Alerting...', 'Ameliorating...', 'Allying...', 'Annexing...', 'Aping...', 'Availing...', 'Averaging...',
  // ---- B (100) ----
  'Babbling...', 'Backing...', 'Backtracking...', 'Balancing...', 'Ballooning...', 'Banking...', 'Bargaining...', 'Bartering...', 'Basing...', 'Basking...',
  'Batching...', 'Bathing...', 'Battling...', 'Beaching...', 'Beaming...', 'Bearing...', 'Beating...', 'Beautifying...', 'Beckoning...', 'Becoming...',
  'Bedazzling...', 'Befriending...', 'Beginning...', 'Behaving...', 'Beholding...', 'Believing...', 'Belonging...', 'Benchmarking...', 'Bending...', 'Benefiting...',
  'Bequeathing...', 'Beseeching...', 'Bestowing...', 'Bettering...', 'Bidding...', 'Biding...', 'Billowing...', 'Binding...', 'Birthing...', 'Biting...',
  'Blasting...', 'Blazing...', 'Bleaching...', 'Bleeding...', 'Blending...', 'Blessing...', 'Blinking...', 'Blooming...', 'Blossoming...', 'Blowing...',
  'Blurring...', 'Blushing...', 'Boarding...', 'Boasting...', 'Boiling...', 'Bolstering...', 'Bonding...', 'Booking...', 'Booming...', 'Boosting...',
  'Bootstrapping...', 'Borrowing...', 'Bottling...', 'Bouncing...', 'Bounding...', 'Bowing...', 'Bowling...', 'Boxing...', 'Bracing...', 'Brainstorming...',
  'Braiding...', 'Branching...', 'Branding...', 'Braving...', 'Breaking...', 'Breathing...', 'Breeding...', 'Breezing...', 'Brewing...', 'Bridging...',
  'Briefing...', 'Brightening...', 'Bringing...', 'Broadcasting...', 'Broadening...', 'Bronzing...', 'Browsing...', 'Brushing...', 'Bubbling...', 'Budding...',
  'Budgeting...', 'Buffering...', 'Building...', 'Bulking...', 'Bundling...', 'Buoying...', 'Burnishing...', 'Bustling...', 'Buying...', 'Buzzing...',
  // ---- C (100) ----
  'Caching...', 'Cajoling...', 'Caking...', 'Calibrating...', 'Calling...', 'Calming...', 'Campaigning...', 'Camping...', 'Canceling...', 'Canoodling...',
  'Canvasing...', 'Capitalizing...', 'Captioning...', 'Captivating...', 'Capturing...', 'Caring...', 'Carving...', 'Cascading...', 'Cashing...', 'Casting...',
  'Cataloging...', 'Catapulting...', 'Catching...', 'Categorizing...', 'Catering...', 'Cautioning...', 'Ceasing...', 'Celebrating...', 'Cementing...', 'Centralizing...',
  'Certifying...', 'Chaining...', 'Chairing...', 'Chalking...', 'Challenging...', 'Championing...', 'Channeling...', 'Chanting...', 'Chaperoning...', 'Charging...',
  'Charting...', 'Chasing...', 'Chatting...', 'Cheering...', 'Cherishing...', 'Chewing...', 'Chilling...', 'Chiming...', 'Chipping...', 'Chirping...',
  'Chiseling...', 'Choosing...', 'Chopping...', 'Choreographing...', 'Chronicling...', 'Chugging...', 'Ciphering...', 'Circling...', 'Circulating...', 'Citing...',
  'Civilizing...', 'Clamping...', 'Clanging...', 'Clapping...', 'Clarifying...', 'Clashing...', 'Classifying...', 'Clawing...', 'Cleaning...', 'Cleansing...',
  'Clearing...', 'Cleaving...', 'Climbing...', 'Clinching...', 'Clipping...', 'Cloaking...', 'Clocking...', 'Cloning...', 'Closing...', 'Clouding...',
  'Clustering...', 'Clutching...', 'Coaching...', 'Coalescing...', 'Coating...', 'Coaxing...', 'Cocooning...', 'Codifying...', 'Coexisting...', 'Cogitating...',
  'Cohering...', 'Coiling...', 'Coinciding...', 'Collaborating...', 'Collapsing...', 'Collating...', 'Collecting...', 'Coloring...', 'Combining...', 'Comforting...',
  // ---- D (100) ----
  'Dabbling...', 'Dampening...', 'Dancing...', 'Daring...', 'Darting...', 'Dashing...', 'Dating...', 'Dawdling...', 'Dazzling...', 'Deactivating...',
  'Debugging...', 'Debuting...', 'Decanting...', 'Decelerating...', 'Decentralizing...', 'Deciding...', 'Deciphering...', 'Decking...', 'Declaring...', 'Decoding...',
  'Decomposing...', 'Decorating...', 'Decoupling...', 'Dedicating...', 'Deducing...', 'Deepening...', 'Defeating...', 'Defending...', 'Deferring...', 'Defining...',
  'Deflecting...', 'Defragmenting...', 'Defusing...', 'Degreasing...', 'Dehydrating...', 'Delegating...', 'Deliberating...', 'Delighting...', 'Delivering...', 'Delving...',
  'Demanding...', 'Demarcating...', 'Demonstrating...', 'Demystifying...', 'Denoting...', 'Densifying...', 'Departing...', 'Depending...', 'Deploying...', 'Depicting...',
  'Depositing...', 'Depressurizing...', 'Deriving...', 'Descending...', 'Describing...', 'Desiring...', 'Despatching...', 'Detailing...', 'Detecting...', 'Deterring...',
  'Determining...', 'Detoxing...', 'Devaluing...', 'Developing...', 'Deviating...', 'Devising...', 'Devoting...', 'Diagnosing...', 'Diagramming...', 'Dialing...',
  'Digesting...', 'Digging...', 'Digitizing...', 'Diluting...', 'Dimensioning...', 'Directing...', 'Disarming...', 'Disbursing...', 'Discarding...', 'Discerning...',
  'Discharging...', 'Disciplining...', 'Disclosing...', 'Disconnecting...', 'Discounting...', 'Discovering...', 'Discrediting...', 'Discussing...', 'Disentangling...', 'Disguising...',
  'Disinfecting...', 'Dislodging...', 'Dismantling...', 'Dismissing...', 'Dispatching...', 'Dispensing...', 'Dispersing...', 'Displaying...', 'Disposing...', 'Disproving...',
  'Dissecting...', 'Disseminating...', 'Dissipating...', 'Dissolving...', 'Distilling...', 'Distinguishing...', 'Distributing...', 'Diversifying...', 'Diverting...', 'Dividing...',
  'Divining...', 'Divulging...', 'Docking...', 'Documenting...', 'Dodging...', 'Domesticating...', 'Dominating...', 'Donating...', 'Doodling...', 'Dosing...',
  'Doubling...', 'Dovetailing...', 'Downloading...', 'Drafting...', 'Draining...', 'Dramatizing...', 'Drawing...', 'Dreaming...', 'Dredging...', 'Dressing...',
  'Drifting...', 'Drilling...', 'Driving...', 'Dropping...', 'Drumming...', 'Drying...', 'Ducking...', 'Dusting...', 'Dwelling...', 'Dyeing...',
  // ---- E (100) ----
  'Earning...', 'Easing...', 'Echoing...', 'Eclipsing...', 'Economizing...', 'Edging...', 'Editing...', 'Educating...', 'Effecting...', 'Effervescing...',
  'Elaborating...', 'Elating...', 'Electing...', 'Electrifying...', 'Elevating...', 'Eliciting...', 'Eliminating...', 'Elucidating...', 'Emancipating...', 'Embarking...',
  'Embedding...', 'Embellishing...', 'Embodying...', 'Embracing...', 'Embroidering...', 'Emerging...', 'Emitting...', 'Empathizing...', 'Emphasizing...', 'Empowering...',
  'Emulating...', 'Enabling...', 'Enacting...', 'Encapsulating...', 'Enchanting...', 'Encircling...', 'Enclosing...', 'Encoding...', 'Encouraging...', 'Encrypting...',
  'Endearing...', 'Endeavoring...', 'Endorsing...', 'Endowing...', 'Enduring...', 'Energizing...', 'Enforcing...', 'Engaging...', 'Engineering...', 'Engraving...',
  'Enhancing...', 'Enjoying...', 'Enlarging...', 'Enlightening...', 'Enlisting...', 'Enlivening...', 'Enriching...', 'Enrolling...', 'Ensuring...', 'Entering...',
  'Entertaining...', 'Enthralling...', 'Enthusing...', 'Enticing...', 'Entitling...', 'Enumerating...', 'Enveloping...', 'Envisioning...', 'Equipping...', 'Equalizing...',
  'Erecting...', 'Erasing...', 'Escalating...', 'Escaping...', 'Escorting...', 'Establishing...', 'Esteeming...', 'Estimating...', 'Eulogizing...', 'Evaluating...',
  'Evaporating...', 'Evolving...', 'Examining...', 'Exceeding...', 'Excelling...', 'Exchanging...', 'Exciting...', 'Excluding...', 'Executing...', 'Exercising...',
  'Exhaling...', 'Exhibiting...', 'Exhilarating...', 'Existing...', 'Expanding...', 'Expecting...', 'Expediting...', 'Experiencing...', 'Experimenting...', 'Explaining...',
  'Exploring...', 'Exporting...', 'Exposing...', 'Expressing...', 'Extending...', 'Externalizing...', 'Extracting...', 'Extrapolating...', 'Eyeing...',
  // ---- F (100) ----
  'Fabricating...', 'Facilitating...', 'Facing...', 'Factoring...', 'Fading...', 'Farming...', 'Fascinating...', 'Fashioning...', 'Fastening...', 'Fathoming...',
  'Favoring...', 'Feathering...', 'Featuring...', 'Feeding...', 'Feeling...', 'Fencing...', 'Fermenting...', 'Ferrying...', 'Fertilizing...', 'Fetching...',
  'Fiddling...', 'Fielding...', 'Figuring...', 'Filing...', 'Filling...', 'Filtering...', 'Financing...', 'Finding...', 'Fingerprinting...', 'Finishing...',
  'Firing...', 'Firming...', 'Fishing...', 'Fitting...', 'Fixing...', 'Flagging...', 'Flanking...', 'Flashing...', 'Flattening...', 'Flattering...',
  'Flavoring...', 'Fleshing...', 'Flexing...', 'Flicking...', 'Flinging...', 'Flipping...', 'Floating...', 'Flooding...', 'Flooring...', 'Flourishing...',
  'Flowing...', 'Flushing...', 'Fluttering...', 'Flying...', 'Foaming...', 'Focusing...', 'Folding...', 'Following...', 'Forging...', 'Forgiving...',
  'Formalizing...', 'Forming...', 'Formulating...', 'Fortifying...', 'Forwarding...', 'Fostering...', 'Founding...', 'Fragmenting...', 'Framing...', 'Freeing...',
  'Freezing...', 'Freshening...', 'Frosting...', 'Frying...', 'Fueling...', 'Fulfilling...', 'Functioning...', 'Funding...', 'Furnishing...', 'Furthering...',
  'Fusing...', 'Fussing...', 'Factorizing...', 'Fantasizing...', 'Faultfinding...', 'Federating...', 'Fending...', 'Ferreting...', 'Filming...', 'Finalizing...',
  'Finessing...', 'Fireproofing...', 'Fizzing...', 'Flameproofing...', 'Fleecing...', 'Flickering...', 'Flitting...', 'Fluctuating...', 'Fluorescing...', 'Freewheeling...',
  // ---- G (100) ----
  'Gaining...', 'Galloping...', 'Galvanizing...', 'Gaming...', 'Gardening...', 'Garlanding...', 'Garnering...', 'Gathering...', 'Gauging...', 'Gazing...',
  'Gearing...', 'Generalizing...', 'Generating...', 'Gesticulating...', 'Gesturing...', 'Getting...', 'Gifting...', 'Giggling...', 'Gilding...', 'Girding...',
  'Giving...', 'Glancing...', 'Glazing...', 'Gleaming...', 'Gleaning...', 'Glimmering...', 'Glimpsing...', 'Gliding...', 'Glistening...', 'Glittering...',
  'Glowing...', 'Glueing...', 'Goading...', 'Gobbling...', 'Golfing...', 'Governing...', 'Grabbing...', 'Graduating...', 'Grafting...', 'Granting...',
  'Graphing...', 'Grasping...', 'Gratifying...', 'Grating...', 'Greasing...', 'Greeting...', 'Gridding...', 'Grilling...', 'Grinding...', 'Gripping...',
  'Grooving...', 'Grooming...', 'Grounding...', 'Grouping...', 'Growing...', 'Guaranteeing...', 'Guarding...', 'Guessing...', 'Guiding...', 'Gushing...',
  'Gusting...', 'Gutting...', 'Guzzling...', 'Gamboling...', 'Gating...', 'Gazetting...', 'Gelling...', 'Gentrifying...', 'Germinating...', 'Gestating...',
  'Ghosting...', 'Glaciating...', 'Gladdening...', 'Globalizing...', 'Glorifying...', 'Glossing...', 'Gonging...', 'Gouging...', 'Grandstanding...', 'Granulating...',
  'Gravitating...', 'Grazing...', 'Greening...', 'Grimacing...', 'Grubbing...', 'Gurgling...', 'Gyrating...', 'Gabbing...', 'Gaffing...', 'Gallivanting...',
  'Galumphing...', 'Garbling...', 'Garrisoning...', 'Gasping...', 'Gentling...', 'Geotagging...', 'Gimballing...', 'Glinting...', 'Gorging...', 'Grinning...',
  // ---- H (100) ----
  'Habilitating...', 'Hacking...', 'Haggling...', 'Hailing...', 'Halting...', 'Hammering...', 'Handcrafting...', 'Handing...', 'Handling...', 'Hanging...',
  'Happening...', 'Harboring...', 'Hardening...', 'Harmonizing...', 'Harnessing...', 'Harvesting...', 'Hashing...', 'Hastening...', 'Hatching...', 'Hauling...',
  'Having...', 'Heading...', 'Healing...', 'Heaping...', 'Hearing...', 'Heartening...', 'Heating...', 'Heaving...', 'Hedging...', 'Heeding...',
  'Helping...', 'Heralding...', 'Herding...', 'Hesitating...', 'Hibernating...', 'Hiding...', 'Highlighting...', 'Hiking...', 'Hinging...', 'Hinting...',
  'Hiring...', 'Hitting...', 'Hoarding...', 'Hoisting...', 'Holding...', 'Hollowing...', 'Homing...', 'Honing...', 'Honoring...', 'Hooking...',
  'Hopping...', 'Hoping...', 'Horsing...', 'Hosting...', 'Hotfixing...', 'Hovering...', 'Howling...', 'Huddling...', 'Hugging...', 'Hulling...',
  'Humanizing...', 'Humbling...', 'Humming...', 'Hunting...', 'Hurling...', 'Hurrying...', 'Hushing...', 'Hustling...', 'Hybridizing...', 'Hydrating...',
  'Hydroplaning...', 'Hymning...', 'Hyping...', 'Hypothesizing...', 'Habituating...', 'Hairdressing...', 'Hallowing...', 'Halving...', 'Handholding...', 'Handpicking...',
  'Handwriting...', 'Hankering...', 'Hardcoding...', 'Harkening...', 'Hawking...', 'Haymaking...', 'Headhunting...', 'Headlining...', 'Heartwarming...', 'Heightening...',
  'Heehawing...', 'Homesteading...', 'Homeschooling...', 'Honeying...', 'Hooping...', 'Hornswoggling...', 'Hosing...', 'Hounding...', 'Huckstering...', 'Humoring...',
  // ---- I (100) ----
  'Idealizing...', 'Identifying...', 'Igniting...', 'Ignoring...', 'Illuminating...', 'Illustrating...', 'Imagining...', 'Imitating...', 'Immersing...', 'Immortalizing...',
  'Impacting...', 'Imparting...', 'Impersonating...', 'Implementing...', 'Implicating...', 'Importing...', 'Imposing...', 'Impressing...', 'Imprinting...', 'Improving...',
  'Improvising...', 'Inaugurating...', 'Incentivizing...', 'Inching...', 'Including...', 'Incorporating...', 'Increasing...', 'Incrementing...', 'Incubating...', 'Incurring...',
  'Indenting...', 'Indexing...', 'Indicating...', 'Inducting...', 'Indulging...', 'Industrializing...', 'Inferring...', 'Infiltrating...', 'Inflating...', 'Influencing...',
  'Informing...', 'Infusing...', 'Ingesting...', 'Inhabiting...', 'Inhaling...', 'Inheriting...', 'Inhibiting...', 'Initializing...', 'Initiating...', 'Injecting...',
  'Injuring...', 'Inking...', 'Innovating...', 'Inoculating...', 'Inquiring...', 'Inscribing...', 'Inserting...', 'Insisting...', 'Inspecting...', 'Inspiring...',
  'Installing...', 'Instantiating...', 'Instigating...', 'Instilling...', 'Instituting...', 'Instructing...', 'Insulating...', 'Insuring...', 'Integrating...', 'Intending...',
  'Intensifying...', 'Interacting...', 'Intercepting...', 'Interfacing...', 'Interleaving...', 'Interlinking...', 'Interlacing...', 'Interlocking...', 'Interning...', 'Interpolating...',
  'Interpreting...', 'Interrogating...', 'Interrupting...', 'Intersecting...', 'Intervening...', 'Interviewing...', 'Interweaving...', 'Intoning...', 'Introducing...', 'Intuiting...',
  'Inventing...', 'Inventorying...', 'Inverting...', 'Investing...', 'Investigating...', 'Invigorating...', 'Inviting...', 'Involving...', 'Ionizing...', 'Iterating...',
  // ---- J ----
  'Jabbing...', 'Jacketing...', 'Jailing...', 'Jamming...', 'Jangling...', 'Jarring...', 'Jaunting...', 'Jazzing...',
  'Jeering...', 'Jelling...', 'Jeopardizing...', 'Jerking...', 'Jesting...', 'Jettisoning...', 'Jeweling...', 'Jibing...',
  'Jiggling...', 'Jigsawing...', 'Jilting...', 'Jingling...', 'Jiving...', 'Jobbing...', 'Jockeying...', 'Jogging...',
  'Joining...', 'Joking...', 'Jollying...', 'Jolting...', 'Jostling...', 'Jotting...', 'Journeying...', 'Jousting...',
  'Joyriding...', 'Judging...', 'Juggling...', 'Julienning...', 'Jumping...', 'Junketing...', 'Justifying...', 'Jutting...',
  'Juxtaposing...', 'Jabbering...', 'Jading...', 'Jalousing...', 'Japing...', 'Jargonizing...', 'Jauncing...', 'Jawboning...',
  'Jawing...', 'Jeopardying...', 'Jellifying...', 'Jemmying...', 'Jettying...', 'Jewelling...', 'Jibbing...', 'Jigging...',
  'Jitterbugging...', 'Jinxing...', 'Jittering...', 'Jobhunting...', 'Joggling...', 'Joisting...', 'Jokifying...', 'Jollifying...',
  'Jonesing...', 'Joshing...', 'Jouking...', 'Journalling...', 'Jovializing...', 'Jowing...', 'Joying...', 'Joypopping...',
  'Jubilating...', 'Juddering...', 'Judoing...', 'Juking...', 'Jumbling...', 'Jumpstarting...', 'Junking...', 'Jurifying...',
  'Jurying...', 'Justling...', 'Juicing...', 'Jouncing...', 'Javelining...', 'Jocundizing...', 'Japering...', 'Japonicaing...',
  'Jasperizing...', 'Jazzercising...', 'Jellyfishing...', 'Jerrybuilding...', 'Jerseying...', 'Jessying...', 'Jobseeking...', 'Jointing...',
  'Junketeering...', 'Jawbreaking...', 'Jaywalking...',
  // ---- K ----
  'Keeling...', 'Keening...', 'Keeping...', 'Kenning...', 'Kerbing...', 'Kerneling...', 'Kettling...', 'Keyboarding...',
  'Keying...', 'Keynoting...', 'Kibitzing...', 'Kicking...', 'Kidding...', 'Kidnapping...', 'Kilning...', 'Kindling...',
  'Kinging...', 'Kinking...', 'Kissing...', 'Kitting...', 'Kneading...', 'Kneeling...', 'Knifing...', 'Knighting...',
  'Knitting...', 'Knocking...', 'Knotting...', 'Knowing...', 'Knuckling...', 'Koshering...', 'Kowtowing...', 'Kvetching...',
  'Karaoking...', 'Kayoing...', 'Kecking...', 'Kedging...', 'Keeking...', 'Kelping...', 'Kenneling...', 'Keratinizing...',
  'Kerfing...', 'Kernelling...', 'Kibbutzing...', 'Kiboshing...', 'Kickboxing...', 'Kickstarting...', 'Kiddying...', 'Kiltering...',
  'Kippering...', 'Kiting...', 'Kittening...', 'Klaxoning...', 'Knapping...', 'Kneecapping...', 'Knelling...', 'Knobbling...',
  'Knolling...', 'Kodaking...', 'Konking...', 'Kooking...', 'Koreanizing...', 'Kremlining...', 'Krumping...', 'Kudosing...',
  'Kurbling...', 'Kvelling...', 'Kingmaking...', 'Kyanising...', 'Kyboshing...', 'Kything...', 'Kaolinizing...', 'Kaputing...',
  'Katalysing...', 'Kathoding...', 'Keshing...', 'Keypunching...', 'Khediving...', 'Kalsomining...', 'Kamiing...', 'Kantianing...',
  'Karaokeing...', 'Karateing...', 'Karstifying...', 'Katabolizing...', 'Kathing...', 'Kazaching...', 'Kebabbing...', 'Kebobbing...',
  'Keeving...', 'Keelhauling...', 'Keenlying...', 'Keepnetting...', 'Keltering...', 'Kerseying...', 'Ketling...', 'Keyframing...',
  'Keyseating...', 'Kibbling...', 'Kickboarding...', 'Kickflipping...', 'Kidneystoning...', 'Kieving...', 'Kimchifying...', 'Kimmering...',
  'Kindergartening...', 'Kinescoping...', 'Kingfishing...', 'Kirkifying...', 'Kirshening...', 'Kitbagging...', 'Kitchening...', 'Kitesurfing...',
  'Klondiking...', 'Kludging...', 'Knackering...', 'Kneippering...', 'Knobkerrying...', 'Knowledging...', 'Kohlrabiing...', 'Koorifying...',
  'Kotowing...', 'Kronaing...', 'Krytroning...', 'Kugelhopfing...', 'Kumquating...', 'Kurrajonging...', 'Kyanizing...',
  // ---- L (100) ----
  'Labeling...', 'Laboring...', 'Lacing...', 'Laddering...', 'Lading...', 'Lagging...', 'Lambasting...', 'Laminating...', 'Landing...', 'Languishing...',
  'Lapping...', 'Lapsing...', 'Larding...', 'Lashing...', 'Lasting...', 'Latching...', 'Lathering...', 'Lauding...', 'Laughing...', 'Launching...',
  'Laundering...', 'Lavishing...', 'Laying...', 'Lazing...', 'Leaching...', 'Leading...', 'Leafing...', 'Leaking...', 'Leaning...', 'Leaping...',
  'Learning...', 'Leasing...', 'Leathering...', 'Leaving...', 'Lecturing...', 'Ledgering...', 'Leeching...', 'Leering...', 'Legitimizing...', 'Lending...',
  'Lengthening...', 'Lessening...', 'Letting...', 'Leveling...', 'Leveraging...', 'Levying...', 'Liberating...', 'Licensing...', 'Licking...', 'Lifting...',
  'Lightening...', 'Lighting...', 'Liking...', 'Limbering...', 'Limiting...', 'Lining...', 'Linking...', 'Lionizing...', 'Liquidating...', 'Lisping...',
  'Listening...', 'Litigating...', 'Littering...', 'Living...', 'Loading...', 'Loafing...', 'Loaning...', 'Lobbying...', 'Lobing...', 'Localizing...',
  'Locating...', 'Locking...', 'Lodging...', 'Lofting...', 'Logging...', 'Longing...', 'Looking...', 'Looping...', 'Loosening...', 'Looting...',
  'Loping...', 'Losing...', 'Lounging...', 'Loving...', 'Lowering...', 'Lubricating...', 'Lugging...', 'Lulling...', 'Lumbering...', 'Lumping...',
  'Lunching...', 'Lunging...', 'Luring...', 'Lurking...', 'Lustering...', 'Lustrating...', 'Luxuriating...', 'Lying...', 'Lynching...', 'Lyricizing...',
  // ---- M (100) ----
  'Machining...', 'Magnetizing...', 'Magnifying...', 'Maintaining...', 'Mainstreaming...', 'Making...', 'Managing...', 'Mandating...',
  'Maneuvering...', 'Mangling...', 'Manifesting...', 'Manipulating...', 'Manning...', 'Manufacturing...', 'Mapping...', 'Marching...',
  'Marketing...', 'Marking...', 'Marrying...', 'Marshaling...', 'Marveling...', 'Mashing...', 'Masking...', 'Massaging...',
  'Massing...', 'Mastering...', 'Matching...', 'Materializing...', 'Matriculating...', 'Mattering...', 'Maximizing...', 'Meaning...',
  'Measuring...', 'Mediating...', 'Meditating...', 'Meeting...', 'Melding...', 'Mellowing...', 'Melting...', 'Memorizing...',
  'Mending...', 'Mentioning...', 'Mentoring...', 'Merging...', 'Meriting...', 'Meshing...', 'Mesmerizing...', 'Messaging...',
  'Metabolizing...', 'Metalworking...', 'Metamorphosing...', 'Metering...', 'Microblogging...', 'Microchipping...', 'Microfilming...', 'Micromanaging...',
  'Migrating...', 'Milking...', 'Milling...', 'Mimicking...', 'Mincing...', 'Minding...', 'Mingling...', 'Miniaturizing...',
  'Minimizing...', 'Mining...', 'Ministering...', 'Minting...', 'Mirroring...', 'Misaligning...', 'Miscalculating...', 'Misdiagnosing...',
  'Misfiring...', 'Misjudging...', 'Mislaying...', 'Mismatching...', 'Misplacing...', 'Misquoting...', 'Misreading...', 'Missing...',
  'Misspelling...', 'Mistaking...', 'Misting...', 'Misunderstanding...', 'Mitigating...', 'Mixing...', 'Moaning...', 'Mobilizing...',
  'Mocking...', 'Modeling...', 'Moderating...', 'Modernizing...', 'Modifying...', 'Modularizing...', 'Modulating...', 'Moistening...',
  'Moisturizing...', 'Molding...', 'Mollifying...', 'Monitoring...', 'Monetizing...', 'Monogramming...', 'Monologuing...', 'Monopolizing...',
  'Mooring...', 'Moralizing...', 'Morphing...', 'Mortgaging...', 'Moseying...', 'Motivating...', 'Motoring...', 'Mottling...',
  'Moulding...', 'Mounting...', 'Mountaineering...', 'Mourning...', 'Mousetrapping...', 'Mouthing...', 'Moving...', 'Mowing...',
  'Muckraking...', 'Muddling...', 'Mudslinging...', 'Muffling...', 'Mulching...', 'Multiplying...', 'Multiplexing...', 'Multitasking...',
  'Mumbling...', 'Mummifying...', 'Munching...', 'Murmuring...', 'Muscling...', 'Musicalizing...', 'Musing...', 'Musseling...',
  'Mustering...', 'Mutating...', 'Muting...', 'Mutinying...', 'Muttering...', 'Mutualizing...', 'Muzzling...', 'Mystifying...',
  'Mailing...', 'Mamboing...', 'Manacling...', 'Manhandling...', 'Manicuring...', 'Mansplaining...', 'Mantling...', 'Marinating...',
  'Marooning...', 'Marring...', 'Masquerading...', 'Masterminding...', 'Masticating...', 'Mauling...', 'Meandering...', 'Mechanizing...',
  'Meddling...', 'Meliorating...', 'Melodizing...', 'Memorializing...', 'Menacing...', 'Mercerizing...', 'Merchandising...', 'Metallizing...',
  'Mildewing...', 'Militating...', 'Mimeographing...', 'Mindmapping...', 'Minesweeping...', 'Misappropriating...', 'Misconstruing...', 'Misrepresenting...',
  // ---- N (100) ----
  'Nabbing...', 'Nailing...', 'Naming...', 'Nanosizing...', 'Napping...', 'Narrating...', 'Narrowing...', 'Nattering...',
  'Naturalizing...', 'Navigating...', 'Neatening...', 'Nebulizing...', 'Necessitating...', 'Necking...', 'Necropsying...', 'Needling...',
  'Negating...', 'Negotiating...', 'Nerving...', 'Nesting...', 'Nestling...', 'Netting...', 'Nettling...', 'Networking...',
  'Neutralizing...', 'Newscasting...', 'Nibbling...', 'Nicking...', 'Nicknaming...', 'Nictitating...', 'Niggling...', 'Nipping...',
  'Nitpicking...', 'Nobbling...', 'Nocking...', 'Nodding...', 'Noising...', 'Nominating...', 'Nonplussing...', 'Noodling...',
  'Normalizing...', 'Nosediving...', 'Nosing...', 'Notarizing...', 'Notating...', 'Notching...', 'Noticing...', 'Notifying...',
  'Noting...', 'Nourishing...', 'Novelizing...', 'Nucleating...', 'Nudging...', 'Nuggetting...', 'Nuking...', 'Nullifying...',
  'Numbering...', 'Numbing...', 'Nursemaiding...', 'Nursing...', 'Nurturing...', 'Nutmegging...', 'Nuzzling...', 'Narrowcasting...',
  // ---- O (100) ----
  'Obeying...', 'Objecting...', 'Objectivizing...', 'Obligating...', 'Obliging...', 'Obliterating...', 'Obnubilating...', 'Obscuring...',
  'Observing...', 'Obsessing...', 'Obsoleting...', 'Obstructing...', 'Obtaining...', 'Obtruding...', 'Obviating...', 'Occasioning...',
  'Occupying...', 'Occurring...', 'Offering...', 'Officiating...', 'Offloading...', 'Offsetting...', 'Ogling...', 'Oiling...',
  'Okaying...', 'Ominating...', 'Omitting...', 'Onboarding...', 'Oozing...', 'Opacifying...', 'Opalescing...', 'Opening...',
  'Operating...', 'Opining...', 'Opposing...', 'Optimizing...', 'Optioning...', 'Orating...', 'Orbiting...', 'Orchestrating...',
  'Ordaining...', 'Ordering...', 'Organizing...', 'Orienting...', 'Originating...', 'Ornamenting...', 'Orphaning...', 'Oscillating...',
  'Ossifying...', 'Ostracizing...', 'Outbidding...', 'Outclassing...', 'Outdoing...', 'Outfitting...', 'Outgrowing...', 'Outlasting...',
  'Outlining...', 'Outmaneuvering...', 'Outpacing...', 'Outperforming...', 'Outreaching...', 'Outsmarting...', 'Outsourcing...', 'Outstripping...',
  'Outwitting...', 'Overachieving...', 'Overarching...', 'Overbalancing...', 'Overbooking...', 'Overbuilding...', 'Overcoming...', 'Overcompensating...',
  'Overdelivering...', 'Overdoing...', 'Overeating...', 'Overemphasizing...', 'Overestimating...', 'Overflowing...', 'Overhauling...', 'Overhearing...',
  'Overheating...', 'Overlaying...', 'Overloading...', 'Overlooking...', 'Overpowering...', 'Overprinting...', 'Overproducing...', 'Overreaching...',
  'Overriding...', 'Overruling...', 'Overseeing...', 'Overshadowing...', 'Overshooting...', 'Oversimplifying...', 'Oversleeping...', 'Overstating...',
  'Overstepping...', 'Overstocking...', 'Overstretching...', 'Overtaking...', 'Overthinking...', 'Overthrowing...', 'Overturning...', 'Overvaluing...',
  'Overwatching...', 'Overwhelming...', 'Owing...', 'Owning...', 'Oxidizing...', 'Oxygenating...', 'Ozonizing...', 'Obolizing...',
  // ---- P ----
  'Pacing...', 'Packaging...', 'Packing...', 'Padding...', 'Paddling...', 'Paging...', 'Painting...', 'Pairing...',
  'Palatalizing...', 'Palling...', 'Palming...', 'Palpating...', 'Pampering...', 'Panelizing...', 'Panicking...', 'Pantomiming...',
  'Papering...', 'Parachuting...', 'Parading...', 'Paragliding...', 'Paralysing...', 'Paraphrasing...', 'Parceling...', 'Pardoning...',
  'Parenting...', 'Pariking...', 'Parking...', 'Parleying...', 'Parodying...', 'Paroling...', 'Parrying...', 'Parsing...',
  'Partaking...', 'Partitioning...', 'Partnering...', 'Partying...', 'Passing...', 'Passivizing...', 'Pasting...', 'Pastoring...',
  'Patching...', 'Patenting...', 'Patrolling...', 'Patronizing...', 'Patterning...', 'Pausing...', 'Paving...', 'Pawing...',
  'Paying...', 'Peaking...', 'Pealing...', 'Pecking...', 'Pedaling...', 'Peeking...', 'Peeling...', 'Peering...',
  'Pegging...', 'Pelting...', 'Penalizing...', 'Penciling...', 'Pending...', 'Penetrating...', 'Pensioning...', 'Peppering...',
  'Perceiving...', 'Perching...', 'Perfecting...', 'Perforating...', 'Performing...', 'Perfuming...', 'Perishing...', 'Permeating...',
  'Permitting...', 'Permuting...', 'Perpetuating...', 'Perplexing...', 'Persevering...', 'Persisting...', 'Personalizing...', 'Personifying...',
  'Persuading...', 'Perving...', 'Pestering...', 'Petitioning...', 'Petrifying...', 'Pettifogging...', 'Phaseing...', 'Philandering...',
  'Philosophizing...', 'Phoneing...', 'Photocopying...', 'Photographing...', 'Photosynthesizing...', 'Phrasing...', 'Picking...', 'Picnicking...',
  'Picturing...', 'Piecing...', 'Piercing...', 'Piggybacking...', 'Pilfering...', 'Piloting...', 'Pinching...', 'Pinging...',
  'Pinning...', 'Pioneering...', 'Piping...', 'Pitching...', 'Pitying...', 'Pivoting...', 'Placating...', 'Placing...',
  'Plagiarizing...', 'Plaiting...', 'Planning...', 'Planting...', 'Plastering...', 'Plating...', 'Playing...', 'Pleading...',
  'Pleasuring...', 'Pledging...', 'Plodding...', 'Plotting...', 'Ploughing...', 'Plowing...', 'Plucking...', 'Plugging...',
  'Plumbing...', 'Plummeting...', 'Plumping...', 'Plundering...', 'Plunging...', 'Pluralizing...', 'Plying...', 'Poaching...',
  'Pocketing...', 'Podcasting...', 'Poeticizing...', 'Pointing...', 'Poising...', 'Poisoning...', 'Poking...', 'Polarizing...',
  'Policing...', 'Polishing...', 'Politicizing...', 'Pollinating...', 'Polling...', 'Pondering...', 'Pooling...', 'Popping...',
  'Popularizing...', 'Populating...', 'Poring...', 'Porting...', 'Portioning...', 'Portraying...', 'Posing...', 'Positioning...',
  'Positing...', 'Possessing...', 'Posting...', 'Postponing...', 'Postulating...', 'Posturing...', 'Potting...', 'Pouncing...',
  'Pounding...', 'Pouring...', 'Pouting...', 'Powdering...', 'Powering...', 'Practicing...', 'Praising...', 'Prancing...',
  'Prattling...', 'Praying...', 'Preaching...', 'Preambleing...', 'Preceding...', 'Precipitating...', 'Precluding...', 'Precooking...',
  'Predicting...', 'Predisposing...', 'Prefacing...', 'Preferring...', 'Prefiguring...', 'Prefixing...', 'Preheating...', 'Prejudging...',
  'Preluding...', 'Premising...', 'Preoccupying...', 'Preordaining...', 'Preparing...', 'Prepaving...', 'Prepaying...', 'Preponderating...',
  'Prerecording...', 'Prescribing...', 'Presenting...', 'Preserving...', 'Presetting...', 'Presiding...', 'Pressuring...', 'Pressurizing...',
  'Prestressing...', 'Presuming...', 'Pretending...', 'Prettifying...', 'Prevailing...', 'Preventing...', 'Previewing...', 'Preying...',
  'Pricing...', 'Pricking...', 'Pridiing...', 'Priming...', 'Printing...', 'Prioritizing...', 'Privatizing...', 'Privileging...',
  'Prizing...', 'Probing...', 'Proceeding...', 'Processing...', 'Proclaiming...', 'Procrastinating...', 'Procuring...', 'Prodding...',
  'Producing...', 'Profaning...', 'Professing...', 'Profiling...', 'Profiting...', 'Programming...', 'Progressing...', 'Prohibiting...',
  'Projecting...', 'Proliferating...', 'Prolonging...', 'Promenading...', 'Promising...', 'Promoting...', 'Prompting...', 'Promulgating...',
  'Pronouncing...', 'Proofing...', 'Proofreading...', 'Propagating...', 'Propelling...', 'Prophesying...', 'Proposing...', 'Propping...',
  'Proroguing...', 'Prosecuting...', 'Proselytizing...', 'Prospecting...', 'Prospering...', 'Protecting...', 'Protesting...', 'Protruding...',
  'Proving...', 'Providing...', 'Provisioning...', 'Provoking...', 'Prowling...', 'Pruning...', 'Psyching...', 'Publicizing...',
  'Publishing...', 'Puckering...', 'Puffing...', 'Pulling...', 'Pulping...', 'Pulsating...', 'Pulverizing...', 'Pummeling...',
  'Pumping...', 'Punching...', 'Puncturing...', 'Punishing...', 'Punning...', 'Purging...', 'Purifying...', 'Purloining...',
  'Purporting...', 'Purring...', 'Pursuing...', 'Pushing...', 'Putting...', 'Puzzling...', 'Pyramiding...',
  // ---- Q ----
  'Quacking...', 'Quadrupling...', 'Quaffing...', 'Quailing...', 'Qualifying...', 'Quantifying...', 'Quarreling...', 'Quarrying...',
  'Quartering...', 'Quashing...', 'Quavering...', 'Queening...', 'Quelling...', 'Quenching...', 'Querying...', 'Questing...',
  'Questioning...', 'Queueing...', 'Quickening...', 'Quieting...', 'Quilting...', 'Quipping...', 'Quivering...', 'Quizzing...',
  'Quoting...',
  // ---- R ----
  'Racing...', 'Racking...', 'Radiating...', 'Raffling...', 'Rafting...', 'Raging...', 'Raining...', 'Raising...',
  'Rallying...', 'Rambling...', 'Ramifying...', 'Ramping...', 'Ransacking...', 'Ransoming...', 'Ranting...', 'Rapping...',
  'Rapproching...', 'Rapturing...', 'Raring...', 'Rasping...', 'Ratifying...', 'Rating...', 'Rationalizing...',
  'Rationing...', 'Rattling...', 'Ravaging...', 'Raving...', 'Reaching...', 'Reacting...', 'Readjusting...', 'Readying...',
  'Realigning...', 'Realizing...', 'Reallocating...', 'Reanimating...', 'Reaping...', 'Reappearing...', 'Reapplying...', 'Rearranging...',
  'Reasoning...', 'Reassembling...', 'Reasserting...', 'Reassessing...', 'Reassigning...', 'Reassuring...', 'Rebalancing...', 'Rebating...',
  'Rebelling...', 'Rebooting...', 'Rebounding...', 'Rebranding...', 'Rebuilding...', 'Rebuking...', 'Recalculating...', 'Recalibrating...',
  'Recalling...', 'Recanting...', 'Recapping...', 'Recapturing...', 'Receding...', 'Receiving...', 'Recentering...', 'Recharging...',
  'Rechecking...', 'Rechristening...', 'Recirculating...', 'Reciting...', 'Reclaiming...', 'Reclassifying...', 'Reclining...', 'Recognizing...',
  'Recoiling...', 'Recollecting...', 'Recommending...', 'Recommissioning...', 'Recompiling...', 'Reconciling...', 'Reconfiguring...', 'Reconnecting...',
  'Reconsidering...', 'Reconstituting...', 'Reconstructing...', 'Recording...', 'Recounting...', 'Recouping...', 'Recovering...', 'Recreating...',
  'Recruiting...', 'Rectifying...', 'Recuperating...', 'Recurring...', 'Recycling...', 'Redacting...', 'Redefining...', 'Redeploying...',
  'Redesigning...', 'Redeveloping...', 'Redialing...', 'Redirecting...', 'Rediscovering...', 'Redistributing...', 'Redoing...', 'Redoubling...',
  'Redrafting...', 'Reducing...', 'Reeling...', 'Refactoring...', 'Referencing...', 'Referring...', 'Refilling...', 'Refinancing...',
  'Refining...', 'Refitting...', 'Reflecting...', 'Reformatting...', 'Reforming...', 'Refracting...', 'Refraining...', 'Refreshing...',
  'Refueling...', 'Refunding...', 'Refurbishing...', 'Refusing...', 'Refuting...', 'Regaining...', 'Regaling...', 'Regarding...',
  'Regenerating...', 'Registering...', 'Regressing...', 'Regretting...', 'Regrouping...', 'Regulating...', 'Rehabilitating...', 'Rehearsing...',
  'Reigning...', 'Reimbursing...', 'Reinforcing...', 'Reining...', 'Reinstalling...', 'Reinstating...', 'Reintegrating...', 'Reinterpreting...',
  'Reintroducing...', 'Reinventing...', 'Reinvesting...', 'Reissuing...', 'Reiterating...', 'Rejecting...', 'Rejoicing...', 'Rejoining...',
  'Rejuvenating...', 'Rekindling...', 'Relating...', 'Relaxing...', 'Relaying...', 'Releasing...', 'Relegating...', 'Relenting...',
  'Relieving...', 'Relighting...', 'Relishing...', 'Reliving...', 'Reloading...', 'Relocating...', 'Relying...', 'Remaining...',
  'Remanding...', 'Remarking...', 'Remarrying...', 'Remastering...', 'Remedying...', 'Remembering...', 'Reminding...', 'Reminiscing...',
  'Remitting...', 'Remodeling...', 'Remolding...', 'Remonstrating...', 'Removing...', 'Rendering...', 'Rendezvousing...', 'Reneging...',
  'Renegotiating...', 'Renewing...', 'Renouncing...', 'Renovating...', 'Renting...', 'Reopening...', 'Reorganizing...', 'Repacking...',
  'Repairing...', 'Repaying...', 'Repealing...', 'Repeating...', 'Repelling...', 'Repenting...', 'Repercussing...', 'Replacing...',
  'Replaying...', 'Replenishing...', 'Replicating...', 'Replying...', 'Repointing...', 'Reporting...', 'Reposing...', 'Repositioning...',
  'Representing...', 'Repressing...', 'Reprimanding...', 'Reprinting...', 'Reproaching...', 'Reprocessing...', 'Reproducing...', 'Reprogramming...',
  'Reproving...', 'Repulsing...', 'Repurposing...', 'Requesting...', 'Requiring...', 'Requisitioning...', 'Requiting...', 'Rescinding...',
  'Rescuing...', 'Researching...', 'Reselling...', 'Resembling...', 'Resenting...', 'Reserving...', 'Resetting...', 'Resettling...',
  'Reshaping...', 'Residing...', 'Resigning...', 'Resisting...', 'Reskilling...', 'Resoling...', 'Resolving...', 'Resonating...',
  'Resorting...', 'Resounding...', 'Respecting...', 'Respiring...', 'Responding...', 'Restarting...', 'Restating...', 'Resting...',
  'Restocking...', 'Restoring...', 'Restraining...', 'Restricting...', 'Restructuring...', 'Resulting...', 'Resuming...', 'Resurfacing...',
  'Resurging...', 'Resurrecting...', 'Retailing...', 'Retaining...', 'Retaliating...', 'Retelling...', 'Rethinking...', 'Retiring...',
  'Retorting...', 'Retouching...', 'Retracing...', 'Retracting...', 'Retraining...', 'Retranslating...', 'Retreating...', 'Retrieving...',
  'Retrofitting...', 'Retrying...', 'Returning...', 'Reunifying...', 'Reuniting...', 'Reusing...', 'Revealing...', 'Reveling...',
  'Revenging...', 'Reverberating...', 'Revering...', 'Reversing...', 'Reverting...', 'Reviewing...', 'Reviling...', 'Revising...',
  'Revisiting...', 'Revitalizing...', 'Reviving...', 'Revoking...', 'Revolting...', 'Revolutionizing...', 'Revolving...', 'Rewarding...',
  'Rewiring...', 'Rewording...', 'Reworking...', 'Rewriting...', 'Rhapsodizing...', 'Rhyming...', 'Ribbing...', 'Ridding...',
  'Riding...', 'Riffling...', 'Rifling...', 'Rigging...', 'Righting...', 'Rimming...', 'Ringing...', 'Rinsing...',
  'Rioting...', 'Ripping...', 'Rippling...', 'Rising...', 'Risking...', 'Rivaling...', 'Riveting...', 'Roaming...',
  'Roaring...', 'Roasting...', 'Robbing...', 'Robing...', 'Rocking...', 'Rolling...', 'Romancing...', 'Romanticizing...',
  'Roofing...', 'Rooming...', 'Rooting...', 'Roping...', 'Rorting...', 'Rostering...', 'Rotating...', 'Roting...',
  'Roughening...', 'Rounding...', 'Rousing...', 'Rousting...', 'Roving...', 'Rowing...', 'Rubbing...', 'Ruining...',
  'Ruling...', 'Rumbling...', 'Ruminating...', 'Rummaging...', 'Running...', 'Ruptioning...', 'Rushing...', 'Rusticating...',
  'Rustling...', 'Reticulating...',
];

// ---- ANSI helpers ----
function stripAnsi(s) {
  return String(s)
    .replace(/\x1b\[[0-9;?]*[a-zA-Z]/g, '')
    .replace(/\x1b\[[0-9;?]* [a-zA-Z]/g, '')
    .replace(/\x1b\][^\x07\x1b]*(?:\x07|\x1b\\)/g, '');
}

// Make UNTRUSTED text safe to paint: file contents from Read, command output from
// Bash, diff bodies, tool arguments.
//
// The goal is to keep the content as ORIGINAL as possible while stopping the
// terminal from OBEYING it. Only the ESC byte is rewritten — every following byte
// (the `[31m`, the `[10;20H` parameters) is shown verbatim, so nothing is lost:
//
//     file contains:  ESC [ 3 1 m E R R O R ESC [ 0 m
//     screen shows :  ^[ [ 3 1 m E R R O R ^[ [ 0 m
//
// A terminal cannot act on a sequence whose ESC has been split into `^[`, so:
//   * `ESC[31m`   no longer recolours half the transcript
//   * `ESC[0m`    no longer resets the row's styling mid-line
//   * `ESC[10;20H` / `ESC[2J` no longer move the cursor or clear the screen
//
// `^[` is the same convention `cat -v`, `less` and `bat` use for ESC, so it reads
// as "there is an escape here" rather than as content. Tab is kept (the renderer
// expands it) and newlines are the caller's business; only the dangerous C0
// controls are defanged, and they are shown as their caret form so they remain
// visible instead of silently vanishing.
export function sanitizeText(s) {
  return String(s == null ? '' : s)
    // ESC -> "^[" . The rest of the sequence is untouched.
    .replace(/\x1b/g, '^[')
    // A bare BEL/BS/VT/FF would still be interpreted by some terminals.
    .replace(/\x07/g, '^G')
    .replace(/\x08/g, '^H')
    .replace(/[\x0b\x0c]/g, ' ')
    // Drop NUL and the remaining C0 controls (they have no visible form).
    .replace(/[\x00-\x06\x0e-\x1f\x7f]/g, '');
}

/**
 * How much of a running command's output to KEEP, not just display.
 *
 * This string is mirrored into the hub row (and so into the SSE patch the
 * browser applies on every frame), which means an unbounded buffer grows the
 * terminal's row, the hub's row and the browser's copy at the same time. Only
 * the tail is ever drawn, so only the tail is worth holding.
 */
export const LIVE_OUTPUT_MAX_CHARS = 64 * 1024;

/** The last `max` CHARACTERS of `s`, cut on a line boundary so the tail never
    starts mid-line. */
export function tailChars(s, max) {
  const str = String(s == null ? '' : s);
  if (str.length <= max) return str;
  const cut = str.slice(str.length - max);
  const nl = cut.indexOf('\n');
  return nl >= 0 ? cut.slice(nl + 1) : cut;
}

function visualCol(s) { return visualWidth(stripAnsi(String(s))); }
function col(text, c) { return c + String(text) + C.reset; }

// A message the USER actually typed, as opposed to one the harness injected with
// role 'user'. `beginTurn` (file-history) runs once per real prompt, and /undo's
// picker lists them, so both must agree on what counts. Harness notes are marked
// with `_harness` at the source (the truncation-recovery nudge and the compaction
// handoff in agent.js). Older sessions predate the flag, so the <system-reminder>
// wrapper they used is still recognised as a fallback.
export function isRealUserPrompt(m) {
  if (!m || m.role !== 'user') return false;
  if (m._harness) return false;
  const text = typeof m.content === 'string' ? m.content : '';
  if (/^<system-reminder>/.test(text.trim())) return false;
  return true;
}

function fitAnsi(s, w) {
  const str = String(s);
  const v = visualCol(str);
  if (v < w) return str + ' '.repeat(w - v);
  if (v === w) return str;
  let out = '';
  let n = 0;
  let i = 0;
  while (i < str.length) {
    if (str[i] === ESC) {
      const m = /^\x1b\[[0-9;?]*[a-zA-Z]/.exec(str.slice(i))
        || /^\x1b\[[0-9;?]* [a-zA-Z]/.exec(str.slice(i))
        || /^\x1b\][^\x07\x1b]*(?:\x07|\x1b\\)/.exec(str.slice(i));
      if (m) { out += m[0]; i += m[0].length; continue; }
    }
    const cp = str.codePointAt(i);
    const ch = String.fromCodePoint(cp);
    const cw = visualWidth(ch);
    if (n + cw > w) break;
    n += cw;
    out += ch;
    i += cp > 0xffff ? 2 : 1;
  }
  if (n < w) out += ' '.repeat(w - n);
  return out;
}

function wrapWords(str, width) {
  width = Math.max(1, width | 0);
  const out = [];
  let line = '';
  // Running width of `line`. It used to be recomputed with
  // `visualCol(line + ' ' + w)` on EVERY word, which is O(line) per word and so
  // O(n²) per paragraph — a single long line (a streamed paragraph, a wide table
  // row) cost ~46ms at 20KB and froze the UI on every markdown chunk. Widths are
  // additive for the plain text this receives (no ANSI is present until
  // inlineMarkdown runs later), so accumulate instead of re-measuring.
  let lineW = 0;
  // Expand tabs first: visualCol counts '\t' as 0 columns but the terminal
  // advances to the next tab stop, which made the row wider than computed and
  // wrapped it onto the following line.
  const words = expandTabs(str).split(' ');
  for (const w of words) {
    const wW = visualCol(w);
    // A word longer than the line must be hard-split. This MUST measure visual
    // columns (not string length): CJK characters occupy two cells, so slicing
    // by `.length` would emit lines twice as wide as the box and the terminal
    // would wrap them onto the next row, corrupting the layout.
    if (wW > width) {
      if (line) { out.push(line); line = ''; lineW = 0; }
      let chunk = '';
      let cw = 0;
      for (const ch of w) {
        const chw = visualCol(ch);
        if (cw + chw > width) { out.push(chunk); chunk = ''; cw = 0; }
        chunk += ch; cw += chw;
      }
      if (chunk) { line = chunk; lineW = cw; }
      continue;
    }
    const sep = line ? 1 : 0;              // the single space we would add
    if (lineW + sep + wW <= width) {
      line = line ? line + ' ' + w : w;
      lineW += sep + wW;
    } else {
      if (line) out.push(line);
      line = w;
      lineW = wW;
    }
  }
  if (line) out.push(line);
  else if (out.length === 0) out.push('');
  return out;
}

// Extract a (possibly still-streaming) JSON string value by key from a partial
// JSON document. Used to show a Write's `content` as it arrives; returns '' when
// the value hasn't started or is incomplete enough that decoding fails.
export function extractJsonString(json, key) {
  if (!json) return '';
  const idx = json.indexOf(`"${key}"`);
  if (idx < 0) return '';
  const colon = json.indexOf(':', idx + key.length + 2);
  if (colon < 0) return '';
  let i = colon + 1;
  while (i < json.length && /\s/.test(json[i])) i++;
  if (json[i] !== '"') return '';
  i++;
  let out = '';
  while (i < json.length) {
    const ch = json[i];
    if (ch === '\\') {
      const nxt = json[i + 1];
      if (nxt === undefined) break;
      const map = { n: '\n', t: '\t', r: '\r', '"': '"', '\\': '\\', '/': '/', b: '\b', f: '\f' };
      if (nxt === 'u') {
        const hex = json.slice(i + 2, i + 6);
        if (hex.length < 4) break;
        out += String.fromCharCode(parseInt(hex, 16) || 0);
        i += 6; continue;
      }
      out += map[nxt] !== undefined ? map[nxt] : nxt;
      i += 2; continue;
    }
    if (ch === '"') break;
    out += ch;
    i++;
  }
  return out;
}

// Line diff for the Edit tool, rendered as a unified diff with context:
//     <n>   unchanged line      (dim)
//     <n> - removed line
//     <n> + added line
// Unchanged lines are kept but trimmed to CONTEXT_LINES on each side of a change
// (claude-code's rule), so the diff reads as a patch rather than two orphaned
// blocks — an edit of 5 lines no longer dumps all 5 unchanged rows.
const DIFF_CONTEXT_LINES = 3;
export function lineDiff(oldStr, newStr, startLine = 1) {
  const a = String(oldStr == null ? '' : oldStr).replace(/\r\n/g, '\n').split('\n');
  const b = String(newStr == null ? '' : newStr).replace(/\r\n/g, '\n').split('\n');
  // LCS table (inputs are edit snippets, so sizes stay small).
  const n = a.length, m = b.length;
  const dp = Array.from({ length: n + 1 }, () => new Uint16Array(m + 1));
  for (let i = n - 1; i >= 0; i--) {
    for (let j = m - 1; j >= 0; j--) {
      dp[i][j] = a[i] === b[j] ? dp[i + 1][j + 1] + 1 : Math.max(dp[i + 1][j], dp[i][j + 1]);
    }
  }
  const raw = [];
  let i = 0, j = 0;
  // Line numbers as they appear in the real file (startLine = first old line).
  let oldNo = startLine, newNo = startLine;
  while (i < n && j < m) {
    if (a[i] === b[j]) { raw.push({ type: 'ctx', text: a[i], no: oldNo }); i++; j++; oldNo++; newNo++; }
    else if (dp[i + 1][j] >= dp[i][j + 1]) { raw.push({ type: 'del', text: a[i], no: oldNo }); i++; oldNo++; }
    else { raw.push({ type: 'add', text: b[j], no: newNo }); j++; newNo++; }
  }
  while (i < n) { raw.push({ type: 'del', text: a[i], no: oldNo }); i++; oldNo++; }
  while (j < m) { raw.push({ type: 'add', text: b[j], no: newNo }); j++; newNo++; }
  // Keep at most DIFF_CONTEXT_LINES unchanged rows adjacent to a change; drop the
  // rest (an elision row is inserted where rows were removed).
  const out = [];
  const isChange = (k) => raw[k] && raw[k].type !== 'ctx';
  for (let k = 0; k < raw.length; k++) {
    if (raw[k].type !== 'ctx') { out.push(raw[k]); continue; }
    // Distance to the NEAREST change on either side; keep when within the window.
    let dist = Infinity;
    for (let t = k - 1; t >= 0 && t >= k - DIFF_CONTEXT_LINES; t--) { if (isChange(t)) { dist = Math.min(dist, k - t); break; } }
    for (let t = k + 1; t < raw.length && t <= k + DIFF_CONTEXT_LINES; t++) { if (isChange(t)) { dist = Math.min(dist, t - k); break; } }
    if (dist <= DIFF_CONTEXT_LINES) { out.push(raw[k]); continue; }
    // Elide this context row, marking the gap once.
    if (out.length && out[out.length - 1].type !== 'gap') out.push({ type: 'gap' });
  }
  return out;
}

// Word-wrap a string that may contain ANSI colour codes, measuring VISIBLE
// width only. Escape sequences are carried over to the line they belong to.
function wrapAnsiWords(str, width) {
  width = Math.max(1, width | 0);
  const tokens = String(str).split(/(\s+)/); // keep whitespace as tokens
  const out = [];
  let line = '';
  let lineW = 0;
  const push = () => { if (line !== '') out.push(line); line = ''; lineW = 0; };
  for (const tok of tokens) {
    if (tok === '') continue;
    const tw = visualCol(tok);
    if (/^\s+$/.test(tok)) {
      if (lineW > 0) { line += tok; lineW += tw; }
      continue;
    }
    if (lineW > 0 && lineW + tw > width) push();
    if (tw > width && visualCol(tok) > width) {
      // Hard-split an over-long token by visible columns.
      let chunk = '';
      let cw = 0;
      for (const ch of tok) {
        const chw = visualCol(ch);
        if (cw + chw > width) { out.push(chunk); chunk = ''; cw = 0; }
        chunk += ch; cw += chw;
      }
      if (chunk) { line = chunk; lineW = cw; }
      continue;
    }
    line += tok;
    lineW += tw;
  }
  if (line !== '') out.push(line);
  if (out.length === 0) out.push('');
  return out;
}

// Word-aware wrap that also returns each row's starting offset in the source
// string, so the caret can be mapped to a (row, col) inside the composer.
function wrapWithOffsets(text, width) {
  const out = [];
  const n = text.length;
  if (n === 0) return [{ text: '', start: 0 }];
  let i = 0;
  while (i < n) {
    let w = 0;
    let j = i;
    let lastSpace = -1;
    while (j < n) {
      const ch = text[j];
      const cw = visualWidth(ch);
      if (w + cw > width) break;
      if (ch === ' ') lastSpace = j;
      w += cw;
      j++;
    }
    if (j === i) j = i + 1; // always make progress (wide char > width)
    if (j < n && lastSpace > i) {
      out.push({ text: text.slice(i, lastSpace), start: i });
      i = lastSpace + 1;
    } else {
      out.push({ text: text.slice(i, j), start: i });
      i = j;
    }
  }
  return out;
}

// The composer is ONLY for messages to the model. Dialogs (pickers, forms) do
// not use it — they render their own inputs (search box, form fields).
// The prompt glyph matches the transcript's user marker (`❯`) so the composer
// reads as "the same kind of thing" as a sent user message.
//
// SHELL MODE (`!`) — modelled on kimi-code's editor. Typing `!` on an EMPTY
// composer flips a mode flag instead of inserting the character; the `!` is
// rendered as the PREFIX. That is what keeps it from appearing twice:
//   - the buffer holds only the command (`git status`), never the bang
//   - the caret never has to step over a marker it is not editing
//   - submit never has to strip anything
// The mode ends on Esc/Backspace while the buffer is empty, or on submit.
export function composerInput(state) {
  const shell = state.inputMode === 'bash';
  return { text: state.input || '', caret: state.caret || 0, prefix: shell ? '! ' : '❯ ' };
}

// Marker text for a collapsed paste. Only a multi-line TEXT paste collapses; an
// IMAGE always collapses (its payload is a temp file path, which should never be
// shown as if the user typed it).
//   text, multi-line : [paste #1 +12 lines]
//   text, one line   : [paste #1 1 lines]
//   image            : [paste #1 image]
// The `image` form keeps the same `paste #N` prefix on purpose: expandPastes,
// highlightPasteMarkers and adjacentPasteMarker all key off it, so images get the
// chip styling and atomic caret/delete behaviour for free.
export function pasteMarker(id, lineCount, kind = 'paste') {
  if (kind === 'image') return `[paste #${id} image]`;
  return lineCount > 1 ? `[paste #${id} +${lineCount} lines]` : `[paste #${id} ${lineCount} lines]`;
}
// The tail of any collapsed-paste marker: `+L lines`, `L lines`, or `image`.
const PASTE_MARKER_RE = /\[paste #(\d+) (?:\+\d+ lines|\d+ lines|image)\]/g;

// Expand every `[paste #N …]` marker in `text` back to its real content.
export function expandPastes(text, pastes) {
  if (!pastes || !text || !text.includes('[paste #')) return text;
  return text.replace(PASTE_MARKER_RE, (whole, id) => {
    const entry = pastes.get(Number(id));
    return entry ? entry.text : whole;
  });
}

// Wrap each collapsed-paste marker in the composer row with a selection background
// so it renders as one block chip (foreground preserved). Non-marker text is left
// untouched.
export function highlightPasteMarkers(row) {
  const s = String(row);
  if (!s.includes('[paste #')) return s;
  return s.replace(PASTE_MARKER_RE, (m) => C.selBg + m + C.reset);
}

// Apply selection background to the text portion of a composer row.
// `text` is the visible text on this row (after the prefix), `textStart`
// is the character offset of `text[0]` in the full input string, and
// `[selAnchor, selHead]` is the selection range in the full input.
export function highlightSelection(text, textStart, selAnchor, selHead) {
  if (!text) return text;
  const a = Math.min(selAnchor, selHead);
  const h = Math.max(selAnchor, selHead);
  let out = '';
  let inSel = false;
  for (let i = 0; i < text.length; i++) {
    const globalIdx = textStart + i;
    const want = globalIdx >= a && globalIdx < h;
    // Selection only changes the BACKGROUND; the foreground keeps its own colour.
    // Leaving the selection resets just the background (bgReset = ESC[49m), NOT the
    // whole style — a bare reset would also kill the foreground, so a cyan/white
    // run after the highlight reverted to grey.
    if (want && !inSel) { out += C.selBg; inSel = true; }
    else if (!want && inSel) { out += C.bgReset; inSel = false; }
    out += text[i];
  }
  if (inSel) out += C.reset;
  return out;
}

// The composer treats a collapsed-paste marker as ONE atomic unit: moving the
// caret across it jumps over the whole marker, and deleting it removes the entire
// marker. `dir` = -1 (look left of the caret) or +1 (right). Covers both the text
// (`+L lines`) and image (`image`) forms.
const MARKER_LEFT_RE = /\[paste #(\d+) (?:\+\d+ lines|\d+ lines|image)\]$/;
const MARKER_RIGHT_RE = /^\[paste #(\d+) (?:\+\d+ lines|\d+ lines|image)\]/;
export function adjacentPasteMarker(text, caret, dir) {
  const s = String(text || '');
  const c = Math.max(0, Math.min(s.length, caret));
  if (dir < 0) {
    const m = MARKER_LEFT_RE.exec(s.slice(0, c));
    if (m) return { start: c - m[0].length, end: c, id: Number(m[1]) };
  } else {
    const m = MARKER_RIGHT_RE.exec(s.slice(c));
    if (m) return { start: c, end: c + m[0].length, id: Number(m[1]) };
  }
  return null;
}

// Apply the hover highlight to the visible columns [col0, col1) of an ANSI row.
// The highlight is an explicit bright style (C.hover), and it is RE-APPLIED
// after every escape sequence inside the span: a row is built from several
// col(...) chunks, each of which ends in RESET, and those resets used to cancel
// a bare BOLD a few characters into the row — so only the first chunk of a row
// ever appeared to light up. When the span ends, the row's own style is put
// back by replaying the SGR codes seen so far.
export function tintRange(row, col0, col1) {
  const s = String(row);
  if (col1 <= col0) return s;
  const hover = C.hover;
  let out = '';
  let cur = ''; // the row's own SGR state so far (replayed after the span)
  let col = 0;
  let i = 0;
  let tinting = false;
  while (i < s.length) {
    if (s[i] === ESC) {
      const m = /^\x1b\[[0-9;?]*[a-zA-Z]/.exec(s.slice(i))
        || /^\x1b\][^\x07\x1b]*(?:\x07|\x1b\\)/.exec(s.slice(i));
      if (m) {
        const seq = m[0];
        if (seq.endsWith('m') && !isHoverSgr(seq)) { // track the row's OWN state
          const p = seq.slice(2, -1);
          if (p === '' || p.split(';').includes('0')) cur = '';
          else cur += seq;
        }
        out += seq;
        // Re-apply the highlight AFTER every SGR while tinting, so it always WINS.
        // Applying it before the sequence was the bug behind "only the cyan part
        // lights up": a row is built from col(...) chunks, and the label's own
        // `\x1b[90m` (grey) came after the hover and overrode its colour, so the
        // dim half of every `KEY label` pair stayed grey. The re-apply is skipped for
        // the hover codes themselves, which would otherwise stack on every pass.
        if (tinting) out += hover;
        i += seq.length;
        continue;
      }
    }
    const cp = s.codePointAt(i);
    const ch = String.fromCodePoint(cp);
    const cw = visualWidth(ch);
    const want = col >= col0 && col < col1;
    if (want && !tinting) { out += hover; tinting = true; }
    else if (!want && tinting) { out += C.reset + cur; tinting = false; }
    out += ch;
    col += cw;
    i += cp > 0xffff ? 2 : 1;
  }
  if (tinting) out += C.reset + cur;
  return out;
}

// True for the sequences `C.hover` itself is made of. They must not be echoed back
// into `cur` (they are not part of the row's own style) and must not trigger another
// re-apply, or a single span would accumulate a copy of the style per SGR.
function isHoverSgr(seq) {
  return C.hover.includes(seq);
}

// Wrap the single visible cell at column `col` in reverse video: our own block
// caret. The row is already padded to the full width, so a caret past the last
// character inverts a padding space (kimi-code renders its caret the same way).
// A wide (2-column) glyph is inverted as a whole so the block keeps its size.
export function caretBlock(row, col) {
  const s = String(row);
  if (col < 0) return s;
  let out = '';
  let shown = 0;
  let i = 0;
  while (i < s.length) {
    if (s[i] === ESC) {
      const m = /^\x1b\[[0-9;?]*[a-zA-Z]/.exec(s.slice(i))
        || /^\x1b\][^\x07\x1b]*(?:\x07|\x1b\\)/.exec(s.slice(i));
      if (m) { out += m[0]; i += m[0].length; continue; }
    }
    const cp = s.codePointAt(i);
    const ch = String.fromCodePoint(cp);
    const cw = visualWidth(ch);
    if (col >= shown && col < shown + cw) {
      // Invert exactly one cell; ESC[7m .. ESC[27m leaves the row's colours alone.
      out += '\x1b[7m' + ch + '\x1b[27m';
    } else {
      out += ch;
    }
    shown += cw;
    i += cp > 0xffff ? 2 : 1;
  }
  return out;
}

// Lay the composer out as display rows. The first row carries the prompt
// prefix; wrapped continuation rows are indented to match. Explicit newlines
// start a fresh row. Returns the rows plus the caret's (row, col) within them
// (col already includes the leading border column).
export function composerLayout(state, insideW) {
  const { text: rawText, caret: rawCaret, prefix } = composerInput(state);
  const text = rawText;
  const caret = Math.max(0, Math.min(text.length, rawCaret));
  const cont = ' '.repeat(visualCol(prefix));
  const rows = [];
  // Per display row: the text offsets it covers plus the visual width of its
  // prefix, so a mouse click can be mapped back to a text index (click-to-caret).
  const meta = [];
  let caretRow = 0;
  let caretCol = 1 + visualCol(prefix);
  let base = 0;
  const paras = text.split('\n');
  for (let pi = 0; pi < paras.length; pi++) {
    const p = paras[pi];
    const pre = pi === 0 ? prefix : cont;
    const bodyW = Math.max(1, insideW - visualCol(pre));
    const segs = wrapWithOffsets(p, bodyW);
    for (let si = 0; si < segs.length; si++) {
      const seg = segs[si];
      const rowPre = si === 0 ? pre : cont;
      rows.push(rowPre + seg.text);
      // `line` records which LOGICAL line (paragraph) the row belongs to, and
      // `segCount`/`segIdx` which wrap segment it is within it. Vertical caret
      // movement needs both: kimi clamps a non-last segment to `length - 1` so the
      // caret cannot land on the first character of the NEXT row (which would make
      // ↑/↓ appear to skip), and only the last segment may reach the line's end.
      meta.push({ start: base + seg.start, end: base + seg.start + seg.text.length, preWidth: visualCol(rowPre), line: pi, segIdx: si, segCount: segs.length });
      const absStart = base + seg.start;
      const absEnd = absStart + seg.text.length;
      if (caret >= absStart && caret <= absEnd) {
        caretRow = rows.length - 1;
        caretCol = 1 + visualCol(rowPre) + visualCol(seg.text.slice(0, caret - absStart));
      }
    }
    base += p.length + 1; // + the '\n' we split on
  }
  if (rows.length === 0) { rows.push(prefix); meta.push({ start: 0, end: 0, preWidth: visualCol(prefix) }); }
  return { rows, meta, caretRow, caretCol };
}

// Map a click inside the composer content (colInside = 0-based column within the
// text area, after the left border) on display row `rowIdx` back to a text index.
// Map a VISUAL column (0-based, as the terminal counts it) to a CHARACTER index in
// `line`. The two differ whenever the text holds wide glyphs (CJK, emoji) — a
// Chinese character is ONE index but TWO columns — so treating a click column as a
// string index put the caret to the RIGHT of the click on any non-ASCII line.
// The walk is over the ORIGINAL string (what `caretCol` indexes); each character's
// column width comes from its tab-EXPANDED form (what the renderer draws).
function charIndexForVisualCol(line, col) {
  const raw = String(line == null ? '' : line);
  let w = 0;
  let idx = 0;
  for (const ch of raw) {
    const cw = visualWidth(expandTabs(ch));
    if (w + cw > col) break;
    w += cw;
    idx += 1;
  }
  return idx;
}

export function composerTextIndexAt(layout, rowIdx, colInside) {
  const m = layout.meta[rowIdx];
  if (!m) return 0;
  const colInSeg = colInside - m.preWidth; // columns into the segment text
  if (colInSeg <= 0) return m.start;
  // Walk the row's text to find the character whose cumulative width passes colInSeg.
  const rowText = layout.rows[rowIdx].slice(m.preWidth);
  let w = 0;
  let idx = 0;
  for (const ch of rowText) {
    const cw = visualWidth(ch);
    if (w + cw > colInSeg) break;
    w += cw;
    idx += ch.length;
  }
  return Math.min(m.end, m.start + idx);
}

// A Bash result is a FAILURE when the command exited non-zero or the spawn
// itself errored. Detected from the tool-result text (the only place the code
// survives for the UI, since the exit-code line is hidden from display).
// Failure prefixes that the built-in tools actually return (verified against
// src/tools/*.js). Any result starting with one of these is a FAILED call:
//   "Error: old_string not found in …"      (Edit)
//   "Error reading/writing <path>: …"       (Read/Write/Edit)
//   "Cannot read: <path> appears to be …"   (Read)
//   "Edit rejected: …"                      (Edit staleness / read guards)
//   "Command cannot be empty."              (Bash)
// resolvePath throws are surfaced verbatim as `e.message`, e.g.
//   "Path outside workspace: …" / "ENOENT: no such file or directory …".
const FAIL_PREFIX = /^(Error\b|\[error:|Cannot read:|Edit rejected:|Command cannot be empty\b|Path outside workspace\b|ENOENT\b|EACCES\b|EPERM\b|EISDIR\b|ENOTDIR\b)/i;

export function isFailureResult(text, toolName) {
  const s = String(text == null ? '' : text);
  const trimmed = s.trim();
  if (FAIL_PREFIX.test(trimmed)) return true;
  // A non-zero Bash exit code marks the call as failed (red status bullet). The
  // `[exit code: N]` LINE itself is never shown to the user — it is bookkeeping
  // for the model only (see messageLines).
  const m = /\[exit code:\s*([^\]]+)\]/.exec(s);
  if (!m) return false;
  const v = m[1].trim();
  return v !== '0';
}

// Extract the human-readable failure reason from a tool result, or '' when the
// result should not render an extra "why it failed" line. The reason is shown
// in red under the tool call for non-Bash tools (Edit / Read / Write / …); Bash
// failures are already obvious from the command's own output, so they return ''.
export function failureReason(text, toolName) {
  const name = String(toolName || '').toLowerCase();
  if (name === 'bash') return '';
  const s = String(text == null ? '' : text);
  const trimmed = s.trim();
  if (!FAIL_PREFIX.test(trimmed)) return '';
  // Collapse to a single line and drop the `[error: …]` wrapper.
  let line = trimmed.split('\n')[0].trim();
  line = line.replace(/^\[error:\s*/i, '').replace(/\]$/, '').trim();
  return line;
}

function msgColorFor(role, text) {
  // 'rich' output (e.g. /context, /usage panels) carries its OWN ANSI colours — do
  // not wrap it in a single role colour, or the whole panel comes out one shade.
  if (role === 'rich') return '';
  if (role === 'system' && typeof text === 'string' && text.startsWith('[turn took')) return C.gray;
  // System/status lines are NEUTRAL grey, not the brand teal: the deep teal showed
  // up on every command result and one-line notice, and at that frequency it read
  // as noise. Grey keeps them quiet; the accents stay for user/tool/working rows.
  if (role === 'system') return C.gray;
  if (role === 'user') return C.cyan;
  if (role === 'bash') return C.shellMode;   // ! shell-mode echo: violet, like kimi
  if (role === 'warn') return C.orange;    // unfinished-turn warning
  if (role === 'queued') return C.gray;    // pending, not yet sent
  if (role === 'steer') return C.yellow;   // injected into the running turn
  if (role === 'tool') return C.blue;
  if (role === 'tool_result') return C.gray;
  if (role === 'skill') return C.blue;
  if (role === 'image') return C.gray;   // the row names a file, it is not prose
  // Default foreground color based on theme
  return C.fg;
}

// ---- tool call display: "Using Name (keyArg)" / "Used Name (keyArg) ----
// Mirrors kimi-code's extractKeyArgument: pick the one argument that best
// identifies the call, so a tool line reads `Using Read (src/tui.js)`.
const KEY_ARG = {
  Bash: ['command'],
  Read: ['path', 'file_path'],
  Write: ['path', 'file_path'],
  Edit: ['path', 'file_path'],
  Grep: ['pattern'],
  Glob: ['pattern'],
  FileLines: ['path', 'file_path'],
  FetchURL: ['url'],
  WebSearch: ['query'],
  Agent: ['description', 'prompt'],
  TaskOutput: ['task_id'],
  TaskStop: ['task_id'],
};
const MAX_ARG = 60;
function keyArgument(name, args, workspace) {
  if (!args || typeof args !== 'object') return '';
  const keys = KEY_ARG[name] || Object.keys(args);
  for (const k of keys) {
    const v = args[k];
    if (typeof v !== 'string' || !v.length) continue;
    // Neutralise escapes BEFORE measuring: sanitizeText turns ESC into the two
    // visible characters `^[`, so truncating first and sanitizing after made a
    // long command (a `node -e "…"` one-liner is the usual case) come out `+1`
    // column wider than MAX_ARG — and a trailing ESC cut at the boundary left the
    // row ending in a bare `^` instead of a proper `…`.
    let text = sanitizeText(v.split('\n')[0]);
    // Make absolute paths under the workspace relative (shorter + familiar).
    if ((k === 'path' || k === 'file_path') && path.isAbsolute(text) && workspace) {
      const rel = path.relative(workspace, text);
      if (rel && !rel.startsWith('..') && !path.isAbsolute(rel)) text = rel;
    }
    if (text.length > MAX_ARG) {
      text = (k === 'path' || k === 'file_path')
          ? '…' + text.slice(text.length - (MAX_ARG - 1))
          : text.slice(0, MAX_ARG - 1) + '…';
    }
    // Display paths with forward slashes (consistent across platforms).
    if (k === 'path' || k === 'file_path') text = text.replace(/\\/g, '/');
    return text;
  }
  return '';
}
export function formatToolLine(msg, workspace, spin, pulseStart, shimmerEdge) {
  const name = msg.toolName || '';
  const arg = keyArgument(name, msg.toolArgs, workspace);
  const verb = msg.pending ? 'Using' : 'Used';
  // Pending tool calls have a sweep animation (like "Working...")
  // Once the tool finishes (pending=false) the name shows in plain cyan.
  let nameDisplay;
  if (msg.pending) {
    // Multi-stage sweep animation for tool names (like the "Working..." line):
    //   out to pale cyan, back; out to cyan-blue, back — one cycle.
    // The tick counts come from SWEEP_TICKS so this row and the Working row share
    // one smoothness budget (see the SWEEP_* block near the top of the file).
    const SWEEP = SWEEP_TICKS;       // ticks per half-sweep
    const HALF  = SWEEP + SWEEP;     // ticks per colour pair (sweep + sweep back)
    const CYCLE = HALF * 2;          // ticks for the full loop
    // Phase is measured from the tick the pulse BEGAN, so a spinner that has already
    // been running does not drop the sweep into a mid-cycle colour.
    //
    // `??`, NOT `||`: `pulseStart` is legitimately 0 at the START of a turn (that is
    // where the spinner begins), and `0 || spin` evaluates to `spin`, making
    // `spin - spin === 0` forever — the name then held ONE flat colour and never
    // animated at all. Only `null`/`undefined` mean "no anchor yet".
    const anchor = pulseStart ?? spin;
    const inCycle = ((spin - anchor) % CYCLE + CYCLE) % CYCLE;
    const inHalf  = inCycle % HALF;       // position within this colour pair's half
    const phase   = inCycle < HALF ? 0 : 1; // 0 = l↔c, 1 = c↔b

    // Colours as plain RGB triples (mirroring Working's orange→yellow/red pattern).
    // The orange pulse swings HARD — yellow is +100G/+120B off the base and red is
    // -140G — but this sweep used to move only +64R / -35G, i.e. about a QUARTER of
    // that amplitude, so "pale cyan" and "cyan-blue" were both nearly
    // indistinguishable from plain cyan. Match the orange pulse's swing:
    //   pale cyan = base + a strong red lift (toward white)
    //   cyan-blue = base with the green pulled DOWN but not away: green 90 read as
    //               plain blue and clashed with the cyan base, so it is kept at 150
    //               — still clearly darker/cooler than the base, still cyan-family
    // so each phase is a DIFFERENT colour, not a shade of the same one.
    const c = [0, 215, 255];      // pure cyan (like ORANGE base)
    const l = [150, 255, 255];    // pale cyan (like YELLOW: base + strong R/G lift)
    const b = [0, 150, 255];      // cyan-blue (like RED: base with green pulled down)
    const base = c;                       // always cyan, like Working's constant ORANGE
    const target = phase === 0 ? l : b;   // pale cyan, then cyan-blue

    const chars = name;
    const n = chars.length;

    // A character fades over a band this many characters wide. Same sizing rule as
    // the Working row, so the two sweeps have the same feel.
    const BAND = bandCharsFor(n) / n;

    // Interpolate base ↔ target by `t` (0 = base, 1 = target).
    const mix = (t) => {
      const k = Math.max(0, Math.min(1, t));
      return lerpColor(
          base[0] + (target[0] - base[0]) * k,
          base[1] + (target[1] - base[1]) * k,
          base[2] + (target[2] - base[2]) * k,
          base[0] + (target[0] - base[0]) * k,
          base[1] + (target[1] - base[1]) * k,
          base[2] + (target[2] - base[2]) * k,
          0,
      );
    };

    const out = [];
    // The band SHAPE is shared with the Working row, and this sweep SETTLES: a
    // character the head has passed stays at its target colour, which is what makes
    // the name read as "filling in" left to right rather than a light passing over.
    // The edge arrives as a PARAMETER, threaded from `state` by the render chain:
    // formatToolLine is module-level and `state` lives in startTUI's closure, so
    // reading `state.shimmerEdge` here threw "state is not defined" on the first
    // pending tool row — the ReferenceError surfaced as an unhandledRejection and
    // the process handler exited the TUI the moment a tool call started.
    const edge = shimmerEdge || 'cosine';
    for (let i = 0; i < n; i++) {
      const charAt = n > 0 ? i / n : 0;
      let t; // 0 = base, 1 = target
      // Same geometry as the Working row's pulse: the head runs from BEHIND the name
      // to past its end within each half, so the first frame of a half is the resting
      // colour and the last frame is fully settled. Starting at `1/SWEEP` (already
      // past the first character) made the name jump on the very first frame.
      //   / (SWEEP - 1) so the FIRST frame is progress 0 and the LAST is 1.
      const progress = (inHalf < SWEEP ? inHalf : inHalf - SWEEP) / (SWEEP - 1);
      const head = -BAND + progress * (1 + BAND * SWEEP_TRAVEL_PAD);
      const settled = sweepSettle(head - charAt, BAND, edge);
      t = inHalf < SWEEP ? settled : 1 - settled;
      out.push(col(chars[i], mix(t)));
    }
    nameDisplay = out.join('');
  } else {
    // Non-pending: show in plain cyan
    nameDisplay = col(name, C.cyan);
  }
  // Show streamed size for Write tool
  let sizeStr = '';
  if (name === 'Write' && typeof msg.streamContent === 'string' && msg.streamContent.length) {
    const bytes = Buffer.byteLength(msg.streamContent, 'utf8');
    sizeStr = bytes >= 1048576 ? ` ${(bytes / 1048576).toFixed(1)}MB`
      : bytes >= 1024 ? ` ${(bytes / 1024).toFixed(1)}KB`
      : ` ${bytes}B`;
  }
  // Show +xx -xx diff counts for Edit tool when done. The diff itself is rendered
  // under the `↳` receipt, so prefer the counts the tool_result handler copied over.
  let diffStr = '';
  const edDiff = (Array.isArray(msg.diff) && msg.diff.length) ? msg.diff : msg._diffCounts;
  if (name === 'Edit' && !msg.pending && Array.isArray(edDiff) && edDiff.length) {
    const adds = edDiff.filter((d) => d.type === 'add').length;
    const deletes = edDiff.filter((d) => d.type === 'del').length;
    if (adds || deletes) {
      diffStr = ' ' + (adds ? col(`+${adds}`, C.green) : '') + ' ' + (deletes ? col(`-${deletes}`, C.red) : '');
    }
  }
  // The `●` bullet carries the state (orange while running, green when done),
  // so the verb itself stays plain white and the tool name keeps the theme
  // colour.
  const argText = arg ? ' ' + col(`(${arg})`, C.gray) : '';
  return col(verb, C.white) + ' ' + nameDisplay + argText + col(sizeStr, C.gray) + diffStr;
}

// ---- live TODO panel (kimi-code's todo-panel) ----
// Renders above the input box: a rule, a "Todo" heading, up to 5 rows, and a
// "+N more · ctrl+t to expand" hint. Ctrl+T expands the full list.
const TODO_MAX_VISIBLE = 5;
export function selectVisibleTodos(todos) {
  if (todos.length <= TODO_MAX_VISIBLE) return { rows: todos, hidden: 0, counts: {} };
  const inProgress = [], pending = [], done = [];
  todos.forEach((t, i) => {
    if (t.status === 'in_progress') inProgress.push(i);
    else if (t.status === 'pending') pending.push(i);
    else done.push(i);
  });
  const picked = new Set(inProgress.slice(0, TODO_MAX_VISIBLE));
  if (picked.size < TODO_MAX_VISIBLE) {
    const doneC = [...done].reverse();
    const pendC = pending;
    const remaining = TODO_MAX_VISIBLE - picked.size;
    let doneCount, pendCount;
    if (!doneC.length) { doneCount = 0; pendCount = Math.min(remaining, pendC.length); }
    else if (!pendC.length) { pendCount = 0; doneCount = Math.min(remaining, doneC.length); }
    else {
      doneCount = 1;
      pendCount = Math.min(remaining - 1, pendC.length);
      if (pendCount < remaining - 1) doneCount = Math.min(doneC.length, remaining - pendCount);
    }
    for (let i = 0; i < doneCount; i++) picked.add(doneC[i]);
    for (let i = 0; i < pendCount; i++) picked.add(pendC[i]);
  }
  const idx = [...picked].sort((a, b) => a - b);
  const counts = { done: 0, in_progress: 0, pending: 0 };
  todos.forEach((t, i) => { if (!picked.has(i)) counts[t.status] = (counts[t.status] || 0) + 1; });
  return { rows: idx.map((i) => todos[i]), hidden: todos.length - idx.length, counts };
}

function todoRow(todo, w) {
  const mark = todo.status === 'in_progress' ? col('●', C.cyan + C.bold)
    : todo.status === 'done' ? col('✓', C.green)
    : col('○', C.gray);
  const title = todo.status === 'in_progress' ? col(todo.title, C.white + C.bold)
    : todo.status === 'done' ? col(todo.title, C.gray)
    : col(todo.title, C.white);
  return '  ' + mark + ' ' + fitAnsi(title, Math.max(1, w - 4));
}

// `hoverTop` / `dragTop` drive the top rule's hover and press colours: that rule
// is a drag handle for resizing the panel.
function renderTodoPanel(state, w, hoverTop, dragTop) {
  const todos = state.todos || [];
  if (!todos.length) return [];
  const out = [];
  const ruleColor = dragTop ? C.scrollThumbActive : (hoverTop ? C.hover : C.border);
  out.push(col('─'.repeat(w), ruleColor));
  out.push(col('  Todo', C.cyan + C.bold));
  const want = todoRowCount(state);
  // Keep the automatic pick ORDER (so the in-progress item keeps its priority) and
  // top it up from the remaining items until `want` rows are shown.
  const ordered = [];
  const seen = new Set();
  for (const t of selectVisibleTodos(todos).rows) { ordered.push(t); seen.add(t); }
  for (const t of todos) {
    if (ordered.length >= want) break;
    if (!seen.has(t)) { ordered.push(t); seen.add(t); }
  }
  const rows = ordered.slice(0, want);
  for (const t of rows) out.push(todoRow(t, w));
  const hidden = todos.length - rows.length;
  if (hidden > 0) {
    const counts = { done: 0, in_progress: 0, pending: 0 };
    for (const t of todos) if (!rows.includes(t)) counts[t.status] = (counts[t.status] || 0) + 1;
    const dist = [['done', 'done'], ['in_progress', 'in progress'], ['pending', 'pending']]
      .filter(([k]) => counts[k] > 0).map(([k, label]) => `${counts[k]} ${label}`).join(', ');
    // The hint appears exactly when rows are hidden — which is exactly when Ctrl+T
    // is useful — so this is where the key has to be discoverable.
    out.push(col(`  … +${hidden} more${dist ? ` (${dist})` : ''} · ctrl+t to expand · drag the top rule to resize`, C.gray));
  }
  return out;
}

// --- queue pane (kimi-code's QueuePane) -------------------------------------
// One rule line, one line per queued message, one dim hint line. Queued input is
// held while the agent is streaming and is injected by Ctrl-S (or by the agent
// itself at the next tool boundary).
// Supports auto-collapse and drag-to-resize like the todo panel.
const QUEUE_MAX_VISIBLE = 5;
function renderQueuePanel(state, w, hoverTop, dragTop) {
  const queued = state.queued || [];
  if (!queued.length) return [];
  
  const out = [];
  const ruleColor = dragTop ? C.scrollThumbActive : (hoverTop ? C.hover : C.border);
  out.push(col('─'.repeat(w), ruleColor));
  out.push(col('  Queue', C.cyan + C.bold));
  
  const want = queueRowCount(state);
  const rows = queued.slice(0, want);
  for (const text of rows) {
    // Collapse to a single line, like kimi's queue pane does.
    const single = String(text).replace(/\s+/g, ' ').trim();
    out.push(col('  ', C.cyan) + col('❯ ', C.cyan) + col(fitAnsi(single, Math.max(1, w - 6)), C.white));
  }
  
  const hidden = queued.length - rows.length;
  if (hidden > 0) {
    const hint = state.running 
      ? `… +${hidden} more · ↑ to edit · ctrl-s to steer immediately · drag top rule to resize`
      : `… +${hidden} more · ↑ to edit · will send now · drag top rule to resize`;
    out.push(col('  ' + hint, C.gray));
  } else {
    const hint = state.running ? '↑ to edit · ctrl-s to steer immediately' : '↑ to edit · will send now';
    out.push(col('  ' + hint, C.gray));
  }
  
  return out;
}

// How many queue ROWS the panel shows.
//   * `state.queueRows` (set by dragging the top rule) wins when present;
//   * otherwise show all items up to QUEUE_MAX_VISIBLE.
// Always clamped to [1, queued.length]: at least ONE row, never more than exist.
export function queueRowCount(state) {
  const queued = state.queued || [];
  if (!queued.length) return 0;
  const manual = state.queueRows;
  let rows;
  if (typeof manual === 'number' && Number.isFinite(manual)) {
    rows = Math.round(manual);
  } else {
    rows = Math.min(queued.length, QUEUE_MAX_VISIBLE);
  }
  return Math.max(1, Math.min(queued.length, rows));
}

// Height (in rows) the queue panel will occupy, for layout math.
export function queuePanelHeight(state) {
  const queued = state.queued || [];
  if (!queued.length) return 0;
  const rows = queueRowCount(state);
  const extra = queued.length > rows ? 1 : 0; // the "… +N more" hint
  return 2 + rows + extra; // rule + heading + rows (+ hint)
}

// How many todo ROWS the panel shows.
//   * `state.todoRows` (set by dragging the top rule) wins when present;
//   * otherwise the automatic heuristic (selectVisibleTodos) decides.
// Always clamped to [1, todos.length]: at least ONE row, never more than exist.
export function todoRowCount(state) {
  const todos = state.todos || [];
  if (!todos.length) return 0;
  const manual = state.todoRows;
  let rows;
  if (typeof manual === 'number' && Number.isFinite(manual)) {
    rows = Math.round(manual);
  } else {
    rows = state.todosExpanded ? todos.length : selectVisibleTodos(todos).rows.length;
  }
  return Math.max(1, Math.min(todos.length, rows));
}

// Height (in rows) the todo panel will occupy, for layout math.
export function todoPanelHeight(state) {
  const todos = state.todos || [];
  if (!todos.length) return 0;
  const rows = todoRowCount(state);
  const extra = todos.length > rows ? 1 : 0; // the "… +N more" hint
  return 2 + rows + extra; // rule + heading + rows (+ hint)
}

// Render one chat message into display lines.
// Returns { lines: [{text, ind, color}] } (ind = indent string for continuation).
//
// `rawMode` (/raw) shows the model's text VERBATIM: no Markdown rendering, no
// wrapping, no ANSI interpretation. It exists to answer "what did the model
// actually send" when a rendering bug makes a reply look wrong — with the renderer
// in the way there is no way to tell a bad reply from a bad render.
function messageLines(msg, width, workspace, expanded, spin, pulseStart, rawMode, shimmerEdge) {
  if (rawMode && (msg.role === 'assistant' || msg.role === 'thinking')) {
    const src = String(msg.text == null ? '' : msg.text);
    // escape the ANSI bytes so a stray `\x1b[31m` in the model's output cannot
    // repaint the terminal — the point is to SEE it, not to obey it.
    const out = src.replace(/\x1b/g, '^[').split('\n').map((t, i) => ({
      text: t, ind: i === 0 ? '' : '', color: C.gray,
    }));
    return out.length ? out : [{ text: '', ind: '', color: C.gray }];
  }
  // Tool calls render as a single "● Using/Used Name (arg)" line (kimi style).
  // The body already carries its own ANSI colours, so mark it pre-colored.
  if (msg.role === 'tool') {
    const body = formatToolLine(msg, workspace, spin, pulseStart, shimmerEdge);
    // Red bullet for a failed call (a Bash non-zero exit / [error: …]).
    const failed = msg.failed === true || (msg.role === 'tool' && msg.failed === true);
    const pre = col('● ', msg.pending ? C.orange : (failed ? C.red : C.green));
    const bodyW = Math.max(1, width - visualCol('● '));
    const wrapped = wrapAnsiWords(body, bodyW);
    // Mark every CONTINUATION boundary with a trailing `…` so a wrapped command
    // never looks like it ended at a quote or `;`. Without this, a command like
    // `$ProgressPreference='SilentlyContinue'; Invoke-WebRequest …` broke right
    // after the closing quote, and the first row read as the whole command.
    // The last row keeps whatever `keyArgument` already put there (its own `…`
    // when the text itself was truncated).
    const out = wrapped.map((t, i) => ({
      text: i < wrapped.length - 1 ? t + col('…', C.gray) : t,
      ind: i === 0 ? pre : '  ',
      raw: true,   // text already contains ANSI; do not wrap in another colour
    }));
    const name = msg.toolName || '';
    const indent = '  ';
    const avail = Math.max(1, width - visualCol(indent));

    // AgentSwarm renders kimi's live progress BLOCK instead of a `↳` output dump:
    // a header, one cell per subagent, and a status pip bar. The members live on
    // the message (see the tool_use handler, which registers them as soon as the
    // args arrive) and update in place while the swarm runs.
    if (name === 'AgentSwarm' && Array.isArray(msg.swarmMembers) && msg.swarmMembers.length) {
      const block = renderSwarmProgress({
        description: msg.swarmDescription || '',
        model: msg.swarmModel || '',
        members: msg.swarmMembers,
        failed: msg.swarmFailed === true,
      }, width, { indent: ' ', availableGridHeight: 8 });
      for (const line of block) out.push({ text: line, ind: '', raw: true });
      return out;
    }

    // Live output of a RUNNING command (Bash): rendered under the "Using …"
    // row exactly like the finished "Used …" output, just not done yet. Only
    // the tail is shown (capped) so a chatty command cannot flood the frame.
    if (msg.pending && typeof msg.liveOutput === 'string' && msg.liveOutput.length) {
      const bodyW = Math.max(1, width - visualCol('  '));
      const rawLines = sanitizeText(msg.liveOutput).replace(/\r\n/g, '\n').split('\n');
      const MAX_RUN_LINES = expanded ? Infinity : 8;
      const shown = rawLines.slice(-MAX_RUN_LINES); // running: show the newest output
      if (rawLines.length > MAX_RUN_LINES) {
        out.push({ text: col(`… ${rawLines.length - MAX_RUN_LINES} earlier line(s)`, C.gray), ind: indent, raw: true });
      }
      for (const ln of shown) {
        for (const t of (ln === '' ? [''] : wrapWords(ln, bodyW))) {
          out.push({ text: col(t, C.gray), ind: indent, raw: true });
        }
      }
    }

    // Ctrl+B detach hint (mirrors kimi-code). A foreground Bash/Agent call that
    // has been running a while advertises the shortcut that moves it to the
    // background; the hint disappears the moment the result lands. Bash waits
    // DETACH_HINT_DELAY_MS so short commands never flash it; Agent-like tools
    // announce it immediately since they are long-running by nature.
    if (msg.pending && (name === 'Bash' || name === 'Agent' || name === 'AgentSwarm') && msg.startAt) {
      const waited = Date.now() - msg.startAt;
      const delay = name === 'Bash' ? DETACH_HINT_DELAY_MS : 0;
      if (waited >= delay) {
        out.push({ text: col(DETACH_HINT_TEXT, C.gray), ind: indent, raw: true });
      }
    }

    // Write: stream the file content while the model is still emitting it.
    if (name === 'Write' && typeof msg.streamContent === 'string' && msg.streamContent.length) {
      // Only the first MAX lines are drawn, so sanitize+split a bounded PREFIX.
      // Doing it over the whole accumulated content re-processed every byte on
      // each frame — O(n²) over the stream, which blocked the main thread on a
      // large file. The cut is generous (64 KB) to cover MAX long lines; the
      // line count for the "… N more lines" note is taken from the message,
      // which tracks the true size cheaply.
      const SCAN_BYTES = 64 * 1024;
      const head = msg.streamContent.length > SCAN_BYTES ? msg.streamContent.slice(0, SCAN_BYTES) : msg.streamContent;
      const lines = sanitizeText(head).replace(/\r\n/g, '\n').split('\n');
      // A file's content almost always ends in a newline, and `split('\n')` turns
      // that into a final EMPTY element — which rendered as a phantom numbered line
      // ("14" with nothing after it) below the real content. Drop it, but only the
      // one the trailing newline produced (an intentionally blank last line survives
      // as long as the content does not end with a newline).
      if (lines.length > 1 && lines[lines.length - 1] === '' && /\n$/.test(head)) lines.pop();
      const MAX = 20;
      // The TRUE line count comes from the message: `lines` only covers the scanned
      // prefix, so counting it would understate a large file's size.
      const totalLines = msg._streamLineCount || lines.length;
      const wNum = String(totalLines).length;
      lines.slice(0, MAX).forEach((ln, i) => {
        out.push({ text: col(`${String(i + 1).padStart(wNum)} ${ln}`, C.gray), ind: i === 0 ? '↳ ' : indent, raw: true });
      });
      const shown = Math.min(lines.length, MAX);
      if (totalLines > shown) out.push({ text: col(`… ${totalLines - shown} more lines`, C.gray), ind: indent, raw: true });
    }

    // The Edit diff is NOT drawn here: it rides on the tool_result message and is

    // The Edit diff is NOT drawn here: it rides on the tool_result message and is
    // rendered BELOW the `↳` receipt (see the tool_result branch). Drawing it here
    // put it between the `● Used Edit` status bullet and the receipt.
    return out;
  }
  // A PLAN block (Plan mode): the model's <|plan|>…</|plan|> body, rendered as a
  // single-column TABLE — the same ╭─┬─╮ / ├─┼─┤ / ╰─┴─╯ vocabulary the Markdown
  // table renderer uses, so a plan reads as structured data rather than as prose
  // or as a second composer box.
  if (msg.role === 'plan') {
    // `width` is the transcript's inner width (the caller already removed the
    // one-column margin); the wrapped user boxes land at `width - 2`.
    const tableW = Math.max(12, width - 2);
// Body rows.
    // NOTE: rows must be {text, ind, raw} OBJECTS — messageLines' contract. Pushing
    // plain strings here made rowToLine read `undefined` and the whole block rendered as
    // blank lines.
    const out = [];
    const bar = (ch) => col(ch, C.border);
    const inner = Math.max(1, tableW - 2);
    const full = (l, r) => bar(l + '─'.repeat(inner) + r);
    // Header: the table's single column is captioned "Plan".
    out.push({ text: full('╭', '╮'), ind: '', raw: true });
    out.push({ text: bar('│') + fitAnsi(col(' Plan', C.cyan + C.bold), inner) + bar('│'), ind: '', raw: true });
    out.push({ text: bar('├' + '─'.repeat(inner) + '┤'), ind: '', raw: true });
    const lines = String(msg.text || '').replace(/\r\n/g, '\n').split('\n');
    while (lines.length && lines[lines.length - 1].trim() === '') lines.pop();
    const textW = Math.max(1, inner - 2);
    for (const raw of lines) {
      if (raw.trim() === '') {
        out.push({ text: bar('│') + ' '.repeat(inner) + bar('│'), ind: '', raw: true });
        continue;
      }
      // Headings are emphasised; everything else renders as Markdown body text so
      // **bold**, `code` and bullets work.
      const isHead = /^\s*#{1,6}\s/.test(raw);
      const shown = isHead ? raw.replace(/^\s*#{1,6}\s*/, '') : raw;
      for (const r of renderMdText(shown, textW, isHead ? (C.cyan + C.bold) : C.white, C.cyan)) {
        out.push({ text: bar('│') + ' ' + fitAnsi(r, textW) + ' ' + bar('│'), ind: '', raw: true });
      }
    }
    out.push({ text: full('╰', '╯'), ind: '', raw: true });
    return out;
  }

  // A BACKGROUND TASK lifecycle card (kimi-style):
  //     ● agent task completed in background (review the diff)
  //     ✗ bash task failed in background (npm test · exit 1)
  // The bullet is `●` normally and `✗` for a failure; the colour follows the
  // phase. The task's conclusion sits underneath, indented, and is capped like
  // a tool result so one chatty subagent cannot flood the transcript.
  if (msg.role === 'bg_task') {
    const card = msg.card || { phase: 'completed', headline: 'background task finished', detail: undefined };
    const tone = card.phase === 'started' ? C.cyan : card.phase === 'completed' ? C.green : C.red;
    const bullet = card.phase === 'failed' ? '✗ ' : '● ';
    const out = [];
    const detail = card.detail ? col(` (${card.detail})`, C.gray) : '';
    out.push({ text: col(bullet, tone) + col(card.headline, tone) + detail, ind: '', raw: true });
    const body = String(msg.text || '').trim();
    if (body) {
      const indent = '  ';
      const avail = Math.max(1, width - visualCol(indent));
      const lines = body.replace(/\r\n/g, '\n').split('\n');
      const MAX = expanded ? 200 : 6;
      for (const ln of lines.slice(0, MAX)) {
        for (const w of (ln === '' ? [''] : wrapWords(ln, avail))) {
          out.push({ text: col(w, C.gray), ind: indent, raw: true });
        }
      }
      if (lines.length > MAX) {
        out.push({ text: col(`… ${lines.length - MAX} more lines, ctrl+o to expand`, C.gray), ind: indent, raw: true });
      }
    }
    return out;
  }

  // Tool output: a single "↳ " marker on the first line, then the output
  // indented by 2 columns. Long output is capped (kimi caps result previews
  // too) so one command cannot flood the whole transcript.
  if (msg.role === 'tool_result') {
    // The marker sits in the SAME COLUMN as the tool bullet `●` (rendered as
    // '● ', i.e. columns 0-1), so `↳ ` starts at column 0 and the output text
    // is indented to the tool text column. ONE `↳` per result, however many
    // lines it has.
    const pre = '↳ ';
    const cont = '  ';
    const bodyW = Math.max(1, width - visualCol(cont));
    // Strip escapes BEFORE splitting: a file or a command can emit raw SGR /
    // cursor codes, and letting them through made the terminal OBEY them —
    // recolouring the transcript, resetting styles mid-row, moving the cursor or
    // clearing the screen over the composer.
    const rawLines = sanitizeText(msg.text).replace(/\r\n/g, '\n').split('\n');
    // Trim blank lines at BOTH ends: commands typically emit a trailing
    // newline, and some tools emit a leading one. A stray blank line would
    // render as a lone "↳ " with no content.
    while (rawLines.length && rawLines[0].trim() === '') rawLines.shift();
    while (rawLines.length && rawLines[rawLines.length - 1].trim() === '') rawLines.pop();
    const MAX_RESULT_LINES = expanded ? Infinity : 12;
    // The exit-code line is bookkeeping for the AGENT (it stays in the tool
    // result the model receives) and is NEVER shown to the user — success or
    // failure. A failure is already legible from the RED result text below.
    // `[error: …]` is kept: it carries the message, not just a code.
    const visible = rawLines.filter((ln) => !/^\[exit code:/.test(ln.trim()));
    const failed = msg.failed === true;
    const shown = visible.slice(0, MAX_RESULT_LINES);

    // ---- DISPLAY ORDER -----------------------------------------------------
    // The row reads as a block under the tool line, with ONE `↳` marker:
    //   ● Used Edit (a.js) +1 -1        <- status bullet
    //   ↳ 3 - old line                  <- `↳` rides the FIRST body row
    //     3 + new line
    //   Edited a.js: replaced 1 occurrence(s).   <- receipt LAST
    // For an Edit the DIFF is the body (and carries the marker); the receipt text
    // moves to the bottom. For every other tool the tool output IS the body, so
    // the marker sits on its first line, exactly as before.
    const diffRows = [];
    const receiptRows = [];
    const hasDiff = Array.isArray(msg.diff);   // empty array => receipt-only (Write)

    if (hasDiff) {
      // Same collapse rule as the tool output and thinking blocks above: a short
      // preview by default, everything once Ctrl+O expands. 16 rows (not 12)
      // because a change renders as a PAIR: `- old` then `+ new`.
      const MAX = expanded ? Infinity : 16;
      // Show the unified diff WITH context rows (ctx = dim, marked by a space in
      // the sign column) so a change is not two orphaned blocks; `gap` rows mark
      // where unchanged lines were elided.
      const total = msg.diff.length;
      const wNo = Math.max(1, ...msg.diff.map((d) => String(d.no || 0).length));
      let emitted = 0;
      for (const d of msg.diff) {
        if (emitted >= MAX) break;
        if (d.type === 'gap') {
          diffRows.push({ text: col('  ⋮', C.gray), ind: cont, raw: true });
          emitted++;
          continue;
        }
        const no = String(d.no || 0).padStart(wNo);
        const mark = d.type === 'add' ? '+' : d.type === 'del' ? '-' : ' ';
        // Unchanged context lines are WHITE (they are real file content); the
        // added/removed lines carry the green/red. Grey made the context recede
        // so far the diff read as two disconnected change blocks.
        const color = d.type === 'add' ? C.green : d.type === 'del' ? C.red : C.white;
        // Diff lines are FILE content and can carry escapes; show them as `^[`.
        diffRows.push({ text: col(`${no} ${mark} ${sanitizeText(d.text)}`, color), ind: cont, raw: true });
        emitted++;
      }
      if (total > emitted) {
        diffRows.push({
          text: col(`… (${total - emitted} more lines, ctrl+o to expand)`, C.gray),
          ind: cont, raw: true,
        });
      }
      if (total === 0) diffRows.push({ text: col('(no changes)', C.gray), ind: cont, raw: true });
      // The receipt: one line per source line of the tool's own message.
      for (const ln of shown) {
        const color = failed ? C.red : C.gray;
        for (const t of (ln === '' ? [''] : wrapWords(ln, bodyW))) {
          receiptRows.push({ text: t, ind: cont, color });
        }
      }
    } else {
      // No diff: the tool's own output is the body.
      shown.forEach((ln, idx) => {
        const isErr = /^\[error:/.test(ln.trim());
        // A failed run is red throughout so it cannot be skimmed past.
        const color = isErr ? C.red : (failed ? C.red : C.gray);
        const wrapped = ln === '' ? [''] : wrapWords(ln, bodyW);
        wrapped.forEach((t, i) => {
          diffRows.push({ text: t, ind: idx === 0 && i === 0 ? pre : cont, color });
        });
      });
      if (visible.length > MAX_RESULT_LINES) {
        diffRows.push({ text: `… ${visible.length - MAX_RESULT_LINES} more lines`, ind: cont, color: failed ? C.red : C.gray });
      }
    }

    const out = [];
    for (const r of diffRows) out.push(r);
    for (const r of receiptRows) out.push(r);
    // Put the `↳` on the FIRST rendered row (diff or output) — never on the
    // receipt, which now sits last.
    if (out.length && out[0].ind === cont && Array.isArray(msg.diff) && msg.diff.length > 0) {
      out[0] = { ...out[0], ind: pre };
    }
    // The TOOL ROW may already have drawn this result's body — a Write streams the
    // file's content up there ("↳ 1 line one …") — in which case the receipt below is
    // the whole result and must NOT open a second `↳` block:
    //     ● Used Write (a.txt) 1.3KB
    //     ↳  1 <content>                     <- the body, marked on the tool row
    //     ↳ File written: a.txt (1372 bytes) <- the stray second `↳`, now plain
    // One body, one marker. `bodyOnToolRow` is set by the tool_result handler, which
    // is the only place that knows whether the tool row had content to show.
    if (msg.bodyOnToolRow && out.length && out[0].ind === pre) {
      out[0] = { ...out[0], ind: cont };
    }
    // Nothing to show (empty output) -> render no row at all rather than a
    // dangling "↳ ".
    return out;
    // Nothing to show (empty output) -> render no row at all rather than a
    // dangling "↳ ".
    return out;
  }

  // Compaction block, matching kimi-code's CompactionComponent:
  //   running   -> blinking bullet + "Compacting context…" (+ optional instruction)
  //   done      -> solid green bullet + "Compaction complete (X → Y tokens)"
  //                + " (Ctrl-O to show/hide compaction summary)"
  //   cancelled -> warning bullet + "Compaction cancelled"
  // Expanded state is the SHARED Ctrl+O one, so one key reveals tool output and
  // compaction summaries alike.
  if (msg.role === 'compaction') {
    const INDENT = '  ';
    const done = msg.phase === 'done';
    const canceled = msg.phase === 'cancelled';
    const bulletColor = done ? C.green : canceled ? C.yellow : C.white;
    // Blink off `spin` — the same monotonic tick the tool-call bullets use. It has
    // to be a STATE-driven phase, NOT `Date.now()`: the render cache is validated
    // against `spinKey`, so a clock-derived phase changes without invalidating the
    // cache and the bullet renders once and then freezes.
    const on = ((spin || 0) >> 3) % 2 === 0;
    const bullet = (!done && !canceled && !on) ? '  ' : col('● ', bulletColor);
    let head;
    if (done) {
      const detail = (msg.tokensBefore != null && msg.tokensAfter != null)
        ? col(` (${fmtTokens(msg.tokensBefore)} → ${fmtTokens(msg.tokensAfter)} tokens)`, C.gray) : '';
      const hint = (msg.text || '').trim()
        ? col(` (Ctrl-O to ${expanded ? 'hide' : 'show'} compaction summary)`, C.gray) : '';
      head = bullet + col('Compaction complete', C.green + C.bold) + detail + hint;
    } else if (canceled) {
      head = bullet + col('Compaction cancelled', C.yellow + C.bold);
    } else {
      head = bullet + col('Compacting context…', C.cyan + C.bold);
    }
    const out = [{ text: head, ind: '', raw: true }];
    if (msg.instruction) {
      out.push({ text: INDENT + col(String(msg.instruction), C.gray), ind: INDENT, raw: true });
    }
    if (done && expanded && (msg.text || '').trim()) {
      const bodyW = Math.max(1, width - visualCol(INDENT));
      for (const ln of String(msg.text).replace(/\r\n/g, '\n').split('\n')) {
        if (ln === '') { out.push({ text: '', ind: INDENT, raw: true }); continue; }
        for (const w of wrapWords(ln, bodyW)) {
          out.push({ text: INDENT + col(w, C.gray), ind: INDENT, raw: true });
        }
      }
    }
    return out;
  }

  // Reasoning ("thinking") block, matching kimi-code's ThinkingComponent:
  //   live      -> "<spinner> thinking…" then the LAST 2 content lines, indented
  //   finalized -> "● " marker on the first line, up to 2 preview lines, then a
  //                "… (N more lines)" hint
  // All of it is dim text.
  if (msg.role === 'thinking') {
    const INDENT = '  ';
    const bodyW = Math.max(1, width - visualCol(INDENT));
    const contentLines = [];
    for (const ln of String(msg.text || '').replace(/\r\n/g, '\n').split('\n')) {
      if (ln === '') { contentLines.push(''); continue; }
      for (const w of wrapWords(ln, bodyW)) contentLines.push(w);
    }
    // AN EMPTY REASONING BLOCK DRAWS NOTHING.
    //
    // A model may emit a `think` event with no text, and the block that spans a tool
    // call can be left with nothing in it — the tool boundary finalises the block, so
    // when the model reasons again it opens a NEW one. Either way the old code drew a
    // bare `●` row (or a lone "thinking…" spinner), which reads as a rendering bug:
    // there is no thought to show.
    //
    // Only the RENDERING is suppressed. The block stays in `state.chat`, so the next
    // `think` event APPENDS to it rather than opening another one — the state machine
    // (and the row cache that keys on it) is unchanged, and a block that later
    // receives text appears with its full content.
    if (!contentLines.some((l) => l.trim() !== '')) return [];
    const PREVIEW = expanded ? Infinity : 2;
    // The reasoning BODY is italic; the "thinking…" label and the "N more lines"
    // hint are NOT. Closed with endItalic rather than reset, so the row keeps the
    // dim gray it is drawn in.
    const it = (s) => (s === '' ? s : C.italic + s + C.endItalic);
    const out = [];
    if (msg.pending) {
      // The spinner frame is NOT baked in here: a glyph that changes every 80ms
      // tick would invalidate this row's cache and re-wrap the whole reasoning
      // block each time (measured ~44ms/frame vs ~6ms warm), which is what made
      // long thinking look laggy while ordinary streamed text stayed smooth.
      // renderChatLines substitutes the live frame outside the cache instead.
      out.push({ text: SPIN_PLACEHOLDER + ' thinking…', ind: '', color: C.gray });
      const vis = contentLines.length > PREVIEW ? contentLines.slice(-PREVIEW) : contentLines;
      for (const l of vis) out.push({ text: it(l), ind: INDENT, color: C.gray });
    } else {
      const shown = contentLines.slice(0, PREVIEW);
      shown.forEach((l, i) => out.push({ text: it(l), ind: i === 0 ? '● ' : INDENT, color: C.gray }));
      if (contentLines.length > PREVIEW) {
        out.push({ text: `… (${contentLines.length - PREVIEW} more lines, ctrl+o to expand)`, ind: INDENT, color: C.gray });
      }
    }
    return out;
  }



  let icon = '';
  switch (msg.role) {
    case 'system': icon = ''; break;
    case 'user': icon = '❯'; break;
    case 'bash': icon = '!'; break;   // shell-mode echo
    case 'warn': icon = '⚑'; break;   // ⚑ unfinished-turn warning
    // `queued` keeps the SAME marker as a user message: it is a user message, just
    // not sent yet. Its pending state is shown by the colour (gray) and the queue
    // pane below, not by a different glyph.
    case 'queued': icon = '❯'; break;
    case 'steer': icon = '❯'; break;
    // A skill activation is its own kind of row, not a user message: kimi prints
    // `▶ Activated skill: <name>` with the user's args dim underneath, and that is
    // what makes it clear a SKILL ran rather than the user having typed a slash
    // command. See the `skill` branch below for the body.
    case 'skill': icon = '▶'; break;
    // A pasted image is its own row type: the marker says what was pasted, and the
    // picture (when the terminal can draw one) follows it.
    case 'image': icon = '▣'; break;
    case 'aborted': icon = ''; break;
    default: icon = '';
  }
  const prefix = icon ? icon + ' ' : ''; // Restore original: no extra blank column
  const preW = visualCol(prefix);
  const contPad = ' '.repeat(preW);
  const bodyW = Math.max(1, width - preW);
  const fg = msgColorFor(msg.role, msg.text);
  // The marker keeps the theme colour (cyan) while a USER message renders its
  // text in white — the whole line used to inherit the role colour, so user
  // text came out cyan too. `indColor` colours the marker only.
  const indColor = msg.role === 'user' ? C.cyan : msg.role === 'bash' ? C.shellMode : fg;
  const bodyFg = msg.role === 'user' ? C.white : msg.role === 'bash' ? C.shellMode : fg;
  const codeFg = C.cyan;
  const lines = [];
  // 'rich' panels already contain their own ANSI; emit each source line VERBATIM
  // (raw), because wrapWords would treat the escape bytes as text and shred them.
  if (msg.role === 'rich') {
    for (const raw of String(msg.text || '').split('\n')) {
      lines.push({ text: raw, ind: '', raw: true });
    }
    if (lines.length === 0) lines.push({ text: '', ind: '', raw: true });
    return lines;
  }
  // A SKILL activation: kimi's card is
  //     ▶ Activated skill: <name>
  //       <the user's args, dim>
  // The args line is omitted when there are none. `msg.text` is only the NAME and
  // `msg.args` the trailing text, so the body is built here rather than wrapped.
  if (msg.role === 'skill') {
    lines.push({ text: prefix + 'Activated skill: ' + C.bold + String(msg.text || ''), ind: '', color: C.blue });
    const args = String(msg.args || '').trim();
    if (args) {
      const w = Math.max(1, width - 2);
      for (const seg of wrapWords(args, w)) lines.push({ text: seg, ind: '  ', color: C.gray });
    }
    return lines;
  }
  // A pasted IMAGE. The row NAMES the file: that is the receipt for what the model received,
  // and it is the only thing shown, because the terminal is not asked to draw a picture.
  if (msg.role === 'image') {
    const file = String(msg.image || msg.text || '');
    const label = file ? file.split(/[\\/]/).pop() : 'image';
    lines.push({ text: prefix + label, ind: '', color: fg });
    return lines;
  }
  // A collapsible PLUGIN LOG: collapsed shows the single summary line already in
  // `msg.text`; expanded shows `msg.allLines` (one per notice). Ctrl+L flips
  // `msg.expanded`. Rendered as plain lines with a continuation indent, so an
  // expanded block still reads as one message.
  if (msg.pluginLog) {
    const src = msg.expanded && Array.isArray(msg.allLines) ? msg.allLines : [String(msg.text || '')];
    src.forEach((line) => {
      for (const ln of wrapWords(expandTabs(String(line)), bodyW)) {
        // Marker on the first row only; every later line gets the continuation pad.
        const firstRow = lines.length === 0;
        lines.push({ text: ln, ind: firstRow ? prefix : contPad, color: firstRow ? bodyFg : C.gray });
      }
    });
    if (!lines.length) lines.push({ text: '', ind: prefix, color: bodyFg });
    return lines;
  }
  // Only assistant/thinking output benefits from Markdown; user/system/tool
  // stay plain so their text is never mangled. Assistant text should be WHITE by default.
  const useMd = msg.role === 'assistant';
  if (useMd) {
    // Split into the STABLE head (already-complete blocks) and the growing tail.
    // The head's wrapped lines are cached on the message, so a streaming frame only
    // wraps the tail block instead of the entire reply. Without this the whole
    // accumulated text was re-wrapped every frame (measured ~10ms at 40 KB, which
    // stalls the 80ms animation tick).
    const { headRows, tailRows, headCut } = renderMdIncremental(msg, String(msg.text || ''), bodyW, fg, codeFg);
    const c = msg._mdCache;
    let headWrapped = c && c.headWrapped;
    if (!headWrapped || c.headWrappedCut !== headCut) {
      // ONLY the first row of the whole message carries the `❯` marker; every later
      // row uses the continuation pad. Using `prefix` for every head row put a `❯`
      // on each line of the message.
      headWrapped = headRows.map((ml, i) => ({ text: ml, ind: i === 0 ? prefix : contPad, raw: true }));
      if (c) { c.headWrapped = headWrapped; c.headWrappedCut = headCut; }
    }
    for (const w of headWrapped) lines.push(w);
    const tailBase = lines.length;
    tailRows.forEach((ml, i) => {
      lines.push({ text: ml, ind: (tailBase === 0 && i === 0) ? prefix : contPad, raw: true });
    });
    if (!lines.length) lines.push({ text: '', ind: prefix, color: fg });
  } else {
    let code = false;
    for (const raw of expandTabs(String(msg.text || '')).split('\n')) {
      if (raw.trimStart().startsWith('```')) { code = !code; continue; }
      if (code) lines.push({ text: raw.slice(0, bodyW), ind: contPad, color: codeFg });
      else {
        for (const ln of wrapWords(raw, bodyW)) {
          // The marker is emitted only for the message's FIRST row. Using a
          // per-source-line index repeated `❯` on every line of a multi-line
          // message.
          const firstRow = lines.length === 0;
          lines.push({ text: ln, ind: firstRow ? prefix : contPad, color: bodyFg, indColor: firstRow ? indColor : undefined });
        }
      }
    }
  }
  if (lines.length === 0) lines.push({ text: '', ind: prefix, color: fg });
  return lines;
}

// Block-level Markdown renderer. Produces pre-styled rows (each carries its own
// ANSI). Supports: headings, thematic breaks, blockquotes, unordered/ordered and
// INCREMENTAL markdown for a STREAMING assistant message.
//
// While a reply streams, `msg.text` grows every frame, and re-parsing the WHOLE
// accumulated text each time measured 5ms/frame at 10 KB and ~20ms at 50 KB — a
// visible stall at the 80ms tick ("the spinner freezes while it types").
//
// The unit of reuse is a top-level BLOCK: a run of lines up to the next blank line
// that is not inside a code fence, with the blank lines attached to the FOLLOWING
// block. Rendering block-by-block and concatenating produces byte-identical output
// to rendering the whole document (verified across headings, lists, fenced code,
// multiple fences, and consecutive blank lines), which is what makes the cache
// safe. Only the LAST block can still be growing, so only it is re-rendered.
//
// (An earlier attempt cut the text at a blank line and rendered head/tail
// separately. That is NOT equivalent — a trailing blank line contributes a row on
// its own but acts as a separator inside the whole document — so the two renders
// disagreed by a row. Blocks avoid the problem entirely.)
export function renderMdIncremental(msg, text, width, fg, codeFg) {
  const src = text.replace(/\r\n/g, '\n');
  let c = msg._mdCache;
  // Layout identity: same width/colours and the same text. Comparing the text (not
  // just its length) is required — a same-length replacement must re-render.
  if (c && c.width === width && c.fg === fg && c.codeFg === codeFg && c.text === src) {
    return { headRows: c.headRows, tailRows: c.tailRows, headCut: c.headCut };
  }
  if (!c || c.width !== width || c.fg !== fg || c.codeFg !== codeFg) {
    c = msg._mdCache = { width, fg, codeFg };
  }

  const parts = splitBlocks(src);
  // A block is final once a LATER block exists; the last one is still growing.
  const headCount = Math.max(0, parts.length - 1);
  const canReuse = Array.isArray(c.blocks)
    && Array.isArray(c.blockTexts)
    && c.blockTexts.length >= headCount
    && parts.length >= headCount
    && c.blockTexts.slice(0, headCount).every((t, i) => t === parts[i]);

  const blocks = canReuse ? c.blocks.slice(0, headCount) : parts.slice(0, headCount).map((b) => renderMdText(b, width, fg, codeFg));
  const headRows = [];
  for (const b of blocks) for (const r of b) headRows.push(r);
  const tailRows = renderMdText(parts.length ? parts[parts.length - 1] : '', width, fg, codeFg);
  const headCut = parts.length > 1 ? parts.slice(0, headCount).join('\n').length : 0;

  msg._mdCache = {
    text: src, width, fg, codeFg,
    blocks, blockTexts: parts.slice(0, headCount),
    headRows, tailRows, headCut,
  };
  return { headRows, tailRows, headCut };
}

// Split at blank lines OUTSIDE a fence. The blank line(s) begin the NEXT block, so
// every block renders the same whether or not later blocks exist — that is the
// property the incremental cache depends on.
export function splitBlocks(src) {
  if (src === '') return [''];
  const lines = src.split('\n');
  const out = [];
  let cur = [];
  let fence = false;
  for (const ln of lines) {
    const isFence = /^\s*(```+|~~~+)/.test(ln);
    const blank = ln.trim() === '';
    if (blank && !fence) {
      if (cur.length) { out.push(cur); cur = []; }
      cur.push(ln);
      continue;
    }
    if (isFence) fence = !fence;
    cur.push(ln);
  }
  if (cur.length) out.push(cur);
  return out.map((b) => b.join('\n'));
}

export function renderMdText(text, width, fg, codeFg) {
  const src = String(text).replace(/\r\n/g, '\n');
  const para = src.split('\n');
  const out = [];
  let i = 0;
  const isTableSep = (l) => /^\s*\|?\s*:?-{2,}.*\|/.test(l) || /^\s*\|[-: ]+\|/.test(l);
  const splitCells = (l) => {
    const s = l.trim().replace(/^\|/, '').replace(/\|$/, '');
    return s.split('|').map((c) => c.trim());
  };

  while (i < para.length) {
    let line = para[i];
    const t = line.replace(/\s+$/, '');
    // Fenced code block. Rendered with a rule ABOVE (labelled with the language)
    // and a matching full-width rule BELOW, so the block is visibly delimited.
    const fm = /^\s*(```+|~~~+)\s*(\S*)/.exec(t);
    if (fm) {
      const lang = fm[2] || '';
      i++;
      const buf = [];
      while (i < para.length && !/^\s*(```+|~~~+)/.test(para[i])) { buf.push(para[i]); i++; }
      i++; // closing fence
      const rule = (s) => col(s, C.gray);
      // Opening rule: `─ <lang> ` then `─` padding out to the FULL width.
      // (The old version subtracted 4 and was 2 columns short of the panel.)
      if (lang) {
        const head = `\u2500 ${lang} `;
        out.push(rule(head + '─'.repeat(Math.max(1, width - visualCol(head)))));
      } else {
        out.push(rule('─'.repeat(Math.max(1, width))));
      }
      // Fenced code block CONTENT is plain body text — render it in the
      // default terminal colour (white), not the theme's cyan. The cyan is
      // reserved for UI chrome and the language label; a large code block in
      // cyan reads as "everything is the theme colour" (matches the "assistant
      // text should be white" requirement).
      for (const cl of buf) out.push(col(cl.slice(0, width), C.white));
      // Closing rule, matching the opening one.
      out.push(rule('─'.repeat(Math.max(1, width))));
      continue;
    }
    // Table: a header line followed by a separator line
    if (t.includes('|') && i + 1 < para.length && isTableSep(para[i + 1])) {
      const header = splitCells(t);
      const sep = splitCells(para[i + 1]);
      const body = [];
      i += 2;
      while (i < para.length && para[i].trim().includes('|') && !isTableSep(para[i])) { body.push(splitCells(para[i])); i++; }
      renderTable(out, header, body, sep.length, width, fg);
      continue;
    }
    // Fall through to single-line renderer
    const rows = markdownLineToRows(t, width, fg, codeFg, false);
    out.push(...rows);
    i++;
  }
  return out;
}

// Render a Markdown table as aligned columns. Header bolded, rows readable.
function renderTable(out, header, body, colCount, width, fg) {
  const cols = Math.max(header.length, colCount, ...body.map((r) => r.length));
  const B = C.border;
  const val = (r, c) => (r && r[c] !== undefined ? String(r[c]) : '');
  // Per-column natural width (visual columns), reserving 2 padding each side.
  const natural = Array.from({ length: cols }, (_, c) => {
    let m = 0;
    const consider = (v) => { m = Math.max(m, visualCol(v)); };
    consider(val(header, c));
    for (const r of body) consider(val(r, c));
    return m;
  });
  // Cap total table width to the available width (minus borders).
  const availInner = Math.max(cols, width - (cols + 1));
  const totalNatural = natural.reduce((a, b) => a + 2 + b, 0);
  let widths;
  if (totalNatural <= availInner) {
    widths = natural;
  } else {
    // Scale down proportionally, but never below 1.
    const over = totalNatural - availInner;
    const surplus = natural.reduce((a, b) => a + (b > 1 ? b - 1 : 0), 0) + cols * 1;
    widths = natural.map((n) => {
      const shrink = over > 0 ? Math.min(n - 1, Math.round((n - 1) * (over / Math.max(1, surplus)))) : 0;
      return Math.max(1, n - shrink);
    });
  }
  // Render one row; bold for the header.
  const oneRow = (cells, bold, onlyCells) => {
    const parts = [];
    for (let c = 0; c < cols; c++) {
      const v = val(cells, c);
      const cell = ' ' + v + ' '.repeat(Math.max(0, widths[c] - visualCol(v))) + ' ';
      parts.push(bold ? col(cell, C.white + C.bold) : col(cell, C.gray));
    }
    out.push(col('│', B) + parts.join(col('│', B)) + col('│', B));
  };
  out.push(col('╭' + widths.map((w) => '─'.repeat(w + 2)).join('┬') + '╮', B));
  oneRow(header, true);
  out.push(col('├' + widths.map((w) => '─'.repeat(w + 2)).join('┼') + '┤', B));
  for (const r of body) oneRow(r, false);
  out.push(col('╰' + widths.map((w) => '─'.repeat(w + 2)).join('┴') + '╯', B));
}
function markdownLineToRows(line, width, fg, codeFg, isContinuation) {
  const out = [];
  const t = line.replace(/\s+$/, '');

  // Headings: `# 标题`
  let m = /^(\s*)(#{1,6})\s+(.*)$/.exec(t);
  if (m && !isContinuation) {
    const hashCount = m[2].length;
    // h1 is bold white, h2 is plain white, h3+ is gray. Only h1 carries BOLD.
    const size = hashCount === 1 ? C.white + C.bold : hashCount === 2 ? C.white : C.gray;
    for (const w of wrapWords(m[3], width)) {
      out.push(col(w, size));
    }
    return out;
  }
  // Thematic break
  if (/^\s*(-{3,}|\*{3,}|_{3,})$/.test(t)) {
    out.push(col('─'.repeat(Math.min(width, Math.max(8, width))), C.gray));
    return out;
  }
  // Blockquote
  if (/^\s*>\s?/.test(t)) {
    const content = t.replace(/^\s*>\s?/, '');
    for (const w of wrapWords(content, Math.max(1, width - 2))) {
      out.push(col('▍' + w, C.gray));
    }
    return out;
  }
  // Unordered/ordered list — bold the bullet, keep content plain. Also handles
  // task checkboxes `- [ ] xxx` / `- [x] xxx`.
  {
    const task = /^(\s*)([-*+]\s+)?\[( |x|X)\]\s+(.*)$/.exec(t);
    if (task && !isContinuation) {
      const checked = task[3] !== ' ';
      const box = checked ? col('✓', C.green) : col('○', C.gray);
      const content = col(' ' + inlineMarkdown(task[4], codeFg, fg), fg);
      for (const w of wrapWords(task[4], Math.max(1, width - 4))) {
        out.push(col('  ', C.gray) + box + (w === task[4] ? content : col(' ' + w, fg)));
      }
      return out;
    }
    const li = /^(\s*)([-*+]|\d+[.)])\s+(.*)$/.exec(t);
    if (li && !isContinuation) {
      const isOrdered = /^\d/.test(li[2]);
      const bullet = isOrdered ? col(li[2], C.cyan) : col('•', C.cyan);
      const pad = isOrdered ? ' '.repeat(visualCol(li[2])) + ' ' : '  ';
      let first = true;
      for (const w of wrapWords(inlineMarkdown(li[3], codeFg, fg), Math.max(1, width - 2))) {
        out.push((first ? col('', C.gray) + bullet + ' ' : col(pad, C.gray)) + col(w, fg));
        first = false;
      }
      return out;
    }
  }
  // Inline styles: **bold**, *italic*, `code`, [text](url)
  if (/[*`\[]/.test(t)) {
    for (const w of wrapWords(t, width)) out.push(col(inlineMarkdown(w, codeFg, fg), fg));
    return out;
  }
  // Plain - apply default foreground color
  for (const w of wrapWords(t, width)) out.push(col(w, fg));
  return out;
}

// Apply inline markdown to a single line: `code`, **bold**, *italic*, ~~strike~~,
// [text](url). Order matters so inner tokens are handled safely.
// `base` is the surrounding foreground colour; every inline style re-asserts it
// after its own reset, otherwise the bare `\e[0m` would cancel the base colour
// for the REST of the line (plain text after a **bold** run used to lose its
// colour and fall back to the terminal default).
function inlineMarkdown(s, codeFg, base) {
  const fb = base || '';
  let r = s;
  // Inline code first so it is not mangled by * [] ~.
  r = r.replace(/`([^`]+)`/g, (_, c) => col(c, codeFg) + fb);
  // Bold
  r = r.replace(/\*\*([^*]+)\*\*/g, (_, c) => C.bold + c + C.reset + fb);
  // Strikethrough
  r = r.replace(/~~([^~]+)~~/g, (_, c) => '\x1b[9m' + c + '\x1b[29m');
  // Italic
  r = r.replace(/(^|[^*])\*([^*\s][^*]*?)\*(?!\*)/g, (_, pre, c) => pre + '\x1b[3m' + c + '\x1b[23m');
  // Links: [text](url) -> text (cyan); autolink bare http(s) urls
  r = r.replace(/\[([^\]]+)\]\(([^)]+)\)/g, (_, txt) => col(txt, C.cyan) + fb);
  r = r.replace(/(^|\s)(https?:\/\/[^\s]+)/g, (_, pre, url) => pre + col(url, C.cyan));
  return r;
}

// Flatten chat buffer into visible colored lines.
// Render the chat to display lines. Each message caches its rendered rows keyed
// by (text, width, expanded) so streaming — which only changes the LAST message
// — does not re-wrap the entire transcript on every frame. Same idea as kimi's
// per-component render cache; it is what lets high-throughput models stream
// without the UI burning CPU re-rendering old messages.
// ---- Codewhale-style rendering ----
// Each transcript line is a Line: { spans: [ {content, color}, ... ] }.
// Selection is applied to the SPANS INSIDE each line; the number of lines
// never changes. This keeps scrollbar `total` and the mouse lineIdx mapping
// stable (the previous one-span-per-line splice model renumbered lines and
// desynchronised both).

function span(text, color) { return { content: text, color: '' + (color || '') }; }

// Merge the selection background into a span's colour string. Codewhale uses
// Ratatui's `Style::patch` which COMPOSES background + existing foreground
// rather than replacing the foreground. We prepend the selection background
// and preserve whatever foreground the span already carries.
function selStyled(color) { return C.selBg + (color || ''); }

// Apply a selection range to one line's spans (Codewhale apply_selection_to_line).
// Returns a NEW array of spans; the caller replaces the line's spans. `col_start`
// and `col_end` are in visual columns; `usize::MAX` = Infinity for the tail.


// Convert a single messageLines row into a Line ({spans:[...]}).
function rowToLine(r) {
  const ind = r.ind || '';
  const body = r.text || '';
  // If raw, text already has ANSI codes; otherwise apply color.
  // `indColor` colours only the indent/marker, so a user row can show a cyan
  // `❯` with white message text.
  if (r.raw) return ind + body;
  if (r.indColor && ind) {
    const tail = r.color ? (r.color + body + C.reset) : body;
    return r.indColor + ind + C.reset + tail;
  }
  const text = ind + body;
  if (r.color) return r.color + text + C.reset;
  return text;
}

// Pull the string values that are ALREADY complete out of a partially streamed
// JSON argument blob, so a tool row can render its key argument while the model
// is still emitting it. Only complete `"key":"value"` pairs are returned.
//
// NOTE: this rescans the WHOLE blob and is O(n) per call. Callers that see one
// call per streamed chunk must use createArgStream()/feedArgStream() instead —
// see the comment there for why re-scanning freezes the UI.
function extractPartialArgs(raw, prev) {
  const out = { ...(prev || {}) };
  const s = String(raw || '');
  const re = /"([A-Za-z_][\w-]*)"\s*:\s*"((?:[^"\\]|\\.)*)"/g;
  let m;
  while ((m = re.exec(s)) !== null) {
    const key = m[1];
    const val = m[2]
      .replace(/\\n/g, '\n').replace(/\\r/g, '\r').replace(/\\t/g, '\t')
      .replace(/\\"/g, '"').replace(/\\\\/g, '\\');
    out[key] = val;
  }
  return out;
}

// Incremental scanner for a streamed JSON arguments blob.
//
// WHY THIS EXISTS: a tool call's arguments arrive in many small chunks, and the
// TUI used to re-parse the ENTIRE accumulated blob on every chunk — one full
// regex pass (extractPartialArgs) plus one full character-by-character decode
// (extractJsonString) per chunk. That is O(n²) in the argument size, all of it
// synchronous on the main thread between network reads, so the UI could not
// repaint. Measured: streaming a 500 KB Write cost ~5.2 s of blocked main
// thread, and a larger one hung the process.
//
// This scanner walks the blob ONCE: every character is consumed exactly once,
// across all chunks, and the state carries forward. Closed pairs land in
// `pairs`; the value still being read is available via argStreamValue() so a
// Write can show its content live. Only flat string args are tracked, which is
// all the tool schemas use and all the display reads.
export function createArgStream() {
  return {
    pairs: {},       // complete "key":"value" pairs
    mode: 'seekKey', // seekKey | inKey | seekColon | seekVal | inVal
    key: '',
    cur: '',         // key whose value is currently being read
    val: '',
    esc: false,      // previous char was a backslash inside a string
    uni: null,       // non-null while collecting the 4 hex digits of \uXXXX
    // Newlines in the value currently being read (or, once closed, in the pair
    // stored under `lastKey`). Maintained as the value is decoded so the live
    // Write preview never has to re-scan the whole content to count lines.
    valLines: 1,
    lastKey: '',
    lastKeyLines: 1,
  };
}

const ARG_ESCAPES = { n: '\n', t: '\t', r: '\r', b: '\b', f: '\f', '"': '"', '\\': '\\', '/': '/' };

// Feed one chunk into the stream. Returns the stream for chaining.
export function feedArgStream(st, chunk) {
  const s = String(chunk == null ? '' : chunk);
  if (!st || !s) return st;

  for (let i = 0; i < s.length; i++) {
    const c = s[i];
    if (st.mode === 'seekKey') {
      if (c === '"') { st.mode = 'inKey'; st.key = ''; }
      continue;
    }
    if (st.mode === 'inKey') {
      if (st.esc) { st.key += c; st.esc = false; continue; }
      if (c === '\\') { st.esc = true; continue; }
      if (c === '"') { st.mode = 'seekColon'; continue; }
      st.key += c;
      continue;
    }
    if (st.mode === 'seekColon') {
      if (c === ':') { st.mode = 'seekVal'; continue; }
      if (/\s/.test(c)) continue;
      // A quoted string that is NOT followed by `:` is not a key — it is an array
      // element such as `["x"]`. Abandon it and re-scan this char in seekKey so
      // the scan stays in sync (the original flat regex never matched those, and
      // treating one as a key desynced everything after it).
      st.mode = 'seekKey';
      i--;
      continue;
    }
    if (st.mode === 'seekVal') {
      if (/\s/.test(c)) continue;
      if (c === '"') { st.mode = 'inVal'; st.val = ''; st.cur = st.key; st.valLines = 1; continue; }
      // A non-string value (number/bool/null/object/array). We do not track those,
      // so resume scanning for the next key. Every char is still consumed once.
      st.mode = 'seekKey';
      continue;
    }
    // mode === 'inVal'
    if (st.uni !== null) {
      st.uni += c;
      if (st.uni.length === 4) {
        const cp = parseInt(st.uni, 16) || 0;
        st.val += String.fromCharCode(cp);
        if (cp === 10) st.valLines++;
        st.uni = null;
      }
      continue;
    }
    if (st.esc) {
      st.esc = false;
      if (c === 'u') { st.uni = ''; continue; }
      const dec = ARG_ESCAPES[c] !== undefined ? ARG_ESCAPES[c] : c;
      st.val += dec;
      if (dec === '\n') st.valLines++;
      continue;
    }
    if (c === '\\') { st.esc = true; continue; }
    if (c === '"') {
      st.pairs[st.cur] = st.val;
      st.lastKey = st.cur;
      st.lastKeyLines = st.valLines;
      st.cur = ''; st.val = '';
      st.mode = 'seekKey';
      continue;
    }
    // Fast path: copy the whole run of ordinary characters (no quote, backslash
    // or newline) in ONE slice instead of char by char. Most of a streamed value
    // is plain text, and this is what keeps a multi-MB Write from pinning the
    // main thread in the per-character loop.
    {
      let j = i;
      while (j < s.length) {
        const cj = s.charCodeAt(j);
        if (cj === 34 /* " */ || cj === 92 /* \ */ || cj === 10 /* \n */) break;
        j++;
      }
      if (j > i) { st.val += s.slice(i, j); i = j - 1; continue; }
    }
    st.val += c;
    if (c === '\n') st.valLines++;
  }
  return st;
}

// The value of `key` — the completed one when the pair has closed, otherwise the
// partial text decoded so far (which is what a live Write preview needs).
export function argStreamValue(st, key) {
  if (!st) return '';
  if (Object.prototype.hasOwnProperty.call(st.pairs, key)) return st.pairs[key];
  if (st.mode === 'inVal' && st.cur === key) return st.val;
  return '';
}

// Line count of `key`'s value, tracked incrementally (no re-scan). Used by the
// streaming Write preview for its "… N more lines" note.
export function argStreamLineCount(st, key) {
  if (!st) return 1;
  if (st.mode === 'inVal' && st.cur === key) return st.valLines;
  if (st.lastKey === key) return st.lastKeyLines;
  const v = argStreamValue(st, key);
  if (!v) return 1;
  let n = 1;
  for (let i = 0; i < v.length; i++) if (v.charCodeAt(i) === 10) n++;
  return n;
}

// Cheap fingerprint of a string for render-cache keys.
//
// It must NOT index or slice a LARGE string: `argStreamValue()` returns a cons
// string built by repeated `+=`, and any read beyond `.length` forces V8 to
// FLATTEN the whole rope — O(n). Doing that once per streamed chunk is O(n²) and
// measured at ~4.5 s for a 10 MB Write, which is exactly the main-thread block
// this fix exists to remove.
//
// So: small strings are embedded verbatim (accurate); large ones are represented
// by their LENGTH only, which is O(1) even on a cons string. That is sufficient
// here because every string keyed this way is append-only while it is being
// streamed (assistant text and a Write's content only ever grow), and is written
// once when a turn completes. A large equal-length replacement does not occur on
// these fields — the diff/content that can change arbitrarily live elsewhere.
// Fingerprint memo. `fp()` used to build `${len}:${text}` for every field of
// every message on EVERY frame — for a 3.4k-message transcript the key strings
// alone measured ~60ms per frame, which starved the 80ms animation tick and
// made the startup animation visibly stall. Text fields change rarely, so the
// fingerprint is memoised per string VALUE: the same immutable string returns
// the same fingerprint without re-measuring. The map is bounded so a long
// session with ever-growing streamed text cannot grow it without limit.
const FP_VERBATIM_MAX = 4096;
const FP_CACHE_MAX = 8192;
const fpCache = new Map();
function fp(s) {
  if (s == null) return '0';
  const str = typeof s === 'string' ? s : String(s);
  const hit = fpCache.get(str);
  if (hit !== undefined) return hit;
  const n = str.length;
  // Short strings keep the text inline (cheap and collision-free); long ones use
  // the length alone, as before.
  const out = n <= FP_VERBATIM_MAX ? n + ':' + str : n + ':';
  if (fpCache.size >= FP_CACHE_MAX) {
    const oldest = fpCache.keys().next().value;
    if (oldest !== undefined) fpCache.delete(oldest);
  }
  fpCache.set(str, out);
  return out;
}


// Fingerprint of a tool-args object for the render-cache key. `JSON.stringify`
// was used here and stringified EVERY argument — including a streaming Write's
// whole file content — on every frame. The rendered tool line only shows the key
// argument (see keyArgument), so hashing each value's length plus a bounded
// sample is enough to detect the change, and is O(#keys) instead of O(bytes).
function fpArgs(args) {
  if (!args || typeof args !== 'object') return '0';
  const keys = Object.keys(args);
  if (!keys.length) return '0';
  let out = '';
  for (const k of keys) {
    const v = args[k];
    out += k + '=' + (typeof v === 'string' ? fp(v) : (v === undefined ? 'u' : String(v).slice(0, 32))) + ';';
  }
  return out;
}

/**
 * The shared-store key for a rendered message.
 *
 * Built from the SAME predicates the cache-validity check below uses, because the two
 * have to agree: the key decides whether a store entry may be reused, and a disagreement
 * between them shows up as rows drawn for a different width or a different toggle — a
 * mis-drawn frame, not a stale one.
 *
 * The message TEXT is included, and compared by value, because a streamed reply replaces
 * `text` on every delta; a reference check would miss every reuse after the first frame.
 * The live-output fields are included for the same reason: tool arguments and partial
 * results change without `text` changing.
 *
 * `id` is the message identity rather than its index, so inserting or removing a message
 * (which compaction and /undo both do) does not shift every later key onto a different
 * entry. The row COUNT memo stays index-based on purpose — that is a different lifetime.
 */
function lruKeyFor(m, rowWidth, expanded, spinKey, state) {
  return makeRowKey({
    id: `${m.role}:${m.toolName || ''}` + (m.toolCallId ? `:${m.toolCallId}` : ''),
    text: [m.text, m.streamContent, m.liveOutput, m.diff, m._diffCounts,
      m.toolArgs ? fpArgs(m.toolArgs) : ''].map((v) => String(v == null ? '' : v)).join('\u0000'),
    w: rowWidth,
    fg: m.role,
    codeFg: state.shimmerEdge || (state.cfg && state.cfg.shimmerEdge) || 0,
    expanded: m.pluginLog ? !!m.expanded : expanded,
    raw: !!state.rawMode,
    pending: !!m.pending,
    failed: !!m.failed,
    theme: currentTheme(),
    spin: spinKey,
  });
}

export function renderChatLines(state, w, viewport) {
  const out = [];
  const expanded = !!state.expanded;
  const PAD = ' ';
  const padW = visualCol(PAD);
  const innerW = Math.max(1, w - padW);
  // Reduced motion swaps the rotating glyph for a breathing dot, so this is the one
  // place the substitution is decided for the whole transcript.
  const spinFrame = spinnerFrame(state).glyph;
  const chat = state.chat;
  const n = chat.length;

  // Pass 1: exact row count per message (and the total). Every message's cache
  // is validated/rebuilt here so the counts are exact; only the STRING assembly
  // is limited to the visible window.
  // Two ADJACENT bordered messages share a wall: the previous box's bottom rule
  // doubles as this one's top rule, so it contributes ONE row less than a
  // standalone box. Pass 2 skips that top rule when drawing, so the count here
  // has to skip it too — counting 2 rules unconditionally made `total` one row
  // bigger per shared wall than the rows actually pushed, so every absolute row
  // index after the first shared wall pointed further down the transcript than
  // the row drawn there, and a drag copied messages the user never selected.
  let prevBordered = false;
  let rowStart;
  let msgLen;
  let cursor = 0;
  // Reuse the previous paint's metrics when the transcript and layout are
  // unchanged. Scrolling changes NEITHER, so a scroll frame can skip the O(n)
  // walk entirely — pass 1 exists to learn each message's row count, and that
  // cannot change just because the viewport moved.
  const mem = state._metrics;
  const sig = (mem && mem.w === w && mem.expanded === expanded && mem.innerW === innerW)
    ? metricsSignature(state, n, w, expanded, innerW) : 0;
  if (mem && sig && mem.sig === sig) {
    rowStart = mem.rowStart;
    msgLen = mem.msgLen;
    cursor = mem.total;
    prevBordered = mem.prevBordered;
  } else {
  rowStart = new Int32Array(n);
  msgLen = new Int32Array(n);
  for (let mi = 0; mi < n; mi++) {
    const m = chat[mi];
    const border = m.role === 'user' || m.role === 'queued' || m.role === 'bash';
    const ww = border ? Math.max(1, Math.min(1, innerW - 4)) : innerW; // placeholder
    void ww;
    rowStart[mi] = cursor;
    const rules = border ? (prevBordered ? 1 : 2) : 0;
    // Reuse/minimal layout for the row count: same width/border arithmetic as
    // the layout path below. We need boxText for bordered messages.
    const boxInner = Math.max(1, innerW - 4);
    const boxText = Math.max(1, boxInner - Math.min(1, Math.max(0, boxInner - 1)) * 2);
    const rowWidth = border ? boxText : innerW;
    const cached = m._cache;
    // Which rows animate? A pending tool call and a running compaction block both
    // derive their look from `state.spin`, so the cached layout must be invalidated
    // when that tick advances. Setting spinKey to 0 for everything else keeps
    // static rows cached across ticks.
    const animating = (m.role === 'tool' && m.pending) || (m.role === 'compaction' && m.phase === 'running');
    const spinKeyNow = animating ? (state.spin || 0) : 0;
    const valid = cached
      && cached.rowW === rowWidth && cached.expanded === expanded
      && cached.textRef === m.text && cached.streamRef === m.streamContent
      && cached.liveRef === m.liveOutput && cached.failed === m.failed
      && cached.diffRef === m.diff && cached.countsRef === m._diffCounts
      && cached.keyArgs === (m.toolArgs ? fpArgs(m.toolArgs) : '0')
      && cached.spinKey === spinKeyNow
      // The collapsible plugin log renders from `m.expanded` + `m.allLines`, which
      // the cache key must include: otherwise Ctrl+L only flipped the flag and the
      // cached (collapsed) rows were reused, so nothing visibly changed.
      && cached.pluginExpanded === (m.pluginLog ? !!m.expanded : null)
      && cached.isPending === (m.pending ? 1 : 0)
      // /raw changes how an assistant row is built, so the cache must be invalidated
      // when it flips — otherwise the old Markdown rows are reused and the toggle
      // appears to do nothing.
      && cached.raw === !!state.rawMode
      // THE PALETTE. Every cached row is finished text, escapes included, so a theme
      // change has to invalidate all of them. Without this the chrome repainted (it is
      // composed per frame) while the assistant's own text kept the OLD colours — white
      // words left sitting in a gruvbox palette after a switch. `auto` resolves to a
      // concrete name, so following the terminal is caught too.
      && cached.theme === currentTheme();
    // An evicted message keeps only `m._count`. When its layout key still matches,
    // the row count is known, so the message is counted WITHOUT re-rendering it —
    // which is the whole point of keeping the count separate from the rows (an idle
    // 2000-message transcript was re-rendering ~7700 messages per frame otherwise).
    // The key is a NUMBER, not a string. Building `rowWidth + '|' + ...` for every
    // message on every frame allocated one string per message, which profiled at
    // ~1.15ms/frame on an 8000-message transcript — 6x the arithmetic below, and
    // pure garbage for the collector.
    const countKey = rowWidth * 8 + (expanded ? 1 : 0) + (m.pending ? 2 : 0) + (m.pluginLog && m.expanded ? 4 : 0)
      + (state.rawMode ? 16 : 0);
    if (!valid && !cached && m._count && m._count.key === countKey) {
      msgLen[mi] = m._count.len + rules;
      cursor += msgLen[mi];
      prevBordered = border;
      continue;
    }
    if (valid) {
      msgLen[mi] = cached.rows.length + rules;
    } else {
      // Before re-rendering, ask the SHARED store. This is the path that makes the
      // store worth having: a message whose local cache was dropped, or one rebuilt by a
      // session switch, lands here with no local entry and used to re-wrap its rows from
      // scratch. Now it costs one Map lookup.
      const shared = rowCacheGet(lruKeyFor(m, rowWidth, expanded, spinKeyNow, state));
      if (shared && shared.rowW === rowWidth && shared.expanded === expanded
        && shared.spinKey === spinKeyNow && shared.isPending === (m.pending ? 1 : 0)
        && shared.raw === !!state.rawMode
        // The content fields are compared by REFERENCE here, exactly as in the local
        // check above: they are only equal if nothing rewrote them, and the key already
        // covered the value-level ones. Anything the key does not name is checked here, so
        // the two together cover every input the render reads.
        && shared.textRef === m.text && shared.streamRef === m.streamContent
        && shared.liveRef === m.liveOutput && shared.diffRef === m.diff
        && shared.countsRef === m._diffCounts
        && shared.keyArgs === (m.toolArgs ? fpArgs(m.toolArgs) : '0')
        && shared.pluginExpanded === (m.pluginLog ? !!m.expanded : null)) {
        m._cache = shared;
        msgLen[mi] = shared.rows.length + rules;
      } else {
        const rows = messageLines(m, rowWidth, state.cwd, expanded, state.spin, state.pulseStart, state.rawMode,
          state.shimmerEdge || (state.cfg && state.cfg.shimmerEdge));
        const wrapped = rows.map(rowToLine);
        const isPending2 = m.pending ? 1 : 0;
        const cc = {
          // The palette is part of the key: `rows` are finished strings with their escapes
          // already in them, so a cached row cannot be re-tinted later. See the `valid` test
          // above, which compares this field against `currentTheme()`.
          theme: currentTheme(),
          rowW: rowWidth, expanded, spinKey: spinKeyNow, isPending: isPending2,
          textRef: m.text, streamRef: m.streamContent, liveRef: m.liveOutput,
          failed: m.failed, diffRef: m.diff, countsRef: m._diffCounts,
          keyArgs: m.toolArgs ? fpArgs(m.toolArgs) : '0',
          pluginExpanded: m.pluginLog ? !!m.expanded : null,
          raw: !!state.rawMode,
          rows: wrapped, spinRows: null,
        };
        for (let i = 0; i < wrapped.length; i++)
          if (wrapped[i].indexOf(SPIN_PLACEHOLDER) >= 0) {
            if (!cc.spinRows) cc.spinRows = new Set();
            cc.spinRows.add(i);
          }
        m._cache = cc;
        // The ROW COUNT is all the scroll maths needs, and it is stable for a given
        // layout key. Record it separately so an evicted message (below) still has a
        // count and never has to be re-rendered just to be counted — that re-render
        // is what made an idle 2000-message transcript cost 78ms per frame.
        m._count = { key: countKey, len: wrapped.length };
        msgLen[mi] = wrapped.length + rules;
      }
    }
    // Drop the local copy for anything far from the tail, and hand its rows to the
    // shared store first so a later pass can reuse them. Storing here rather than on the
    // way IN matters: storing on the way in and then looking the key up in the same loop
    // made the FIRST paint do the work twice for every message it had just rendered.
    if (mi < n - CACHE_KEEP && m._cache) {
      rowCacheSet(lruKeyFor(m, rowWidth, expanded, spinKeyNow, state), m._cache);
      m._cache = null;
    }
    cursor += msgLen[mi];
    prevBordered = border;
  }
  }
  const total = cursor;
  state._chatTotal = total;
  state._chatTotal = total;
  // Memo for the count-only caller (scrollChat). These metrics do NOT depend on
  // `scroll`, only on the transcript and the layout, so they stay valid until one
  // of those changes. scrollChat used to call the FULL renderer — with no viewport
  // that renders every message's rows — just to learn the total, which is what made
  // every wheel tick stall on a long transcript.
  state._metrics = {
    sig: sig || metricsSignature(state, n, w, expanded, innerW),
    w, expanded, innerW, total, rowStart, msgLen, prevBordered,
  };

  // Visible window: [total - bodyH - scroll, total - scroll), with a small
  // margin above so a message crossing the boundary renders whole. When no
  // viewport is given, render everything (full render).
  let visibleFrom = 0, visibleTo = -1;
  if (viewport && Number.isFinite(viewport.bodyH) && viewport.bodyH > 0) {
    const bodyH = viewport.bodyH;
    const maxScroll = Math.max(0, total - bodyH);
    const asked = Math.max(0, viewport.scroll || 0);

    // ---- scroll anchoring --------------------------------------------------
    // `scroll` counts rows UP from the bottom, so content ABOVE the viewport
    // growing (streamed text, a new tool row) would push what the user is reading
    // off the top of the screen. The old fix inferred that growth by comparing
    // `state._chatTotal` with the PREVIOUS paint's count — a value it read before
    // this function ran — so the correction always landed one chunk late and
    // accumulated error. The row count is exact here, so the view is anchored by
    // ROW instead: `_anchorPin` remembers the last paint's `{ total, scroll }`,
    // and the rows added above the pinned row move `scroll` by the same amount.
    //
    // `viewport.scroll` is NOT read while a pin exists: this function overwrites
    // `state.scroll`, and composeFrame() feeds that same value back in, so
    // treating it as "what the user asked for" made the anchoring self-feeding.
    // A deliberate move (wheel, drag, jump, a new message) clears the pin through
    // dropScrollPin(), and the position is taken from the caller on that paint.
    const pin = state._anchorPin;
    let scroll;
    if (pin && pin.bodyH === bodyH) {
      // The view has not been moved deliberately since the last paint, so carry
      // the anchor across the rows added above it. `pin.scroll === 0` means the
      // view is pinned to the tail and must keep following it as it grows.
      scroll = pin.scroll === 0 ? 0 : pin.scroll + (total - pin.total);
    } else {
      scroll = asked;
    }
    scroll = Math.min(maxScroll, Math.max(0, scroll));
    state.scroll = scroll;
    state._anchorPin = { total, scroll, bodyH };

    const end = total - scroll;
    const start = end - bodyH;
    visibleFrom = Math.max(0, start - 12);
    visibleTo = Math.min(total, end + 12);
  }

  // Pass 2: assemble final strings, but only for messages that overlap the
  // visible range (or the whole transcript when no viewport).
  cursor = 0;
  // The two rule strings depend ONLY on `innerW` and the box colour, and there are just
  // two colours, so each is built at most twice per frame. They used to be built for
  // EVERY bordered message BEFORE the visibility test — 2 x `'─'.repeat(114)` plus two
  // `col()` calls for all ~2000 bordered messages of an 8000-message transcript, when at
  // most a couple of dozen are ever on screen. That measured ~0.5ms/frame of allocation
  // discarded unused, and pure garbage for the collector: the same class of waste the
  // numeric `countKey` in pass 1 removed.
  const ruleCache = { top: new Map(), bot: new Map() };
  const ruleText = Math.max(1, innerW - 4);
  const rule = (top, color) => {
    const m = top ? ruleCache.top : ruleCache.bot;
    let got = m.get(color);
    if (got === undefined) {
      got = PAD + col((top ? '╭' : '╰') + '─'.repeat(ruleText) + (top ? '╮' : '╯'), color);
      m.set(color, got);
    }
    return got;
  };

  for (let mi = 0; mi < n; mi++) {
    const msg = chat[mi];
    const bordered = msg.role === 'user' || msg.role === 'queued' || msg.role === 'bash';
    const boxColor = msg.role === 'bash' ? C.shellMode : C.border;
    let boxPad = 1, boxText = innerW;
    if (bordered) {
      const boxW = innerW - 2;
      const boxInner = Math.max(1, boxW - 2);
      boxPad = Math.min(1, Math.max(0, boxInner - 1));
      boxText = Math.max(1, boxInner - boxPad * 2);
    }
    // Shared wall with the previous bordered message (its bottom rule is ours).
    let shared = false;
    if (bordered && mi > 0) {
      const prev = chat[mi - 1];
      shared = (prev.role === 'user' || prev.role === 'queued' || prev.role === 'bash')
        && rowStart[mi - 1] + msgLen[mi - 1] === cursor;
    }
    const len = msgLen[mi];
    const visible = visibleTo < 0 || (cursor + len > visibleFrom && cursor < visibleTo);
    if (visible) {
      // Pass 1 may have skipped building the rows for a message far from the
      // viewport (it only needed the row COUNT, so it used `_count`). Now that the
      // message IS visible, build them here — otherwise an evicted message rendered
      // as blank rows, which is what made scrolled-back history look like it had
      // "not loaded". The row width must match what pass 1 counted with.
      let ccc = msg._cache;
      if (!ccc || !ccc.rows || ccc.rows.length !== len - (bordered ? (shared ? 1 : 2) : 0)) {
        const bw = bordered ? boxText : innerW;
        const built = messageLines(msg, bw, state.cwd, expanded, state.spin, state.pulseStart, state.rawMode,
          state.shimmerEdge || (state.cfg && state.cfg.shimmerEdge)).map(rowToLine);
        ccc = { rows: built, spinRows: null };
        for (let i = 0; i < built.length; i++) {
          if (built[i].indexOf(SPIN_PLACEHOLDER) >= 0) {
            if (!ccc.spinRows) ccc.spinRows = new Set();
            ccc.spinRows.add(i);
          }
        }
        msg._cache = ccc;
      }
      const spinRows = ccc.spinRows;
      const liveAt = (r, i) => (spinRows && spinRows.has(i) ? r.split(SPIN_PLACEHOLDER).join(spinFrame) : r);
      if (bordered && !shared) out.push(rule(true, boxColor));
      if (bordered) {
        const pad = ' '.repeat(boxPad);
        const wall = col('│', boxColor);
        for (let i = 0; i < ccc.rows.length; i++)
          out.push(PAD + wall + pad + fitAnsi(liveAt(ccc.rows[i], i), boxText) + pad + wall);
      } else {
        for (let i = 0; i < ccc.rows.length; i++) out.push(PAD + liveAt(ccc.rows[i], i));
      }
      if (bordered) out.push(rule(false, boxColor));
    } else {
      for (let i = 0; i < len; i++) out.push('');
    }
    cursor += len;
  }
  return out;
}

// A cheap signature of everything pass 1 depends on. Values are only compared
// (never stringified per message), so this stays O(n) arithmetic with no
// allocation per message — the same reason countKey is numeric.
export function metricsSignature(state, n, w, expanded, innerW) {
  let h = 2166136261 >>> 0;
  const mix = (v) => { h ^= (v | 0); h = Math.imul(h, 16777619) >>> 0; };
  mix(n); mix(w); mix(innerW); mix(expanded ? 1 : 0); mix(state.spin || 0);
  // THE PALETTE. This signature decides whether the WHOLE transcript is walked at all, so a
  // theme switch that left it alone skipped the per-message `valid` check too — every cached
  // row kept the colours it was rendered with, which is why the chrome repainted and the
  // assistant's text did not. Hashed rather than compared by name: this is a number.
  for (let ci = 0; ci < currentTheme().length; ci++) {
    h ^= currentTheme().charCodeAt(ci);
    h = Math.imul(h, 16777619) >>> 0;
  }
  // rawMode changes every assistant row's shape, so it is part of the layout
  // identity: without this, toggling /raw left the cached rows on screen.
  mix(state.rawMode ? 1 : 0);
  const chat = state.chat;
  for (let i = 0; i < n; i++) {
    const m = chat[i];
    // Text length + identity of the mutable fields. A same-length edit is caught by
    // `m._cache` being nulled at the edit sites, so length is enough here.
    mix(i);
    mix(typeof m.text === 'string' ? m.text.length : 0);
    mix(typeof m.streamContent === 'string' ? m.streamContent.length : 0);
    mix(m.pending ? 1 : 0);
    mix(m.pluginLog && m.expanded ? 1 : 0);
    mix(m._cache ? 1 : 0);
    mix(m._count ? 1 : 0);
  }
  return h;
}

/**
 * Total transcript rows WITHOUT building a single rendered string. Reuses the
 * memo from the last renderChatLines when the transcript and layout are unchanged
 * (the scrolling case). Returns the row count.
 */
export function chatRowTotal(state, w) {
  const mem = state._metrics;
  const expanded = !!state.expanded;
  const innerW = Math.max(1, w - 1);
  const sig = metricsSignature(state, state.chat.length, w, expanded, innerW);
  if (mem && mem.sig === sig) return mem.total;
  renderChatLines(state, w);           // fills state._metrics
  return state._chatTotal || 0;
}

// ---- scroll anchoring --------------------------------------------------------
// The view is anchored by ROW inside renderChatLines(), where the exact row count
// (`total`) and the visible window are both known. `state._anchorPin` carries the
// previous paint's `{ total, scroll, bodyH }`; when the transcript grows, the
// delta is added to `scroll` so the same row stays at the top of the screen.
//
// Nothing needs to be compensated when the transcript grows — the pin just needs
// to be DROPPED whenever `scroll` is set from outside (wheel, drag, jump to
// bottom), because that is a deliberate move and the old pin no longer describes
// where the user is looking.
function dropScrollPin(state) {
  state._anchorPin = null;
}



// Serialise a Line (array of spans) to an ANSI string.
function lineToString(line) {
  let s = '';
  for (const sp of line.spans) {
    // Emit the span's colour prefix, then the content, then RESET so a
    // selection background (which carries no fg) cannot bleed into the next
    // span. Omitting the reset made a single-span line's selection highlight
    // run all the way to the right edge.
    s += sp.color + sp.content + C.reset;
  }
  return s;
}

function modeLabel(mode) {
  // One word per mode, matching the command names (/ask, /yolo, /auto) so the
  // status line, the /permission picker and /status all read the same. The old
  // long forms ("Always Ask", "Ask When Needed", "Never Ask") also wrapped the
  // status group awkwardly next to Plan/Focus.
  if (mode === 'auto') return 'Auto';
  if (mode === 'yolo') return 'Yolo';
  return 'Ask';
}

function trimDecimal(v) {
  const s = v.toFixed(1);
  return s.endsWith('.0') ? s.slice(0, -2) : s;
}

// Token counts use 1024-based units: context sizes are powers of two, so
// 262144 reads as "256k", not "262.1k". k values at or above 100 are rounded
// to whole numbers ("977k").
function fmtTokens(n) {
  n = Number(n);
  if (!Number.isFinite(n) || n < 0) return '0';
  if (n >= 1024 * 1024 * 1024) return trimDecimal(n / (1024 * 1024 * 1024)) + 'G';
  if (n >= 1024 * 1024) return trimDecimal(n / (1024 * 1024)) + 'M';
  if (n >= 1024) {
    const k = n / 1024;
    return (k >= 100 ? Math.round(k) : trimDecimal(k)) + 'k';
  }
  return String(n);
}

// Thousands separators for a plain count. fmtTokens rounds to k/M, which is right
// for a context gauge but wrong for a token BILL: "1.5M input tokens" hides
// whether that is 1.45M or 1.54M, and the cost readout next to it is precise.
function fmtCount(n) {
  const v = Number(n);
  if (!Number.isFinite(v)) return '0';
  return Math.round(v).toLocaleString('en-US');
}

// A money amount, at a precision that stays readable across five orders of
// magnitude: a single cheap request is fractions of a cent, a long session is
// dollars. A bare `0.00` for a real cost is the failure to avoid, so anything
// non-zero under a cent keeps its decimals rather than rounding away. The symbol
// is the caller's business — the status row puts it AFTER the number.
function moneyAmount(v, currency = 'USD') {
  const n = Number(v);
  if (!Number.isFinite(n)) return 'n/a';
  // CNY is about 7x USD, so the same amount crosses these thresholds one step
  // sooner; scaling the comparison keeps both currencies at the same precision.
  const scale = currency === 'CNY' ? 7 : 1;
  if (n === 0) return '0.00';
  if (n * scale < 0.01) return n.toFixed(5);
  if (n * scale < 1) return n.toFixed(4);
  return n.toFixed(2);
}

/**

/**
 * `$12.34` / `¥86.51` — the amount with its symbol in front, for a panel line
 * where there is room to spell the currency out too.
 */
function formatCost(amount, currency = 'USD') {
  const n = Number(amount);
  if (!Number.isFinite(n)) return 'unknown';
  return `${currency === 'CNY' ? '¥' : '$'}${moneyAmount(n, currency)}`;
}

// A tiny ASCII line chart for a numeric series (context growth over steps).
// Renders `height` rows; each column is one sample, scaled to the series max.
// No dependency — Claude Code pulls in `asciichart`, we do not need it.
function sparkChart(values, width, height) {
  const series = (values || []).filter((v) => Number.isFinite(v));
  if (series.length < 2) return [];
  // Downsample to `width` columns by taking evenly spaced samples.
  const cols = Math.min(width, series.length);
  const sampled = [];
  for (let i = 0; i < cols; i++) {
    sampled.push(series[Math.round(i / (cols - 1) * (series.length - 1))]);
  }
  const max = Math.max(...sampled, 1);
  const min = Math.min(...sampled, 0);
  const span = Math.max(1, max - min);
  const rows = [];
  const BLOCK = [' ', '▁', '▂', '▃', '▄', '▅', '▆', '▇', '█'];
  // Single-row sparkline.
  if (height <= 1) {
    rows.push(sampled.map((v) => BLOCK[Math.min(8, Math.round((v - min) / span * 8))]).join(''));
    return rows;
  }
  for (let r = height - 1; r >= 0; r--) {
    let line = '';
    for (const v of sampled) {
      const level = (v - min) / span * (height - 1);
      line += level >= r ? '█' : ' ';
    }
    rows.push(line);
  }
  return rows;
}

// Usage as a whole-number percentage of `max`, ceiled so any non-zero usage
// shows at least 1%, clamped to [0, 100]. A non-positive or non-finite `max`
// reports 0.
function usagePercent(used, max) {
  if (!Number.isFinite(max) || max <= 0) return 0;
  return Math.min(100, Math.max(0, Math.ceil((used / max) * 100)));
}

// The session's spend, cached on `state` for the status bar. Called wherever its
// inputs change — a usage event, a model switch, a resume, /new, a currency
// switch — and never from the render path, which has no config in scope and must
// stay cheap.
//
// Three cached fields, because the render path can only READ:
//   _costKnown   prices exist for this model at all
//   _costUsd     the amount in USD (the native unit; /cost always reports it)
//   _costText    the amount as it should be PRINTED, in the display currency
// `_costText` is null when the currency needs a rate that is not available yet;
// the row then falls back to the USD text rather than a converted guess.
export function refreshCost(state, cfg) {
  const cost = modelCost(cfg);
  const usage = state.usage || {};
  const hasUsage = !!usage.calls;
  const usd = (hasUsage && cost) ? usageCost(usage, cost) : null;
  const currency = costCurrency(cfg);
  state._costKnown = !!cost;
  state._costUsd = usd;
  state._costCurrency = currency;
  // A sync lookup only: the rate has to have been warmed already (startup, or the
  // /cost that switched the currency). Converting here would need an await.
  const fx = usd === null ? null : syncRate(currency, { override: cfgCnyPerUsd(cfg) });
  const amount = (usd === null || !fx) ? null : convert(usd, currency, fx.rate);
  state._costRate = fx ? fx.rate : null;
  // The symbol leads, the same way formatCost writes it in /cost: `$0.0523`, not
  // `0.0523$`. One spelling for the number across both readouts.
  if (amount === null) state._costText = usd === null ? null : formatCost(usd);
  else state._costText = formatCost(amount, currency);
}

// The currency the cost readouts use, from config.toml (`cost_currency`), the
// environment, or USD. Persisted by `/cost usd|cny`, so the switch survives a
// restart and the status row follows it.
export function costCurrency(cfg) {
  const fromEnv = normalizeCurrency(process.env.HNCODE_COST_CURRENCY);
  if (fromEnv) return fromEnv;
  const raw = cfg && ((cfg.raw && cfg.raw.cost_currency) ?? cfg.costCurrency);
  return normalizeCurrency(raw) || 'USD';
}

// Human-readable elapsed duration, omitting zero leading units:
//   1y 1mon 1d 1h 1min 1s  /  2y 2mon 2d 2h 2min 2s
// Units are NEVER pluralised with a trailing "s": the old code rendered 5
// minutes as "5ms", which reads as 5 MILLISECONDS (and 2 hours as "2hs").
// Minutes are "m", so months use "mon" to stay unambiguous.
function fmtDuration(ms) {
  ms = Math.max(0, Math.floor(ms));
  const sec = Math.floor(ms / 1000) % 60;
  const min = Math.floor(ms / 60000) % 60;
  const hour = Math.floor(ms / 3600000) % 24;
  const day = Math.floor(ms / 86400000) % 30;
  const mon = Math.floor(ms / 2592000000) % 12;
  const year = Math.floor(ms / 31536000000);
  const parts = [];
  if (year) parts.push(year + 'y');
  if (mon) parts.push(mon + 'mon');
  if (day) parts.push(day + 'd');
  if (hour) parts.push(hour + 'h');
  if (min) parts.push(min + 'm');
  // Seconds are always shown (at least "0s").
  parts.push(sec + 's');
  return parts.join(' ');
}

// Left/right justify: left text, then padding, then right text flush to `w`.
// ANSI codes are ignored for width so colored segments still align exactly.
// When both don't fit, the LEFT is preserved and the RIGHT (tip) is truncated.
function justify(left, right, w) {
  const lw = visualCol(left);
  const rw = visualCol(right);
  if (left && right) {
    if (lw + rw + 1 <= w) return left + ' '.repeat(w - lw - rw) + right;
    const room = w - lw - 1;
    if (room > 0) return left + ' ' + fitAnsi(right, room);
    return fitAnsi(left, w);
  }
  if (!left) return ' '.repeat(Math.max(0, w - rw)) + right;
  if (!right) return left + ' '.repeat(Math.max(0, w - lw));
  return fitAnsi(left, w);
}

// Height of the composer box (top border + content rows + bottom border).
export function composerHeight(state, cols) {
  const insideW = Math.max(0, (cols | 0) - 2);
  return composerLayout(state, insideW - 3).rows.length + 2;
}

// UNCLAMPED height of the AskUserQuestion box. `composeFrame` caps the real
// height to the space available (see `questionH`), and the renderer drops the
// hint row / scrolls the option list to fit that cap. This is therefore the
// height wanted when there IS room.
// Rows: top border + header + wrapped question + one per row + hint/entry + bottom
export function questionBoxHeight(state, insideW) {
  const qs = state.question;
  if (!qs) return 0;
  const cur = qs.items[qs.index] || { question: '', options: [] };
  const innerW = Math.max(1, insideW - 2);
  const isLast = qs.index === qs.items.length - 1;
  const optRows = (cur.options || []).length + 1 + (isLast ? 1 : 0);   // + Other (+ supplement)
  const qRows = Math.max(1, wrapWords(cur.question, Math.max(1, innerW - 2)).length);
  return 2 + 1 + qRows + optRows + 1;
}

// The height the box ACTUALLY emits, given the terminal height `h` and the rows
// already taken by other chrome. Mirrors composeFrame's cap + the renderer's
// fit logic, so geometry and painting cannot disagree.
export function questionBoxClampedHeight(state, insideW, h, chromeH) {
  const want = questionBoxHeight(state, insideW);
  if (!want) return 0;
  const cap = Math.max(1, h - chromeH - 1);
  const q = Math.min(want, cap);
  const qs = state.question;
  const cur = qs.items[qs.index] || { question: '', options: [] };
  const innerW = Math.max(1, insideW - 2);
  const isLast = qs.index === qs.items.length - 1;
  const optRows = (cur.options || []).length + 1 + (isLast ? 1 : 0);
  const qRows = Math.max(1, wrapWords(cur.question, Math.max(1, innerW - 2)).length);
  const boxBudget = q - 2 - qRows;                  // room for options (+hint)
  const showHint = boxBudget >= optRows + 1;
  const optShown = Math.min(optRows, Math.max(0, boxBudget - (showHint ? 1 : 0)));
  return 2 + qRows + optShown + (showHint ? 1 : 0);
}

// ---- scrollbar (Codewhale's TranscriptScrollbar) ---------------------------
// Geometry for a vertical scrollbar over the transcript body. `scroll` is the
// number of lines scrolled UP from the bottom (0 = pinned to newest). Returns
// the thumb's row range within the body (0-based) so the painter and the mouse
// hit-test share one source of truth.
//
// NOTE on precision: the terminal's mouse protocol reports INTEGER rows, so a
// drag can only address `bodyH` distinct positions. On a long transcript that is
// inherently coarse (100k lines over 24 rows = ~4.3k lines per row) and no
// formula fixes it — fine control comes from the wheel / keyboard instead (see
// the `sbFine` handling in handleKey). What this function DOES guarantee is that
// the thumb's travel is monotonic, uses every row, and lands exactly on both
// ends; `thumbLenF` is kept unrounded purely so the grab offset inside the thumb
// is not quantised to a whole row when the thumb is 10+ rows tall.
export function scrollbarGeometry({ total, bodyH, scroll }) {
  const maxScroll = Math.max(0, total - bodyH);
  const pos = Math.min(maxScroll, Math.max(0, scroll || 0));
  // OpenTUI works on a 2x virtual grid so the thumb has HALF-ROW resolution: each
  // real row is two virtual units, and a thumb boundary landing inside a cell is
  // drawn as `▀` (top half) or `▄` (bottom half). That is what makes a short
  // scrollbar look smooth instead of jumping a whole row at a time. See OpenTUI
  // Slider.ts: getVirtualThumbSize / getVirtualThumbStart / renderVertical.
  const virtualTrack = bodyH * 2;
  // Thumb size = viewport / (content + viewport) of the track, min one virtual unit.
  const contentSize = maxScroll + bodyH;
  const virtualThumbSize = bodyH >= total
    ? virtualTrack
    : Math.max(1, Math.min(
      Math.floor(virtualTrack * (bodyH / Math.max(1, contentSize))),
      virtualTrack,
    ));
  // 0 = bottom (pinned), maxScroll = top. Row 0 is the TOP of the body, so the
  // virtual start counts from the top (OpenTUI's value grows downward; ours
  // grows upward from the newest line, hence the inversion).
  const fromTop = maxScroll === 0 ? 0 : (maxScroll - pos) / maxScroll;
  const maxVirtualStart = Math.max(0, virtualTrack - virtualThumbSize);
  const virtualThumbStart = Math.round(fromTop * maxVirtualStart);

  // Row-range + fractional forms, kept for the drag maths and the hit-test, which
  // reason in whole rows. Derived from the virtual values so paint and drag agree.
  const thumbLenF = Math.max(1, virtualThumbSize / 2);
  const thumbStart = Math.floor(virtualThumbStart / 2);
  const thumb = Math.max(1, Math.ceil((virtualThumbStart + virtualThumbSize) / 2) - thumbStart);
  const maxThumbStartF = Math.max(0, bodyH - thumbLenF);

  return {
    thumbStart, thumbLen: thumb, thumbLenF, maxThumbStartF,
    virtualThumbStart, virtualThumbSize, virtualTrack,
    bodyH, total, maxScroll,
  };
}

// The glyph for one body row, exactly OpenTUI's per-cell rule (Slider.ts
// renderVertical): full coverage -> `█`; a half-covered cell -> `▀` when the thumb
// starts in the upper half of that cell, `▄` when it starts in the lower half;
// no coverage -> ` ` (the track shows through as its background colour).
export function scrollbarGlyph(g, row) {
  if (!g) return ' ';
  const cellStart = row * 2;
  const cellEnd = cellStart + 2;
  const start = Math.max(g.virtualThumbStart, cellStart);
  const end = Math.min(g.virtualThumbStart + g.virtualThumbSize, cellEnd);
  const coverage = end - start;
  if (coverage >= 2) return '█';
  if (coverage > 0) return (start - cellStart) === 0 ? '▀' : '▄';
  return ' ';
}

// Map a position on the track to a transcript scroll offset. `rowF` is the mouse
// row (fractional allowed) and `grabOffset` is where inside the thumb the drag
// started, in rows, so the thumb does not jump under the pointer on press.
// Exported so the drag handler and its tests share ONE definition of the mapping.
export function scrollFromThumbPos(g, rowF, grabOffset = 0) {
  if (!g) return 0;
  const track = Math.max(1e-6, g.maxThumbStartF != null
    ? g.maxThumbStartF
    : Math.max(1, g.bodyH - (g.thumbLenF != null ? g.thumbLenF : g.thumbLen)));
  const frac = Math.max(0, Math.min(1, (rowF - grabOffset) / track));
  return Math.round((1 - frac) * g.maxScroll);
}

// Paint the scrollbar glyph into the LAST column of a body row. The row already
// has exactly `w` visible columns; we replace the final one with the gutter.

// ---- mouse text selection (Codewhale-style: modify object properties, not strings) ---
// Apply selection background by modifying the color property of line objects,
// not by adding ANSI codes to strings. This preserves existing ANSI structure.
function applySelectionToRow(lines, idx, sel, w) {
  if (idx < 0) return lines;
  const a = sel.anchor, h = sel.head;
  if (!a || !h) return lines;
  const start = (h.row < a.row || (h.row === a.row && h.col < a.col)) ? h : a;
  const end = start === a ? h : a;
  if (idx < start.row || idx > end.row) return lines;
  
  let c0, c1;
  if (start.row === end.row) { 
    c0 = start.col; 
    c1 = end.col; 
  }
  else if (idx === start.row) { 
    c0 = start.col; 
    c1 = Infinity; 
  }
  else if (idx === end.row) { 
    c0 = 0; 
    c1 = end.col; 
  }
  else { 
    c0 = 0; 
    c1 = Infinity; 
  }
  
  // Apply selection background to each line object in the array
  for (const lineObj of lines) {
    // Calculate visual column position for this line object
    let col = 0;
    const text = lineObj.text || '';
    
    // Check if this line object overlaps with selection
    for (let i = 0; i < text.length; i++) {
      const cp = text.codePointAt(i);
      const ch = String.fromCodePoint(cp);
      const cw = visualWidth(ch);
      
      if (col >= c0 && col < c1) {
        // Apply selection background by setting color property
        // If already has color, merge with selection bg
        if (lineObj.color) {
          // Merge colors: keep original foreground, add selection background
          lineObj.color = C.selBg + lineObj.color;
        } else {
          lineObj.color = C.selBg;
        }
      }
      
      col += cw;
      i += cp > 0xffff ? 2 : 1;
      
      if (col >= w) break;
    }
  }
  
  return lines;
}

// Wrap the visible columns [c0, c1) of an ANSI string in the selection
// background, preserving the existing foreground colours inside the range.
// NOTE: pass (end.col + 1) as c1 — the end column is the cell under the pointer
// and is part of the selection.
function highlightAnsiRange(row, c0, c1, w) {
  const s = String(row);
  let out = '';
  let col = 0;
  let i = 0;
  let inSel = false;

  while (i < s.length) {
    if (s[i] === '\x1b') {
      // Emit the escape, then RE-ASSERT the selection background if we are
      // inside the range. The row embeds its own resets (a markdown bold or
      // inline-code span ends in ESC[0m), and a bare ESC[0m cancels the
      // background too — so without re-asserting, everything after the first
      // coloured run inside the selection lost its highlight.
      const m = /^\x1b\[[0-9;?]*[a-zA-Z]/.exec(s.slice(i)) || /^\x1b\[[0-9;?]* [a-zA-Z]/.exec(s.slice(i));
      if (m) {
        out += m[0];
        if (inSel) out += C.selBg;
        i += m[0].length;
        continue;
      }
    }

    const cp = s.codePointAt(i);
    const ch = String.fromCodePoint(cp);
    const cw = visualWidth(ch);
    const want = col >= c0 && col < c1;

    if (want && !inSel) {
      // Selection changes only the BACKGROUND; the foreground (documented colour)
      // is left intact so a cyan/teal markdown span stays its colour inside the
      // highlight.
      out += C.selBg;
      inSel = true;
    } else if (!want && inSel) {
      // Leave the selection: reset just the background (ESC[49m), keeping the
      // row's foreground. A bare reset would also clear the foreground.
      out += C.bgReset;
      inSel = false;
    }

    out += ch;
    col += cw;
    i += cp > 0xffff ? 2 : 1;

    if (col >= w) break;
  }

  if (inSel) out += C.reset;

  return out;
}

// Truncate an ANSI string to exactly `width` visible columns (no padding).
function sliceAnsi(s, width) {
  const str = String(s);
  if (width <= 0) return '';
  let out = '';
  let col = 0;
  let i = 0;
  while (i < str.length) {
    if (str[i] === '\x1b') {
      const m = /^\x1b\[[0-9;?]*[a-zA-Z]/.exec(str.slice(i)) || /^\x1b\[[0-9;?]* [a-zA-Z]/.exec(str.slice(i));
      if (m) { out += m[0]; i += m[0].length; continue; }
    }
    const cp = str.codePointAt(i);
    const ch = String.fromCodePoint(cp);
    const cw = visualWidth(ch);
    if (col + cw > width) break;
    out += ch;
    col += cw;
    i += cp > 0xffff ? 2 : 1;
  }
  return out + (out.includes('\x1b') ? C.reset : '');
}

/**
 * Add FAINT to the visible columns [from, to) of an ANSI row, leaving every cell's
 * own colours untouched.
 *
 * WHY THIS EXISTS
 * ---------------
 * The popup is a modal, and a modal is made by the SURROUNDINGS receding while the
 * card stays at full contrast. Dimming the card's own interior would mute the thing
 * the user has to read and act on, so the backdrop is dimmed first and the card is
 * painted opaquely over it afterwards.
 *
 * WHY THE CELL KEEPS ITS OWN COLOUR
 * ---------------------------------
 * A retained-mode TUI (OpenTUI, which cline's dialogs run on) dims by setting one
 * attribute on the cell and the renderer blends it — the cell keeps its own
 * foreground. hncode paints finished ANSI strings instead, so "dim" has to be
 * written into the string. Overwriting each cell with a fixed grey would throw away
 * the colour the transcript deliberately uses (cyan user markers, green diff
 * counts, red errors) and flatten the whole screen to one shade; `C.dim` is an
 * attribute, so it can simply be prepended and the cell's own SGR still applies.
 * That is the ANSI equivalent of what the retained renderer does for free.
 *
 * WHY IT GOES THROUGH parseCells INSTEAD OF WRITING `C.dim + ch + C.reset`
 * ----------------------------------------------------------------------
 * The first version emitted that per cell, and it silently DESTROYED colour: the
 * `C.reset` closed each cell, so every cell after the first was painted with no
 * foreground at all. It looked correct with the escapes stripped — which is exactly
 * how it was being checked — and wrong on a real terminal, where a row of cyan user
 * markers went grey after the first character. Dimming a cell means adding an
 * attribute to the style that cell ALREADY carries, which is what the cell buffer
 * knows and a raw string walk does not.
 */
/**
 * The background colour a cell carries, as `[r, g, b]`, or null when the cell has no
 * explicit background (which includes a cell whose background was already reset).
 *
 * THE LAST `48;…` IS THE ONE IN FORCE. `parseCells` accumulates SGR codes into a cell's
 * style and never drops the ones a later background overrides, so a cell inside the
 * context bar carries every fill up to its own column — `48;…system`, `48;…prompt`,
 * `48;…assistant`, `48;…thinking`. Matching the FIRST one reported the same colour for
 * every cell in the row, and the backdrop dimming then rewrote all five fills to that one
 * colour: the bar came back as a single flat band, which on a terminal whose page is not
 * black is indistinguishable from the page — the bar looked simply gone.
 */
function cellBg(cells, c) {
  const cell = cells[c];
  if (!cell) return null;
  let m = null;
  for (const hit of cell.style.matchAll(/48;(?:2;(\d+);(\d+);(\d+)|5;(\d+))/g)) m = hit;
  if (!m) return null;
  if (m[1] !== undefined) return [Number(m[1]), Number(m[2]), Number(m[3])];
  // 256-colour index -> rgb. Only the two families a palette can plausibly use here: the
  // 6x6x6 cube (16..231) and the grey ramp (232..255). Anything else is left alone rather
  // than converted wrongly, because a wrong colour is worse than an undimmed cell.
  const n = Number(m[4]);
  if (n >= 232 && n <= 255) {
    const v = 8 + (n - 232) * 10;
    return [v, v, v];
  }
  if (n >= 16 && n <= 231) {
    const c6 = (n - 16) / 36 | 0;
    const g6 = ((n - 16) % 36) / 6 | 0;
    const b6 = (n - 16) % 6;
    const step = (v) => (v === 0 ? 0 : 55 + v * 40);
    return [step(c6), step(g6), step(b6)];
  }
  return null;
}

function dimRange(row, from, to) {
  if (to <= from) return row;
  const cells = parseCells(row);
  for (let c = from; c < to && c < cells.length; c++) {
    // Prefix the cell's own style, so it keeps its colour and merely gains faint.
    const cell = cells[c];
    if (cell.style.includes(C.dim)) continue;
    // `ESC[2m` fades the FOREGROUND only. A cell painted with a BACKGROUND — the context
    // bar's segments, the scrollbar thumb, any filled chip — therefore stayed at full
    // brightness while every glyph around it receded, so an open picker left the bar
    // blazing under the dimmed page. The bar is read as a row of colour with no text at
    // all, so this was the only part of the screen that did not dim.
    //
    // Terminals have no "dim this background", so the background is darkened explicitly:
    // a cell that carries one gets a proportionally darker `48;2;…` in place of the
    // `48;5;n` it had, keeping the hue and losing the brightness. Which is the same
    // operation a real compositor does, and it composes with `C.dim` on the glyph.
    // Terminals have no "dim this background", so the background is darkened explicitly:
    // a cell that carries one gets a proportionally darker `48;2;…` in place of the
    // `48;5;n` it had, keeping the hue and losing the brightness. Which is the same
    // operation a real compositor does, and it composes with `C.dim` on the glyph.
    //
    // Nothing is exempt. The scrollbar's thumb was going to be, on the reasoning that its
    // colour is what distinguishes idle from hovered from dragged — but an overlay being
    // open means the pointer is on the card, so the thumb cannot be hovered or dragged at
    // that moment and there is no state to lose. It dims with everything else, which is also
    // what the scrollbar test has always asked for ("nothing on the bar keeps full
    // brightness").
    const bg = cellBg(cells, c);
    const faded = bg ? dimmedBg(bg) : '';
    // ORDER MATTERS, and getting it wrong is invisible in a stripped-text check.
    //
    // `ESC[2m` (faint) is an INTENSITY attribute, not a glyph attribute: a terminal that
    // implements it as a global dimming applies it to the background as well. Emitting
    // `ESC[0m ESC[2m ESC[48;5;24m` leaves faint active while the fill is being set, and
    // Windows Terminal's response to "a faint background" is to drop the background outright —
    // the bar came back with its glyphs and nothing behind them, which reads as "the bar
    // vanished" rather than as a terminal quirk.
    //
    // So the fill goes FIRST and the faint after it: the intensity attribute is then applied
    // to a fill the terminal has already resolved, and nothing downstream can unset it.
    //
    // The two branches differ because they are two different corrections, and only one of
    // them replaces the fill: `dimmedBg` returns '' at 256 colours (where no darker shade
    // keeps the segments apart), and there the original `48;…` has to be put BACK rather
    // than dropped, or the fill is lost entirely.
    // The WHOLE escape has to go, not just its parameters: stripping `48;2;…` from
    // `ESC[48;2;…m` leaves a bare `ESC[m`, and a bare `ESC[m` is itself a full reset —
    // it cancelled the faded fill that had just been emitted and every attribute before
    // it, so on a truecolor terminal the bar came out with no background at all.
    const withoutFill = cell.style.replace(/\x1b\[48;(?:5;\d+|2;\d+;\d+;\d+)m/g, '');
    const style = faded ? faded + C.dim + withoutFill : cell.style + C.dim;
    cells[c] = { ...cell, style };
  }
  return renderCells(cells);
}

/** How far a background is pulled toward the page when the page dims.

/** How far a background is pulled toward the page when the page dims.
 *
 *  NOT a plain multiply. Two things made that wrong:
 *
 *  * On a 256-colour terminal the bar's fills are ALREADY dark — the free segment is
 *    rgb(48,48,48), index 236 — and halving one lands on rgb(17,17,17), which quantises
 *    into the 6x6x6 cube's lowest step and comes out indistinguishable from the page. The
 *    picture did not dim, it disappeared, leaving only its glyphs.
 *
 *  * Dimming a backdrop is a loss of CONTRAST, not of light. What makes a surface recede is
 *    its distance from the page colour shrinking, so the fill moves TOWARD the background
 *    rather than toward black. That keeps every fill distinguishable from the page while
 *    making it plainly quieter, which is the whole point of a backdrop.
 *
 *  The floor exists for the same reason: a fill already at the page's own brightness has
 *  nowhere to go, and forcing it lower only makes it read as a hole.
 */
const DIM_BACKGROUND_SCALE = 0.72;
const DIM_BACKGROUND_FLOOR = 28;

/**
 * The dimmed form of a background, or '' to leave it alone.
 *
 * WHY IT IS A NO-OP AT 256 COLOURS
 * -------------------------------
 * The obvious implementation — scale the triple toward the page — does not survive
 * quantisation. The 6x6x6 cube has six steps per channel and the bar's blues live in its
 * lowest two (`ctxSystem` lands on index 23, `ctxAssistant` on 61). Pulling them down by even
 * 15% collapses them: measured across the six fills, 0.85x keeps five distinct and 0.72x
 * keeps four, and the segments that merge are precisely the ones the bar exists to tell
 * apart. What came out on a 256-colour terminal was a row of one flat colour — dimmed, but
 * no longer a bar.
 *
 * So the fill is only rewritten where an exact triple can be stated. `ESC[2m` still dims the
 * glyphs at every depth, and at 256 colours that is what the terminal can express faithfully;
 * the alternative is a bar that has quietly lost two of its five segments.
 *
 * `bgRgb` rather than a raw `48;2;…`, for the same reason it exists: an escape the terminal
 * does not implement is dropped silently, which looks exactly like "the fill vanished" — and
 * that is what happened before this was noticed.
 */
function dimmedBg([r, g, b]) {
  if (!TRUECOLOR) return '';
  const k = (v) => Math.max(DIM_BACKGROUND_FLOOR, Math.min(255, Math.round(v * DIM_BACKGROUND_SCALE)));
  const out = [k(r), k(g), k(b)];
  // Unchanged means the fill was already at the floor: darkening further would only make it
  // read as a hole punched in the page.
  if (out[0] === r && out[1] === g && out[2] === b) return '';
  return bgRgb(out[0], out[1], out[2]);
}

/**
 * Replace the visible columns [from, to) of an ANSI row with blank cells, keeping every
 * other cell exactly as it was.
 *
 * WHY THIS EXISTS
 * ---------------
 * A floating card composites over the frame, and the columns it occupies are its own.
 * What it must NOT do is leave the transcript's glyphs pressed against its edge: a
 * panel is a surface with a margin, and text that runs right up to (or under) the last
 * column of the panel reads as clipped, not as a layer. The card reserves one column
 * each side as a gutter, and this is what clears those columns.
 *
 * WHY NOT `row.slice(0, a) + ' '.repeat(n) + row.slice(b)`
 * --------------------------------------------------------
 * String indices are not display columns. A row containing a CJK glyph has fewer
 * characters than columns, so a slice at a column index cuts the row in the wrong place
 * — the same desynchronisation `parseCells` exists to prevent. Working on cells keeps
 * index == column.
 */
function blankRange(row, from, to) {
  if (to <= from) return row;
  const cells = parseCells(row);
  // A WIDE glyph is one cell plus a continuation cell, and `renderCells` emits the
  // continuation as NOTHING — the glyph before it already covers both columns. So
  // blanking only one half of a pair is what shifted the whole row: the half left behind
  // stopped being emitted while the blanked half emitted a single space, and the row
  // came out one column short. Everything after it slid left, which moved the
  // scrollbar column inward on exactly the rows where a wide glyph straddled the
  // range boundary. The pair is therefore blanked as a UNIT: if the range touches
  // either half, both halves become ordinary spaces, so the columns are still there.
  for (let c = from; c < to && c < cells.length; c++) {
    let start = c;
    if (cells[c].cont) start = c - 1;
    if (start < 0) continue;
    cells[start] = { ch: ' ', style: '', blank: false };
    // The glyph's second column is inside the range, or it is not — either way it has
    // to go with the first, or the pair no longer accounts for two columns.
    if (cells[start + 1] && cells[start + 1].cont) {
      cells[start + 1] = { ch: ' ', style: '', blank: false };
    }
  }
  return renderCells(cells);
}

// ---- git status for the status line ----------------------------------------
// The badge shows the branch and the uncommitted diff totals. Computing that
// costs a handful of git subprocesses, so it is NEVER done from the render path:
// composeFrame only reads `state._gitInfo`. It is refreshed from exactly two
// places —
//   1. a 15s timer while the TUI is idle (see GIT_REFRESH_MS), and
//   2. the end of every turn (the agent's edits land there), plus explicit
//      commands like /git and /move.
// Frame-rate polling was the previous design and cost a git spawn per keystroke;
// a fixed cadence is both cheaper and more predictable.
const GIT_REFRESH_MS = 15000;

// Re-resolve the hover highlight against a FRESH frame.
//
// `state.hoverHit` records a screen row captured the moment the mouse moved, and it
// is only updated by the next mouse event. A repaint that moves content under a
// stationary pointer therefore left the highlight on the WRONG text: hovering a row
// and then letting the transcript grow (a streamed reply, an interrupt notice) kept
// whatever slid into that row tinted. Re-running the hit test with the pointer's last
// position against this frame's hitboxes keeps the highlight on the control the
// pointer is actually over, and drops it when that control is gone.
//
// Returns the resolved span, or null when the pointer is not over anything (which is
// what clears the tint). Falls back to null when there is no pointer data at all, so
// a caller can decide whether to keep the stored span.
// Click targets that must NOT be tinted on hover. They are text-entry or
// text-body areas: tinting a line of editable text reads as a SELECTION, which it
// is not, and it repaints on every mouse move for no benefit.
//   composerRow — the input line (existing behaviour)
//   editor      — the modal editor's text body (e.g. /set-system-prompt, /personal)
//   panelBody   — an info panel's rows (nothing on them is clickable; the hitbox
//                 only exists so a click inside does not dismiss the panel)
//   pickerBody  — the picker popup's box rows (same absorb-only role; the rows
//                 that DO have an action carry pickerItem/pickerCategory/… and
//                 are registered after it, so backward iteration finds those first)
const NO_HOVER_TINT = new Set(['composerRow', 'editor', 'panelBody', 'pickerBody']);

export function resolveHoverHit(state, hitboxes) {
  const m = state._lastMouse;
  if (!m) return null;
  const row = (m.row || 1) - 1;
  const col = (m.col || 1) - 1;
  const boxes = hitboxes || state._hitboxes || [];
  for (let i = boxes.length - 1; i >= 0; i--) {
    const hb = boxes[i];
    if (hb.row !== row) continue;
    if (col < hb.col0 || col > hb.col1) continue;
    if (NO_HOVER_TINT.has(hb.kind)) return null;
    // `kind` travels with the hit: the hover tint only needs the span, but a hit that has
    // something TO SAY — the context bar naming the segment under the pointer — needs to
    // know which one, and the span alone cannot tell a segment from a status-line field.
    return { row: hb.row, col0: hb.col0, col1: hb.col1, kind: hb.kind, data: hb.data };
  }
  return null;
}

export function refreshGitInfo(state, opts = {}) {
  const cwd = state.cwd || state.workspace || '';
  if (!cwd) return;
  if (!cwd) return;
  const now = Date.now();
  const force = opts.force === true;
  // Mid-turn the agent is about to write more files, so a poll would only produce
  // a value that is stale on arrival. The turn-end refresh covers it. Explicit
  // callers (the timer between turns, /git) still get through with force.
  if (!force && state.running) return;
  state._gitCwd = cwd;
  state._gitAt = now;
  // ASYNC: does not block the caller. On the startup path this is what lets the
  // first frame draw immediately — the badge appears a moment later when git
  // answers, instead of freezing the TUI behind four spawnSync calls. `seq`
  // discards a stale reply if another refresh started while this one ran.
  const seq = (state._gitSeq = (state._gitSeq || 0) + 1);
  gitmod.statuslineInfoAsync(cwd)
    .then((info) => {
      if (state._gitSeq !== seq) return;      // superseded by a newer refresh
      state._gitInfo = info;
      if (typeof state._requestRender === 'function') state._requestRender();
    })
    .catch(() => {
      if (state._gitSeq !== seq) return;
      state._gitInfo = null;   // a git failure must never break rendering
      if (typeof state._requestRender === 'function') state._requestRender();
    });
}
/**
 * Tokens per content type, and how many messages of each kind there are.
 *
 * Shared by `/context` (which prints the table) and by the status bar's bar (which draws
 * it), so the two can never disagree about what is being counted.
 */
export function contextBreakdown(session, cfg) {
  // `cfg` is optional because the render path reaches this through `state.cfg`, and a state
  // built directly (several tests do) has no `cfg` at all. An absent config must not take
  // the frame down; it only means the tool-definition count falls back to the full list.
  const conf = cfg || {};
  const byRole = { system: 0, user: 0, assistant: 0, tool: 0, other: 0 };
  const countByRole = { system: 0, user: 0, assistant: 0, tool: 0, other: 0 };
  for (const m of ((session && session.messages) || [])) {
    // Per-message estimator, memoised: `estimateMessagesTokens([m])` re-ran the whole message
    // Per-message estimator, memoised: `estimateMessagesTokens([m])` re-ran the whole message
    // loop for a single-element array, which on a long transcript made /context O(n²). The
    // memo means re-opening /context — or opening it after the bar already priced these
    // messages — is a WeakMap hit per message instead of a fresh walk of every tool body.
    const t = messageTokens(m, conf);
    const r = (m.role === 'system' || m.role === 'user' || m.role === 'assistant' || m.role === 'tool') ? m.role : 'other';
    byRole[r] += t;
    countByRole[r] += 1;
  }
  // Tool definitions ride every request (name + schema), priced here the same way
  // usedTokens() prices them.
  const toolCount = Array.isArray(conf.toolFilter) ? conf.toolFilter.length : (toolNames().length);
  return { byRole, countByRole, toolDefTokens: toolCount * 8, toolCount };
}

/**
 * The same breakdown in the shape the bar draws it, CACHED.
 *
 * The cache is not an optimisation detail, it is what makes the bar affordable: the walk
 * is O(messages) with a token estimate for each, which on a long transcript is the most
 * expensive thing a frame could do — and a frame happens several times a second while text
 * streams. The numbers only move when the conversation does, so the key is the message COUNT
 * plus the token total: a count change means something was added or removed, and the total
 * catches an in-place edit to an existing message.
 *
 * `state._ctxSegs` holds `{ key, segments }`.
 */
export function contextSegments(state, cfg) {
  const msgs = (state.session && state.session.messages) || [];
  // The system prompt is assembled fresh each turn and deliberately kept OUT of
  // `session.messages`: a system entry there would be persisted and replayed, so both
  // turn start and every step boundary write the array back with `role !== 'system'`
  // filtered out. The render path reads exactly that array, so during a turn there was
  // no system message to count and the `system prompt` segment got zero columns and
  // vanished — then reappeared at turn end, when the full request is assigned back.
  // `turnSystemPrompt` carries the assembled text for the duration of the turn so the
  // segment can be priced the whole time it is actually being sent.
  const hasSystemMsg = msgs.some((m) => m && m.role === 'system');
  const sysText = (!hasSystemMsg && typeof state.turnSystemPrompt === 'string') ? state.turnSystemPrompt : '';
  const priced = sysText ? [{ role: 'system', content: sysText }, ...msgs] : msgs;
  const total = state.ctxTokens || 0;
  const key = `${msgs.length}:${total}:${state.rounds || 0}:${sysText.length}`;
  const hit = state._ctxSegs;
  if (hit && hit.key === key) return hit.segments;

  const { byRole } = contextBreakdown({ messages: priced }, cfg);
  // Reasoning is not a session message — `agent.js` keeps it out of `messages` because it
  // must not be sent back to the model — so it has no per-message source. It is whatever
  // the gauge counts that the conversation does not, and only once the model has produced
  // some, so a model that never thinks gets no phantom segment.
  const counted = byRole.system + byRole.user + byRole.assistant + byRole.tool + byRole.other;
  // The gauge's total and the sum of the per-message estimates are NOT the same number, and
  // the difference is not small: `ctxTokens` is what the provider REPORTED for the request, so
  // it carries the system prompt, every tool definition, and the framing around each message
  // — none of which appear in `session.messages` as countable text. Drawing the estimate as
  // the bar made a 5%-full session render as a bar that was 95% empty, which contradicts the
  // percentage printed on the same row.
  //
  // So the estimate is scaled up to the reported total. Every segment's RELATIVE share is
  // preserved — and the share is the only thing a colour can honestly encode — while the
  // filled part of the bar now agrees with the number beside it. Reasoning is left out of the
  // scaling: it is not a session message at all, and it is measured separately as whatever
  // the gauge counts that the conversation does not.
  const scale = counted > 0 && total > counted ? total / counted : 1;
  const share = (n) => Math.round(n * scale);
  const conversation = share(byRole.system) + share(byRole.user) + share(byRole.assistant)
    + share(byRole.tool) + share(byRole.other);
  const segments = {
    system: share(byRole.system),
    prompt: share(byRole.user),
    assistant: share(byRole.assistant),
    thinking: state.seenThinking ? Math.max(0, total - conversation) : 0,
    tools: share(byRole.tool) + share(byRole.other),
  };
  state._ctxSegs = { key, segments };
  return segments;
}

// ---- pure frame composer (no TTY side effects) ----
// kimi-code-cli layout: NO top chrome. Top-to-bottom it is:
//   chat (fills the top) / composer box / [command menu] / status line /
//   [Ctrl-C confirm] / context line (very last screen row).
// Returns { ansi, cursor: {row, col} } with 0-based coords.
export function composeFrame(state, cols, rows) {
  const w = Math.max(20, cols | 0);
  const h = Math.max(12, rows | 0);
  // NOTE: no git call here. The render path only READS state._gitInfo; refreshing
  // it is driven by a 15s timer and by turn-end (see refreshGitInfo).
  // A full-screen takeover (kimi's screen-takeover) owns the ENTIRE screen: no
  // chat, no composer, no status bar. Those surfaces return BEFORE the generic
  // hover pass near the end of this function, so the tint has to be applied here
  // — that is exactly what `takeoverFrame` does, in one place. A takeover that
  // forgets it (as the registry browser did) ends up clickable with NO hover,
  // which reads as broken. Passing the recorded hitboxes makes hover automatic:
  // if something is a click target, it is a hover target.
  const takeoverFrame = (lines, hbs) => {
    // Resolve from the POINTER, not from `state.hoverHit`: each takeover records
    // `_lastMouse` in its own handler, and gating on hoverHit (which some surfaces
    // never set) is what left the registry rows untinted. `resolveHoverHit` returns
    // null when there is no pointer data, so an untouched screen stays plain.
    const hv = resolveHoverHit(state, hbs);
    if (hv && hv.row >= 0 && hv.row < lines.length) {
      lines[hv.row] = tintRange(lines[hv.row], hv.col0, hv.col1 + 1);
    }
    return { ansi: '', lines, cursor: { row: 0, col: 0 }, cursorVisible: false,
             width: w, height: h, cursorRow: 0, cursorCol: 0, cursorShape: hideCursor(),
             hitboxes: hbs, composerMeta: [] };
  };
  if (state.tasksViewer) {
    const lines = renderTaskOutputViewer(state.tasksViewer, w, h);
    return takeoverFrame(lines, []);
  }
  if (state.tasksPanel) {
    const lines = renderTasksBrowser(state.tasksPanel, w, h);
    // The browser records its own click targets; the shape matches what hitAt()
    // expects, so the generic dispatch works unchanged.
    return takeoverFrame(lines, (state.tasksPanel._taskHits || []).slice());
  }
  // The /skills and /plugins manager is a full-screen takeover like the browser above.
  if (state.registryBrowser) {
    const lines = renderRegistryBrowser(state.registryBrowser, w, h);
    return takeoverFrame(lines, (state.registryBrowser._regHits || []).slice());
  }

  // The file tree browser (/files) is another takeover. It re-renders from ITS OWN state
  // every frame, so a directory opened with the arrows is reflected immediately.
  if (state.fileTree) {
    const ctx = state.fileTree;
    const rows = visibleRows(ctx.root, ctx.expanded);
    const view = renderTree({
      root: ctx.root, rows, sel: ctx.sel, scroll: ctx.scroll,
      width: w, height: h, filter: ctx.filter, expandedSet: ctx.expanded,
    });
    // Remember what was drawn: the key handler needs the same `rows` this frame used, or
    // an arrow or a click would act on a list the user is not looking at.
    ctx._rows = rows;
    ctx.sel = view.sel;
    ctx.scroll = view.scroll;
    return takeoverFrame(view.lines, []);
  }
  const insideW = Math.max(0, w - 2);

  // A full-screen overlay: it takes the whole body and the composer is hidden.
  // `state.editor` MUST be in here — it renders into `lines` first, but without
  // this the `if (!dialog)` composer block further down painted the input box
  // straight over it, so /personal and /set-system-prompt showed only a caret.
  // The question prompt is deliberately NOT a dialog: it is a box above the
  // composer, so the transcript stays visible (see the `state.question` block).
  const dialog = state.editor || state.picker || state.form || state.panel || null;

// TRUE TAKEOVER: an overlay that owns the whole body and REPLACES the composer.
// The picker is deliberately excluded — it is a floating popup composited over the
// transcript (see the picker popup step), so the composer, the todo panel and the
// tail of the conversation must stay on screen underneath it. Hiding the composer
// for a menu is what made the picker read as a full-screen takeover: the input box
// you were about to type into vanished, and the rows the box floats over were
// overwritten with spaces, erasing whatever was behind them.
//
// `dialog` stays as-is (truthy for every overlay) wherever the question is "is
// SOMETHING modal open" — key routing, absorbing stray clicks, the caret — because
// a picker IS modal even though it is not a takeover. Only the LAYOUT decisions,
// which ask "does this overlay own the body", use this one.
const takeover = state.editor || state.panel || null;

  // ---- geometry ----
  const composer = composerLayout(state, insideW - 3); // bodyW = (insideW-3)-2 = 53, matches fitAnsi(textW-2) = cInner-4 = 53
  const composerBoxH = takeover ? 0 : composer.rows.length + 2;
  const menuItems = (state.menuOpen && state.menuList.length && !takeover)
    ? Math.min(state.menuList.length, MAX_MENU) + 1
    : 0;
  // The notice no longer reserves a row: it is drawn ON the context row (see the
  // bottom of this function), so `noticeH` only selects the colour there.
const noticeH = state.notice ? 1 : 0;
  // The confirm prompt now works the way the notice above it does: drawn ON the context row,
  // in the tip row's left half. It took a row of its own before, which pushed the bar and
  // the composer down every time Ctrl+C was pressed — for a prompt that lasts three seconds.
  const confirmH = 0;
  const workingH = (!takeover && state.running) ? 1 : 0;
  // The todo and queue panels sit directly above the composer, so they stay visible
// under a picker for the same reason the composer does — a popup covers the
// transcript, not the controls.
const todoH = takeover ? 0 : todoPanelHeight(state);
const queueH = takeover ? 0 : queuePanelHeight(state);
  // The side-thread box takes its rows OUT of the transcript, the same way the queue
  // panel does — otherwise it would overlap the chat.
  const btwH = (!takeover && state.btwPanel && state.btwPanel.turns && state.btwPanel.turns.length)
    ? btwPanelHeight(state, h, insideW)
    : 0;
  // The question box is chrome above the composer, so its rows must come OUT of
  // the transcript area — otherwise the box would overlap the chat.
  //
  // On a short terminal the box can be taller than the whole space available. It
  // must NOT simply overflow: the overflow is trimmed from the TOP (see the
  // topTrim below), which eats the box's own top border and header and leaves a
  // dangling `│`. Cap it so the box plus the composer always fit, and let the
  // transcript shrink to zero instead.
  // The `@file` list occupies the same rows as the `/` menu, so it counts against
  // the same budget — otherwise the frame overflows and the top trim eats the
  // transcript. Only one of the two can be open at a time (see refreshMention).
  const mentionItems = (state.mentionOpen && state.mentionList.length && !takeover)
    ? Math.min(state.mentionList.length, MAX_MENU) + 1
    : 0;
  const chromeH = todoH + queueH + btwH + workingH + composerBoxH + menuItems + mentionItems + STATUS_H + CTX_H;
  // NOTE the extra `- 1`: `bodyH` below is clamped to a MINIMUM of 1 row, so that
  // row has to be reserved here too. Without it the total came out one over and
  // the top trim ate the box's `╭` border.
  const questionH = (!takeover && state.question)
    ? Math.min(questionBoxHeight(state, insideW), Math.max(1, h - chromeH - 1))
    : 0;
  const bottomH = chromeH + questionH;
  const bodyH = Math.max(1, h - bottomH);

  const lines = [];
  let dialogCaret = null;
  // The AskUserQuestion box's free-text caret, recorded as an absolute frame row
  // (the box sits mid-frame, not at the top), corrected with topPad/topTrim below.
  let questionCaret = null;
  const hits = [];
  const addHit = (row, col0, col1, hit) => hits.push({ row, col0, col1, ...hit });
  // Built by the picker branch below and PAINTED after the chat body, so the
  // picker floats over the transcript instead of replacing it (see the picker
  // popup step). Rows/columns stay body-relative until that step positions it.
  let pickerOverlay = null;
  // Where the picker card landed, so the whole frame can be dimmed once every row
  // exists (the status line and context row are pushed after the card is drawn).
  let pickerCard = null;
  // The card's first and last BODY-relative rows, set when the overlay is placed
  // (`[start, end]`, inclusive). Used at the hitbox assembly step to drop the controls
  // UNDERNEATH an open overlay, so the pointer cannot tint or operate what the card
  // covers. Stays null when no overlay is drawn.
  let overlayCardRows = null;
  // The FORM's card spec, when one is open. /provider and /model editing open a form,
  // and it is drawn through the SAME popup path as the picker (see the popup card step),
  // so editing no longer blanks the screen.
  let popupCard = null;
  // Composition-time row where the chat body starts, set when it is drawn.
  let chatOrigin = null;
  // Cleared every frame: the body records its origin only when it is actually
  // drawn, and the `+= topPad - topTrim` correction at the end of this function
  // must not run twice against a stale value (a dialog frame leaves the body
  // unpainted, and the mouse handler relies on null meaning "no body on screen").
  state._bodyScreenTop = null;


  if (state.editor) {
    // A simple modal multiline editor: the text, a caret we draw ourselves, and a
    // key hint. Ctrl+S saves, Esc cancels. The view follows the caret.
    const ed = state.editor;
    const rule = col('─'.repeat(w), C.border);
    const textLines = ed.text.split('\n');
    // The title is CLAMPED to one row. An overlong title (e.g. /personal's, which
    // embeds the full file path) used to be emitted unwrapped: the terminal then
    // wrapped it onto a second visual row while the `lines` array still had ONE,
    // so every row below — the text body included — sat one row lower on screen
    // than the code assumed. Clicks and the caret landed one line off.
    lines.push(col(fitAnsi(ed.title || 'Edit', w), C.cyan + C.bold));
    lines.push(rule);
    const hint = ed.hint || 'Ctrl+S save · Esc cancel · Enter newline';
    // Clamped like the title: an overlong hint would wrap on screen and shift the
    // body the same way.
    lines.push(col(fitAnsi(hint, w), C.gray));
    lines.push('');
    // Viewport height for the editor body. The editor's own rows are:
    //   title + rule + hint + blank            (4, pushed above)
    //   viewH body rows                        (the text)
    //   line-info (+ optional notice) + rule   (2 or 3, pushed below)
    // so `viewH` must leave room for 6 (or 7 with a notice), NOT 5 — one row too
    // many made the frame one line over `h` and the top trim cut the editor's own
    // title and text, leaving just a bare caret on /personal & /set-system-prompt.
    const edFixed = ed.notice ? 7 : 6;
    const viewH = Math.max(1, bodyH - edFixed);
    // Keep the caret row in view.
    let top = Math.max(0, ed.top || 0);
    if (ed.caretRow < top) top = ed.caretRow;
    if (ed.caretRow >= top + viewH) top = ed.caretRow - viewH + 1;
    ed.top = top;
    for (let i = 0; i < viewH; i++) {
      const idx = top + i;
      const txt = idx < textLines.length ? expandTabs(textLines[idx]) : '';
      lines.push(col(fitAnsi(txt, w), C.white));
      // Mouse click on this body row moves the caret to that line. The payload is
      // `line`, NOT `row`: `row` is the hitbox's SCREEN row and composeFrame
      // overwrites it with the topPad/topTrim correction, which turned the text
      // index into `idx + topPad - topTrim` — clicking near the top jumped the
      // caret far down the file.
      addHit(lines.length - 1, 0, w - 1, { kind: 'editor', line: idx });
    }
    lines.push(col(fitAnsi(`  line ${ed.caretRow + 1}/${textLines.length} · ${textLines.length} lines`, w), C.gray));
    if (ed.notice) lines.push(col(fitAnsi('  ' + ed.notice, w), ed.noticeKind === 'error' ? C.red : C.green));
    lines.push(rule);
    // Caret position = caret column within the visible window. The `+ 4` is the
    // four rows pushed above the body (title, rule, hint, blank) — it was `3`
    // (i.e. the title / rule / hint / blank rows miscounted as three), so the
    // block caret was drawn ONE ROW ABOVE the line it was editing on /personal
    // and /set-system-prompt.
    dialogCaret = {
      row: 4 + Math.max(0, Math.min(viewH - 1, ed.caretRow - top)),
      col: Math.min(w - 1, visualCol(expandTabs(textLines[ed.caretRow] || '').slice(0, ed.caretCol))),
    };
    while (lines.length < bodyH) lines.push(' '.repeat(w));
  } else if (state.panel) {
    const p = state.panel;
    const rule = col('─'.repeat(w), C.border);
    const bodyLines = p.lines || [];
    const viewH = Math.max(1, bodyH - 5);
    const maxTop = Math.max(0, bodyLines.length - viewH);
    const top = Math.min(maxTop, Math.max(0, p.top || 0));
    const panelTop = lines.length;   // first row of the panel (its title)
    lines.push(col(p.title || '', C.cyan + C.bold));
    lines.push(rule);
    for (let i = 0; i < viewH; i++) {
      const idx = top + i;
      lines.push(col(fitAnsi(idx < bodyLines.length ? bodyLines[idx] : '', w), C.white));
    }
    const up = top > 0 ? '▲' : ' ';
    const down = top + viewH < bodyLines.length ? `▼ ${bodyLines.length - top - viewH} more` : '';
    lines.push(col(fitAnsi(`  ${up} ${down}`, w), C.gray));
    lines.push(col('Esc close · ↑/↓ scroll', C.gray));
    lines.push(rule);
    // A hitbox for EVERY rendered row of the panel. A click INSIDE the panel must
    // NOT dismiss it: without these the mousedown fell through to the "click outside
    // an overlay closes it" path, so any click — even one meant to scroll or select
    // the text — closed the panel. `addHit` is single-row, so one per row is needed
    // (a single hit on the title row would still leave every content row closable).
    for (let r = panelTop; r < lines.length; r++) addHit(r, 0, w - 1, { kind: 'panelBody' });
    while (lines.length < bodyH) lines.push(' '.repeat(w));
  } else if (state.form) {
    const f = state.form;
    // A rule row starts as a SENTINEL, exactly as in the picker: the popup box is
    // narrower than the terminal, so a full-width rule computed here would not fit. The
    // overlay step turns it into the box's inner width once that is known.
    const RULE = { __rule: true };
    const fields = f.fields || [];
    // An optional DESCRIPTION under the title, wrapped to the box. /settings uses it: the
    // list row carries only the key and its value, so this is where the setting says what it
    // actually does — and it is the moment the user is about to change it.
    const body = [col(f.title || '', C.cyan + C.bold)];
    if (f.note) {
      // `cols`, not `innerW`: the card's own width is decided later, in the overlay step, and
      // `innerW` does not exist in this scope — naming it killed the process the moment any
      // setting was opened. Wrapped to the terminal minus the card's margins; the overlay
      // step trims whatever still does not fit.
      for (const l of wrapWords(f.note, Math.max(20, cols - 8))) body.push(col(l, C.gray));
    }
    body.push(RULE, '');
    const fieldBodyRows = [];
    fields.forEach((field, i) => {
      const active = i === f.fieldIdx;
      const label = col((field.label + ':').padEnd(f.labelW + 1), active ? C.cyan : C.gray);
      const shown = active ? renderFieldValue(field, true) : renderFieldValue(field, false);
      fieldBodyRows.push(body.length);
      body.push(label + shown);
      if (i === f.fieldIdx) dialogCaret = { row: body.length - 1, col: visualCol(label) + fieldCaretCol(field, active) };
    });
    let typeBodyRow = -1;
    let typeOpts = [];
    if (!f.hideType) {
      body.push('');
      // "OpenAI Responses" sits right after "OpenAI" and maps to the Responses API
      // protocol (a distinct wire format from chat/completions). Use the form's own
      // list when present so the drawn options and the keyboard cycle cannot drift.
      const types = (f.types && f.types.length) ? f.types : PROTOCOL_TYPES;
      const typeActive = f.fieldIdx === fields.length;
      const labelW = visualCol('Type:'.padEnd(f.labelW + 1));
      let colCursor = labelW;
      typeOpts = types.map((t) => {
        const brick = (typeActive ? '❯ ' : '  ') + t;
        const cw = visualCol(brick);
        const rec = { opt: t, colStart: colCursor, colEnd: colCursor + cw };
        colCursor += cw + 2;
        return rec;
      });
      const typeStr = types.map((t) => t === f.type
        ? col((typeActive ? '❯ ' : '  ') + t, typeActive ? (C.cyan + C.bold) : C.cyan)
        : col('  ' + t, C.gray)).join('  ');
      const typeLabel = col('Type:'.padEnd(f.labelW + 1), typeActive ? C.cyan : C.gray);
      const typeHint = f.type ? '' : col('  ← choose', C.yellow);
      body.push(typeLabel + typeStr + typeHint);
      typeBodyRow = body.length - 1;
    }
    body.push('');
    body.push(col(f.hint || 'Tab next field · Enter submit · Esc cancel', C.gray));
    body.push(RULE);
    // The form is a POPUP, like the picker — it used to be a full-screen takeover,
    // which meant /provider and /model editing blanked the whole screen and hid the
    // composer, the status line and the list you were picking from. The body is stashed
    // and the popup step boxes and centres it over the dimmed transcript; the caret and
    // the field hitboxes stay BODY-relative until then.
    popupCard = { body, fieldBodyRows, typeBodyRow, typeOpts, anchor: null };
  }
  if (state.picker) {
    const pick = state.picker;
    const query = state.pickerQuery || '';
    const list = pickerFiltered(state);
    const selIdx = Math.max(0, Math.min(list.length - 1, pick.sel || 0));
    // A rule row starts as a SENTINEL: the popup box is narrower than the
    // terminal, so a full-width rule computed here would not fit. The overlay
    // step turns it into the box's inner width once that is known.
    const RULE = { __rule: true };
    const titleSuffix = pick.searchable === false ? '' : ' (type to search)';
    const hintText = pick.hint || '↑↓ navigate · Enter select · Esc cancel';
    const body = [
      col(pick.title || '', C.cyan + C.bold) + col(titleSuffix, C.gray),
      RULE,
      col(hintText, C.gray),
      '',
    ];
    // The caret stays BODY-RELATIVE here; the overlay step converts it to an
    // absolute frame position once the box is placed.
    let pickCaret = null;
    if (pick.searchable !== false) {
      body.push(col('Search: ', C.gray) + col(query, C.white));
      if (query) {
        pickCaret = { row: body.length - 1, col: visualCol('Search: ') + visualCol(query) };
      }
    }
    // Category tabs (if the picker defines them): "All" + provider categories.
    // Each tab records its COLUMN RANGE so a click can select that category and a
    // hover can highlight it (previously the row was pure text: no hitbox at all).
    let catBodyRow = -1;
    const catTabs = [];
    if (pick.categories && pick.categories.length > 1) {
      const cats = pick.categories;
      const active = state.pickerCategory || cats[0];
      const allItems = state.picker.items || [];
      let catLine = col('Categories: ', C.gray);
      let catCursor = visualCol('Categories: ');
      for (let ci = 0; ci < cats.length; ci++) {
        const label = cats[ci];
        const active_ = label === active;
        // Count items in this category (for the tab label).
        let cnt;
        if (label === cats[0]) {
          cnt = allItems.filter((it) => !it.action).length; // "All" = all non-action items
        } else {
          cnt = allItems.filter((it) => it.category === label).length;
        }
        const text = active_ ? `[${label} (${cnt})]` : ` ${label} (${cnt}) `;
        const seg = active_ ? col(text, C.cyan + C.bold) : col(text, C.gray);
        catTabs.push({ label, colStart: catCursor, colEnd: catCursor + visualCol(text) - 1 });
        catCursor += visualCol(text);
        catLine += seg;
      }
      body.push(catLine);
      catBodyRow = body.length - 1;
    }
    // Overhead: header rows (body.length) + optional footer (empty + footer row).
    const footerRows = pick.footer ? 2 : 0;
    const overhead = body.length + footerRows + 2; // +2 for the trailing blank and a "more" line
    // The picker is a floating BOX, not the whole body: cap its height so the
    // transcript stays visible around it and the box can never outgrow the
    // screen. The overlay clips defensively anyway.
    const popBudget = Math.max(4, Math.min(bodyH - 2, 30));
    const maxItems = Math.max(1, Math.min(MAX_PICKER, popBudget - overhead - 1)); // -1 reserved for potential "more" line
    let first = Math.max(0, selIdx - Math.floor((maxItems - 1) / 2));
    if (first + maxItems > list.length) first = Math.max(0, list.length - maxItems);
    const shown = list.slice(first, first + maxItems);
    const itemBodyRows = [];
    // Empty state: distinguish "still searching" from "no hits".
    if (!shown.length) {
      const msg = pick._loading ? 'Searching…' : (pick.searchable !== false && query ? 'No matches' : '');
      if (msg) body.push(col('  ' + msg, C.gray));
    }
    shown.forEach((item, j) => {
      const idx = first + j;
      const isSel = idx === selIdx;
      const ptr = isSel ? col('❯ ', C.cyan) : '  ';
      const label = col(String(item.label), isSel ? (C.cyan + C.bold) : C.white);
      const sub = item.sub != null && item.sub !== '' ? col('  ' + String(item.sub), C.gray) : '';
      // The "current" marker sits right after the name (not right-aligned at the far
      // edge), with a wider gap so it does not crowd the label.
      const cur = item.current ? col('   ← current', C.green) : '';
      // `valueTag` is the setting's CURRENT VALUE. It goes after the description, not
      // right-aligned: the card sizes itself to its widest row, so padding a value out to
      // the terminal width made every row full-width and the card filled the screen.
      //
      // The value is capped at 40 columns INDEPENDENTLY of the room left on the row. A
      // value pasted into `system_prompt` can be a paragraph, and letting its length decide
      // meant one row set the width for all 50 — which is the same full-screen problem by
      // another route. `displayValue` already shortens long values for this reason; the cap
      // here is the picker's own, because it is what decides the card.
      let tag = '';
      if (item.valueTag != null && item.valueTag !== '') {
        const raw = String(item.valueTag);
        const room = Math.min(40, Math.max(8, cols - visualCol(ptr + label + sub + cur) - 6));
        const text = visualCol(raw) > room ? `${raw.slice(0, Math.max(1, room - 1))}…` : raw;
        tag = col(
          `  ${text}`,
          // Grey for the default, and colour ONLY for a value the user has actually changed.
          // A settings list is mostly defaults, so painting all of them drew the eye nowhere;
          // what stands out should be what is NOT the default. Orange rather than cyan:
          // cyan is the accent the rest of the chrome already uses (the pointer, the tab,
          // the selection), so a changed value in it read as "selected" rather than "edited".
          item.valueTagChanged ? C.orange : C.gray,
        );
      }
      itemBodyRows.push(body.length);
      body.push(col(ptr + label + sub + cur + tag, C.white));
    });
    if (list.length > maxItems) body.push(col(`▼ ${list.length - (first + shown.length)} more`, C.gray));
    let footerBodyRow = -1;
    let footerOpts = [];
    if (pick.footer) {
      const f = pick.footer;
      body.push('');
      const label = col(`${f.label || 'Thinking'}:  `, C.gray);
      const labelW = visualCol(`${f.label || 'Thinking'}:  `);
      let colCursor = labelW;
      const bricks = (f.options || []).map((o) => {
        const brick = f.focused
          ? (o === f.value ? `[ ${o} ]` : ` ${o} `)
          : ` ${o} `;
        const cw = visualCol(brick);
        footerOpts.push({ opt: o, colStart: colCursor, colEnd: colCursor + cw });
        colCursor += cw + 1;
        return o === f.value ? col(brick, C.cyan + C.bold) : col(brick, C.gray);
      }).join(' ');
      const row = label + bricks + (f.focused && !f.value ? col('  ← choose', C.yellow) : '');
      body.push(row);
      footerBodyRow = body.length - 1;
      if (f.focused) {
        pickCaret = { row: body.length - 1, col: visualCol(label) + 1 };
      }
    }
    body.push('');
    // Do NOT paint here. The picker is a POPUP drawn over the transcript: the
    // chat body renders first, then the overlay step (right after the chat
    // branch) boxes this content and paints it centered. Everything the paint
    // needs is stashed with rows/columns still BODY-relative.
    pickerOverlay = {
      body, itemBodyRows, catBodyRow, catTabs, footerBodyRow, footerOpts,
      caret: pickCaret, first, anchor: pick.anchor || null,
    };
  }
  // The chat body is the LAST fallback for an open overlay. It used to be the
  // bare `else` of the PICKER branch, so opening the editor (picker == null) ran
  // this too and appended a whole extra viewport of rows ON TOP of the editor.
  // The frame then overflowed, the top trim ate the editor's own title and text,
  // and /personal & /set-system-prompt showed nothing but a stray caret.
  // The PICKER no longer suppresses the chat: it is a popup OVER the transcript
  // (see the picker popup step below), so the conversation stays visible behind
  // the dialog instead of the whole body going blank for a menu.
  if (!state.editor && !state.panel) {
    // Windowed: renderChatLines computes the visible tail from bodyH+scroll and
    // fills the rest with padding. `chat` still has the full row count (holes
    // are blank strings), so `chat.length` remains the true total and the
    // slices below stay correct. `state._forceFullRender` (tests) bypasses the
    // window so the full path can be compared.
    const chat = state._forceFullRender
      ? renderChatLines(state, w)
      : renderChatLines(state, w, { bodyH, scroll: state.scroll || 0 });
    if (state.selection && state.selection.anchor && state.selection.head) {
      // Apply selection highlight directly on ANSI strings
      for (let i = 0; i < chat.length; i++) {
        const a = state.selection.anchor, h = state.selection.head;
        if (!Number.isFinite(a.row) || !Number.isFinite(h.row)) { /* no range */ }
        else {
        const startIdx = (h.row < a.row || (h.row === a.row && h.col < a.col)) ? h : a;
        const endIdx = startIdx === a ? h : a;
        if (i < startIdx.row || i > endIdx.row) continue;
        let c0, c1;
        // +1: the end column is the cell under the pointer and is selected too.
        if (startIdx.row === endIdx.row) { c0 = startIdx.col; c1 = endIdx.col + 1; }
        else if (i === startIdx.row) { c0 = startIdx.col; c1 = Infinity; }
        else if (i === endIdx.row) { c0 = 0; c1 = endIdx.col + 1; }
        else { c0 = 0; c1 = Infinity; }
        chat[i] = highlightAnsiRange(chat[i], c0, c1, cols);
        }
      }
    }
    if (process.env.HNCODE_DEBUG && state.selection) {
      const _a = state.selection.anchor, _h = state.selection.head;
      const _s = (_h.row < _a.row || (_h.row === _a.row && _h.col < _a.col)) ? _h : _a;
      const _e = _s === _a ? _h : _a;
    }
    const total = chat.length;
    const maxScroll = Math.max(0, total - bodyH);
    const scroll = Math.min(maxScroll, Math.max(0, state.scroll || 0));
    const start = total <= bodyH ? -(bodyH - total) : total - bodyH - scroll;
    const showBar = total > bodyH && w > 4;
    const sb = showBar ? scrollbarGeometry({ total, bodyH, scroll }) : null;

    // Body row 0's index inside `lines`, captured BEFORE the loop pushes anything.
    // Whatever is already in `lines` (a plan table, a prompt box) precedes the
    // body, so `lines.length` here IS the body's origin; deriving it afterwards as
    // `lines.length - bodyH` assumes nothing came before it, which is false.
    const bodyScreenTop = lines.length;
    chatOrigin = bodyScreenTop;
    for (let i = 0; i < bodyH; i++) {
      const idx = start + i;
      let row = '';
      if (idx >= 0 && idx < total) {
        row = chat[idx] || '';
      }
      if (sb) {
        // The scrollbar cell is drawn EXACTLY the way OpenTUI's SliderRenderable draws
        // it (packages/core/src/renderables/Slider.ts, `renderVertical`):
        //
        //   setCellWithAlphaBlending(x, y, char, foregroundColor, backgroundColor)
        //
        // with foregroundColor = the THUMB colour and backgroundColor = the TRACK
        // colour. That pairing is what a half block needs: `▄` paints its lower half
        // with the foreground and leaves the upper half on the background, so a
        // half-covered row reads as "half thumb, half track".
        //
        // It used to set BOTH to the thumb colour, on the theory that a block glyph
        // fills its cell so only its background shows. That is true of `█` but NOT of
        // `▀`/`▄`: the exposed half kept the thumb colour, so a half-covered row grew a
        // second square. It also broke the modal backdrop — `dimRange` adds faint
        // (`ESC[2m`), which fades the FOREGROUND only, so an open picker left the
        // thumb's background half at full brightness while the rest of the screen
        // receded.
        const glyphChar = scrollbarGlyph(sb, i);
        const onThumb = glyphChar !== ' ';
        let fg;
        if (onThumb) {
          if (state.sbDrag) fg = C.scrollThumbActiveFg;
          else if (state.sbHover) fg = C.scrollThumbHoverFg;
          else fg = C.scrollThumbFg;
        } else {
          fg = C.scrollTrackFg;
        }
        const bg = C.scrollTrackBg;
        row = fitAnsi(row, w - 1) + fg + bg + glyphChar + C.reset;
      }
      lines.push(row);
    }
    state._sb = sb;
    state._bodyTop = start;
    state._bodyH = bodyH;
    // Where body row 0 lands in the FINAL `lines` array. `start` is a transcript
    // row number, but the mouse reports a SCREEN row, and the two are only equal
    // when the chat happens to begin at screen row 0. Anything pushed before the
    // body (nothing today, but the padding below is enough) shifts it, so the
    // mapping is recorded here rather than assumed — hitboxes already do the same
    // `+ topPad - topTrim` correction (see the end of this function) and the mouse
    // mapping did not, which is what made a drag copy the wrong lines.
    state._bodyScreenTop = lines.length - bodyH;
    // How many blank padding rows precede the first body row on screen. When
    // the transcript is shorter than the body, `start` is negative and those
    // rows are padding; a click there must NOT map to a transcript line.
    state._bodyPadTop = Math.max(0, -start);
  }

  // ---- popup card ------------------------------------------------------------
  // Both the picker and the form float over the transcript. They used to differ: the
  // picker was a centred box but the form was a full-screen takeover, so /provider and
  // /model editing blanked the screen and hid the list you were picking from. They now
  // share ONE box builder, so the two can never drift apart again.
  //
  // `card` is `{ body, anchor }`. Row/column numbers produced here are composition-time
  // indices, corrected by the same `+ topPad - topTrim` the hitboxes get at the end.
  const cardSpec = pickerOverlay || popupCard;
  if (cardSpec) {
    const ov = cardSpec;
    // Measure the content first: the box hugs it instead of spanning the screen.
    let contentW = 1;
    for (const b of ov.body) if (typeof b === 'string') contentW = Math.max(contentW, visualCol(b));
    // +2 for one space of padding each side of the content — the same breathing
    // The panel hugs its content, but never so wide that it stops reading as a floating
    // surface: at `w - 2` the margins go to zero and it spans the terminal, which looks
    // like a takeover. Two columns of breathing room each side keeps it visibly centred
    // no matter how long a row is — the row is clipped to fit instead of the panel growing.
    const inner = Math.max(8, Math.min(w - 6, contentW + 2));
    const boxW = inner + 2;
    // An ANCHORED box opens at the given screen position (the right-click context
    // menu follows the pointer) instead of centred — and is then nudged back INSIDE
    // the frame, because a menu that opens at the pointer near the right or bottom
    // edge would otherwise be clipped in half by its own screen.
    //
    // Both axes are clamped against the frame, because the anchor is an absolute
    // screen position and the card must never be painted off the edge of it.
    let padLeft = Math.max(0, Math.floor((w - boxW) / 2));
    let padTop = null;   // null = centred vertically
    if (ov.anchor) {
      padLeft = Math.max(0, Math.min(w - boxW, Math.round(ov.anchor.col)));
      padTop = Math.max(0, Math.min(h - 1, Math.round(ov.anchor.row)));
    }
    // The card is a FILLED PANEL, not a bordered box: no frame, no side walls, no
    // inner rule. The panel background IS the boundary — a solid block of colour that
    // the transcript cannot show through — which is how Cline's dialog reads (it sets
    // a `backgroundColor` on the panel and nothing else; see
    // apps/cli/src/tui/components/dialog-theme-sync.tsx).
    //
    // WHY THE FRAME HAD TO GO, beyond taste: every box-drawing character it used
    // (`╭ ╮ ╰ ╯ ─ │`) is East Asian AMBIGUOUS — 1 column in our width model, 2 on a CJK
    // terminal — so each frame row was drawn twice as wide as we thought and the wall
    // landed far right of the panel. A filled surface has no such character: the block
    // ends where its background ends, whatever the terminal's width rules are.
    //
    // Padding: one column each side, and one blank row above and below, so the text has
    // room to breathe and the first/last item does not touch the edge.
    //
    // EVERY row goes through `padRow`, including the blanks. A bare `''` parses to ZERO
    // cells, so it contributed no layer cells at all and those rows had NO background —
    // the greyed transcript showed straight through two lines of the panel. Padding each
    // row to the full panel width is what makes the background continuous.
    const PANEL_BG = C.bgPanel;
    const padRow = (content) => ' ' + fitAnsi(content, Math.max(1, boxW - 2)) + ' ';
    const box = [padRow('')];
    for (const b of ov.body) {
      // Rule sentinels become a blank spacer row now that there is no frame to rule off.
      if (b && b.__rule) { box.push(padRow('')); continue; }
      box.push(padRow(b));
    }
    box.push(padRow(''));
    const fit = box.slice(0, h);
    // An anchored box keeps the row it was given (clamped above); a normal one is
    // centred on the TERMINAL, not on the transcript area.
    //
    // It used to centre within `origin + room` — the region left over after the
    // composer, todo panel and status line took their rows. That is not the middle
    // of the screen: the card sat visibly high, above the vertical centre, because
    // every one of those chrome rows counts as space the card refused to use. The
    // frame height `h` is the real screen, so that is what it is centred on.
    const top = padTop != null
      ? padTop
      : Math.max(0, Math.floor((h - fit.length) / 2));
    // Clamp against the FRAME height, not `lines.length`: `lines` is still short at this
    // point — the topPad/topTrim pass that pads it to `h` has not run yet — so
    // clamping to it pulled the card upwards on any frame with a short transcript,
    // which is exactly the tall-terminal case it was supposed to centre on.
    const at = Math.max(0, Math.min(h - fit.length, top));
    // The card is a floating LAYER, composited cell-by-cell onto the row.
    //
    // It used to be `lines[r] = fit[i]`, a whole-string replacement, which also erased
    // the transcript BESIDE the card: a row of `11111111111111` came out as
    // `        |111111|`. Compositing keeps both flanks and replaces only the card's own
    // columns, which is the whole point of drawing it as a layer.
    //
    // EVERY cell in the card is opaque: it carries PANEL_BG in addition to its own
    // style, so the terminal fills that column and nothing behind can show through.
    // This is what makes the bleed-through impossible even when our measured widths
    // and the terminal's disagree (see the note above `PANEL_BG`).
    const layer = fit.map((row) => {
      const cells = parseCells(row);
      for (let i = 0; i < cells.length; i++) {
        cells[i] = { ...cells[i], style: PANEL_BG + cells[i].style };
      }
      return cells;
    });
    pickerCard = { at, padLeft, boxW, height: fit.length, layer };
    // The card's rows, BODY-relative here and corrected with the same topPad/topTrim
    // as every other hitbox below. Recorded so the hitbox assembly step can drop the
    // controls UNDERNEATH the card: an overlay is modal, so a pointer inside it must
    // not tint or operate the transcript/composer behind it.
    overlayCardRows = [at, at + fit.length - 1];
    // Panel-relative row/column of the CONTENT. `body` index 0 is the panel's blank
    // top pad row, and the rows are `' ' + text + ' '`, so the text starts one column in:
    //   row   at + 1 + bodyRow   (the +1 skips the blank pad row pushed above)
    //   col   padLeft + 1        (the +1 skips the leading pad space)
    // There is no border any more, so the old `+2` for the wall glyph is gone: using it
    // would have shifted every hover tint and click one column to the right.
    const rowOf = (bodyRow) => at + 1 + bodyRow;
    const col0 = padLeft;
    const col1 = padLeft + boxW - 1;
    const contentCol0 = padLeft + 1;
    const contentCol1 = padLeft + boxW - 2;
    // Row-wide panel hit FIRST: a click on the title/hint/padding is INSIDE the panel
    // (absorbed, no action) — only a click outside it dismisses.
    // Both hitAt and resolveHoverHit iterate BACKWARD (last registered wins),
    // so the precise item/tab/footer hits go AFTER this one and win where they
    // overlap — otherwise every inner click would be swallowed by the panel hit
    // and picking an item with the mouse would stop working.
    //
    // Everything registered BEFORE this point belongs to the transcript behind the
    // card; those hits are dropped once every row is known (see the hitbox assembly
    // step at the end of this function, which is where `overlayTop` is applied).
    for (let i = 0; i < fit.length; i++) addHit(at + i, col0, col1, { kind: 'pickerBody' });
    // Row-wide box hit FIRST: a click on the title/hint/border is INSIDE the
    // dialog (absorbed, no action) — only a click outside the box dismisses.
    // Both hitAt and resolveHoverHit iterate BACKWARD (last registered wins),
    // so the precise item/tab/footer hits go AFTER this one and win where they
    // overlap — otherwise every inner click would be swallowed by the box hit
    // and picking an item with the mouse would stop working.
    //
    // Everything registered BEFORE this point belongs to the transcript behind the
    // card; those hits are dropped once every row is known (see the hitbox assembly
    // step at the end of this function, which is where `overlayTop` is applied).
    for (let i = 0; i < fit.length; i++) addHit(at + i, col0, col1, { kind: 'pickerBody' });
    if (ov.itemBodyRows) {
      ov.itemBodyRows.forEach((bi, j) => addHit(rowOf(bi), contentCol0, contentCol1, { kind: 'pickerItem', index: ov.first + j }));
    }
    if (ov.catBodyRow >= 0) {
      ov.catTabs.forEach((tab) => {
        // +1 = the leading padding space before the content (no border any more).
        addHit(rowOf(ov.catBodyRow), padLeft + 1 + tab.colStart, padLeft + 1 + tab.colEnd,
          { kind: 'pickerCategory', label: tab.label });
      });
    }
    if (ov.footerBodyRow >= 0) {
      ov.footerOpts.forEach((rec) => {
        addHit(rowOf(ov.footerBodyRow), padLeft + 1 + rec.colStart, padLeft + 1 + rec.colEnd,
          { kind: 'pickerFooterOpt', option: rec.opt });
      });
    }
    // The form's own hits: a field row spans the card's CONTENT (not its walls, for
    // the reason given above `contentCol0`), and a Type option is a precise clickable
    // range within its row. These are what make clicking a field focus it now that the
    // form is a centred card rather than a full-width screen.
    if (ov.fieldBodyRows) {
      ov.fieldBodyRows.forEach((bi, i) => addHit(rowOf(bi), contentCol0, contentCol1, { kind: 'formField', index: i }));
    }
    if (ov.typeBodyRow >= 0) {
      ov.typeOpts.forEach((rec) => {
        addHit(rowOf(ov.typeBodyRow), padLeft + 1 + rec.colStart, padLeft + 1 + rec.colEnd,
          { kind: 'formType', option: rec.opt });
      });
    }
    // The form's caret is BODY-relative, like the picker's — it is converted here,
    // where the card's position is finally known.
    if (popupCard && dialogCaret) {
      dialogCaret = { row: rowOf(dialogCaret.row), col: padLeft + 1 + dialogCaret.col };
    }
    if (ov.caret) {
      // Absolute frame row/col; the cursor step adds the same `+ topPad` the
      // other dialog carets get (dialogs are padded below, never trimmed). +1 =
      // the leading padding space before the content (no border any more).
      dialogCaret = { row: rowOf(ov.caret.row), col: padLeft + 1 + ov.caret.col };
    }
  }

  // AskUserQuestion prompt: a box sitting directly above the composer (not a
  // full-screen dialog) so the transcript the question refers to stays visible.
  //
  // Layout:
  //   |Q1| Q2            <- question tabs (Tab switches), current lit
  //   用哪种权限模式？      <- the question text
  //   > A  读取自动执行…   <- option: marker + label + dim desc on the same row
  //     B  什么都不问
  //     Other
  //   ↑↓ 移动 · Enter 选择 · Esc 取消
  // Single-select marker is `> `; multi-select uses an empty/filled square.
  if (state.question && !takeover) {
    const qs = state.question;
    const cur = qs.items[qs.index] || { question: '', options: [] };
    const promptW = insideW;
    const innerW = Math.max(1, promptW - 2);
    const bar = (ch) => col(ch, C.border);
    const boxRow = (content) => bar('│') + ' ' + fitAnsi(content, innerW) + ' ' + bar('│');
    lines.push(bar('╭' + '─'.repeat(promptW) + '╮'));
    const box = [];
    // ---- tab bar: each question, plus a trailing "Other" (whole-request note) ----
    // `qs.index` selects a question; `qs.index === qs.items.length` selects the
    // Other tab. The current tab is highlighted (background).
    const onOtherTab = qs.index >= qs.items.length;
    {
      let tabs = '';
      const tabName = (i) => {
        const it = qs.items[i];
        return String((it && it.header) || `Q${i + 1}`).trim() || `Q${i + 1}`;
      };
      for (let i = 0; i <= qs.items.length; i++) {
        const name = i === qs.items.length ? OTHER_LABEL : tabName(i);
        const on = i === qs.index;
        tabs += on ? col(' ' + name + ' ', C.selBg + C.cyan + C.bold) : col(' ' + name + ' ', C.gray);
        tabs += ' ';
      }
      box.push(boxRow(fitAnsi(tabs, innerW - 2)));
    }
    const itemRows = [];
    let caretInBox = -1;
    let caretColInBox = -1;
    if (onOtherTab) {
      // The Other tab holds the whole-request free-text note (may be blank).
      for (const seg of wrapWords('Add extra context for the whole request (optional).', innerW - 2)) {
        box.push(boxRow(col('  ' + seg, C.gray)));
      }
      const label = OTHER_LABEL + ': ';
      const text = String(qs.supplement || (qs.editing === 'supplement' ? qs.editingText : '') || '');
      const ec = Math.max(0, Math.min(text.length, qs.editing === 'supplement' && qs.editingCaret != null ? qs.editingCaret : text.length));
      caretInBox = box.length;
      caretColInBox = visualCol(label) + visualCol(text.slice(0, ec));
      box.push(boxRow(col(label, C.gray) + col(text, C.white)));
      box.push(boxRow(col('Enter submit · Tab/arrows switch', C.gray)));
    } else {
          // ---- the question text, wrapped by DISPLAY width (CJK-safe) ----
          for (const seg of wrapWords(cur.question, innerW - 2)) {
            box.push(boxRow(col('  ' + seg, C.white)));
          }
          // Options: the model's options, then our per-question "Other" (free answer).
          const opts = cur.options.map((o) => ({ label: o.label, description: o.description, kind: 'option' }));
          opts.push({ label: OTHER_LABEL, description: '', kind: 'other' });
          const boxBudget = (questionH || Infinity) - 2 - box.length;
          const showHint = boxBudget >= opts.length + 1;
          const bodyBudget = Math.max(0, boxBudget - (showHint ? 1 : 0));
          let firstOpt = 0;
          if (opts.length > bodyBudget && bodyBudget > 0) {
            firstOpt = Math.min(Math.max(0, qs.sel - bodyBudget + 1), opts.length - bodyBudget);
          }
          const shownOpts = opts.slice(firstOpt, firstOpt + (bodyBudget || opts.length));
          shownOpts.forEach((o, k) => {
            const j = firstOpt + k;
            const isSel = j === qs.sel;
            const chosen = qs.picked.has(j);
            // Marker: single-select draws `> ` on the current row; multi-select shows an
            // empty/filled square (filled = picked). Plain block glyphs, never emoji.
            let marker;
            if (cur.multiSelect) marker = chosen ? '\u25a0 ' : '\u25a1 ';
            else marker = isSel ? '> ' : '  ';
            // The current row is marked by `> ` (single) / the filled square (multi); no
            // background highlight.
            const markerPaint = isSel ? C.cyan : (chosen ? C.cyan : C.gray);
            const labelPaint = isSel ? (C.cyan + C.bold) : (chosen ? C.cyan : C.white);
            const typed = (o.kind === 'other' && qs.otherText) ? `: ${qs.otherText}` : '';
            const head = col(marker, markerPaint) + col(String(o.label) + typed, labelPaint);
            const desc = o.description ? col('  ' + o.description, C.gray) : '';
            itemRows.push({ boxIdx: box.length, index: j });
            box.push(boxRow(fitAnsi(head + desc, innerW - 2)));
          });
          if (qs.editing === 'other' && showHint) {
            const label = OTHER_LABEL + ': ';
            const text = String(qs.editingText || '');
            const ec = Math.max(0, Math.min(text.length, qs.editingCaret == null ? text.length : qs.editingCaret));
            caretInBox = box.length;
            caretColInBox = visualCol(label) + visualCol(text.slice(0, ec));
            box.push(boxRow(col(label, C.gray) + col(text, C.white)));
          } else if (showHint) {
            const hint = cur.multiSelect
              ? '↑↓ move · Space toggle · Enter confirm · Esc dismiss'
              : '↑↓ move · Enter select · Esc dismiss';
            box.push(boxRow(col(hint, C.gray)));
          }
    }
    const boxTop = lines.length;
    for (const b of box) lines.push(b);
    lines.push(bar('╰' + '─'.repeat(promptW) + '╯'));
    itemRows.forEach((r) => addHit(boxTop + r.boxIdx, 0, w - 1, { kind: 'questionItem', index: r.index }));
    if (caretInBox >= 0) {
      // The box is mid-frame (chat above, composer below), NOT pinned to the top,
      // so its caret is recorded as an absolute frame row and corrected with the
      // same `topPad - topTrim` shift the hitboxes get at the end of this function.
      // Column: 2 (border + space) + the label + the text BEFORE the field caret.
      questionCaret = { row: boxTop + caretInBox, col: 2 + caretColInBox };
    }
  }

  if (workingH) {
    const frameInfo = spinnerFrame(state);
    const frame = frameInfo.glyph;
    // Reduced motion turns the whole row into its resting form: no type-on, no
    // sweep, no pulse. The row still exists (the user must be able to see that a
    // turn is running) but nothing moves except the dot's slow brightness.
    const still = reducedMotionOn(state);
    // ---- shared palette for the whole Working row -------------------------
    // Everything on this row (spinner glyph, typed chars, elapsed tail, sweep)
    // must come from ONE set of RGB values, rendered through the SAME lerpColor
    // path. Mixing C.gray (ANSI 90 ≈ #808080) with the sweep's #969696, or
    // C.orange (256-colour 208) with the sweep's #ff8c00 (=214), made the row
    // visibly change shade at each phase boundary.
    const GREY_RGB = [150, 150, 150];
    const ORANGE_RGB = [255, 140, 0];
    const greyEsc = lerpColor(GREY_RGB[0], GREY_RGB[1], GREY_RGB[2], GREY_RGB[0], GREY_RGB[1], GREY_RGB[2], 0);
    const orangeEsc = lerpColor(ORANGE_RGB[0], ORANGE_RGB[1], ORANGE_RGB[2], ORANGE_RGB[0], ORANGE_RGB[1], ORANGE_RGB[2], 0);
    const elapsed = state.turnStart ? ` ${col('[' + fmtDuration(Date.now() - state.turnStart) + ']', greyEsc)}` : '';
    // The wording was chosen once at turn start; the gradient below loops
    // independently, so the phrase stays put while the colours sweep.
    const workMsg = state.workMsg || WORKING_MESSAGES[0];
    const spin = state.spin || 0;

    // ---- reduced motion: the resting row ----
    // Nothing types on, sweeps or pulses. The phrase, the elapsed tail and a dot that
    // slowly changes brightness are all that is drawn. Handled FIRST so the animated
    // branches below cannot run at all.
    if (still) {
      const dim = frameInfo.dim;
      const dotEsc = dim ? greyEsc : orangeEsc;
      lines.push(
        (dim ? C.dim : '') + col(frame, dotEsc) + ' '
        + col(workMsg, greyEsc) + elapsed + (dim ? C.reset : ''),
      );
    }
    // ---- turn-start animation ----
    // 0.5s: type out "Working..." in grey (chars appear left→right)
    // 0.5s: fill with orange (chars change colour left→right)
    // After 1s total: start the normal pulse animation (yellow/red cycle)
    else if (state.startAnim) {
      // 1s total: 0.5s types `Working... [0s]` out in grey, then 0.5s sweeps the
      // PHRASE grey → orange. The `[0s]` tail types out WITH the phrase but is
      // EXCLUDED from the colour sweep — it stays grey the whole time.
      const DUR = 1000;
      const t = Math.min(1, (Date.now() - state.startAnim.start) / DUR);
      const phase = t < 0.5 ? 'type' : 'color';
      const phaseT = t < 0.5 ? t * 2 : (t - 0.5) * 2; // 0→1 within each phase

      const phrase = workMsg;
      const tailText = state.turnStart ? ` [${fmtDuration(Date.now() - state.turnStart)}]` : '';
      const totalChars = phrase.length + tailText.length;
      const out = [];

      if (phase === 'type') {
        // Type the WHOLE row (phrase + tail) left → right, all in the grey.
        const typedCount = Math.floor(phaseT * totalChars);
        for (let i = 0; i < phrase.length; i++) {
          out.push(i < typedCount ? col(phrase[i], greyEsc) : ' ');
        }
        const tailTyped = Math.max(0, typedCount - phrase.length);
        for (let i = 0; i < tailText.length; i++) {
          out.push(i < tailTyped ? col(tailText[i], greyEsc) : ' ');
        }
        // The tail is already inside `out`, so do NOT append `elapsed` here.
        lines.push(col(frame, orangeEsc) + ' ' + out.join(''));
      } else {
        // Colour sweep: only the PHRASE goes grey → orange. The tail stays grey
        // (it is appended as the colored `elapsed` chunk after `out`).
        const BAND = bandCharsFor(phrase.length) / phrase.length;
        // head sweeps from the far edge of the band to the settle point, so the first
        // frame is untouched and the last has every character settled. See the
        // SWEEP_* block above for why the travel is `1 + BAND` and not `1 + 2*BAND`.
        const head = -BAND + phaseT * (1 + BAND * SWEEP_TRAVEL_PAD);
        // SETTLE, not pulse: a character the head has passed stays orange, so the
        // phrase FILLS IN left to right and ends fully orange. A travelling pulse here
        // was the bug — a pulse dims a character again after the band leaves it, so
        // the phase ended with the phrase DARK instead of orange (measured:
        // [ ] -> [ :#@#: ] -> [ :#] -> [ ]).
        const edge = state.shimmerEdge || (state.cfg && state.cfg.shimmerEdge) || 'cosine';
        for (let i = 0; i < phrase.length; i++) {
          const charAt = i / phrase.length;
          const tChar = sweepSettle(head - charAt, BAND, edge);
          const r = Math.round(GREY_RGB[0] + (ORANGE_RGB[0] - GREY_RGB[0]) * tChar);
          const g = Math.round(GREY_RGB[1] + (ORANGE_RGB[1] - GREY_RGB[1]) * tChar);
          const b = Math.round(GREY_RGB[2] + (ORANGE_RGB[2] - GREY_RGB[2]) * tChar);
          out.push(col(phrase[i], lerpColor(r, g, b, r, g, b, 0)));
        }
        lines.push(col(frame, orangeEsc) + ' ' + out.join('') + elapsed);
      }
      if ((Date.now() - state.startAnim.start) >= 1000) {
        state.startAnim = null;
        // The colour phase has just finished painting the phrase orange. Anchor
        // the pulse to THIS tick so its first frame is the orange start of the
        // orange -> yellow sweep, not a mid-cycle colour.
        state.pulseStart = state.spin || 0;
      }
    }
        // ---- turn-finish animation ----
    // 0.5s morph: `[turn took 1s]` grows in from the LEFT, covering the working
    // phrase one character at a time; once the phrase is fully covered, the
    // rest of the final text is simply appended. The whole row fades to grey.
    else if (state.finishAnim) {
      const DUR = 500;
      const t = Math.min(1, (Date.now() - state.finishAnim.start) / DUR);
      const wordFrom = state.finishAnim.wordFrom || '';
      const wordTo = state.finishAnim.wordTo || 'turn took';
      const tail = state.finishAnim.tail || '';   // ` <duration>]`, never changes
      // SWEEP: start from the LIVE word (`Working...`), pad it on the right to
      // the wider of the two words, then overwrite it left → right, one
      // character per step. Characters the sweep has not reached keep their OLD
      // value, so each `.` disappears on its own turn:
      //   [Working... 59s] → [turn to... 59s] → [turn too.. 59s] → [turn took 59s]
      // Width = the LONGER word, otherwise a longer old word gets truncated and
      // its trailing dots vanish at once.
      const width = Math.max(wordFrom.length, wordTo.length);
      const from = wordFrom.padEnd(width, '.');
      const toPadded = wordTo.padEnd(width, '');
      const done = t >= 1 ? width : Math.floor(t * width);   // chars overwritten so far
      let word = '';
      for (let i = 0; i < width; i++) {
        word += (i < done) ? (toPadded[i] || '') : from[i];
      }
      // Colour: orange → grey over the animation. Uses the SAME shared constants
      // so the row does not shift shade when the finish morph begins.
      const r = Math.round(ORANGE_RGB[0] + (GREY_RGB[0] - ORANGE_RGB[0]) * t);
      const g = Math.round(ORANGE_RGB[1] + (GREY_RGB[1] - ORANGE_RGB[1]) * t);
      const b = Math.round(ORANGE_RGB[2] + (GREY_RGB[2] - ORANGE_RGB[2]) * t);
      const animColor = lerpColor(r, g, b, r, g, b, 0);
      lines.push(col(frame, animColor) + ' ' + col('[', animColor) + col(word, animColor) + col(tail, greyEsc));
    } else {

      // Timing: SWEEP ticks per half-sweep, four halves per cycle (out to yellow,
    // back, out to red, back). The tick count lives in SWEEP_TICKS so every animated
    // row shares one smoothness budget — see the SWEEP_* block near the top.
    const SWEEP = SWEEP_TICKS;       // ticks per half-sweep
    const HALF  = SWEEP + SWEEP;     // ticks per colour (out + back)
    const CYCLE = HALF * 2;          // ticks for the full loop
    // Phase is measured from the tick the pulse BEGAN (state.pulseStart), not
    // from 0: the spinner has been running since turn start, so a raw
    // `spin % CYCLE` dropped the pulse into a mid-cycle colour (often the red
    // half) the instant the start animation handed over.
    // `??`, NOT `||` — the same trap as the tool-name sweep: a `pulseStart` of 0 is a
    // real anchor (the turn's first tick), and `0 || spin` collapses the cycle to 0, so
    // the row would sit on one colour forever instead of pulsing.
    const inCycle = ((spin - (state.pulseStart ?? spin)) % CYCLE + CYCLE) % CYCLE;
    const inHalf  = inCycle % HALF;       // position within this colour's half
    const phase   = inCycle < HALF ? 0 : 1; // 0 = yellow, 1 = red

    // Colours as plain RGB triples (never ANSI strings). ORANGE is the shared
    // constant so the pulse starts exactly where the start animation ended.
    const YELLOW = [255, 240, 120];
    const RED    = [255, 0, 0];    // pure red
    const target = phase === 0 ? YELLOW : RED;

    const chars = workMsg;
    const n = chars.length;
    // The band is sized once for this row; `framesPerChar(n)` is the resulting
    // smoothness, and 3+ frames is where a fade stops looking like a snap.
    const BAND = bandCharsFor(n) / n;

    // Interpolate orange ↔ target by `t` (0 = orange, 1 = target).
    const mix = (t) => {
      const k = Math.max(0, Math.min(1, t));
      return lerpColor(
          ORANGE_RGB[0] + (target[0] - ORANGE_RGB[0]) * k,
          ORANGE_RGB[1] + (target[1] - ORANGE_RGB[1]) * k,
          ORANGE_RGB[2] + (target[2] - ORANGE_RGB[2]) * k,
          ORANGE_RGB[0] + (target[0] - ORANGE_RGB[0]) * k,
          ORANGE_RGB[1] + (target[1] - ORANGE_RGB[1]) * k,
          ORANGE_RGB[2] + (target[2] - ORANGE_RGB[2]) * k,
          0,
      );
    };

    const out = [];
    // The pulse is TWO settles, not a ramp: the first takes every character from
    // orange to the phase's target (yellow or red), the second takes it back to
    // orange. Each runs its head from the far edge of the band to the settle point,
    // so:
    //
    //   first frame of a phase -> head is behind everything -> nothing swept yet
    //   last frame             -> head is past everything   -> every char settled
    //
    // That geometry is what makes the boundary seamless. The previous version started
    // the head at `1/SWEEP`, already PAST the first character, so the very first pulse
    // frame painted char 0 at 50% of the target right after the row had been fully
    // ORANGE — a visible jump on every handoff, and again at each half-cycle.
    // `/ (SWEEP - 1)`, not `/ SWEEP`: the first frame of a half must be progress 0
    // and its LAST frame progress 1, so every half starts untouched and ends fully
    // settled. Dividing by SWEEP left the final frame at (SWEEP-1)/SWEEP = 0.9, so the
    // sweep never quite completed and the row carried a 2% residue into the next half.
    const progress = (inHalf < SWEEP ? inHalf : inHalf - SWEEP) / (SWEEP - 1);
    const head = -BAND + progress * (1 + BAND * SWEEP_TRAVEL_PAD);
    const pulseEdge = state.shimmerEdge || (state.cfg && state.cfg.shimmerEdge) || 'cosine';
    for (let i = 0; i < n; i++) {
      const charAt = n > 0 ? i / n : 0;
      // Settled amount toward the target; the back-sweep is the same shape mirrored,
      // so it un-settles toward orange in the same left-to-right order.
      const settled = sweepSettle(head - charAt, BAND, pulseEdge);
      const t = inHalf < SWEEP ? settled : 1 - settled;
      out.push(col(chars[i], mix(t)));
    }
    lines.push(col(frame, orangeEsc) + ' ' + out.join('') + elapsed);
    }
  }

  if (!takeover && state.todos && state.todos.length) {
    // The panel's top rule is a DRAG HANDLE. Record its screen row as a hitbox so
    // the mouse handler can hover/press it; the row offset is corrected to final
    // screen coordinates by composeFrame's hitbox pass (like every other hit).
    const todoTopRow = lines.length;
    addHit(todoTopRow, 0, w - 1, { kind: 'todoResize' });
    for (const l of renderTodoPanel(state, w, state.todoResizeHover, state.todoResizeDrag)) lines.push(l);
  }

  // Queued (not yet sent) messages, directly above the composer: these are what
  // Ctrl-S steers into the running turn. See renderQueuePanel.
  if (!takeover && state.queued && state.queued.length) {
    // The panel's top rule is a DRAG HANDLE. Record its screen row as a hitbox so
    // the mouse handler can hover/press it.
    const queueTopRow = lines.length;
    addHit(queueTopRow, 0, w - 1, { kind: 'queueResize' });
    for (const l of renderQueuePanel(state, w, state.queueResizeHover, state.queueResizeDrag)) lines.push(l);
  }

  // Side-thread box (/btw), docked directly above the composer — the placement kimi
  // uses (its panelContainer sits over the editor with `connectedAbove = true`), so
  // the conversation being asked about stays visible while you keep typing.
  if (!takeover && state.btwPanel && state.btwPanel.turns && state.btwPanel.turns.length) {
    for (const l of renderBtwPanel(state, w, { terminalRows: h })) lines.push(l);
  }



    // Approval pending overlay - same width as the composer, placed above it.
  // The border characters are coloured INDIVIDUALLY and each content row is
  // padded to an exact inner width: colouring the whole row (as this used to)
  // also wrapped the padding in the border colour and left the right `│`
  // white and drifting inside the box next to the text.
  if (state.approvalPending && !dialog) {
    const ap = state.approvalPending;
    const promptW = insideW;
    // Content span: promptW - 2 leaves one padding space on each side, so the
    // row is exactly 1 + 1 + (promptW - 2) + 1 + 1 = promptW + 2 wide — the same
    // as the composer. Using promptW - 4 made the box 2 columns too narrow and
    // fitAnsi pushed the right border inward.
    const innerW = Math.max(1, promptW - 2);
    const bar = (ch) => col(ch, C.border);
    const boxRow = (content) => bar('│') + ' ' + fitAnsi(content, innerW) + ' ' + bar('│');
    const verb = col('Approve', C.white + C.bold);
    const cmd = col(ap.toolName + '?', C.cyan + C.bold);
    lines.push(bar('╭' + '─'.repeat(promptW) + '╮'));
    lines.push(boxRow(verb + ' ' + cmd));
    if (Array.isArray(ap.detail) && ap.detail.length) {
      for (const ln of ap.detail) {
        // Wrap by DISPLAY width so a wide/CJK glyph cannot push the border out.
        for (const seg of wrapWords(ln === '' ? ' ' : ln, innerW)) {
          lines.push(boxRow(col(seg, C.gray)));
        }
      }
    } else if (ap.desc) {
      for (const seg of wrapWords(ap.desc, innerW)) lines.push(boxRow(col(seg, C.gray)));
    }
    lines.push(boxRow(col('Enter approve | Ctrl+A approve for session | Esc reject', C.gray)));
    lines.push(bar('╰' + '─'.repeat(promptW) + '╯'));
  }

  // Plan review: shown once the model hands over a <|plan|> in Plan mode. Same box
  // shape as the tool approval above so the two read as the same kind of prompt.
  // It shows WHAT the plan will touch (step/file counts and the files named), so
  // approving is an informed decision rather than a guess from prose.
  if (state.planPending && !dialog) {
    const promptW = insideW;
    const innerW = Math.max(1, promptW - 2);
    const bar = (ch) => col(ch, C.border);
    const boxRow = (content) => bar('│') + ' ' + fitAnsi(content, innerW) + ' ' + bar('│');
    lines.push(bar('╭' + '─'.repeat(promptW) + '╮'));
    lines.push(boxRow(col('Review', C.white + C.bold) + ' ' + col('this plan', C.cyan + C.bold)));
    // The plan body is ALREADY shown in its table above — summarise it here.
    let review = [];
    try { review = reviewLines(state.planPending.plan, state.workspace); } catch { review = []; }
    for (const r of review) lines.push(boxRow(col(r, C.gray)));
    lines.push(bar('╰' + '─'.repeat(promptW) + '╯'));
  }
  
  let composerFirstRow = -1;
  if (!takeover) {
    composerFirstRow = lines.length + 1;
    // The composer carries the same 1-column left margin as the transcript, so its
    // walls line up exactly with a sent user/queue message's box.
    //   frame width = 1 (margin) + 1 (│) + cInner + 1 (│)  =>  cInner = w - 3
    // `insideW` (w-2) is the space BETWEEN the walls, so the margin is taken OUT of
    // it rather than added on top — otherwise the box came out 2 columns short.
    const CPAD = ' ';
    const cInner = Math.max(1, insideW - 1);
    // In shell mode the whole editor frame shifts to the violet shellMode hue
    // (same token kimi-code uses for its bash-mode border), so it reads as
    // "shell mode" rather than the cyan prompt frame.
    const shellBorder = state.inputMode === 'bash' ? C.shellMode : C.border;
    lines.push(CPAD + col('╭' + '─'.repeat(cInner) + '╮', shellBorder));
    for (let ri = 0; ri < composer.rows.length; ri++) {
      addHit(lines.length, 2, cInner, { kind: 'composerRow', rowIdx: ri });
      // Colour the prompt glyph like the transcript's user marker (cyan) and keep
      // the typed TEXT white. The prefix is the first `❯ ` of the row (the
      // continuation rows are padded with spaces instead).
      const rawRow = composer.rows[ri];
      const styledRow = highlightPasteMarkers(rawRow);
      // One space of padding after the left wall (and before the right wall), the
      // same as the transcript's user/queue boxes, so the geometry is identical.
      const pre = composerInput(state).prefix;
      const textW = Math.max(1, cInner - 2); // Original value: 1+1+textW+1+1 = 60 with pre=2, fitWidth=55
      // Apply composer text selection highlight if a selection is active.
      const sel = state.composerSel;
      const rowMeta = composer.meta[ri] || {};
      let rowAnsi;
      if (rawRow.startsWith(pre)) {
        const textPart = styledRow.slice(pre.length);
        const textStart = rowMeta.start != null ? rowMeta.start : 0;
        const highlighted = (sel && sel.anchor !== sel.head)
          ? highlightSelection(textPart, textStart, sel.anchor, sel.head)
          : textPart;
        // The `!` (shell mode) prefix is BOLD: it is a mode marker, not punctuation,
        // and it should out-weigh the `❯` prompt glyph at a glance.
        const preCol = state.inputMode === 'bash' ? (C.shellMode + C.bold) : C.cyan;
        rowAnsi = ' ' + col(pre, preCol) + C.white +
          fitAnsi(highlighted, Math.max(1, textW - visualCol(pre))) + ' ';
      } else {
        const textStart = rowMeta.start != null ? rowMeta.start : 0;
        const highlighted = (sel && sel.anchor !== sel.head)
          ? highlightSelection(styledRow, textStart, sel.anchor, sel.head)
          : styledRow;
        rowAnsi = ' ' + C.white + fitAnsi(highlighted, textW) + ' ';
      }
      lines.push(
        CPAD + col('│', shellBorder) + rowAnsi + C.reset + col('│', shellBorder)
      );
    }
    lines.push(CPAD + col('╰' + '─'.repeat(cInner) + '╯', shellBorder));
  }

  
  const MPAD = ' ';
  const mInner = Math.max(1, insideW - 3);
  const menuRow = (content) => MPAD + col('│', C.border) + ' ' + fitAnsi(content, mInner) + ' ' + col('│', C.border);
  if (state.menuOpen && state.menuList.length && !takeover) {
    const totalMatches = state.menuList.length;
    const sel = state.menuSel + 1;
    const off = state.menuOffset || 0;
    const shown = state.menuList.slice(off, off + MAX_MENU);
    // The second level lists ARGUMENT words, whose `name` is only the completion
    // SUFFIX. Showing "reshold" for `/auto-trim th` would be nonsense, so the row
    // displays the WHOLE word (prefix + suffix) while still inserting just the
    // suffix. `_argWord` marks which level a row belongs to.
    const isArgLevel = shown.some((c) => c._argWord);
    shown.forEach((cmd, j) => {
      const selected = off + j === state.menuSel;
      const mark = selected ? col('❯ ', C.cyan) : '  ';
      const label = isArgLevel && cmd._argWord
        ? (cmd._argPrefix || '') + cmd.name
        : cmd.name;
      const nameField = col(label, selected ? (C.cyan + C.bold) : C.gray);
      const hint = cmd.argumentHint ? col(' ' + cmd.argumentHint, C.gray) : '';
      const pad = Math.max(2, 18 - visualCol(label) - visualCol(hint));
      const desc = col(cmd.desc, C.gray);
      addHit(lines.length, 2, mInner, { kind: 'menuItem', index: off + j });
      lines.push(menuRow(mark + nameField + hint + ' '.repeat(pad) + desc));
    });
    const footer = isArgLevel
      ? `(${sel}/${totalMatches})  Enter or Tab to insert · Esc to dismiss`
      : `(${sel}/${totalMatches})`;
    lines.push(menuRow(col(footer, C.gray)));
  }

  // Inline `@file` candidate list — the same widget as the `/` menu above, so the
  // two read as one mechanism. Shows the path, dims the directory prefix of a
  // nested entry so the BASENAME is what your eye lands on.
  if (state.mentionOpen && state.mentionList.length && !takeover && !state.menuOpen) {
    const totalMatches = state.mentionList.length;
    const sel = state.mentionSel + 1;
    // Render the VISIBLE WINDOW, but decide "is this row the selected one" by the
    // entry's GLOBAL index. The window start is re-derived here from the selection
    // rather than trusted from state: whatever offset the caller left behind, the
    // selected row is inside the slice, so it is always the one that highlights.
    const off = windowOffset(state.mentionSel, state.mentionOffset, totalMatches);
    const shown = state.mentionList.slice(off, off + MAX_MENU);
    shown.forEach((it, j) => {
      const globalIndex = off + j;
      const selected = globalIndex === state.mentionSel;
      const mark = selected ? col('❯ ', C.cyan) : '  ';
      const rel = String(it.rel || it.label || '');
      const isDir = !!it.isDir;
      // The SELECTED row highlights its WHOLE path; unselected rows use the dim
      // colour. Previously the part before the last `/` was always rendered dim,
      // so a selected `src/tools/` showed bright `tools/` next to a grey `src/` —
      // even though the very same `src/` was bright when it was selected itself.
      // That inconsistency is what the per-segment split caused; there is no
      // longer a split, so the row reads as one selected (or unselected) item.
      const label = col(rel, selected ? (C.cyan + C.bold) : C.gray);
      const pad = Math.max(2, 40 - visualCol(rel));
      addHit(lines.length, 2, mInner, { kind: 'mentionItem', index: globalIndex });
      lines.push(menuRow(mark + label + ' '.repeat(pad)));
    });
    lines.push(menuRow(col(`(${sel}/${totalMatches})  Enter or Tab to insert · Esc to dismiss`, C.gray)));
  }

  const cwd = state.cwd || '';
  // Thinking suffix: "<model> thinking <level>". The level is shown whenever one
  // is set (including 'on', which used to be elided and made the footer unable to
  // tell "on" apart from "no level selected"). A model whose thinking is supported
  // but has no chosen level still reads just "thinking".
  const thinkLevel = state.effort && state.effort !== 'off' ? String(state.effort) : '';
  const thinking = state.reasoning
    ? (thinkLevel ? ` thinking ${thinkLevel}` : ' thinking')
    : state.seenThinking ? ' thinking' : '';
  const label = state.modelLabel || state.model || '';
  // Plan / Focus / Swarm are mutually exclusive modes, so at most one badge is
  // shown. Swarm uses a spring-green (cyan shifted toward green) to stay in the
  // theme family while reading as its own thing next to Plan's cyan.
  const modeBadge = state.plan ? col('Plan', C.cyan + C.bold)
    : state.focus ? col('Focus', C.blue + C.bold)
    : state.swarm ? col('Swarm', C.spring + C.bold)
    : '';
  const parts = [];
  // Track the column range of the two fields made CLICKABLE (mode group and model),
  // so this row can register hitboxes for them. Everything else stays decoration.
  const statusRow = lines.length;        // the status line's frame row
  const slHits = [];                     // { col0, col1, kind }
  let slCol = 0;                         // running visual column
  const pushPart = (text, hit) => {
    if (parts.length) slCol += 2;        // parts are joined with two spaces
    const cw = visualCol(text);
    if (hit) slHits.push({ ...hit, col0: slCol, col1: slCol + cw - 1 });
    slCol += cw;
    parts.push(text);
  };
  // The permission mode and the Plan/Focus badge are both "what mode am I in",
  // so they read as ONE group: separated by a single space. Everything after the
  // group gets the normal two-space divider, so a name that already contains a
  // space is not mistaken for the group boundary:
  //   Auto Plan  workbuddy/deepseek-v4.1-flash  D:\hncode
  let modeGroup = state.slMode !== false ? col(modeLabel(state.mode), C.orange + C.bold) : '';
  if (modeBadge) modeGroup = modeGroup ? modeGroup + ' ' + modeBadge : modeBadge;
  if (modeGroup) pushPart(modeGroup, { kind: 'statusMode' });
  if (state.slModel !== false && label) {
    const think = state.slEffort !== false ? thinking : '';
    pushPart(col(`${label}${think}`, C.white), { kind: 'statusModel' });
  }
  if (state.slTasks !== false) {
    // Two SEPARATE badges, mirroring kimi-code's footer: `bashTasks` counts
    // background processes and `agentTasks` counts background subagents. They are
    // semantically different (you wait on a command, you read an agent's report),
    // so kimi keeps them apart and so do we. Only RUNNING tasks are counted — a
    // finished task leaves the badge, which is what makes it a live indicator
    // rather than a running total. `bg N→M` used to conflate both kinds and also
    // showed a stale count after everything finished.
    const ts = Object.values(state.tasks || {});
    const running = ts.filter((t) => t.status === 'running');
    const bashTasks = running.filter((t) => t.kind !== 'agent').length;
    const agentTasks = running.filter((t) => t.kind === 'agent').length;
    if (bashTasks > 0) parts.push(col(`[${bashTasks} task${bashTasks === 1 ? '' : 's'} running]`, C.cyan));
    if (agentTasks > 0) parts.push(col(`[${agentTasks} agent${agentTasks === 1 ? '' : 's'} running]`, C.spring));
  }
  if (state.slCwd !== false && cwd) parts.push(col(cwd, C.gray));
  // GIT badge: branch, then the working-tree diff totals. Placed AFTER the path so
  // it reads as "where I am → what branch → how much is uncommitted". Rendered
  // from state._gitInfo, which a 15s timer and turn-end refresh — the render path
  // itself never spawns git (see refreshGitInfo).
  if (state.slGit !== false) {
    const gi = state._gitInfo;
    if (gi && gi.branch) {
      // Branch name: pale yellow + bold. Branch and its diff are ONE part, joined
      // by a SINGLE space, so it reads as `main +1 -1` (tight). The outer
      // parts.join('  ') uses two spaces, so this still separates the git badge
      // from the path/model with two spaces while keeping branch↔diff at one.
      let badge = C.bold + col(gi.branch, C.branch);
      if (gi.insertions || gi.deletions) {
        // Two colours so the direction is readable at a glance: +N green, -N red.
        const bits = [];
        if (gi.insertions) bits.push(col(`+${gi.insertions}`, C.green));
        if (gi.deletions) bits.push(col(`-${gi.deletions}`, C.red));
        badge += ' ' + bits.join(' ');
      }
      // Push it, or the whole git segment — branch AND `+N -N` — is computed and
      // thrown away: the badge silently vanished from the statusline when the
      // pushPart refactor dropped this line.
      parts.push(badge);
    }
  }
  const statusLeft = parts.join('  ');
  // The session tallies — cost, turns, steps, tokens/sec — ride the RIGHT of this row. They
  // used to trail the context row as one string, which crowded the composition numbers
  // together with the context gauge; here they sit with the other session figures and the
  // tip moves down to the last row, beside the notice.
  //
  // The cost segment is conditional for two reasons: the provider must have reported tokens
  // AND the model must have prices (its own entry or the models.dev catalog). Either one
  // missing would mean inventing the number, so it is omitted rather than shown as `0$`,
  // which reads as "this was free".
  const costSeg = state._costText ? `${state._costText} cost | ` : '';
  const countsRight = col(`${costSeg}${state.rounds} turn${state.rounds === 1 ? '' : 's'} | ${state.steps} step${state.steps === 1 ? '' : 's'} | ${Math.round(state.tokRate)} tok/s`, C.white);
  const statusRight = countsRight;
  // Plugin TUI widgets render into the status bar's right side.
  try { const wid = renderWidgets(); if (wid) statusRight && (statusRight += '   '); if (wid) statusRight = (statusRight || '') + wid; } catch {}
  lines.push(justify(statusLeft, statusRight, w));
  // Clickable status fields: the mode group opens /permissions, the model name
  // opens /model. Registered on the row just pushed; hover comes free from the
  // generic hover tint (any hitbox is tinted unless it is a composerRow).
  for (const h of slHits) addHit(statusRow, h.col0, h.col1, { kind: h.kind });

  // The context row is now a BAR: the window's composition as colour, with the same
  // `context: 12% (11.7k/97.7k)` text set into the free segment's right edge. The wording
  // is unchanged from the string this replaces — only its carrier changed from a line of
  // text to the tail of a bar, so nothing that was readable stops being readable.
  //
  // `contextSegments` is the cached per-content-type breakdown. It is a cache rather than a
  // per-frame walk because the walk is O(messages) with a token estimate each, which on a
  // long transcript is the single most expensive thing the frame could do — and the
  // numbers only move when the conversation does.
  //
  // No bar when the window is unknown: a bar claiming to be full is worse than no bar, and
  // `ctxMax` is 0 until the first usage report lands.
  const ctxText = `context: ${state.ctxPercent}% (${fmtTokens(state.ctxTokens || 0)}/${fmtTokens(state.ctxMax || 1)})`;
  const ctxSegs = contextSegments(state, state.cfg);
  const barRow = lines.length;
  const bar = state.ctxMax > 0
    ? renderContextBar(ctxSegs, state.ctxTokens || 0, state.ctxMax, w, ctxText)
    : { text: '', hits: [] };
  lines.push(bar.text || ' '.repeat(w));
  // Every segment is a hover target, INCLUDING one too narrow to carry a label: pointing at
  // it is then the only way to read what it is, which is why `renderContextBar` returns the
  // spans rather than the bar alone.
  for (const hit of bar.hits) {
    addHit(barRow, hit.col0, hit.col1, { kind: 'ctxSegment', data: hit.data });
  }

  // The last row: a hovered segment's caption, else the short-lived notice, on the left; the
  // tip on the right. The caption takes precedence because it answers what the pointer is
  // asking, and it stays for as long as the pointer rests on that segment.
  //
  // The hover is resolved HERE, at paint time, so the caption and the highlight on the bar
  // can never disagree — the two come out of the same hit list in the same pass.
  // Read from THIS pass's own hit list, not `state._hitboxes`: the bar's segments are
  // registered a few lines above, so the hit being resolved is one this frame just created.
  // Reading the previous frame's list made the caption lag the pointer by a repaint.
  const barHover = resolveHoverHit(state, hits);
  const segCaption = (barHover && barHover.kind === 'ctxSegment' && barHover.row === barRow)
    ? segmentCaption(barHover.data, ctxSegs[barHover.data] || 0)
    : '';
  const tipText = (state.slTips !== false && state.tip) ? col(state.tip, C.gray) : '';
  // The confirm prompt takes this slot ahead of the hover caption and the notice. It is the
  // one thing on screen that must not be missed, and a slot already exists: the left of the
  // tip row. Giving it a row of its own pushed the bar up and moved the notice out of the
  // place the eye already looks for it.
  const leftText = state.confirmExit
    ? col(fitAnsi('Press Ctrl+C again to exit', w - visualCol(tipText) - 2), C.yellow)
    : (segCaption
      ? col(segCaption, C.white)
      : (noticeH ? col(state.notice, state.noticeKind === 'error' ? C.red : C.gray) : ''));
  lines.push(justify(leftText, tipText, w));


  // Normalize EVERY row to exactly `w` columns BEFORE anything composites onto it.
  //
  // The transcript's blank filler rows are EMPTY strings, not runs of spaces, and the
  // frame is only padded to full width by the `fitAnsi` pass at the very END of this
  // function. Any pass that works in COLUMNS therefore saw fewer columns than the
  // screen does: the picker's backdrop dimming, its gutter blanking and the hover tint
  // all run before that final pad, so on a SHORT transcript — a fresh session, where
  // most of the body is filler — their column ranges fell past the end of the row and
  // silently did nothing. The visible symptom was the modal backdrop coming out
  // un-dimmed around the card, which is the very thing that makes a popup read as
  // focused.
  //
  // Padding here fixes dim/blank/tint together and makes the invariant explicit: from
  // this point on, column N of a row IS screen column N. The final `fitAnsi` pass then
  // has nothing left to do for width (an `w`-wide row is returned unchanged).

  for (let i = 0; i < lines.length; i++) lines[i] = fitAnsi(lines[i] == null ? '' : lines[i], w);
  let topPad = 0;
  if (lines.length < h) { topPad = h - lines.length; }
  while (lines.length < h) lines.unshift(' '.repeat(w));
  let topTrim = 0;
  if (lines.length > h) { topTrim = lines.length - h; lines.splice(0, topTrim); }
  // An OPEN OVERLAY ABSORBS THE POINTER. Every control the frame registered while the
  // transcript / composer / status line was drawn belongs UNDER the card, and leaving
  // those hitboxes in place left holes in it:
  //
  //   * a pointer inside the card at a row that lines up with the composer or the
  //     status line resolved to THAT control, so the tint was applied to text BEHIND
  //     the popup and showed through it;
  //   * a CLICK there ran the control behind the card — clicking a menu row could put
  //     the caret in the composer instead.
  //
  // The card's own targets are registered last, so keeping only the hits that overlap
  // the card's row span leaves exactly what a modal dialog should expose. The
  // scrollbar, todo and queue resize handles (also registered earlier) go with it.
  const overlayRows = overlayCardRows
    ? { from: overlayCardRows[0] + topPad - topTrim, to: overlayCardRows[1] + topPad - topTrim }
    : null;
  const hitboxes = hits
    .map((hb) => ({ ...hb, row: hb.row + topPad - topTrim }))
    .filter((hb) => hb.row >= 0 && hb.row < h)
    .filter((hb) => !overlayRows || (hb.row >= overlayRows.from && hb.row <= overlayRows.to));
  // The body's screen origin needs the SAME correction the hitboxes just got:
  // rows pushed above it (topPad) and any trimmed off the top both move it. It is
  // adjusted here because only at this point is the final geometry known.
  if (state._bodyScreenTop != null) state._bodyScreenTop += topPad - topTrim;

  // NOTE: the hover tint is applied AFTER the picker's cell layer, further down. It used
  // to run here, and the picker repainted the card over the row it had just tinted — the
  // card is opaque now, so every hover highlight inside it was erased again in the same
  // frame, which is why hovering a picker item stopped showing anything.

  let cursor;
  let cursorVisible;
  if (dialogCaret) {
    // A dialog is drawn at the TOP of the frame: the filler rows go BELOW it
    // (topPad) and nothing is trimmed off the top. The caret row is relative to
    // the dialog body, so it MUST be shifted by that same pad — without it the
    // block caret landed `topPad` rows too high (the editor's title / rule / hint
    // sit above the body, which is exactly the one row it was off by on
    // /personal and /set-system-prompt). The hitboxes below already apply the pad;
    // the caret did not.
    cursor = { row: Math.min(dialogCaret.row + topPad, h - 1), col: Math.min(dialogCaret.col, w - 1) };
    cursorVisible = true;
  } else if (questionCaret) {
    // The AskUserQuestion box sits MID-frame (chat above, composer below), so its
    // caret row is an absolute frame index: apply the SAME `topPad - topTrim`
    // correction the hitboxes got, or the block caret lands rows off when the
    // frame was padded/trimmed.
    cursor = {
      row: Math.max(0, Math.min(questionCaret.row + topPad - topTrim, h - 1)),
      col: Math.min(questionCaret.col, w - 1),
    };
    cursorVisible = true;
  } else if (dialog) {
    cursor = { row: 0, col: 0 };
    cursorVisible = false;
  } else {
    const menuH = (state.menuOpen && state.menuList.length && !dialog)
      ? Math.min(state.menuList.length, MAX_MENU) + 1 : 0;
    // The `@file` list occupies the same rows as the `/` menu, and it pushes the
    // composer UP by exactly that many. This formula derives the caret's screen row
    // from the chrome BELOW the composer, so leaving the list out of `bottomChrome`
    // kept the caret at its old row while the input box moved up — the caret sat
    // several rows below the text it was editing. Must mirror `mentionItems` in the
    // layout budget above.
    const mentionH = (state.mentionOpen && state.mentionList.length && !dialog)
      ? Math.min(state.mentionList.length, MAX_MENU) + 1 : 0;
    // The confirm prompt is NOT a term here: it shares the tip row, which is already inside
    // STATUS_H, so counting it made the caret jump up a line every time Ctrl+C was pressed.
    const bottomChrome = STATUS_H + CTX_H + menuH + mentionH;
    const caretScreenRow = h - bottomChrome - 2 - (composer.rows.length - 1 - composer.caretRow);
    cursor = {
      row: Math.max(0, Math.min(caretScreenRow, h - 1)),
      col: Math.min(composer.caretCol + 2, w - 1),
    };
    cursorVisible = true;
  }

  // Modal backdrop + the card's cell layer. Both run LAST, once every row of the frame
  // exists — the composer, the status line and the context row are pushed onto `lines`
  // well after the card was measured, so painting the card here put it past the end of
  // the array and had those rows painted over it (the card appeared clipped on tall
  // terminals), and dimming here is the only way to reach those rows at all.
  //
  // Order matters and mirrors OpenTUI's two-pass model: dim the scene, THEN composite
  // the card over it. Dimming after the card went on would fade the card's own text.
  if (pickerCard) {
    // The frame geometry is only final here: `topPad` rows were pushed above and
    // `topTrim` were trimmed off, so the card's recorded row takes the same correction
    // the hitboxes do.
    const at = pickerCard.at + topPad - topTrim;
    // The card's columns, plus the one-column gutter on each side. The card's own
    // padding lives inside `boxW`, so without this the transcript's last glyph before
    // the card lands in the column DIRECTLY against the panel edge and reads as clipped
    // by it. Clearing that column turns the edge into a margin, which is how a floating
    // surface is meant to look: the text stops, then the panel starts.
    const gutterL = pickerCard.padLeft - 1;
    const gutterR = pickerCard.padLeft + pickerCard.boxW;
    // Pass 1 — recede the backdrop. The card's own cells are left alone; only the
    // columns AROUND it are dimmed, so it reads as a hole punched in a dimmed screen.
    for (let r = 0; r < lines.length; r++) {
      if (lines[r] == null) continue;
      const inCard = r >= at && r < at + pickerCard.height;
      if (!inCard) { lines[r] = dimRange(lines[r], 0, w); continue; }
      lines[r] = dimRange(dimRange(lines[r], 0, pickerCard.padLeft), pickerCard.padLeft + pickerCard.boxW, w);
      // The gutters are cleared AFTER the dimming, never before: blanking resets a
      // cell's style, so a blank written first would simply be dimmed again.
      if (gutterL >= 0) lines[r] = blankRange(lines[r], gutterL, gutterL + 1);
      if (gutterR < w) lines[r] = blankRange(lines[r], gutterR, gutterR + 1);
    }
    // Pass 2 — composite the card's cell layer over the dimmed backdrop. Every cell of
    // the card is opaque, so it fully covers its own columns; the flanks the layer does
    // not reach keep the dimmed transcript.
    for (let i = 0; i < pickerCard.layer.length; i++) {
      const r = at + i;
      if (r < 0 || r >= lines.length) continue;
      lines[r] = drawFrameBuffer(lines[r] == null ? ' '.repeat(w) : lines[r], pickerCard.layer[i], pickerCard.padLeft);
    }
  }

  if (state.hoverHit) {
    // The hover target is a SCREEN ROW captured when the mouse last moved, and it is
    // only updated by the next mouse event — so a repaint that moves content under a
    // stationary pointer left the highlight on whatever text slid into that row
    // (hover a line, let a streamed reply or an interrupt notice arrive, and unrelated
    // text kept the tint). Resolve against the LAST POINTER POSITION using THIS frame's
    // hitboxes instead, and when there is no pointer data to resolve with, DROP the
    // highlight: a stale screen row is never a safe thing to draw from.
    //
    // It runs after the picker layer on purpose: the card is opaque, so tinting first
    // and painting the card over it hid the highlight completely.
    const hv = resolveHoverHit(state, hitboxes);
    if (hv && hv.row >= 0 && hv.row < lines.length) {
      // `col1` is the LAST included column (see hitAt), but tintRange takes a
      // half-open [col0, col1) range — without the +1 the final column of every
      // hover target stayed un-tinted.
      lines[hv.row] = tintRange(lines[hv.row], hv.col0, hv.col1 + 1);
    }
  }

  let padded = lines.map((l) => fitAnsi(l, w));
  // Mixin seam: beforeRender - plugins may rewrite the painted lines. Runs before the
  // ANSI string is built so the change actually reaches the screen.
  try { const out = runPatchSync('beforeRender', { lines: padded, state, cols: w, rows: h }, (c) => c); if (out && Array.isArray(out.lines)) padded = out.lines; } catch (e) {}
  // Draw the block caret ourselves (composer OR dialog field / search box) and
  // keep the hardware cursor hidden for the whole session: the differential
  // painter writes full-width rows while scrolling, and the terminal parks its
  // own cursor at the end of the screen for a frame — which read as the caret
  // flickering between the input box and the bottom row.
  if (cursorVisible && cursor.row >= 0 && cursor.row < padded.length) {
    padded[cursor.row] = caretBlock(padded[cursor.row], cursor.col);
  }
  const cursorShape = hideCursor();

  const ansi = `\x1b[H` + padded.join('\n')
    + `\x1b[${cursor.row + 1};${cursor.col + 1}H` + cursorShape;
  let _frame = { ansi, lines: padded, cursor, cursorVisible, width: w, height: h,
           cursorRow: cursor.row, cursorCol: cursor.col, cursorShape, hitboxes, composerMeta: composer.meta };
  // Mixin seam: afterRender - plugins may modify the final frame (overlay, banner).
  try { const out = runPatchSync('afterRender', { frame: _frame, state }, (c) => c); if (out && out.frame) _frame = out.frame; } catch (e) {}
  return _frame;
}

// Differential paint: emit cursor-positioning + content for ONLY the rows whose
// content changed since `prev`. This is what keeps redraws flicker-free and
// cheap (kimi-code's pi-tui does the same). A full repaint happens on first
// paint and whenever the terminal size changes.
//
// WHY EVERY ROW ENDS WITH A CARRIAGE RETURN
// -----------------------------------------
// A terminal sets its "pending wrap" flag when a printed character fills the LAST
// column, and the next printable character then wraps to the following line. Every row
// composeFrame produces is exactly `cols` columns wide on purpose (the frame is padded),
// so writing one fills that column EVERY time. POSIX says the next cursor movement
// cancels the flag, and xterm and Windows Terminal honour that — but not all emulators
// do, and the failure is nasty: the next row's first character wraps, everything after
// it shifts down a line, and because this painter compares against the frame it BELIEVES
// it painted, the mess is never repaired. It surfaces as a few characters of the last
// reply stranded on screen (sometimes a lone wide glyph like `通`, sometimes a stray
// `a` or `7`) that disappear only when something forces a full repaint — re-entering the
// session, or a resize.
//
// `\r` is the one cursor move every terminal implements, and clearing the flag on CR is
// what xterm's own `do_cr` does. It costs one byte per written row and cannot move
// anything that matters, because each row is preceded by its own absolute address.
const CR = '\r';
// Synchronized output: the terminal holds the frame until END, so a repaint that
// rewrites 30 rows lands as one update instead of 30 visible steps.
const SYNC_BEGIN = '\x1b[?2026h';
const SYNC_END = '\x1b[?2026l';
export function diffFrame(prev, next) {
  let shape = '';
  if (!prev || prev.cursorShape !== next.cursorShape) shape = next.cursorShape;
  const pos = `\x1b[${next.cursorRow + 1};${next.cursorCol + 1}H`;

  // Synchronized output (DEC 2026) is wrapped around every write only when the
  // terminal said it knows the mode (see terminalCaps): a terminal that does not
  // implement it is supposed to ignore the private mode, but on a frame of ~30 rows
  // that is two sequences written per repaint on nothing more than a promise.
  const before = syncOutputUsable() ? SYNC_BEGIN : '';
  const after = syncOutputUsable() ? SYNC_END : '';

  const sizeChanged = !prev || prev.width !== next.width || prev.height !== next.height;
  if (sizeChanged) {
    let out = before;
    for (let i = 0; i < next.lines.length; i++) out += `\x1b[${i + 1};1H\x1b[2K` + next.lines[i] + CR;
    out += after + pos + shape;
    return out;
  }

  const maxLines = Math.max(prev.lines.length, next.lines.length);
  let first = -1, last = -1;
  for (let i = 0; i < maxLines; i++) {
    const a = i < prev.lines.length ? prev.lines[i] : '';
    const b = i < next.lines.length ? next.lines[i] : '';
    if (a !== b) { if (first === -1) first = i; last = i; }
  }
  if (first === -1) {
    return pos + shape;
  }

  let out = before;
  // Only [first, last] changed; rewriting to the bottom of the screen made a
  // single appended line repaint the whole viewport every frame.
  //
  // Every row is addressed ABSOLUTELY (`ESC[<n>;1H`). This used to write the
  // first row absolutely and then advance with `\r\n`, which is a RELATIVE move
  // that SCROLLS the screen once the line feed happens on the last terminal row
  // (or with the cursor past the bottom margin). The Working/pulse row sits
  // directly above the composer's `╭` border, so a repaint span reaching it
  // scrolled everything up by a row and the next `ESC[2K` erased the composer's
  // top border — "Working… gets written on the next line and overwrites the
  // input box". Absolute addressing cannot scroll, so the span is now safe.
  const reach = Math.min(next.lines.length, last + 1);
  for (let i = first; i < reach; i++) out += `\x1b[${i + 1};1H\x1b[2K` + next.lines[i] + CR;
  // No "clear the trailing rows" pass is needed: composeFrame always returns
  // EXACTLY `rows` lines (both frames here share the same height, otherwise the
  // sizeChanged path above would have run), so a shrinking viewport is already
  // handled by `last` moving up and the freed rows being rewritten as blanks.
  out += after;
  out += pos + shape;
  return out;
}


function renderFieldValue(field, active) {
  const val = field.value || '';
  if (field.kind === 'mask') {
    const masked = '•'.repeat(val.length);
    return active ? col(masked || ' ', C.white) : col(masked, C.white);
  }
  return active ? col(val || ' ', C.white) : col(val, C.white);
}
function fieldCaretCol(field, active) {
  const val = field.value || '';
  const shown = field.kind === 'mask' ? '•'.repeat(val.length) : val;
  const c = Math.max(0, Math.min(shown.length, field.caret || 0));
  return visualCol(shown.slice(0, c));
}
// ---- prompt history (persisted across restarts) -----------------------------
// Kept in the hncode config directory so the history survives a restart; the
// in-memory array alone meant every relaunch started with an empty ↑ list.
const HISTORY_MAX = 500;

function historyFile() {
  try {
    return path.join(path.dirname(hncodeConfigFile()), 'history.json');
  } catch {
    return path.join(os.homedir(), '.hncode', 'history.json');
  }
}

export function loadHistory() {
  try {
    const raw = fs.readFileSync(historyFile(), 'utf8');
    const arr = JSON.parse(raw);
    if (!Array.isArray(arr)) return [];
    return arr.filter((x) => typeof x === 'string' && x.trim() !== '').slice(-HISTORY_MAX);
  } catch {
    return [];
  }
}

export function saveHistory(list) {
  try {
    const file = historyFile();
    fs.mkdirSync(path.dirname(file), { recursive: true });
    // Newest last, capped, and de-duplicated while keeping order.
    const seen = new Set();
    const out = [];
    for (const x of (list || []).slice(-HISTORY_MAX)) {
      if (typeof x !== 'string' || !x.trim()) continue;
      if (seen.has(x)) continue;
      seen.add(x);
      out.push(x);
    }
    fs.writeFileSync(file, JSON.stringify(out, null, 0), 'utf8');
  } catch { /* history is a convenience; never break the session over it */ }
}

// ---- state factory ----
export function makeState({ cfg, session, opts }) {
  const cwd = session.workspace || cfg.workspace || process.cwd();
  // The session's thinking level. Restored from the session (so a resume keeps the
  // level the user picked), else the config's, else the plain on/off implied by
  // `reasoning`. `state.reasoning` is DERIVED from it rather than read off
  // `cfg.reasoning` alone: a resumed session whose effort is 'on' left
  // `reasoning` false, so the status line omitted "thinking on" until the model
  // was re-picked (setEffort is the only other writer, and it sets both).
  const effort = (session && session.effort) || cfg.effort || (cfg.reasoning ? 'on' : 'off');
  return {
    workspace: cwd,
    cfg,
    // The SAME session local this function already reads for `effort`, kept on the state
    // so the module-level renderers can reach the conversation: `composeFrame` receives
    // only `(state, cols, rows)` and has no closure over startTUI's locals.
    session: session || null,
    provider: cfg.provider || '',
    provider: cfg.provider || '',
    model: cfg.model || '',
    // REDUCED MOTION and the sweep-edge shape are copied onto the STATE, not read
    // from `cfg` at render time: `composeFrame(state, …)` only receives the state,
    // and `cfg` is a closure variable inside startTUI. Everything else that the
    // renderer needs from configuration does the same (see `state.experiments`).
    reducedMotion: !!cfg.reducedMotion,
    shimmerEdge: cfg.shimmerEdge || 'cosine',
    // How much of the display-only transcript is written to disk. These rows — a notice, a
    // warning, a compaction result, a reasoning block — have no home in `session.messages`,
    // because that array is what gets SENT to the model; a `/save-history off` session
    // simply does not keep them. `undefined` on the session means the default (on), so an
    // older file is not read as "off".
    saveHistory: !(session && session.saveHistory === false),
    // Reasoning is split out because it is the bulk of the cost: a long session's file
    // grows by more than its own answers. `/save-history nothinking` keeps the notices and
    // drops the chains.
    saveThinking: !(session && session.saveThinking === false),
    modelLabel: modelLabel(cfg) || cfg.model || '',
    // CLI flags win; otherwise resume whatever the session was left in.
    mode: opts.auto ? 'auto' : opts.yolo ? 'yolo' : ((session && session.mode) || 'ask'),
    reasoning: effort !== 'off',
    seenThinking: false,
    expanded: false,
    todos: (session && Array.isArray(session.todos)) ? session.todos : [],
    todosExpanded: false,
    cwd,
    cwdOverride: null,
    tip: '',
    ctxPercent: 0,
    ctxTokens: 0,
    ctxMax: cfg.maxContextTokens || 512000,
    rounds: (session && session.rounds) || 0,
    turnStart: 0,
    steps: (session && session.steps) || 0,
    lastTurnMs: (session && session.lastTurnMs) || 0,
    // Step-size history for /usage's trend chart, persisted on the session so it
    // survives a --resume (in-memory only otherwise). Bounded at write time.
    tokenHistory: (session && Array.isArray(session.tokenHistory)) ? session.tokenHistory.slice() : [],
    _stepsBase: 0,
    _turnSteps: 0,
    // How many times the session-naming request has been tried this run. Capped
    // so a permanently failing namer does not pay for a request every turn (see
    // the `needsTitle` block in runAgent).
    titleAttempts: 0,
    tokRate: 0,
    chat: [],
    scroll: 0,
    selection: null,
    sbDrag: false,
    sbDragOffset: 0,
    sbHover: false,
    // Todo panel resize: the top rule is a drag handle. `todoRows` is the
    // manual row count (undefined = automatic), and the two flags drive its
    // hover/press styling.
    todoRows: undefined,
    todoResizeHover: false,
    todoResizeDrag: false,
    todoResizeStart: null,
    // Queue panel resize: the top rule is a drag handle. `queueRows` is the
    // manual row count (undefined = automatic), and the two flags drive its
    // hover/press styling.
    queueRows: undefined,
    queueResizeHover: false,
    queueResizeDrag: false,
    queueResizeStart: null,
    // Turn-start animation: while non-null, the Working row renders the typing
    // and color-fill animation for 1s before starting the normal pulse cycle.
    startAnim: null,   // { start }
    hoverHit: null,
    input: '',
    caret: 0,
    // 'prompt' (talk to the model) or 'bash' (run the line in the shell). Typing
    // `!` on an empty composer flips this; the `!` itself never enters `input`.
    // See composerInput() for why that matters.
    inputMode: 'prompt',
    composerSel: null,
    pastes: new Map(),
    pasteCounter: 0,
    queued: [],
    running: false,
    spin: 0,
    workMsg: WORKING_MESSAGES[0],   // chosen once per turn
    // (swarm state is set below from the session — see the `swarm:` line after
    // plan/focus, so it is read from ONE place.)
    // Turn-finish animation: while non-null, the Working row renders the morph
    // from `from` to `to` (see composeFrame). Cleared ~0.5s after turn end.
    // Turn-finish animation: while non-null, the Working row renders the morph
    // from `from` to `to` (see composeFrame). Cleared ~0.5s after turn end.
    finishAnim: null,   // { start, from, to }
    mouse: true,
    menuOpen: false,
    menuList: [],
    menuSel: 0,
    menuOffset: 0,
    // Inline `@file` candidate list — the same widget as the `/` menu, rendered in
    // the same place. Kept separate from menuList so the two can never both claim
    // the ↑↓ keys.
    mentionOpen: false,
    mentionList: [],
    mentionSel: 0,
    mentionOffset: 0,
    objective: '',
    goalPaused: false,
    plan: !!(session && session.plan),
    planPath: (session && session.planPath) || null,
    focus: !!(session && session.focus),
    // Swarm mode is per-SESSION (like plan/focus), not just per-config: it is
    // restored here and written by persistState(). Reading only config.toml left
    // it off after /sessions resume, /fork and a plain restart.
    swarm: !!(session && session.swarm),
    effort,
    // Theme removed - forced dark only
    addDirs: [],
    tasks: {},
    // Output-token timestamps behind the tok/s readout, and the last computed rate.
    // Declared HERE, with the rest of the state, because the producer
    // (the agent onEvent) pushes on every streamed token: a field that only /new
    // creates is a crash the moment a session is restored instead of started.
    _tokTimes: [],
    tokRate: 0,
    pickerQuery: '',
    pickerCategory: null,  // active filter category (null = "All")
    pickerCategories: null,
    form: null,
    // AskUserQuestion dialog: { items, index, sel, picked:Set, multiSelect-going
    // state, editing, text, resolve }. Non-null while the user is answering.
    question: null,
    // Plan approval: { plan, resolve } while the user reviews a <|plan|> in Plan
    // mode. Mirrors approvalPending, but for the whole plan rather than one tool.
    planPending: null,
    // /tasks full-screen browser: { tasks, filter, selectedIndex, listScroll,
    // pendingStop, flash, flashTimer } or null when closed.
    tasksPanel: null,
    // Output viewer state (makeViewerState result) or null.
    tasksViewer: null,
    // Swarm mode (/swarm): when on, the prompt tells the model to decompose work
    // across parallel subagents via AgentSwarm.
    swarm: false,
    panel: null,
    notice: '',
    noticeKind: 'info',
    confirmExit: false,
    history: loadHistory(),   // restored from disk so ↑ works across restarts
    historyIdx: -1,
    _tipIndex: 0,
    // Provider-reported token totals for the whole session (see the `usage`
    // event). Restored from the session so --resume keeps counting from what was
    // already spent instead of restarting the cost readout at zero.
    usage: (session && session.usage) || {},
    // The most recent single request's report, for a per-request readout.
    lastUsage: null,
    // Spend cache for the status bar (see refreshCost). Declared here with the rest
    // of the state — a field only refreshCost creates is a crash the first time the
    // RENDERER runs before it, which is exactly what happens on a restored session.
    _costUsd: null,
    _costKnown: false,
    _costText: null,        // the amount as printed, in the display currency
    _costCurrency: 'USD',
    _costRate: null,        // the rate used, or null when the figure is USD
  };
}

// Pick a RANDOM tip, never the same one twice in a row. Any legacy "Tip #N:"
// prefix is stripped so the status line never shows a number.
export function setTip(state) {
  if (TIPS.length === 0) return;
  if (TIPS.length === 1) { state.tip = stripTipPrefix(TIPS[0]); return; }
  let i;
  do { i = Math.floor(Math.random() * TIPS.length); }
  while (i === state._tipIndex);
  state._tipIndex = i;
  state.tip = stripTipPrefix(TIPS[i]);
}

function stripTipPrefix(s) {
  return String(s).replace(/^Tip #\d+:\s*/i, '');
}

// `convRowFor` lives in session.js now: the Web daemon needs the same
// message -> rows expansion for a finished session, and it must NOT import this
// module (that would drag in the renderer, the agent and the LLM client). See the
// import at the top of this file.

// Split a history into { kept, dropped } for compaction. Pure, so the boundary
// rules can be tested without a model or a TTY.
//
// Two rules matter and used to be missing from the manual `/compact` path:
//   * the kept tail is budgeted by TOKENS, because one Read result can dwarf fifty
//     short turns — a count-based slice either fails to get under the threshold or
//     drops far more than necessary;
//   * the tail may never START on a `tool` message whose assistant(toolCalls) was
//     dropped. Most APIs reject a tool result with no preceding call, so that
//     boundary would break the next request outright.
export function planCompaction(msgs, cfg, ratio, maxCtx) {
  const list = Array.isArray(msgs) ? msgs : [];
  // With an explicit ratio, keep `1 - ratio` OF THE CURRENT HISTORY. Without one,
  // keep `cfg.compactKeepRatio` (default 0.2) of the CURRENT usage — the same rule
  // auto-compaction uses, so /compact and the automatic path agree.
  const used = estimateMessagesTokens(list, cfg);
  const keepRatio = (cfg && typeof cfg.compactKeepRatio === 'number'
    && cfg.compactKeepRatio > 0 && cfg.compactKeepRatio < 1) ? cfg.compactKeepRatio : 0.2;
  const keepBudget = (ratio !== null)
    ? Math.max(1, Math.floor(used * (1 - ratio)))
    : Math.max(1, Math.floor((used || (maxCtx || 512000) * 0.85) * keepRatio));

  // Price each message ONCE, and memoise it. `tokOf(m)` used to call
  // estimateMessagesTokens twice per message (once for [m], once for []), and the loop
  // visits every message, so a 4000-message transcript re-scanned ~8000 whole-array
  // estimates. The empty array contributes nothing anyway —
  // estimateMessagesTokens([]) is 0 by definition.
  //
  // `messageTokens` additionally caches each message's own figure, so a SECOND run of
  // this planner over the same transcript (/compact, then the automatic path) costs a
  // WeakMap lookup per message instead of re-walking every tool result body.
  const tokOf = (m) => messageTokens(m, cfg);
  let keepFrom = list.length;
  let keptTokens = 0;
  while (keepFrom > 0) {
    const n = list.length - keepFrom;              // already-kept count
    if (n >= 2 && keptTokens >= keepBudget) break;
    const t = tokOf(list[keepFrom - 1]);
    // Always keep at least the last two messages, however big they are.
    if (n >= 2 && keptTokens + t > keepBudget) break;
    keptTokens += t;
    keepFrom--;
  }
  while (keepFrom > 0 && keepFrom < list.length && list[keepFrom].role === 'tool') keepFrom--;
  return { kept: list.slice(keepFrom), dropped: list.slice(0, keepFrom) };
}

export function reconstructChat(s) {
  // Shell commands the user ran with `!` are shown on resume at the position they
  // originally ran. Each entry's `anchor` is how many REAL conversation messages
  // (session.messages items) preceded it, so we inject it beside that message.
  // They live in session.shellHistory, never in session.messages — the model
  // never sees them.
  const shellByAnchor = new Map();
  const shells = (s && s.shellHistory) || [];
  for (const sh of shells) {
    // A malformed entry must not take the whole resume down: `sh.anchor` on a
    // null threw right here, before the guard inside emitShells() could help.
    if (!sh || typeof sh !== 'object') continue;
    const a = Number(sh.anchor != null ? sh.anchor : 0);
    if (!shellByAnchor.has(a)) shellByAnchor.set(a, []);
    shellByAnchor.get(a).push(sh);
  }
  // Emit the shell block for anchor `a` (command + its output) onto `out`.
  const emitShells = (out, a) => {
    for (const sh of shellByAnchor.get(a) || []) {
      // Same junk-entry guard as the messages loop: a malformed shellHistory
      // entry must not take the whole resume down with it.
      if (!sh || typeof sh !== 'object') continue;
      out.push({ role: 'bash', text: String(sh.cmd || '') });
      // `ok` is null while the command is still running (the entry is written
      // before it executes). Reporting that as success turned an interrupted run
      // green on resume, so an unfinished entry stays unmarked.
      if (sh.result) out.push({ role: 'tool_result', text: String(sh.result), failed: sh.ok === false });
      // The `[cmd — done in 1s]` receipt is added to the transcript AFTER the
      // command runs and is never in session.messages, so a resume used to drop
      // it and the block looked truncated. Rebuild it from the persisted timing.
      if (sh.ok === true || sh.ok === false) {
        const ms = (sh.doneAt && sh.ts) ? Math.max(0, sh.doneAt - sh.ts) : 0;
        const label = `${String(sh.cmd || '').split('\n')[0]} — ${sh.ok ? 'done' : 'failed'} in ${fmtDuration(ms)}`;
        out.push({ role: 'system', text: `[${label}]` });
      }
    }
  };

  // Rows that live ONLY on screen, from an earlier session. `session.messages` holds what
  // the model sees, so a notice, a warning, a compaction result and a reasoning block have
  // no home there — writing them in would spend context on prose the model already acted
  // on. They are recorded in `session.transcript` instead, each with the same kind of
  // `anchor` shellHistory uses (how many real messages preceded it), so a resume puts them
  // back in the slot they were shown in rather than at the tail.
  const transcriptByAnchor = new Map();
  for (const ev of ((s && s.transcript) || [])) {
    if (!ev || typeof ev !== 'object' || !ev.row) continue;
    const a = Number(ev.anchor != null ? ev.anchor : 0);
    if (!transcriptByAnchor.has(a)) transcriptByAnchor.set(a, []);
    transcriptByAnchor.get(a).push(ev.row);
  }
  const emitTranscript = (out, a) => {
    for (const row of transcriptByAnchor.get(a) || []) {
      if (!row || typeof row !== 'object') continue;
      // `pending` is live state — a spinner that ended before the session was closed must
      // not start spinning again on resume — so it is settled on the way back in.
      out.push(row.pending ? { ...row, pending: false } : { ...row });
    }
  };

  const out = [];
  const msgs = (s && s.messages) || [];
  for (let mi = 0; mi < msgs.length; mi++) {
    const m = msgs[mi];
    // Inject shell commands that anchored BEFORE this message (in the slot after
    // the previous message). This runs BEFORE the junk-entry skip below: a
    // malformed message at index `mi` used to `continue` past the emit, so a
    // shell command anchored at that index was dropped from the resume entirely.
    emitShells(out, mi);
    emitTranscript(out, mi);
    // Skip junk entries. A session file can carry a null (older writer, hand
    // edit, truncated write); reading `m.role` off it threw and the whole resume
    // died with an unhandled TypeError instead of showing the rest of the
    // conversation.
    if (!m || typeof m !== 'object') continue;
    const role = m.role;
    const text = typeof m.content === 'string' ? m.content : '';

    // `_conv` marks a row as mirroring an entry in session.messages. Rows that
    // exist only on screen (shell echoes, receipts, notices) leave it unset, so
    // /compact can rebuild the transcript from the conversation alone instead of
    // guessing where the tail starts.
    for (const row of convRowFor(m)) out.push({ ...row, _conv: true });
  }

  // Any shell commands and transcript rows anchored at/past the end land at the very tail.
  emitShells(out, msgs.length);
  emitTranscript(out, msgs.length);
  return out;
}

export function pickerFiltered(state) {
  if (!state.picker) return [];
  const items = state.picker.items || [];
  const q = (state.pickerQuery || '').trim().toLowerCase();
  let filtered = items;
  if (q) {
    // A query that matches nothing must yield an EMPTY list, so the renderer can
    // show "No matches". Falling back to the full list hid the miss entirely and
    // made a typo look like "everything still matches".
    filtered = items.filter((it) => String(it.label).toLowerCase().includes(q));
  }
  // Category filter: only narrow when the selected category actually has items.
  // ("All", or no category, keeps everything.)
  const cat = state.pickerCategory;
  if (cat && cat !== 'All') {
    filtered = filtered.filter((it) => it.category === cat);
  }
  return filtered;
}

// ---- argument completion (the second level of the `/` menu) ----
//
// Once a command name is followed by a SPACE, the command menu used to close and
// the user was left typing blind — no way to see that `/auto-trim` takes
// `threshold`/`keep`, or that `/effort` takes `off|on|high|medium|low`. The hint
// text shown in the first-level list already names those words, so they are
// PARSED from it rather than kept in a second table that could drift out of sync.
//
// Only bare word alternatives are extracted. A hint like `[count]` or `<path>`
// describes a value the user has to supply, and offering it as a completion would
// just insert a placeholder; those are skipped.


export function argCompletionsFor(name, dynamicFor) {
  // A command may supply its completions from live state instead of a static hint
  // (e.g. /effort's levels come from the current model's models.dev data, which the
  // hardcoded hint could never track). When a provider returns a non-empty list it
  // wins outright; the hint parser below is only the fallback.
  if (typeof dynamicFor === 'function') {
    try {
      const dyn = dynamicFor(String(name || '').toLowerCase());
      if (Array.isArray(dyn) && dyn.length) return dyn;
    } catch { /* fall through to the static hint */ }
  }
  const entry = allCommands().find((c) => c.name === name);
  if (!entry || !entry.argumentHint) return [];
  // The hint is a small grammar: `|` separates alternatives, `[...]` wraps an
  // optional group, `<...>` is a value the USER must supply. Walk it one `|`-chunk
  // at a time and keep only chunks that are a bare literal word.
  //
  // A chunk is skipped when it is (or contains) a placeholder, because completing
  // `[count]` or `<path>` would just insert the word "count"/"path" as if it were a
  // choice. That test has to happen BEFORE brackets are stripped — `[ratio]` and
  // `[on|off]` look the same once you remove them, and the first is a value while
  // the second is a set of words.
  const words = [];
  const chunks = String(entry.argumentHint).split('|');
  for (let i = 0; i < chunks.length; i++) {
    const chunk = chunks[i].trim();
    if (!chunk) continue;
    // Strip an optional-group bracket, but only from THIS chunk: `[on|off` splits
    // into `[on` and `off]`, and a `]` closing the group must not be treated as
    // part of the word. `[msg]` / `[count]` are self-contained and handled below.
    const openedOnly = chunk.startsWith('[') && !chunk.endsWith(']');
    const closedOnly = chunk.endsWith(']') && !chunk.startsWith('[');
    let inner = chunk.replace(/^\[/, '').replace(/\]$/, '').trim();
    // A self-contained single-word group is a VALUE, not a choice: `[count]`,
    // `[ratio]`, `[msg]`, `[branch]`. Offering it would insert the placeholder name.
    if (!openedOnly && !closedOnly && /^\[[^\s\]]+\]$/.test(chunk)) continue;
    // `<path>`, `<file.md>`, but ALSO `threshold <n>`: take the literal word that
    // precedes the placeholder, and drop the chunk when the placeholder comes first.
    if (/</.test(inner)) {
      const head = inner.split(/</)[0].trim();
      if (!head) continue;
      inner = head;
      // A chunk that was ONLY a placeholder (`<objective>`) leaves nothing usable.
      if (/^[^\s<]*>/.test(chunk.replace(/^\[/, ''))) continue;
    }
    if (/>/.test(inner)) inner = inner.split(/>/).pop().trim();
    // `-f`, `--staged`, numbers, `50%`: not something to offer as a word.
    const first = inner.split(/\s+/)[0] || '';
    if (!/^[a-z][a-z0-9-]*$/i.test(first)) continue;
    if (!words.includes(first)) words.push(first);
  }
  return words;
}


// Build the second-level list for `/cmd <partial>`.
//
// Two kinds of entry come out of this, mirroring how the first level mixes
// commands and skills:
//   * a word from the command's hint      -> completes the word
//   * that command's own argumentHint     -> shown as a reminder when there is
//     nothing left to complete, so typing `/auto-trim ` still tells you the shape
function buildArgMenu(entry, rest, dynamicFor) {
  // `rest` is everything after "/cmd ". Split off the word being typed: a trailing
  // space means the word is finished and we are completing the NEXT one.
  const trailingSpace = /\s$/.test(rest);
  const tokens = rest.trim().split(/\s+/).filter(Boolean);
  const partial = trailingSpace ? '' : (tokens[tokens.length - 1] || '');
  const priorTokens = trailingSpace ? tokens : tokens.slice(0, -1);

  // Only the first positional slot is completed. A command like
  // `/auto-trim threshold 50%` has a value after the sub-word, and guessing at
  // every later slot would offer words that do not belong there.
  const words = argCompletionsFor(entry.name, dynamicFor);
  if (!words.length) return [];

  const matches = words.filter((w) => w.startsWith(partial.toLowerCase()));
  // Already used earlier in this same command line: do not offer it twice.
  const fresh = matches.filter((w) => !priorTokens.includes(w));

  const items = fresh.map((w) => ({
    name: partial ? w.slice(partial.length) : w,
    full: w,
    argumentHint: '',
    desc: entry.argumentHint,
    _argWord: true,
    _argPrefix: partial,
    _cmdName: entry.name,
  }));
  // Nothing matches a partial the user typed: keep the hint visible so the menu
  // does not simply disappear mid-word.
  if (!items.length && partial) {
    items.push({
      name: '', full: '', argumentHint: '', desc: `${entry.name} ${entry.argumentHint}`,
      _argWord: false, _cmdName: entry.name,
    });
  }
  return items;
}

// Accept the highlighted menu entry into the composer. Handles BOTH levels:
//   * a command (level 1) -> replace the whole input with "/<name>"
//   * an argument word    -> append only the REMAINING characters of that word to
//     (level 2)             what is already typed, then leave a trailing space so
//                           the next word can be started
// Level 2 was impossible before: Tab did `input = '/' + sel.name`, which for an
// argument entry would have wiped the command name off the line entirely.
export function acceptMenuSelection(state) {
  const sel = state.menuList[state.menuSel];
  if (!sel) return;
  if (!sel._argWord) {
    state.input = '/' + sel.name;
    state.caret = state.input.length;
    return;
  }
  // For argument entries `name` holds only the completion SUFFIX (see buildArgMenu).
  const before = state.input.slice(0, state.caret);
  state.input = before + (sel.name || '') + ' ';
  state.caret = state.input.length;
}

// Live argument completions. A few commands complete from RUNTIME state rather
// than a fixed hint string: /effort's levels come from the current model's
// models.dev data (effortOptions), which a hardcoded hint cannot track. `startTUI`
// installs the provider (it is the only place with `cfg`/`state` in scope);
// refreshMenu only knows `state`, so the provider is held here.
let argCompletionProvider = null;
export function setArgCompletionProvider(fn) { argCompletionProvider = typeof fn === 'function' ? fn : null; }

export function refreshMenu(state) {
  const val = state.input || '';
  if (val === '' || !val.startsWith('/')) {
    state.menuOpen = false;
    state.menuList = [];
    state.menuSel = 0;
    state.menuOffset = 0;
    return;
  }
  // A space means the command name is settled and we are now in its ARGUMENTS.
  // This used to close the menu outright, which is what made `/auto-trim ` leave
  // the user with no reference for what to type next.
  if (val.includes(' ')) {
    const m = /^\/([^\s]+)\s+([\s\S]*)$/.exec(val);
    const cmdEntry = m ? allCommands().find((c) => c.name === m[1].toLowerCase()
      || (c.aliases || []).includes(m[1].toLowerCase())) : null;
    const argMenu = cmdEntry ? buildArgMenu(cmdEntry, m[2], argCompletionProvider) : [];
    // A command with no completable arguments (a free-form `<title>` or `<path>`)
    // has nothing to offer, so the menu closes as it always did — but only there.
    state.menuList = argMenu;
    state.menuSel = Math.min(state.menuSel, Math.max(0, state.menuList.length - 1));
    state.menuOpen = state.menuList.length > 0;
    ensureMenuVisible(state);
    return;
  }
  const prefix = val.slice(1).toLowerCase();
  // `/skill:` and `/skill:<partial>` list the installed skills as menu entries so
  // they are tab-completable exactly like a built-in command. The entry's `name`
  // is the full `skill:<name>` token, so accepting it types the whole thing.
  if (prefix.startsWith(SKILL_PREFIX)) {
    const partial = prefix.slice(SKILL_PREFIX.length);
    state.menuList = skillCompletions(partial).map((s) => ({
      name: s.insert,
      description: s.description || 'skill',
      _skill: true,
    }));
    state.menuSel = Math.min(state.menuSel, Math.max(0, state.menuList.length - 1));
    state.menuOpen = state.menuList.length > 0;
    ensureMenuVisible(state);
    return;
  }
  // Merge skills into the general `/` list so they are visible the moment `/` is
  // typed, not only after `/skill:`. Each is a plain command entry whose `name`
  // is the full `skill:<name>` token — Tab types the whole thing and Enter runs
  // the skill via dispatch's default branch. Skills are filtered by the same
  // prefix once the user narrows past `skill:`. (The dedicated `skill:` branch
  // above is kept so a bare `/skill` also narrows the skill list.)
  // Focus the skill list ONLY when the prefix has clearly committed to "skill":
  //   - `/skill:...` (the explicit form), or
  //   - `/skill` typed in FULL (the bare prefix itself).
  // It used to trigger on any prefix that `'skill'.startsWith(prefix)` matched —
  // so `/s`, `/sk`, `/ski` dropped every command (`/status`, `/search`, …) and
  // showed only skills. A partial prefix must merge commands and skills.
  const skillIntent = prefix === 'skill' || prefix.startsWith(SKILL_PREFIX);
  const skillPrefix = prefix.startsWith(SKILL_PREFIX)
    ? prefix.slice(SKILL_PREFIX.length)
    : (prefix === 'skill' ? '' : prefix);
  const filteredSkills = skillCompletions(skillPrefix).map((s) => ({
    name: s.insert,
    description: s.description || 'skill',
    _skill: true,
  }));
  // When the prefix intends the skill area, only show skills. Otherwise show
  // commands + every skill (a bare `/` lists everything, and any other prefix
  // matches skill names directly).
  const cmdList = skillIntent
    ? []
    : allCommands().filter((c) => c.name.startsWith(prefix));
  state.menuList = [...cmdList, ...filteredSkills];
  state.menuSel = Math.min(state.menuSel, Math.max(0, state.menuList.length - 1));
  state.menuOpen = state.menuList.length > 0;
  ensureMenuVisible(state);
}

// Scroll a fixed-height selection window so the selected row stays visible.
// Shared by the `/` menu and the `@` candidate list: both render at most
// MAX_MENU rows starting at `offset`, so a selection outside that window would
// highlight NOTHING — which is exactly the "some entries never highlight" bug
// the @ list had (it force-reset offset to 0 on every keystroke while the
// selection could sit anywhere).
export function windowOffset(sel, offset, count, max = MAX_MENU) {
  if (!count) return 0;
  const s = Math.max(0, Math.min(sel || 0, count - 1));
  let off = Math.max(0, Math.min(offset || 0, Math.max(0, count - max)));
  if (s < off) off = s;
  else if (s > off + max - 1) off = Math.max(0, s - max + 1);
  return off;
}

function ensureMenuVisible(state) {
  if (!state.menuList.length) return;
  state.menuOffset = windowOffset(state.menuSel, state.menuOffset, state.menuList.length);
}

// ---- command dispatch ----
export async function dispatch(cmdRaw, arg, state, cfg, session, h, submit, stdout, renderFrameArg) {
  const { addChat, openPicker, openForm, notice, sendPrompt, quit, saveSession, openEditor } = h;

  // ---- command alias expansion ----
  // A user-defined alias (set via the alias/global-alias plugin commands) is
  // expanded BEFORE any built-in or plugin command is resolved, so an alias
  // behaves exactly like typing the full command. Aliases are stored in
  // cfg.command_aliases as a map: { short: { to, scope, workspace } }. A `global`
  // scope matches in every workspace; a `project` scope only in its workspace.
  {
    const full = String(cmdRaw || '').replace(/^\/+/, '');
    const rawName = full.split(/\s+/)[0].toLowerCase();
    const aliases = (cfg && cfg.command_aliases) || {};
    const here = aliases[rawName];
    const ws = (state && (state.cwd || state.workspace)) || process.cwd();
    if (here && (here.scope === 'global' || here.workspace === ws)) {
      const rest = full.slice(rawName.length).replace(/^\s+/, '');
      const expanded = `${here.to} ${rest}`.trim();
      cmdRaw = expanded;
      // arg is recomputed from the expanded command so the rest of dispatch sees
      // the resolved name and its trailing args consistently.
      const sp = expanded.indexOf(' ');
      arg = sp === -1 ? '' : expanded.slice(sp + 1).trim();
    }
  }

  // The repaint hook: the parameter is kept for callers that pass it, but the
  // authoritative source is `h.renderFrame` (the host always supplies one). The
  // parameter was declared and NEVER passed by any of the four callers, so a
  // command that repaints — /compact does — crashed with "renderFrame is not a
  // function". A no-op fallback keeps a headless caller working.
  const renderFrame = (typeof renderFrameArg === 'function') ? renderFrameArg
    : (typeof h.renderFrame === 'function') ? h.renderFrame
    : () => {};
  const entry = findCommand(cmdRaw);
  const cmd = entry ? entry.name : String(cmdRaw || '').replace(/^\//, '');
  const app = (m) => notice(m, 'info');
  // Settings changed through a command must be written to the session at once.
  const persist = () => { try { h.persistState && h.persistState(); } catch {} };
  const appErr = (m) => notice(m, 'error');
  const say = (m) => addChat({ role: 'system', text: m });
  // A panel whose colours are embedded in the text (grey labels, white values).
  // Added as 'rich' so msgLines emits it verbatim instead of tinting the whole
  // block one role colour.
  const sayRich = (m) => addChat({ role: 'rich', text: m });
  // A panel from plain text: the FIRST line is a white/bold heading, every other
  // line is dim grey (indented list items, paths, dim prose). This is the shared
  // look for `/context`-style output — used instead of `say()` (which tinted a
  // whole block teal) for anything with structure: lists, key/value blocks, diffs.
  const sayPanel = (text) => {
    const parts = String(text == null ? '' : text).split('\n');
    const out = parts.map((line, i) => {
      const body = line.startsWith(' ') || line === '' ? line
        : (line.startsWith('│') || line.startsWith('┌') || line.startsWith('└') ? line : '  ' + line);
      if (i === 0 && line.trim()) return C.white + C.bold + line + C.reset;
      return C.gray + body + C.reset;
    });
    addChat({ role: 'rich', text: out.join('\n') });
  };

  /**
   * Write one setting, through the single validation point in the schema.
   *
   * Every surface lands here — `/set`, the /settings browser, and the web's setConfig — so
   * they cannot disagree about what a value means or which keys exist.
   */
  function applySetting(key, value) {
    const def = SETTING_BY_KEY.get(key);
    if (!def) { appErr(`Unknown setting: ${key}. Try /settings.`); return false; }
    const coerced = coerceSetting(key, value);
    if (!coerced.ok) { appErr(coerced.error); return false; }

    try {
      if (def.kind === 'bool') setConfigBool(key, coerced.value === 'true');
      else setConfigString(key, coerced.value);
    } catch (e) { appErr(`Could not write config.toml: ${e.message}`); return false; }

    // Live-apply: mutate `cfg` AND `cfg.raw`, because some readers look at one and some at
    // the other, and a change that only reaches one of them appears to work until the next
    // frame reads the other.
    const raw = coerced.value;
    if (def.kind === 'bool') {
      const v = raw === 'true';
      cfg[key] = v; cfg.raw[key] = v;
      // The names the rest of the code actually reads, where they differ from the key.
      if (key === 'auto_compact') cfg.autoCompact = v;
      if (key === 'auto_trim') cfg.autoTrim = v;
      if (key === 'auto_update') cfg.autoUpdate = v;
      if (key === 'calm_mode') cfg.calmMode = v;
      if (key === 'swarm_mode') cfg.swarm = v;
      if (key === 'tool_allow_external_paths') cfg.allowExternal = v;
    } else {
      cfg[key] = raw; cfg.raw[key] = raw;
      if (key === 'compact_threshold') cfg.compactThreshold = Number(raw) / 100;
      if (key === 'compact_keep_ratio') cfg.compactKeepRatio = Number(raw) / 100;
      if (key === 'trim_threshold') cfg.trimThreshold = Number(raw) / 100;
      if (key === 'trim_keep_ratio') cfg.trimKeepRatio = Number(raw) / 100;
      if (key === 'max_context_tokens') cfg.maxContextTokens = Number(raw) || cfg.maxContextTokens;
      if (key === 'provider') cfg.provider = raw;
      if (key === 'model') { cfg.model = raw; state.modelLabel = raw; }
      if (key === 'effort') { cfg.effort = raw; state.effort = raw; }
      if (key === 'secondary_model') cfg.secondaryModel = raw;
      if (key === 'subagent_model') cfg.subagentModel = raw;
      if (key === 'tool_result_max_bytes') cfg.toolResultMaxBytes = Number(raw);
      if (key === 'tool_result_preview_bytes') cfg.toolResultPreviewBytes = Number(raw);
      if (key === 'probe_timeout_ms') cfg.probeTimeoutMs = Number(raw);
      if (key === 'log_level') cfg.logLevel = raw;
      if (key === 'shell') cfg.shell = raw;
    }

    // Effects that are not a plain field: switching the theme has to repaint every cell,
    // and a system-prompt change has to reach the next request.
    //
    // The repaint is requested through `state`, not by touching `lastFrame`: this function
    // runs inside `dispatch`, which cannot see startTUI's painter. `lastFrame` is dropped by
    // the next `paintNow`, which is what forces every cell to be rewritten — a theme change
    // left to the differential painter emits nothing, because the frame it compares against
    // already matches.
    if (key === 'theme') { setTheme(raw); state._forceRepaint = true; }
    if (key === 'system_prompt') cfg.systemPrompt = raw;
    if (key === 'append_system_prompt') cfg.appendSystemPrompt = raw;
    if (key === 'plan_instructions') cfg.planInstructions = raw;
    if (key === 'focus_instructions') cfg.focusInstructions = raw;
    if (key === 'swarm_instructions') cfg.swarmInstructions = raw;
    if (typeof renderFrameArg === 'function') renderFrameArg();
    return true;
    return true;
  }

  const raw = (arg || '').trim();

  switch (cmd) {
    case 'permission': {
      const named = { ask: 'ask', manual: 'ask', yolo: 'yolo', auto: 'auto' }[raw.toLowerCase()];
      if (named) { setPermission(state, named); persist(); app(`Permission mode: ${PERMISSION_LABEL[named]}`); return; }
      openPicker({
        title: 'Select permission mode',
        items: [
          { label: 'Ask', sub: 'read-only runs automatically; every other action asks first', current: state.mode === 'ask', value: 'ask' },
          { label: 'Yolo', sub: 'nothing asks: edits and commands run automatically, inside the workspace or not', current: state.mode === 'yolo', value: 'yolo' },
          { label: 'Auto', sub: 'nothing asks and nothing is reviewed: everything runs and is decided automatically', current: state.mode === 'auto', value: 'auto' },
        ],
        sel: ['ask', 'yolo', 'auto'].indexOf(state.mode),
        searchable: false,
        hint: '↑↓ navigate · Enter select · Esc cancel',
        onPick: (it) => { setPermission(state, it.value); persist(); app(`Permission mode: ${PERMISSION_LABEL[it.value]}`); return true; },
      });
      return;
    }
    case 'yolo': setPermission(state, 'yolo'); persist(); app(`Permission mode: ${PERMISSION_LABEL.yolo}`); return;
    case 'auto': setPermission(state, 'auto'); persist(); app(`Permission mode: ${PERMISSION_LABEL.auto}`); return;
    case 'ask': setPermission(state, 'ask'); persist(); app(`Permission mode: ${PERMISSION_LABEL.ask}`); return;

    case 'plan': {
      const a = raw.toLowerCase();
      // `/plan saved` lists the plans persisted to <workspace>/.hncode/plans.
      if (a === 'saved' || a === 'list') {
        const items = listPlans(state.workspace || cfg.workspace);
        if (!items.length) { say('No saved plans yet. Approve a plan in Plan mode to save it.'); return; }
        h.openPanel('hncode — saved plans', [
          `${items.length} plan(s) in ${plansDir(state.workspace || cfg.workspace)}:`,
          '',
          ...items.map((p) => `  ${p.name}   ${new Date(p.mtimeMs).toISOString().slice(0, 16).replace('T', ' ')}`),
        ]);
        return;
      }
      if (a === 'clear') { state.plan = false; state.planPath = null; persist(); app('Plan cleared.'); return; }
      if (a === 'on') state.plan = true;
      else if (a === 'off') state.plan = false;
      else state.plan = !state.plan;
      if (state.plan) { state.focus = false; state.swarm = false; }
      persist();
      app(`Plan mode: ${state.plan ? 'ON (read-only planning)' : 'OFF'}`);
      return;
    }
    case 'focus': {
      const a = raw.toLowerCase();
      let want = !state.focus;
      if (a === 'on') want = true;
      else if (a === 'off') want = false;
      state.focus = want;
      if (state.focus) { state.plan = false; state.swarm = false; }
      persist();
      app(`Focus mode: ${state.focus ? 'ON (Read/Write/Edit/Bash only)' : 'OFF (all tools)'}`);
      return;
    }

    case 'settings': {
      // A PICKER, not a screen takeover. Every other chooser in hncode is a picker — /model,
      // /theme, /permissions — and they share a look, a key set and the mouse. A settings
      // screen that owned the whole terminal looked like a different program and, because
      // the takeover path has its own click handling, could not be clicked at all.
      //
      // The tabs are the picker's own `categories`, which already render as a clickable,
      // hoverable strip with per-tab counts. Nothing new had to be invented for them.
      //
      // The SETTINGS_SCHEMA order drives the rows, and every row edits exactly as it does
      // elsewhere: a bool flips, anything else opens the value prompt.
      const arg = raw.trim().toLowerCase();
      const tabs = populatedTabs();
      const argTab = tabs.find((t) => t.id === arg);
      const items = [];
      for (const t of tabs) {
        for (const d of settingsForTab(t.id)) {
          const value = displayValue(cfg, d.key);
          // The row carries the NAME and the VALUE, nothing else. A description here made
          // every row four times longer than the information it conveys, squeezed the
          // value into whatever space was left, and let the longest description set the
          // width of the whole card. The description is not lost — it is what the edit
          // form shows, which is where the user is about to change the value anyway.
          const changed = isSet(cfg, d.key) && value !== d.default;
          items.push({
            label: d.ui.label || d.key,
            valueTag: value,
            valueTagChanged: changed,
            // Which tab this row belongs to, for the category filter.
            category: t.id,
            // Carried through to onPick: the key, its kind, and the description the form
            // needs — none of it belongs on the row.
            setKey: d.key,
            setKind: d.kind,
            setHint: d.ui ? d.ui.hint : '',
          });
        }
      }
      const catLabels = ['All', ...tabs.map((t) => t.id)];
      openPicker({
        title: 'Settings',
        items,
        categories: catLabels.length > 1 ? catLabels : null,
        category: argTab ? argTab.id : null,
        // Open on the tab named on the command line, else on the first row.
        sel: 0,
        hint: '↑↓ navigate · Enter change · Tab category · /search · Esc close',
        onPick: (it) => {
          if (!it || !it.setKey) return true;
          const key = it.setKey;
          const def = SETTING_BY_KEY.get(key);
          // A bool flips IN PLACE: a toggle with a confirm step is a worse toggle.
          if (def.kind === 'bool') {
            applySetting(key, effectiveValue(cfg, key) === 'true' ? 'false' : 'true');
            // Re-open so the list shows the new value — the picker closed on the pick, and
            // a settings screen that closes after every change is unusable for a second one.
            void dispatch('/settings', raw.trim(), state, cfg, session, h, submit, stdout);
            return true;
          }
          // Everything else opens a one-line prompt, pre-filled with the value in force.
          openForm({
            title: def.ui ? def.ui.label : key,
            fields: [{
              key: 'value',
              label: def.kind === 'text' ? 'Value (blank clears)' : 'Value',
              value: String(effectiveValue(cfg, key)),
            }],
            type: null,
            hideType: true,
            labelW: 18,
            // The description left the list row, so the form is where it appears.
            note: it.setHint || (def.ui ? def.ui.hint : ''),
            hint: def.values
              ? `one of: ${def.values.join(', ')} · Enter save · Esc cancel`
              : 'Enter save · Esc cancel',
            onSubmit: (values) => {
              applySetting(key, values && values.value);
              // Back to the list, so the next setting is one keystroke away.
              void dispatch('/settings', raw.trim(), state, cfg, session, h, submit, stdout);
            },
          });
          return true;
        },
      });
      return;
    }


    case 'set': {
      // `/set <key> <value>` — the direct path, so any setting is reachable without
      // remembering which command owns it. `/set` alone lists what is changed.
      const parts = raw.trim().split(/\s+/).filter(Boolean);
      if (!parts.length) {
        const changed = changedSettings(cfg);
        if (!changed.length) {
          sayPanel(['Nothing is set away from its default.', '', 'Browse everything with /settings,',
            'or set one directly: /set <key> <value>'].join('\n'));
          return;
        }
        const lines = [`${changed.length} setting(s) differ from the default:`, ''];
        for (const d of changed) {
          lines.push(`  ${d.key.padEnd(28)} ${displayValue(cfg, d.key)}   (default ${d.default})`);
        }
        sayPanel(lines.join('\n'));
        return;
      }
      const key = parts[0];
      if (!SETTING_BY_KEY.has(key)) {
        appErr(`Unknown setting: ${key}. Run /settings to browse, or /set to list what is changed.`);
        return;
      }
      if (parts.length === 1) {
        const d = SETTING_BY_KEY.get(key);
        sayPanel([
          `  ${d.key}`,
          `  value     ${displayValue(cfg, key)}`,
          `  default   ${d.default}`,
          `  type      ${d.kind}${d.values ? ` (${d.values.join(', ')})` : ''}`,
          d.ui ? `  where     ${d.ui.tab} › ${d.ui.group}` : '  (no settings row; set by /set only)',
          '',
          d.ui ? `  ${d.ui.hint}` : '',
        ].join('\n'));
        return;
      }
      applySetting(key, parts.slice(1).join(' '));
      return;
    }


    case 'model': {
      const models = (cfg.raw && cfg.raw.models) || {};
      let names = Object.keys(models);
      if (!names.length) {
        const pr = (cfg.raw && cfg.raw.providers) || {};
        names = Object.keys(pr);
        if (!names.length) { appErr('No providers configured. Add one first: /provider'); return; }
        if (raw) {
          if (!pr[raw]) { appErr(`Unknown provider: ${raw}`); return; }
          applyModel(state, cfg, resolveProvider(cfg, raw));
          app(`Model → ${cfg.model || '(unset)'} via ${raw}`);
          return;
        }
        openPicker({
          title: 'Select a provider',
          items: names.map((n) => ({ label: n, sub: ((pr[n] || {}).base_url || '').replace(/^https?:\/\//, ''), current: n === cfg.provider })),
          sel: Math.max(0, names.indexOf(cfg.provider)),
          onPick: (it) => { applyModel(state, cfg, resolveProvider(cfg, it.label)); app(`Provider → ${cfg.provider}`); return true; },
        });
        return;
      }
      if (raw) {
        if (!models[raw]) { appErr(`Unknown model alias: ${raw}`); return; }
        applyModel(state, cfg, resolveModelArg(cfg, raw));
        app(`Model → ${cfg.model}`);
        return;
      }
      {
        // Build categories: "All" + one per configured provider.
        const _providers = Object.keys(cfg.raw.providers || {});
        const _catLabels = ['All', ..._providers];
        openPicker({
          title: 'Select a model',
          items: [
            ...names.map((n) => ({ label: n, sub: models[n].provider || cfg.provider || '', current: n === cfg.model, category: models[n].provider || '' })),
            { label: '＋ Add model…', sub: 'register a model under a provider', action: 'add-model' },
          ],
          categories: _catLabels,
          category: null,  // start on "All"
          // Trimmed to fit the row, which is clipped (not wrapped) at the terminal
          // width: `Esc cancel` and the long "switch category" phrasing are the
          // guessable parts, and dropping them keeps `Ctrl+E edit` on screen at the
          // narrowest width the dialog targets.
          hint: '↑↓ navigate · Enter select · Tab category · Ctrl+E edit',
          sel: Math.max(0, names.indexOf(cfg.model)),
          // Ctrl+E edits the selected model's stored details (display name, context
          // window, output limit). These are exactly the fields resolveConfig reads,
          // so an edit takes effect on the next turn without editing config.toml by hand.
          onCtrlE: (item) => {
            if (!item || item.action === 'add-model') { appErr('Select a model first, then Ctrl+E to edit it.'); return; }
            const entry = models[item.label] || {};
            const provider = entry.provider || cfg.provider || '';
            const modelId = entry.model || bareModelId(provider, item.label, entry);
            openForm({
              title: `Edit ${item.label}`,
              fields: [
                { key: 'display_name', label: 'Display Name', value: entry.display_name || entry.displayName || '' },
                { key: 'context', label: 'Context Tokens', value: String(entry.context_length || entry.contextLength || '') },
                { key: 'output', label: 'Max Output Tokens', value: String(entry.max_output_tokens || entry.maxOutputTokens || entry.max_tokens || '') },
              ],
              type: null,
              hideType: true,
              labelW: 20,
              hint: 'Tab next field · Enter save · Esc cancel (blank clears the value)',
              onSubmit: (values) => {
                const num = (v) => { const n = Number(String(v || '').replace(/[^0-9]/g, '')); return n > 0 ? n : undefined; };
                // Reasoning is NOT edited here: the thinking LEVEL is chosen in the
                // picker's Thinking footer (sourced from models.dev), and whether a
                // model supports reasoning is a property of the model, not a field to
                // hand-toggle. This form edits only stored metadata.
                upsertModel(provider, modelId, {
                  display_name: (values.display_name || '').trim() || undefined,
                  contextLength: num(values.context),
                  maxOutputTokens: num(values.output),
                });
                // Keep the in-memory config in sync so the status line / next turn see
                // the change immediately (a restart is not required).
                cfg.raw.models = cfg.raw.models || {};
                const k = modelKey(provider, modelId);
                cfg.raw.models[k] = {
                  ...entry,
                  provider,
                  model: modelId,
                  display_name: (values.display_name || '').trim() || undefined,
                  context_length: num(values.context),
                  max_output_tokens: num(values.output),
                };
                applyModel(state, cfg, resolveProvider(cfg, provider));
                app(`Saved ${item.label}: context ${num(values.context) || 'default'}, output ${num(values.output) || 'default'}`);
              },
            });
          },
          footerFor: (item) => {
            if (!item || item.action === 'add-model') return { label: 'Thinking', options: ['off', 'on'], value: state.effort || 'off', focused: false };
            const itemOpts = effortOptions(cfg, item.label);
            if (!itemOpts.length) return null;
            const cur = item.label === cfg.model ? (state.effort && itemOpts.includes(state.effort) ? state.effort : 'off') : (itemOpts.includes(state.effort) ? state.effort : itemOpts.includes('off') ? 'off' : itemOpts[0]);
            return { label: 'Thinking', options: itemOpts, value: cur, focused: false };
          },
          // Choosing a model has TWO parts here — the model and its thinking level — so a
          // CLICK on a row must not close the menu before the level can be clicked.
          clickKeepsOpen: true,
          onFooterPick: (level) => {
            setEffort(state, cfg, level);
            persist();
            app(`Model → ${cfg.model}${state.effort && state.effort !== 'off' ? ` (thinking ${state.effort})` : ''}`);
            return true;
          },
          onPick: (it) => {
            if (it.action === 'add-model') {
            const pr = (cfg.raw && cfg.raw.providers) || {};
            const providers = Object.keys(pr);
            if (!providers.length) { appErr('No providers configured. Add one first: /provider'); return true; }
            openPicker({
              title: 'Add model — choose a provider',
              items: providers.map((n) => ({ label: n, sub: ((pr[n] || {}).base_url || '').replace(/^https?:\/\//, ''), provider: n })),
              searchable: true,
              onPick: (pit) => {
                openForm({
                  title: `Add A Model To ${pit.label}`,
                  fields: [
                    { key: 'model', label: 'Model ID' },
                    { key: 'display_name', label: 'Display Name' },
                  ],
                  type: null,
                  hideType: true,
                  hint: 'Tab next field · Enter save · Esc cancel (display name defaults to the id)',
                  onSubmit: (values) => {
                    if (!values.model) { appErr('Cancelled: model id is required.'); return; }
                    const disp = values.display_name || values.model;
                    addModel(pit.provider, values.model, { display_name: values.display_name });
                    cfg.raw.models = cfg.raw.models || {};
                    cfg.raw.models[modelKey(pit.provider, values.model)] = { provider: pit.provider, model: values.model, display_name: values.display_name || undefined };
                    app(`Model added: ${pit.provider}/${values.model} (${disp})`);
                  },
                });
                return true;
              },
            });
            return true;
          }
          applyModel(state, cfg, resolveModelArg(cfg, it.label));
          const fo = state.picker && state.picker.footer;
          if (fo && fo.value) setEffort(state, cfg, fo.value);
          app(`Model → ${cfg.model}${state.effort && state.effort !== 'off' ? ` (thinking ${state.effort})` : ''}`);
          return true;
        },
        });
      }
      return;
    }
    case 'effort': {
      const opts = effortOptions(cfg);
      if (!opts.length) { appErr('The current model has no thinking control.'); return; }
      if (raw) {
        const v = raw.toLowerCase();
        if (!opts.includes(v)) { appErr(`Unknown effort: ${raw} (expected ${opts.join(' / ')})`); return; }
        setEffort(state, cfg, v);
        persist();
        app(`Thinking effort → ${v}`);
        return;
      }
      openPicker({
        title: 'Select thinking effort',
        items: opts.map((o) => ({ label: o, sub: o === 'off' ? 'no reasoning tokens' : `${o} reasoning budget`, current: (state.effort || 'off') === o })),
        sel: Math.max(0, opts.indexOf(state.effort || 'off')),
        searchable: false,
        onPick: (it) => { setEffort(state, cfg, it.label); persist(); app(`Thinking effort → ${it.label}`); return true; },
      });
      return;
    }
    case 'provider': {
      // The provider list is rebuilt in three places — on open, after a delete, and
      // after an edit — so it is built in ONE place. The edit case is why: its
      // handler used to write `state.picker.items` directly, but `openForm` had
      // already set `state.picker = null`, so saving an edit threw
      // "Cannot set properties of null" and the uncaughtException handler exited
      // hncode. Reopening the picker is both the fix and the intent (the list has to
      // show the new name/URL).
      const providerItems = () => {
        const pr = (cfg.raw && cfg.raw.providers) || {};
        const rows = Object.keys(pr).map((name) => ({
          label: name,
          sub: (pr[name].base_url || pr[name].baseUrl || '').replace(/^https?:\/\//, '') || '(no base_url)',
          current: name === cfg.provider,
        }));
        rows.push({ label: '＋ Add provider…', sub: 'create a new [providers.*] entry', action: 'add' });
        return rows;
      };
      const pr = (cfg.raw && cfg.raw.providers) || {};
      const names = Object.keys(pr);
      // The whole picker is a named function so the EDIT path can build a fresh one:
      // by the time its form submits, `state.picker` is null (openForm clears it) and
      // the old code wrote `state.picker.items` straight into that null, throwing and
      // taking the process down.
      //
      // The selection is computed from a FRESH key list, not the `names` captured at
      // command time: after a rename or a delete, `names` no longer describes the
      // rows on screen and the highlight landed on the wrong provider.
      const openProviderPicker = (selName) => {
        const keys = Object.keys(cfg.raw.providers || {});
        return openPicker({
          title: keys.length ? 'Select a provider' : 'No providers yet',
          items: providerItems(),
          sel: Math.max(0, keys.indexOf(selName || cfg.provider)),
          // The hint must NAME the keys this picker actually handles. It defines
          // onCtrlR (re-fetch models) and onDelete (remove the provider) but the
          // default hint text mentions neither, so both actions were invisible —
          // a listener with no advertised shortcut is the same as no feature.
          //
          // Short enough to fit the row (which is clipped, not wrapped, at the
          // terminal width): the dropped words are the guessable ones — arrows, Esc,
          // and "type to search", which the title suffix already says.
          hint: '↑↓ navigate · Enter edit · Del remove · Ctrl+R refresh',
          // Ctrl+R: re-fetch the selected provider's models from /v1/models, or from
          // the whole models.dev catalog when the provider is a catalog one. Replaces
          // the provider's model entries rather than appending.
        onCtrlR: (it) => {
          if (!it || it.action === 'add') { appErr('Select a provider first, then Ctrl+R to refresh its models.'); return; }
          refreshProviderModels(state, cfg, it.label, h).catch((e) => appErr(`Refresh failed: ${e.message}`));
        },
        onDelete: (it) => {
          if (!it || it.action === 'add') return false;
          removeProvider(it.label);
          delete (cfg.raw.providers || {})[it.label];
          for (const key of Object.keys(cfg.raw.models || {})) {
            if (key.split('/')[0] === it.label) delete cfg.raw.models[key];
          }
          // The picker is still open here (Delete runs from the list), so the rows
          // are refreshed in place.
          if (state.picker) {
            state.picker.items = providerItems();
            state.picker.sel = Math.max(0, Math.min(state.picker.sel, state.picker.items.length - 1));
          }
          if (cfg.provider === it.label) { cfg.provider = ''; state.provider = ''; }
          app(`Provider removed: ${it.label}`);
          return true;
        },
        onPick: (it) => {
          if (it.action === 'add') {
            // Show a submenu to choose between known providers and custom
            openPicker({
              title: 'Add a provider',
              items: [
                { label: 'Known provider', sub: 'browse models.dev catalog', action: 'known' },
                { label: 'Custom provider', sub: 'enter base URL, key and protocol yourself', action: 'custom' },
              ],
              searchable: false,
              hint: '↑↓ navigate · Enter select · Esc cancel',
              onPick: (subIt) => {
                if (subIt.action === 'custom') {
                  openForm({
                    title: 'Add A Custom Provider',
                    fields: [
                      { key: 'name', label: 'Provider Name' },
                      { key: 'base_url', label: 'Base URL' },
                      { key: 'api_key', label: 'API Key', kind: 'mask' },
                    ],
                    type: null,
                    // Same as the edit form: picking a Type IS the final decision
                    // here, so a click on it saves. Without this a mouse user had to
                    // click the type and then still press Enter.
                    typeClickSubmits: true,
                    hint: 'Tab next field · ↑/↓ field · ←/→ type · Enter save · Esc cancel',
                    onSubmit: (values, type) => {
                      if (!values.name) { appErr('Cancelled: provider name is required.'); return; }
                      if (!type) { appErr('Cancelled: choose a Type (OpenAI / OpenAI Responses / Anthropic).'); return; }
                      const protocol = typeToProtocol(type);
                      // A hand-entered provider is NOT from the catalog: known=false.
                      registerProvider(state, cfg, h, values.name, values.base_url, values.api_key, protocol, type, false);
                    },
                  });
                  return true;
                }
                // Known provider: load catalog and show list
                app('Loading provider list…');
                fetchCatalog().then((catalog) => {
                  const entries = catalog
                    ? Object.values(catalog)
                        .filter((p) => p && p.id)
                        .map((p) => ({
                          id: p.id,
                          name: p.name || p.id,
                          api: p.api || catalogDefaultUrl(p.id),
                          npm: p.npm || '',
                          doc: p.doc || '',
                          models: p.models || {},
                        }))
                        .sort((a, b) => String(a.name).localeCompare(String(b.name)))
                    : [];
                  const items = entries.map((p) => ({
                    label: p.name,
                    sub: p.id,
                    providerId: p.id,
                    base_url: p.api,
                    npm: p.npm,
                    catalogModels: p.models,
                    action: 'pickKnown',
                  }));
                  if (!items.length) {
                    appErr('No known providers found in catalog.');
                    return;
                  }
                  openPicker({
                    title: 'Select a known provider',
                    items,
                    searchable: true,
                    hint: '↑↓ navigate · type to search · Enter select · Esc cancel',
                    onPick: (pit) => {
                      // Protocol is DETECTED, not asked: models.dev marks the SDK via
                      // `npm`. Everything that is not the Anthropic SDK speaks the
                      // OpenAI wire format (the catalog is dominated by openai-compatible).
                      const protocol = /anthropic/i.test(pit.npm || '') ? 'anthropic' : 'openai';
                      openForm({
                        title: `Add ${pit.label}`,
                        // Name is PRE-FILLED with the catalog id but editable — you may
                        // want a different key (e.g. two accounts for the same provider).
                        // The URL comes from the catalog (or the provider's well-known
                        // default) and the protocol was detected above, so neither needs
                        // a field. Only the key is empty and must be typed.
                        fields: [
                          // Pre-fill the DISPLAY name (mixed case, e.g. "Deep Infra"),
                          // not the catalog id — it reads better and the user can edit it.
                          { key: 'name', label: 'Provider Name', value: pit.label || pit.providerId },
                          { key: 'api_key', label: 'API Key', kind: 'mask', value: '' },
                        ],
                        type: null,
                        hideType: true,
                        hint: 'Tab next field · Enter save · Esc cancel',
                        onSubmit: async (values) => {
                          const name = (values.name || '').trim() || pit.label || pit.providerId;
                          const base_url = pit.base_url;
                          // known=true records the SOURCE (models.dev); the catalog id is
                          // kept separately so a renamed provider still maps to its entry.
                          registerProvider(state, cfg, h, name, base_url, values.api_key, protocol, protocolToType(protocol), true, pit.providerId);

                          // Auto-fetch models; the catalog's own per-model limits
                          // (limit.context / limit.output) and reasoning options are
                          // merged in, so models whose endpoint reports nothing still
                          // get correct values. models.dev is the SOURCE OF TRUTH for
                          // thinking levels — we never guess them.
                          try {
                            const models = await fetchModels({ baseUrl: base_url, apiKey: values.api_key, protocol });
                            const cat = pit.catalogModels || {};
                            const enrich = (id, base = {}) => {
                              const c = cat[id] || {};
                              return {
                                ...base,
                                limit: (base.limit) || c.limit || {},
                                reasoning: base.reasoning !== undefined ? base.reasoning : c.reasoning,
                                reasoningOptions: base.reasoningOptions || c.reasoning_options,
                                cost: base.cost || c.cost,
                              };
                            };
                            const merged = models.length
                              ? models.map((m) => enrich(m.id, m))
                              : Object.entries(cat).map(([id, m]) => enrich(id, { id, display: m.name || id }));
                            if (merged.length > 0) {
                              for (const m of merged) {
                                const lim = m.limit || {};
                                const ctxLen = m.contextLength || lim.context || undefined;
                                const maxOut = m.maxOutputTokens || lim.output || undefined;
                                // Thinking levels come ONLY from models.dev's
                                // reasoning_options; effortsFromOptions returns null
                                // when there is nothing usable, so no guessing happens.
                                const efforts = m.efforts || effortsFromReasoning(m.reasoningOptions);
                                // Pricing comes from the catalog too. Without it /usage
                                // can only report tokens, never what they cost.
                                const cost = costFromCatalog(m.cost);
                                const key = modelKey(name, m.id);
                                addModel(name, m.id, {
                                  display_name: m.display,
                                  contextLength: ctxLen,
                                  maxTokens: m.maxTokens,
                                  maxOutputTokens: maxOut,
                                  reasoning: m.reasoning === true,
                                  efforts,
                                  cost,
                                });
                                if (!cfg.raw.models) cfg.raw.models = {};
                                // Merge over any existing entry: fields this fetch
                                // did not report keep the values already there
                                // (same rule as the Ctrl+R refresh).
                                cfg.raw.models[key] = mergeRefreshedModelEntry(name, m, cfg.raw.models[key]);
                              }
                              app(`Added ${merged.length} model(s) with limits from the catalog.`);
                            } else {
                              app(`Provider added. No models found at this endpoint or in the catalog.`);
                            }
                          } catch (error) {
                            app(`Provider added. Failed to fetch models: ${error.message}`);
                          }
                        },
                      });
                      return true;
                    },
                  });
                  });
                return true;
              },
            });
            return true;
          }
          // Enter on a regular provider opens the edit form (Ctrl+E removed).
          const p = cfg.raw.providers && cfg.raw.providers[it.label] || {};
          openForm({
            title: `Edit Provider: ${it.label}`,
            fields: [
              { key: 'name', label: 'Provider Name', value: it.label },
              { key: 'base_url', label: 'Base URL', value: p.base_url || p.baseUrl || '' },
              { key: 'api_key', label: 'API Key', kind: 'mask', value: p.api_key || p.apiKey || '' },
            ],
            // `type` here is the LABEL the form cycles through, so convert the stored
            // protocol back to its label (passing the raw 'openai' showed a Type field
            // whose selection did not match what was saved).
            type: protocolToType(p.protocol || 'openai'),
            // The Type field is SHOWN here — editing a provider is exactly where you
            // switch between OpenAI / OpenAI Responses / Anthropic. It used to be
            // hidden, so the protocol could never be changed after creation and the
            // "←/→ type" hint pointed at a field that was not on screen.
            hideType: false,
            // Clicking a Type finishes the edit, like Enter does — the type is the
            // last decision on this form, so a mouse user should not have to reach
            // for the keyboard afterwards.
            typeClickSubmits: true,
            hint: 'Tab next field · ←/→ type · Enter save · Esc cancel',
            onSubmit: (values, type) => {
              if (!values.name) { appErr('Cancelled: provider name is required.'); return; }
              // The chosen Type arrives as the SECOND arg (`values` holds only the
              // text fields) — `values.type` was undefined and silently saved 'openai'.
              const protocol = typeToProtocol(type);
              // Preserve the source flags of the entry being edited (known / catalog),
              // otherwise a rename would silently forget it is a models.dev provider.
              const catalogId = p.catalog;
              const wasKnown = p.known;
              // A RENAME has to delete the old `[providers.<old>]` block explicitly:
              // addProvider() only replaces a block whose name matches, so writing the
              // new name left the old entry in config.toml and the provider showed up
              // TWICE (the stale one with the old URL, until a restart read the file).
              // Only on a rename — calling it for an in-place edit would delete the
              // block addProvider just wrote.
              if (values.name !== it.label) removeProvider(it.label);
              addProvider(values.name, { base_url: values.base_url, api_key: values.api_key, protocol, known: wasKnown, catalog: catalogId });
              delete (cfg.raw.providers || {})[it.label];
              // Keep the IN-MEMORY provider table in step with the file: without this
              // the old entry lingered with its old protocol/URL, and the model menu
              // read stale data until a restart.
              cfg.raw.providers = cfg.raw.providers || {};
              cfg.raw.providers[values.name] = {
                base_url: values.base_url || undefined,
                api_key: values.api_key || undefined,
                protocol,
                known: wasKnown,
                catalog: catalogId,
              };
              // The picker is GONE by now — openForm set `state.picker = null` — so the
              // refreshed list is built as a NEW picker rather than written into the
              // old one. That write is what threw "Cannot set properties of null" and
              // exited hncode; reopening also re-points the selection at the renamed
              // entry and shows the user the new name/URL.
              if (values.name === cfg.provider) {
                // Re-resolve so a protocol/URL change takes effect on the NEXT turn
                // instead of waiting for a restart.
                applyModel(state, cfg, resolveProvider(cfg, values.name));
              }
              // Re-discover models under the new name (the old list was just dropped).
              fetchAndRegisterModels(state, cfg, values.name, h);
              app(`Provider updated: ${values.name}`);
              openProviderPicker(values.name);
              return true;
            },
          });
          return true;
        },
          });   // closes openPicker({ … })
      };        // closes the openProviderPicker arrow body
      // Open the picker for the first time. Everything above only DEFINED the
      // handlers; without this call the command rendered nothing.
      openProviderPicker(cfg.provider);
      return;
    }

    case 'new':
      // Save current session's todos before switching
      if (session && Array.isArray(state.todos)) {
        session.todos = state.todos.slice();
        saveSession(session);
      }
      
      state.chat = [];
      Object.assign(session, { id: sess.newId(), title: '', messages: [], createdAt: Date.now(), rounds: 0, steps: 0, lastTurnMs: 0 });
      state.objective = '';
      state.rounds = 0; state.steps = 0; state.lastTurnMs = 0;
      // New session starts with empty TODO list
      state.todos = [];
      session.todos = [];
      // Set terminal window title to default (Untitled)
      stdout.write('\x1b]0;Untitled\x07');
      // A fresh session has no history, so the context gauge must go back to 0
      // (otherwise it kept showing the PREVIOUS session's usage until the next
      // turn reported a new estimate). The window size is a property of the
      // current model, so it is re-resolved from cfg rather than kept stale.
      state.ctxTokens = 0;
      state.ctxPercent = 0;
      state.ctxMax = cfg.maxContextTokens || state.ctxMax;
      state.tokRate = 0;
      state._tokTimes = [];
      // The spend belongs to the session that is ending, so a new session starts
      // from zero. The session object is reused, so `usage` must be CLEARED here
      // rather than just left out.
      state.usage = {};
      state.lastUsage = null;
      refreshCost(state, cfg);
      // `shellHistory` belongs to the conversation that just ended. The session object
      // is REUSED here, so leaving it in place carried the previous session's
      // `!command` rows into a session the user had just started — and they showed up
      // again after the next `--continue`, because saveSession persists whatever is on
      // the object. An entry whose anchor is 0 (a `!command` run before the first
      // message) renders even in a session that has said nothing at all.
      session.shellHistory = [];
      delete session.usage;
      saveSession(session);
      app(`Started a new session (${session.id}).`);
      return;
    case 'sessions':
    case 'all-sessions': {
      const everyWorkspace = cmd === 'all-sessions';
      const all = sess.listSessions();
      const cwd = path.resolve(state.cwd || state.workspace || process.cwd());
      // `/sessions` is scoped to THIS directory; `/all-sessions` deliberately is not,
      // so a conversation started elsewhere can be resumed without cd-ing into it
      // first. Both share ONE implementation below — a second copy of this resume
      // logic would have to be kept in step with every fix made to it.
      const list = everyWorkspace ? all : all.filter((s) => {
        const sessionCwd = s.workspace ? path.resolve(s.workspace) : null;
        return sessionCwd === cwd;
      });
      if (!list.length) {
        app(everyWorkspace
          ? 'No saved sessions.'
          : (all.length ? `No sessions in this directory (${cwd}). Try /all-sessions.` : 'No saved sessions.'));
        return;
      }
      openPicker({
        title: everyWorkspace ? 'Resume a session (all workspaces)' : 'Resume a session',
        items: list.slice(0, 50).map((s) => ({
          label: (s.title || 'untitled').slice(0, 30),
          sub: `${new Date(s.updatedAt || s.createdAt || 0).toLocaleString().slice(0, 19)} · ${(s.messages || []).length} msgs · ${s.workspace || ''}${s.lastTurnMs ? ` · last turn ${fmtDuration(s.lastTurnMs)}` : ''}`,
          id: s.id,
        })),
        onPick: (it) => {
          const meta = list.find((s) => s.id === it.id);
          if (meta) {
            // The list only carries METADATA (no messages — readSessionMeta strips
            // them). Assigning it straight onto `session` wiped the transcript, so
            // the resumed session appeared empty or stale. Load the FULL session
            // file (like --continue / --resume do), then merge its settings.
            const full = sess.loadSession(meta.id);
            if (!full) { app(`Could not load session ${meta.id}`); return true; }
            const keepModel = cfg.model;
            const keepInner = cfg.innerModel;
            const keepProvider = cfg.provider;
            Object.assign(session, full);
            cfg.model = keepModel;
            cfg.innerModel = keepInner;
            cfg.provider = keepProvider;
            state.chat = reconstructChat(session);
            state.scroll = 0;
            dropScrollPin(state);   // fresh transcript: re-seed the anchor on paint
            state.rounds = session.rounds || 0;
            state.steps = session.steps || 0;
            state.lastTurnMs = session.lastTurnMs || 0;
            // The resumed session may live in another directory, and EVERY tool path
            // resolves against it (`resolvePath` uses `ctx.cwd || ctx.workspace`,
            // and the agent copies `cfg` into `ctx` each turn). Updating only
            // state.cwd moved the STATUS LINE while Edit/Read/Bash kept writing to
            // the previous workspace — the resume looked right and hit the wrong
            // files. `cfg` is the one the tools read, so it moves too.
            if (full.workspace) {
              state.cwd = full.workspace;
              state.workspace = full.workspace;
              cfg.workspace = full.workspace;
              cfg.cwd = full.workspace;
              // An in-flight agent holds its own ctx copy; keep it in step so a
              // resume while a turn is running cannot split the two.
              if (state.agent && state.agent.ctx) {
                state.agent.ctx.cwd = full.workspace;
                state.agent.ctx.workspace = full.workspace;
              }
              refreshGitInfo(state, { force: true });
            }

            
            // Update context gauge based on restored session messages.
            const approx = estimateMessagesTokens(session.messages, cfg);
            state.ctxTokens = approx;
            state.ctxMax = cfg.maxContextTokens || state.ctxMax;
            state.ctxPercent = usagePercent(approx, state.ctxMax);
            
            const dur = session.lastTurnMs ? ` · last turn ${fmtDuration(session.lastTurnMs)}` : '';
            app(`Resumed ${meta.id} (${meta.title || 'untitled'}) · ${(session.messages || []).length} messages.${dur}`);
          }
          return true;
        },
      });
      return;
    }
    case 'tasks': {
      // Open the full-screen task browser (kimi's TASK BROWSER). Through the host:
      // dispatch is module-level and the panel lives inside startTUI.
      h.openTasksPanel();
      return;
    }
    case 'swarm': {
      // Swarm mode: tell the model to decompose work across parallel subagents.
      const a = raw.toLowerCase();
      let want;
      if (a === 'on') want = true;
      else if (a === 'off') want = false;
      else want = !state.swarm;
      state.swarm = want;
      // Plan / Focus / Swarm are one mutually exclusive group: turning one on
      // turns the other two off.
      if (want) { state.plan = false; state.focus = false; }
      try { setConfigString('swarm_mode', want ? 'true' : 'false'); } catch {}
      cfg.raw.swarm_mode = want;
      app(want
        ? 'Swarm mode ON - the model will decompose work across parallel subagents (AgentSwarm)'
        : 'Swarm mode OFF');
      return;
    }
    case 'swarm-sub-agent': {
      // Which model subagents run on. Empty/unset = follow this session's model
      // (the "default"), so a user who never touches this gets the behaviour they
      // already had. Stored in config.toml as `subagent_model`, and mirrored onto
      // `cfg.subagentModel` where the Agent/AgentSwarm tools read it.
      const models = (cfg.raw && cfg.raw.models) || {};
      const names = Object.keys(models);
      const desired = raw.trim();

      const showCurrent = () => (cfg.subagentModel
        ? `Subagent model: ${cfg.subagentModel}`
        : `Subagent model: default (this session's — ${cfg.model || 'unset'})`);

      const setSubagentModel = (value) => {
        const v = value || '';
        try { setConfigString('subagent_model', v); }
        catch (e) { appErr('Could not write config.toml: ' + e.message); return; }
        cfg.subagentModel = v;
        cfg.raw.subagent_model = v;
        app(v ? `Subagent model → ${v}` : `Subagent model → default (this session's model)`);
      };

      // `/swarm-sub-agent default` (or `none`/`reset`) clears the override.
      if (desired) {
        const d = desired.toLowerCase();
        if (d === 'default' || d === 'none' || d === 'reset' || d === 'clear') { setSubagentModel(''); return; }
        if (!models[desired]) { appErr(`Unknown model alias: ${desired}. Run /swarm-sub-agent to pick one.`); return; }
        setSubagentModel(desired);
        return;
      }
      if (!names.length) {
        appErr('No models configured. Add one first: /provider');
        return;
      }
      // The same model menu as /model, with a subagent-scoped title and a
      // "default" row that clears the override.
      const providers = Object.keys(cfg.raw.providers || {});
      openPicker({
        title: 'Select a subagent model',
        items: [
          {
            label: 'default',
            sub: `follow this session's model (${cfg.model || 'unset'})`,
            action: 'default',
            current: !cfg.subagentModel,
          },
          ...names.map((n) => ({
            label: n,
            sub: models[n].provider || cfg.provider || '',
            current: n === cfg.subagentModel,
            category: models[n].provider || '',
          })),
        ],
        categories: ['All', ...providers],
        category: null,
        hint: '↑↓ navigate · Tab switch category · Enter select · Esc cancel',
        onPick: (it) => {
          if (it.action === 'default') { setSubagentModel(''); return true; }
          setSubagentModel(it.label);
          return true;
        },
      });
      return;
    }
    case 'fork': {
      // Forking is the whole point of the command: the two conversations must be able to
      // diverge without touching each other. `forkOf` owns that guarantee
      // (a copy per message, the lineage, and the counters that belong to the
      // conversation rather than to the copy) and lives in its own module so it can be
      // tested directly.
      const forked = forkOf(session, sess.newId);
      sess.saveSession(forked);
      app(`Session forked (${forked.id}). Still in the original; switch via /sessions.`);
      renderFrame();
      return;
    }
    case 'undo': {
      const msgs = session.messages || [];
      // Indexes of REAL user prompts. Harness-generated `role: 'user'` notes (the
      // truncation-recovery nudge, compaction handoffs wrapped in <system-reminder>)
      // must not count: they inflate the tally and would show up as fake prompts in
      // the picker. `beginTurn` runs once per real prompt, so this list is what the
      // file-history turns line up with.
      const promptIdx = [];
      for (let i = 0; i < msgs.length; i++) if (isRealUserPrompt(msgs[i])) promptIdx.push(i);

      // Bare `/undo` opens a PICKER of the prompts (cline-style): choose one and the
      // session rewinds TO JUST BEFORE it — transcript and files together. A numeric
      // argument keeps the old "go back N prompts" behaviour, so scripts and muscle
      // memory are unaffected.
      const argStr = String(raw || '').trim();
      if (!argStr || !/^\d+$/.test(argStr)) {
        if (!promptIdx.length) { app('Nothing to undo.'); return; }
        const items = promptIdx.map((mi, k) => {
          const text = String(msgs[mi].content == null ? '' : msgs[mi].content).replace(/\s+/g, ' ').trim();
          return {
            label: text.length > 64 ? text.slice(0, 61) + '…' : (text || '(empty prompt)'),
            sub: `prompt ${k + 1} of ${promptIdx.length} · rewinds ${promptIdx.length - k} turn(s)`,
            _k: k,
          };
        });
        openPicker({
          title: 'Rewind to just before…',
          items,
          searchable: true,
          hint: '↑↓ navigate · type to filter · Enter rewind · Esc cancel',
          onPick: (it) => {
            if (!it || it._k == null) return true;
            const count = promptIdx.length - it._k;   // turns to drop, newest first
            confirmUndo(count, it.label, () => doUndo(count));
            return true;
          },
        });
        return;
      }

      const count = Math.max(1, parseInt(argStr, 10) || 1);
      // CONFIRM before rewinding. This destroys work: the transcript truncates AND
      // file-history puts every file the turns touched back (deleting files they
      // created). There is no redo, and with the picker above a stray Enter used to
      // be enough. A y/n picker that names the file count is the cheapest guard.
      const confirmUndo = (n, summary, run) => {
        openPicker({
          title: `Rewind ${n} prompt(s)?`,
          searchable: false,
          hint: '↑↓ choose · Enter confirm · Esc cancel',
          items: [
            { label: 'Cancel', sub: 'keep everything as it is' },
            { label: 'Rewind', sub: `${summary} — the transcript truncates and the files those turns changed are restored (no redo)` },
          ],
          onPick: (it) => {
            if (it && it.label === 'Rewind') run();
            else app('Rewind cancelled.');
            return true;
          },
        });
        renderFrame();
      };
      // Shared rewind used by both paths (numeric arg and picker). Defined here so
      // it closes over session/state/saveSession; the picker's onPick fires later
      // but still holds this closure.
      const doUndo = (count) => {
        const cur = session.messages || [];
        let ci = cur.length;
        for (let i = 0; i < count; i++) {
          let j = ci - 1;
          while (j >= 0 && !isRealUserPrompt(cur[j])) j--;
          if (j < 0) break;
          ci = j;
        }
        if (ci >= cur.length) { app('Nothing to undo.'); return; }
        const removed = cur.slice(ci);
        state.chat = state.chat.slice(0, Math.max(0, state.chat.length - removed.length));
        saveSession(session);
        // Rewind the FILES too. This used to only truncate the transcript and then
        // say "Undid 1 prompt", while every Edit/Write the agent had made stayed on
        // disk — so the user believed the work was withdrawn and then found their
        // files still rewritten. file-history.js holds the pre-turn content of each
        // file the agent touched, taken on the first write to it in that turn.
        const rewound = rewindFiles(session.id, count);
        const filesNote = describeRewind(rewound);
        // The files on disk are now older than what the model Read, so every hash in
        // the Read snapshot pool describes content that is no longer there. Clear it,
        // or the model's next Edit is rejected as "changed since it was Read" against
        // a file the user just watched being restored.
        if (state.agent && state.agent.readPool) {
          try { state.agent.readPool.clear(); } catch { /* best-effort */ }
        }
        if (rewound.failed.length) {
          for (const f of rewound.failed) appErr(`Could not restore ${f.path}: ${f.error}`);
        }
        app(`Undid ${count} prompt${count > 1 ? 's' : ''}${filesNote ? ` — ${filesNote}` : ' (no files changed)'}.`);
        renderFrame();
      };
      confirmUndo(count, `the last ${count} prompt(s)`, () => doUndo(count));
      return;
    }
    case 'title': {
      if (raw) {
        session.title = raw.slice(0, 200);
        saveSession(session);
        // Set terminal window title - use OSC sequence
        // Only show "Untitled" prefix if user hasn't set a custom title
        const displayTitle = session.title || 'Untitled';
        stdout.write(`\x1b]0;${displayTitle}\x07`);
        app(`Session title set to: "${displayTitle}"`);
      } else {
        app(`Session title: ${session.title || 'not set'}`);
      }
      return;
    }
    case 'compact': {
      const msgs = session.messages || [];
      if (msgs.length <= 2) { app('Nothing to compact yet.'); return; }
      const ratio = raw ? parseFloat(raw) : null; // optional slice ratio (0-1)
      if (ratio !== null && !(ratio > 0 && ratio < 1)) {
        app('Invalid ratio; use 0-1 (e.g., 0.2 to drop the oldest 20% of messages)');
        return;
      }

      // Summarising is a full model round-trip. Without this, a second /compact
      // (or a message typed while it works) would edit the same history at the
      // same time — `state.running` is what submit() checks to queue instead.
      if (state.running) { app('Busy — wait for the current turn to finish.'); return; }
      state.running = true;
      renderFrame();

      const maxCtx = cfg.maxContextTokens || state.ctxMax || 512000;
      const plan = planCompaction(msgs, cfg, ratio, maxCtx);
      const droppedMsgs = plan.dropped;
      const kept = plan.kept;
      const dropped = droppedMsgs.length;


      // Summarize the dropped portion, so context survives the trim — that is the
      // whole point of compaction. Rendered as the SAME live compaction block the
      // automatic path uses (blinking bullet → "Compaction complete"), so the two
      // look identical instead of one getting a spinner and the other a text line.
      let summary = '';
      const liveBlock = {
        role: 'compaction', phase: 'running', startedAt: Date.now(), instruction: '',
      };
      addChat(liveBlock);
      renderFrame();
      if (droppedMsgs.length > 0) {
        const llm = new LLM(cfg);
        // Let Esc abort the summary request (see the escape handler).
        state._compactLlm = llm;
        try {
          // Thinking off, no tools — same reasoning as the automatic path in
          // agent.js: a reasoning model can spend the whole output budget on
          // `reasoning_content` and return an empty summary, which turns /compact
          // into a plain loss of history.
          summary = await llm.requestText([
            { role: 'system', content: 'You are an expert at summarizing coding-agent conversations. Summarize the conversation history below. Capture: the user\'s original request, key decisions made, files created or modified, errors encountered and how they were resolved, and the current state of any ongoing work or remaining tasks. Be concise but thorough — aim for 3-5 short paragraphs that let the model continue the task with full context. Do NOT include meta-commentary, only the facts.' },
            ...droppedMsgs,
          ], { noReasoning: true, noTools: true });
        } catch (e) {
          summary = '';
        }
        state._compactLlm = null;
      }
      // Interrupted (Esc): abort yields an empty summary; do NOT trim — that would
      // drop history with nothing to replace it. Mark the block cancelled and stop.
      if (state._compactAborted) {
        state._compactAborted = false;
        liveBlock.phase = 'cancelled';
        liveBlock._cache = null;
        state.running = false;
        renderFrame();
        return;
      }

      const compactedSummary = summary
        ? `[hncode] Earlier conversation context was compacted. ${dropped} older message(s) were replaced by this summary:\n\n${summary}`
        : `[hncode] ${dropped} earlier message(s) were compacted without a summary. Their detail is no longer available.`;

      // The summary MUST be a `user` message, NOT `system`. runAgent() skips every
      // `system` entry in session.messages (it rebuilds the prompt from scratch),
      // and the turn-end save filters `system` out of the persisted history — so a
      // `system` summary was dropped at BOTH ends, leaving the model with a trimmed
      // transcript and no record of what had been removed. Auto-compaction only
      // gets away with it because it edits the request array directly.
      const summaryMsg = { role: 'user', content: compactedSummary };

      session.messages = [summaryMsg, ...kept];
      // `convRowFor` returns an ARRAY (one assistant message expands into its own
      // row plus one row per tool call). Spreading it into an object literal —
      // `{ ...convRowFor(m), _conv: true }` — produced `{0: {...}, 1: {...},
      // _conv: true}` instead of rows: a message with a role of `undefined`, which
      // renders as blank. That is what made the transcript go empty after a manual
      // /compact. Flat-map so every produced row is a row.
      state.chat = [
        ...state.chat.filter((m) => !m._conv),
        { role: 'user', text: compactedSummary, _conv: true },
        ...kept.flatMap((m) => convRowFor(m).map((r) => ({ ...r, _conv: true }))),
      ];

      saveSession(session);
      state.tokens = estimateMessagesTokens(session.messages, cfg);
      state.ctxTokens = state.tokens;
      state.ctxPercent = usagePercent(state.tokens, state.ctxMax || maxCtx);
      // The transcript was just replaced with a much shorter one. Drop the scroll
      // anchor (as /sessions and /move do) so the next paint seeds a fresh one and
      // the view lands on the newest rows instead of compensating for a row delta
      // that no longer describes anything.
      dropScrollPin(state);
      state.scroll = 0;
      state.running = false;
      // Settle the live block into "Compaction complete (before → after tokens)",
      // matching the automatic path.
      liveBlock.phase = 'done';
      liveBlock.tokensBefore = estimateMessagesTokens(msgs, cfg);
      liveBlock.tokensAfter = state.tokens;
      liveBlock.text = summary || '';
      liveBlock._cache = null;
      renderFrame();
      return;
    }

    case 'set-system-prompt': {
      // Two steps: pick a source, then edit it. Showing the editor straight away
      // (the old behaviour) left no way to start from a preset.
      const builtin = SYSTEM_PROMPT;
      const custom = cfg.raw && cfg.raw.system_prompt ? String(cfg.raw.system_prompt) : '';

      // Open the editor on `text`. Saving writes it to config.toml; an EMPTY value
      // clears the override and restores the built-in. `presetName` is only used
      // for the title, so the user can see which preset they started from.
      const edit = (text, presetName) => {
        openEditor({
          title: presetName
            ? `System prompt — preset "${presetName}" (edit, then Ctrl+S to save)`
            : (custom
              ? 'System prompt (custom — saving replaces it; clear it to restore the built-in)'
              : 'System prompt (built-in — saving overrides it)'),
          text,
          caretRow: 0,
          caretCol: 0,
          onSave: (value) => {
            const trimmed = String(value).trim();
            try {
              setConfigString('system_prompt', trimmed);
            } catch (e) { appErr('Could not write config.toml: ' + e.message); return; }
            cfg.systemPrompt = trimmed;
            cfg.raw.system_prompt = trimmed;
            if (trimmed) app(`System prompt saved (${trimmed.length} chars) → ${hncodeConfigFile()}`);
            else app('System prompt override cleared; the built-in prompt is in use again.');
          },
        });
      };

      // A preset only lands in the editor — never written straight to config.toml.
      // No preset fits every workflow, and the user should be free to adjust it
      // before it takes effect.
      const items = [
        {
          label: 'Edit current prompt',
          sub: custom ? 'edit the custom prompt in use' : 'edit the built-in prompt',
          action: 'edit-current',
        },
        {
          label: 'Start from a preset…',
          sub: `${FAMILIES.length} model families × ${TASKS.length} tasks`,
          action: 'presets',
        },
      ];
      if (custom) {
        items.push({
          label: 'Restore built-in',
          sub: 'clear the override and go back to the shipped prompt',
          action: 'restore',
        });
      }
      openPicker({
        title: 'System prompt',
        items,
        searchable: false,
        hint: '↑↓ navigate · Enter select · Esc cancel',
        onPick: (it) => {
          if (it.action === 'edit-current') {
            edit(custom || builtin);
            return true;
          }
          if (it.action === 'restore') {
            try { setConfigString('system_prompt', ''); }
            catch (e) { appErr('Could not write config.toml: ' + e.message); return true; }
            cfg.systemPrompt = '';
            cfg.raw.system_prompt = '';
            app('System prompt override cleared; the built-in prompt is in use again.');
            return true;
          }
          // Preset picker: the FAMILY is the list (↑↓), the TASK is a footer row
          // (Tab to focus, ←→ to change) — the same shape /model uses for its
          // Thinking row. `presetState` remembers the chosen task across the
          // list selection.
          const presetState = { task: 'general' };
          const taskLabel = () => {
            const t = TASKS.find((x) => x.id === presetState.task) || TASKS[0];
            return t.label;
          };
          openPicker({
            title: 'System prompt presets',
            items: FAMILIES.map((f) => ({
              label: f.label,
              sub: f.sub,
              presetId: f.id,
            })),
            hint: '↑↓ family · Tab focus task · Enter load into editor · Esc cancel',
            footer: {
              label: 'Task',
              options: TASKS.map((t) => t.label),
              value: taskLabel(),
              focused: false,
            },
            onPick: (it) => {
              // Tab/←→ moved the footer; Enter on a list row applies (family, task).
              const task = TASKS.find((t) => t.label === state.picker.footer.value) || TASKS[0];
              const text = buildPreset(it.presetId, task.id);
              // An empty result means the preset could not be built (unknown family,
              // or a build() that failed). Say so instead of closing the menu with
              // nothing happening, which reads as a broken Enter key.
              if (!text) { appErr(`Could not build the "${it.presetId}" preset.`); return false; }
              edit(text, presetLabel(it.presetId, task.id));
              return true;
            },
          });
          return true;
        },
      });
      return;
    }

    case 'personal': {
      // Personal preferences: free-form notes injected into the system prompt on
      // EVERY turn (see /personal's handler comment in config.js). Two scopes —
      // global (~/.hncode/PERSONAL.md, all workspaces) and project
      // (<workspace>/.hncode/PERSONAL.md, this workspace only). Bare /personal
      // asks which scope; saving an EMPTY body deletes that scope's file.
      const workspace = state.workspace || cfg.workspace || process.cwd();
      const openScope = (scope) => {
        const file = personalPromptFile(scope, workspace);
        openEditor({
          title: `Personal preferences (${scope}) — ${file}`,
          text: readPersonalPromptRaw(scope, workspace),
          caretRow: 0,
          caretCol: 0,
          onSave: (value) => {
            try { writePersonalPrompt(scope, workspace, value); }
            catch (e) { appErr('Could not write ' + file + ': ' + e.message); return; }
            if (String(value).trim()) app(`Personal preferences saved (${scope}) → ${file}`);
            else app(`Personal preferences cleared (${scope}); nothing will be injected.`);
          },
        });
      };
      const firstLine = (scope) => {
        const t = readPersonalPromptRaw(scope, workspace).trim();
        return t ? t.split('\n')[0].slice(0, 48) : '(empty)';
      };
      const a = raw.toLowerCase();
      if (a === 'global' || a === 'g' || a === 'user') { openScope('global'); return; }
      if (a === 'project' || a === 'p' || a === 'local') { openScope('project'); return; }
      if (a === '') {
        openPicker({
          title: 'Personal preferences — choose a scope',
          items: [
            { label: 'project', sub: `this workspace only — ${firstLine('project')}` },
            { label: 'global', sub: `all workspaces — ${firstLine('global')}` },
          ],
          onPick: (it) => { openScope(it.label); return true; },
        });
        return;
      }
      appErr('Usage: /personal [global|project]');
      return;
    }

    case 'memory': {
      // The AGENT's own notes (the Memory tool writes them). Same two scopes as
      // /personal but a separate pair of files, so the user's preferences and the
      // model's notes never overwrite each other. Bare /memory shows what is
      // stored; `clear` wipes a scope, since a wrong note otherwise keeps being
      // injected into every future prompt.
      const workspace = state.workspace || cfg.workspace || process.cwd();
      const a = raw.trim().toLowerCase();
      const openScope = (scope) => {
        const file = memoryFile(scope, workspace);
        openEditor({
          title: `Agent memory (${scope}) — ${file}`,
          text: readMemoryRaw(scope, workspace),
          caretRow: 0,
          caretCol: 0,
          onSave: (value) => {
            try { writeMemoryRaw(scope, workspace, value); }
            catch (e) { appErr('Could not write ' + file + ': ' + e.message); return; }
            if (String(value).trim()) app(`Agent memory saved (${scope}) → ${file}`);
            else app(`Agent memory cleared (${scope}); nothing will be injected.`);
          },
        });
      };
      const summary = (scope) => {
        const t = readMemoryRaw(scope, workspace).trim();
        if (!t) return '(empty)';
        const n = t.split('\n').filter((l) => l.trim().startsWith('-')).length;
        return `${n} note${n === 1 ? '' : 's'}`;
      };
      if (a === 'clear' || a === 'reset') {
        openPicker({
          title: 'Clear agent memory — choose a scope',
          items: [
            { label: 'project', sub: `this workspace only — ${summary('project')}` },
            { label: 'global', sub: `all workspaces — ${summary('global')}` },
          ],
          onPick: (it) => {
            const file = memoryFile(it.label, workspace);
            try { writeMemoryRaw(it.label, workspace, ''); }
            catch (e) { appErr('Could not clear ' + file + ': ' + e.message); return true; }
            app(`Agent memory cleared (${it.label}) — ${file}`);
            return true;
          },
        });
        return;
      }
      if (a === 'global' || a === 'g' || a === 'user') { openScope('global'); return; }
      if (a === 'project' || a === 'p' || a === 'local') { openScope('project'); return; }
      if (a === '') {
        openPicker({
          title: 'Agent memory — choose a scope',
          items: [
            { label: 'project', sub: `this workspace only — ${summary('project')}` },
            { label: 'global', sub: `all workspaces — ${summary('global')}` },
          ],
          onPick: (it) => { openScope(it.label); return true; },
        });
        return;
      }
      appErr('Usage: /memory [global|project|clear]');
      return;
    }

    case 'permissions': {
      // Standing allow / ask / deny rules (see permissions.js). They are read from
      // config.toml's [permissions] table, so bare /permissions PRINTS what is in
      // force and `edit` opens the TOML file — a free-text editor beats a wizard
      // here because the rule syntax is the thing being edited, and the file is
      // where the user may already have other settings.
      const rules = cfg.permissions || {};
      const n = (k) => (Array.isArray(rules[k]) ? rules[k].length : 0);
      if (raw.trim().toLowerCase() === 'edit') {
        const file = hncodeConfigFile();
        openEditor({
          title: `Permissions — ${file}`,
          text: (() => { try { return fs.readFileSync(file, 'utf8'); } catch { return ''; } })(),
          caretRow: 0,
          caretCol: 0,
          onSave: (value) => {
            try { fs.writeFileSync(file, String(value)); }
            catch (e) { appErr('Could not write ' + file + ': ' + e.message); return; }
            // Re-read so the new rules apply on the NEXT tool call, without a restart.
            const fresh = resolveConfig();
            cfg.permissions = fresh.permissions;
            app(`Permissions saved. allow=${(cfg.permissions.allow || []).length} `
              + `ask=${(cfg.permissions.ask || []).length} deny=${(cfg.permissions.deny || []).length}`
              + ' — effective immediately.');
          },
        });
        return;
      }
      const selfTest = selfTestRules(rules);
      const lines = [
        'Standing permission rules, checked BEFORE the mode shortcuts',
        '(so a deny cannot be bypassed with Auto, and an ask still prompts):',
        '',
        describeRules(rules),
        '',
        'Session approvals:',
        describeSessionApprovals(session.sessionApprovals),
        '',
        'Rule self-test:',
        describeSelfTest(selfTest),
        '',
        `Config file: ${hncodeConfigFile()}`,
        'Edit with:   /permissions edit',
        '',
        'Syntax:',
        '  Bash                    every Bash call',
        '  Bash(npm run test)      that exact command',
        '  Bash(npm run test *)    a command starting with `npm run test `',
        '  Read(./src/**)          a tool whose path argument matches the glob',
        '',
        'Examples, checked here and reported above:',
        '  Bash(git push *)  # match: git push origin | not_match: git pull',
      ];
      h.openPanel('Permissions', lines);
      if (selfTest.failed.length) {
        appErr(`${selfTest.failed.length} rule example(s) failed — see /permissions.`);
      }
      if (!n('allow') && !n('ask') && !n('deny')) {
        app('No permission rules set — /permissions edit to add some.');
      }
      return;
    }

    case 'external': {
      // Outside-the-workspace access. Persisted to config.toml as
      // `tool_allow_external_paths`, so it survives a restart — the point of the
      // switch is that a user grants (or revokes) it ONCE, instead of it being
      // implied by whichever permission mode they happen to be in.
      //
      // Bare /external TOGGLES, like /plan, /focus and every other on-off mode in
      // this CLI. `on` / `off` force a state so a script can be explicit.
      const a = raw.trim().toLowerCase();
      const cur = !!cfg.allowExternal;
      let want;
      if (a === 'on' || a === 'true' || a === 'yes' || a === '1') want = true;
      else if (a === 'off' || a === 'false' || a === 'no' || a === '0') want = false;
      else if (a === '') want = !cur;
      else { appErr('Usage: /external [on|off]'); return; }

      const envForced = process.env.HNCODE_ALLOW_EXTERNAL === '1';
      try { setConfigBool('tool_allow_external_paths', want); }
      catch (e) { appErr('Could not write config.toml: ' + e.message); return; }
      cfg.allowExternal = want;
      if (cfg.raw) cfg.raw.tool_allow_external_paths = want;
      // Push it into the RUNNING agent too: it snapshotted cfg at construction, so
      // without this the switch would only take effect on the next turn.
      if (state.agent && state.agent.ctx) state.agent.ctx.allowExternal = want;
      app(want
        ? 'External paths: ON — tools may read and write outside the workspace.'
        : 'External paths: OFF — tools are confined to the workspace.');
      if (envForced && !want) {
        appErr('Note: HNCODE_ALLOW_EXTERNAL=1 is set, so access stays ON until you unset it.');
      }
      return;
    }

    case 'web': {
      // Publish this session to the browser through the MACHINE-WIDE web UI.
      //
      // There is one daemon per machine, on the fixed port from config.toml, and
      // it is what the user opens: it lists every workspace and every session —
      // the running ones live, the finished ones read from disk. This command
      // brings up this session's own server and registers it there; if the daemon
      // is already up it is REUSED rather than restarted, which is the whole point
      // of a stable address and a stable token.
      const a = raw.trim();
      if (a.toLowerCase() === 'off' || a.toLowerCase() === 'stop') {
        app(h.stopWeb() ? 'Web UI stopped (this session is no longer listed).' : 'Web UI is not running.');
        return;
      }
      if (!h.startWebGlobal) { appErr('Web UI is unavailable in this build.'); return; }
      // Optional "[bindIp] [port]" — the same shapes `--web` accepts. The old
      // code threw these away and always bound loopback, so `/web 0.0.0.0` looked
      // like it worked while nothing was reachable from the network.
      let bindArg, portArg;
      if (a) {
        const parts = a.split(/\s+/);
        if (/^\d+$/.test(parts[0])) portArg = Number(parts[0]);
        else bindArg = parts[0];
        if (parts[1] && /^\d+$/.test(parts[1])) portArg = Number(parts[1]);
      }
      say('Starting the web UI…');
      h.startWebGlobal(bindArg, portArg).then(({ srv, daemon, token }) => {
        if (!daemon) {
          // The daemon could not be reached or started. The session's own server
          // is still up, so report THAT rather than pretending /web failed.
          sayPanel([
            `Web UI (this session only): ${srv.url}`,
            '',
            'The machine-wide daemon is unavailable, so this session is served',
            'directly. Open the address above; the token is below.',
            '',
            `    ${srv.token}`,
          ].join('\n'));
          notice(`Web UI on ${srv.url} (daemon unavailable)`, 'error');
          return;
        }
        const lan = daemon.host && daemon.host !== '127.0.0.1' && daemon.host !== 'localhost';
        sayPanel([
          `Web UI:   ${daemon.rootUrl}`,
          `Session:  ${daemon.url}`,
          `Bind:     ${daemon.host}:${daemon.port}${lan ? '  (reachable from the network)' : '  (this machine only)'}`,
          daemon.spawned ? 'Daemon:   started (was not running)' : 'Daemon:   reused (already running)',
          '',
          'The root page lists every workspace and session — running ones live,',
          'finished ones from disk. The token below is stored in config.toml, so',
          'it stays the same across restarts.',
          '',
          'Access token (paste it into the login page):',
          '',
          `    ${token || srv.token}`,
          '',
          'Anyone with this token can run commands as you. Stop this session with',
          '/web off.',
        ].join('\n'));
        notice(`Web UI at ${daemon.rootUrl}`);
      }).catch((e) => {
        appErr(`Could not start the web UI: ${e.message}`);
      });
      return;
    }






    case 'calm-mode': {
      // Terse-output mode: while ON, an instruction is injected with each request
      // telling the model not to narrate what it is about to do or why, unless
      // asked. Persisted so it survives a restart.
      const a = raw.toLowerCase();
      let want;
      if (a === 'on') want = true;
      else if (a === 'off') want = false;
      else if (a === '') want = !cfg.calmMode;
      else { appErr('Usage: /calm-mode [on|off]'); return; }
      try { setConfigString('calm_mode', want ? 'true' : 'false'); }
      catch (e) { appErr('Could not write config.toml: ' + e.message); return; }
      cfg.calmMode = want;
      cfg.raw.calm_mode = want;
      app(`Calm mode: ${want ? 'ON — the model will keep explanations to a minimum' : 'OFF'}`);
      return;
    }

    case 'init': {
      if (!cfg.model) { appErr('LLM not set. Configure a provider with /provider first.'); return; }
      // Optional free-text instructions, like /compact's optional ratio: whatever
      // the user types after `/init` steers what goes into the file (e.g.
      // `/init focus on the tRPC routers and our migration rules`). With no
      // argument the built-in checklist is used on its own.
      const instructions = raw.trim();
      // Already have one? Then this is likely an UPDATE, and overwriting silently
      // would throw away whatever the user hand-edited in there.
      const existing = agentsFilesFor(state.cwd || cfg.workspace, cfg.workspace || state.cwd || process.cwd())
        .filter((f) => /(^|[\\/])agents?\.md$/i.test(f.path) && !/override/i.test(f.path));
      const base = 'Analyze this codebase and write an AGENTS.md file at the workspace root. '
        + 'Keep it concise instructions for future agents: project layout, build/test commands, '
        + 'and conventions. Prefer concrete commands and paths over prose.';
      const update = existing.length
        ? `\n\nThere is already an AGENTS.md at ${existing[0].path}. Read it first, then revise it `
          + 'in place: keep what is still accurate, correct what is stale, and add what is missing. '
          + 'Do not discard existing instructions unless they are wrong.'
        : '';
      const extra = instructions ? `\n\nThe user asked you to focus on this:\n${instructions}` : '';
      say(instructions
        ? '/init — generating AGENTS.md, guided by your instructions…'
        : '/init — analyzing the workspace to generate AGENTS.md…');
      sendPrompt(base + update + extra);
      return;
    }

    case 'goal': {
      const a = raw.toLowerCase();
      if (!raw || a === 'status') {
        if (state.objective) sayPanel(`Goal: ${state.objective}\nStatus: ${state.goalPaused ? 'paused' : 'active'}`);
        else say('No goal set. Start one with /goal <objective>.');
        return;
      }
      if (a === 'pause') { state.goalPaused = true; app('Goal paused. Use /goal resume to continue.'); return; }
      if (a === 'resume') {
        if (!state.objective) { app('No goal to resume.'); return; }
        state.goalPaused = false; app('Goal resumed.');
        sendPrompt('Resume the active goal.');
        return;
      }
      if (a === 'cancel') { state.objective = ''; state.goalPaused = false; app('Goal cancelled.'); return; }
      if (a.startsWith('replace ')) { state.objective = raw.slice(8).trim(); app('Goal replaced.'); return; }
      state.objective = raw; state.goalPaused = false;
      app(`Goal set: ${raw}`);
      sendPrompt(raw);
      return;
    }

    case 'help':
      h.openPanel('hncode — commands', [
        ...allCommands().map((c) => `  /${c.name.padEnd(14)} ${(c.argumentHint || '').padEnd(26)} ${c.description || c.desc}`),
        '',
        'Skills',
        `  /${SKILL_PREFIX}<name>     run an installed skill (Tab completes the name)`,
        '  /import-skill <file.md>  add or overwrite a skill from a Markdown file',
        '  /skills                  open the skill manager (Tab switches tabs)',
        '  /skills install <name>   download one from the repo, without the panel',
        '  /skills remove <name>    delete the local copy',
        '  /plugins                 open the plugin manager',
        '  /plugins install <name>  download one from the repo',
        '',
        'Shortcuts',
        '  Enter          send the message',
        '  Shift+Enter    insert a newline',
        '  Ctrl+Shift+C   copy the selection (or the last answer)',
        '  Ctrl+Shift+V   paste the clipboard (multi-line pastes collapse)',
        '  ↑ / ↓          input history (empty composer) · scroll the chat',
        '  /              open the command menu · Tab completes',
        '  !              on an empty prompt: switch to shell mode (Esc/Backspace to leave)',
        '  Esc            cancel the menu / dialog · interrupt the turn',
        '  Ctrl+E         open config.toml in editor',
        '  Ctrl-B         move a running Bash command to the background',
        '  Ctrl-S         steer queued input into the running turn',
        '  ↑ (queued)     recall the last queued message for editing',
        '  Ctrl-O         expand/collapse tool output and thinking',
        '  Ctrl-T         expand/collapse the todo panel',
        '  Ctrl-C twice   exit hncode',
      ]);
      return;
    case 'status': {
      const lines = [
        `hncode v${VERSION}`,
        `Model:       ${cfg.model || 'not set'}${state.effort && state.effort !== 'off' ? ` (thinking ${state.effort})` : ''}`,
        `Provider:    ${cfg.provider || 'not set'}${cfg.protocol ? ` (${cfg.protocol})` : ''}`,
        `Endpoint:    ${cfg.endpoint || 'not set'}`,
        `API key:     ${cfg.apiKey ? 'set' : 'NOT SET'}`,
        `Directory:   ${state.cwd}`,
        `Permissions: ${PERMISSION_LABEL[state.mode]}`,
        `Plan mode:   ${state.plan ? 'on' : 'off'}`,
        `Session:     ${session.id}`,
      ];
      if (session.title) lines.push(`Title:       ${session.title}`);
      if (state.objective) lines.push(`Goal:        ${state.objective}${state.goalPaused ? ' (paused)' : ''}`);
      lines.push(`Context:     ${state.ctxPercent}% (${fmtTokens(state.ctxTokens)}/${fmtTokens(state.ctxMax)})`);
      sayPanel(lines.join('\n'));
      return;
    }
    case 'usage': {
      const msgs = session.messages || [];
      const approx = Math.round(JSON.stringify(msgs).length / 3.5);
      const g = C.gray, w = C.white, b = C.bold;
      const u = state.usage || {};
      const lines = [
        w + b + 'Session usage' + C.reset,
        '  ' + g + 'messages      ' + C.reset + w + msgs.length + C.reset,
      ];
      // Provider-reported totals when there are any: they are what the model
      // actually billed. The estimate is the fallback for an endpoint that reports
      // nothing (or predates `stream_options`).
      if (u.calls) {
        const cr = u.input ? Math.round((u.cached || 0) / u.input * 100) : 0;
        lines.push('  ' + g + 'requests      ' + C.reset + w + fmtCount(u.calls) + C.reset);
        lines.push('  ' + g + 'input tokens  ' + C.reset + w + fmtCount(u.input || 0) + C.reset
          + (u.cached ? g + `  (${cr}% cached)` + C.reset : ''));
        lines.push('  ' + g + 'output tokens ' + C.reset + w + fmtCount(u.output || 0) + C.reset);
        if (u.reasoning) {
          lines.push('  ' + g + 'reasoning     ' + C.reset + w + fmtCount(u.reasoning) + C.reset
            + g + '  included in output' + C.reset);
        }
        lines.push('  ' + g + 'total tokens  ' + C.reset + w + fmtCount((u.input || 0) + (u.output || 0)) + C.reset);
        lines.push('  ' + g + 'est. cost     ' + C.reset + formatCost(usageCost(u, modelCost(cfg))) + C.reset);
      } else {
        lines.push('  ' + g + 'approx tokens ' + C.reset + w + fmtCount(approx) + C.reset);
        lines.push('  ' + g + 'token totals  ' + C.reset + C.gray
          + 'not reported by this endpoint yet' + C.reset);
      }
      lines.push('');
      lines.push(w + b + 'Context window' + C.reset);
      lines.push('  ' + g + 'used          ' + C.reset + w + `${state.ctxPercent}% `
        + g + `(${fmtTokens(state.ctxTokens)} / ${fmtTokens(state.ctxMax)})` + C.reset);
      // Trend of the request size across this session's steps: rises as history
      // accumulates and drops when a compaction trims it.
      const hist = Array.isArray(state.tokenHistory) ? state.tokenHistory : [];
      if (hist.length >= 2) {
        const chart = sparkChart(hist, 50, 6);
        if (chart.length) {
          const hi = Math.max(...hist);
          const lo = Math.min(...hist);
          lines.push('');
          lines.push(w + b + `Context over ${hist.length} steps` + C.reset
            + g + `  ${fmtTokens(lo)} → ${fmtTokens(hi)}` + C.reset);
          for (const row of chart) lines.push(g + '  ' + row + C.reset);
          lines.push(g + '  ' + '─'.repeat(Math.min(50, hist.length))
            + '  now: ' + fmtTokens(state.ctxTokens) + C.reset);
        }
      }
      sayRich(lines.join('\n'));
      return;
    }
    case 'cost': {
      // What this session has spent, at the CURRENT model's rates. The token totals
      // come from the provider's own accounting (`usage` events); the prices come
      // from models.dev, stored per model entry. Either half can be missing, and the
      // readout says which rather than printing a confident $0.00.
      //
      // `/cost usd` and `/cost cny` SWITCH the currency: the choice is written to
      // config.toml (`cost_currency`), so the status row and every later /cost use
      // it. Bare `/cost` reports in the currency already selected.
      const asked = normalizeCurrency(raw);
      if (raw && !asked) {
        appErr(`Unknown currency: ${raw} (expected ${SUPPORTED_CURRENCIES.join(' / ')})`);
        return;
      }
      const current = costCurrency(cfg);
      if (asked && asked !== current) {
        try { setConfigString('cost_currency', asked); }
        catch (e) { appErr('Could not write config.toml: ' + e.message); return; }
        cfg.raw.cost_currency = asked;
      }
      const wantCurrency = asked || current;
      // The row needs the rate SYNCHRONOUSLY, so warm the module's rate cache before
      // refreshing, otherwise a fresh `cny` switch would draw in USD until the next
      // usage event happened to refresh it.
      let fx = syncRate(wantCurrency, { override: cfgCnyPerUsd(cfg) });
      if (!fx && wantCurrency !== 'USD') {
        fx = await usdRate(wantCurrency, { override: cfgCnyPerUsd(cfg) });
      }
      refreshCost(state, cfg);
      const switched = asked && asked !== current;

      const u = state.usage || {};
      const usdCost = usageCost(u, modelCost(cfg));
      const cost = modelCost(cfg);
      const g = C.gray, w = C.white, b = C.bold;
      const lines = [w + b + `Cost — ${state.modelLabel || cfg.model || '(no model)'}` + C.reset, ''];
      if (switched) {
        lines.push('  ' + g + `Currency → ${wantCurrency} (saved to config.toml)` + C.reset);
        lines.push('');
      }
      if (!u.calls) {
        lines.push('  ' + g + 'No token usage reported yet. Send a message — or the' + C.reset);
        lines.push('  ' + g + 'endpoint may not support streaming usage.' + C.reset);
        sayRich(lines.join('\n'));
        return;
      }
      lines.push('  ' + g + 'requests      ' + C.reset + w + fmtCount(u.calls) + C.reset);
      lines.push('  ' + g + 'input  tokens ' + C.reset + w + fmtCount(u.input || 0) + C.reset);
      lines.push('  ' + g + 'output tokens ' + C.reset + w + fmtCount(u.output || 0) + C.reset);
      if (u.cached) lines.push('  ' + g + 'cache reads   ' + C.reset + w + fmtCount(u.cached) + C.reset);
      if (u.cacheWrite) lines.push('  ' + g + 'cache writes  ' + C.reset + w + fmtCount(u.cacheWrite) + C.reset);
      lines.push('');
      if (!cost) {
        // A made-up $0.00 reads as "this was free", which is a lie in the one
        // direction that matters. Say the price is unknown, and show the exact TOML
        // to paste — a self-hosted or gateway provider (a local proxy, a company
        // endpoint) has no entry in models.dev, so the user is the only source.
        lines.push('  ' + C.red + 'No pricing for this model.' + C.reset);
        lines.push('  ' + g + 'A provider not added from the models.dev catalog has no' + C.reset);
        lines.push('  ' + g + 'price to read. Add one to config.toml:' + C.reset);
        lines.push('');
        lines.push('  ' + g + `[models.${JSON.stringify(cfg.model)}]` + C.reset);
        lines.push('  ' + g + 'cost_input = 0.15      # USD per 1M input tokens' + C.reset);
        lines.push('  ' + g + 'cost_output = 0.6      # USD per 1M output tokens' + C.reset);
        lines.push('  ' + g + 'cost_cache_read = 0.003' + C.reset);
        sayRich(lines.join('\n'));
        return;
      }
      const per = (v) => (v === undefined ? '—' : `$${v}`);
      lines.push('  ' + g + 'per 1M tokens ' + C.reset + w
        + `in ${per(cost.input)} · out ${per(cost.output)} · cache-read ${per(cost.cacheRead)}` + C.reset);
      if (wantCurrency === 'USD') {
        lines.push('  ' + w + b + 'estimated total ' + C.reset + formatCost(usdCost));
        lines.push('  ' + g + 'Switch with /cost cny for ￥ at the current rate.' + C.reset);
      } else if (!fx) {
        // Converting at a guessed 7.0 would be wrong in a way the user cannot see,
        // so show the true USD figure and say what is missing.
        lines.push('  ' + w + b + 'estimated total ' + C.reset + formatCost(usdCost));
        lines.push('  ' + C.red + `No ${wantCurrency} rate available (offline?).` + C.reset);
        lines.push('  ' + g + 'Set cny_per_usd in config.toml, or HNCODE_CNY_PER_USD.' + C.reset);
      } else {
        const local = convert(usdCost, wantCurrency, fx.rate);
        lines.push('  ' + w + b + 'estimated total ' + C.reset
          + formatCost(local, wantCurrency) + g + `  (${formatCost(usdCost)} @ ${fx.rate})` + C.reset);
        lines.push('  ' + g + `rate ${fx.rate} ${wantCurrency}/USD — ${fx.source}` + C.reset);
        lines.push('  ' + g + 'Switch back with /cost usd.' + C.reset);
      }
      sayRich(lines.join('\n'));
      return;
    }
    case 'raw': {
      // Verbatim rendering of assistant replies. Not persisted on purpose: it is a
      // debug view, and a session restored tomorrow should render normally.
      const a = raw.toLowerCase();
      let want;
      if (a === 'on') want = true;
      else if (a === 'off') want = false;
      else if (a === '') want = !state.rawMode;
      else { appErr('Usage: /raw [on|off]'); return; }
      state.rawMode = want;
      // The layout cache keys on rawMode (see metricsSignature), so invalidating the
      // metrics memo is enough — but the per-message row caches also carry it, and
      // both are keyed on it now, so nothing else has to be dropped here.
      state._metrics = null;
      app(want
        ? 'Raw mode: ON — replies shown exactly as the model sent them.'
        : 'Raw mode: OFF — Markdown rendering restored.');
      return;
    }
    case 'reduced-motion': {
      // Replaces every animation (spinner rotation, sweeps, pulse) with a dot that
      // slowly brightens and dims. Persisted because it is an accessibility choice:
      // a user who needs it should not have to re-enter it every launch.
      const a = raw.toLowerCase();
      let want;
      if (a === 'on') want = true;
      else if (a === 'off') want = false;
      else if (a === '') want = !state.reducedMotion;
      else { appErr('Usage: /reduced-motion [on|off]'); return; }
      state.reducedMotion = want;
      try { setConfigString('reduced_motion', want ? 'true' : 'false'); } catch { /* not fatal */ }
      app(want
        ? 'Reduced motion: ON — animation is replaced by a slow-breathing dot.'
        : 'Reduced motion: OFF — animation restored.');
      return;
    }
    case 'shimmer-edge': {
      // The sweep's band shape. Purely a matter of taste; persisted next to the other
      // look options. `cosine` matches codex's soft-both-edges band; `linear` is the
      // original one-sided ramp.
      const a = raw.trim().toLowerCase();
      if (!a || a === 'show') {
        app(`Shimmer edge: ${state.shimmerEdge}. /shimmer-edge cosine | linear`);
        return;
      }
      if (a !== 'cosine' && a !== 'linear') { appErr('Usage: /shimmer-edge cosine|linear'); return; }
      state.shimmerEdge = a;
      try { setConfigString('shimmer_edge', a); } catch { /* not fatal */ }
      app(`Shimmer edge: ${a}.`);
      return;
    }
    case 'output-style': {
      // Output styles, loaded from FILES (see output-styles.js). The style is
      // injected as a per-request system reminder rather than baked into the system
      // prompt, so switching does not invalidate the prompt cache.
      const arg = raw.trim();
      const lower = arg.toLowerCase();
      if (lower === 'off' || lower === 'none' || lower === 'clear') {
        state.outputStyle = null;
        cfg.outputStyle = null;
        try { setConfigString('output_style', ''); } catch { /* not fatal */ }
        app('Output style cleared.');
        return;
      }
      if (lower === 'edit') {
        const file = state.outputStyle && state.outputStyle.file;
        if (!file) { appErr('No style selected. Pick one with /output-style, or create one with /output-style new <name>.'); return; }
        openEditor({
          title: `Output style — ${file}`,
          text: (() => { try { return fs.readFileSync(file, 'utf8'); } catch { return ''; } })(),
          caretRow: 0, caretCol: 0,
          onSave: (value) => {
            try { fs.writeFileSync(file, String(value)); }
            catch (e) { appErr('Could not write ' + file + ': ' + e.message); return; }
            // Re-read so an edit takes effect on the NEXT request.
            const again = findStyle(state.outputStyle.name, state.cwd);
            state.outputStyle = again;
            app(`Style saved: ${again ? again.name : file}`);
          },
        });
        return;
      }
      if (lower.startsWith('new')) {
        const name = arg.slice(3).trim();
        const dir = styleDirs(state.cwd)[0];
        const { file, created } = writeStyleTemplate(dir, name || 'my-style');
        app(created ? `Created ${file} — /output-style edit to fill it in.` : `Already exists: ${file}`);
        openEditor({
          title: `New output style — ${file}`,
          text: (() => { try { return fs.readFileSync(file, 'utf8'); } catch { return ''; } })(),
          caretRow: 3, caretCol: 0,
          onSave: (value) => {
            try { fs.writeFileSync(file, String(value)); } catch (e) { appErr('Could not write: ' + e.message); return; }
            const s = findStyle(nameFromFile(file), state.cwd);
            if (s) { state.outputStyle = s; cfg.outputStyle = s.name; app(`Output style → ${s.name}`); }
            else app(`Saved ${file} (no body yet, so it is not selectable).`);
          },
        });
        return;
      }
      // A name selects it; a bare `/output-style` lists what is available.
      const styles = listStyles(state.cwd);
      if (!arg) {
        if (!styles.length) {
          h.openPanel('Output styles', [
            'No styles found.',
            '',
            `Directory: ${styleDirs(state.cwd)[0]}`,
            'Create one with: /output-style new <name>',
            '',
            'A style is a Markdown file. The first line may be a name, and the',
            'body is the instruction added to every request.',
          ]);
          return;
        }
        openPicker({
          title: 'Output styles',
          items: [
            { label: 'None', sub: 'use the default formatting rules', action: 'none' },
            ...styles.map((s) => ({
              label: s.name,
              sub: s.description || path.basename(s.file),
              current: !!(state.outputStyle && state.outputStyle.name === s.name),
              style: s,
            })),
          ],
          searchable: true,
          onPick: (it) => {
            if (it.action === 'none') {
              state.outputStyle = null; cfg.outputStyle = null;
              try { setConfigString('output_style', ''); } catch { /* not fatal */ }
              app('Output style cleared.');
              return true;
            }
            state.outputStyle = it.style;
            cfg.outputStyle = it.style.name;
            try { setConfigString('output_style', it.style.name); } catch { /* not fatal */ }
            app(`Output style → ${it.style.name}`);
            return true;
          },
        });
        return;
      }
      const found = findStyle(arg, state.cwd);
      if (!found) { appErr(`No style matching "${arg}". /output-style to list them.`); return; }
      state.outputStyle = found;
      cfg.outputStyle = found.name;
      try { setConfigString('output_style', found.name); } catch { /* not fatal */ }
      app(`Output style → ${found.name}`);
      return;
    }
    case 'experiments': {
      // Feature flags (see experiments.js). Bare `/experiments` lists them with
      // their state; `/experiments <name> on|off` sets one. The list is what makes
      // a bug report reproducible, so the flags are shown with what they do.
      const parts = raw.trim().split(/\s+/).filter(Boolean);
      const stateNow = experimentState(cfg);
      if (!parts.length) {
        const rows = describeExperiments(stateNow);
        const lines = [
          'Unfinished features. Off unless enabled here or in config.toml.',
          '',
          ...rows.map((r) => `  ${r.on ? '[on] ' : '[off]'} ${r.name.padEnd(22)} ${r.desc}`),
          '',
          'Toggle:  /experiments <name> on|off',
          'Env:     HNCODE_EXPERIMENTS=name1,name2 turns them on for one run',
          `Config:  [experiments] in ${hncodeConfigFile()}`,
        ];
        h.openPanel('Experiments', lines);
        const on = rows.filter((r) => r.on);
        if (on.length) app(`${on.length} experiment(s) on: ${on.map((r) => r.name).join(', ')}`);
        return;
      }
      const name = parts[0];
      if (!isExperiment(name)) {
        appErr(`Unknown experiment: ${name}. /experiments lists them.`);
        return;
      }
      let want;
      if (parts[1] === 'on') want = true;
      else if (parts[1] === 'off') want = false;
      else if (!parts[1]) want = !stateNow[name];
      else { appErr('Usage: /experiments <name> [on|off]'); return; }
      const merged = mergeExperiments(cfg.raw.experiments, { [name]: want });
      try {
        setConfigString('experiments', JSON.stringify(merged));
      } catch (e) { appErr('Could not write config.toml: ' + e.message); return; }
      cfg.raw.experiments = merged;
      app(`Experiment ${name}: ${want ? 'ON' : 'OFF'}`);
      // A flag can only affect code that reads it, and most of them are read when a
      // request is built, so the change is announced as taking effect next turn
      // rather than pretending to be live.
      app('Takes effect on the next request.');
      return;
    }
    case 'btw':
    case 'aside': {
      // A side question, shown in a BOX DOCKED ABOVE THE COMPOSER — kimi's placement.
      // The conversation you are asking about stays visible, and the composer is where
      // you keep typing: a follow-up question needs no command at all, because
      // sendPrompt routes to this box while it is open (see the composer path).
      //
      // The side thread FORKS the conversation, so the model knows what you are working
      // on; nothing it says is written back to the session.
      const question = raw.trim();

      if (!question) {
        // Bare `/btw`: open the box (asking nothing yet) or explain it.
        if (state.btwPanel) { app('The side-thread box is already open — type a question, or press Esc to close it.'); return; }
        state.btwPanel = { turns: [], model: '', reasoning: false };
        state.btwScroll = 0;
        app('Side thread box open — type a question and press Enter. Esc closes it.');
        renderFrame();
        return;
      }
      if (question.toLowerCase() === 'clear') {
        state.sideThread = null;
        state.btwPanel = null;
        state.btwScroll = 0;
        app('Side thread closed.');
        renderFrame();
        return;
      }

      if (!state.sideThread) {
        const modelCfg = secondaryModelCfg(cfg);
        state.sideThread = new SideThread({
          basePrompt: (cfg.systemPrompt && String(cfg.systemPrompt).trim()) || SYSTEM_PROMPT,
          // The fork: the conversation as it stands NOW. A copy, so nothing the side
          // thread appends can reach the session.
          history: forkMessages(session),
          tools: SIDE_RO_TOOLS,
          model: modelCfg.model || cfg.model,
        });
      }
      if (!state.btwPanel) state.btwPanel = { turns: [], model: '', reasoning: false };
      await askSideQuestion(state, cfg, question, renderFrame);
      return;
    }
    case 'recap': {
      // Where the session got to. Read-only: it changes nothing, unlike /compact.
      const stats = digestStats(session.messages);
      // A recap is ABOUT the conversation, so it gets the real history rather than a
      // digest — a lossy summary of a summary is worse than the original. Bounded, so
      // a very long session does not send its opening messages to answer "where am I".
      const history = forkMessages(session, { limit: 80 });
      if (!history.length) {
        app('Nothing to recap yet — this session has no conversation.');
        return;
      }
      const modelCfg = secondaryModelCfg(cfg);
      const llm = new LLM({ ...modelCfg, maxOutputTokens: Math.max(512, modelCfg.maxOutputTokens || 0) });
      notice(`Recapping (${modelCfg.model || cfg.model})…`, 'info');
      try {
        const text = await llm.requestText(recapMessages(history), { noTools: true, noReasoning: true });
        if (text === null) { appErr('The recap request failed.'); return; }
        if (!text.trim()) { appErr('The recap came back empty.'); return; }
        h.openPanel('Recap', [
          `${stats.users} prompt(s), ${stats.assistants} repl(y|ies), ${stats.total} entries`,
          '',
          ...text.trim().split('\n'),
          '',
          '/replay walks the same session step by step.',
        ]);
      } catch (e) {
        appErr(`Recap failed: ${e.message}`);
      }
      return;
    }
    case 'secondary-model': {
      // The model for side work. Stored by NAME in config.toml; empty means "use the
      // session's model", which is the safe default — a model the user never chose
      // should not be invented from whatever happens to be in the list.
      const arg = raw.trim();
      if (!arg) {
        const models = Object.keys((cfg.raw && cfg.raw.models) || {});
        h.openPicker({
          title: 'Secondary model (side questions, recaps)',
          items: [
            { label: '(same as this session)', sub: cfg.model || '(none)', action: 'off' },
            ...models.map((m) => ({ label: m, current: cfg.secondaryModel === m, action: 'set', model: m })),
          ],
          searchable: true,
          onPick: (it) => {
            const value = it.action === 'off' ? '' : it.model;
            try { setConfigString('secondary_model', value); }
            catch (e) { appErr('Could not write config.toml: ' + e.message); return true; }
            cfg.secondaryModel = value;
            cfg.raw.secondary_model = value;
            app(value ? `Secondary model → ${value}` : 'Secondary model cleared — side work uses this session\'s model.');
            return true;
          },
        });
        return;
      }
      if (arg.toLowerCase() === 'off' || arg.toLowerCase() === 'none') {
        try { setConfigString('secondary_model', ''); } catch (e) { appErr(e.message); return; }
        cfg.secondaryModel = '';
        cfg.raw.secondary_model = '';
        app('Secondary model cleared.');
        return;
      }
      // Accept a partial name, like /model does, so the user does not have to type the
      // whole provider-prefixed key.
      const keys = Object.keys((cfg.raw && cfg.raw.models) || {});
      const hit = keys.find((k) => k === arg)
        || keys.find((k) => k.toLowerCase() === arg.toLowerCase())
        || keys.find((k) => k.toLowerCase().includes(arg.toLowerCase()));
      if (!hit) { appErr(`No model matching "${arg}". /secondary-model lists them.`); return; }
      try { setConfigString('secondary_model', hit); } catch (e) { appErr(e.message); return; }
      cfg.secondaryModel = hit;
      cfg.raw.secondary_model = hit;
      app(`Secondary model → ${hit}`);
      return;
    }
    case 'replay':
    case 'rollout': {
      // Step through the session. A read-only VIEW: nothing is resumed or re-sent.
      const steps = buildSteps(session.messages);
      if (!steps.length) { app('This session has nothing to replay.'); return; }
      const arg = raw.trim().toLowerCase();
      const pos = (() => {
        const cur = Number.isFinite(state.replayStep) ? state.replayStep : steps.length - 1;
        if (arg === 'first') return 0;
        if (arg === 'last' || arg === '') return steps.length - 1;
        if (arg === 'next' || arg === 'n') return Math.min(steps.length - 1, cur + 1);
        if (arg === 'prev' || arg === 'p') return Math.max(0, cur - 1);
        const n = Number(arg);
        // A 1-based step number, because the frame shows `step 3/12`.
        return Number.isInteger(n) && n >= 1 ? Math.min(steps.length - 1, n - 1) : steps.length - 1;
      })();
      state.replayStep = pos;
      const summary = replaySummary(steps);
      h.openPanel('Replay', [
        ...renderStep(steps, pos, { width: 78 }),
        '',
        `${summary.total} step(s): ${Object.entries(summary.counts).map(([k, v]) => `${v} ${k}`).join(', ')}`,
        'Next: /replay next · prev: /replay prev · jump: /replay <n>',
      ]);
      return;
    }
    case 'schedule': {
      // Recurring prompts. `list` shows them; `run <id>` fires one now for testing
      // (which is the only way to check a schedule without waiting for the clock).
      const parts = raw.trim().split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      if (sub === 'run') {
        const id = parts[1];
        const rows = listSchedules(cfg.schedule);
        const entry = rows.find((e) => e.id === id);
        if (!entry) { appErr(`No schedule "${id || ''}". /schedule lists them.`); return; }
        if (!entry.valid) { appErr(`Schedule "${id}" is invalid: ${entry.error}`); return; }
        app(`Running schedule "${id}" now.`);
        sendPrompt(entry.prompt, { fromSchedule: id });
        return;
      }
      if (sub && sub !== 'list') { appErr('Usage: /schedule [list | run <id>]'); return; }
      const rows = listSchedules(cfg.schedule);
      const bad = rows.filter((e) => !e.valid);
      h.openPanel('Schedules', [
        'Prompts queued on this session while it is open.',
        '',
        describeSchedules(cfg.schedule),
        '',
        `Config file: ${hncodeConfigFile()}`,
        'A schedule fires ONCE per due minute; a session closed over the due time',
        'does not fire a catch-up burst when it starts again.',
        '',
        'Field order: minute hour day-of-month month day-of-week',
        'When BOTH day fields are set, cron fires on EITHER (that is the standard rule).',
      ]);
      if (bad.length) appErr(`${bad.length} schedule(s) are invalid — see /schedule.`);
      return;
    }
    case 'teleport': {
      // Export or import a session, rewriting the workspace path if it moved.
      const parts = raw.trim().split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      if (sub === 'import') {
        const file = parts.slice(1).join(' ');
        if (!file) { appErr('Usage: /teleport import <file>'); return; }
        let text = '';
        try { text = fs.readFileSync(file, 'utf8'); }
        catch (e) { appErr(`Could not read ${file}: ${e.message}`); return; }
        let pack;
        try { pack = parseTeleport(text); }
        catch (e) { appErr(`Not a usable teleport: ${e.message}`); return; }
        const { session: imported, warnings } = unpackInto(pack, {
          workspace: state.workspace || cfg.workspace,
          newId: () => sess.newId(),
        });
        for (const w of warnings) app(`Note: ${w}`);
        imported.id = imported.id || sess.newId();
        try { sess.saveSession(imported); } catch (e) { appErr(`Could not save: ${e.message}`); return; }
        app(`Imported "${imported.title || 'untitled'}" as ${imported.id} — resume it with /sessions.`);
        return;
      }
      if (sub && sub !== 'export') { appErr('Usage: /teleport [export [path] | import <file>]'); return; }
      const pack = packSession(session, {
        from: state.workspace || cfg.workspace,
        to: state.workspace || cfg.workspace,
      });
      const dir = path.join(path.dirname(hncodeConfigFile()), 'teleport');
      const out = parts.slice(1).join(' ') || path.join(dir, teleportFileName(session));
      try {
        fs.mkdirSync(path.dirname(out), { recursive: true });
        fs.writeFileSync(out, serializeTeleport(pack), 'utf8');
      } catch (e) { appErr(`Could not write ${out}: ${e.message}`); return; }
      h.openPanel('Teleport exported', [
        out,
        '',
        describeTeleport(pack),
        '',
        'What travels: the conversation, with paths rewritten.',
        'What does not: background jobs, token totals, and session approvals —',
        'those describe THIS machine and would be wrong on another.',
        '',
        'Move it with scp/ssh, then on the other side:',
        `  /teleport import ${path.basename(out)}`,
      ]);
      return;
    }
    case 'context': {
      // Break the context window down by what actually occupies it, so the user
      // can see WHERE the tokens go instead of one percentage. Mirrors Claude
      // Code's ContextVisualization.
      const { byRole, countByRole, toolDefTokens, toolCount } = contextBreakdown(session, cfg);
      const total = byRole.system + byRole.user + byRole.assistant + byRole.tool + byRole.other + toolDefTokens;
      const max = state.ctxMax || cfg.maxContextTokens || 1;
      const pct = (n) => `${(n / max * 100).toFixed(1)}%`;      // A simple bar so the biggest consumer is obvious at a glance.
      const bar = (n) => {
        const width = 24;
        const filled = Math.max(0, Math.min(width, Math.round(n / Math.max(1, total) * width)));
        return '█'.repeat(filled) + '░'.repeat(width - filled);
      };
      const rows = [
        ['system prompt', byRole.system, countByRole.system],
        ['tool definitions', toolDefTokens, toolCount],
        ['user messages', byRole.user, countByRole.user],
        ['assistant', byRole.assistant, countByRole.assistant],
        ['tool results', byRole.tool, countByRole.tool],
      ];
      if (byRole.other) rows.push(['other', byRole.other, countByRole.other]);
      rows.sort((a, b) => b[1] - a[1]);
      const g = C.gray, w = C.white, b = C.bold;
      const lines = [
        w + b + `Context breakdown` + C.reset
          + g + `  (${fmtTokens(total)} / ${fmtTokens(max)}  ${pct(total)})` + C.reset,
        '',
      ];
      for (const [name, tok, cnt] of rows) {
        if (!tok) continue;
        lines.push(
          '  ' + g + bar(tok) + C.reset
          + w + `  ${fmtTokens(tok).padStart(7)}` + C.reset
          + g + `  ${pct(tok).padStart(6)}  ` + C.reset
          + w + name + C.reset
          + (cnt ? g + ` (${cnt})` + C.reset : ''),
        );
      }
      // Advice, only when there is something worth saying.
      const tips = [];
      if (byRole.tool > total * 0.4) tips.push('Tool results dominate — /compact or a narrower search would free the most.');
      if (byRole.system > total * 0.3) tips.push('The system prompt is large — trim AGENTS.md / personal prompt.');
      if (total / max > 0.8) tips.push('Over 80% — auto-compaction is close. /compact now to keep control.');
      if (tips.length) lines.push('', ...tips.map((t) => g + '  ' + t + C.reset));
      sayRich(lines.join('\n'));
      return;
    }
    case 'search': {
      // Interactive project search: type to search (ripgrep via the Grep tool),
      // Enter inserts the hit as `path:line: text` into the composer.
      const picker = {
        title: 'Search project',
        hint: '↑↓ navigate · Enter insert · Esc cancel',
        items: [],
        sel: 0,
        searchable: true,
        _loading: false,
        onQueryChange: (q) => {
          const query = String(q || '').trim();
          const mine = ++searchSeq;
          if (!query) { picker.items = []; picker._loading = false; renderFrame(); return; }
          const tool = getTool('Grep');
          if (!tool) { picker.items = [{ label: 'Grep tool unavailable' }]; renderFrame(); return; }
          picker._loading = true;
          renderFrame();
          Promise.resolve(tool.execute({ pattern: query, path: '.' }, { cwd: state.cwd, workspace: state.workspace, signal: { aborted: false } }))
            .then((out) => {
              if (mine !== searchSeq) return;   // a newer query superseded this one
              picker._loading = false;
              const text = typeof out === 'string' ? out : '';
              const rows = text.split('\n').filter((l) => l && !/^\[?error/i.test(l)).slice(0, 200);
              picker.items = rows.map((line) => {
                // Path may contain a drive colon on Windows (`D:\a\b.js:12:code`),
                // so anchor on `:<digits>:` rather than the first colon.
                const m = /^(.*?):(\d+):(.*)$/.exec(line);
                if (m) return { label: `${m[1]}:${m[2]}`, sub: m[3].trim().slice(0, 100), hit: { path: m[1], line: Number(m[2]) } };
                return { label: line.slice(0, 120), sub: '', hit: null };
              });
              renderFrame();
            })
            .catch(() => { if (mine === searchSeq) { picker._loading = false; picker.items = []; renderFrame(); } });
        },
        onPick: (item) => {
          const insert = item && item.hit ? `${item.hit.path}:${item.hit.line}` : (item ? item.label : '');
          state.input = (state.input || '') + insert;
          state.caret = state.input.length;
          refreshMenu(state);
          return true;
        },
      };
      searchSeq += 1;
      state.picker = picker;
      state.pickerQuery = raw.trim();
      state.pickerCategory = null;
      if (state.pickerQuery) picker.onQueryChange(state.pickerQuery);
      renderFrame();
      return;
    }
    case 'auto-update': {
      // Toggle /auto-update. Persists to config.toml so it survives restarts.
      const a = raw.toLowerCase();
      let want;
      if (a === 'on') want = true;
      else if (a === 'off') want = false;
      else want = !cfg.autoUpdate;
      try { setConfigString('auto_update', want ? 'true' : 'false'); }
      catch (e) { appErr('Could not write config.toml: ' + e.message); return; }
      cfg.autoUpdate = want;
      cfg.raw.auto_update = want;
      app(want
        ? 'Auto-update ON — checks npm at startup and every 30 min, installs in the background'
        : 'Auto-update OFF');
      return;
    }
    case 'auto-compact': {
      // /auto-compact              -> toggle on/off (persisted)
      // /auto-compact on|off       -> set explicitly
      // /auto-compact threshold 85%  -> fire when usage reaches 85% of the window
      // /auto-compact keep 20%       -> keep ~20% of the CURRENT usage after a trim
      const parts = raw.trim().split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      const valStr = parts.slice(1).join(' ').trim();
      const parseRatio = (s) => {
        const str = String(s || '').trim();
        if (!str) return null;
        const pct = str.endsWith('%');
        const n = parseFloat(str);
        if (!Number.isFinite(n)) return null;
        const v = pct ? n / 100 : (n > 1 ? n / 100 : n);   // "85" and "85%" both = 0.85
        if (!(v > 0 && v < 1)) return null;
        return v;
      };
      if (sub === 'threshold' || sub === 'keep') {
        const v = parseRatio(valStr);
        if (v === null) { appErr(`Usage: /auto-compact ${sub} <0-1 | n%>  (e.g. ${sub === 'threshold' ? '0.85 or 85%' : '0.2 or 20%'})`); return; }
        const key = sub === 'threshold' ? 'compact_threshold' : 'compact_keep_ratio';
        try { setConfigString(key, String(v)); }
        catch (e) { appErr('Could not write config.toml: ' + e.message); return; }
        if (sub === 'threshold') { cfg.compactThreshold = v; cfg.raw.compact_threshold = v; }
        else { cfg.compactKeepRatio = v; cfg.raw.compact_keep_ratio = v; }
        app(sub === 'threshold'
          ? `Auto-compaction now fires at ${Math.round(v * 100)}% of the context window`
          : `Auto-compaction now keeps ~${Math.round(v * 100)}% of the current usage after trimming`);
        return;
      }
      // Toggle / set on/off. Persists to config.toml so it survives restarts.
      let want;
      if (sub === 'on') want = true;
      else if (sub === 'off') want = false;
      else want = cfg.autoCompact === false;   // flip from the current state
      try { setConfigString('auto_compact', want ? 'true' : 'false'); }
      catch (e) { appErr('Could not write config.toml: ' + e.message); return; }
      cfg.autoCompact = want;
      cfg.raw.auto_compact = want;
      const pct = Math.round((cfg.compactThreshold == null ? 0.85 : cfg.compactThreshold) * 100);
      app(want
        ? `Auto-compaction ON — older history is summarized once a request reaches ${pct}% of the context window`
        : 'Auto-compaction OFF — history is no longer trimmed automatically (use /compact manually)');
      return;
    }
    case 'auto-trim': {
      // /auto-trim                 -> toggle on/off (persisted)
      // /auto-trim on|off          -> set explicitly
      // /auto-trim threshold 50%   -> trim once a request reaches 50% of the window
      // /auto-trim keep 30%        -> keep ~30% of the tool-result TEXT after a trim
      //
      // The mirror of /auto-compact above, deliberately: same argument shape, same
      // persistence, same wording. Trimming is the cheap pass (replace old tool
      // bodies with a pointer to disk), compaction is the expensive one (summarize
      // history); the trigger here defaults far lower because doing it early avoids
      // needing the other at all.
      // Accepts a fraction ("0.5"), a whole-number percentage ("50"), or an
      // explicit percentage ("50%"). A trailing `%` ALWAYS means percent. Without
      // it, a bare value >= 1 is read as a percentage ONLY when it is a whole
      // number: "50" is 50%, but "1.5" is rejected rather than silently read as
      // 1.5% — a value that looks like an out-of-range fraction is far more likely
      // a typo than a deliberate hundredth.
      const parseRatioTrim = (s) => {
        const str = String(s || '').trim();
        if (!str) return null;
        const pct = str.endsWith('%');
        const n = parseFloat(str);
        if (!Number.isFinite(n)) return null;
        if (!pct && n >= 1 && !Number.isInteger(n)) return null;
        const v = pct ? n / 100 : (n >= 1 ? n / 100 : n);
        if (!(v > 0 && v < 1)) return null;
        return v;
      };
      const parts = raw.trim().split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      const valStr = parts.slice(1).join(' ').trim();
      if (sub === 'threshold' || sub === 'keep') {
        const v = parseRatioTrim(valStr);
        if (v === null) {
          appErr(`Usage: /auto-trim ${sub} <0-1 | n%>  (e.g. ${sub === 'threshold' ? '0.5 or 50%' : '0.3 or 30%'})`);
          return;
        }
        const key = sub === 'threshold' ? 'trim_threshold' : 'trim_keep_ratio';
        try { setConfigString(key, String(v)); }
        catch (e) { appErr('Could not write config.toml: ' + e.message); return; }
        if (sub === 'threshold') { cfg.trimThreshold = v; cfg.raw.trim_threshold = v; }
        else { cfg.trimKeepRatio = v; cfg.raw.trim_keep_ratio = v; }
        app(sub === 'threshold'
          ? `Auto-trim now fires at ${Math.round(v * 100)}% of the context window`
          // Both knobs are shares of the SAME thing — what the model is sent — so the
          // denominator is named here. It was "of the tool-result text", which read as a
          // different scale from the line above and is no longer what the code does.
          : `Auto-trim now keeps ~${Math.round(v * 100)}% of the tool-result text after trimming`);
        return;
      }
      let wantTrim;
      if (sub === 'on') wantTrim = true;
      else if (sub === 'off') wantTrim = false;
      else wantTrim = cfg.autoTrim === false;   // flip from the current state
      try { setConfigString('auto_trim', wantTrim ? 'true' : 'false'); }
      catch (e) { appErr('Could not write config.toml: ' + e.message); return; }
      cfg.autoTrim = wantTrim;
      cfg.raw.auto_trim = wantTrim;
      const thr = Math.round((cfg.trimThreshold == null ? 0.5 : cfg.trimThreshold) * 100);
      const keepPct = Math.round((cfg.trimKeepRatio == null ? 0.3 : cfg.trimKeepRatio) * 100);
      app(wantTrim
        ? `Auto-trim ON — old tool results are elided from the request once it reaches ${thr}% of the window, keeping ~${keepPct}% of them (use /trim to do it now)`
        : 'Auto-trim OFF — tool results are sent in full (use /trim to elide them once)');
      return;
    }
case 'trim': {
      // Manual trim, the counterpart of /auto-trim. Runs the same pass on demand,
      // regardless of the trigger ratio — for when the user knows the history is
      // carrying output they are done with and does not want to wait for the 50%
      // mark.
      //
      // The single optional argument IS the keep ratio (`/trim 30%`), with no
      // `keep` keyword in front of it: there is only one parameter, so naming it
      // adds a word to type and nothing to remember.
      //
      // Deliberately does NOT touch the saved session: this elides what is SENT and
      // copies the removed text to disk (see tool-result.js), so the transcript the
      // user scrolls back through is intact.
      const parts = raw.trim().split(/\s+/).filter(Boolean);
      let keepRatio = Number.isFinite(cfg.trimKeepRatio) ? cfg.trimKeepRatio : 0.3;
      // `[keep-ratio]`, not `[0.3]`: 0.3 is the DEFAULT, not the only accepted
      // value. The code takes a fraction (`0.3`) or a percent (`30%` / `30`), so the
      // placeholder names the TYPE and the default moves into the text — the same
      // shape as /compact's `[ratio]` and /effort's `[level]`.
      const USAGE = `Usage: /trim [keep-ratio]  (a fraction like 0.3, or a percent like 30%; default ${keepRatio})`;
      if (parts.length > 1) { appErr(USAGE); return; }
      if (parts.length === 1) {
        const spec = String(parts[0]).trim();
        const pct = spec.endsWith('%');
        const n = parseFloat(spec);
        // Same convention as /auto-trim: a trailing `%` always means percent, and a
        // bare value >= 1 must be a whole-number percentage ("50" is 50%, "1.5" is
        // rejected rather than silently read as 1.5%).
        if (Number.isFinite(n) && !pct && n >= 1 && !Number.isInteger(n)) { appErr(USAGE); return; }
        const v = Number.isFinite(n) ? (pct ? n / 100 : (n >= 1 ? n / 100 : n)) : NaN;
        if (!(v > 0 && v < 1)) { appErr(USAGE); return; }
        keepRatio = v;
      }
      const target = (state.agent && state.agent.messages) || (session && session.messages);
      if (!target || !target.length) { app('Nothing to trim.'); return; }
      const before = estimateMessagesTokens(target);
      const res = trimToolResults(target, { sessionId: session && session.id, keepRatio });
      if (!res || !res.elided) { app('Nothing to trim — no tool result is large enough to elide.'); return; }
      // `trimToolResults` rewrote content IN PLACE, and the target may be the agent's
      // own live message array. The agent keeps a rolling token total over it, so it
      // has to be told: otherwise its ledger still describes the pre-trim bodies, the
      // next request is priced as if nothing had been freed, and auto-compaction fires
      // on a history that was just trimmed.
      if (state.agent && target === state.agent.messages && state.agent._ledger) state.agent._ledger.reset();
      const after = estimateMessagesTokens(target);
      // Update the STATUS LINE, not just the transcript. The context gauge is fed
      // by request events (llm.js emits `tokens`/`after`), so trimming between
      // requests left it showing the pre-trim number until the next turn — the user
      // had to send a message to see the effect. `/trim` knows the exact count, so
      // push it into the same state fields the events would have set.
      state.ctxTokens = after;
      state.ctxPercent = usagePercent(after, state.ctxMax || cfg.maxContextTokens || 1);
      if (session) {
        try {
          session.tokenHistory = Array.isArray(session.tokenHistory) ? session.tokenHistory : [];
          if (session.tokenHistory[session.tokenHistory.length - 1] !== after) session.tokenHistory.push(after);
        } catch { /* history is best-effort */ }
      }
      app(`Trimmed ${res.elided} tool result(s): ~${fmtTokens(res.elidedBytes / 4)} tokens of output elided, keeping ~${Math.round(keepRatio * 100)}%.`);
      app(`Context now ~${fmtTokens(after)} (was ~${fmtTokens(before)}). The removed text is on disk — the model can Read it back.`);
      renderFrame();
      return;
    }
    case 'update': {
      // Manual update check. This is the ONLY place an update is ever reported;
      // the automatic background check stays completely silent.
      app('Checking for updates...');
      cfg.updateRunning = true;
      try {
        const r = await upd.checkAndUpdate();
        if (r.status === 'updated') app(r.message);
        else if (r.status === 'uptodate') app(r.message);
        else app('Update check: ' + (r.message || 'failed'));
      } catch (e) {
        appErr('Update check failed: ' + (e && e.message || e));
      } finally {
        cfg.updateRunning = false;
      }
      return;
    }
    case 'version': app(`hncode v${VERSION}`); return;

    case 'mcp': {
      // Show REAL connection state (from startup) alongside the configured
      // servers, plus each server's discovered tools. `/mcp tools` lists them.
      const cfgMcp = loadMcpConfig(state.workspace || cfg.workspace);
      const conns = getLiveConnections();
      const lines = describeServers(cfgMcp, conns);
      if (cfgMcp.errors.length) lines.push('', 'Config problems:', ...cfgMcp.errors.map((e) => `  ! ${e}`));
      const showTools = String(raw || '').toLowerCase() === 'tools';
      if (showTools) {
        const found = conns.filter((c) => c.ok).map((c) => `  ${c.name}: ${c.toolCount} tool(s)`);
        lines.push('', found.length ? 'Discovered tools:' : 'No servers connected — they connect at startup.');
        lines.push(...found);
      }
      h.openPanel('hncode — mcp', lines);
      return;
    }
    case 'doctor': {
      // Diagnose the environment. Read-only: nothing here repairs or writes, so it is
      // safe to run on a machine whose state matters.
      //
      // Async because one of the checks profiles the largest session, which loads and
      // parses it. A synchronous report could not answer "where did the memory go".
      const cfgMcp = loadMcpConfig(state.workspace || cfg.workspace);
      // Terminal size comes from the `stdout` PARAMETER, not from `dims()`. `dims` is a
      // closure inside startTUI and this switch runs in the module-level `dispatch`, which
      // cannot see it — referencing it threw `dims is not defined` for anyone who ran
      // /doctor. `stdout` is already a dispatch parameter, and the fallback matches dims'.
      let termDims = { cols: 80, rows: 24 };
      try {
        const [c, r] = stdout.getWindowSize();
        termDims = { cols: c || 80, rows: r || 24 };
      } catch { /* not a TTY: the default stands */ }
      const args = {
        cfg,
        workspace: state.workspace || cfg.workspace || state.cwd,
        sessionsDir: sess.sessionsDir(),
        mcpServers: cfgMcp.servers,
        mcpConnections: getLiveConnections(),
        dims: termDims,
      };
      const flags = String(raw || '').trim().split(/\s+/).filter(Boolean);
      const showAll = flags.includes('--all') || flags.includes('-a');
      // `--probe` makes a real request, so it is opt-in and announced: the user is about to
      // spend a few tokens, and a report that silently did that would be worse than one that
      // did not.
      const probe = flags.includes('--probe');
      if (probe) {
        args.probe = true;
        args.childProcess = cp;
        h.notice('Probing the provider with one real request…', 'info');
      }
      Promise.resolve(runDoctor(args)).then((results) => {
        h.openPanel('hncode — doctor', formatDoctor(results, { showOk: showAll, version: VERSION }));
      }).catch((e) => {
        appErr(`doctor failed: ${(e && e.message) || e}`);
      });
      return;
    }
    case 'memory-profile': {
      // Where this session's memory actually goes. A file size or a row count says nothing
      // actionable: on a real 2.6 MB session the tool ARGUMENTS were 0.66 MB — more than the
      // text and the tool results combined — and no count hints at that.
      const verbose = /--verbose|-v\b/.test(String(raw || '').trim());
      const profile = profileMemory({ session, state, convRowFor: sess.convRowFor });
      h.openPanel('hncode — memory', renderMemoryProfile(profile, { verbose }));
      return;
    }
    case 'mcp-config': {
      const mcpFile = path.join(os.homedir(), '.hncode', 'mcp.json');
      const readDoc = () => {
        let doc = { mcpServers: {} };
        try { doc = JSON.parse(fs.readFileSync(mcpFile, 'utf8')); } catch { /* new/empty */ }
        doc.mcpServers = doc.mcpServers || {};
        return doc;
      };
      const writeDoc = (doc) => {
        fs.mkdirSync(path.dirname(mcpFile), { recursive: true });
        fs.writeFileSync(mcpFile, JSON.stringify(doc, null, 2) + '\n', 'utf8');
      };
      const [action, name, ...rest] = raw.split(/\s+/).filter(Boolean);

      // Bare `/mcp-config` -> an interactive MANAGER (cline-style dialog), not a
      // text dump. Listing is still available (`list`) for scripts, and the
      // add/remove forms below stay so existing usage keeps working.
      if (!action) {
        const doc = readDoc();
        const names = Object.keys(doc.mcpServers);
        const items = names.map((n) => {
          const s = doc.mcpServers[n] || {};
          return { label: n, sub: s.url ? s.url : `${s.command || ''} ${(s.args || []).join(' ')}`.trim(), _name: n };
        });
        items.push({ label: '＋ Add a server…', sub: 'register a new MCP server', _add: true });
        openPicker({
          title: `MCP servers (${names.length})`,
          items,
          searchable: true,
          hint: '↑↓ navigate · Enter manage · Esc close',
          onPick: (it) => {
            if (it && it._add) {
              openForm({
                title: 'Add MCP server',
                fields: [
                  { key: 'name', label: 'Name', value: '' },
                  { key: 'target', label: 'Command or URL', value: '' },
                  { key: 'args', label: 'Args (space-separated)', value: '' },
                ],
                type: null,
                hint: 'Tab next field · Enter save · Esc cancel',
                onSubmit: (values) => {
                  const n = (values.name || '').trim();
                  const target = (values.target || '').trim();
                  if (!n || !target) { appErr('Name and command/URL are required.'); return; }
                  const d = readDoc();
                  d.mcpServers[n] = /^https?:\/\//.test(target)
                    ? { url: target }
                    : { command: target, args: (values.args || '').split(/\s+/).filter(Boolean) };
                  writeDoc(d);
                  app(`MCP server added: ${n}. Start a new session to apply.`);
                },
              });
              return true;
            }
            if (!it || !it._name) return true;
            // Pick a server -> manage it: remove, with the file named so the action
            // is not a mystery. (Editing a server's target is rare; remove+re-add.)
            openPicker({
              title: `Manage "${it._name}"`,
              searchable: false,
              hint: '↑↓ choose · Enter confirm · Esc cancel',
              items: [
                { label: 'Back', sub: 'do nothing' },
                { label: 'Remove', sub: `delete this server from ${mcpFile} — start a new session to apply` },
              ],
              onPick: (sel) => {
                if (!sel || sel.label !== 'Remove') return true;
                const d = readDoc();
                delete d.mcpServers[it._name];
                writeDoc(d);
                app(`MCP server removed: ${it._name}. Start a new session to apply.`);
                return true;
              },
            });
            return true;
          },
        });
        return;
      }

      const doc = readDoc();
      if (action === 'list') {
        const names = Object.keys(doc.mcpServers);
        sayPanel(names.length ? `MCP servers (${mcpFile}):\n` + names.map((n) => `  ${n}`).join('\n') : `No MCP servers configured. File: ${mcpFile}`);
        return;
      }
      if (['remove', 'rm', 'delete'].includes(action)) {
        if (!name || !doc.mcpServers[name]) { appErr(`No such MCP server: ${name || '(none)'}`); return; }
        delete doc.mcpServers[name];
        writeDoc(doc);
        app(`MCP server removed: ${name}. Start a new session to apply.`);
        return;
      }
      if (action === 'add') {
        const target = rest[0] || '';
        if (!name || !target) { appErr('Usage: /mcp-config add <name> <command|url> [args...]'); return; }
        doc.mcpServers[name] = /^https?:\/\//.test(target) ? { url: target } : { command: target, args: rest.slice(1) };
        writeDoc(doc);
        app(`MCP server added: ${name} → ${mcpFile}. Start a new session to apply.`);
        return;
      }
      appErr('Usage: /mcp-config (manage) | list | add <name> <command|url> [args...] | remove <name>');
      return;
    }

    case 'save-history': {
      // What the DISPLAY-ONLY transcript keeps on disk: the notices, warnings, compaction
      // results, plan cards, background-task cards and reasoning blocks that have no home
      // in `session.messages` (that array is what gets sent to the model). Reasoning is
      // split out because it is the bulk of the cost — a long session's file grows by more
      // than its own answers — so the short notices can be kept without the megabytes.
      const on = (v) => (v === false ? 'on' : 'off');
      const what = String(raw || '').toLowerCase();
      if (what === 'on' || what === 'off') {
        state.saveHistory = what === 'on';
        // A settings change must reach disk at once, or a restart silently reverts it.
        session.saveHistory = state.saveHistory;
        session.saveThinking = state.saveThinking;
        persistState();
      } else if (what === 'thinking') {
        state.saveThinking = true;
        session.saveThinking = true;
        persistState();
      } else if (what === 'nothinking') {
        state.saveThinking = false;
        session.saveThinking = false;
        persistState();
      } else if (what) {
        appErr('Usage: /save-history [on|off|thinking|nothinking]');
        return;
      }
      say(`Saved history — display rows: ${on(state.saveHistory)} · reasoning: ${on(state.saveThinking)}`);
      renderFrame();
      return;
    }

    case 'theme': {
      const arg = raw.trim().toLowerCase();
      // ONE write path, shared with /settings and /set. Writing the config HERE by hand is
      // how the theme ended up half-applied: `setConfigString` reached the file but not
      // `cfg.raw`, so anything that re-read the setting - reopening this picker, a frame
      // composed later - saw the old value while the screen showed the new one.
      const apply = (name) => {
        if (!hasTheme(name)) {
          appErr(`Unknown theme "${name}". Known: ${THEME_NAMES.join(', ')}`);
          return false;
        }
        // `applySetting` writes config.toml, updates `cfg` AND `cfg.raw`, applies the
        // palette, and requests the full repaint a colour change needs.
        applySetting('theme', name);
        state.theme = name;
        return true;
      };
      if (THEME_NAMES.includes(arg)) {
        if (!apply(arg)) return;
        app(`Theme: ${arg}`);
        return;
      }
      if (arg) { appErr(`Usage: /theme [name]  — known: ${THEME_NAMES.join(', ')}`); return; }
      openPicker({
        title: 'Theme',
        items: THEME_NAMES.map((n) => ({
          label: n,
          sub: THEME_LABELS[n] || '',
          // `current` is the picker's own marker: a green `← current` AFTER the
          // description. Folding it into `label` put a grey arrow beside the name.
          current: state.theme === n,
          value: n,
        })),
        onPick: (it) => {
          if (apply(it.value)) app(`Theme: ${it.value}`);
          return true;
        },
      });
      return;
    }

    case 'keybindings': {
    }
    case 'keybindings': {
      // Bindings live in ~/.hncode/keybindings.json; this is the editing entry point.
      // A binding names a target the key dispatcher ALREADY understands (another key) or
      // a slash command, so nothing here can invent a state the UI cannot render.
      const parts = raw.trim().split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      const { file, doc } = readOrEmpty();
      if (!sub || sub === 'list') {
        h.openPanel('hncode — keybindings', describeKeybindings(loadKeybindings()));
        return;
      }
      if (sub === 'edit') {
        let text = '';
        try { text = fs.readFileSync(file, 'utf8'); } catch { text = '{\n  \n}\n'; }
        openEditor({
          title: `Keybindings — ${file}`,
          text, caretRow: 1, caretCol: 2,
          onSave: (value) => {
            try { fs.mkdirSync(path.dirname(file), { recursive: true }); fs.writeFileSync(file, String(value), 'utf8'); }
            catch (e) { appErr(`Could not write ${file}: ${e.message}`); return; }
            const now = refreshKeybindings();
            app(now.errors.length ? `Saved with ${now.errors.length} problem(s) — /keybindings to see them.` : `Saved. ${now.bindings.size} binding(s) active.`);
          },
        });
        return;
      }
      if (sub === 'add') {
        const from = parts[1];
        const to = parts.slice(2).join(' ');
        if (!from || !to) { appErr('Usage: /keybindings add <key> <key|/command>   e.g. /keybindings add ctrl+e /theme'); return; }
        const src = normalizeKey(from);
        if (!src) { appErr(`"${from}" is not a usable key name.`); return; }
        // Validate BEFORE writing: a file the loader would reject is worse than a refusal,
        // because the user then has a broken config and no idea which line did it.
        if (to.startsWith('/')) doc[src] = to.trim();
        else {
          const dst = normalizeKey(to);
          if (!dst) { appErr(`"${to}" is not a usable key name or a /command.`); return; }
          if (dst === src) { appErr('A key cannot be bound to itself.'); return; }
          doc[src] = dst;
        }
        try { writeKeybindings(undefined, doc); } catch (e) { appErr(`Could not write: ${e.message}`); return; }
        const now = refreshKeybindings();
        app(now.errors.length
          ? `Added ${src} → ${to}, but the file now has ${now.errors.length} problem(s).`
          : `Bound ${src} → ${to}`);
        return;
      }
      if (sub === 'remove' || sub === 'rm' || sub === 'delete') {
        const src = normalizeKey(parts[1] || '');
        if (!src) { appErr('Usage: /keybindings remove <key>'); return; }
        if (!(src in doc)) { appErr(`No binding for ${src}.`); return; }
        delete doc[src];
        try { writeKeybindings(undefined, doc); } catch (e) { appErr(`Could not write: ${e.message}`); return; }
        refreshKeybindings();
        app(`Unbound ${src}`);
        return;
      }
      // An unadorned key name sets that ONE binding, which is the shortest useful form.
      if (parts.length === 2) {
        const src = normalizeKey(parts[0]);
        if (src) {
          const to = parts[1];
          if (to.startsWith('/')) doc[src] = to.trim();
          else {
            const dst = normalizeKey(to);
            if (!dst || dst === src) { appErr('Target must be a different key or a /command.'); return; }
            doc[src] = dst;
          }
          try { writeKeybindings(undefined, doc); } catch (e) { appErr(`Could not write: ${e.message}`); return; }
          refreshKeybindings();
          app(`Bound ${src} → ${to}`);
          return;
        }
      }
      appErr('Usage: /keybindings [list | add <key> <key|/command> | remove <key> | edit]');
      return;
    }
    case 'agents': {
      // Control running subagents from the terminal, without spending a turn: the same
      // operations the model has as tools, for when the USER is the one watching a
      // subagent go wrong.
      const parts = raw.trim().split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      if (!sub || sub === 'list') {
        const rows = describeRuns();
        h.openPanel('hncode — subagents', rows);
        return;
      }
      if (sub === 'message' || sub === 'msg') {
        const id = parts[1];
        const text = parts.slice(2).join(' ');
        if (!id || !text) { appErr('Usage: /agents message <agent-id> <text>'); return; }
        const r = sendToRun(id, text);
        if (r.ok) app(r.message); else appErr(r.message);
        return;
      }
      if (sub === 'interrupt' || sub === 'stop') {
        const id = parts[1];
        if (!id || id === 'all') {
          const all = interruptAll();
          app(all.ok ? `Interrupted ${all.count} subagent(s): ${all.agents.join(', ')}` : 'No subagent is running.');
          return;
        }
        const r = interruptRun(id);
        if (r.ok) app(r.message); else appErr(r.message);
        return;
      }
      if (sub === 'close') {
        const id = parts[1];
        if (!id) { appErr('Usage: /agents close <agent-id>'); return; }
        const r = closeRun(id);
        if (r.ok) app(r.message); else appErr(r.message);
        return;
      }
      appErr('Usage: /agents [list | message <id> <text> | interrupt [id|all] | close <id>]');
      return;
    }
    case 'files': {
      // The walker is tools/ignore.js — the SAME one Grep and Glob use, so the browser can
      // never show a file the tools would refuse to search. Directories come from the flat
      // result, so there is no second traversal to disagree with the first.
      const filter = raw.trim();
      const cwd = state.cwd || cfg.workspace || process.cwd();
      let files = [];
      try {
        files = walkFiles(cwd, { includeIgnored: false });
      } catch (e) { appErr(`Could not read ${cwd}: ${e.message}`); return; }
      const root = buildTree(files, cwd);
      if (!root.children.length) { app(`No files found under ${cwd}.`); return; }
      // Open the FIRST level by default: a fully collapsed tree makes the user press →
      // before they can see anything, and a fully expanded one on a big repo dumps
      // thousands of rows.
      const expanded = new Set();
      for (const c of root.children) if (c.dir) expanded.add(c.rel);
      state.fileTree = { root, expanded, sel: 0, scroll: 0, filter, cwd };
      // Close the other overlays so only one thing owns the screen.
      state.picker = null; state.form = null; state.panel = null; state.menuOpen = false;
      renderFrame();
      return;
    }
    case 'checkpoints': {
      // Per-FILE checkpoints. /undo rewinds whole TURNS (transcript + every file those turns
      // touched); this is the surgical counterpart — "give me back this one file as it was
      // before that edit" — which the existing index already records but nothing could reach.
      const sid = session && session.id;
      const parts = raw.trim().split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      if (!sub || sub === 'list') {
        h.openPanel('hncode — checkpoints', describeCheckpoints(sid, state.workspace || cfg.workspace));
        return;
      }
      const n = Number(parts[1]);
      if (!Number.isFinite(n) || n < 1) { appErr('Usage: /checkpoints [list | restore <n> | diff <n>]'); return; }
      const all = listCheckpoints(sid);
      const entry = all.find((c) => c.index === n);
      if (!entry) { appErr(`No checkpoint ${n}. /checkpoints lists them.`); return; }
      if (sub === 'diff') {
        const d = checkpointDelta(entry);
        if (!d) { appErr('No size comparison available for that checkpoint.'); return; }
        const rel = entry.path;
        sayPanel(`${rel}\nthen: ${d.before} line(s)\nnow:  ${d.after} line(s)\nchange: ${d.lines >= 0 ? '+' : ''}${d.lines}`);
        return;
      }
      if (sub === 'restore') {
        const r = restoreCheckpoint(sid, entry);
        if (!r.ok) { appErr(`Could not restore: ${r.error}`); return; }
        app(r.action === 'deleted'
          ? `Removed ${entry.path} (it did not exist at that checkpoint).`
          : `Restored ${entry.path} from checkpoint ${n}.`);
        return;
      }
      appErr('Usage: /checkpoints [list | restore <n> | diff <n>]');
      return;
    }
    case 'statusline':
      openPicker({
        title: 'Status line items',
        title: 'Status line items',
        items: (() => {
          // `sub` must be set here, not only in onPick: the picker renders
          // `sub` must be set here, not only in onPick: the picker renders
          // item.sub, so without an initial value every toggle showed a blank
          // state until the user toggled it once.
          const toggles = [
            ['permission mode', 'slMode'],
            ['model name', 'slModel'],
            ['thinking effort', 'slEffort'],
            ['current directory', 'slCwd'],
            ['git branch & diff', 'slGit'],
            ['background tasks', 'slTasks'],
            ['rotating tips', 'slTips'],
          ];
          return toggles.map(([label, key]) => {
            const isOn = state[key] !== false;
            return { label, key, kind: 'toggle', isOn, sub: isOn ? 'on' : 'off' };
          });
        })(),
        hint: '↑↓ navigate · Enter toggle · Esc close',
        onPick: (it) => {
          it.isOn = !it.isOn;
          it.sub = it.isOn ? 'on' : 'off';
          state[it.key] = it.isOn;
          if (it.key === 'slGit') refreshGitInfo(state, { force: true });
          app(`Status line: ${it.label} → ${it.isOn ? 'shown' : 'hidden'}`);
          return false;
        },
      });
      return;
    case 'export-md': {
      const msgs = session.messages || [];
      if (!msgs.length) { appErr('Nothing to export (empty session).'); return; }
      const out = raw || path.join(state.cwd, `hncode-export-${session.id}.md`);
      try {
        fs.mkdirSync(path.dirname(out), { recursive: true });
        fs.writeFileSync(out, buildMarkdown(session), 'utf8');
        say(`Exported ${msgs.length} messages → ${out}`);
      } catch (e) { appErr(`Export failed: ${e.message}`); }
      return;
    }
    case 'import-session': {
      // Force a Markdown file: the content is injected into the prompt, so a
      // binary/arbitrary file would waste tokens or corrupt the request.
      const pickMd = (list) => list.filter((f) => /\.(md|markdown)$/i.test(f));
      const doImport = (target) => {
        if (!target) return;
        let abs;
        try { abs = path.resolve(state.cwd, target); } catch { abs = target; }
        if (!/\.(md|markdown)$/i.test(abs)) { appErr('Only Markdown files are supported (.md / .markdown).'); return; }
        let text;
        try {
          const st = fs.statSync(abs);
          if (!st.isFile()) { appErr('Not a file: ' + target); return; }
          text = fs.readFileSync(abs, 'utf8');
        } catch (e) { appErr('Could not read ' + target + ': ' + e.message); return; }
        if (!text.trim()) { appErr('That Markdown file is empty: ' + target); return; }
        const rel = path.relative(state.cwd, abs).replace(/\\/g, '/') || target;
        say(`/import-session — attaching ${rel} (${text.length} chars) to the prompt…`);
        // The file content travels WITH the message, so the model does not need
        // a Read call to see it.
        sendPrompt(
          'The following is the contents of ' + rel + ', provided inline so you do not need to read it with a tool.\n\n'
          + '<file path="' + rel + '">\n' + text + '\n</file>\n\n'
          + 'Use it as context for whatever I ask next.',
        );
      };
      if (raw) { doImport(raw); return; }
      // No argument: offer the Markdown files in the workspace.
      let entries = [];
      try {
        entries = pickMd(fs.readdirSync(state.cwd)).sort();
      } catch { entries = []; }
      // Also look one level down — exports often land in a subdirectory.
      const found = [];
      for (const name of entries) found.push(name);
      try {
        for (const d of fs.readdirSync(state.cwd, { withFileTypes: true })) {
          if (!d.isDirectory() || d.name.startsWith('.') || d.name === 'node_modules') continue;
          let inner = [];
          try { inner = pickMd(fs.readdirSync(path.join(state.cwd, d.name))); } catch { continue; }
          for (const name of inner.slice(0, 20)) found.push(d.name + '/' + name);
        }
      } catch { /* ignore */ }
      if (!found.length) {
        appErr('No Markdown files found in ' + state.cwd + '. Pass a path: /import-session <file.md>');
        return;
      }
      openPicker({
        title: 'Import a Markdown file into the prompt',
        items: found.slice(0, 60).map((p) => ({
          label: p,
          sub: (() => { try { return Math.max(1, Math.round(fs.statSync(path.join(state.cwd, p)).size / 1024)) + ' KB'; } catch { return ''; } })(),
          id: p,
        })),
        searchable: true,
        hint: '↑↓ choose · Enter attach · Esc cancel — or /import-session <path>',
        onPick: (it) => { doImport(it.id); return true; },
      });
      return;
    }
    case 'copy': {
      const last = [...state.chat].reverse().find((m) => m.role === 'assistant' && (m.text || '').trim());
      if (!last) { appErr('No assistant message to copy.'); return; }
      try {
        if (process.platform === 'win32') cp.execSync('clip', { input: last.text });
        else cp.execSync('pbcopy', { input: last.text });
        app(`Copied to clipboard (${last.text.length} characters).`);
      } catch { appErr('Clipboard unavailable.'); }
      return;
    }
    case 'add-dir': {
      state.addDirs = state.addDirs || [];
      if (!raw || raw === 'list') {
        sayPanel(state.addDirs.length ? 'Additional directories:\n' + state.addDirs.map((d) => `  ${d}`).join('\n') : 'No additional directories.');
        return;
      }
      const dir = path.resolve(state.cwd, raw.replace(/^~/, os.homedir()));
      if (!fs.existsSync(dir)) { appErr(`Directory does not exist: ${dir}`); return; }
      openPicker({
        title: `Add directory to workspace: ${dir}`,
        items: [
          { label: 'Yes, for this session', value: 'session' },
          { label: 'Yes, and remember this directory', value: 'persist' },
          { label: 'No', value: 'no' },
        ],
        searchable: false,
        onPick: (it) => {
          if (it.value === 'no') { app(`Did not add ${dir} as a working directory.`); return true; }
          if (!state.addDirs.includes(dir)) state.addDirs.push(dir);
          if (it.value === 'persist') {
            const f = hncodeConfigFile();
            try { fs.appendFileSync(f, `\n[workspace]\nadditional_dirs = ["${dir.replace(/"/g, '\\"')}"]\n`, 'utf8'); } catch {}
            app(`Added workspace directory:\n  ${dir}\n  Saved to:\n  ${f}`);
          } else app(`Added workspace directory:\n  ${dir}\n  For this session only`);
          return true;
        },
      });
      return;
    }

    case 'move': {
      if (!raw) { appErr('Usage: /move <target-directory>'); return; }
      const target = path.resolve(state.cwd, raw.replace(/^~/, os.homedir()));
      if (!fs.existsSync(target)) { appErr(`Directory does not exist: ${target}`); return; }
      // Create a new session in the target directory with the same messages.
      const newSession = {
        id: sess.newId(),
        title: session.title || '(moved)',
        workspace: target,
        model: session.model,
        createdAt: Date.now(),
        updatedAt: Date.now(),
        messages: (session.messages || []).slice(),
        rounds: session.rounds,
        steps: session.steps,
        mode: session.mode,
        plan: session.plan,
        planPath: session.planPath,
        focus: session.focus,
        swarm: session.swarm,
        effort: session.effort,
        theme: session.theme,
        todos: (session.todos || []).slice(),
        lastTurnMs: session.lastTurnMs,
      };
      sess.saveSession(newSession);
      // Hand the new session BACK to the caller. Assigning the local parameter used to be
      // the whole of this step, and it changed nothing outside `dispatch`: the caller keeps
      // its own `session` binding, so every later save wrote the OLD object — still stamped
      // with the directory being left behind. `h.replaceSession` is what rebinds it.
      if (h.replaceSession) h.replaceSession(newSession);
      session = newSession;
      // The directory changed, so the status line (path + git badge) must follow.
      // It previously kept showing the OLD path because state.cwd was never
      // updated here.
      // `cfg` follows too, for the same reason as /sessions: the tools resolve their
      // paths against `ctx.cwd || ctx.workspace`, which the agent copies from `cfg`
      // each turn. Moving only the status line left Edit/Read/Bash pointed at the
      // directory being left behind.
      state.cwd = target;
      state.workspace = target;
      cfg.workspace = target;
      cfg.cwd = target;
      if (state.agent && state.agent.ctx) {
        state.agent.ctx.cwd = target;
        state.agent.ctx.workspace = target;
      }
      refreshGitInfo(state, { force: true });
      state.chat = reconstructChat(session);
      state.scroll = 0;
      dropScrollPin(state);   // fresh transcript: re-seed the anchor on paint
      state.rounds = session.rounds || 0;
      state.steps = session.steps || 0;
      saveSession(session);
      app(`Session moved to: ${target} (${newSession.id})`);
      return;
    }

    case 'reload': {
      try {
        // Full reload: re-read config AND re-load plugins, without restarting the process.
        const fresh = h.reloadConfig ? h.reloadConfig() : null;
        if (fresh) {
          Object.assign(cfg, fresh);
          state.model = cfg.model;
          state.provider = cfg.provider;
          state.modelLabel = modelLabel(cfg) || cfg.model || '';
          state.reasoning = !!cfg.reasoning;
          cfg.effort = state.reasoning ? state.effort : '';
          if (cfg.raw && cfg.raw.theme) { state.theme = cfg.raw.theme; setTheme(state.theme); }
          const beforeMax = state.ctxMax;
          state.ctxMax = cfg.maxContextTokens || state.ctxMax;
          state.ctxPercent = usagePercent(state.ctxTokens || 0, state.ctxMax);
          const changed = beforeMax !== state.ctxMax;
          app(changed
            ? `Config reloaded. Context window: ${fmtTokens(beforeMax)} -> ${fmtTokens(state.ctxMax)} (now ${state.ctxPercent}% used)`
            : 'Config reloaded.');
          app('Config and plugins reloaded.');
        }
        // Re-load plugins so an added/edited plugin takes effect without a restart.
        if (h.reloadPlugins) {
          const notes = await h.reloadPlugins();
          for (const n of (notes || [])) app(`${n.level === 'error' ? '!' : '?'}[plugin] ${n.text}`);
        }
      } catch (e) { appErr(`Reload failed: ${e.message}`); }
      return;
    }
    case 'reload-config': {
      try {
        const fresh = h.reloadConfig ? h.reloadConfig() : null;
        if (fresh) {
          Object.assign(cfg, fresh);
          state.model = cfg.model;
          state.provider = cfg.provider;
          state.modelLabel = modelLabel(cfg) || cfg.model || '';
          state.reasoning = !!cfg.reasoning;
          cfg.effort = state.reasoning ? state.effort : '';
          if (cfg.raw && cfg.raw.theme) { state.theme = cfg.raw.theme; setTheme(state.theme); }
          const beforeMax = state.ctxMax;
          state.ctxMax = cfg.maxContextTokens || state.ctxMax;
          state.ctxPercent = usagePercent(state.ctxTokens || 0, state.ctxMax);
          const changed = beforeMax !== state.ctxMax;
          app(changed
            ? `Config reloaded. Context window: ${fmtTokens(beforeMax)} -> ${fmtTokens(state.ctxMax)} (now ${state.ctxPercent}% used)`
            : 'Config reloaded.');
        }
      } catch (e) { appErr(`Reload failed: ${e.message}`); }
      return;
    }    case 'plugins': {
      // Only the remove/install fast paths need these; `list` goes through the
      // browser, which loads what it needs itself.
      const remote = await import('./remote.js');
      const parts = raw.split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();

      if (sub === 'remove' || sub === 'rm' || sub === 'delete') {
        const name = parts[1];
        if (!name) { appErr('Usage: /plugins remove <name>'); return; }
        const ok = remote.removeLocalPlugin(name);
        if (!ok) { appErr(`No such plugin: ${name}`); return; }
        // Removing the files does not unload the code already registered in this
        // process, so point at the command that does. Saying so avoids the impression
        // that the removal failed.
        app(`Plugin removed: ${name} (run /plugins reload, or restart hncode)`);
        return;
      }
      if (sub === 'install' || sub === 'add' || sub === 'i') {
        const name = parts[1];
        if (!name) { appErr(`Usage: /plugins install <name>  (see /plugins list)\nRepo: https://github.com/${remote.DEFAULT_REPO}/tree/${remote.DEFAULT_REF}/plugins`); return; }
        notice(`Downloading plugin ${name}…`, 'info');
        const res = await remote.installRemotePlugin(name);
        if (!res.ok) { appErr(`Install failed: ${res.error}`); return; }
        app(`Plugin ${res.replaced ? 'updated' : 'installed'}: ${res.name} (${res.files.join(', ')})`);
        app('Reload them with /plugins reload, or restart hncode.');
        return;
      }
      if (sub === 'reload') {
        // Hot reload: unload every plugin (running its dispose + collected teardown),
        // then re-import the files with cache busting. The alternative was a restart,
        // which is what made plugin development painful.
        if (!h.reloadPlugins) { appErr('Reload is unavailable in this host.'); return; }
        const notes = await h.reloadPlugins();
        const errs = (notes || []).filter((n) => n.level === 'error').length;
        if (errs) {
          for (const n of notes) if (n.level === 'error') appErr(`[plugin] ${n.text}`);
        }
        app(`Plugins reloaded${errs ? ` with ${errs} error${errs === 1 ? '' : 's'}` : ''} — /plugins list to inspect.`);
        return;
      }

      // `list` (or bare) opens the interactive manager (tabs + descriptions, like
      // kimi's panel). An unknown subcommand still errors rather than silently opening
      // it as if the word had been understood.
      if (sub !== 'list' && sub !== '') {
        appErr('Usage: /plugins [list] | install <name> | remove <name> | reload');
        return;
      }
      await h.openRegistryBrowser('plugins');
      return;
    }
    case 'skills': {
      const parts = raw.split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      const remote = await import('./remote.js');
      if (sub === 'remove' || sub === 'rm' || sub === 'delete') {
        const name = parts[1];
        if (!name) { appErr('Usage: /skills remove <name>'); return; }
        const ok = deleteSkill(name);
        app(ok ? `Skill removed: ${normalizeSkillName(name)}` : `No such skill: ${name}`);
        return;
      }
      if (sub === 'install' || sub === 'add' || sub === 'i') {
        const name = parts[1];
        if (!name) { appErr(`Usage: /skills install <name>  (see /skills list)\nRepo: https://github.com/${remote.DEFAULT_REPO}/tree/${remote.DEFAULT_REF}/skills`); return; }
        notice(`Downloading skill ${name}…`, 'info');
        const res = await remote.installRemoteSkill(name);
        if (!res.ok) { appErr(`Install failed: ${res.error}`); return; }
        app(`Skill ${res.replaced ? 'updated' : 'installed'}: ${res.name}${res.description ? ' — ' + res.description : ''}`);
        app(`Activate it with /${SKILL_PREFIX}${res.name}`);
        return;
      }
      if (sub === 'list' || sub === '') {
        // The interactive manager (tabs + descriptions). It fetches the remote list for
        // its Available tab itself, so nothing is fetched here.
        await h.openRegistryBrowser('skills');
        return;
      }
      appErr('Usage: /skills [list] | install <name> | remove <name>');
      return;
    }
    case 'import-skill': {
      // Usage: /import-skill <file.md> [name]
      const parts = raw.split(/\s+/).filter(Boolean);
      const file = parts[0];
      const nameArg = parts[1];
      if (!file) { appErr('Usage: /import-skill <file.md> [name]'); return; }
      const res = importSkill(file, nameArg);
      if (!res.ok) { appErr(res.error); return; }
      app(`${res.replaced ? 'Skill overwritten' : 'Skill imported'}: ${res.name} → ${res.path}`);
      say(`Activate it with /${SKILL_PREFIX}${res.name}`);
      return;
    }
    case 'hooks': {
      const workspace = state.workspace || cfg.workspace || process.cwd();
      const parts = raw.split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      if (sub === 'test') {
        const event = parts[1];
        if (!event || !HOOK_EVENTS.includes(event)) {
          appErr(`Usage: /hooks test <event>  (events: ${HOOK_EVENTS.join(', ')})`);
          return;
        }
        const { hooks } = loadHooks(workspace);
        const res = await runShellHooks({ hooks }, event, { toolName: 'Bash', toolArgs: { command: 'echo hi' }, prompt: 'test' }, workspace);
        if (!(hooks[event] || []).length) { app(`No ${event} hooks configured.`); return; }
        const lines = res.results.map((r) => {
          const head = r.ok ? `✔ ${r.entry.command}` : `✖ ${r.entry.command} (${r.message})`;
          const body = (r.stderr || r.stdout || '').trim();
          return body ? `${head}\n${body}` : head;
        });
        h.openPanel(`hncode — hooks: ${event} (test)`, [
          `Ran ${res.results.length} hook(s)${res.blocked ? ' — the tool WOULD be blocked' : ''}.`,
          '',
          ...lines,
        ]);
        return;
      }
      const { hooks, errors } = loadHooks(workspace);
      const lines = describeHooks({ hooks });
      if (errors.length) lines.push('', 'Config problems:', ...errors.map((e) => `  ! ${e}`));
      h.openPanel('hncode — hooks', lines);
      return;
    }
    case 'git': {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      if (!gitmod.isRepo(cwd)) { appErr(`Not a git repository: ${cwd}`); return; }
      refreshGitInfo(state, { force: true });   // keep the badge in sync with this view
      const branch = gitmod.currentBranch(cwd);
      const s = gitmod.status(cwd);
      const info = gitmod.parseRemote(gitmod.remoteUrl(cwd));
      const lines = [
        `branch:  ${branch || '(unknown)'}`,
        `head:    ${gitmod.headSha(cwd)}`,
        info ? `remote:  ${info.owner}/${info.repo}  (${info.host})` : 'remote:  (none)',
        '',
        `changes (${s.ok ? s.entries.length : '?'}):`,
        ...gitmod.statusLines(cwd).map((l) => '  ' + l),
      ];
      h.openPanel('hncode — git', lines);
      return;
    }
    case 'add': {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      if (!gitmod.isRepo(cwd)) { appErr(`Not a git repository: ${cwd}`); return; }
      // `/add` stages everything (`git add -A`); `/add <path> ...` stages just
      // those paths. This is the explicit staging step /commit does implicitly.
      const paths = raw.split(/\s+/).filter(Boolean);
      const r = gitmod.stage(paths, cwd);
      if (!r.ok) { appErr(`git add failed: ${r.error}`); return; }
      const staged = gitmod.stagedFiles(cwd);
      app(paths.length ? `Staged ${paths.length} path(s).` : 'Staged all changes.');
      sayPanel(`Index now holds ${staged.length} file(s):\n` + staged.map((f) => '  ' + f).join('\n'));
      return;
    }
    case 'diff': {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      if (!gitmod.isRepo(cwd)) { appErr(`Not a git repository: ${cwd}`); return; }
      const staged = /--staged|--cached/.test(raw);
      const path = raw.replace(/--staged|--cached/g, '').trim();
      const r = gitmod.diffText(cwd, { staged, path: path || undefined });
      if (!r.ok) { appErr(`git diff failed: ${r.error}`); return; }
      if (r.empty) { say(staged ? 'No staged changes.' : 'No uncommitted changes.'); return; }
      sayPanel((staged ? 'Staged changes' : 'Uncommitted changes') + (path ? ` in ${path}` : '') + ':\n' + r.text);
      return;
    }
    case 'log': {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      if (!gitmod.isRepo(cwd)) { appErr(`Not a git repository: ${cwd}`); return; }
      const parts = raw.split(/\s+/).filter(Boolean);
      const count = parts[0] && /^\d+$/.test(parts[0]) ? parts.shift() : undefined;
      const path = parts.join(' ') || undefined;
      const r = gitmod.logText(cwd, { count, path });
      if (!r.ok) { appErr(`git log failed: ${r.error}`); return; }
      if (r.empty) { say('No commits yet.'); return; }
      sayPanel(`Recent commits${path ? ` for ${path}` : ''}:\n` + r.text);
      return;
    }
    case 'push': {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      if (!gitmod.isRepo(cwd)) { appErr(`Not a git repository: ${cwd}`); return; }
      const parts = raw.split(/\s+/).filter(Boolean);
      const force = parts.includes('-f') || parts.includes('--force');
      const branchArg = parts.find((x) => !x.startsWith('-')) || '';
      const branch = branchArg || gitmod.currentBranch(cwd);
      const upstream = gitmod.hasUpstream(cwd, branch);
      const state2 = gitmod.aheadBehind(cwd, branch);
      const detail = `${branch}${upstream ? '' : ' (no upstream — will set one)'}${state2 ? ` — ${state2}` : ''}`;
      // Push is OUTBOUND: always confirm first, and say exactly what will happen.
      h.openPicker({
        title: `Push ${branch}?`,
        items: [
          { label: 'Push', sub: `git push ${force ? '--force-with-lease ' : ''}origin ${detail}` },
          { label: 'Cancel', sub: 'do not push' },
        ],
        searchable: false,
        hint: '↑↓ navigate · Enter select · Esc cancel',
        onPick: (it) => {
          if (it.label !== 'Push') { app('Push cancelled.'); return true; }
          const r = gitmod.push(cwd, { branch: branchArg || undefined, force, setUpstream: !upstream });
          if (!r.ok) appErr(`Push failed: ${r.error}`);
          else { app(`Pushed ${branch}.`); sayPanel(`git push output:\n${r.output}`); }
          return true;
        },
      });
      return;
    }
    case 'stash': {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      if (!gitmod.isRepo(cwd)) { appErr(`Not a git repository: ${cwd}`); return; }
      const parts = raw.split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      if (!sub || sub === 'list') {
        const list = gitmod.stashList(cwd);
        sayPanel(list.length ? `Stashes (${list.length}):\n` + list.map((s) => '  ' + s).join('\n') : 'No stashes.');
        return;
      }
      if (sub === 'push' || sub === 'save') {
        const msg = parts.slice(1).join(' ') || undefined;
        const r = gitmod.stashPush(cwd, msg);
        if (!r.ok) { appErr(`git stash failed: ${r.error}`); return; }
        app('Stashed changes.'); sayPanel(r.output || 'Changes stashed.');
        return;
      }
      if (sub === 'pop') {
        const r = gitmod.stashPop(cwd);
        if (!r.ok) { appErr(`git stash pop failed: ${r.error}`); return; }
        app('Restored from stash.'); sayPanel(r.output || 'Stash popped.');
        return;
      }
      appErr('Usage: /stash [list] | push [message] | pop');
      return;
    }
    case 'rebase': {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      if (!gitmod.isRepo(cwd)) { appErr(`Not a git repository: ${cwd}`); return; }
      const onto = String(raw || '').trim();
      if (!onto) { appErr('Usage: /rebase <branch>'); return; }
      const cur = gitmod.currentBranch(cwd);
      // Rewrites history on the current branch: confirm before running.
      h.openPicker({
        title: `Rebase ${cur} onto ${onto}?`,
        items: [
          { label: 'Rebase', sub: `git rebase ${onto}` },
          { label: 'Cancel', sub: 'leave the branch as is' },
        ],
        searchable: false,
        hint: '↑↓ navigate · Enter select · Esc cancel',
        onPick: (it) => {
          if (it.label !== 'Rebase') { app('Rebase cancelled.'); return true; }
          const r = gitmod.rebase(cwd, onto);
          if (!r.ok) appErr(`Rebase failed (resolve conflicts, then /rebase --continue or git rebase --abort): ${r.error}`);
          else { app(`Rebased ${cur} onto ${onto}.`); sayPanel(r.output || 'Rebase complete.'); }
          return true;
        },
      });
      return;
    }
    case 'commit': {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      if (!gitmod.isRepo(cwd)) { appErr(`Not a git repository: ${cwd}`); return; }
      // `/commit <message>` commits what is already staged, staging everything
      // when the index is empty (the common "commit my changes" case).
      // `/commit` with NO message hands the job to the model, which can read the
      // diff and draft a message — that is the point of having an agent.
      const message = String(raw || '').trim();
      if (!message) {
        const s = gitmod.status(cwd);
        if (s.ok && !s.entries.length) { app('Nothing to commit — working tree is clean.'); return; }
        const branch = gitmod.currentBranch(cwd);
        const pending = gitmod.statusLines(cwd).slice(0, 40).join('\n');
        await submit(
          `Create a git commit for the current changes.\n\n`
          + `Repository state (branch: ${branch}):\n${pending}\n\n`
          + `Steps: run \`git diff\` (and \`git status\`) to review the changes, stage the relevant files, then commit with a concise message `
          + `that explains the intent. Match the repository's existing commit-message style. Do not push. `
          + `Finally, report the commit hash and a one-line summary of what was committed.`,
        );
        return;
      }
      if (!gitmod.hasStagedChanges(cwd)) {
        const st = gitmod.stage([], cwd);
        if (!st.ok) { appErr(`git add failed: ${st.error}`); return; }
      }
      const res = gitmod.commit(message, cwd);
      if (!res.ok) { appErr(`Commit failed: ${res.error}`); return; }
      app(`Committed ${res.sha}: ${message.split('\n')[0]}`);
      const files = res.stdout.split('\n').slice(0, 8).join('\n');
      sayPanel(`Committed ${res.sha}\n${files}`);
      return;
    }
    case 'branch': {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      if (!gitmod.isRepo(cwd)) { appErr(`Not a git repository: ${cwd}`); return; }
      const parts = raw.split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      if (!sub || sub === 'list') {
        const cur = gitmod.currentBranch(cwd);
        const branches = gitmod.listBranches(cwd);
        if (!branches.length) { app(`No branches yet (current: ${cur}).`); return; }
        sayPanel(`Branches (current: ${cur}):\n` + branches.map((b) => `  ${b === cur ? '* ' : '  '}${b}`).join('\n'));
        return;
      }
      if (sub === '-c' || sub === 'create' || sub === 'new') {
        const name = parts[1];
        if (!name) { appErr('Usage: /branch -c <name> [from]'); return; }
        const r = gitmod.createBranch(name, cwd, parts[2]);
        if (!r.ok) { appErr(`Could not create branch: ${r.error}`); return; }
        app(`Switched to new branch: ${name}`);
        return;
      }
      const r = gitmod.switchBranch(parts[0], cwd);
      if (!r.ok) { appErr(`Could not switch branch: ${r.error}`); return; }
      app(`Switched to branch: ${parts[0]}`);
      return;
    }
    case 'pr': {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      if (!gitmod.isRepo(cwd)) { appErr(`Not a git repository: ${cwd}`); return; }
      const base = String(raw || '').trim() || 'main';
      const url = gitmod.prUrl(cwd, base);
      if (!url) { appErr('No git remote named "origin" — cannot build a PR URL.'); return; }
      const branch = gitmod.currentBranch(cwd);
      sayPanel(`Open a pull request for ${branch} → ${base}:\n  ${url}`);
      app('PR link copied to the transcript (Ctrl+Shift+C to copy).');
      return;
    }
    case 'cache': {
      // Prompt caching: explicit cache breakpoints for the stable prefix (tools +
      // system + conversation head). Saves input tokens on every turn after the
      // first. Anthropic gets cache_control markers; OpenAI-compatible providers
      // get a stable prompt_cache_key.
      const a = String(raw || '').toLowerCase();
      const want = a === 'on' ? true : a === 'off' ? false : !(cfg.promptCache !== false);
      cfg.promptCache = want;
      try { setConfigString('prompt_cache', want ? 'true' : 'false'); } catch { /* best-effort persist */ }
      app(`Prompt caching: ${want ? 'ON' : 'OFF'}`);
      sayPanel(want
        ? 'The stable prefix (tools + system + conversation head) is marked cacheable.\n'
          + 'Providers bill cached input at a fraction of the normal rate. Effective\n'
          + 'for: anthropic (cache_control), openai-compatible (prompt_cache_key).'
        : 'Prompt caching disabled — every request sends the full prompt as fresh input.');
      return;
    }
    case 'worktree': {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      if (!gitmod.isRepo(cwd)) { appErr(`Not a git repository: ${cwd}`); return; }
      const parts = raw.split(/\s+/).filter(Boolean);
      const sub = (parts[0] || '').toLowerCase();
      if (!sub || sub === 'list') {
        const list = gitmod.listWorktrees(cwd);
        sayPanel(`Worktrees (${list.length}):\n` + list.map((w) => `  ${w.path}  ${w.branch ? '[' + w.branch + ']' : w.detached ? '(detached)' : ''}`).join('\n'));
        return;
      }
      if (sub === 'add') {
        const dir = parts[1];
        if (!dir) { appErr('Usage: /worktree add <dir> [branch]'); return; }
        const r = gitmod.addWorktree(dir, parts[2], cwd);
        if (!r.ok) { appErr(`Could not add worktree: ${r.error}`); return; }
        app(r.reused ? `Worktree already exists: ${r.path}` : `Worktree created: ${r.path}${r.branch ? ` [${r.branch}]` : ''}`);
        return;
      }
      // cline's `--worktree`: spin up an ISOLATED worktree and move the session into
      // it, so an experiment cannot touch the working tree you were just in. Unlike
      // `add`, there is nothing to type: the path and branch are derived. A DETACHED
      // worktree is the default — it is disposable, needs no branch name, and cannot
      // collide with an existing branch.
      if (sub === 'new' || sub === 'create') {
        const slug = (parts.slice(1).join('-') || `${session.id || 'session'}`)
          .replace(/[^A-Za-z0-9._-]+/g, '-').replace(/^-+|-+$/g, '').slice(0, 48) || 'wt';
        const stamp = new Date().toISOString().replace(/[:.]/g, '-').slice(0, 19);
        const root = path.join(os.homedir(), '.hncode', 'worktrees', `${slug}-${stamp}`);
        const wantBranch = /--branch/.test(raw);   // opt in to a real branch
        const r = gitmod.addWorktree(root, wantBranch ? slug : null, cwd, { detach: !wantBranch });
        if (!r.ok) { appErr(`Could not create worktree: ${r.error}`); return; }
        // Move the session into it, the same way /sessions switches a workspace:
        // status line, cfg, and the live agent ctx all have to follow or the tools
        // keep writing to the directory we just left.
        const target = r.path;
        state.cwd = target;
        state.workspace = target;
        cfg.workspace = target;
        cfg.cwd = target;
        if (state.agent && state.agent.ctx) {
          state.agent.ctx.cwd = target;
          state.agent.ctx.workspace = target;
        }
        refreshGitInfo(state, { force: true });
        app(`Worktree ready: ${target}${r.branch ? ` [${r.branch}]` : ' (detached)'} — this session now works there.`);
        return;
      }
      if (sub === 'remove' || sub === 'rm') {
        const dir = parts[1];
        if (!dir) { appErr('Usage: /worktree remove <dir>'); return; }
        const force = parts.includes('--force');
        const doRemove = () => {
          const r = gitmod.removeWorktree(dir, cwd, { force });
          app(r.ok ? `Worktree removed: ${dir}` : `Could not remove worktree: ${r.error}`);
          renderFrame();
        };
        // `--force` discards uncommitted work in that worktree, and git will NOT
        // refuse — so this is the one path where a mistyped dir really loses data.
        // Confirm it; the non-forced form is already safe (git rejects a dirty tree).
        if (force) {
          openPicker({
            title: `Force-remove worktree "${dir}"?`,
            searchable: false,
            hint: '↑↓ choose · Enter confirm · Esc cancel',
            items: [
              { label: 'Cancel', sub: 'keep the worktree' },
              { label: 'Force remove', sub: 'discards uncommitted changes in that worktree — cannot be undone' },
            ],
            onPick: (it) => {
              if (it && it.label === 'Force remove') doRemove();
              else app('Worktree removal cancelled.');
              return true;
            },
          });
          renderFrame();
          return;
        }
        doRemove();
        return;
      }
      appErr('Usage: /worktree [list] | new [name] [--branch] | add <dir> [branch] | remove <dir>');
      return;
    }
    case 'logout': {
      const pr = (cfg.raw && cfg.raw.providers) || {};
      const names = Object.keys(pr);
      if (!names.length) { app('Nothing to logout.'); return; }
      const doLogout = (name) => {
        const p = pr[name] || {};
        delete p.api_key;
        delete p.apiKey;
        addProvider(name, { base_url: p.base_url, api_key: '', protocol: p.protocol });
        if (cfg.provider === name) cfg.apiKey = '';
        app(`Logged out from ${name}.`);
      };
      if (raw && pr[raw]) { doLogout(raw); return; }
      openPicker({
        title: 'Select a provider to log out',
        items: names.map((n) => ({ label: n, sub: (pr[n].base_url || '').replace(/^https?:\/\//, '') })),
        searchable: false,
        onPick: (it) => { doLogout(it.label); return true; },
      });
      return;
    }
    case 'feedback': {
      // Build a prefilled GitHub issue URL and show it in the transcript, the way
      // /pr shows a PR link — the user opens it and the issue form is already
      // filled in. Nothing is written to disk or posted from here.
      //
      // `/feedback <title> | <body>`, with the split on a `|` when one is present so a
// multi-word title is possible ("Crash on startup | it exits immediately").
      // Without a `|` the FIRST word is the title and the rest is the body, which
      // keeps the common one-liner short to type.
      const parts = String(raw || '').trim();
      if (!parts) { appErr('Usage: /feedback <title> | <body>'); return; }
      const bar = parts.indexOf('|');
      let title, body;
      if (bar !== -1) {
        title = parts.slice(0, bar).trim();
        body = parts.slice(bar + 1).trim();
      } else {
        const sp = parts.indexOf(' ');
        title = sp === -1 ? parts : parts.slice(0, sp);
        body = sp === -1 ? '' : parts.slice(sp + 1).trim();
      }
      if (!title) { appErr('Usage: /feedback <title> | <body>'); return; }
      // The body is EXACTLY what the user typed. Nothing is appended — a report
      // the user did not write (an environment footer, a template) reads as noise
      // in the issue form and has to be deleted before submitting.
      const url = 'https://github.com/NiceHello666/hncode/issues/new'
        + `?title=${encodeURIComponent(title)}`
        + (body ? `&body=${encodeURIComponent(body)}` : '');
      sayPanel(`Open a GitHub issue:\n  ${url}`);
      app('Issue link copied to the transcript (Ctrl+Shift+C to copy).');
      return;
    }
    case 'exit': quit(); return;

    default: {
      // A skill activation: /skill:<name> [extra args]. The skill's body is sent
      // as the turn's prompt, so it behaves like a saved prompt fragment the user
      // can recall by name (tab-completed in the composer).
      const rawName = String(cmdRaw || '').replace(/^\/+/, '');
      if (rawName.toLowerCase().startsWith(SKILL_PREFIX)) {
        const name = normalizeSkillName(rawName);
        const sk = readSkill(name);
        if (!sk || !sk.body) {
          appErr(`No such skill: ${name}. Use /skills to list them, or /import-skill to add one.`);
          return;
        }
        // `raw` is whatever was typed AFTER the skill name, and it is the user's own
        // instruction: it has to reach the model AND appear in the transcript. It was
        // appended only to the hidden `skillBody` system message while the row showed
        // the bare `/skill:name`, so the user's text disappeared from the conversation
        // and the model saw it as a detached system note rather than as their words.
        const extra = String(raw || '').trim();
        const prompt = skillPrompt(sk) + (extra ? `\n\n${extra}` : '');
        // The row is a SKILL ACTIVATION card, not a user bubble and not the literal
        // `/skill:foo` text (which read as the user having typed a command). The body
        // rides a system message so it never renders as the user's own speech — the
        // distinction kimi draws, and the reason this row exists at all.
        addChat({ role: 'skill', text: name, args: extra, _conv: true });
        await sendPrompt('/' + SKILL_PREFIX + name, { skillBody: prompt, bubbleText: extra });
        return;
      }
      // Check if this is a plugin-registered command.
      if (isPluginCommand(cmd)) {
        const pc = findCommand(cmd);
        // NOTE: `pc` comes from the plugin registry, which does NOT carry the
        // `_plugin` marker — that is only added by allCommands() for display. The
        // old guard `pc._plugin` was therefore always falsy, so plugin commands
        // fell through to "Unknown command" and never ran at all. isPluginCommand
        // above already established that this name resolves to a plugin.
        if (pc && typeof pc.run === 'function') {
          // AWAIT the handler: plugins may register an async `run`, and without
          // awaiting, a rejection escaped as an unhandled promise rejection and
          // the catch below never saw it (the command appeared to fail silently).
          try { await pc.run(raw, { state, cfg, session, h, app, appErr }); }
          catch (e) { appErr(`Plugin command "/${cmd}" failed: ${e.message}`); }
          return;
        }
      }
      // Unknown command: show error message
      appErr(`Unknown command: /${cmdRaw.replace(/^\//, '')}`);
      return;
    }
  }
}

// Display names for the permission modes. One word each, matching the command
// names, so /permission's picker, /status and the status line all read the same.
// The old long forms ("Always Ask" / "Ask When Needed" / "Never Ask") also
// mis-described the two auto modes once neither one asks any more.
const PERMISSION_LABEL = { ask: 'Ask', yolo: 'Yolo', auto: 'Auto' };
function setPermission(state, mode) { state.mode = mode; }

// The shortcuts hncode dispatches itself, as tokens in the same vocabulary the keybindings
// file and `registerKeybind` use. A plugin asking `api.isKeyBound('ctrl+t')` needs to know
// these are taken, and they cannot be discovered by reading a data structure — the handlers
// are a long switch. The list is the REACHABLE set, so a plugin is warned about the ones a
// user would notice losing; the switch's internal cursor keys are deliberately absent,
// because a plugin claiming those is not something to guard against.
const BUILTIN_KEYS = new Set([
  'c-c',   // interrupt / quit
  'c-b',   // background a running Bash command
  'c-d',   // exit on an empty composer
  'c-l',   // expand the plugin log block
  'c-o',   // expand tool output and diffs
  'c-p',   // command palette
  'c-r',   // reload the current session from disk
  'c-s',   // steer the running turn
  'c-t',   // expand/collapse the todo panel
  'c-v',   // paste
  'c-x',   // (reserved; Ctrl+Shift+X is paste-and-run)
  'c-s-c', // copy the selection or last answer
  'c-s-v', // paste as a bracketed paste
  'c-up', 'c-down',   // scroll the output area
  'escape',
  'tab', 's-tab',
  'enter', 'newline',
  'up', 'down', 'left', 'right',
  'home', 'end', 'pgup', 'pgdn',
]);


// Is `p` inside the workspace (or one of the extra directories added via
// /add-dir)? Used by YOLO mode: work inside the workspace is auto-approved, work
// outside it asks.
export function isInWorkspace(state, p) {
  if (!p) return false;
  let abs;
  try { abs = path.resolve(state.cwd || state.workspace || process.cwd(), p); } catch { return false; }
  try { abs = fs.realpathSync(abs); } catch { /* may not exist yet (a new file) */ }
  const roots = [state.cwd || state.workspace, ...(state.addDirs || [])].filter(Boolean);
  for (const root of roots) {
    let r;
    try { r = fs.realpathSync(root); } catch { r = path.resolve(root); }
    const rel = path.relative(r, abs);
    if (rel === '' || (!rel.startsWith('..') && !path.isAbsolute(rel))) return true;
  }
  return false;
}

/**
 * The config for SIDE work — /btw, /recap. Uses `secondaryModel` when it resolves,
 * else the session's own config unchanged.
 *
 * A model the user selected but that no longer resolves falls back SILENTLY to the
 * session model: the alternative is a side question failing because of a config
 * entry set weeks ago, which is worse than using a more expensive model. The panel
 * header shows which model answered, so the fallback is visible.
 */
function secondaryModelCfg(cfg) {
  const name = cfg && cfg.secondaryModel;
  if (!name) return cfg;
  if (!(cfg.raw && cfg.raw.models && cfg.raw.models[name])) return cfg;
  try { return resolveModelArg(cfg, name) || cfg; }
  catch { return cfg; }
}

/**
 * Ask one side question, streaming the reply into the docked box.
 *
 * The turn is pushed BEFORE the request so a running turn renders immediately
 * ("Waiting for answer…" plus a caret), and the answer accumulates IN PLACE — the
 * same live-update shape kimi's `appendAnswer` gives, so the reply is watched as it
 * arrives rather than appearing all at once at the end.
 *
 * Returns the turn after the request settles, so a caller can report a failure.
 */
export async function askSideQuestion(state, cfg, question, repaint) {
  // The repaint is INJECTED rather than imported: renderSoon lives inside startTUI
  // (it owns the frame timer), and this function is called from dispatch() too.
  const paint = typeof repaint === 'function' ? repaint : (() => {});
  const modelCfg = secondaryModelCfg(cfg);
  const panel = state.btwPanel || (state.btwPanel = { turns: [], model: '', reasoning: false });
  const turn = {
    prompt: String(question || '').trim(),
    answer: '',
    thinking: '',
    phase: 'running',
  };
  panel.turns.push(turn);
  panel.model = modelCfg.model || cfg.model;
  // A new question means the user wants to SEE it, so any scrollback is dropped.
  state.btwScroll = 0;
  paint();

  // Only the reading tools are exposed; a call to anything else is refused at the
  // runner (see sideToolAllowed). The model still sees every tool DEFINITION, which
  // is what keeps the prompt cache shared with the main thread.
  const sideCfg = {
    ...modelCfg,
    toolFilter: SIDE_RO_TOOLS,
    sideThreadTools: SIDE_RO_TOOLS,
    noDelegation: true,
    maxOutputTokens: cfg.maxOutputTokens,
  };
  try {
    if (!state.sideThread) {
      state.sideThread = new SideThread({
        basePrompt: (cfg.systemPrompt && String(cfg.systemPrompt).trim()) || SYSTEM_PROMPT,
        tools: SIDE_RO_TOOLS,
        model: modelCfg.model || cfg.model,
      });
    }
    const payload = state.sideThread.payload(turn.prompt);
    // The Agent loop, not a bare request: a side question may READ a file to answer,
    // and only the loop can run a tool.
    const sideAgent = new Agent({
      cfg: sideCfg,
      messages: payload,
      onApproval: async (toolName) => sideToolAllowed(toolName),
      onEvent: (e) => {
        if (e.type === 'data' && e.text) { turn.answer += e.text; paint(); }
        if (e.type === 'think' && e.text) { turn.thinking += e.text; paint(); }
      },
    });
    await sideAgent.run();
    turn.answer = String(turn.answer).trim();
    if (!turn.answer) {
      turn.error = 'The side question came back empty.';
      turn.phase = 'failed';
    } else {
      turn.phase = 'done';
      state.sideThread.record(turn.prompt, turn.answer);
    }
  } catch (e) {
    turn.error = `Side question failed: ${e.message}`;
    turn.phase = 'failed';
  }
  paint();
  return turn;
}

// Record a Ctrl+A approval on the SESSION (not on config). Kept as a thin wrapper
// so the storage location is stated once: a persisted grant would apply to next
// week's work, which is not what "approve for this session" means.
function approveForSession(state, toolName, args) {
  if (!state) return;
  state.sessionApprovals = rememberApproval(state.sessionApprovals, toolName, args);
}

// Decide whether a tool call stays inside the workspace. Anything we cannot PROVE
// is inside asks the user — that is the safe default for YOLO.
function isInsideWorkspace(state, toolName, args) {
  if (!args || typeof args !== 'object') return false;
  switch (toolName) {
    // Path-taking tools: check the path argument.
    case 'Read': case 'Write': case 'Edit': case 'FileLines': case 'Glob': case 'Grep':
      return isInWorkspace(state, args.path || args.file_path || args.dir || state.cwd);
    case 'Bash': {
      // A shell command can touch anything, so it is only auto-approved when every
      // path-like token it mentions resolves inside the workspace AND it contains
      // no blatantly destructive form. Anything ambiguous asks.
      const cmd = String(args.command || '');
      const cwd = args.cwd || state.cwd;
      if (args.cwd && !isInWorkspace(state, args.cwd)) return false;
      if (isDestructiveCommand(cmd)) return false;
      return commandPathsAreInside(state, cmd, cwd);
    }
    default:
      // Unknown tool: ask (never widen the auto-approve surface by accident).
      return false;
  }
}

// The destructive / read-only verdicts live in shell-safety.js: they need a real

// The destructive / read-only verdicts live in shell-safety.js: they need a real
// split of the command into segments and a peel of its wrappers, which a single
// regex over the whole line cannot do. These wrappers stay because they are the
// names the rest of the TUI (and any plugin patching tui.js#isReadOnlyCommand)
// already uses.
function isDestructiveCommand(cmd) {
  return shellIsDestructiveCommand(cmd);
}
export function isReadOnlyCommand(cmd) {
  return shellIsReadOnlyCommand(cmd);
}

/**
 * The rows a reasoning block draws. Exported for the test that an EMPTY block draws
 * none — the rule lives in `messageLines`, which is reached through a full frame, and
 * asserting it through the frame alone cannot tell "no rows" from "one blank row".
 */
export function makeThinkingLineForTest(state, msg) {
  return messageLines(msg, (state && state.termCols) || 80, (state && state.cwd) || process.cwd(), false, 0, 0, false,
    (state && state.shimmerEdge) || (state && state.cfg && state.cfg.shimmerEdge));
}

/**
 * Add one display-only row to `session.transcript`, or extend the open reasoning block.
 *
 * THE TEXT IS ASSIGNED, NOT APPENDED. `appendThinking` records the SAME live block on
 * every streamed chunk, and that block's `text` is already the whole reasoning so far —
 * so appending it re-added everything seen before on each delta, growing the stored text
 * as O(n²). A 5000-character chain arriving five characters at a time landed as 2.5 MB,
 * and one long turn pushed a session file past the 512 MB limit where `JSON.stringify`
 * throws `Invalid string length` — losing the turn outright and making the session
 * unlistable. Any OTHER producer of a thinking row hands over a complete block too, so
 * the block on record is always the whole thing.
 *
 * Module-level and exported so a test can drive the real write path: a round trip through
 * `saveSession` cannot catch this, because whatever was stored does round-trip — only the
 * SIZE of it is wrong.
 *
 * @returns {boolean} true when an open block was extended rather than a row added.
 */
export function appendTranscriptRow(list, anchor, row, pending) {
  const last = list[list.length - 1];
  if (last && last.anchor === anchor && row.role === 'thinking'
      && last.row && last.row.role === 'thinking' && last.row.pending) {
    last.row.text = row.text || '';
    last.row.pending = pending;
    return true;
  }
  list.push({ anchor, ts: Date.now(), row: { ...row, pending } });
  return false;
}


// True when every absolute / parent-relative path mentioned in the command lies
// inside the workspace. Relative paths are resolved against the command's cwd.
function commandPathsAreInside(state, cmd, cwd) {
  const s = String(cmd || '');
  // Absolute (Windows drive or POSIX) and explicit parent-relative paths.
  const tokens = s.match(/(?:[A-Za-z]:[\\/]|\/|\.\.?[\\/])[^\s"'|;&<>)]*/g) || [];
  for (const tok of tokens) {
    // Skip URL-ish and flag-ish tokens.
    if (/^(https?:)?\/\//.test(tok)) continue;
    const cleaned = tok.replace(/[\\/]+$/, '');
    if (!cleaned) continue;
    if (!isInWorkspace(state, path.resolve(cwd || state.cwd, cleaned))) return false;
  }
  // A `cd` that leaves the workspace is not routine either.
  const cds = s.match(/\bcd\s+([^\s;&|]+)/gi) || [];
  for (const c of cds) {
    const target = c.replace(/^\s*cd\s+/i, '').trim();
    if (target && !isInWorkspace(state, path.resolve(cwd || state.cwd, target))) return false;
  }
  return true;
}
function applyModel(state, cfg, next) {
  cfg.model = next.model; cfg.innerModel = next.innerModel; cfg.provider = next.provider;
  cfg.baseUrl = next.baseUrl; cfg.endpoint = next.endpoint; cfg.apiKey = next.apiKey; cfg.protocol = next.protocol;
  // Carry the resolved context window over too. resolveProvider/resolveModelArg
  // compute `maxContextTokens` for the NEW model, but it lives on the returned
  // object — without copying it here, cfg (and the gauge below) kept the previous
  // model's window after a switch.
  if (next.maxContextTokens != null) cfg.maxContextTokens = next.maxContextTokens;
  state.model = cfg.model; state.provider = cfg.provider;
  state.modelLabel = modelLabel(cfg) || cfg.model || '';
  state.seenThinking = false;
  // Switching models changes the WINDOW, so the percentage has to be recomputed
  // against it. Updating only `ctxMax` left the old ratio in place, and a 1M-window
  // model showed "73% — 364k/1M": two numbers that cannot both be true.
  state.ctxMax = cfg.maxContextTokens || state.ctxMax;
  state.ctxPercent = usagePercent(state.ctxTokens || 0, state.ctxMax);
  // Prices belong to the MODEL, so the session's cost is re-priced on a switch.
  // Accumulating dollars per event instead would price every earlier request at
  // whatever model happened to be active at the time — which is not what the
  // session total means.
  refreshCost(state, cfg);
  try { if (cfg.model) rememberModel(cfg.model); } catch {}
}

function setEffort(state, cfg, value) {
  state.effort = value;
  state.reasoning = !!value && value !== 'off';
  cfg.effort = state.reasoning ? value : '';
}

function registerProvider(state, cfg, h, name, baseUrl, apiKey, protocol, typeLabel, known, catalogId) {
  addProvider(name, { base_url: baseUrl, api_key: apiKey, protocol, known, catalog: catalogId });
  cfg.raw.providers = cfg.raw.providers || {};
  cfg.raw.providers[name] = {
    base_url: baseUrl || undefined, api_key: apiKey || undefined, protocol,
    known: !!known, catalog: catalogId || undefined,
  };
  applyModel(state, cfg, resolveProvider(cfg, name));
  h.notice(`Provider added: ${name} (${typeLabel}) → ${hncodeConfigFile()}`, 'info');
  fetchAndRegisterModels(state, cfg, name, h);
}

async function fetchAndRegisterModels(state, cfg, providerName, h) {
  const p = (cfg.raw.providers || {})[providerName] || {};
  const baseUrl = p.base_url || p.baseUrl || '';
  if (!baseUrl) return;
  h.notice(`Discovering models for ${providerName}…`, 'info');
  const models = await fetchModels({ baseUrl, apiKey: p.api_key || p.apiKey || '', protocol: p.protocol || 'openai' });
  if (!models.length) { h.notice(`No models discovered for ${providerName} (endpoint unreachable or empty).`, 'error'); return; }
  cfg.raw.models = cfg.raw.models || {};
  for (const m of models) {
    addModel(providerName, m.id, { display_name: m.display, contextLength: m.contextLength, maxTokens: m.maxTokens });
    // Merge over any existing entry rather than replacing it: discovery reports
    // fewer fields than the user may have set (context_length, pricing, …), and a
    // field the endpoint did not report must not blank out a value already there.
    const key = modelKey(providerName, m.id);
    cfg.raw.models[key] = mergeRefreshedModelEntry(providerName, m, cfg.raw.models[key]);
  }
  h.notice(`Discovered ${models.length} models for ${providerName}. Use /model to pick one.`, 'info');
}

// Merge ONE refreshed model's data over its previous config entry.
//
// A refresh REPLACES the provider's entries wholesale, but the source (models.dev
// catalog or /v1/models) does not report every field for every model. Building
// the new entry from the fetch ALONE therefore wiped anything the user had set by
// hand — most visibly `context_length`, which then resolved back to the default
// window: a "refresh" that overwrote user settings with nothing.
//
// The rule: a field the source REPORTED wins (that is what a refresh is for); a
// field it did NOT report keeps the value already in the entry — including the
// camelCase spellings older writers used (`contextLength`/`maxTokens`/
// `displayName`), which are folded into the canonical keys here because
// resolveConfig checks `contextLength` BEFORE `context_length`: leaving both on
// the entry would let the stale camelCase copy shadow the fresh value.
export function mergeRefreshedModelEntry(providerName, m, prev) {
  const src = m || {};
  const lim = src.limit || {};
  const p = prev || {};
  const {
    contextLength: pCtx, context_window: pCtxW, max_context_size: pCtxMax,
    maxTokens: pMaxTok, maxOutputTokens: pMaxOut, displayName: pDisplay,
    ...rest
  } = p;
  const ctxLen = src.contextLength || lim.context
    || rest.context_length || pCtx || pCtxW || pCtxMax;
  const maxOut = src.maxOutputTokens || lim.output || rest.max_output_tokens || pMaxOut;
  const maxTok = src.maxTokens || rest.max_tokens || pMaxTok;
  const display = src.display || rest.display_name || pDisplay;
  // Thinking levels: models.dev reasoning_options is the ONLY source of graded
  // lists (effortsFromReasoning returns null for "nothing usable"), so absent
  // that we keep the entry's own list instead of dropping a user's choice.
  const efforts = src.efforts || effortsFromReasoning(src.reasoningOptions) || rest.efforts;
  // The source said true/false -> its value (an explicit `false` must win over an
  // old `true`). The source was silent -> keep what the entry had.
  const reasoning = src.reasoning === true ? true
    : (src.reasoning === false ? false : rest.reasoning);
  // Pricing: only DEFINED fields overwrite, so a partial (or absent) cost report
  // cannot blank out prices the entry already carries.
  const costFields = Object.fromEntries(
    Object.entries(costEntry(costFromCatalog(src.cost))).filter(([, v]) => v !== undefined),
  );
  return {
    ...rest, // everything else the entry carried (ownedBy, custom keys …)
    provider: providerName,
    model: src.id,
    display_name: display,
    context_length: ctxLen,
    max_tokens: maxTok,
    max_output_tokens: maxOut,
    reasoning,
    efforts: efforts || undefined,
    ownedBy: src.ownedBy || rest.ownedBy,
    ...costFields,
  };
}

// Ctrl+R in /provider: re-discover the selected provider's model list. Two cases:
//   * the provider came from models.dev (its key is a catalog id) -> take the WHOLE
//     catalog model list for it, enriched with limit.context / limit.output and
//     reasoning_options. This also covers providers whose /v1/models is empty or
//     wrong, since the catalog is authoritative.
//   * any other provider -> just re-fetch its /v1/models.
// Existing entries are REPLACED (a refresh, not an append), so a removed model
// really disappears instead of lingering as a stale row. Fields the refresh did
// NOT fetch are KEPT from the existing entry (see mergeRefreshedModelEntry): a
// refresh may update settings, never blank them.
async function refreshProviderModels(state, cfg, providerName, h) {
  if (!providerName || providerName.startsWith('＋')) return;
  const p = (cfg.raw.providers || {})[providerName] || {};
  const baseUrl = p.base_url || p.baseUrl || '';
  const protocol = p.protocol || 'openai';
  const apiKey = p.api_key || p.apiKey || '';
  h.notice(`Refreshing models for ${providerName}…`, 'info');

  // SOURCE decides where models come from:
  //   known = true  -> models.dev catalog. `catalog` says WHICH entry (so a renamed
  //                    provider still maps correctly); it falls back to the provider
  //                    name for entries written before `catalog` existed.
  //   known = false (or the key is absent on an old config) -> the endpoint's own
  //                    /v1/models. For an old config with no `known` key we still
  //                    accept a name that matches a catalog id, so existing
  //                    models.dev providers keep working without a rewrite.
  const knownFlag = p.known === true ? true
    : (p.known === false ? false : null);
  const catalogId = p.catalog || providerName;
  let catModels = {};
  if (knownFlag !== false) {
    try {
      const catalog = await fetchCatalog();
      const catEntry = catalog ? catalog[catalogId] : null;
      if (catEntry && catEntry.models) catModels = catEntry.models;
    } catch { /* catalog is optional */ }
  }
  const catIds = Object.keys(catModels);
  const inCatalog = catIds.length > 0;

  let merged;
  if (inCatalog) {
    // The provider IS in models.dev, and the catalog already carries the model
    // list plus limit.context / limit.output / reasoning_options. That is strictly
    // more than /v1/models reports, so we use it directly and make NO network call
    // to the endpoint — one less request, and no failure when the key is unset or
    // the endpoint is slow/wedged.
    merged = catIds.map((id) => {
      const m = catModels[id] || {};
      return {
        id,
        display: m.name || id,
        limit: m.limit || {},
        reasoning: m.reasoning,
        reasoningOptions: m.reasoning_options,
        // Pricing, so a refresh does not silently DROP the cost data the first
        // install wrote — the entries are replaced wholesale below.
        cost: m.cost,
      };
    });
  } else {
    // Custom / self-hosted provider not in the catalog: the only source is the
    // endpoint's own /v1/models.
    let list = [];
    if (baseUrl) {
      try { list = await fetchModels({ baseUrl, apiKey, protocol }); } catch { list = []; }
    }
    if (!list.length) {
      h.notice(`No models found for ${providerName} (not in the catalog and the endpoint reported none).`, 'error');
      return;
    }
    merged = list;
  }

  cfg.raw.models = cfg.raw.models || {};
  // Replace this provider's entries: SNAPSHOT the current ones first (the merge
  // below needs them), then drop them. Models the source no longer lists still
  // disappear — that is what makes Ctrl+R a real refresh.
  const prevByKey = new Map();
  for (const key of Object.keys(cfg.raw.models)) {
    if (key.split('/')[0] !== providerName) continue;
    prevByKey.set(key, cfg.raw.models[key]);
    delete cfg.raw.models[key];
  }
  const persisted = [];
  for (const m of merged) {
    const key = modelKey(providerName, m.id);
    const entry = mergeRefreshedModelEntry(providerName, m, prevByKey.get(key));
    cfg.raw.models[key] = entry;
    // The file write gets the SAME merged values: persisting the raw fetch would
    // re-wipe on disk what the merge just preserved in memory.
    persisted.push({
      id: m.id,
      display_name: entry.display_name,
      contextLength: entry.context_length,
      maxTokens: entry.max_tokens,
      maxOutputTokens: entry.max_output_tokens,
      reasoning: entry.reasoning,
      efforts: entry.efforts,
      cost: {
        input: entry.cost_input,
        output: entry.cost_output,
        cacheRead: entry.cost_cache_read,
        cacheWrite: entry.cost_cache_write,
      },
    });
  }
  // Persist the REPLACEMENT so the refresh survives a restart. Without this the
  // in-memory list looked refreshed but config.toml kept the old entries, and the
  // next launch silently reverted (stale models back, removed ones still present).
  try { replaceProviderModels(providerName, persisted); }
  catch (e) { h.notice(`Refreshed in memory, but writing config failed: ${e.message}`, 'error'); }
  // If the active model belonged to this provider, re-resolve so the status line
  // and the next turn see the refreshed values.
  if (cfg.provider === providerName) applyModel(state, cfg, resolveProvider(cfg, providerName));
  h.notice(`Refreshed ${merged.length} model(s) for ${providerName} (saved).`, 'info');
}

function buildMarkdown(session) {
  const parts = [`# ${session.title || session.id || 'hncode session'}`, ''];
  for (const m of (session.messages || [])) {
    const who = m.role === 'user' ? '**User**' : m.role === 'assistant' ? '**Assistant**' : `**${m.role}**`;
    parts.push(`${who}: ${typeof m.content === 'string' ? m.content : JSON.stringify(m.content || '', null, 2)}`);
    if (m.toolCalls && m.toolCalls.length) {
      for (const tc of m.toolCalls) parts.push(`- tool: ${tc.name}(${JSON.stringify(tc.args || {})})`);
    }
  }
  return parts.join('\n');
}

// ---- key tokenizer (raw bytes -> tokens) ----
export function tokenize(str) {
  const out = [];
  let i = 0;
  while (i < str.length) {
    const c = str[i];
    if (c === ESC && str.startsWith('\x1b[200~', i)) {
      const end = str.indexOf('\x1b[201~', i + 6);
      if (end === -1) break;
      out.push({ paste: str.slice(i + 6, end) });
      i = end + 6;
      continue;
    }
    if (c === ESC) {
      const ku = /^\x1b\[(\d+)(?:;(\d+))?(?::\d+)?u/.exec(str.slice(i));
      if (ku) {
        const cp = parseInt(ku[1], 10);
        const mod = ku[2] ? parseInt(ku[2], 10) - 1 : 0;
        const shift = (mod & 1) !== 0, alt = (mod & 2) !== 0, ctrl = (mod & 4) !== 0;
        if ((cp === 13 || cp === 10) && shift) { out.push({ key: 'newline' }); i += ku[0].length; continue; }
        if (cp === 13 || cp === 10) { out.push({ key: 'enter' }); i += ku[0].length; continue; }
        if (cp === 9) { out.push({ key: shift ? 'shift-tab' : 'tab' }); i += ku[0].length; continue; }
        if (cp === 27) { out.push({ key: 'escape' }); i += ku[0].length; continue; }
        if (!ctrl && !alt && cp >= 32) {
          out.push({ ch: String.fromCodePoint(cp) });
          i += ku[0].length; continue;
        }
        // Shift+Arrow / Shift+Home / Shift+End: the caret MOVES while extending a
        // selection. Emitted as their own tokens so the composer can tell them
        // apart from the plain arrows (which scroll the transcript).
        if (shift && !ctrl && !alt && cp >= 0xE000 && cp < 0xE100) {
          const arrows = { 0xE000: 'up', 0xE001: 'down', 0xE003: 'left', 0xE002: 'right' };
          const a = arrows[cp];
          if (a) { out.push({ key: 'shift-' + a }); i += ku[0].length; continue; }
        }
        // Ctrl+Arrow (CSI-u form) -> c-up / c-down / c-left / c-right, matching the
        // legacy CSI path above so both encodings behave the same.
        if (ctrl && !shift && !alt && cp >= 0xE000 && cp < 0xE100) {
          const arrows = { 0xE000: 'up', 0xE001: 'down', 0xE003: 'left', 0xE002: 'right' };
          const a = arrows[cp];
          if (a) { out.push({ key: 'c-' + a }); i += ku[0].length; continue; }
        }
        if (shift && !ctrl && !alt && (cp === 0xE014 || cp === 0xE015)) {
          out.push({ key: cp === 0xE014 ? 'shift-home' : 'shift-end' });
          i += ku[0].length; continue;
        }
        // Fall back for terminals that send the legacy CSI form with a `2` modifier
        // (handled in csiName) — nothing to do here.
        if (ctrl && shift && !alt) {
          // Ctrl+Shift+<letter> needs its own token. Collapsing it into 'c-<x>'
          // made Ctrl+Shift+C indistinguishable from Ctrl+C, so "copy" ran the
          // interrupt / exit-confirmation path instead.
          const ch = ctrlLetter(cp);
          if (ch) { out.push({ key: 'c-s-' + ch }); i += ku[0].length; continue; }
        }
        if (ctrl && !alt) {
          const ch = ctrlLetter(cp);
          if (ch) { out.push({ key: 'c-' + ch }); i += ku[0].length; continue; }
        }
        i += ku[0].length; continue;
      }
      if (str[i + 1] === '[') {
        if (str[i + 2] === '<') {
          const mm = /^\x1b\[<(\d+);(\d+);(\d+)([Mm])/.exec(str.slice(i));
          if (!mm) break;
          const btn = parseInt(mm[1], 10);
          const mcol = parseInt(mm[2], 10);
          const mrow = parseInt(mm[3], 10);
          const press = mm[4] === 'M';
          if ((btn & 64) === 64) {
            out.push({ key: (btn & 1) ? 'wheeldown' : 'wheelup', col: mcol, row: mrow });
          } else if (press && (btn & 3) === 0 && (btn & 32) === 0) {
            out.push({ key: 'mousedown', button: 'left', col: mcol, row: mrow });
          } else if (press && (btn & 32) === 32 && (btn & 3) === 3) {
            out.push({ key: 'mousehover', col: mcol, row: mrow });
          } else if (press && (btn & 32) === 32) {
            out.push({ key: 'mousemove', button: 'left', col: mcol, row: mrow });
          } else if (!press && (btn & 3) === 0) {
            out.push({ key: 'mouseup', button: 'left', col: mcol, row: mrow });
          } else if (press && (btn & 3) === 2) {
            out.push({ key: 'rightclick', col: mcol, row: mrow });
          }
          i += mm[0].length;
          continue;
        }
        let j = i + 2;
        // Scan the whole parameter run: digits, `;` separators, and a leading `?`
        // (private mode). It used to scan DIGITS ONLY, so `1;5A` (Ctrl+Up) stopped
        // at the `;`, `fin` became `;`, and the `!/[A-Za-z~]/` guard below aborted
        // the sequence — Ctrl+Arrow/Shift+Arrow sent in the legacy CSI form were
        // silently DROPPED. The `;`-parameter parsing further down was unreachable.
        while (j < str.length && (str[j] >= '0' && str[j] <= '9' || str[j] === ';')) j++;
        if (str[j] === '?') { j++; while (j < str.length && (str[j] >= '0' && str[j] <= '9' || str[j] === ';')) j++; }
        const fin = str[j];
        if (fin === undefined || !/[A-Za-z~]/.test(fin)) break;
        const rawParams = str.slice(i + 2, j);
        const params = (rawParams.match(/^\d+/) || [''])[0];
        // Modifier: the 2nd `;`-separated parameter, 1-based (`;2` = Shift, `;5`
        // = Ctrl, `;6` = Ctrl+Shift). Legacy terminals send Shift+Arrow this way
        // rather than as a CSI-u sequence.
        const modStr = (rawParams.match(/;(\d+)/) || [])[1];
        const mod = modStr ? parseInt(modStr, 10) - 1 : 0;
        const shift = (mod & 1) !== 0, ctrl = (mod & 4) !== 0;
        const base = csiName(params, fin);
        if (shift && !ctrl && ['up', 'down', 'left', 'right', 'home', 'end'].includes(base)) {
          out.push({ key: 'shift-' + base });
          i = j + 1;
          continue;
        }
        // Ctrl+Arrow. Without this the modifier was dropped and Ctrl+Up arrived as
        // a plain `up` — indistinguishable from an unmofified arrow. Emitted as its
        // own token so the key handler can give it a distinct action (scroll the
        // output area).
        if (ctrl && !shift && ['up', 'down', 'left', 'right', 'home', 'end'].includes(base)) {
          out.push({ key: 'c-' + base });
          i = j + 1;
          continue;
        }
        out.push({ key: base });
        i = j + 1;
      } else if (str[i + 1] === 'O') {
        const f = str[i + 2];
        if (f === undefined) break;
        out.push({ key: f === 'P' ? 'f1' : 'escape' });
        i += 3;
      } else {
        out.push({ key: 'escape' });
        i++;
      }
    } else if (c === '\r') {
      out.push({ key: 'enter' });
      i++;
      if (str[i] === '\n') i++;
    }
    else if (c === '\n') { out.push({ key: 'newline' }); i++; }
    else if (c === '\t') { out.push({ key: 'tab' }); i++; }
    else if (c === '\x03') { out.push({ key: 'c-c' }); i++; }
    else if (c === '\x02') { out.push({ key: 'c-b' }); i++; }
    else if (c === '\x04') { out.push({ key: 'c-d' }); i++; }
    else if (c === '\x0f') { out.push({ key: 'c-o' }); i++; }
    else if (c === '\x14') { out.push({ key: 'c-t' }); i++; }
    else if (c === '\x13') { out.push({ key: 'c-s' }); i++; }
    // Ctrl+V arrives as the raw control byte 0x16 (terminals do not wrap it in a
    // CSI-u sequence unless the Kitty protocol maps it), so it needs an explicit
    // entry here — otherwise it fell through to { ch: '\x16' } and was dropped.
    else if (c === '\x16') { out.push({ key: 'c-v' }); i++; }
    // Ctrl+X is the same story: raw 0x18. Ctrl+Shift+X comes through the CSI-u
    // path above as `c-s-x` on terminals that report modified keys.
    else if (c === '\x18') { out.push({ key: 'c-x' }); i++; }
    // Backspace must be matched BEFORE the general Ctrl rule below: 0x08 is also
    // the "Ctrl+H" code, and terminals send it for Backspace.
    else if (c === '\x7f' || c === '\x08') { out.push({ key: 'backspace' }); i++; }
    // Every other Ctrl+<letter> arrives as the raw byte 0x01-0x1A (A-Z). Without
    // this general rule only the hand-listed few above were recognised and the
    // rest fell through to `{ ch: '\x05' }` — a literal control character, so
    // Ctrl+E (0x05) and friends were simply dead on legacy terminals. The listed
    // codes are matched first, so this only catches the ones not spelled out.
    else if (c >= '\x01' && c <= '\x1a') { out.push({ key: 'c-' + String.fromCharCode(c.charCodeAt(0) + 96) }); i++; }
    else { out.push({ ch: c }); i++; }
  }
  return { tokens: out, rest: str.slice(i) };
}
// Lower-case letter (or space) a control-key code point stands for, else null.
export function ctrlLetter(cp) {
  if (cp >= 97 && cp <= 122) return String.fromCharCode(cp);
  if (cp >= 65 && cp <= 90) return String.fromCharCode(cp + 32);
  if (cp === 32) return ' ';
  return null;
}
export function csiName(params, fin) {
  if (fin === 'A') return 'up';
  if (fin === 'B') return 'down';
  if (fin === 'C') return 'right';
  if (fin === 'D') return 'left';
  if (fin === 'F') return 'end';
  if (fin === 'H') return 'home';
  if (fin === 'Z') return 'shift-tab';
  if (fin === '~') {
    const n = parseInt(params || '0', 10);
    if (n === 1 || n === 7) return 'home';
    if (n === 3) return 'delete';
    if (n === 4 || n === 8) return 'end';
    if (n === 5) return 'pageup';
    if (n === 6) return 'pagedown';
    return 'escape';
  }
  return 'escape';
}

// ---- TUI entry point ----
export async function startTUI(opts) {
  const { cfg } = opts;
  // `let`, and mirrored on `state.session`, because /move REPLACES the session: the command
  // hands back a new object, and every later save would otherwise keep writing the old one —
  // which is how /move left the session stamped with the directory it was moved away from.
  let session = opts.session;
  
  // FIRST: Ensure model is initialized before restoring session
  if (!cfg.model || !cfg.innerModel) {
    // Model not set yet - use default or prompt user
    if (!cfg.model) {
      console.log('No model configured. Please run /model to select one.');
      return 1;
    }
  }

  const state = makeState({ cfg, session, opts });
  // Mirror the session on the state so `/move` can rebind ONE binding and have every
  // consumer follow (see `replaceSession`).
  state.session = session;

  cfg.effort = state.reasoning ? state.effort : '';
  // Price the session's restored tokens against the model it is about to use, so
  // /cost and the status badge are right before the first new request.
  refreshCost(state, cfg);
  // Restore the selected OUTPUT STYLE by NAME, re-reading its file: the body may
  // have been edited since the session was saved, and the name is what config.toml
  // stores (see config.outputStyle). A name that no longer resolves is reported
  // rather than silently ignored — the user set it and would otherwise be left
  // wondering why their style stopped applying.
  if (cfg.outputStyle) {
    const s = findStyle(cfg.outputStyle, state.cwd);
    if (s) state.outputStyle = s;
    else appErr(`Output style "${cfg.outputStyle}" no longer exists — /output-style to pick another.`);
  }
  // FEATURE FLAGS: resolved once here so the whole session reads a stable set, and
  // so /experiments has something to show. A flag enabled from the ENVIRONMENT is
  // announced, because a behaviour that differs from config.toml with no visible
  // reason is the worst kind of surprise.
  state.experiments = experimentState(cfg);
  {
    const fromEnv = enabledExperiments({ raw: {} }, process.env);
    if (fromEnv.length) app(`Experiments from environment: ${fromEnv.join(', ')}`);
  }
  // The startup palette: what config says, else `auto` — the brand palette, and the theme
  // schema's own default. Hard-coding 'dark' here meant a saved theme was ignored on the
  // next start, so `/theme gruvbox` looked like it had not stuck.
  setTheme(cfg.raw && hasTheme(cfg.raw.theme) ? cfg.raw.theme : 'auto');

  // Live argument completions for the composer menu. /effort completes from the
  // CURRENT model's thinking levels (models.dev data), which the static hint
  // cannot express — so the hint stays a generic placeholder and the real words
  // come from here. Reads `cfg`/`state` live on every call, so a /model switch is
  // reflected immediately.
  setArgCompletionProvider((name) => {
    if (name === 'effort' || name === 'thinking') {
      return effortOptions(cfg, state.model);
    }
    return null;
  });
  
  // Calculate initial context usage from loaded session
  if (session && session.messages && session.messages.length) {
    const approx = estimateMessagesTokens(session.messages, cfg);
    state.ctxTokens = approx;
    state.ctxPercent = usagePercent(approx, state.ctxMax);
  }

  // Warm the models.dev catalogue in the background. It is what supplies PRICES
  // for a model entry that predates them (see config.modelCost), so without this
  // `/cost` and the status badge report "unknown" until the user happens to open
  // /provider. Deliberately not awaited: a slow catalog must not delay the first
  // paint, and the cost readout is only consulted on demand.
  //
  // The RATE is warmed here too, when the saved currency is not USD: the render
  // path reads it synchronously, so without this a session resumed with
  // `/cost cny` set would draw its cost in USD until the next usage event.
  void (async () => {
    try {
      const cur = costCurrency(cfg);
      await fetchCatalog();
      if (cur !== 'USD') await usdRate(cur, { override: cfgCnyPerUsd(cfg) });
      refreshCost(state, cfg);
    } catch { /* offline: the readout says the price is unknown */ }
  })();
  
  // NOW: Restore session with the correct model context.
  // The shellHistory test matters as much as the messages one: `!command` output
  // lives ONLY in shellHistory, so a session of nothing but shell commands has an
  // empty `messages` and was restored as a blank screen.
  if (session && ((session.messages && session.messages.length) || (session.shellHistory || []).length)) {
    state.chat = reconstructChat(session);
  }


  const stdin = process.stdin;
  const stdout = process.stdout;

  // ---- web UI bridge (/web) --------------------------------------------------
  // `web` is null until the user runs /web. `hub` is created then too, so a
  // session that never opens the UI pays for none of this. The hub is the shared
  // state; syncWeb pushes the transcript into it and pushes the session status,
  // and `webActions` wires the browser's requests to the SAME functions the
  // keyboard calls — that is what makes the two front-ends behave identically.
  let web = null;
  let hub = null;
  let webSyncQueued = false;
  // The machine-wide daemon attachment (see attachGlobalWeb). Null until /web,
  // and its presence is what "this session is published" means.
  let webDaemon = null;

  function syncWeb() {
    if (!web || !hub) return;
    // Coalesce: `emit` for each changed row already marks the subscribers dirty,
    // and syncChat is cheap, but a burst of frames would still run it repeatedly
    // for the same state.
    if (webSyncQueued) return;
    webSyncQueued = true;
    setImmediate(() => {
      webSyncQueued = false;
      if (!web || !hub) return;
      try { hub.syncChat(state.chat); } catch { /* the UI must never break the TUI */ }
      try { hub.setStatus(webStatus()); } catch { /* best-effort */ }
    });
  }


  // Everything the browser's status panel and side panes show. Built fresh on each
  // sync: it is a handful of field reads, and deriving it from live state is what
  // keeps the two front-ends from disagreeing after a mode change.
  function webStatus() {
    // Files this conversation touched, counted from the transcript. The TUI has no
    // separate index, and reading it here means a Write the model made is listed
    // without any tool having to announce itself.
    const files = new Map();
    const bump = (p, op) => {
      if (typeof p !== 'string' || !p) return;
      let rel = p;
      try { rel = path.relative(state.cwd || cfg.workspace || '', p) || p; } catch { /* keep as-is */ }
      if (rel.startsWith('..')) rel = p;                 // outside the workspace: show it whole
      const e = files.get(rel) || { path: rel, ops: new Set(), count: 0 };
      e.ops.add(op);
      e.count++;
      files.set(rel, e);
    };
    for (const m of state.chat || []) {
      if (m.role !== 'tool' || !m.toolArgs) continue;
      const a = m.toolArgs;
      const p = a.path || a.file_path;
      bump(p, m.toolName || 'tool');
    }
    const fileList = [...files.values()]
      .map((e) => ({ path: e.path, ops: [...e.ops].join(' '), count: e.count }))
      .sort((x, y) => y.count - x.count || x.path.localeCompare(y.path))
      .slice(0, 200);

    const tasks = Object.values(state.tasks || {}).map((t) => ({
      id: t.id || t.taskId || '',
      kind: t.kind || 'bash',
      status: t.status || 'running',
      summary: t.summary || t.description || t.prompt || '',
      // Passed through when the task carries them, so the web task card can show
      // a start time / agent id instead of silently rendering nothing.
      startedAt: t.startedAt || t.startAt || 0,
      agentId: t.agentId || '',
    }));

    const next = {
      session: session && session.id,
      title: session && session.title,
      model: state.modelLabel || cfg.model || '',
      provider: cfg.provider || '',
      mode: PERMISSION_LABEL[state.mode] || state.mode || '',
      cwd: state.cwd || '',
plan: !!state.plan,
      focus: !!state.focus,
      swarm: !!state.swarm,
      // Live git status mirror, so the web statusline can show branch + diff
      // counts exactly like the TUI footer. Null when git is unavailable.
      git: state._gitInfo || null,
      // Thinking state, mirroring the terminal footer's model suffix. The
      // statusline appends "thinking[: effort]" from these two fields.
      reasoning: !!state.reasoning,
      effort: state.effort || '',
      busy: !!state.running,
      // The Working row's phrase and animation tick. Sent so the BROWSER shows
      // the same word, mid-sweep, as the terminal — the browser used to pick its
      // own random word and run its own clock, so the two screens disagreed about
      // both the text and the colour phase.
      workMsg: state.workMsg || '',
      spin: state.spin || 0,
      // The tick the current pulse BEGAN. The browser animates the tool-name
      // sweep and the Working row off `spin`, and both must start their cycle at
      // the tick the pulse started — using the raw spinner tick would drop them
      // into a mid-cycle colour the instant the animation hands over, which is a
      // different colour on screen from the terminal's.
      pulseStart: state.pulseStart == null ? 0 : state.pulseStart,
      ctxTokens: state.ctxTokens || 0,
      ctxMax: state.ctxMax || 0,
      ctxPercent: state.ctxPercent || 0,
      rounds: state.rounds || 0,
      steps: state.steps || 0,
      tokRate: state.tokRate || 0,
todos: [...(state.todos || [])],
      queued: [...(state.queued || [])],
      tasks,
      files: fileList,
      tools: toolsForWeb(),
      commands: commandsForWeb(),
      // The workspace tree, for `@` completion in the composer. Cached (below)
      // because walking a real project is synchronous I/O on the render path.
      workspaceFiles: workspaceFilesForWeb(),
      quick: QUICK_COMMANDS,
      // The enumerable settings the browser can CHANGE, with the current value.
      //
      // The terminal exposes these as pickers, which the browser cannot render —
      // that is why /model and friends did nothing there. Sending the options
      // with the status lets the browser draw its own control and post the choice
      // back through `dispatch` ("/model <alias>"), which is the same path the
      // keyboard takes.
      options: optionsForWeb(),
      // A blocking prompt, if one is on screen — the browser renders it as a modal
      // and answers through the `approve` / `answerQuestion` actions.
      pending: pendingForWeb(),
    };

    // Reuse the previous identity for any field whose CONTENT is unchanged.
    //
    // `setStatus` skips the broadcast when nothing changed, and it decides that by
    // identity. Most fields above are rebuilt on every call (todos, queued, tasks
    // and the file list all come from fresh arrays), so without this every frame
    // would look like a change and the full status would be pushed over SSE twelve
    // times a second for nothing. Comparing here — once, shallowly — is what makes
    // the "did anything actually change" test meaningful.
    const prev = (hub && hub.status) || null;
    if (prev) {
      for (const k of Object.keys(next)) {
        if (next[k] === prev[k]) continue;
        if (shallowEqualArray(next[k], prev[k])) next[k] = prev[k];
      }
    }
    return next;
  }

  /** True when two arrays hold the same content (compared one level deep). */
  function shallowEqualArray(a, b) {
    if (!Array.isArray(a) || !Array.isArray(b) || a.length !== b.length) return false;
    for (let i = 0; i < a.length; i++) {
      if (a[i] === b[i]) continue;
      // Elements are usually small objects (a todo, a task); compare their own
      // fields rather than their identity.
      if (!shallowEqualObject(a[i], b[i])) return false;
    }
    return true;
  }

  function shallowEqualObject(a, b) {
    if (!a || !b || typeof a !== 'object' || typeof b !== 'object') return false;
    if (Array.isArray(a) !== Array.isArray(b)) return false;
    const ka = Object.keys(a);
    const kb = Object.keys(b);
    if (ka.length !== kb.length) return false;
    for (const k of ka) {
      const va = a[k];
      const vb = b[k];
      if (va === vb) continue;
      // A stringified compare covers the one nested level these shapes have (an
      // ops list, a tool's args). It only runs once the references differ, so it
      // is not on the hot path for unchanged rows.
      if (va && vb && typeof va === 'object' && typeof vb === 'object') {
        if (JSON.stringify(va) !== JSON.stringify(vb)) return false;
        continue;
      }
      return false;
    }
    return true;
  }

  // The settings the browser can change, each with its current value and the
  // candidates that can replace it. Every entry maps to a `dispatch` invocation,
  // so the browser never needs a code path of its own — it posts the same command
  // the terminal would run. That is what makes /model work in the browser.
  function optionsForWeb() {
    const models = (cfg.raw && cfg.raw.models) || {};
    const modelItems = Object.keys(models).map((key) => {
      // Each model carries its OWN thinking levels. The browser draws them next
      // to the model so switching model shows that model's valid efforts, exactly
      // as the terminal's picker does with `effortOptions(cfg, item.label)`. A
      // model without a Thinking control (`effortOptions` returns []) is simply
      // absent from the list.
      const efforts = effortOptions(cfg, key);
      return {
        value: key,
        label: models[key].display_name || key,
        sub: models[key].provider || '',
        current: key === cfg.model,
        efforts: efforts.map((v) => ({ value: v, label: v, current: v === (state.effort || 'off') })),
      };
    });
    const efforts = effortOptions(cfg);
return {
      model: { value: cfg.model || '', items: modelItems },
      effort: {
        value: state.effort || 'off',
        items: efforts.map((v) => ({ value: v, label: v, current: v === (state.effort || 'off') })),
      },
      mode: {
        value: state.mode || 'ask',
        items: ['ask', 'yolo', 'auto'].map((v) => ({
          value: v, label: PERMISSION_LABEL[v] || v, current: v === (state.mode || 'ask'),
        })),
      },
      plan: {
        value: state.plan ? 'on' : 'off',
        items: [
          { value: 'on', label: 'on', current: !!state.plan },
          { value: 'off', label: 'off', current: !state.plan },
        ],
      },
      focus: {
        value: state.focus ? 'on' : 'off',
        items: [
          { value: 'on', label: 'on', current: !!state.focus },
          { value: 'off', label: 'off', current: !state.focus },
        ],
      },
      calmMode: {
        value: cfg.calmMode ? 'on' : 'off',
        items: [
          { value: 'on', label: 'on', current: !!cfg.calmMode },
          { value: 'off', label: 'off', current: !cfg.calmMode },
        ],
      },
    };
  }

  // `@` completion needs the file list, and re-walking the tree on every status
  // push would be synchronous I/O inside the render loop. The cache is keyed by
  // the workspace and refreshed on a TTL, matching the terminal's own @-list cache
  // (MENTION_CACHE_MS) so the two front-ends offer the same files.
  let wsFilesCache = { root: '', at: 0, files: null };
  function workspaceFilesForWeb() {
    const root = state.cwd || state.workspace || process.cwd();
    const now = Date.now();
    if (wsFilesCache.files && wsFilesCache.root === root && now - wsFilesCache.at < 5000) {
      return wsFilesCache.files;
    }
    let files = [];
    try { files = collectWorkspaceFiles(root, { limit: 2000, maxDepth: 6 }); } catch { files = []; }
    wsFilesCache = { root, at: now, files };
    return files;
  }
  // Built ONCE per session and reused by reference.
  //
  // `webStatus` runs on every frame (syncWeb is called from paintNow), so building
  // these lists each time cost a map over ~20 tools and ~60 commands at the
  // spinner's 80 ms cadence — and it defeated `setStatus`'s change detection,
  // which compares by identity. The registries do not change while a session runs,
  // so caching is both cheaper and MORE correct: an unchanged array reference is
  // what lets the status broadcast be skipped.
  let toolsCache = null;
  let commandsCache = null;

  function toolsForWeb() {
    if (toolsCache) return toolsCache;
    try {
      toolsCache = toolNames().map((n) => {
        const t = getTool(n);
        return { name: n, description: (t && t.description) || '' };
      });
    } catch { toolsCache = []; }
    return toolsCache;
  }

  function commandsForWeb() {
    if (commandsCache) return commandsCache;
    try {
      const cmds = allCommands().map((c) => ({
        name: c.name,
        aliases: c.aliases || [],
        desc: c.desc || c.description || '',
        argumentHint: c.argumentHint || '',
      }));
      // Merge installed skills into the `/` completion list so the web composer
      // offers them the moment `/` is typed, mirroring the TUI menu.
      for (const s of listSkills()) {
        cmds.push({
          name: SKILL_PREFIX + s.name,
          aliases: [],
          desc: s.description || 'skill',
          argumentHint: '',
        });
      }
      commandsCache = cmds;
    } catch { commandsCache = []; }
    return commandsCache;
  }

  // The approval / question currently waiting on the user, in a shape the browser
  // can render. Only ONE of these can be open at a time (the agent blocks on it).
  function pendingForWeb() {
    if (state.approvalPending) {
      const ap = state.approvalPending;
      return {
        kind: 'approval',
        id: 'approval',
        detail: [String(ap.toolName || ''), ...(ap.detail || [ap.desc || ''])].join('\n'),
      };
    }
    if (state.question) {
      const q = state.question;
      const cur = (q.items && q.items[q.index]) || { question: '', options: [] };
      const total = (q.items || []).length;
      const isLast = q.index === total - 1;
      return {
        kind: 'question',
        id: 'question',
        question: cur.question || '',
        header: cur.header || '',
        options: (cur.options || []).map((o) => ({ label: o.label, description: o.description || '' })),
        // Progress + mode, so the browser can render "n/total", multi-select
        // checkboxes, and the per-question "Other" row.
        index: q.index || 0,
        total,
        multiSelect: !!cur.multiSelect,
        // The whole-request free-text note is offered after the LAST question
        // (same as the terminal's SUPPLEMENT row).
        hasSupplement: isLast,
        placeholder: '',
      };
    }
    // The PLAN under review in Plan mode. Same channel as the other two modals, so the
    // browser needs no new plumbing — only a third `kind` to render. Without it a plan
    // arrived in the web UI as a blocking turn with nothing on screen to answer it, and
    // the only way out was Esc in a terminal that might not be open.
    if (state.planPending) {
      return {
        kind: 'plan',
        id: 'plan',
        // The plan text as the model wrote it. `detail` is what the browser's modal body
        // already renders, so it is filled here too rather than only in `plan`.
        detail: String(state.planPending.plan || ''),
        plan: String(state.planPending.plan || ''),
        // The four outcomes the terminal's key handler can produce (see the planPending
        // branch in handleKey: enter -> approve, e -> edit, esc -> keep, and 'auto' which
        // skips the prompt entirely). Each is offered so the browser is not a dead end.
        outcomes: ['approve', 'edit', 'keep'],
      };
    }
    // The full-screen EDITOR (`openEditor`), reached by /memory, /personal, /permissions,
    // /output-style, /keybindings and /set-system-prompt. Without a web form for it, all
    // six commands run to the point of opening the editor and then do nothing visible —
    // the browser had no way to show one, so the command looked broken rather than
    // unsupported. It rides the same `pending` channel as the other modals.
    if (state.editor) {
      const ed = state.editor;
      return {
        kind: 'editor',
        id: 'editor',
        title: String(ed.title || 'Edit'),
        hint: String(ed.hint || ''),
        text: String(ed.text == null ? '' : ed.text),
        // Whether saving writes anything back. `onSave` is what the TUI calls; an editor
        // without one is read-only, and the browser should say so rather than offer a Save
        // that silently discards.
        savable: typeof ed.onSave === 'function',
      };
    }
    return null;

  }

  // Roles that exist only on screen, so `session.messages` cannot carry them: that array
  // is what gets SENT to the model, and a notice or a warning in it would spend context on
  // prose the model has already acted on. They are persisted to `session.transcript`
  // instead, which nothing sends to a provider.
  //
  // `rich` is deliberately not here. Those rows are command OUTPUT — /diff, /log, /cost,
  // /context — and replaying them on resume shows a snapshot of a moment that has passed:
  // a diff from an earlier commit, a cost that has since changed. They also carry their
  // own ANSI, which has no place in a JSON transcript.
  //
  // `bash` and `tool_result` are not here either: `runShellCommand` already records both
  // in `session.shellHistory`, and reconstructChat rebuilds them from it. Recording them
  // a second time would double every `!cmd` on resume.
  const PERSISTED_ROLES = new Set(['system', 'warn', 'plan', 'compaction', 'bg_task', 'skill', 'steer', 'thinking']);

  function recordTranscriptRow(msg) {
    if (!session) return;
    if (state.saveHistory === false) return;           // the user's switch
    const row = normalizeMsg(msg);
    if (!PERSISTED_ROLES.has(row.role)) return;
    // Reasoning is the one long-text role here and the bulk of the cost, so it has its
    // own flag: the short notices stay cheap enough to keep on by default.
    if (row.role === 'thinking' && state.saveThinking === false) return;
    const list = (session.transcript = session.transcript || []);
    const anchor = (session.messages || []).length;
    // `pending` is dropped by normalizeMsg but the extend test needs it, so it is read
    // off the live message rather than the normalized copy.
    const pending = !!(msg && msg.pending);
    appendTranscriptRow(list, anchor, row, pending);
  }


  const addChat = (msg) => {
    state.chat.push(normalizeMsg(msg));
    recordTranscriptRow(msg);
    // Auto-follow / re-anchor is delegated to anchorScroll() so exactly ONE place
    // adjusts `scroll`. This block used to run its own row-delta compensation
    // against a second baseline (_addChatRows) which — like anchorScroll's old
    // one — was not refreshed while the view was pinned. After the user scrolled
    // up, BOTH paths added the same rows, so the view jumped by twice the growth.
    anchorScroll();
    renderFrame();
  };
  let noticeTimer = null;
  function notice(text, kind = 'info') {
    state.notice = text;
    state.noticeKind = kind;
    renderFrame();
    if (noticeTimer) clearTimeout(noticeTimer);
    noticeTimer = setTimeout(() => { state.notice = ''; renderFrame(); }, 4000);
  }

  function dims() {
    try {
      const [cols, rows] = stdout.getWindowSize();
      return { cols: cols || 80, rows: rows || 24 };
    } catch { return { cols: 80, rows: 24 }; }
  }
  let lastFrame = null;
  let paintScheduled = false;
  // Deadline for the next FULL repaint. A differential painter compares against the frame
  // it BELIEVES it painted, never the real screen, so any divergence between the two is
  // permanent: it survives every later frame because the comparison keeps saying "that row
  // has not changed". Divergence has several possible causes — a terminal that does not
  // cancel the pending-wrap flag on a cursor move, a width model that disagrees with the
  // terminal's for some glyph, a resize that `getWindowSize` reported late — and rather
  // than only defend against the ones we know about, bound the damage: repaint the whole
  // frame unconditionally every few seconds, so anything stray is gone within that window
  // instead of lingering until the user re-enters the session.
  //
  // The cost is one full frame per interval of ACTIVITY (an idle session paints rarely,
  // so it pays almost nothing), and `diffFrame` wraps the write in a synchronized update,
  // so a full repaint does not flicker.
  const FULL_REPAINT_MS = 3000;
  let lastFullPaint = 0;
  function paintNow() {
    paintScheduled = false;
    const { cols, rows } = dims();
    const frame = composeFrame(state, cols, rows);
    const now = Date.now();
    // `state._forceRepaint` is set by anything that changed what EVERY cell should say
    // without changing the frame's text — a theme switch is the case that matters. The
    // differential painter compares against the frame it believes it painted, so a new
    // palette alone emits no bytes and the screen keeps the old colours. Set through the
    // state because the setter lives in `dispatch`, which cannot see this closure.
    const forcePaint = state._forceRepaint === true;
    if (forcePaint) state._forceRepaint = false;
    const forceFull = forcePaint || (now - lastFullPaint) >= FULL_REPAINT_MS;
    const out = diffFrame(forceFull ? null : lastFrame, frame);
    if (forceFull) lastFullPaint = now;
    lastFrame = frame;
    state._hitboxes = frame.hitboxes || [];
    state._composerMeta = frame.composerMeta || [];
    if (out) stdout.write(out);
    // "Painted" becomes observable here: everything that reaches the screen goes
    // through this one function, so the tick advancing means bytes left this process.
    // See src/flush-tick.js for what reads it.
    noteTerminalFlush();
    // Mirror the transcript to the web UI, if one is attached. Done HERE because
    // every change reaches the screen through this one function, so it catches the
    // rows that bypass addChat (streamed prose, tool rows, the plan bubble, an
    // abort) without instrumenting each of those call sites. `syncChat` is a no-op
    // until `/web` runs, and it is incremental, so an idle frame costs nothing.
    if (web) void syncWeb();
    // Re-set AFTER the write: `_frameTickAt` names the LAST frame, so it has to be
    // captured once that frame is on the terminal, not before it.
    state._frameTickAt = getTerminalFlushTick();
  }
  function renderFrame() { paintNow(); }
  // Paint the pending frame NOW, if there is one.
  //
  // The mouse handlers read geometry that `composeFrame` produced — `_bodyScreenTop` for
  // row mapping, the hitbox list for what a click hit — and a click frequently arrives in
  // the window between a state change and its `renderSoon()`. The values are usually
  // right (the pending paint renders the same state again), but a resize or a re-entrant
  // render can make that pending paint a DIFFERENT frame, and then the click acts on a
  // row the user never sees. Settling it here is cheaper than any timeout: at most one
  // extra frame, and only when a click lands mid-paint.
  //
  // It clears `paintScheduled` itself through `paintNow`, so the queued immediate
  // becomes a no-op rather than painting twice.
  function flushFrame() {
    if (paintScheduled) paintNow();
  }
  // Let module-level helpers (refreshGitInfo) ask for a repaint once their async
  // data lands, without holding a reference to this closure.
  state._requestRender = renderFrame;
  // No frame-rate cap: paint on the next event-loop turn. Calls made within the
  // same tick still coalesce (paintScheduled), so a burst of stream deltas
  // produces one frame per tick at full speed instead of being throttled to
  // ~60fps and having intermediate frames dropped.
  function renderSoon() {
    if (paintScheduled) return;
    paintScheduled = true;
    setImmediate(paintNow);
  }
  function openPicker(p) {
    let footer = p.footer ? { focused: false, ...p.footer } : null;
    if (p.footerFor) {
      const item = (p.items || [])[Math.max(0, Math.min((p.items || []).length - 1, p.sel || 0))];
      footer = p.footerFor(item, footer) || footer;
    }
    state.picker = {
      title: p.title || '',
      items: p.items || [],
      sel: Math.max(0, Math.min((p.items || []).length - 1, p.sel || 0)),
      searchable: p.searchable !== false,
      hint: p.hint || null,
      keepInput: !!p.keepInput,
      onPick: p.onPick || (() => true),
      onDelete: p.onDelete || null,
      onCancel: p.onCancel || null,
      onCtrlE: p.onCtrlE || null,     // Ctrl+E "edit selected" hook (e.g. /model)
      onCtrlR: p.onCtrlR || null,     // Ctrl+R "refresh selected" hook (e.g. /provider)
      onFooterPick: p.onFooterPick || null,  // a CLICK on a footer option (see below)
      // A picker with a second decision on its footer row (/model: the list picks the
      // model, the row picks the thinking level) must not close on a list CLICK — the
      // mouse could otherwise never reach the footer. The keyboard is unaffected: Enter
      // still picks and closes.
      clickKeepsOpen: !!p.clickKeepsOpen,
      footerFor: p.footerFor || null,
      footer,
      categories: p.categories || null,   // list of category labels (first is "All")
      category: p.category || null,        // active category (null = "All")
      // Screen position the box should open AT, instead of centred. Used by the
      // right-click context menu, which by convention appears under the pointer: a
      // menu that jumps to the middle of the screen loses the one piece of context
      // that told the user which row they right-clicked. `{ row, col }` in absolute
      // frame coordinates. Null (the default) means "centre it".
      anchor: p.anchor || null,
    };
    state.pickerQuery = '';
    state.pickerCategory = (state.picker.categories && state.picker.categories.length)
      ? (p.category || state.picker.categories[0]) : null;
    state.form = null;
    state.menuOpen = false; state.menuList = []; state.menuSel = 0;
    // The previous frame's hover described a DIFFERENT layout (the row the pointer
    // was over, before this overlay replaced those rows). Keeping it tinted whatever
    // the new overlay happened to draw on that row.
    state.hoverHit = null;
    // A dialog usually replaces the composer, so the half-typed prompt is
    // cleared — but the right-click context menu is an overlay ON TOP of the
    // composer and must leave it (text + caret) untouched, otherwise opening it
    // silently destroyed the prompt.
    if (!p.keepInput) { state.input = ''; state.caret = 0; }
    renderFrame();
  }

  // ---- @ file completion ----------------------------------------------------

  // ---- @ file completion ----------------------------------------------------
  // Typing `@` shows an INLINE candidate list above the composer — the same widget
  // `/` uses (state.mention*) — rather than taking over the screen. It used to be a
  // silent rewrite of the input to the FIRST match of a single-directory listing:
  // you could not see the candidates, could not descend into a subdirectory
  // (`@src/` matched nothing), and hidden files were dropped.
  //
  // `walk` is bounded (depth + entry count) because it runs on a keystroke.
  function collectWorkspaceFiles(root, { limit = 4000, maxDepth = 8 } = {}) {
    const out = [];
    const skip = new Set(['node_modules', '.git', 'dist', 'build', '.next', 'target', '__pycache__']);
    const walk = (dir, rel, depth) => {
      if (out.length >= limit || depth > maxDepth) return;
      let entries;
      try { entries = fs.readdirSync(dir, { withFileTypes: true }); } catch { return; }
      // Deterministic order: directories first, then files, each alphabetical, so
      // the list does not jump around between keystrokes.
      entries.sort((a, b) => (b.isDirectory() - a.isDirectory()) || a.name.localeCompare(b.name));
      for (const e of entries) {
        if (out.length >= limit) return;
        if (skip.has(e.name)) continue;
        const relPath = rel ? rel + '/' + e.name : e.name;
        if (e.isDirectory()) {
          out.push({ label: relPath + '/', isDir: true, rel: relPath + '/' });
          walk(path.join(dir, e.name), relPath, depth + 1);
        } else {
          out.push({ label: relPath, isDir: false, rel: relPath });
        }
      }
    };
    walk(root, '', 0);
    return out;
  }

  // Everything after the last `@` that has no whitespace in it is the query.
  function atQueryAt(input) {
    const s = String(input || '');
    const at = s.lastIndexOf('@');
    if (at < 0) return null;
    const after = s.slice(at + 1);
    if (/\s/.test(after)) return null;      // an email-ish "@foo bar" is not a path
    // Only treat it as a mention when `@` starts a word (start of input or after space).
    if (at > 0 && !/\s/.test(s[at - 1])) return null;
    return { at, query: after };
  }

  // The file index is CACHED per workspace root. Walking a real project on every
  // keystroke measured 82 ms on a 3k-entry tree — a visible stall while typing —
  // and a monorepo with node_modules is far worse. The cache is refreshed when it
  // is older than MENTION_CACHE_MS or the root changes, so the list still tracks
  // files created during the session without paying the walk on every character.
  let mentionCache = null;   // { root, at, files }
  const MENTION_CACHE_MS = 5000;

  function mentionFiles(root) {
    const now = Date.now();
    if (mentionCache && mentionCache.root === root && now - mentionCache.at < MENTION_CACHE_MS) {
      return mentionCache.files;
    }
    const files = collectWorkspaceFiles(root);
    mentionCache = { root, at: now, files };
    return files;
  }

  // Refresh the inline @ list from the current input. Called on every keystroke
  // that touches the mention, and on Tab. Closes the list when the caret leaves the
  // mention (e.g. a space was typed after it).
  function refreshMention() {
    const hit = atQueryAt(state.input || '');
    if (!hit) {
      state.mentionOpen = false;
      state.mentionList = [];
      state.mentionSel = 0;
      state.mentionOffset = 0;
      return;
    }
    const root = state.cwd || state.workspace || process.cwd();
    const q = hit.query.toLowerCase();
    const all = mentionFiles(root);
    // Precompute the lowercase label + basename once per entry instead of inside
    // the comparator: they were recomputed on every comparison of every sort.
    const ranked = [];
    for (const f of all) {
      const label = f.label.toLowerCase();
      if (q && !label.includes(q)) continue;
      const base = label.slice(label.lastIndexOf('/') + 1);
      ranked.push({ f, nameHit: q && base.startsWith(q) ? 0 : 1 });
    }
    ranked.sort((a, b) => {
      if (a.nameHit !== b.nameHit) return a.nameHit - b.nameHit;
      if (a.f.isDir !== b.f.isDir) return a.f.isDir ? -1 : 1;
      return a.f.label.length - b.f.label.length || (a.f.label < b.f.label ? -1 : a.f.label > b.f.label ? 1 : 0);
    });
    state.mentionList = ranked.slice(0, 200).map((r) => r.f);
    state.mentionSel = Math.min(state.mentionSel || 0, Math.max(0, state.mentionList.length - 1));
    // Keep the window on the selected row. This used to reset the offset to 0,
    // which left a selection beyond MAX_MENU rows invisible — the renderer only
    // walks [offset, offset+MAX_MENU), so nothing at all appeared highlighted.
    state.mentionOffset = windowOffset(state.mentionSel, state.mentionOffset, state.mentionList.length);
    state.mentionOpen = state.mentionList.length > 0;
  }

  // Accept the highlighted candidate: replace the whole `@query` token.
  function acceptMention() {
    const it = (state.mentionList || [])[state.mentionSel || 0];
    if (!it) return false;
    const hit = atQueryAt(state.input || '');
    if (!hit) return false;
    state.input = String(state.input || '').slice(0, hit.at) + '@' + it.rel;
    state.caret = state.input.length;
    state.mentionOpen = false;
    state.mentionList = [];
    state.mentionSel = 0;
    renderFrame();
    return true;
  }

  function openForm(spec) {
    const fields = (spec.fields || []).map((f) => ({
      key: f.key, label: f.label || f.key || '', value: f.value || '',
      kind: f.kind || 'text', caret: (f.value || '').length,
    }));
    const labelW = spec.labelW || Math.max(0, ...fields.map((f) => f.label.length + 1));
    state.form = {
      title: spec.title || '',
      fields,
      fieldIdx: 0,
      type: spec.type !== undefined ? spec.type : PROTOCOL_TYPES[0],
      // The selectable Type values. Kept on the form so the keyboard cycle uses the
      // SAME list the renderer draws — a 2-item toggle here silently dropped any
      // third option (e.g. "OpenAI Responses").
      types: Array.isArray(spec.types) && spec.types.length ? spec.types : PROTOCOL_TYPES,
      hideType: !!spec.hideType,
      labelW,
      note: spec.note || '',
      hint: spec.hint || 'Tab next field · ←/→ type · Enter submit · Esc cancel',
      // Opt-in: a CLICK on a Type option submits the form, the same as Enter. Off by
      // default so a form where the type is one of several decisions keeps the click
      // as a plain selection. /provider turns it on: there the type IS the last
      // decision, and the user asked for the click to finish.
      typeClickSubmits: !!spec.typeClickSubmits,
      onSubmit: spec.onSubmit || (() => {}),
      onCancel: spec.onCancel || null,
    };
    state.picker = null;
    state.pickerQuery = '';
    state.menuOpen = false; state.menuList = []; state.menuSel = 0;
    renderFrame();
  }

  // Open the modal multiline editor (see the `state.editor` branch in
  // composeFrame for the rendering and in handleKey for the editing keys).
  function openEditor(spec) {
    const text = String(spec.text || '');
    const ls = text.split('\n');
    const row = Math.max(0, Math.min(ls.length - 1, spec.caretRow || 0));
    state.editor = {
      title: spec.title || 'Edit',
      hint: spec.hint || 'Ctrl+S save · Esc cancel · Enter newline · arrows move',
      text,
      caretRow: row,
      caretCol: Math.max(0, Math.min((ls[row] || '').length, spec.caretCol || 0)),
      top: 0,
      notice: '',
      noticeKind: 'info',
      onSave: spec.onSave || null,
    };
    state.panel = null; state.picker = null; state.pickerQuery = ''; state.pickerCategory = null; state.form = null;
    state.menuOpen = false; state.menuList = []; state.menuSel = 0;
    renderFrame();
  }

  function openPanel(title, lines) {
    state.panel = { title: title || '', lines: lines || [], top: 0 };
    state.picker = null; state.pickerQuery = ''; state.pickerCategory = null; state.form = null;
    state.menuOpen = false; state.menuList = []; state.menuSel = 0;
    renderFrame();
  }

  // ---- /tasks panel (kimi's TASK BROWSER) ----------------------------------
  function refreshTasksPanel() {
    const p = state.tasksPanel;
    if (!p) return;
    p.tasks = sortedTasks(state.agent ? state.agent.ctx : { tasks: state.tasks });
    const vis = visibleTasks(p.tasks, p.filter);
    if (p.selectedIndex >= vis.length) p.selectedIndex = Math.max(0, vis.length - 1);
  }

  function openTasksPanel() {
    const tasks = sortedTasks(state.tasks ? { tasks: state.tasks } : {});
    state.tasksPanel = {
      tasks,
      filter: 'all',
      selectedIndex: 0,
      listScroll: 0,
      pendingStop: null,
      flash: '',
      flashTimer: null,
    };
    const vis = visibleTasks(tasks, 'all');
    const runningIdx = vis.findIndex((x) => x.status === 'running');
    state.tasksPanel.selectedIndex = runningIdx >= 0 ? runningIdx : 0;
    state.menuOpen = false; state.menuList = []; state.menuSel = 0;
    state.picker = null; state.form = null; state.panel = null;
    renderFrame();
  }

  function closeTasksPanel() {
    const p = state.tasksPanel;
    if (!p) return;
    if (p.flashTimer) clearTimeout(p.flashTimer);
    if (p.pollTimer) clearInterval(p.pollTimer);
    state.tasksPanel = null;
    // Full-screen takeover: its hitbox rows say nothing about the frame that is
    // about to be restored, so the hover highlight goes with it.
    state.hoverHit = null;
    renderFrame();
  }

  function tasksFlash(msg) {
    const p = state.tasksPanel;
    if (!p) return;
    p.flash = msg;
    if (p.flashTimer) clearTimeout(p.flashTimer);
    p.flashTimer = setTimeout(() => { p.flash = ''; renderFrame(); }, 2500);
  }

  // ---- /skills and /plugins manager (kimi's registry panel) ------------------
  // Both commands open the SAME browser; only `kind` differs, so the two cannot drift
  // apart the way two copies would.

  /**
   * Load what the browser shows.
   *
   * The LOCAL half is read synchronously from disk and published FIRST, then the remote
   * half is fetched and merged in. The order matters: the panel opens on a local tab
   * (Loaded / On disk / Installed), and making those wait on a network round-trip meant
   * a slow or blocked GitHub left the user staring at "Loading…" for information that
   * was available instantly. Only `busy` describes the fetch, and the panel now shows
   * local rows while it is set.
   */
  async function loadRegistryData(kind) {
    const remote = await import('./remote.js');
    const b = state.registryBrowser;
    if (!b) return;

    // 1. Local data: no network, no await. Available immediately.
    if (kind === 'skills') {
      b.data = {
        installed: listSkills().map((s) => ({ name: s.name, description: s.description })),
        remote: b.data?.remote || [],
        remoteError: '',
      };
    } else {
      const { pluginLoaded } = await import('./plugin.js');
      b.data = {
        loaded: pluginLoaded.map((p) => ({ name: p.name, version: p.version, id: p.id })),
        onDisk: remote.listLocalPlugins(),
        remote: b.data?.remote || [],
        remoteError: '',
      };
    }
    b.busy = 'Fetching the repo list…';
    renderFrame();

    // 2. Remote data, best-effort. A failure is recorded per-half so each tab can say
    //    something true about itself.
    try {
      const listed = kind === 'skills'
        ? await remote.listRemoteSkillsDetailed()
        : await remote.listRemotePlugins();
      b.data.remote = listed.ok ? listed.items : [];
      b.data.remoteError = listed.ok ? '' : listed.error;
    } catch (e) {
      b.data.remote = [];
      b.data.remoteError = String((e && e.message) || e);
    }
    b.busy = null;
    renderFrame();
  }

  async function openRegistryBrowser(kind) {
    state.registryBrowser = {
      kind,
      tab: kind === 'skills' ? 'installed' : 'loaded',
      selectedIndex: 0,
      data: null,
      busy: null,
      flash: '',
    };
    // Close the other overlays so only one thing owns the screen.
    state.picker = null; state.form = null; state.panel = null;
    state.menuOpen = false; state.menuList = []; state.menuSel = 0;
    renderFrame();
    await loadRegistryData(kind);
  }

  function closeRegistryBrowser() {
    state.registryBrowser = null;
    state.hoverHit = null;
    renderFrame();
  }

  /** Run the selected row's action, then reload so the list reflects reality. */
  async function registryAct() {
    const b = state.registryBrowser;
    if (!b || !b.data) return;
    const { rowsForTab } = await import('./registry-browser.js');
    const remote = await import('./remote.js');
    const rows = rowsForTab(b, b.tab);
    const row = rows[Math.min(b.selectedIndex || 0, Math.max(0, rows.length - 1))];
    if (!row || row.disabled || row.action === 'none') return;
    const name = row.name;
    b.busy = row.action.startsWith('install') ? `Installing ${name}…` : `Removing ${name}…`;
    renderFrame();
    try {
      if (row.action === 'install-skill' || row.action === 'reinstall-skill') {
        const r = await remote.installRemoteSkill(name);
        b.flash = r.ok ? `Skill ${r.replaced ? 'updated' : 'installed'}: ${r.name}` : `Install failed: ${r.error}`;
      } else if (row.action === 'remove-skill') {
        const ok = remote.removeLocalSkill(name);
        b.flash = ok ? `Skill removed: ${name}` : `Could not remove ${name}`;
      } else if (row.action === 'install-plugin' || row.action === 'reinstall-plugin') {
        const r = await remote.installRemotePlugin(name);
        b.flash = r.ok ? `Plugin ${r.replaced ? 'updated' : 'installed'}: ${r.name} — restart hncode to load it` : `Install failed: ${r.error}`;
      } else if (row.action === 'remove-plugin') {
        const ok = remote.removeLocalPlugin(name);
        b.flash = ok ? `Plugin removed: ${name} — restart hncode to unload it` : `Could not remove ${name}`;
      }
    } catch (e) {
      b.flash = `Failed: ${String((e && e.message) || e)}`;
    }
    b.busy = null;
    await loadRegistryData(b.kind);
  }

  // Key handling for the /files tree. A full-screen takeover: it owns every key while open.
  //
  // Arrows navigate and →/← open and close, which is the shape everyone already knows from
  // a file manager. Enter INSERTS the path into the composer rather than opening the file:
  // the point of browsing here is to bring a path into the conversation, and opening an
  // external editor would take the user out of hncode mid-turn.
  function handleFileTreeKey(t) {
    const ctx = state.fileTree;
    if (!ctx) return false;
    const rows = ctx._rows || visibleRows(ctx.root, ctx.expanded);
    const count = rows.length;

    if (t.key === 'escape' || t.key === 'c-c') {
      state.fileTree = null;
      state.hoverHit = null;
      renderFrame();
      return true;
    }
    if (t.key === 'up' || t.key === 'c-p') { ctx.sel = moveSel(ctx.sel, -1, count); renderFrame(); return true; }
    if (t.key === 'down' || t.key === 'c-n') { ctx.sel = moveSel(ctx.sel, 1, count); renderFrame(); return true; }
    if (t.key === 'home') { ctx.sel = 0; renderFrame(); return true; }
    if (t.key === 'end') { ctx.sel = Math.max(0, count - 1); renderFrame(); return true; }
    if (t.key === 'pgup') { ctx.sel = moveSel(ctx.sel, -10, count); renderFrame(); return true; }
    if (t.key === 'pgdn') { ctx.sel = moveSel(ctx.sel, 10, count); renderFrame(); return true; }

    const cur = rows[ctx.sel];
    if (t.key === 'right' || t.key === 'l') {
      // Open the selected directory. A FILE is left alone: there is nothing under it, and
      // silently doing nothing is better than a message the user did not ask for.
      if (cur && cur.node.dir && !ctx.expanded.has(cur.node.rel)) {
        ctx.expanded.add(cur.node.rel);
        renderFrame();
      }
      return true;
    }
    if (t.key === 'left' || t.key === 'h') {
      if (cur && cur.node.dir && ctx.expanded.has(cur.node.rel)) {
        ctx.expanded.delete(cur.node.rel);
        renderFrame();
        return true;
      }
      // On a closed directory (or a file), go UP to the parent: the usual tree behaviour,
      // and the only way to reach a sibling of a deep node without many keypresses.
      if (cur && cur.node.rel.includes('/')) {
        const parentRel = cur.node.rel.slice(0, cur.node.rel.lastIndexOf('/'));
        const at = rows.findIndex((r) => r.node.rel === parentRel);
        if (at >= 0) { ctx.sel = at; renderFrame(); return true; }
      }
      return true;
    }
    if (t.key === 'c-o') {
      // Expand/collapse the whole tree, so a big repo can be surveyed at once.
      const dirs = allDirs(ctx.root);
      const allOpen = dirs.length > 0 && dirs.every((d) => ctx.expanded.has(d));
      ctx.expanded = allOpen ? new Set() : new Set(dirs);
      renderFrame();
      return true;
    }
    if (t.key === 'enter') {
      if (!cur) return true;
      const rel = cur.node.rel;
      // The INSERTED form is relative with forward slashes: that is what the tools accept
      // on every platform, and an absolute Windows path in a prompt is noise. Same append
      // the /search picker does, so both "bring a file into the composer" paths agree.
      state.input = (state.input || '') + rel;
      state.caret = state.input.length;
      state.fileTree = null;
      refreshMenu(state);
      renderFrame();
      notice(`Inserted ${rel}`, 'info');
      return true;
    }
    if (t.key === 'tab') return true;   // swallow: a tree has no tabs to switch
    // Anything else that is a printable character is ignored rather than typed into a
    // hidden composer — the overlay owns the screen, so a stray keystroke must not
    // silently edit text the user cannot see.
    if (t && t.ch) return true;
    return false;
  }

  function handleRegistryRowKey(t) {
    if (!b) return false;

    // MOUSE first: the browser is a full-screen takeover, so it gets the same
    // click/hover treatment as the tasks browser. It registers its own hitboxes
    // (`_regHits`, frame rows) and the conversion from the 1-based screen row
    // happens here, once.
    if (t.key === 'mousedown' || t.key === 'mousehover') {
      // Record the pointer BEFORE anything else, exactly like handleMouse does.
      // `resolveHoverHit` (used by takeoverFrame to tint) works off `_lastMouse`,
      // so without this the highlight was resolved from a stale/no position and
      // never appeared — clickable rows with no hover.
      state._lastMouse = t;
      const hits = b._regHits || [];
      const row = (t.row || 1) - 1;
      const col = (t.col || 1) - 1;
      let hit = null;
      for (let i = hits.length - 1; i >= 0; i--) {
        const hb = hits[i];
        if (hb.row === row && col >= hb.col0 && col <= hb.col1) { hit = hb; break; }
      }
      if (t.key === 'mousehover') {
        // The tint itself is applied by takeoverFrame from `_lastMouse`; here we
        // only keep the row marker in sync and repaint.
        b.hoverIndex = hit && hit.kind === 'regRow' ? hit.index : null;
        renderFrame();
        return true;
      }
      if (!hit) return true;                       // click on empty space: consume it
      if (hit.kind === 'regTab') {
        b.tab = hit.tab;
        b.selectedIndex = 0;
        renderFrame();
        return true;
      }
      if (hit.kind === 'regRow') {
        // First click selects; clicking the ALREADY-selected row performs its
        // action (the same thing Enter does), so install/remove is reachable by
        // mouse without a separate button.
        if (b.selectedIndex === hit.index) {
          const action = handleRegistryBrowserKey(b, { key: 'enter' });
          if (action === 'install' || action === 'remove') { void registryAct(); return true; }
        }
        b.selectedIndex = hit.index;   // the index came from the rendered row list
        renderFrame();
        return true;
      }
      return true;
    }

    const action = handleRegistryBrowserKey(b, t);
    if (action === 'close') { closeRegistryBrowser(); return true; }
    if (action === 'install' || action === 'remove') { void registryAct(); return true; }
    if (action === 'reload') { void loadRegistryData(b.kind); return true; }
    renderFrame();
    return true;
  }

  function openTaskOutputViewer(taskId) {
    const ctxLike = state.agent && state.agent.ctx ? state.agent.ctx : { tasks: state.tasks };
    const task = getTask(ctxLike, taskId) || (state.tasks || {})[taskId];
    if (!task) { tasksFlash('No such task: ' + taskId); return; }
    state.tasksViewer = makeViewerState(task);
    renderFrame();
  }

  function closeTaskOutputViewer() {
    state.tasksViewer = null;
    state.hoverHit = null;
    renderFrame();
  }

  // Map a mouse token onto the tasks browser's own hitboxes. The browser works in
  // FRAME cells (row 0 = header), the mouse reports 1-based screen cells, so the
  // conversion happens here once instead of in every branch below.
  function taskPanelHit(p, t) {
    const hits = p._taskHits || [];
    const row = (t.row || 1) - 1;
    const col = (t.col || 1) - 1;
    for (let i = hits.length - 1; i >= 0; i--) {
      const hb = hits[i];
      if (hb.row === row && col >= hb.col0 && col <= hb.col1) return hb;
    }
    return null;
  }

  // Returns true when the key was consumed by the panel / viewer.
  function handleTasksPanelKey(t) {
    const p = state.tasksPanel;
    if (!p) return false;
    const ctxLike = state.agent && state.agent.ctx ? state.agent.ctx : { tasks: state.tasks };
    // MOUSE first: the browser is a full-screen takeover, so a click on a row selects
    // it (and a second click opens its output), a click on a footer word runs that
    // word's action, and moving over either highlights it.
    if (t.key === 'mousehover' || t.key === 'mousedown') {
      const hit = taskPanelHit(p, t);
      if (t.key === 'mousehover') {
        const next = hit ? { row: hit.row, col0: hit.col0, col1: hit.col1 } : null;
        const prev = state.hoverHit;
        const changed = (!!next !== !!prev)
          || (next && prev && (next.row !== prev.row || next.col0 !== prev.col0 || next.col1 !== prev.col1));
        if (changed) { state.hoverHit = next; renderFrame(); }
        // Keep the list row under the pointer highlighted too, so the tint and the
        // per-row marker agree.
        p.hoverIndex = hit && hit.kind === 'taskRow' ? hit.index : null;
        return true;
      }
      if (!hit) return true;                       // a click on empty space: consume it
      if (hit.kind === 'taskRow') {
        p.selectedIndex = hit.index;
        renderFrame();
        return true;
      }
      if (hit.kind === 'taskFooter') {
        // Re-dispatch the click as the KEY that word advertises, so a click and a
        // keypress go through exactly the same path.
        const asKey = { select: null, output: 'enter', stop: 's', refresh: 'r', filter: 'tab', close: 'escape' }[hit.action];
        if (hit.action === 'confirmStop') return handleTasksPanelKey({ ch: 'y' });
        if (hit.action === 'cancelStop') return handleTasksPanelKey({ key: 'escape' });
        if (hit.action === null || asKey == null) return true;
        if (asKey === 'enter') return handleTasksPanelKey({ key: 'enter' });
        if (asKey === 'tab') return handleTasksPanelKey({ key: 'tab' });
        if (asKey === 'escape') return handleTasksPanelKey({ key: 'escape' });
        return handleTasksPanelKey({ ch: asKey });
      }
      return true;
    }
    // Snapshot the STOP target BEFORE the key handler clears pendingStop on 'y'.
    const stopTarget = p.pendingStop;
    const action = handleTasksBrowserKey(p, t);
    p.tasks = sortedTasks(ctxLike);
    const vis = visibleTasks(p.tasks, p.filter);
    const sel = vis[p.selectedIndex];

    switch (action) {
      case 'close': closeTasksPanel(); return true;
      case 'toggleFilter':
        p.filter = p.filter === 'all' ? 'active' : 'all';
        p.selectedIndex = 0;
        break;
      case 'refresh':
        p.tasks = sortedTasks(ctxLike);
        tasksFlash('Refreshed');
        break;
      case 'stopIgnored':
        tasksFlash((sel ? sel.taskId : '') + ' is already terminal - nothing to stop.');
        break;
      case 'requestStop':
        // Nothing to do yet: the footer now asks for Y to confirm.
        break;
      case 'cancelStop':
        tasksFlash('Stop cancelled');
        break;
      case 'confirmStop': {
        // 'y' was pressed: stop the task that was pending.
        stopTask(ctxLike, stopTarget);
        p.tasks = sortedTasks(ctxLike);
        break;
      }
      case 'openOutput':
        if (sel) openTaskOutputViewer(sel.taskId);
        return true;
      default:
        break;
    }
    renderFrame();
    return true;
  }

  // Kill / abort one task by id. An agent task aborts through its controller; a
  // process is killed as a tree (Windows) or by signal.
  function stopTask(ctxLike, id) {
    if (!id) return;
    const tk = getTask(ctxLike, id) || (state.tasks || {})[id];
    if (!tk || tk.status !== 'running') return;
    try {
      if (tk.kind === 'agent' && typeof tk._abort === 'function') {
        tk._abort();
      } else if (tk.pid) {
        if (process.platform === 'win32') {
          try { cp.spawnSync('taskkill', ['/pid', String(tk.pid), '/t', '/f'], { stdio: 'ignore' }); } catch {}
        } else {
          try { process.kill(tk.pid, 'SIGTERM'); } catch {}
        }
      }
    } catch {}
    settleTask(tk, 'killed', { stopReason: 'User initiated stop' });
    tasksFlash('Stopped ' + id);
  }

  function handleTasksViewerKey(t) {
    const v = state.tasksViewer;
    if (!v) return false;
    // Refresh from the live store so a running task's tail keeps moving.
    const ctxLike = state.agent && state.agent.ctx ? state.agent.ctx : { tasks: state.tasks };
    const fresh = getTask(ctxLike, v.task.taskId);
    if (fresh) v.task = fresh;
    const action = handleViewerKey(v, t, dims().rows);
    if (action === 'close') closeTaskOutputViewer();
    else renderFrame();
    return true;
  }

  if (!stdin.isTTY) {
    return 1;
  }
  let wasRaw = false;
  try { stdin.setRawMode(true); wasRaw = true; } catch { wasRaw = false; }
  stdin.resume();
  stdin.setEncoding('utf8');

  // ASK THE TERMINAL before writing anything it might not understand. Three things
  // below depend on the answer — the synchronized-output wrapper, the Kitty keyboard
  // protocol, and which theme is readable — and until now all three were guesses (see
  // src/term-caps.js). This must run BEFORE the first paint so a light-background
  // terminal never flashes a frame in the dark theme, and it owns stdin while it runs
  // because a query REPLY arrives on the same stream as keystrokes.
  const probe = await probeTerminal({ stdin, stdout });
  const caps = terminalCaps();
  if (caps.bg) state.termBg = caps.bg;
  // Tell the palette resolver which way the terminal goes. `auto` needs this and nothing
  // else: on a light background it becomes the light theme, otherwise the dark one. The
  // answer is handed in because colors.js is a leaf module with no probe of its own.
  const lightBg = isLightBg(caps.bg);
  setLightBackground(lightBg);
  state.lightBg = lightBg;
  // An EXPLICIT theme wins over the probe: a user who named one has told us. `auto` is the
  // default and asks the probe, which is how the setting named "follow the terminal" ends
  // up following it — the old code special-cased a light background here instead, so the
  // setting and the code disagreed about what auto meant.
  const configuredTheme = (cfg.raw && cfg.raw.theme) || 'auto';
  state.theme = hasTheme(configuredTheme) ? configuredTheme : 'auto';
  setTheme(state.theme);

  // ONLY NOW may the alternate screen be entered. Everything above is a query whose reply
  // arrives on stdin, and the probe owns stdin while it waits — entering the alternate
  // screen first would paint a frame in the wrong palette before the answer came back, which
  // is the flash this ordering exists to prevent.
  stdout.write(alternateScreen(true));
  stdout.write(clearScreen());
  // Kitty keyboard protocol. Great when supported (finer key reporting), but a
  // terminal that does not implement `>1u` reacts badly to it (dropped/mangled
  // input) — so it is enabled only when the probe heard the terminal speak it.
  // `caps.kitty === null` (nothing answered) keeps the old default of ON, so a
  // terminal that simply says nothing is treated exactly as before.
  if (process.env.HNCODE_NO_KITTY_KEYS !== '1' && kittyKeysUsable()) stdout.write('\x1b[>1u');
  // Mouse modes, split so that an UNSUPPORTED one cannot take the others down:
  // a terminal that rejects `?1003h` (any-motion — the least widely supported)
  // would, in a single write, often drop click/drag too. Bracket-paste + SGR +
  // click/drag/sgr go first (universally supported); any-motion (hover) last,
  // and skippable via HNCODE_NO_MOUSE_HOVER=1 when a terminal chokes on it.
  stdout.write('\x1b[?2004h\x1b[?1000h\x1b[?1002h\x1b[?1006h');
  if (process.env.HNCODE_NO_MOUSE_HOVER !== '1') stdout.write('\x1b[?1003h');
  // Start the PowerShell clipboard helper now: its cold start is seconds long,
  // and doing it lazily on the first Ctrl+Shift+V made the shortcut look dead.
  // Deferred by one turn of the event loop, though: `spawn` costs ~950ms here (the
  // OS creating the process; measured, not our code), and running it inline held the
  // FIRST paint back by that much. One turn is early enough — the shell needs ~2s to
  // warm anyway, and the handler that could paste is not live until after this tick.
  setTimeout(warmClipboard, 0);
  setTip(state);
  // Fill the git badge — asynchronously, AFTER the first paint. It used to run
  // before renderFrame() with a blocking spawnSync git, which added ~330ms to
  // startup; now the frame draws at once and the badge appears when git answers.
  refreshGitInfo(state, { force: true });
  renderFrame();

  // MCP: connect in the BACKGROUND, now that the UI is on screen. Each server
  // gets up to CONNECT_TIMEOUT_MS, so doing this before the first paint would
  // stall the whole TUI; instead we start it and report the outcome as a notice
  // ("MCP: connected to …") when it lands. Tools registered here become visible
  // to the model on its next turn.
  if (typeof opts.mcpConnect === 'function') {
    Promise.resolve()
      .then(() => opts.mcpConnect())
      .then((res) => {
        const servers = (res && res.servers) || [];
        if (!servers.length) return;
        // The notice line is a SINGLE status-line row, so report all servers in
        // one message — looping notice() per server only left the last one
        // visible. Failures are listed too, and the whole notice turns red when
        // any server failed.
        const okServers = servers.filter((s) => s.ok);
        const bad = servers.filter((s) => !s.ok);
        const parts = [];
        if (okServers.length) {
          const tools = okServers.reduce((n, s) => n + (s.toolCount || 0), 0);
          const names = okServers.map((s) => s.name).join(', ');
          parts.push(`MCP connected: ${names} (${tools} tool${tools === 1 ? '' : 's'})`);
        }
        if (bad.length) {
          parts.push(`MCP failed: ${bad.map((s) => s.name).join(', ')}`);
        }
        notice(parts.join(' · '), bad.length ? 'error' : 'info');
        // A connecting server may have changed the tool list; repaint so any
        // tool-count readout is current.
        renderFrame();
      })
      .catch(() => { /* MCP must never break the session */ });
  }

  const tipTimer = setInterval(() => { setTip(state); renderFrame(); }, TIP_INTERVAL);
  // Git badge: a fixed 15s cadence. Deliberately NOT tied to the frame loop (that
  // spawned git per keystroke) and NOT run mid-turn (the agent is still writing;
  // the turn-end refresh picks up its edits). Repaints only when something
  // actually changed, so an idle session stays quiet.
  const gitTimer = setInterval(() => {
    if (state.running) return;
    const before = state._gitInfo && `${state._gitInfo.branch}|${state._gitInfo.insertions}|${state._gitInfo.deletions}`;
    refreshGitInfo(state, { force: true });
    const after = state._gitInfo && `${state._gitInfo.branch}|${state._gitInfo.insertions}|${state._gitInfo.deletions}`;
    if (before !== after) renderFrame();
  }, GIT_REFRESH_MS);
  // SCHEDULES (/schedule): checked every 30s, because a cron expression has minute
  // resolution and a slower tick could miss the minute entirely. Skipped while a turn
  // is running, so a due schedule queues its work rather than interrupting — safe
  // because the run record makes it fire once per due minute, not once per tick.
  //
  // The record lives in a side file (`schedule-state.json`) rather than in
  // config.toml: rewriting the user's whole configuration once a minute is both
  // risky and wrong in kind — a run record is state, not configuration.
  let lastScheduleCheck = '';
  const scheduleTimer = setInterval(() => {
    if (state.running) return;
    const configFile = hncodeConfigFile();
    let history;
    try { history = readScheduleHistory(configFile); } catch { return; }
    let due;
    try { due = dueWithHistory(cfg.schedule, history); } catch { return; }
    if (!due.length) return;
    lastScheduleCheck = due[0].minuteKey;
    history = { ...history };
    for (const d of due) history[d.id] = d.minuteKey;
    writeScheduleHistory(configFile, history);
    for (const d of due) {
      notice(`Schedule "${d.id}" is due — queuing its prompt.`, 'info');
      try { sendPrompt(d.prompt, { fromSchedule: d.id }); }
      catch (e) { appErr(`Schedule "${d.id}" could not queue its prompt: ${e.message}`); }
    }
  }, 30 * 1000);
  void lastScheduleCheck;
  const spinTimer = setInterval(() => {
    if (!state.running) return;
    // Monotonic tick counter — do NOT wrap it at SPINNER.length, or the
    // Working-colour cycle (which counts up to ~48 ticks) can never reach its
    // red phase. The SPINNER frame is derived with `% SPINNER.length` at the
    // call site instead.
    state.spin = (state.spin || 0) + 1;
    renderFrame();
  }, 80);

  // Paced reveal tick. The 80ms spinner tick above is too coarse for this: at 12.5
  // frames a second a burst drips out in visible steps of ~48 characters, which is
  // exactly the stair-step the buffer exists to remove. ~16ms gives the same visual
  // rate the controller caps at, and the tick is a no-op when nothing is buffered, so
  // an idle session pays nothing for it.
  //
  // It runs whenever the buffer holds text, NOT only while `state.running`: the tail of
  // a reply can still be draining as the turn ends, and that text must reach the screen
  // rather than waiting for the next turn to start.
  const STREAM_TICK_MS = 16;
  const streamTimer = setInterval(() => {
    if (streamBuf.isEmpty) return;
    if (drainStream()) renderSoon();
  }, STREAM_TICK_MS);
  if (streamTimer.unref) streamTimer.unref();

  const TOK_WINDOW_MS = 1000;
  const tokTimer = setInterval(() => {
    const times = state._tokTimes;
    if (!times || !times.length) {
      if (state.tokRate !== 0) { state.tokRate = 0; renderFrame(); }
      return;
    }
    const cutoff = Date.now() - TOK_WINDOW_MS;
    let drop = 0;
    while (drop < times.length && times[drop] < cutoff) drop++;
    if (drop) times.splice(0, drop);
    const rate = times.length;
    if (rate !== state.tokRate) { state.tokRate = rate; renderFrame(); }
  }, 50);

  // ---- auto-update (background + SILENT, never blocks the TUI) --------------
  // If autoUpdate is on, check npm at startup and then every 30 minutes. The
  // check and the install both run detached, and NOTHING is ever printed: the
  // whole point is that the user never notices. Version notices appear only for
  // the explicit /update command (see its dispatch case).
  let autoCheckTimer = null;
  let autoCheckInflight = false;
  const runAutoCheck = async () => {
    if (!cfg.autoUpdate || autoCheckInflight) return;
    autoCheckInflight = true;
    try { await upd.checkAndUpdate(); } catch { /* silent */ }
    finally { autoCheckInflight = false; }
  };
  if (cfg.autoUpdate) {
    setTimeout(() => { void runAutoCheck(); }, 800);
    autoCheckTimer = setInterval(() => { void runAutoCheck(); }, upd.AUTO_UPDATE_INTERVAL_MS);
    if (autoCheckTimer.unref) autoCheckTimer.unref();
  }


  // Keys typed while the capability probe owned stdin were handed back rather than
  // dropped, so the composer starts with them instead of losing them.
  let keyBuf = probe.rest || '';
  let escTimer = null;
  let escRetries = 0;
  let confirmTimer = null;
  const flushEsc = () => {
    escTimer = null;
    escRetries++;
    const { tokens, rest } = tokenize(keyBuf);
    keyBuf = rest;
    for (const t of tokens) handleKey(t);
    if (keyBuf) {
      if (escRetries > 4) {
        handleKey({ key: 'escape' });
        keyBuf = '';
        escRetries = 0;
      } else {
        escTimer = setTimeout(flushEsc, 40);
      }
    } else {
      escRetries = 0;
    }
  };

  // A terminal that did not answer the capability probe in time may still answer
  // AFTERWARDS, and those bytes arrive on this same stream — the key parser would type
  // them into the composer as garbage. Only possible when the probe never saw its DA1
  // sentinel (so something was still outstanding), and only for a short window: the
  // replies are a single burst, ~1ms after the queries.
  const replyFilterUntil = probe.complete ? 0 : Date.now() + 2000;

  stdin.on('data', (chunk) => {
    // `HNCODE_TRACE_KEYS` makes every inbound chunk and every key it produced visible in
    // ~/.hncode/keys.log. It exists because a keystroke that is silently swallowed looks
    // identical from the outside to one that was never delivered — the terminal may send
    // raw 0x03, a kitty CSI-u sequence, or nothing at all, and only the bytes say which.
    // Off unless the variable is set; nothing here runs in the normal path beyond the test.
    const traceKeys = process.env.HNCODE_TRACE_KEYS === '1';
    if (traceKeys) traceKey('chunk', chunk);
    if (Date.now() < replyFilterUntil) {
      chunk = stripProbeReplies(chunk);
      if (traceKeys) traceKey('after-probe-filter', chunk);
      if (!chunk) return;
    }
    keyBuf += chunk;
    escRetries = 0;
    if (escTimer) clearTimeout(escTimer);
    const { tokens, rest } = tokenize(keyBuf);
    keyBuf = rest;
    for (const t of tokens) {
      if (traceKeys) traceKey('key', t);
      handleKey(t);
    }
    if (keyBuf) {
      escTimer = setTimeout(flushEsc, 40);
    }
  });

  // Keys the probe handed back are dispatched HERE. The handler above only runs on a
  // NEW data event, so bytes seeded into `keyBuf` would otherwise sit there unparsed
  // until the user pressed another key. Deferred by a turn of the event loop: this
  // point is still in the middle of `startTUI`'s synchronous setup, and `handleKey`
  // touches state that is not finished being built yet.
  if (keyBuf) {
    setImmediate(() => {
      if (!keyBuf) return;
      const { tokens, rest } = tokenize(keyBuf);
      keyBuf = rest;
      for (const t of tokens) handleKey(t);
    });
  }

  function mouseToCell(t) {
    const { cols } = dims();
    const col = Math.max(0, Math.min(cols - 1, (t.col || 1) - 1));
    const screenRow = (t.row || 1) - 1;
    // Translate the SCREEN row into a row WITHIN the body, using the body's own
    // origin on screen. `state._bodyTop` is a TRANSCRIPT row number (negative
    // while the transcript is shorter than the viewport); the screen row is
    // absolute. Treating one as the other offset every hit by the rows sitting
    // above the transcript — a short session has `topPad` of them — so a drag
    // selected the wrong lines and copied text from elsewhere, or nothing.
    // `_bodyScreenTop === null` means the TRANSCRIPT BODY IS NOT ON SCREEN this
    // frame — an overlay (panel / form / picker / editor) replaced it, and
    // composeFrame clears the field so that only the body branch sets it. `_bodyTop`
    // is then a leftover from the previous frame, so mapping through it turns a drag
    // over the panel into a selection of transcript rows the user cannot see: the
    // highlight is applied to the (undrawn) chat, so NOTHING looks selected, and
    // Ctrl+Shift+C copies those hidden lines. Report "no transcript cell" instead.
    if (state._bodyScreenTop == null) {
      return { col, screenRow, rowInBody: -1, lineIdx: -1, row: -1 };
    }
    const screenTop = state._bodyScreenTop;
    const rowInBody = screenRow - screenTop;
    const lineIdx = (state._bodyTop != null ? state._bodyTop : 0) + rowInBody;
    // A row outside the body (the padding above it, or the chrome below) maps to
    // no transcript line; report -1 so callers ignore it rather than clamping to
    // line 0, the start of the session.
    const idx = (rowInBody < 0 || lineIdx < 0) ? -1 : lineIdx;
    // `row` is the canonical field the selection model uses (the same name the
    // head carries). Without it `anchor.row` was undefined and the paint loop
    // highlighted the whole transcript (see the selection range test).
    return { col, screenRow, rowInBody, lineIdx: idx, row: idx };
  }
  function isOnScrollbar(t) {
    if (!state._sb) return false;
    const { cols } = dims();
    return (t.col || 1) === cols;
  }
  // Drag the thumb. `rowF` may be fractional (the pointer reports sub-cell
  // resolution), and `grabOffset` remembers where inside the thumb the press
  // landed so the thumb does not jump under the cursor on the first move.
  function scrollFromThumb(rowF) {
    const sb = state._sb;
    if (!sb) return;
    // `sb` is the scrollbar geometry of the frame currently on screen, so it is only
    // correct because `handleMouse` settles any pending paint before dispatching
    // (see flushFrame). Read it here, change the scroll, and paint immediately — the
    // next drag move then works from the frame this one produced.
    state.scroll = scrollFromThumbPos(sb, rowF, state.sbDragOffset || 0);
    dropScrollPin(state);   // deliberate move: reseed the anchor on the next paint
    renderFrame();
  }
  // Advance the AskUserQuestion dialog after a question is answered: next question,
  // or the trailing "Other" tab when it was the last one. Module-level so BOTH the
  // keyboard path (handleKey) and the click path (dispatchHit's questionItem case)
  // advance identically — duplicated logic here would drift.
  function advanceQuestion(qs) {
    const total = qs.items.length;
    if (qs.index < total - 1) {
      qs.index++;
      qs.sel = 0;
      qs.picked = new Set();
      return;
    }
    qs.index = total;   // the Other tab
    qs.editing = 'supplement';
    qs.editingText = qs.supplement || '';
    qs.editingCaret = qs.editingText.length;
  }
  function hitAt(t) {
    const hbs = state._hitboxes || [];
    const row = (t.row || 1) - 1;
    const col = (t.col || 1) - 1;
    for (let i = hbs.length - 1; i >= 0; i--) {
      const hb = hbs[i];
      if (hb.row === row && col >= hb.col0 && col <= hb.col1) return hb;
    }
    return null;
  }

  // Close whatever OVERLAY is up, honouring its cancel callback. Shared by the
  // click-outside path and Ctrl+C so the two cannot drift apart (Esc has its own
  // per-overlay handling that also restores a draft in some cases).
  // `hoverHit` is dropped too: it is a SCREEN row, and the overlay's rows are about
  // to be replaced by the transcript. Keeping it left whatever now occupies that row
  // tinted — the highlight visibly stuck to unrelated text until the pointer moved.
  function dismissOverlay() {
    state.hoverHit = null;
    if (state.picker) {
      const cb = state.picker.onCancel;
      state.picker = null;
      state.pickerQuery = '';
      state.pickerCategory = null;
      if (cb) cb();
      return true;
    }
    if (state.form) { state.form = null; return true; }
    if (state.panel) { state.panel = null; return true; }
    if (state.editor) { state.editor = null; return true; }
    return false;
  }
  // Run a command from a STATUS-LINE CLICK. The command opens a picker, and
  // openPicker clears the composer (correct when the user TYPED the command; wrong
  // when they clicked a status widget and never touched their draft). Snapshot the
  // composer, dispatch, and restore it once the picker has opened.
  function dispatchFromStatusBar(cmd) {
    const savedInput = state.input || '';
    const savedCaret = state.caret || 0;
    Promise.resolve(dispatch(cmd, '', state, cfg, session, host, submit, stdout))
      .catch(() => {})
      .then(() => {
        // Only restore when the picker is the thing now open and it did not itself
        // seed the composer (a command may legitimately write to state.input).
        if (state.picker && !(state.input || '')) {
          state.input = savedInput;
          state.caret = Math.min(savedCaret, savedInput.length);
        }
        renderFrame();
      });
    renderFrame();
  }
  function dispatchHit(hb) {
    if (!hb) return false;
    // A hitbox is a row RANGE, so its geometry is only meaningful once the frame that
    // produced it is on screen — `handleMouse` settles any pending paint before it gets
    // here, which is what makes that true. Left explicit rather than implicit, because
    // a future call site that dispatches a hit directly would otherwise act on a row
    // the user never saw.
    if (hb.row !== undefined) flushFrame();
    switch (hb.kind) {
      case 'mentionItem': {
        // Mirror menuItem: clicking an @candidate selects AND accepts it. The
        // case was simply missing, so a click fell through to `default: false`
        // and did nothing at all.
        state.mentionSel = hb.index;
        acceptMention();
        return true;
      }
      case 'menuItem': {
        state.menuSel = hb.index;
        const cmd = state.menuList[hb.index];
        if (cmd) {
          // A second-level ARGUMENT word is not a command: clicking it completes it
          // into the composer. Dispatching it as a command (the old unconditional
          // behaviour) would have run `/on` and reported "unknown command".
          if (cmd._argWord) {
            acceptMenuSelection(state);
            refreshMenu(state);
            renderFrame();
            return true;
          }
          state.menuOpen = false; state.menuList = []; state.menuSel = 0; state.menuOffset = 0;
          state.input = ''; state.caret = 0;
          dispatch(cmd.name, '', state, cfg, session, host, submit, stdout);
          if (state._quit) { quit(); return true; }
          renderFrame();
        }
        return true;
      }
      case 'statusMode': {
        // Click the permission-mode group in the status line -> /permission (the
        // mode SELECTOR). It was dispatching /permissions (plural, the allow/ask/
        // deny RULES panel) — the wrong command, which opened the rules list and
        // (before that was fixed) crashed on an undefined openPanel.
        // The command opens a picker, and openPicker CLEARS the composer (right for
        // a typed command, wrong for a status-bar CLICK — the user never touched the
        // draft). Snapshot and restore it around the dispatch.
        dispatchFromStatusBar('permission');
        return true;
      }
      case 'statusModel': {
        // Click the model name in the status line -> /model (see statusMode).
        dispatchFromStatusBar('model');
        return true;
      }
      case 'composerRow': {
        const { cols } = dims();
        const insideW = Math.max(0, cols - 2);
        const layout = composerLayout(state, insideW - 3);
        const t = state._lastMouse;
        const clickCol = t ? (t.col || 1) - 1 : 1;
        const colInContent = Math.max(0, clickCol - 1);
        const idx = composerTextIndexAt(layout, hb.rowIdx, colInContent);
        state.caret = idx;
        // Store mousedown position for potential drag selection in the composer.
        state._composerMouseDown = { row: hb.rowIdx, col: idx, caret: idx };
        state.composerSel = null;
        renderFrame();
        return true;
      }
      case 'editor': {
        if (!state.editor) return false;
        const ed = state.editor;
        const ls = ed.text.split('\n');
        // `line` is the text-line index (see the addHit above); `row` would have
        // been mangled by the frame's topPad/topTrim correction.
        ed.caretRow = Math.max(0, Math.min(ls.length - 1, hb.line));
        // Put the caret at the clicked COLUMN, converting the terminal's VISUAL
        // column into a string index (they differ on wide glyphs — CJK text made the
        // caret land to the RIGHT of the click).
        const t = state._lastMouse;
        const col = t ? Math.max(0, (t.col || 1) - 1) : 0;
        ed.caretCol = charIndexForVisualCol(ls[ed.caretRow] || '', col);
        renderFrame();
        return true;
      }
      case 'pickerItem': {
        if (!state.picker) return false;
        state.picker.sel = hb.index;
        if (state.picker.footerFor) {
          const it2 = pickerFiltered(state)[hb.index];
          state.picker.footer = state.picker.footerFor(it2, state.picker.footer);
        }
        const it = pickerFiltered(state)[hb.index];
        if (it) {
          const before = state.picker;
          const done = state.picker.onPick ? state.picker.onPick(it) : true;
          // A picker whose footer holds the second half of the decision (/model) stays
          // open on a CLICK so the mouse can also reach it. With no footer row to click
          // there is nothing left to do, so the pick closes as usual. A pick that opened
          // ANOTHER picker (the "Add model…" row) has already replaced `state.picker`,
          // and that new one is not the one asking to stay open.
          if (state.picker === before && state.picker.clickKeepsOpen && state.picker.footer) { renderFrame(); return true; }
          if (done && state.picker === before) { state.picker = null; state.pickerQuery = ''; state.pickerCategory = null; }
          renderFrame();
        }
        return true;
      }
      case 'pickerCategory': {
        // Click a category tab ("All" / a provider). Mirrors Tab: switch the active
        // category, reset selection and search so the list is not filtered by an
        // invisible stale query. Previously the tab row had no hitbox at all, so a
        // click did nothing and there was no hover.
        if (!state.picker) return false;
        state.pickerCategory = hb.label;
        state.picker.sel = 0;
        state.pickerQuery = '';
        renderFrame();
        return true;
      }
      case 'pickerFooterOpt': {
        if (!state.picker || !state.picker.footer) return false;
        state.picker.footer.focused = true;
        state.picker.footer.value = hb.option;
        // Only a picker that declares onFooterPick treats a click on an option as the
        // decision (and closes on it). Others, /presets among them, use the row as a
        // Tab/←→ selector whose value Enter applies, so a click must not close them.
        if (state.picker.onFooterPick) {
          const before = state.picker;
          if (state.picker.onFooterPick(hb.option) && state.picker === before) {
            state.picker = null; state.pickerQuery = ''; state.pickerCategory = null;
          }
        }
        renderFrame();
        return true;
      }
      case 'formField': {
        if (!state.form) return false;
        state.form.fieldIdx = hb.index;
        renderFrame();
        return true;
      }
      case 'formType': {
        if (!state.form) return false;
        const f = state.form;
        f.fieldIdx = (f.fields || []).length;
        f.type = hb.option;
        // A click on the Type is the LAST decision in this form, so it submits — the
        // same thing Enter does on the Type row. Without this the click only selected
        // the option and the user still had to reach for the keyboard, which is what
        // "点对应的 type 就算完成" was about.
        if (f.typeClickSubmits) {
          const values = {};
          for (const fl of f.fields || []) values[fl.key] = String(fl.value || '').trim();
          state.form = null;
          f.onSubmit(values, f.type);
          renderFrame();
          return true;
        }
        renderFrame();
        return true;
      }
      case 'pickerBody': {
        // A click inside the picker popup (title, hint, border, margins of an
        // item row): consume it so the mousedown does not reach the "click
        // outside an overlay closes it" path. Only a click OUTSIDE the box
        // dismisses the picker. Registered BEFORE the precise item/tab/footer
        // hits: hitAt iterates backward (last registered wins), so those still
        // win where they overlap.
        return true;
      }
      case 'panelBody': {
        // A click inside the info panel (h.openPanel): consume it so the mousedown
        // does not reach the "click outside an overlay closes it" path. The panel
        // itself has no per-row action, so absorbing is the whole behaviour.
        return true;
      }
      case 'questionItem': {
        // Click an option in the AskUserQuestion dialog. `hb.index` is the position
        // in [options..., Other] for the CURRENT question tab. Without this case the
        // click fell through to `default: return false` and did nothing — the only
        // way to answer was the keyboard, even though the rows were click targets.
        if (!state.question) return false;
        const qs = state.question;
        const total = qs.items.length;
        if (qs.index >= total) return true;            // on the "Other" tab: nothing to pick
        if (qs.editing) return true;                    // a text field owns the keys
        const cur = qs.items[qs.index] || { options: [] };
        const options = cur.options || [];
        const isOther = hb.index >= options.length;     // the trailing "Other" row
        qs.sel = hb.index;
        if (isOther) {
          // Mirror Enter/Space on the Other row: open its free-text editor.
          qs.editing = 'other';
          qs.editingText = qs.otherText || '';
          qs.editingCaret = qs.editingText.length;
          renderFrame();
          return true;
        }
        if (cur.multiSelect) {
          // Toggle, exactly like Space — do NOT advance; multi-select needs an
          // explicit Enter to confirm.
          if (qs.picked.has(hb.index)) qs.picked.delete(hb.index); else qs.picked.add(hb.index);
          renderFrame();
          return true;
        }
        // Single-select: choose and advance to the next question, like Enter.
        qs.answers[cur.question] = options[hb.index] && options[hb.index].label;
        advanceQuestion(qs);
        renderFrame();
        return true;
      }
      default:
        return false;
    }
  }
  function handleMouse(t) {
    state._lastMouse = t;
    // Every branch below maps the pointer through geometry `composeFrame` produced —
    // `hitAt` reads the hitbox list, `mouseToCell` reads `_bodyScreenTop`. A click can
    // land in the window between a state change and its `renderSoon()`, and the frame
    // that paint produces may be superseded by a resize or a re-entrant render, so the
    // row acted upon would be one the user never sees painted. Settling the pending
    // paint first makes the geometry the CURRENT frame's, which is what the user is
    // looking at. Costs one extra frame, and only when something is actually pending.
    flushFrame();
    if (t.key === 'mousedown') {
      const hb = hitAt(t);
      if (hb && dispatchHit(hb)) return;
    }
    if (state.picker || state.form || state.panel || state.editor) {
      if (t.key === 'wheelup' || t.key === 'wheeldown') handleKey(t);
      // Hover must still update, or a picker row never lights up: the early
      // return below left `state.hoverHit` stale while an overlay was open, so the
      // hover tint (applied in composeFrame) never reached the menu rows.
      if (t.key === 'mousehover') {
        const hb = hitAt(t);
        // Same exclusion as the normal path: the composer rows are click targets
        // (mousedown places the caret) but are never tinted — the prompt you are
        // typing must not light up.
        const next = (hb && hb.kind !== 'composerRow') ? { row: hb.row, col0: hb.col0, col1: hb.col1 } : null;
        const prev = state.hoverHit;
        const changed = (!!next !== !!prev)
          || (next && prev && (next.row !== prev.row || next.col0 !== prev.col0 || next.col1 !== prev.col1));
        if (changed) { state.hoverHit = next; renderFrame(); }
        return;
      }
      // Clicking OUTSIDE the overlay dismisses it, the way every menu behaves.
      // Without this the press was swallowed here (no hitbox matched, so
      // dispatchHit returned false) and the overlay stayed open — Esc was the only
      // way out, which is not what a right-click context menu implies.
      //
      // A RIGHT-CLICK outside the card is the one case that MOVES the overlay rather
      // than dismissing it: re-opening a context menu at the pointer is what a second
      // right-click is asking for, and this branch used to swallow it (`return` at the
      // bottom), so the menu appeared frozen — it neither moved nor closed. Only a
      // picker that came FROM a right-click has an anchor; anything else (a /model list,
      // a form) treats the press as a dismissal below.
      if (t.key === 'rightclick' && state.picker && state.picker.anchor) {
        openContextMenu(t);
        return;
      }
      if (t.key === 'mousedown' && !hitAt(t)) {
        dismissOverlay();
        renderFrame();
        return;
      }
      return;
    }
    if (t.key === 'mousedown') {
      if (isOnScrollbar(t)) {
        const sb = state._sb;
        const { rowInBody } = mouseToCell(t);
        state.sbDrag = true;
        // Grab INSIDE the thumb (so it does not jump under the pointer); off the
        // thumb, centre it on the pointer. Uses the FRACTIONAL length so the grab
        // point is not quantised to a whole row.
        const len = sb.thumbLenF != null ? sb.thumbLenF : sb.thumbLen;
        state.sbDragOffset = (rowInBody >= sb.thumbStart && rowInBody < sb.thumbStart + sb.thumbLen)
          ? rowInBody - sb.thumbStart : len / 2;
        scrollFromThumb(rowInBody);
        return;
      }
      // The todo panel's top rule is a resize handle: pressing it starts a drag,
      // and the panel height follows the pointer (clamped to 1..all todos). This
      // must come before the transcript-selection arming below, otherwise the
      // press would start a text selection instead.
      const hitTodo = hitAt(t);
      if (hitTodo && hitTodo.kind === 'todoResize') {
        state.todoResizeDrag = true;
        state.todoResizeStart = { row: t.row, rows: todoRowCount(state) };
        renderFrame();
        return;
      }
      // The queue panel's top rule is also a resize handle.
      const hitQueue = hitAt(t);
      if (hitQueue && hitQueue.kind === 'queueResize') {
        state.queueResizeDrag = true;
        state.queueResizeStart = { row: t.row, rows: queueRowCount(state) };
        renderFrame();
        return;
      }
      // Don't start selection on single click, wait for drag.
      const cell = mouseToCell(t);
      // Pressing the padding above the transcript must NOT arm a selection:
      // clamping the index to 0 (as this used to) made the anchor "line 0",
      // so a later drag highlighted from the start of the session.
      state._mouseDownPos = (cell.lineIdx < 0) ? null : { row: cell.lineIdx, col: cell.col };
      // NOTE: the existing selection is deliberately NOT cleared here. It used to
      // be, on the theory that "a press starts a new selection" — but a press that
      // is not followed by a drag is a CLICK, and cancelling the selection is the
      // click's job. Clearing on the press meant any stray mousedown (a right-click
      // the terminal reports as one, a stray click just before Ctrl+Shift+C)
      // destroyed the selection silently while the user was still looking at it.
      // Cancelling now happens on `mouseup`, once the gesture is known to be a
      // click; a real drag overwrites the selection on its first mousemove.
      state._selDragged = false;
      renderFrame();
      return;
    }
    if (t.key === 'mousehover') {
      const onBar = state._sb ? isOnScrollbar(t) : false;
      if (onBar !== state.sbHover) { state.sbHover = onBar; renderFrame(); }
      const hb = hitAt(t);
      // The todo resize handle gets its own hover flag so its rule lights up.
      const onTodoRule = !!(hb && hb.kind === 'todoResize');
      if (onTodoRule !== state.todoResizeHover) { state.todoResizeHover = onTodoRule; renderFrame(); }
      // The queue resize handle also gets a hover flag.
      const onQueueRule = !!(hb && hb.kind === 'queueResize');
      if (onQueueRule !== state.queueResizeHover) { state.queueResizeHover = onQueueRule; renderFrame(); }
      // The composer rows stay click targets (mousedown places the caret), but
      // they are NOT highlighted on hover — tinting the prompt you are typing
      // is noise, not feedback.
      const next = (hb && hb.kind !== 'composerRow') ? { row: hb.row, col0: hb.col0, col1: hb.col1 } : null;
      const prev = state.hoverHit;
      const changed = (!!next !== !!prev)
        || (next && prev && (next.row !== prev.row || next.col0 !== prev.col0 || next.col1 !== prev.col1));
      if (changed) { state.hoverHit = next; renderFrame(); }
      return;
    }
    if (t.key === 'mousemove') {
      if (state.sbDrag) { scrollFromThumb(mouseToCell(t).rowInBody); return; }
      // Dragging the todo rule resizes the panel: moving UP shows more rows.
      if (state.todoResizeDrag) {
        const start = state.todoResizeStart || { row: t.row, rows: todoRowCount(state) };
        const delta = start.row - (t.row || 1);          // up = positive = more rows
        const want = start.rows + delta;
        const total = (state.todos || []).length;
        const clamped = Math.max(1, Math.min(total || 1, want));
        if (clamped !== state.todoRows) { state.todoRows = clamped; renderFrame(); }
        return;
      }
      // Dragging the queue rule resizes the panel: moving UP shows more rows.
      if (state.queueResizeDrag) {
        const start = state.queueResizeStart || { row: t.row, rows: queueRowCount(state) };
        const delta = start.row - (t.row || 1);          // up = positive = more rows
        const want = start.rows + delta;
        const total = (state.queued || []).length;
        const clamped = Math.max(1, Math.min(total || 1, want));
        if (clamped !== state.queueRows) { state.queueRows = clamped; renderFrame(); }
        return;
      }
      // Composer text selection: drag from a composer mousedown.
      if (state._composerMouseDown) {
        const hb = hitAt(t);
        if (hb && hb.kind === 'composerRow') {
          const { cols } = dims();
          const insideW = Math.max(0, cols - 2);
          const layout = composerLayout(state, insideW - 3);
          const clickCol = (t.col || 1) - 1;
          const colInContent = Math.max(0, clickCol - 1);
          const idx = composerTextIndexAt(layout, hb.rowIdx, colInContent);
          state.caret = idx;
          state.composerSel = { anchor: state._composerMouseDown.caret, head: idx };
          renderFrame();
        }
        return;
      }
      // Start selection on drag from mousedown position
      if (state._mouseDownPos) {
        const { col, lineIdx } = mouseToCell(t);
        if (lineIdx < 0) return;   // above the first line: nothing to anchor to
        // The FIRST move of a drag starts a NEW selection anchored at the press
        // point, discarding whatever was selected before. It cannot be expressed as
        // `if (!state.selection)` any more: the press no longer clears the old
        // selection (see the mousedown branch), so that test would keep the OLD
        // anchor and extend from it — dragging over one line would highlight
        // everything back to the previous selection.
        if (!state._selDragged) {
          state._selDragged = true;
          state.selection = { anchor: state._mouseDownPos, head: { row: lineIdx, col } };
        } else {
          state.selection = { anchor: state.selection.anchor, head: { row: lineIdx, col } };
        }
        renderFrame();
        return;
      }
      return;
    }
    if (t.key === 'mouseup') {
      state._mouseDownPos = null;
      state._composerMouseDown = null;
      if (state.todoResizeDrag) {
        // Finish the resize. Keep the hover flag in sync with where the pointer is.
        state.todoResizeDrag = false;
        state.todoResizeStart = null;
        state.todoResizeHover = !!(hitAt(t) && hitAt(t).kind === 'todoResize');
        renderFrame();
        return;
      }
      if (state.queueResizeDrag) {
        // Finish the resize. Keep the hover flag in sync with where the pointer is.
        state.queueResizeDrag = false;
        state.queueResizeStart = null;
        state.queueResizeHover = !!(hitAt(t) && hitAt(t).kind === 'queueResize');
        renderFrame();
        return;
      }
      if (state.sbDrag) {
        state.sbDrag = false;
        state.sbHover = isOnScrollbar(t);
        renderFrame();
        return;
      }
      // A press that never turned into a drag is a CLICK, and a click cancels the
      // selection. This is the ONLY place that cancels it now (the mousedown branch
      // deliberately leaves it alone) — which is what keeps a stray press from
      // destroying a selection the user is still using.
      if (!state._selDragged) {
        state.selection = null;
      }
      renderFrame();
      return;
    }
    if (t.key === 'rightclick') {
      openContextMenu(t);
      return;
    }
  }
  // `allowHidden` is for an EXPLICIT action the user just asked for — the
  // right-click menu's Copy. That menu is a picker overlay, so the transcript is
  // not drawn while it is up and `_bodyScreenTop` is null; the guard below then
  // returned '' and Copy always answered "Nothing to copy", even with text plainly
  // selected. The guard exists to stop a drag/keystroke from silently copying rows
  // the user cannot see, which is not what picking "Copy" means.
  function selectionText(allowHidden = false) {
    const sel = state.selection;
    if (!sel || !sel.anchor || !sel.head) return '';
    // A selection only means something while the TRANSCRIPT is the thing on screen.
    // With an overlay open the body is not drawn, so the highlighted rows are not
    // the rows the user is looking at — copying would hand back text that was never
    // visible. `_bodyScreenTop` is null exactly then (composeFrame clears it every
    // frame and only the body branch sets it).
    if (!allowHidden && state._bodyScreenTop == null) return '';
    const { cols } = dims();
    // The FULL transcript, and that is correct here: `selection.row` is an ABSOLUTE
    // transcript row, not a screen row. mouseToCell() already converted it
    // (`_bodyTop + rowInBody`), and composeFrame's highlight indexes the windowed
    // array with the same absolute number — the windowed array keeps the transcript's
    // absolute length and fills off-screen slots with '', so index N is the same row
    // in both. Verified by printing drawn-vs-full side by side at several scrolls.
    const rawChat = renderChatLines(state, cols);
    const a = sel.anchor, h = sel.head;
    const start = (h.row < a.row || (h.row === a.row && h.col < a.col)) ? h : a;
    const end = start === a ? h : a;

    const out = [];
    for (let r = Math.max(0, start.row); r <= Math.min(rawChat.length - 1, end.row); r++) {
      // renderChatLines() returns ANSI STRINGS (rowToLine), not {spans}
      // objects — reading .spans here threw "Cannot read properties of
      // undefined (reading 'map')" on every copy. Strip the escapes instead.
      const plain = stripAnsi(String(rawChat[r] || ''));
      let c0, c1;

      // +1: the end column is the cell UNDER the pointer, so it is included.
      if (start.row === end.row) { c0 = start.col; c1 = end.col + 1; }
      else if (r === start.row) { c0 = start.col; c1 = Infinity; }
      else if (r === end.row) { c0 = 0; c1 = end.col + 1; }
      else { c0 = 0; c1 = Infinity; }

      const sliced = slicePlainByCol(plain, c0, c1);
      const clean = sliced
        .replace(/<\/?thinking\b[^>]*>/gi, '')
        .replace(/<\/?think\b[^>]*>/gi, '');
      out.push(clean.replace(/\s+$/, ''));
    }
    return out.join('\n');
  }
  function slicePlainByCol(text, c0, c1) {
    if (c0 === 0 && c1 === Infinity) return text;
    let out = '';
    let col = 0;
    const s = String(text || '');
    for (let i = 0; i < s.length; /* manual */) {
      const cp = s.codePointAt(i);
      const ch = String.fromCodePoint(cp);
      const cw = visualWidth(ch);
      if (col >= c0 && (c1 === Infinity || col < c1)) out += ch;
      col += cw;
      i += cp > 0xffff ? 2 : 1;
      if (c1 !== Infinity && col >= c1) break;
    }
    return out;
  }
  function copyToClipboard(text) {
    // Empty text is NOT a success. `copyText` returns false without touching the
    // clipboard, and the old code ignored that — it announced "Copied 0 chars"
    // while the clipboard kept whatever was in it, which reads as "copy did not
    // work" with no way to tell why.
    if (!text) { notice('Nothing to copy', 'error'); return; }
    try {
      const ok = copyText(text); // src/clipboard.js: clip.exe on Windows
      if (ok === false) { notice('Clipboard unavailable', 'error'); return; }
      const n = text.split('\n').length;
      notice(`Copied ${text.length} chars (${n} line${n === 1 ? '' : 's'})`, 'info');
    } catch (e) {
      notice('Clipboard unavailable: ' + (e && e.message ? e.message : e), 'error');
    }
  }
  // Insert pasted text into the composer, collapsing a multi-line paste into a
  // single [paste #N +L lines] marker. Shared by a bracketed paste (what
  // Ctrl+Shift+V sends in most terminals), the Ctrl+Shift+V shortcut and the
  // right-click menu's Paste, so all three behave identically.
  // `kind` = 'image' collapses the insert into a `[paste #N image]` chip instead
  // of dumping the payload (a temp file path) into the prompt. The payload is kept
  // in state.pastes and expanded back on submit, exactly like a multi-line paste.
  function insertComposerPaste(raw, kind = 'paste') {
    const text = String(raw == null ? '' : raw).replace(/\r\n?/g, '\n');
    if (!text) return false;
// A paste starting with `!` into an EMPTY prompt means "run this in the
    // shell" — BUT only when the `!` is clearly a command (`!git status`), not
    // ordinary text that happens to begin with `!` (a markdown image `![..]`, a
    // CSS `!important`). Requiring a command-like token after the bang keeps a
    // copied `![alt](url)` from silently switching into shell mode.
    let body = text;
    if (kind === 'paste' && state.inputMode !== 'bash' && (state.input || '').length === 0 && /^!+[A-Za-z0-9_\/.~-]/.test(body)) {
      state.inputMode = 'bash';
      body = body.replace(/^!+/, '');
    }
    const lineCount = body.split('\n').length;
    let insert = body;
    // An image always collapses (its payload is a path, not something the user
    // typed); text collapses only when it spans more than one line.
    if (kind === 'image' || lineCount > 1) {
      const id = ++state.pasteCounter;
      state.pastes.set(id, { text: body, lines: lineCount, kind });
      insert = pasteMarker(id, lineCount, kind);
    }
    state.input = (state.input || '').slice(0, state.caret) + insert + (state.input || '').slice(state.caret);
    state.caret += insert.length;
    // Shell mode offers no `/` commands or `@` files.
    if (state.inputMode !== 'bash') refreshMenu(state);
    return true;
  }

  // Async so the notice can be painted BEFORE the clipboard read: a cold
  // PowerShell took ~3s, which read as "the shortcut does nothing".
  // Async so the notice can be painted BEFORE the clipboard read: a cold
  // PowerShell took ~3s, which read as "the shortcut does nothing".
  async function pasteFromClipboard(fastPathOnly = false) {
    notice('Pasting…', 'info');
    // One probe handles every clipboard shape: copied FILES (→ paths), plain
    // TEXT (→ text), or an IMAGE (→ a temp .png path). The async version runs it
    // on the PRE-WARMED helper (~10ms) instead of a cold spawn (~2.9s).
    const { text, via } = await readClipboardContentAsync();
    if (text) {
      // An image collapses to a `[paste #N image]` chip, the same way a multi-line
      // paste becomes `[paste #N +L lines]`, so the prompt does not fill up with a
      // temp file path. On submit the chip expands back to that path, which is what
      // the agent's ReadMediaFile needs.
      insertComposerPaste(text, via === 'image' ? 'image' : 'paste');
      notice(via === 'image' ? 'Pasted image' : (via === 'text' ? 'Pasted' : `Pasted ${via} as path`), 'info');
      renderFrame();
      return;
    }
    // Fast path failed — only fall back to the slow warm-helper reader when this
    // is a full paste (Ctrl+Shift+V), not a right-click quick paste.
    if (fastPathOnly) {
      notice('Clipboard empty or unavailable', 'error');
      renderFrame();
      return;
    }
    const result = await readText();
    if (!result.text) { notice('Clipboard empty or unavailable', 'error'); renderFrame(); return; }
    insertComposerPaste(result.text);
    notice(`Pasted via ${result.via}`, 'info');
    renderFrame();
  }
  // Ctrl-S: inject the queued messages (plus the current draft) into the RUNNING
  // turn instead of waiting for it to finish. Mirrors kimi-code's onCtrlS: only
  // meaningful while streaming, and the injected text shows up in the transcript
  // at the point it was steered. Agent.steer() buffers it for the next model
  // call, since nothing can be injected into a request already in flight.
  function steerAll() {
    if (!state.running || !state.agent) {
      notice('Nothing to steer into (the agent is idle)', 'error');
      renderFrame();
      return;
    }
    const items = (state.queued || []).slice();
    const draft = String(state.input || '').trim();
    if (draft) items.push(draft);
    if (!items.length) {
      notice('Nothing queued to steer', 'error');
      renderFrame();
      return;
    }
    for (const text of items) {
      state.agent.steer(text);
      // Show steered messages as `steer` role (no box, yellow) in the output area.
      addChat({ role: 'steer', text });
    }
    // The queue is consumed. The draft was steered too, so clear it (kimi clears
    // the editor for a steered draft).
    if (draft) { state.input = ''; state.caret = 0; state.pastes.clear(); state.pasteCounter = 0; }
    state.queued = [];
    if (web && hub) { try { hub.pubStatusField('queued', []); } catch { /* best-effort */ } }
    renderFrame();
  }

  // ↑ with an empty composer recalls the LAST queued message for editing instead
  // of walking the history (kimi's "↑ to edit" in the queue pane).
  function recallQueued() {
    if (!state.queued || !state.queued.length) return false;
    const text = state.queued[state.queued.length - 1];
    state.queued = state.queued.slice(0, -1);
    if (web && hub) { try { hub.pubStatusField('queued', [...state.queued]); } catch { /* best-effort */ } }
    state.input = text;
    state.caret = text.length;
    // Drop the matching transcript entry: the item is back in the composer.
    for (let i = state.chat.length - 1; i >= 0; i--) {
      if (state.chat[i].role === 'queued' && state.chat[i].text === text) { state.chat.splice(i, 1); break; }
    }
    refreshMenu(state);
    renderFrame();
    return true;
  }

  function openContextMenu(t) {
    const hasSel = !!(state.selection && state.selection.anchor && state.selection.head);
    const hasComposerSel = !!(state.composerSel && state.composerSel.anchor !== state.composerSel.head);
    const items = [];
    if (hasSel) items.push({ label: 'Copy', sub: 'copy the selected text', action: 'copy', primary: true });
    if (hasComposerSel) items.push({ label: 'Copy', sub: 'copy the selected composer text', action: 'copy-composer', primary: true });
    if (hasComposerSel) items.push({ label: 'Cut', sub: 'cut the selected composer text to the clipboard', action: 'cut-composer' });
    items.push({ label: 'Copy last answer', sub: 'copy the last assistant message', action: 'copy-last' });
    items.push({ label: 'Clear selection', sub: 'drop the current selection', action: 'clear' });
    if (hasComposerSel) items.push({ label: 'Clear composer selection', sub: 'drop the composer selection', action: 'clear-composer' });
    items.push({ label: 'Paste', sub: 'paste the clipboard into the composer', action: 'paste' });
    openPicker({
      title: 'Actions',
      items,
      searchable: false,
      // A context menu belongs AT THE POINTER. It opened centred before, which threw
      // away the one cue that said which row was right-clicked — the menu landed
      // halfway across the screen from the selection it acts on. `t.row`/`t.col` are
      // the absolute frame coordinates of the click; the renderer nudges the box back
      // inside the frame when the click is near an edge.
      anchor: { row: t.row, col: t.col },
      keepInput: true, // the composer's text and caret must survive this menu
      hint: '↑↓ navigate · Enter run · Esc cancel',
      onPick: (it) => {
        if (it.action === 'copy') {
          // allowHidden: the menu itself is an overlay, so the transcript is not
          // drawn right now and selectionText()'s "the body must be on screen"
          // guard returned '' — Copy always answered "Nothing to copy".
          const text = selectionText(true);
          if (text) copyToClipboard(text);
          else notice('Nothing to copy — select text first', 'error');
        }
        else if (it.action === 'copy-composer') {
          const sel = state.composerSel;
          const a = Math.min(sel.anchor, sel.head);
          const h = Math.max(sel.anchor, sel.head);
          copyToClipboard((state.input || '').slice(a, h));
        }
        else if (it.action === 'cut-composer') {
          // Same operation as Ctrl+X: to the clipboard, then out of the composer.
          const sel = state.composerSel;
          const a = Math.min(sel.anchor, sel.head);
          const h = Math.max(sel.anchor, sel.head);
          copyToClipboard((state.input || '').slice(a, h));
          state.input = (state.input || '').slice(0, a) + (state.input || '').slice(h);
          state.caret = a;
          state.composerSel = null;
          refreshMenu(state);
        }
        else if (it.action === 'copy-last') {
          const last = [...state.chat].reverse().find((m) => m.role === 'assistant' && (m.text || '').trim());
          if (last) copyToClipboard(last.text); else notice('No assistant message to copy', 'error');
        } else if (it.action === 'clear') { state.selection = null; }
        else if (it.action === 'clear-composer') { state.composerSel = null; }
        else if (it.action === 'paste') {
          // Same path as a bracketed paste / Ctrl+Shift+V: multi-line content
          // collapses into a [paste #N +L lines] marker instead of dumping the
          // raw text (the old code also stripped a real trailing newline).
          void pasteFromClipboard();
        }
        renderFrame();
        return true;
      },
    });
    renderFrame();
  }

  // User keybindings, re-read on every keypress rather than cached: the file is tiny, the
  // read costs microseconds, and it means an edit takes effect immediately. A malformed
  // file is reported ONCE per change (tracked by its errors string) and then ignored, so a
  // typo cannot swallow every key while also not spamming the transcript.
  let keybindings = loadKeybindings();
  let keybindingsErrored = '';
  function refreshKeybindings() {
    keybindings = loadKeybindings();
    const errs = keybindings.errors.join('|');
    if (errs && errs !== keybindingsErrored) {
      keybindingsErrored = errs;
      for (const e of keybindings.errors) app(`!keybindings: ${e}`);
    } else if (!errs) {
      keybindingsErrored = '';
    }
    return keybindings;
  }

  function handleKey(t) {
    // USER KEYBINDINGS, their own layer. A binding either REPLACES a key with another key
    // (applied by rewriting `t.key` below, so the whole switch sees the bound key without
    // knowing bindings exist) or runs a slash command. Mouse and wheel events are never
    // remapped: those names are not keys a user can write, and rewriting them would break
    // the geometry the mouse handlers rely on.
    if (t && t.key && !String(t.key).startsWith('mouse') && t.key !== 'wheelup' && t.key !== 'wheeldown') {
      const bound = resolveKey(t.key, refreshKeybindings().bindings);
      if (bound.command) {
        // The command runs INSTEAD of the key: doing both would fire two unrelated
        // actions from one press. Routed through the same `dispatch` a typed command
        // uses, so a bound command cannot reach a state a typed one could not.
        const text = bound.command;
        const sp = text.indexOf(' ');
        const c = sp === -1 ? text : text.slice(0, sp);
        const arg = sp === -1 ? '' : text.slice(sp + 1).trim();
        Promise.resolve(dispatch(c, arg, state, cfg, session, host, submit, stdout))
          .catch((err) => {
            try { host.notice(`keybinding ${t.key} → ${text} failed: ${(err && err.message) || err}`, 'error'); }
            catch { /* the UI itself is broken */ }
          });
        renderFrame();
        return;
      }
      if (bound.key !== t.key) { t = { ...t, key: bound.key }; }
    }
    // Plugin global keybinds: a plugin claims e.g. 'ctrl+k'. Keyboard events only
    // (never mouse/hover), and never while a full-screen surface owns every key.
    const kbEvents = t && t.key && !t.ch && !String(t.key).startsWith('mouse') && t.key !== 'wheelup' && t.key !== 'wheeldown';
    const kbFree = !state.editor && !state.panel && !state.form && !state.picker && !state.registryBrowser && !state.tasksViewer && !state.tasksPanel && !state.hoverHit;
    if (kbEvents && kbFree) {
      try { if (runKeybindsSync(t.key)) { renderFrame(); return; } } catch (e) {}
    }
    // Full-screen takeovers own EVERY key while open.
    if (state.tasksViewer) { handleTasksViewerKey(t); return; }
    if (state.tasksPanel) { handleTasksPanelKey(t); return; }
    if (state.registryBrowser) { handleRegistryRowKey(t); return; }
    if (state.fileTree) { handleFileTreeKey(t); return; }
    if (t.key === 'mousedown' || t.key === 'mousemove' || t.key === 'mouseup' || t.key === 'rightclick' || t.key === 'mousehover') {
      handleMouse(t);
      return;
    }
    // Handle approval prompt - must be before all other input
    if (state.approvalPending) {
      if (t.key === 'enter' || t.key === ' ') {
        const resolve = state.approvalPending.resolve;
        state.approvalPending = null;
        resolve(true);
        renderFrame();
        return;
      }
      // Ctrl+A approves this AND remembers the decision for the rest of the
      // session, so the same prompt does not come back every turn. The key is `a`
      // for "always", chosen because Enter is already "approve once" and a modifier
      // is needed for the stronger action.
      if (t.key === 'c-a') {
        const ap = state.approvalPending;
        const resolve = ap.resolve;
        state.approvalPending = null;
        approveForSession(state, ap.toolName, ap.args);
        notice(`Approved for this session: ${sessionApprovalLabel(ap.toolName, ap.args)}`, 'info');
        resolve(true);
        renderFrame();
        return;
      }
      if (t.key === 'escape') {
        const resolve = state.approvalPending.resolve;
        state.approvalPending = null;
        resolve(false);
        renderFrame();
        return;
      }
      if (t.key === 'c-c') return;
    }
    // Plan review: the model produced a <|plan|> and Plan mode is waiting.
    // Enter/Space = approve & execute, e = edit first, Esc = keep planning.
    if (state.planPending) {
      const settle = (outcome) => {
        const resolve = state.planPending.resolve;
        state.planPending = null;
        resolve(outcome);
        renderFrame();
      };
      if (t.key === 'enter' || t.key === ' ') { settle('approve'); return; }
      if (t.key === 'escape') { settle('keep'); return; }
      if (t.ch === 'e' || t.ch === 'E') { settle('edit'); return; }
      if (t.key === 'c-c') return;   // do not exit while a plan is under review
      // The wheel and the page keys SCROLL. They do not change the review's state, so
      // swallowing them bought nothing and cost the one thing a long plan needs: a way to
      // read past the fold. Everything else still belongs to the review.
      if (t.key === 'wheelup' || t.key === 'wheeldown') {
        scrollChat(state, t.key === 'wheelup' ? 3 : -3);
        renderFrame();
        return;
      }
      if (t.key === 'pageup' || t.key === 'pagedown') {
        scrollChat(state, t.key === 'pageup' ? 10 : -10);
        renderFrame();
        return;
      }
      return;                        // swallow other keys while reviewing
    }
    if (t.key === 'c-c') {
      // An open overlay consumes Ctrl+C: close it instead of interrupting the
      // turn that is still running behind it. The modal editor belongs here too:
      // without it Ctrl+C fell through to the exit path below, armed the
      // "Press Ctrl+C again to exit" prompt behind the editor (which stays on
      // screen), and a second Ctrl+C — often the very key the user pressed again
      // to dismiss the prompt — quit the app and discarded the draft.
      if (state.menuOpen || state.picker || state.form || state.panel || state.question || state.editor) {
        // One shared dismissal so Ctrl+C and a click outside cannot drift apart:
        // this used to clear `state.form` without calling its `onCancel`, while the
        // click path (added later) does — two ways to close one dialog with two
        // different outcomes.
        dismissOverlay();
        // Ctrl+C on the question dialog = dismiss, the same as Esc.
        if (state.question) { const r = state.question.resolve; state.question = null; r({}); }
        state.menuOpen = false; state.menuList = []; state.menuSel = 0; state.menuOffset = 0;
        renderFrame();
        return;
      }
      if (state.running) {
        if (state.agent) state.agent.interrupt();
      }
      if (state.confirmExit) { quit(); return; }
      state.confirmExit = true;
      renderFrame();
      if (confirmTimer) clearTimeout(confirmTimer);
      confirmTimer = setTimeout(() => { state.confirmExit = false; renderFrame(); }, 3000);
      return;
    }
    if (state.question) {
      // AskUserQuestion dialog. Owns ALL input while open.
      //
      // Tabs: each question is a tab, plus a trailing "Other" tab that holds the
      // whole-request free-text note. `qs.index` is the tab: 0..items.length-1 are
      // questions, items.length is the Other tab. Tab / Shift+Tab / Left / Right
      // switch tabs; Up / Down move the option cursor within a question.
      const qs = state.question;
      const total = qs.items.length;
      const onOtherTab = qs.index >= total;
      const cur = onOtherTab ? { options: [] } : (qs.items[qs.index] || { options: [] });
      const otherIdx = (cur.options || []).length;   // the per-question Other option
      const optCount = otherIdx + 1;                 // options + Other
      // Resolve the call. `dismissed` distinguishes "Esc out" (empty answers) from
      // "answered, maybe with a note".
      const finish = (dismissed) => {
        const r = qs.resolve; state.question = null;
        r(dismissed ? {} : { answers: qs.answers, additional: (qs.supplement || '').trim() });
        renderFrame();
      };
      // After a question is answered, move to the NEXT question; if it was the last
      // one, jump to the Other tab (where Enter submits) — never auto-submit, so
      // the user can leave a note. Shared with the click handler (questionItem).
      const advance = () => { advanceQuestion(qs); renderFrame(); };
      const switchTab = (dir) => {
        // Fold any half-typed free text into its slot before switching.
        if (qs.editing === 'other') qs.otherText = qs.editingText || '';
        else if (qs.editing === 'supplement') qs.supplement = qs.editingText || '';
        qs.editing = null;
        const n = total + 1;   // questions + the Other tab
        qs.index = (qs.index + dir + n) % n;
        qs.sel = 0;
        qs.picked = new Set();
        if (qs.index === total) {
          // Landing on the Other tab opens its text field directly.
          qs.editing = 'supplement';
          qs.editingText = qs.supplement || '';
          qs.editingCaret = qs.editingText.length;
        }
        renderFrame();
      };

      if (qs.editing) {
        const buf = () => String(qs.editingText || '');
        const ec = Math.max(0, Math.min(buf().length, qs.editingCaret == null ? buf().length : qs.editingCaret));
        if (t.key === 'escape') { qs.editing = null; renderFrame(); return; }
        // Leaving the field without committing: Tab / Shift+Tab return to the tab
        // bar (arrows stay inside the text field).
        if (t.key === 'tab' || t.key === 's-tab') {
          if (qs.editing === 'other') qs.otherText = qs.editingText || '';
          else if (qs.editing === 'supplement') qs.supplement = qs.editingText || '';
          qs.editing = null; switchTab(t.key === 's-tab' ? -1 : 1); return;
        }
        if (t.key === 'left') { qs.editingCaret = Math.max(0, ec - 1); renderFrame(); return; }
        if (t.key === 'right') { qs.editingCaret = Math.min(buf().length, ec + 1); renderFrame(); return; }
        if (t.key === 'home') { qs.editingCaret = 0; renderFrame(); return; }
        if (t.key === 'end') { qs.editingCaret = buf().length; renderFrame(); return; }
        if (t.key === 'backspace') {
          if (ec > 0) { qs.editingText = buf().slice(0, ec - 1) + buf().slice(ec); qs.editingCaret = ec - 1; }
          renderFrame(); return;
        }
        if (t.key === 'delete') {
          if (ec < buf().length) qs.editingText = buf().slice(0, ec) + buf().slice(ec + 1);
          renderFrame(); return;
        }
        if (t.paste !== undefined) {
          const ins = String(t.paste).replace(/[\r\n]+/g, ' ');
          qs.editingText = buf().slice(0, ec) + ins + buf().slice(ec);
          qs.editingCaret = ec + ins.length;
          renderFrame(); return;
        }
        if (t.key === 'enter') {
          const answer = (qs.editingText || '').trim();
          if (qs.editing === 'supplement') {
            // The whole-request note is optional: Enter commits it (empty is fine)
            // and ends the call.
            qs.supplement = answer;
            qs.editing = null;
            finish(false);
            return;
          }
          if (!answer) { renderFrame(); return; }          // nothing typed: stay
          qs.answers[cur.question] = answer;
          qs.otherText = '';
          qs.editing = null;
          advance();
          return;
        }
        if (t.ch) {
          qs.editingText = buf().slice(0, ec) + t.ch + buf().slice(ec);
          qs.editingCaret = ec + t.ch.length;
          renderFrame(); return;
        }
        return;
      }

      if (t.key === 'escape') { finish(true); return; }    // dismiss: empty answers
      // Tab / Shift+Tab / Left / Right switch between TABS (questions + Other).
      if ((t.key === 'tab' || t.key === 's-tab' || t.key === 'left' || t.key === 'right')
          && total > 0) {
        const dir = (t.key === 'left' || t.key === 's-tab') ? -1 : 1;
        switchTab(dir);
        return;
      }
      if (onOtherTab) {
        // The Other field opens on arrival; if closed, any text/Enter reopens it.
        if (t.ch || t.key === 'enter') {
          qs.editing = 'supplement';
          qs.editingText = qs.supplement || '';
          qs.editingCaret = qs.editingText.length;
          renderFrame(); return;
        }
        return;
      }
      if (t.key === 'up') { qs.sel = (qs.sel - 1 + optCount) % optCount; renderFrame(); return; }
      if (t.key === 'down') { qs.sel = (qs.sel + 1) % optCount; renderFrame(); return; }

      // Open a free-text editor, seeding it with whatever was typed before.
      const openEditor = (which) => {
        qs.editing = which;
        qs.editingText = which === 'supplement' ? (qs.supplement || '') : (qs.otherText || '');
        qs.editingCaret = qs.editingText.length;
        renderFrame();
      };
      if (cur.multiSelect && (t.key === ' ' || t.ch === ' ')) {
        if (qs.sel >= otherIdx) { openEditor('other'); return; }
        if (qs.picked.has(qs.sel)) qs.picked.delete(qs.sel); else qs.picked.add(qs.sel);
        renderFrame(); return;
      }
      if (t.key === 'enter') {
        if (qs.sel >= otherIdx) { openEditor('other'); return; }
        if (cur.multiSelect) {
          const labels = [...qs.picked].sort((a, b) => a - b).map((i) => cur.options[i].label);
          if (labels.length) qs.answers[cur.question] = labels.join(', ');
          advance();
          return;
        }
        qs.answers[cur.question] = cur.options[qs.sel].label;
        advance();
        return;
      }
      // The wheel and the page keys SCROLL the transcript behind the dialog. They carry no
      // answer, so "own ALL input" does not need them — and without this a long question
      // with an option list taller than the screen could not be read past at all.
      if (t.key === 'wheelup' || t.key === 'wheeldown') {
        scrollChat(state, t.key === 'wheelup' ? 3 : -3);
        renderFrame();
        return;
      }
      if (t.key === 'pageup' || t.key === 'pagedown') {
        scrollChat(state, t.key === 'pageup' ? 10 : -10);
        renderFrame();
        return;
      }
      return;
    }

    if (state.confirmExit) { state.confirmExit = false; if (confirmTimer) clearTimeout(confirmTimer); }


    // Ctrl+Up / Ctrl+Down — scroll the AI output area, ALWAYS (independent of the
    // composer, unlike the plain arrows which first move the caret / walk history).
    // This is the dedicated "read back the transcript" key the user asked for.
    // Handled AFTER the overlay branches above, so an open picker/form/panel keeps
    // its own arrow behaviour on the un-modified keys.
    if (t.key === 'c-up' || t.key === 'c-down') {
      if (!(state.picker || state.form || state.panel || state.editor || state.question || state.menuOpen)) {
        scrollChat(state, t.key === 'c-up' ? 3 : -3);
        renderFrame();
        return;
      }
    }

    // Ctrl+L — expand / collapse the plugin log block(s). The last one is the
    // useful target (it is the most recent), but every pluginLog message is toggled
    // so a session with several reloads behaves predictably.
    if (t.key === 'c-l') {
      if (!(state.picker || state.form || state.panel || state.editor || state.question || state.menuOpen)) {
        const logs = (state.chat || []).filter((m) => m && m.pluginLog);
        if (logs.length) {
          const want = !logs[logs.length - 1].expanded;
          for (const m of logs) m.expanded = want;
          renderFrame();
          return;
        }
      }
    }

    // Ctrl+P — command palette (cline-style): one searchable list of every command,
    // regardless of whether the composer already starts with `/`. Choosing one drops
    // `/name ` into the composer (focus stays there) so arguments can still be typed.
    // The `/`-typed completion menu only appears after a slash is typed, so this is
    // the discoverable entry point.
    if (t.key === 'c-p') {
      if (!(state.picker || state.form || state.panel || state.editor || state.question || state.menuOpen)) {
        const cmds = allCommands();
        if (!cmds.length) { renderFrame(); return; }
        openPicker({
          title: 'Commands',
          searchable: true,
          hint: '↑↓ navigate · type to filter · Enter insert · Esc cancel',
          // The palette must not wipe a half-typed prompt, so it opts out of the
          // composer-clear that openPicker does by default.
          keepInput: true,
          items: cmds.map((c) => ({
            label: '/' + c.name,
            sub: c.description || c.desc || '',
            _name: c.name,
          })),
          onPick: (it) => {
            if (!it || !it._name) return true;
            // Insert rather than execute: arguments almost always follow, and a
            // command that opens a dialog would otherwise swallow the keystroke.
            state.input = '/' + it._name + ' ';
            state.caret = state.input.length;
            refreshMenu(state);
            renderFrame();
            return true;
          },
        });
        renderFrame();
        return;
      }
    }

    // Ctrl+X / Ctrl+Shift+X — CUT. Removes the composer's selected text (or the
    // whole line when nothing is selected) and puts it on the clipboard, like a
    // normal editor. Ctrl+Shift+X is accepted as an alias because some terminals
    // only deliver the modified form.
    if (t.key === 'c-x' || t.key === 'c-s-x') {
      const cur = state.input || '';
      const sel = state.composerSel;
      if (sel && sel.anchor !== sel.head) {
        const a = Math.min(sel.anchor, sel.head);
        const h = Math.max(sel.anchor, sel.head);
        const removed = cur.slice(a, h);
        state.input = cur.slice(0, a) + cur.slice(h);
        state.caret = a;
        state.composerSel = null;
        copyToClipboard(removed);
        refreshMenu(state);
      } else {
        notice('Nothing selected to cut', 'error');
      }
      renderFrame();
      return;
    }

    if (t.key === 'c-s-c') {
      // Ctrl+Shift+C copies the MOUSE SELECTION. It used to fall back to the last
      // assistant reply when there was no selection — which silently copied the
      // WRONG THING: a user who had selected some shell output but whose selection
      // was not established got an AI answer on the clipboard instead, with a
      // "Copied N chars" notice that looked like success. A key that copies
      // something other than what is highlighted is worse than one that copies
      // nothing, so the fallback is gone; ask for the explicit action instead.
      // (Only terminals that can report modified keys — the kitty keyboard
      // protocol hncode already enables — can tell Ctrl+Shift+C from Ctrl+C; one
      // that sends ^C for both cannot.)
      if (state.selection && state.selection.anchor && state.selection.head) {
        const sel = selectionText();
        if (sel) copyToClipboard(sel);
        else notice('Nothing to copy — the selection is empty', 'error');
      } else {
        const composerSel = state.composerSel;
        if (composerSel && composerSel.anchor !== composerSel.head) {
          const a = Math.min(composerSel.anchor, composerSel.head);
          const h = Math.max(composerSel.anchor, composerSel.head);
          copyToClipboard((state.input || '').slice(a, h));
        } else {
          notice('Nothing to copy — select text first (or use the right-click menu)', 'error');
        }
      }
      renderFrame();
      return;
    }

    if (t.key === 'c-s-v') {
      // Ctrl+Shift+V: paste the clipboard like a bracketed paste. A terminal
      // that handles Ctrl+Shift+V itself sends the 200~/201~ sequence, which the
      // tokenizer turns into a {paste} token and which reads the same as this
      // shortcut from the user's point of view.
      void pasteFromClipboard();
      return;
    }

    if (t.key === 'c-v') {
      // Ctrl+V: paste. Many terminals translate Ctrl+V in raw mode to the raw
      // control byte 0x16 (not a bracketed-paste sequence), which tokenize()
      // produces as {key:'c-v'}. That token had NO handler, so Ctrl+V silently
      // did nothing everywhere (only Ctrl+Shift+V / bracketed paste worked).
      // Route it through the same clipboard paste as Ctrl+Shift+V.
      void pasteFromClipboard();
      return;
    }

    if (t.key === 'c-b') {
      const fg = state.agent && state.agent.ctx && state.agent.ctx._foreground;
      if (fg && typeof fg.detach === 'function') {
        const id = fg.detach();
        if (id) {
          notice(`Moved to background: ${id}`, 'info');
          renderFrame();
          return;
        }
      }
    }

    if (t.key === 'c-s' && !state.editor) {
      steerAll();
      return;
    }

    if (t.key === 'c-t' && !state.editor) {
      // An explicit expand/collapse REPLACES any manual drag height, otherwise the
      // `todoRows` value won over `todosExpanded` in todoRowCount and Ctrl+T did
      // nothing once the panel had been dragged.
      // An explicit expand/collapse REPLACES any manual drag height, otherwise the
      // `todoRows` value won over `todosExpanded` in todoRowCount and Ctrl+T did
      // nothing once the panel had been dragged.
      state.todoRows = undefined;
      const total = (state.todos || []).length;
      const before = todoRowCount(state);
      // When the list already fits (<= TODO_MAX_VISIBLE) the automatic view shows
      // everything, so neither state can change the row count: Ctrl+T has no effect
      // here, so do NOT flip the flag (a half-set `todosExpanded` would be state
      // that lies) and say so plainly.
      state.todosExpanded = !state.todosExpanded;
      const after = todoRowCount(state);
      if (before === after) {
        state.todosExpanded = !state.todosExpanded;   // undo: nothing to toggle
        notice(total ? `Todo panel already shows all ${total}` : 'No todos yet', 'info');
        renderFrame();
        return;
      }
      notice(state.todosExpanded
        ? `Todo panel expanded (${after} of ${total})`
        : `Todo panel collapsed (${after} of ${total})`, 'info');
      renderFrame();
      return;
    }

    if (t.key === 'c-o' && !state.editor) {
      state.expanded = !state.expanded;
      notice(state.expanded ? 'Expanded tool output' : 'Collapsed tool output', 'info');
      renderFrame();
      return;
    }

    // ↑ with an empty composer recalls the newest QUEUED message for editing
    // (the queue pane advertises this as "↑ to edit"). This MUST be handled
    // before the running/idle split below: queued messages only exist while the
    // agent is running, so the idle-only branch that used to hold this was
    // unreachable dead code and ↑ scrolled the chat instead.
    {
      const overlay = state.picker || state.form || state.panel || state.menuOpen || state.editor;
      const cur = state.input || '';
      if (!overlay && cur === '' && t.key === 'up' && (state.queued || []).length) {
        recallQueued();
        return;
      }
    }

    // A dialog (/settings, /model, /provider, /sessions, an approval panel, …)
    // owns the keyboard while it is open: Esc closes IT rather than aborting the
    // running turn, and the arrows move its selection instead of scrolling the
    // transcript. Without this guard the running block below stole those keys.
    // The modal editor (e.g. from /set-system-prompt) is included so that Esc and
    // arrow keys are handled by it, not by the running-turn interrupt/scroll logic.
    //
    // `mentionOpen` MUST be in this list: it is the inline `@file` candidate list,
    // which is a keyboard-owning overlay just like the `/` menu. Leaving it out
    // meant that while the agent was streaming, ↑/↓ scrolled the transcript
    // (instead of moving the selection) and Esc interrupted the turn (instead of
    // dismissing the list) — the keys never reached the mention block below.
    const overlayOpen = !!(state.picker || state.form || state.panel || state.menuOpen
      || state.mentionOpen || state.editor);
    if (state.running && !overlayOpen) {
      if (t.key === 'escape') {
        if (state.agent) state.agent.interrupt();
        // Manual /compact runs its own summarizer (no agent). Abort it and flag it,
        // so the /compact handler skips the trim (abort yields an empty summary —
        // trimming would drop history with nothing to replace it).
        if (state._compactLlm) { state._compactAborted = true; try { state._compactLlm.abort(); } catch { /* ignore */ } }
        return;
      }
      if (t.key === 'pageup' || t.key === 'pagedown') {
        scrollChat(state, t.key === 'pageup' ? 10 : -10);
        renderFrame(); return;
      }
      if (t.key === 'wheelup' || t.key === 'wheeldown') {
        scrollChat(state, t.key === 'wheelup' ? 3 : -3);
        renderFrame(); return;
      }
      if (t.key === 'up' || t.key === 'down') {
        // ↑/↓ while the agent streams: FIRST give the composer its caret move
        // (a multi-line draft must still navigate), then fall back to scrolling
        // ONLY when there is nothing else to do. The scroll is what made ↑ feel
        // stuck while output streamed, so it is now the last resort.
        const cur = state.input || '';
        if (cur === '') {
          // Empty composer: the key belongs to HISTORY, not to the viewport.
          // With no history the key does nothing at all — silently scrolling
          // the transcript is what made a bare ↑ feel like it ate the key.
          if (state.history.length) {
            if (state.historyIdx === -1) state.historyIdx = state.history.length;
            state.historyIdx = t.key === 'up'
              ? Math.max(0, state.historyIdx - 1)
              : Math.min(state.history.length, state.historyIdx + 1);
            state.input = state.historyIdx >= state.history.length ? '' : (state.history[state.historyIdx] || '');
            state.caret = state.input.length;
            refreshMenu(state); renderFrame();
          }
          return;
        }
        const insideW = Math.max(0, dims().cols - 2);
        const layout = composerLayout(state, insideW - 3);
        const dir = t.key === 'down' ? 1 : -1;
        const targetRow = layout.caretRow + dir;
        if (targetRow >= 0 && targetRow < layout.rows.length) {
          const starts = rowStartOffsets(state.input || '', layout.rows.length, insideW);
          const colInRow = Math.max(0, layout.caretCol - 1);
          const targetStart = starts[targetRow] != null ? starts[targetRow] : 0;
          state.caret = Math.min((state.input || '').length, targetStart + colInRow);
          state.composerSel = null;
          renderFrame(); return;
        }
        // Draft is on its last/first row: the key is free. Scroll the transcript
        // (useful while output streams and you want to read back).
        scrollChat(state, t.key === 'up' ? 3 : -3);
        renderFrame(); return;
      }
    }
    else {
      if (t.key === 'up' || t.key === 'down') {
        const overlay = state.picker || state.form || state.panel || state.menuOpen
          || state.mentionOpen || state.editor;
        if (!overlay) {
          const cur = state.input || '';
          const insideW = Math.max(0, dims().cols - 2);
          const layout = composerLayout(state, insideW - 3);
          const dir = t.key === 'down' ? 1 : -1;
          const targetRow = layout.caretRow + dir;
          // The composer is MULTI-LINE: ↑/↓ move the caret between its rows
          // first, and only when it is already on the first/last row does the
          // key fall through to history. That is the usual shell/editor rule —
          // typing a paragraph must not have ↑ yank the draft away.
          if (cur !== '' && targetRow >= 0 && targetRow < layout.rows.length) {
            state.caret = verticalCaretIndex(state, cur, layout, targetRow);
            state.composerSel = null;
            renderFrame();
            return;
          }
          // First/last row (or an empty composer): this is history's turn.
          if (state.history.length) {
            if (state.historyIdx === -1) state.historyIdx = state.history.length;
            state.historyIdx = t.key === 'up'
              ? Math.max(0, state.historyIdx - 1)
              : Math.min(state.history.length, state.historyIdx + 1);
            state.input = state.historyIdx >= state.history.length ? '' : (state.history[state.historyIdx] || '');
            state.caret = state.input.length;
            refreshMenu(state); renderFrame();
          }
          return;
        }
      }
    }

    if (state.editor) {
      // Modal multiline editor. Ctrl+S saves, Esc cancels, Enter inserts a
      // newline; the arrows/Home/End move the caret and the view follows it.
      const ed = state.editor;
      const setText = (text, row, col) => {
        ed.text = text;
        const ls = text.split('\n');
        ed.caretRow = Math.max(0, Math.min(ls.length - 1, row));
        ed.caretCol = Math.max(0, Math.min((ls[ed.caretRow] || '').length, col));
        renderFrame();
      };
      const curLines = () => ed.text.split('\n');
      if (t.key === 'escape') { state.editor = null; state.hoverHit = null; renderFrame(); return; }
      // Ctrl+S: save.
      if (t.key === 'c-s') {
        const cb = ed.onSave;
        state.editor = null;
        try { if (cb) cb(ed.text); } catch (e) { notice('Save failed: ' + e.message, 'error'); }
        renderFrame();
        return;
      }
      if (t.key === 'up' || t.key === 'down') {
        const ls = curLines();
        const r = Math.max(0, Math.min(ls.length - 1, ed.caretRow + (t.key === 'up' ? -1 : 1)));
        setText(ed.text, r, ed.caretCol);
        return;
      }
      if (t.key === 'left') { setText(ed.text, ed.caretRow, ed.caretCol - 1); return; }
      if (t.key === 'right') { setText(ed.text, ed.caretRow, ed.caretCol + 1); return; }
      if (t.key === 'home') { setText(ed.text, ed.caretRow, 0); return; }
      if (t.key === 'end') { setText(ed.text, ed.caretRow, (curLines()[ed.caretRow] || '').length); return; }
      if (t.key === 'pageup') { setText(ed.text, ed.caretRow - 10, ed.caretCol); return; }
      if (t.key === 'pagedown') { setText(ed.text, ed.caretRow + 10, ed.caretCol); return; }
      if (t.key === 'enter' || t.key === 'newline') {
        const ls = curLines();
        const line = ls[ed.caretRow] || '';
        ls[ed.caretRow] = line.slice(0, ed.caretCol);
        ls.splice(ed.caretRow + 1, 0, line.slice(ed.caretCol));
        setText(ls.join('\n'), ed.caretRow + 1, 0);
        return;
      }
      if (t.key === 'backspace') {
        const ls = curLines();
        const line = ls[ed.caretRow] || '';
        if (ed.caretCol > 0) {
          ls[ed.caretRow] = line.slice(0, ed.caretCol - 1) + line.slice(ed.caretCol);
          setText(ls.join('\n'), ed.caretRow, ed.caretCol - 1);
        } else if (ed.caretRow > 0) {
          const prev = ls[ed.caretRow - 1] || '';
          ls.splice(ed.caretRow, 1);
          ls[ed.caretRow - 1] = prev + line;
          setText(ls.join('\n'), ed.caretRow - 1, prev.length);
        }
        return;
      }
      if (t.key === 'delete') {
        const ls = curLines();
        const line = ls[ed.caretRow] || '';
        if (ed.caretCol < line.length) {
          ls[ed.caretRow] = line.slice(0, ed.caretCol) + line.slice(ed.caretCol + 1);
          setText(ls.join('\n'), ed.caretRow, ed.caretCol);
        } else if (ed.caretRow < ls.length - 1) {
          ls[ed.caretRow] = line + (ls[ed.caretRow + 1] || '');
          ls.splice(ed.caretRow + 1, 1);
          setText(ls.join('\n'), ed.caretRow, ed.caretCol);
        }
        return;
      }
      if (t.ch) {
        const ls = curLines();
        const line = ls[ed.caretRow] || '';
        ls[ed.caretRow] = line.slice(0, ed.caretCol) + t.ch + line.slice(ed.caretCol);
        setText(ls.join('\n'), ed.caretRow, ed.caretCol + t.ch.length);
        return;
      }
      if (t.paste !== undefined) {
        const ls = curLines();
        const line = ls[ed.caretRow] || '';
        const ins = String(t.paste).replace(/\r\n/g, '\n');
        const parts = (line.slice(0, ed.caretCol) + ins + line.slice(ed.caretCol)).split('\n');
        ls.splice(ed.caretRow, 1, ...parts);
        setText(ls.join('\n'), ed.caretRow + parts.length - 1, parts[parts.length - 1].length);
        return;
      }
      return;
    }

    if (state.panel) {
      const p = state.panel;
      if (t.key === 'escape') { state.panel = null; state.hoverHit = null; renderFrame(); return; }
      if (t.key === 'up') { p.top = Math.max(0, (p.top || 0) - 1); renderFrame(); return; }
      if (t.key === 'down') { p.top = (p.top || 0) + 1; renderFrame(); return; }
      if (t.key === 'pageup') { p.top = Math.max(0, (p.top || 0) - 10); renderFrame(); return; }
      if (t.key === 'pagedown') { p.top = (p.top || 0) + 10; renderFrame(); return; }
      if (t.key === 'home') { p.top = 0; renderFrame(); return; }
      return;
    }


    if (state.form) {
      const f = state.form;
      const nRows = f.fields.length + (f.hideType ? 0 : 1);
      const onType = !f.hideType && f.fieldIdx >= f.fields.length;
      const field = f.fields[f.fieldIdx];
      if (t.key === 'escape') { const cb = f.onCancel; state.form = null; state.hoverHit = null; if (cb) cb(); renderFrame(); return; }
      if (t.key === 'up') { f.fieldIdx = (f.fieldIdx - 1 + nRows) % nRows; renderFrame(); return; }
      if (t.key === 'down') { f.fieldIdx = (f.fieldIdx + 1) % nRows; renderFrame(); return; }
      if (t.key === 'tab') { f.fieldIdx = (f.fieldIdx + 1) % nRows; renderFrame(); return; }
      if (onType) {
        if (t.key === 'left' || t.key === 'right' || t.ch === ' ') {
          const list = (f.types && f.types.length) ? f.types : PROTOCOL_TYPES;
          const i = Math.max(0, list.indexOf(f.type));
          const d = t.key === 'left' ? -1 : 1;
          f.type = list[(i + d + list.length) % list.length];
          renderFrame(); return;
        }
        if (t.key === 'enter') {
          const values = {};
          for (const fl of f.fields) values[fl.key] = fl.value.trim();
          const submit = f.onSubmit; state.form = null; submit(values, f.type); renderFrame(); return;
        }
        return;
      }
      if (t.key === 'left') { field.caret = Math.max(0, field.caret - 1); renderFrame(); return; }
      if (t.key === 'right') { field.caret = Math.min(field.value.length, field.caret + 1); renderFrame(); return; }
      if (t.key === 'home') { field.caret = 0; renderFrame(); return; }
      if (t.key === 'end') { field.caret = field.value.length; renderFrame(); return; }
      if (t.key === 'backspace') {
        if (field.caret > 0) { field.value = field.value.slice(0, field.caret - 1) + field.value.slice(field.caret); field.caret--; }
        renderFrame(); return;
      }
      if (t.key === 'delete') {
        if (field.caret < field.value.length) { field.value = field.value.slice(0, field.caret) + field.value.slice(field.caret + 1); }
        renderFrame(); return;
      }
      if (t.paste !== undefined) {
        const text = String(t.paste).replace(/[\r\n]+/g, '');
        field.value = field.value.slice(0, field.caret) + text + field.value.slice(field.caret);
        field.caret += text.length;
        renderFrame(); return;
      }
      if (t.key === 'enter') {
        const values = {};
        for (const fl of f.fields) values[fl.key] = fl.value.trim();
        const submit = f.onSubmit; state.form = null; submit(values, f.type); renderFrame(); return;
      }
      if (t.ch) { field.value = field.value.slice(0, field.caret) + t.ch + field.value.slice(field.caret); field.caret++; renderFrame(); return; }
      return;
    }

    if (state.picker) {
      const list = pickerFiltered(state);
      const foot = state.picker.footer;
      if (foot) {
        if (t.key === 'left' || t.key === 'right') {
          const i = Math.max(0, foot.options.indexOf(foot.value));
          const d = (t.key === 'right') ? 1 : -1;
          foot.value = foot.options[(i + d + foot.options.length) % foot.options.length];
          renderFrame(); return;
        }
        if (t.key === 'tab') { 
          // If there are multiple categories, Tab cycles them first
          if (state.picker.categories && state.picker.categories.length > 1) {
            const cats = state.picker.categories;
            const active = state.pickerCategory || cats[0];
            const idx = Math.max(0, cats.indexOf(active));
            const next = (idx + 1) % cats.length;
            state.pickerCategory = cats[next];
            state.picker.sel = 0;
            state.pickerQuery = '';
            renderFrame(); return;
          }
          // Otherwise toggle footer focus
          foot.focused = !foot.focused; 
          renderFrame(); 
          return; 
        }
        if (foot.focused) {
          if (t.key === 'enter') { foot.focused = false; renderFrame(); return; }
          if (t.key === 'escape') { foot.focused = false; renderFrame(); return; }
          return;
        }
      }
      if (t.key === 'wheelup' || t.key === 'wheeldown') {
        const n = list.length;
        if (!n) return;
        const cur = Math.min(state.picker.sel, n - 1);
        state.picker.sel = (cur + (t.key === 'wheeldown' ? 1 : n - 1)) % n;
        if (state.picker.footerFor) {
          const item = list[state.picker.sel];
          state.picker.footer = state.picker.footerFor(item, state.picker.footer);
        }
        renderFrame();
        return;
      }
      if (t.key === 'up' || t.key === 'down') {
        const n = list.length;
        if (!n) return;
        const cur = Math.min(state.picker.sel, n - 1);
        state.picker.sel = (cur + (t.key === 'down' ? 1 : n - 1)) % n;
        if (state.picker.footerFor) {
          const item = list[state.picker.sel];
          state.picker.footer = state.picker.footerFor(item, state.picker.footer);
        }
        renderFrame();
        return;
      }
      if (t.key === 'enter') {
        const item = list[state.picker.sel];
        if (!item) return;
        const before = state.picker;
        const done = state.picker.onPick(item);
        if (done && state.picker === before) { state.picker = null; state.pickerQuery = ''; state.pickerCategory = null; }
        renderFrame();
        return;
      }
      if (t.key === 'delete') {
        const item = list[state.picker.sel];
        if (state.picker.onDelete && item) {
          state.picker.onDelete(item);
          renderFrame();
        }
        return;
      }
      // Tab cycles categories (if the picker has them); resets selection & search.
      if (t.key === 'tab' && state.picker.categories && state.picker.categories.length > 1) {
        const cats = state.picker.categories;
        const active = state.pickerCategory || cats[0];
        const idx = Math.max(0, cats.indexOf(active));
        const next = (idx + 1) % cats.length;
        state.pickerCategory = cats[next];
        state.picker.sel = 0;
        state.pickerQuery = '';
        renderFrame(); return;
      }
      // Ctrl+E: a picker may expose an "edit the selected item" action (used by
      // /model to edit the selected model's details). Generic hook, so any picker
      // can opt in without hard-coding the key here.
      if (t.key === 'c-e' && typeof state.picker.onCtrlE === 'function') {
        const item = list[state.picker.sel];
        if (item) state.picker.onCtrlE(item);
        renderFrame();
        return;
      }
      // Ctrl+R: a picker may expose a "refresh the selected item" action (used by
      // /provider to re-discover the selected provider's models).
      if (t.key === 'c-r' && typeof state.picker.onCtrlR === 'function') {
        const item = list[state.picker.sel];
        if (item) state.picker.onCtrlR(item);
        renderFrame();
        return;
      }
      if (t.key === 'escape') {
        const cb = state.picker.onCancel;
        state.picker = null;
        state.pickerQuery = '';
        state.pickerCategory = null;
        // Drop the hover highlight: its row numbering described the MENU, and the
        // transcript is about to take those rows back — leaving it tinted whatever
        // ended up there until the pointer moved again.
        state.hoverHit = null;
        if (cb) cb();
        renderFrame();
        return;
      }
      if (state.picker.searchable !== false) {
        if (t.key === 'backspace') {
          state.pickerQuery = (state.pickerQuery || '').slice(0, -1);
          state.picker.sel = 0;
          const qcb = state.picker.onQueryChange;
          if (qcb) qcb(state.pickerQuery);
          renderFrame(); return;
        }
        if (t.ch) {
          state.pickerQuery = (state.pickerQuery || '') + t.ch;
          state.picker.sel = 0;
          const qcb = state.picker.onQueryChange;
          if (qcb) qcb(state.pickerQuery);
          renderFrame(); return;
        }
      }
      return;
    }

    // The side-thread box owns Esc and ↑/↓ while it is open, the same way the
    // `/`-menu and the `@file` list do. Esc CLOSES it before clearing the composer,
    // because "get me out of this box" is the more specific intent.
    if (state.btwPanel && state.btwPanel.turns && state.btwPanel.turns.length) {
      if (t.key === 'escape') {
        state.btwPanel = null;
        state.btwScroll = 0;
        state.sideThread = null;
        notice('Side thread closed.', 'info');
        renderFrame();
        return;
      }
      // ↑/↓ scroll the box's history, in ROWS. Held on the state as an offset from
      // the tail, matching the transcript's convention.
      if (t.key === 'up' || t.key === 'down') {
        const step = t.key === 'up' ? 4 : -4;
        state.btwScroll = Math.max(0, (state.btwScroll || 0) + step);
        renderFrame();
        return;
      }
    }

    if (t.key === 'escape') {
      // In shell mode a bare Esc on an empty buffer exits the mode (nothing to
      // clear); with text present it falls through and clears as usual.
      if (state.inputMode === 'bash' && state.input.length === 0) {
        state.inputMode = 'prompt';
        renderFrame();
        return;
      }
      state.menuOpen = false; state.menuList = []; state.menuSel = 0;
      state.menuOffset = 0;
      state.mentionOpen = false; state.mentionList = []; state.mentionSel = 0;
      state.mentionOffset = 0;
      state.input = ''; state.caret = 0;
      state.pastes.clear(); state.pasteCounter = 0;
      state.composerSel = null;
      state.inputMode = 'prompt';
      refreshMenu(state);
      renderFrame();
      return;
    }
    if (state.menuOpen) {
      if (t.key === 'up') { state.menuSel = (state.menuSel - 1 + state.menuList.length) % state.menuList.length; ensureMenuVisible(state); renderFrame(); return; }
      if (t.key === 'down') { state.menuSel = (state.menuSel + 1) % state.menuList.length; ensureMenuVisible(state); renderFrame(); return; }
      if (t.key === 'tab') { acceptMenuSelection(state); refreshMenu(state); renderFrame(); return; }
    }
    // The inline `@file` list owns ↑↓/Tab/Enter/Esc while it is open, exactly like
    // the `/` menu above. Enter would otherwise SUBMIT the half-typed prompt.
    if (state.mentionOpen) {
      const n = state.mentionList.length;
      if (t.key === 'up' || t.key === 'down') {
        if (n) {
          state.mentionSel = (state.mentionSel + (t.key === 'down' ? 1 : n - 1)) % n;
          // Keep the selection inside the visible window.
          state.mentionOffset = windowOffset(state.mentionSel, state.mentionOffset, n);
          renderFrame();
        }
        return;
      }
      if (t.key === 'tab' || t.key === 'enter') { acceptMention(); return; }
      if (t.key === 'escape') {
        state.mentionOpen = false;
        state.mentionList = [];
        state.mentionSel = 0;
        state.mentionOffset = 0;
        renderFrame();
        return;
      }
    }
    if (t.key === 'up' || t.key === 'down') {
      const cur = state.input || '';
      if (cur === '') {
        // Empty composer: history owns the key. With NO history the key does
        // nothing — it must not silently scroll the transcript.
        if (state.history.length) {
          if (state.historyIdx === -1) state.historyIdx = state.history.length;
          state.historyIdx = t.key === 'up'
            ? Math.max(0, state.historyIdx - 1)
            : Math.min(state.history.length, state.historyIdx + 1);
          state.input = state.historyIdx >= state.history.length ? '' : (state.history[state.historyIdx] || '');
          state.caret = state.input.length;
          state.composerSel = null;
          refreshMenu(state); renderFrame();
        }
        return;
      }
      const insideW = Math.max(0, dims().cols - 2);
      const layout = composerLayout(state, insideW - 3);
      const dir = t.key === 'down' ? 1 : -1;
      const targetRow = layout.caretRow + dir;
      if (targetRow >= 0 && targetRow < layout.rows.length) {
        // Keep the caret's DISPLAY column, then map it back to a character index
        // on the target row. The old code did `targetStart + colInRow` (adding the
        // row's start offset to the display column), which only works when every
        // row holds the same number of characters — so on wrapped/CJK text an
        // up/down move landed at a wrong (usually left-shifted) position.
        // `composerTextIndexAt` walks the row by display width instead. `caretCol`
        // includes the 1-column border, which this helper does not.
        const colInside = Math.max(0, layout.caretCol - 1);
        state.caret = composerTextIndexAt(layout, targetRow, colInside);
        state.composerSel = null;
        renderFrame(); return;
      }
      // Caret is already on the first/last row: the composer has no further use
      // for the key, so it becomes HISTORY. (Scrolling the transcript is still
      // available on PgUp/PgDn and the wheel — the arrows belong to the input.)
      if (state.history.length) {
        if (state.historyIdx === -1) state.historyIdx = state.history.length;
        state.historyIdx = t.key === 'up'
          ? Math.max(0, state.historyIdx - 1)
          : Math.min(state.history.length, state.historyIdx + 1);
        state.input = state.historyIdx >= state.history.length ? '' : (state.history[state.historyIdx] || '');
        state.caret = state.input.length;
        state.composerSel = null;
        refreshMenu(state); renderFrame(); return;
      }
      return;
    }
    if (t.key === 'wheelup' || t.key === 'wheeldown') {
      // With the pointer ON the scrollbar, scroll one line per notch: the bar is
      // the precision control, and 3-line steps there feel jumpy on a long
      // transcript. Everywhere else keeps the usual 3-line step.
      const onBar = !!(state._lastMouse && isOnScrollbar(state._lastMouse));
      const step = onBar ? 1 : 3;
      const d = t.key === 'wheelup' ? step : -step;
      if (state.panel) {
        const p = state.panel;
        p.top = Math.max(0, (p.top || 0) + (t.key === 'wheelup' ? -3 : 3));
        renderFrame(); return;
      }
      if (state.picker) {
        const n = pickerFiltered(state).length;
        if (n) {
          const cur = Math.min(state.picker.sel, n - 1);
          state.picker.sel = (cur + (t.key === 'wheeldown' ? 1 : n - 1)) % n;
          renderFrame();
        }
        return;
      }
      if (state.menuOpen && state.menuList.length) {
        const n = state.menuList.length;
        const cur = Math.min(state.menuSel, n - 1);
        state.menuSel = (cur + (t.key === 'wheeldown' ? 1 : n - 1)) % n;
        ensureMenuVisible(state);
        renderFrame();
        return;
      }
      // The @ candidate list scrolls its own selection, exactly like /menu —
      // otherwise a wheel notch scrolled the transcript behind an open list.
      if (state.mentionOpen && state.mentionList.length) {
        const n = state.mentionList.length;
        const cur = Math.min(state.mentionSel, n - 1);
        state.mentionSel = (cur + (t.key === 'wheeldown' ? 1 : n - 1)) % n;
        state.mentionOffset = windowOffset(state.mentionSel, state.mentionOffset, n);
        renderFrame();
        return;
      }
      scrollChat(state, d);
      renderFrame(); return;
    }
    if (t.key === 'pageup' || t.key === 'pagedown') {
      if (state.panel) {
        const p = state.panel;
        p.top = Math.max(0, (p.top || 0) + (t.key === 'pageup' ? -10 : 10));
        renderFrame(); return;
      }
      if (state.picker) {
        const n = pickerFiltered(state).length;
        if (n) {
          const cur = Math.min(state.picker.sel, n - 1);
          state.picker.sel = (cur + (t.key === 'pagedown' ? 1 : n - 1)) % n;
          renderFrame();
        }
        return;
      }
      scrollChat(state, t.key === 'pageup' ? 10 : -10);
      renderFrame(); return;
    }
    // Shift+arrows EXTEND a composer selection instead of moving the caret. The
    // anchor is remembered on the first shift-move so moving back shrinks it.
    if (t.key && t.key.startsWith('shift-') && !state.editor && !state.picker && !state.form && !state.panel) {
      const dirName = t.key.slice(6);   // left | right | up | down | home | end
      const cur = state.input || '';
      const caret = state.caret || 0;
      const anchor = state.composerSel ? state.composerSel.anchor : caret;
      let next = caret;
      if (dirName === 'left') {
        const mk = adjacentPasteMarker(cur, caret, -1);
        next = mk ? mk.start : Math.max(0, caret - 1);
        state._caretPrefCol = null;
      } else if (dirName === 'right') {
        const mk = adjacentPasteMarker(cur, caret, 1);
        next = mk ? mk.end : Math.min(cur.length, caret + 1);
        state._caretPrefCol = null;
      } else if (dirName === 'home') {
        next = 0;
        state._caretPrefCol = null;
      } else if (dirName === 'end') {
        next = cur.length;
        state._caretPrefCol = null;
      } else {
        // up/down: move a visual row keeping the column, like the plain arrows, so
        // a multi-line prompt can be selected across lines. Same sticky column as
        // the plain ↑/↓ (see verticalCaretIndex).
        const insideW = Math.max(0, dims().cols - 2);
        const layout = composerLayout(state, insideW - 3);
        const targetRow = layout.caretRow + (dirName === 'down' ? 1 : -1);
        if (targetRow < 0 || targetRow >= layout.rows.length) { renderFrame(); return; }
        next = verticalCaretIndex(state, cur, layout, targetRow);
      }
      state.caret = next;
      state.composerSel = (anchor === next) ? null : { anchor, head: next };
      renderFrame(); return;
    }




    if (t.key === 'left' || t.key === 'right') {
      const dir = t.key === 'left' ? -1 : 1;
      const mk = adjacentPasteMarker(state.input, state.caret || 0, dir);
      if (mk) {
        state.caret = dir < 0 ? mk.start : mk.end;
      } else if (dir < 0) {
        state.caret = Math.max(0, (state.caret || 0) - 1);
      } else {
        state.caret = Math.min(state.input.length, (state.caret || 0) + 1);
      }
      // A horizontal move abandons the sticky column (kimi's setCursorCol).
      state._caretPrefCol = null;
      state.composerSel = null;
      renderFrame(); return;
    }
    if (t.key === 'home') {
      const insideW = Math.max(0, dims().cols - 2);
      const layout = composerLayout(state, insideW);
      const starts = rowStartOffsets(state.input || '', layout.rows.length, insideW);
      state.caret = starts[layout.caretRow] != null ? starts[layout.caretRow] : 0;
      state._caretPrefCol = null;
      state.composerSel = null;
      renderFrame(); return;
    }
    if (t.key === 'end') {
      const insideW = Math.max(0, dims().cols - 2);
      const layout = composerLayout(state, insideW);
      const starts = rowStartOffsets(state.input || '', layout.rows.length, insideW);
      const next = starts[layout.caretRow + 1];
      state.caret = (next != null ? next - 1 : (state.input || '').length);
      state.caret = Math.max(0, Math.min((state.input || '').length, state.caret));
      state._caretPrefCol = null;
      state.composerSel = null;
      renderFrame(); return;
    }

    if (t.key === 'enter') {
      // Enter commits whatever is in the composer. When the `/` MENU is open it
      // selects a command, but the composer's own text is still what was typed —
      // it must be consumed either way, or the typed "/yolo" stayed on screen
      // after the command ran (forced submission skips the composer reset).
      const fromMenu = state.menuOpen && state.menuList.length;
      const selItem = fromMenu ? state.menuList[state.menuSel] : null;
      // An entry from the SECOND level (arguments) is not a command name: it must
      // never be turned into `submit('/' + name)`. That is what produced
      // "Unknown command: /" — typing an argument that matches no completion
      // (`/trim 0`, `/web 0.0.0.0`) left a hint-only row selected, and Enter sent
      // the literal "/". `_cmdName` marks a row as belonging to the argument level.
      const argLevel = !!(selItem && selItem._cmdName);
      if (argLevel && selItem._argWord && selItem.name) {
        // A real completion: insert the word and keep the composer, so the user
        // can go on filling the arguments.
        acceptMenuSelection(state);
        refreshMenu(state);
        renderFrame();
      } else if (argLevel) {
        // The hint-only row (nothing left to complete): submit exactly what the
        // user typed, e.g. "/trim 0", so the command runs and reports its own
        // usage — instead of a bogus "/".
        submit();
        state.input = ''; state.caret = 0;
        state.pastes.clear(); state.pasteCounter = 0;
        state.composerSel = null;
        renderFrame();
      } else if (fromMenu) {
        submit('/' + state.menuList[state.menuSel].name);
        state.input = ''; state.caret = 0;
        state.pastes.clear(); state.pasteCounter = 0;
        state.composerSel = null;
        renderFrame();
      } else {
        submit();
        state.composerSel = null;
      }
      return;
    }
    if (t.key === 'newline') {
      state.input = (state.input || '').slice(0, state.caret) + '\n' + (state.input || '').slice(state.caret);
      state.caret++;
      state.composerSel = null;
      refreshMenu(state); renderFrame(); return;
    }
    if (t.key === 'c-d') {
      if ((state.input || '') === '') { quit(); return; }
      return;
    }
    if (t.key === 'backspace') {
      // In shell mode with an empty buffer there is nothing to delete, so the
      // Backspace reads as "remove the `!`" and drops back to prompt mode —
      // exactly the kimi-code behaviour.
      if (state.inputMode === 'bash' && state.input.length === 0 && !(state.composerSel && state.composerSel.anchor !== state.composerSel.head)) {
        state.inputMode = 'prompt';
        renderFrame();
        return;
      }
      const sel = state.composerSel;
      if (sel && sel.anchor !== sel.head) {
        const a = Math.min(sel.anchor, sel.head);
        const h = Math.max(sel.anchor, sel.head);
        state.input = state.input.slice(0, a) + state.input.slice(h);
        state.caret = a;
      } else if (state.caret > 0) {
        const mk = adjacentPasteMarker(state.input, state.caret, -1);
        if (mk) {
          state.input = state.input.slice(0, mk.start) + state.input.slice(mk.end);
          state.caret = mk.start;
          state.pastes.delete(mk.id);
        } else {
          state.input = state.input.slice(0, state.caret - 1) + state.input.slice(state.caret);
          state.caret--;
        }
      }
      // Deleting can also change the mention (or delete the `@` itself), so the
      // inline list is refreshed the same way as on a printable key.
      refreshMention();
      if (!state.mentionOpen) refreshMenu(state);
      renderFrame(); state.composerSel = null; return;
    }
    if (t.key === 'delete') {
      const sel = state.composerSel;
      if (sel && sel.anchor !== sel.head) {
        const a = Math.min(sel.anchor, sel.head);
        const h = Math.max(sel.anchor, sel.head);
        state.input = state.input.slice(0, a) + state.input.slice(h);
        state.caret = a;
      } else {
        const mk = adjacentPasteMarker(state.input, state.caret, 1);
        if (mk) {
          state.input = state.input.slice(0, mk.start) + state.input.slice(mk.end);
          state.pastes.delete(mk.id);
        } else if (state.caret < state.input.length) {
          state.input = state.input.slice(0, state.caret) + state.input.slice(state.caret + 1);
        }
      }
      refreshMenu(state); renderFrame(); state.composerSel = null; return;
    }
    if (t.paste !== undefined) {
      // A bracketed paste (Ctrl+Shift+V in most terminals): shared with the
      // Ctrl+Shift+V shortcut and the right-click menu's Paste.
      //
      // An EMPTY bracketed paste is the signal that the clipboard held something
      // the terminal cannot send as text — an image. That is exactly what the other
      // agents do on paste (kimi: onPasteImage; claude: empty-paste -> read
      // clipboard; cline: paste event with an image/* mime type), so fall through
      // to the clipboard reader instead of inserting nothing. Without this, pasting
      // a screenshot in Windows Terminal did nothing at all.
      if (t.paste === '') {
        void pasteFromClipboard();
        renderFrame(); return;
      }
      insertComposerPaste(t.paste);
      renderFrame(); return;
    }
    if (t.ch) {
      // `!` on an EMPTY prompt toggles shell mode instead of being inserted — the
      // `!` becomes the prefix, so the buffer holds only the command. Mirrors
      // kimi-code's editor: the marker never enters the text, so the caret never
      // steps over it and submit never strips it.
      if (t.ch === '!' && state.inputMode !== 'bash' && state.input.length === 0) {
        state.inputMode = 'bash';
        state.composerSel = null;
        renderFrame();
        return;
      }
      state.input = state.input.slice(0, state.caret) + t.ch + state.input.slice(state.caret);
      state.caret++;
      state.composerSel = null;
      // Any printable character can extend or start an `@mention`, so refresh the
      // inline list on every keystroke: typing `@` opens it, and typing after it
      // narrows it — the same live-feedback the `/` menu gives. In shell mode
      // there are no @mentions or slash-commands to offer, so skip both.
      if (state.inputMode !== 'bash') {
        refreshMention();
        if (!state.mentionOpen) refreshMenu(state);
      }
      renderFrame();
    }
  }


  function rowStartOffsets(text, rowCount, insideW) {
    const starts = [];
    const prefix = ' > ';
    const cont = '   ';
    let base = 0;
    const paras = String(text).split('\n');
    for (let pi = 0; pi < paras.length; pi++) {
      const p = paras[pi];
      const pre = pi === 0 ? prefix : cont;
      const bodyW = Math.max(1, insideW - visualCol(pre));
      const segs = wrapWithOffsets(p, bodyW);
      for (let si = 0; si < segs.length; si++) starts.push(base + segs[si].start);
      base += p.length + 1;
    }
    return starts;
  }

  // Where the caret lands after a VERTICAL move (↑/↓, plain or Shift+).
  //
  // A faithful port of kimi-code's editor (packages/pi-tui/src/components/editor.ts):
  // `moveToVisualLine()` + `computeVerticalMoveColumn()` + its sticky
  // `preferredVisualCol`. The UNITS are what the previous attempt got wrong —
  // everything below is a CHARACTER offset, never a display column:
  //   * `layout.meta[i].start/.end` are character indices into the whole buffer;
  //   * a row's length is `end - start` CHARACTERS, and the caret's column is
  //     measured from that row's `start` (kimi: `cursorCol - vl.startCol`);
  //   * `layout.caretCol` is NOT usable here: it is `1 + prefixWidth +
  //     displayColumns`, so it mixes in the `❯ ` prefix and counts a double-width
  //     glyph as two. Comparing that against a character length is what made the
  //     caret walk left and right instead of holding its column.
  //
  // Decision table (P = a preference is stored, S = the caret sits mid-row,
  // T = this row is shorter than the current column, U = this row is shorter than
  // the preference), verbatim from kimi:
  //   !P || S : T -> store current, go to row end   |  else -> clear, keep current
  //   P       : T || U -> go to row end (keep pref) |  else -> use pref, clear it
  function verticalCaretIndex(state, text, layout, targetRow) {
    const curMeta = layout.meta[layout.caretRow];
    const targetMeta = layout.meta[targetRow];
    if (!curMeta || !targetMeta) return state.caret;

    const rowLen = (m) => Math.max(0, m.end - m.start);
    // Only the LAST wrap segment of a logical line may put the caret at the line's
    // end; on any other segment the caret stops one character short, or it would sit
    // on the first character of the next row and ↑/↓ would look like it skipped one.
    const isLastSeg = (m) => (m.segIdx || 0) >= (m.segCount || 1) - 1;
    const maxColOf = (m) => (isLastSeg(m) ? rowLen(m) : Math.max(0, rowLen(m) - 1));

    const currentVisualCol = state.caret - curMeta.start;
    const sourceMaxVisualCol = maxColOf(curMeta);
    const targetMaxVisualCol = maxColOf(targetMeta);

    const hasPref = state._caretPrefCol != null;                          // P
    const cursorInMiddle = currentVisualCol < sourceMaxVisualCol;         // S
    const targetTooShort = targetMaxVisualCol < currentVisualCol;         // T
    const targetCantFitPref = hasPref && targetMaxVisualCol < state._caretPrefCol; // U

    let moveTo;
    if (!hasPref || cursorInMiddle) {
      if (targetTooShort) { state._caretPrefCol = currentVisualCol; moveTo = targetMaxVisualCol; }
      else { state._caretPrefCol = null; moveTo = currentVisualCol; }
    } else if (targetTooShort || targetCantFitPref) {
      moveTo = targetMaxVisualCol;
    } else {
      moveTo = state._caretPrefCol;
      state._caretPrefCol = null;
    }

    // kimi clamps against the end of the LOGICAL line, so a caret pushed past the
    // target segment still lands inside the line rather than mid-buffer.
    const paraMeta = layout.meta.filter((m) => m.line === targetMeta.line);
    const paraEnd = (paraMeta[paraMeta.length - 1] || targetMeta).end;
    return Math.min(targetMeta.start + Math.max(0, moveTo), Math.max(targetMeta.start, paraEnd));
  }

  function statusExtra(state) {
    // Neither the notice nor the confirm prompt appears here: both are drawn ON the
    // context row rather than taking one of their own, so neither may shrink the
    // calculated chat viewport either.
    return (state.running ? 1 : 0)
      + ((state.menuOpen && state.menuList.length) ? Math.min(state.menuList.length, MAX_MENU) + 1 : 0);
  }

  // Whether tools may touch paths OUTSIDE the workspace. Its own switch (/external)
  // rather than a property of the permission mode: the old code made Auto and Yolo
  // imply it, so merely switching mode handed out filesystem-wide reach — and it
  // MUTATED cfg, leaving the grant in place after switching back to Ask.
  // Read live, so a /external flip applies to the very next tool call.
  function externalAllowed() {
    return !!cfg.allowExternal;
  }

  function scrollChat(state, delta) {
    const cols = dims().cols, rows = dims().rows;
    // Only the TOTAL row count is needed to clamp the scroll position. This used to
    // call the full renderer with no viewport, which renders every message's rows —
    // so each wheel tick re-rendered the entire transcript just to learn a number,
    // and scrolling a long session stalled. chatRowTotal reuses the last paint's
    // metrics when the transcript has not changed, which is the scrolling case.
    const total = chatRowTotal(state, cols);
    const ch = Math.max(1, rows - (composerHeight(state, cols) + statusExtra(state) + STATUS_H + CTX_H));
    const maxScroll = Math.max(0, total - ch);
    state.scroll = Math.min(maxScroll, Math.max(0, (state.scroll || 0) + delta));
    // A deliberate move: the previous frame's anchor no longer describes where the
    // user is looking, so the next paint must seed a fresh one from this value.
    dropScrollPin(state);
  }

  async function submit(forceText) {
    // `forceText` means the text came from somewhere other than the composer
    // (the queue drain). Clearing the composer in that case would throw away
    // whatever the user has typed SINCE queueing — so only reset it when we are
    // actually submitting the composer's own content. The composer/menu state
    // is always reset, since the prompt is being consumed either way.
    const fromComposer = forceText === undefined;
    const raw = fromComposer ? state.input : forceText;
    let text = expandPastes(raw, state.pastes).trim();
    if (fromComposer) {
      state.input = ''; state.caret = 0;
      state.pastes.clear(); state.pasteCounter = 0;
    }
    state.menuOpen = false; state.menuList = []; state.menuSel = 0;
    state.mentionOpen = false; state.mentionList = []; state.mentionSel = 0;
    state.mentionOffset = 0;
    state.historyIdx = -1;
    if (!text) { renderFrame(); return; }
    if (!state.running) {
      state.turnStart = Date.now();
      // Start animation: 0.5s type out + 0.5s fill with orange = 1s total
      state.startAnim = { start: Date.now() };
      // Marks the tick the steady pulse begins on, so the pulse can start its
      // own orange -> yellow sweep instead of inheriting whatever phase the
      // spinner happens to be in when the start animation ends.
      state.pulseStart = null;
    }
    
    if (state.history[state.history.length - 1] !== text) {
      state.history.push(text);
      saveHistory(state.history);   // persist so ↑ survives a restart
    }
    // Shell passthrough. The MODE is authoritative (the `!` never entered the
    // buffer); a leading `!` in the text is still honoured so a pasted line like
    // `!git status` behaves the same as typing it.
    if (state.inputMode === 'bash' || text.startsWith('!')) {
      const cmd = text.replace(/^!+/, '').trim();
      state.inputMode = 'prompt';   // one command per activation, like kimi
      if (!cmd) { renderFrame(); return; }
      await runShellCommand(cmd);
      return;
    }
    // Commands are handled immediately, never queued: queuing them delayed a
    // /plan or /model until the running turn finished, which is not what
    // typing a command means.
    if (text.startsWith('/')) {
      const sp = text.indexOf(' ');
      const c = sp === -1 ? text : text.slice(0, sp);
      const arg = sp === -1 ? '' : text.slice(sp + 1).trim();
      // A command that rejects must NOT take the process down. `dispatch` is async
      // and was called without a .catch(), so any throw inside a command (e.g. the
      // registry browser hitting a bad field) surfaced as an unhandledRejection,
      // which the process handler turns into process.exit(1) — the whole session
      // died with no in-UI explanation. Catch here, report, and keep running.
      Promise.resolve(dispatch(c, arg, state, cfg, session, host, submit, stdout))
        .catch((err) => {
          try { host.notice(`/${String(c).replace(/^\//, '')} failed: ${(err && err.message) || err}`, 'error'); }
          catch { /* the UI itself is broken; the process handler will log it */ }
          try { renderFrame(); } catch { /* ignore */ }
        });
      if (state._quit) { quit(); return; }
      renderFrame();
      return;
    }
    if (state.running && state.agent) {
      state.queued.push(text);
      // QUEUED, not steered: the message waits and becomes its own turn once
      // this one finishes (the drain after agent.run()). It must NOT be handed
      // to the running turn — Ctrl-S is the explicit "inject it now" shortcut.
      renderFrame();
      // The queue pane is a status field; make sure the web UI sees it NOW rather
      // than whenever the next paint happens to sync. The web queue panel lagged
      // by a minute or more because it only rode along on whatever broadcast a
      // turn happened to trigger next. Push an independent `queued` event so the
      // browser updates the queue pane immediately (claude-code-style granular
      // event instead of a full-status snapshot).
      if (web) void syncWeb();
      if (web && hub) { try { hub.pubStatusField('queued', [...state.queued]); } catch { /* best-effort */ } }
      return;
    }

    await runAgent(text);
  }

  // `!command` — run a shell command directly, without the model.
  //
  // The composer path is deliberately bypassed: the command runs through the same
  // Bash tool the agent uses (so it gets the same timeout, cwd, output
  // sanitising and truncation), but its result is rendered as a `↳` receipt and
  // NOT sent to the model. That is the point — a quick `git add -A && git push`
  // should be instant and predictable, not a round-trip the agent might reword.
  //
  // The command is echoed into the transcript so the scrollback shows what was
  // run, and it is kept out of `session.messages` so it does not pollute the
  // conversation the model sees.
  async function runShellCommand(cmd) {
    const started = Date.now();
    // Echo the command as a dedicated `bash` role so the transcript renders it
    // with SHELL MODE styling (violet frame + `!` glyph). It is recorded in
    // session.shellHistory (persisted, shown on resume) but NEVER in
    // session.messages, so the model never sees the command.
    addChat({ role: 'bash', text: cmd });
    // Record the command for the NEXT session's display. It lives in its own
    // field, not session.messages, so it survives a restart for the user to see
    // but is never sent to the model. `anchor` remembers WHERE in the
    // conversation this shell command ran (how many real messages came before
    // it), so a resume can put it back in that spot instead of appending it at
    // the very end. The result/exit is patched once it runs.
    if (session) {
      session.shellHistory = session.shellHistory || [];
      session.shellHistory.push({ cmd, ts: Date.now(), ok: null, anchor: (session.messages || []).length });
    }
    state.scroll = 0;
    dropScrollPin(state);   // jump to the tail: reseed the anchor on paint
    state.running = true;
    state.startAnim = { start: Date.now() };
    renderFrame();

    let out = '';
    let failed = false;
    try {
      const bash = getTool('Bash');
      if (!bash) {
        out = 'Error: the Bash tool is unavailable.';
        failed = true;
      } else {
        const result = await bash.execute(
          { command: cmd, description: 'shell passthrough' },
          // `allowExternal` follows the /external SETTING, not a hardcoded true.
          // A `!` passthrough bypasses the approval prompt by design (it is the
          // user's own command), but the workspace path guard is a separate
          // decision — hardcoding it here meant `!cat ../secrets` reached outside
          // the workspace even with /external off.
          { ...cfg, cwd: state.cwd || state.workspace, workspace: state.workspace || state.cwd, allowExternal: externalAllowed() },
        );
        out = String(result == null ? '' : result);
        failed = isFailureResult(out, 'Bash');
      }
    } catch (e) {
      out = `Error running command: ${e.message}`;
      failed = true;
    } finally {
      state.running = false;
    }

    addChat({ role: 'tool_result', text: out, failed });
    const ms = Date.now() - started;
    addChat({ role: 'system', text: `[${cmd.split('\n')[0]} — ${failed ? 'failed' : 'done'} in ${fmtDuration(ms)}]` });
    // Close the tail of the shellHistory entry pushed at the start: mark it
    // done/failed with a short result preview, then persist the session so the
    // command (and its outcome) survives a restart.
    if (session && Array.isArray(session.shellHistory) && session.shellHistory.length) {
      const last = session.shellHistory[session.shellHistory.length - 1];
      last.ok = !failed;
      last.doneAt = Date.now();
      last.result = String(out || '').slice(0, 500);   // keep a peek, bound it
      try { sess.saveSession(session); } catch { /* best-effort */ }
    }
    // A shell command can change the working tree, so refresh the git badge now
    // rather than waiting for the next TTL tick.
    refreshGitInfo(state, { force: true });
    renderFrame();
  }

  // `asSystem` injects the text as a SYSTEM message instead of a user message and
  // skips the user bubble. Used by the approved-plan handoff: the plan is not
  // something the user typed, so it must not appear (or persist) as their message.
  async function runAgent(text, opts = {}) {
    // Drop any compaction row left dangling by an interrupted turn so the next
    // auto-compaction starts clean (no ghost 'running' row that blinks with nothing
    // behind it). The live reference is dropped too.
    const asSystem = !!opts.asSystem;
    // `bubbleText` overrides the row drawn in the transcript. A SKILL activation has
    // already drawn its own card (see dispatch), so it passes the user's args here
    // only to feed the MODEL — with no args that is '', and a user bubble for an
    // empty string would show a blank `❯` row under the card.
    const bubble = opts.bubbleText != null ? opts.bubbleText : text;
    if (!asSystem && String(bubble).trim()) addChat({ role: 'user', text: bubble, _conv: true });
    // Fresh buffer for this turn's plan-tag split (see appendAssistant).
    state._planBuf = '';
    // A message the user JUST SENT should always bring the newest content into
    // view, even if they were scrolled up reading history. (Queue/steer do NOT
    // come through here, so they keep the view exactly where the user left it.)
    state.scroll = 0;
    dropScrollPin(state);   // jump to the tail: reseed the anchor on paint
    // Should THIS turn produce the session title? Decided BEFORE the user message
    // is appended to the history: the old test lived in the system-prompt builder
    // and checked `session.messages.length === 0`, but by then the message was
    // already in there, so the injection never fired and no session was ever
    // auto-titled.
    //
    // The `state.titleAttempts` cap is what makes a FAILED naming retryable. The
    // old test (`session.messages.length === 0`) was true on the first turn only,
    // so one offline/aborted/empty reply left the session nameless for good — the
    // comment on generateTitle claimed it "simply tries again" but nothing did.
    // A few extra attempts cover a transient failure without paying for a naming
    // request on every turn of a session the user never wanted named.
    const TITLE_ATTEMPT_LIMIT = 3;
    if (state.titleAttempts == null) state.titleAttempts = 0;
    const needsTitle = !!session && !session.title && state.titleAttempts < TITLE_ATTEMPT_LIMIT;
    state.titleAttempts++;
    state.running = true;
    // Pick the Working… wording ONCE for this turn, so it does not change while
    // the gradient loops. The next turn picks a new one.
    state.workMsg = WORKING_MESSAGES[Math.floor(Math.random() * WORKING_MESSAGES.length)];
    state.rounds = (state.rounds || 0) + 1;
    state._stepsBase = state.steps || 0;
    state._turnSteps = 0;
    // Re-base the start animation to THIS instant and paint immediately.
    // submit() set startAnim before `running` was true, so nothing could render
    // yet; by the time a frame was actually drawn the 1s animation had already
    // run out and the type-out was never seen. Stamping it here — the first
    // moment the row can be painted — makes the animation start on screen.
    state.startAnim = { start: Date.now() };
    state.pulseStart = null;
    renderFrame();
    if (session) session.rounds = state.rounds;
    // The system message is pinned to the front and is NOT persisted to the
    // session (persisting it would pile up one copy per turn). Any older system
    // entry in the history is skipped, so the CURRENT prompt is the only one
    // used:
    //   * a custom prompt from /set-system-prompt (config.toml `system_prompt`),
    //     falling back to the built-in SYSTEM_PROMPT;
    //   * plus the COOL-MODE instruction appended when that mode is ON, so the
    //     model stops narrating what it is about to do and why.
    const basePrompt = (cfg.systemPrompt && String(cfg.systemPrompt).trim()) || SYSTEM_PROMPT;
    let sysText = basePrompt;

    // APPEND rather than replace — the safer of the two prompt knobs, and the one to reach
    // for when the built-in prompt already does most of what you want.
    if (cfg.appendSystemPrompt && String(cfg.appendSystemPrompt).trim()) {
      sysText += '\n\n' + String(cfg.appendSystemPrompt).trim();
    }

    if (cfg.calmMode) {
      sysText += '\n\n' + CALM_MODE_INSTRUCTION;
    }
    // PLAN MODE (/plan): tell the model what to PRODUCE. The tool filter alone
    // only removed its write tools — this is what makes it emit a plan block. A user's own
    // `plan_instructions` is APPENDED, never substituted: replacing this would silently
    // switch Plan mode back to the behaviour the instruction exists to fix.
    if (state.plan) {
      sysText += '\n\n' + PLAN_MODE_INSTRUCTION;
      if (cfg.planInstructions && String(cfg.planInstructions).trim()) {
        sysText += '\n\n' + String(cfg.planInstructions).trim();
      }
    }
    // SWARM MODE (/swarm): push the model toward parallel decomposition.
    if (state.swarm) {
      sysText += '\n\n' + SWARM_MODE_INSTRUCTION;
      if (cfg.swarmInstructions && String(cfg.swarmInstructions).trim()) {
        sysText += '\n\n' + String(cfg.swarmInstructions).trim();
      }
    }
    // FOCUS MODE has no built-in instruction — the tool filter IS its behaviour — so this
    // is the only place to say anything about it.
    if (state.focus && cfg.focusInstructions && String(cfg.focusInstructions).trim()) {
      sysText += '\n\n' + String(cfg.focusInstructions).trim();
    }
    const personal = readPersonalPrompt(state.workspace || cfg.workspace);
    if (personal) {
      sysText += '\n\n' + personal;
    }
    // Agent memory: notes the model wrote for itself in earlier sessions (the
    // Memory tool). Read fresh each turn like the preferences above, so an edit
    // lands on the next prompt. Injected AFTER the user's preferences: the user's
    // standing instructions outrank the model's own earlier notes.
    const memory = readMemory(state.workspace || cfg.workspace);
    if (memory) {
      sysText += '\n\n' + memory;
    }
    // OUTPUT STYLE (/output-style): a form-of-reply instruction read from a file,
    // re-read per turn like the notes above so editing the file takes effect on the
    // next request. Placed AFTER the preferences and memory but BEFORE AGENTS.md:
    // the project's own instructions are the most specific thing here and must win.
    if (state.outputStyle && state.outputStyle.body) {
      sysText += '\n\n' + styleReminder(state.outputStyle);
    }
    // AGENTS.md: the PROJECT's own instructions, read fresh each turn like the
    // personal notes above, so an edit (or a fresh /init) takes effect on the next
    // prompt. Injected LAST and deepest-last so a nested file outranks the root one,
    // which is the precedence order codex documents. Previously /init wrote this
    // file and nothing ever loaded it.
const agents = readAgentsMd(state.cwd || state.workspace || cfg.workspace, state.workspace || cfg.workspace);
    if (agents) {
      sysText += '\n\n' + agents;
    }
    let messages = [{ role: 'system', content: sysText }];
    // Mixin seam: let plugins rewrite the assembled system prompt before the turn.
    try { sysText = await runPatch('systemPrompt', { text: sysText }, (c) => c.text); messages = [{ role: 'system', content: sysText }]; } catch (e) { console.error('[hncode-plugin] systemPrompt patch error:', e.message); }
    // A skill body is injected as its OWN system message so it reaches the model
    // but never appears (or persists) as the user's words, mirroring kimi's
    // activation card. It is filtered out of the saved session like sysText.
    if (opts.skillBody) messages.push({ role: 'system', content: opts.skillBody });
    if (session.messages && session.messages.length) {
      for (const m of session.messages) {
        if (m.role === 'system') continue;
        // Drop an assistant message carrying neither content nor toolCalls — the
        // residue of an old bug.
        if (m.role === 'assistant'
            && !(typeof m.content === 'string' && m.content.trim())
            && !(Array.isArray(m.toolCalls) && m.toolCalls.length)) {
          continue;
        }
        messages.push(m);
      }
    }
    // The approved-plan handoff arrives as a SYSTEM message: it is an instruction
    // from the harness, not something the user typed, and it must not show up as a
    // user bubble or be persisted as one.
    //
    // A SKILL activation's `text` is only the `/skill:<name>` marker. Sending that as
    // the user turn told the model nothing and DROPPED the user's own instruction
    // (`/skill:foo make it blue` lost "make it blue"). So:
    //   * with args  -> the args ARE the user turn (the body rides a system message);
    //   * without args -> there is no user text at all. Pushing the marker would put
    //     the literal `/skill:foo` into the conversation, which is worse than an empty
    //     turn: the model reads it as the user having typed a command. The skill body
    //     is the whole instruction in that case, so no user message is added.
    const argsText = opts.bubbleText != null ? String(opts.bubbleText).trim() : '';
    const isSkill = opts.bubbleText != null;
    if (asSystem) messages.push({ role: 'system', content: text });
    else if (isSkill && !argsText) { /* body-only activation: nothing for the user turn */ }
    else messages.push({ role: 'user', content: opts.modelText != null ? opts.modelText : (argsText || text) });
    // Only the conversation is persisted; the system message does not go into the
    // session. Saving a turn is left to the end of the turn (after agent.run) —
    // writing mid-turn would make sending feel sluggish.
    //
    // The assembled prompt is parked on `state` instead, for the length of the turn. It
    // cannot live in `session.messages` (see contextSegments): the array is trimmed to
    // non-system roles here and again at every step boundary, so with nothing carrying the
    // text the status bar's `system prompt` segment collapses to zero columns and vanishes
    // mid-turn, then returns at turn end when the untrimmed request is assigned back.
    state.turnSystemPrompt = sysText;
Object.assign(session, { model: cfg.model, messages: messages.filter((m) => m.role !== 'system') });
    // The user's message is on disk before the agent has done anything. A crash
    // this early used to lose the entire prompt, because the first save was at
    // turn end.
    try { sess.saveSession(session); } catch { }

    // Called at every step boundary. `messages` is the array the agent appends to,
    // so re-filtering it into the session and writing to disk keeps the saved
    // transcript within one step of what is on screen. Cheap: saveSession is a
    // synchronous write of one JSON file, and a step is seconds apart.
    function persistTurnProgress(list) {
      if (!session || !Array.isArray(list)) return;
      session.messages = list.filter((m) => m.role !== 'system');
      session.rounds = state.rounds || session.rounds;
      session.steps = state.steps || session.steps;
      session.todos = state.todos || session.todos;
      session.mode = state.mode || session.mode;
      try { sess.saveSession(session); } catch { }
    }

    // Focus is a ONE-TURN mode: it narrows the toolset for the turn the user set it
    // on, and turns itself off when that turn ends (see the end of this function).
    // Remember the value HERE, at the start, so that a /focus the user sets while the
    // turn is running survives instead of being cancelled by the turn-end cleanup.
    const focusAtTurnStart = !!state.focus;
    if (state.plan) {
      cfg.toolFilter = ['Read', 'Grep', 'Glob'];
    } else if (state.focus) {
      cfg.toolFilter = ['Read', 'Write', 'Edit', 'Bash'];
    } else {
      cfg.toolFilter = undefined;
    }

    // Outside-the-workspace access is NO LONGER implied by the permission mode.
    // Auto and Yolo used to lift the tool-layer workspace check as a
    // side effect of auto-approving, which meant switching mode silently granted
    // filesystem-wide reach — and it MUTATED cfg, so one auto turn left
    // `allowExternal` permanently true even after switching back to Ask.
    //
    // It is now an explicit, persisted setting: /external [on|off], stored as
    // `tool_allow_external_paths` (or HNCODE_ALLOW_EXTERNAL=1 per session). The mode
    // decides whether a tool needs ASKING; this decides whether the path guard at
    // the tool layer lets the call through at all.
    const mode = state.mode || 'ask';
    cfg.allowExternal = externalAllowed();
    // AskUserQuestion reads this to refuse in auto mode. Set here so the FIRST
    // tool call of the turn already sees it (onApproval re-syncs it live after).
    cfg.permissionMode = mode;


    // Approval callback: called before every tool execution
    const onApproval = async (toolName, args) => {
      // Read the mode LIVE: /permission, /yolo and /auto can change while the
      // turn runs, and the decision must follow the CURRENT setting.
      const cur = state.mode || 'ask';
      // Keep the TOOL LAYER in step with the LIVE state. Agent snapshots cfg into
      // its own ctx at construction, so mutating cfg alone would not reach a turn
      // that is already running. Two things depend on this:
      //   * allowExternal — resolvePath()'s workspace guard. It follows the
      //     /external SETTING alone; the permission mode must not widen it, or
      //     switching to Auto would hand out filesystem-wide reach as a side
      //     effect of a mode change.
      //   * permissionMode — AskUserQuestion refuses to ask while auto is on
      if (state.agent && state.agent.ctx) {
        state.agent.ctx.allowExternal = externalAllowed();
        state.agent.ctx.permissionMode = cur;
      }



      // Standing rules come FIRST, before every mode rule, so:
      //   * a `deny` cannot be escaped by switching to Auto / Yolo;
      //   * an explicit `ask` still prompts even in a mode that auto-approves;
      //   * an `allow` spares the user the same prompt on every turn.
      const rule = decideFromRules(cfg.permissions, toolName, args);
      if (rule === 'deny') {
        appErr(`${toolName} is blocked by a permission rule (deny).`);
        return false;
      }
      if (rule === 'allow') return true;
      // `ask` falls through to the prompt below, skipping the mode shortcuts.

      if (rule !== 'ask') {
        if (cur === 'auto') return true;
      }
      // Session approvals (Ctrl+A on a prompt) come AFTER the configured rules and
      // BEFORE the mode shortcuts:
      //   * after, so a `deny` or an explicit `ask` rule still wins — a transient
      //     grant must not override a decision the user wrote down;
      //   * before, so an approval covers the modes that would otherwise ask again.
      // A destructive command is excluded inside the check, whatever was approved.
      {
        const destructive = toolName === 'Bash'
          && isDestructiveCommand(String((args && (args.command || args.cmd)) || ''));
        if (rule !== 'ask' && isApprovedForSession(session.sessionApprovals, toolName, args, destructive)) {
          return true;
        }
      }
      // Read-only tools never need permission in any mode. AskUserQuestion is on
      // this list because ASKING the user is not a side effect — gating it behind
      // an approval prompt would mean answering two prompts to ask one question.
      // (In auto mode the TOOL refuses itself before any UI; see ctx.permissionMode.)
      const safeTools = ['Read', 'Grep', 'Glob', 'FetchURL', 'WebSearch', 'TaskOutput', 'TaskList', 'TaskStop', 'TaskWait', 'TodoList', 'FileLines', 'AskUserQuestion'];
      if (rule !== 'ask' && safeTools.includes(toolName)) return true;
      // A read-only SHELL COMMAND (ls/git status/rg/cat …) is as safe as a
      // read-only TOOL, so it runs without a prompt in Ask mode too — the user
      // has no decision to make about `git log`. Only in `ask`; an explicit
      // `ask` rule above still wins, and YOLO/AUTO never reach here anyway.
      if (cur === 'ask' && rule !== 'ask' && toolName === 'Bash') {
        const c = String((args && (args.command || args.cmd)) || '');
        if (isReadOnlyCommand(c) && !isDestructiveCommand(c)) return true;
      }


      // Yolo: anything that stays INSIDE the workspace runs
      // without asking — edits, writes and commands alike. Only work that touches
      // a path OUTSIDE the workspace (or a command whose target we cannot prove is
      // inside) needs the user.
      //
      // BASH is the exception: a shell command's paths cannot be proven either way
      // (variables, pipes, subshells), so the old path heuristic flagged ordinary
      // commands like `ls /tmp` and asked about them. In yolo the user has already
      // said "run routine work", so Bash runs without the workspace test — only an
      // obviously destructive command still asks.
      if (cur === 'yolo' && rule !== 'ask') {
        if (toolName === 'Bash') {
          const cmd = String((args && (args.command || args.cmd)) || '');
          if (!isDestructiveCommand(cmd)) return true;
        } else if (isInsideWorkspace(state, toolName, args)) {
          return true;
        }
      }



      return new Promise((resolve) => {
        let desc = '';
        if (args && typeof args === 'object') {
          const keyArgs = args.path || args.file_path || args.pattern || args.command || args.url || args.query || '';
          desc = String(keyArgs).split('\n')[0].slice(0, 120);
        }
        
        // Lines to display. A Bash command (or any long argument) is shown in
        // FULL — collapsing it hid exactly what the user must review.
        const detail = [];
        const rawArg = (args && typeof args === 'object')
          ? (args.command || args.cmd || args.pattern || args.path || args.file_path || args.url || args.query || null)
          : null;
        if (typeof rawArg === 'string' && rawArg.length) {
          for (const ln of rawArg.replace(/\r\n/g, '\n').split('\n')) detail.push(ln);
        }
        // The prompt must NOT touch the composer: the user may already be typing,
        // and only Enter/Esc belong to the prompt.
        state.approvalPending = { toolName, args, desc, resolve, detail };
        renderFrame();
      });
    };
    
    // Seed the agent with the persisted list: Agent() otherwise starts from an
    // empty todoState, which wiped the panel on every new turn.
    cfg.todoState = state.todos || [];
    // AskUserQuestion bridge: the tool calls ctx.askQuestion(questions, ctx) and
    // awaits the answers. Same promise-handshake the approval prompt uses, so the
    // agent simply blocks while the user reads and chooses.
    cfg.askQuestion = (questions, ctx) => new Promise((resolve) => {
      state.question = {
        items: questions,
        index: 0,
        sel: 0,
        picked: new Set(),
        answers: {},
        // Free-text state. `editing` is null | 'other' | 'supplement' and says
        // WHICH row is open; `editingText` is its live buffer. The committed
        // values live in `otherText` / `supplement` so an Esc back-out keeps them.
        editing: null,
        editingText: '',
        // Caret position (character index) inside the free-text buffer. Lets
        // Left/Right move within the field instead of only appending at the end.
        editingCaret: 0,
        otherText: '',
        supplement: '',
        resolve: (answers) => resolve(answers),
      };
      // An aborted turn must not leave the dialog stranded on screen.
      const sig = ctx && ctx.signal;
      const onAbort = () => {
        if (state.question && state.question.resolve === resolve) {
          state.question = null;
          resolve({});
          renderFrame();
        }
      };
      if (sig) {
        if (sig.aborted) { onAbort(); return; }
        sig.addEventListener('abort', onAbort, { once: true });
      }
      renderFrame();
    });
    // Open a file-history turn BEFORE the agent can write anything (file-history.js):
    // the first write to a file in this turn snapshots its pre-turn content, which
    // is exactly what /undo restores. Recorded even when nothing is written, so the
    // index stays lined up one-to-one with the user prompts /undo counts.
    if (session) beginTurn(session.id);
    const agent = new Agent({
      // maxSteps omitted: the agent loop is uncapped (see agent.js).
      // sessionId makes the prompt-cache key stable per session (see cache.js).
      // `tasks` is handed to the agent so its ctx REUSES the same store: background
      // bash jobs and background subagents outlive the turn that started them, and
      // a fresh store per turn made them disappear (while still running).
      // `swarm` rides the per-turn cfg so the Agent can gate AgentSwarm on it: the
      // mode is on `state`, but a tool the model is OFFERED is decided in the
      // constructor, which only ever sees cfg. Read here rather than relying on the
      // `/swarm` handler writing cfg, so a session resumed with swarm on gets the
      // tool and a session with it off never does.
      cfg: { ...cfg, swarm: !!state.swarm, sessionId: (session && session.id) || cfg.sessionId, tasks: (state.tasks = state.tasks || {}) },
      messages, onApproval,
      // Shell hooks are re-read per turn so an edit to hooks.json (or a /hooks
      // change) takes effect on the next message without restarting.
      hookConfig: loadHooks(cfg.workspace).hooks,
      onEvent: (e) => {
        // Everything the MODEL streams counts toward the tok/s meter: reasoning
        // chunks carry `text` just like answer chunks do.
        //
        // `_tokTimes` is (re)created here rather than assumed. It used to be
        // initialized only by /new, so a RESTORED session (`hncode --continue`,
        // /sessions) had it undefined and the very first streamed token threw
        // "Cannot read properties of undefined (reading 'push')" — killing the TUI
        // mid-answer with nothing printed, because this runs inside the agent's
        // onEvent and the exit handler wipes the alternate screen. The tok/s timer
        // already tolerated a missing array; the producer did not.
        const tokTimes = state._tokTimes || (state._tokTimes = []);
        if (e.text) {
          const now = Date.now();
          for (let k = 0, t = estimateTokens(e.text); k < t; k++) tokTimes.push(now);
        }
        // Tool-call ARGUMENTS are model output too (a Write's content, a long
        // Bash command) and used to show 0 tok/s while they streamed. Only the
        // argument stream counts: `tool_output` is the tool RUNNING, and a
        // tool_result is a later turn's input, not tokens the model produced.
        if (e.type === 'tool_args' && e.chunk) {
          const now = Date.now();
          for (let k = 0, t = estimateTokens(e.chunk); k < t; k++) tokTimes.push(now);
        }
        if (e.type === 'step_start') {
          state._turnSteps = (state._turnSteps || 0) + 1;
          state.steps = (state._stepsBase || 0) + state._turnSteps;
          if (session) session.steps = state.steps;
          // Persist at every step boundary, not only at turn end. `messages` is the
          // SAME array this Agent appends to, so copying it here captures every
          // completed step: a crash mid-turn then loses at most the step in flight
          // instead of the whole turn.
          persistTurnProgress(messages);
          renderSoon();
          return;
        }
        if (e.type === 'compacting') {
          // Open a LIVE compaction block (kimi's CompactionComponent): a blinking
          // bullet while the summary round-trip runs, so the turn does not sit
          // silent for seconds. The same row is upgraded in place on `compacted`.
          // If a compaction block from a PREVIOUS (interrupted) turn is still in the
          // transcript, settle it first so we never leave two blinking rows or let a
          // stale cancelled block get re-promoted to running.
          const stale = state.compactionMsg;
          if (stale && state.chat.indexOf(stale) >= 0 && stale.phase !== 'running') {
            const idx = state.chat.indexOf(stale); if (idx >= 0) state.chat.splice(idx, 1);
          } else if (stale && state.chat.indexOf(stale) < 0) {
            for (let i = state.chat.length - 1; i >= 0; i--) {
              if (state.chat[i] && state.chat[i].role === 'compaction') state.chat.splice(i, 1);
            }
          }
          state.compactionMsg = {
            role: 'compaction', phase: 'running', startedAt: Date.now(),
            instruction: e.instruction || '',
          };
          addChat(state.compactionMsg);
          renderSoon();
          return;
        }
        if (e.type === 'compacted') {
          state.ctxTokens = e.after || state.ctxTokens;
          state.ctxPercent = usagePercent(state.ctxTokens, state.ctxMax || 1);
          // Settle the live block rather than pushing a second row: the header
          // becomes "Compaction complete (X → Y tokens)" and the summary stays
          // hidden behind Ctrl+O.
          const block = state.compactionMsg;
          if (block) {
            block.phase = 'done';
            block.tokensBefore = e.before;
            block.tokensAfter = e.after;
            block.text = e.summary || '';
            block._cache = null;
            state.compactionMsg = null;
          } else {
            addChat({
              role: 'compaction', phase: 'done',
              tokensBefore: e.before, tokensAfter: e.after, text: e.summary || '',
            });
          }
          renderSoon();
          return;
        }
        if (e.type === 'compaction_cancelled') {
          // The user interrupted an auto-compaction. Settle the live block so it
          // stops blinking and reads as cancelled (nothing was trimmed).
          const block = state.compactionMsg;
          if (block) { block.phase = 'cancelled'; block._cache = null; state.compactionMsg = null; }
          else addChat({ role: 'compaction', phase: 'cancelled' });
          renderSoon();
          return;
        }
        if (e.type === 'incomplete') {
          // Orange: this is a warning, not ordinary system output.
          addChat({ role: 'warn', text: `Stopped: ${e.reason}. The task may be unfinished — send another message to continue.` });
          return;
        }
        if (e.type === 'data') {
          // Feed the answer text into the paced buffer instead of painting it. The
          // buffer closes any open reasoning region itself, in arrival order, so the
          // block settles exactly when the provider moved on rather than when the next
          // render happened to run.
          //
          // The push RETURNS the characters that are due right now, and they are
          // already off the buffer's queue — applying them is what keeps the delta
          // whole. Dropping the return value silently lost the head of every delta.
          applyStreamOps(streamBuf.pushText(e.text));
          renderSoon(); return;
        }
        if (e.type === 'context') {
          // Live context gauge: the agent reports the estimated request size once
          // per step, so the header and /usage track the growing history.
          state.ctxTokens = e.tokens || 0;
          state.ctxMax = e.max || state.ctxMax;
          state.ctxPercent = usagePercent(state.ctxTokens, state.ctxMax || 1);
          // Keep a bounded series of step sizes so /usage can draw the trend.
          if (!Array.isArray(state.tokenHistory)) state.tokenHistory = [];
          const h = state.tokenHistory;
          if (h[h.length - 1] !== state.ctxTokens) h.push(state.ctxTokens);
          if (h.length > 240) h.splice(0, h.length - 240);
          // Mirror onto the session so saveSession (which persists the whole
          // session object) captures it: a --resume restores the trend chart.
          if (session) {
            if (!Array.isArray(session.tokenHistory)) session.tokenHistory = [];
            if (session.tokenHistory[session.tokenHistory.length - 1] !== state.ctxTokens) session.tokenHistory.push(state.ctxTokens);
            if (session.tokenHistory.length > 240) session.tokenHistory.splice(0, session.tokenHistory.length - 240);
          }
          renderSoon(); return;
        }
        if (e.type === 'usage') {
          // Real token accounting from the provider. Folded into a session total
          // that /usage and /cost report, and persisted with the session so a
          // --resume does not lose what the session has already spent.
          //
          // The COST is recomputed from the total rather than accumulated per
          // event: switching models mid-session would otherwise price every
          // earlier request at the new model's rates.
          if (!state.usage) state.usage = {};
          state.usage = addUsage(state.usage, e.usage);
          if (session) session.usage = state.usage;
          state.lastUsage = e.usage;
          refreshCost(state, cfg);
          renderSoon(); return;
        }
        if (e.type === 'think') {
          state.seenThinking = true;
          // Reasoning goes through the SAME buffer as the answer, so both are paced
          // together and reveal in arrival order. Pacing only the answer would let a
          // reasoning block pop in provider-sized clumps. The push's return value
          // carries the characters due now — see the `data` handler above.
          applyStreamOps(streamBuf.pushReasoning(e.text));
          renderSoon(); return;
        }
        if (e.type === 'aborted') {
          // Show whatever the model had actually produced before the interrupt: the
          // buffer is holding it, and an aborted turn is exactly when the user is
          // reading to see how far it got.
          flushStream();
          const t = [...state.chat].reverse().find((m) => m.role === 'thinking' && m.pending);
          if (t) t.pending = false;
          // Settle any RUNNING tool rows too. A tool that was mid-flight when the
          // user hit Esc never gets its tool_result, so its `pending` stayed true
          // and the `Using <Tool>` name kept pulsing forever. Clearing it drops the
          // name to plain cyan immediately.
          for (const m of state.chat) {
            if (m.role === 'tool' && m.pending) { m.pending = false; m.failed = true; }
          }
          // Use a special role that won't show the ✓ icon
          state.chat.push({ role: 'aborted', text: C.red + 'interrupted' + C.reset });
          renderFrame();
          return;
        }
        if (e.type === 'steer') {
          // The agent injected a steered message into the running turn.
          const qm = [...state.chat].reverse().find((m) => m.role === 'queued' && m.text === e.text)
            || [...state.chat].reverse().find((m) => m.role === 'queued');
          if (qm) qm.role = 'steer';
          const qi = state.queued.indexOf(e.text);
          if (qi >= 0) state.queued.splice(qi, 1);
          // The steered message just left the queue: push the new list to the web
          // queue pane immediately, or it lags until the next whole-status sync.
          if (web && hub) { try { hub.pubStatusField('queued', [...state.queued]); } catch { /* best-effort */ } }
          renderSoon();
          return;
        }
        if (e.type === 'tool_start') {
          // A tool call means the model finished this step's reasoning and is now
          // acting on it, so the turn's text has to be fully on screen first: the tool
          // row is drawn UNDER the reply, and text still trickling in afterwards would
          // push it back down. Draining the buffer here is what keeps that from
          // happening, and it settles the pending thinking block as a side effect (the
          // close marker rides in the same ordered queue).
          // The NEXT `think` event opens a new block under the tool output.
          flushStream();
          settleThinking();
          const dup = state.chat.some((m) => m.role === 'tool' && m.pending && m.id === e.id);
          if (!dup) {
            state.chat.push({ role: 'tool', toolName: e.name, toolArgs: {}, pending: true, id: e.id, streamContent: '', startAt: Date.now(), _conv: true });
          }
        } else if (e.type === 'tool_args') {
          const entry = [...state.chat].reverse().find((m) => m.role === 'tool' && m.pending && m.id === e.id);
          if (entry) {
            // Incremental scan: each chunk is parsed ONCE and the parse state
            // carries forward. Re-parsing the whole accumulated blob per chunk was
            // O(n²) and froze the UI on a large Write (see createArgStream).
            if (!entry._argStream) entry._argStream = createArgStream();
            feedArgStream(entry._argStream, e.chunk);
            // Track the key argument as it streams so "Using Bash (cmd)" shows
            // the command DURING the run rather than only once it has finished.
            entry.toolArgs = { ...(entry.toolArgs || {}), ...entry._argStream.pairs };
            if (entry.toolName === 'Write') {
              entry.streamContent = argStreamValue(entry._argStream, 'content');
              // Incremental line count so the preview's "… N more lines" note is
              // exact without re-scanning the whole content every frame.
              entry._streamLineCount = argStreamLineCount(entry._argStream, 'content');
            }
          }
          renderSoon(); return;
        } else if (e.type === 'tool_output') {
          // Live output from a running tool (Bash): append it to the matching
          // "Using …" row so the command's output is visible before it finishes.
          const entry = [...state.chat].reverse().find((m) => m.role === 'tool' && m.pending && m.id === e.id)
            || [...state.chat].reverse().find((m) => m.role === 'tool' && m.pending);
          if (entry) {
            // Bounded to a TAIL. This string is mirrored into the hub row and
            // shipped over SSE on every patch, so leaving it unbounded grew the
            // TUI's row, the hub's row and the browser's copy together, once per
            // chunk. Only the tail is ever displayed.
            entry.liveOutput = tailChars(
              (entry.liveOutput || '') + e.chunk,
              LIVE_OUTPUT_MAX_CHARS,
            );
            // A swarm streams `[n/m] finished` lines as subagents land: advance the
            // matching cells from queued -> completed so the grid fills in live.
            if (entry.toolName === 'AgentSwarm' && Array.isArray(entry.swarmMembers)) {
              const done = (String(entry.liveOutput).match(/^\[\d+\/\d+\] finished$/gm) || []).length;
              entry.swarmMembers.forEach((mem, i) => {
                if (i < done) { mem.phase = 'completed'; mem.ratio = 1; }
                else if (i === done) { mem.phase = 'working'; mem.ratio = 0.5; }
              });
            }
            renderSoon();
          }
          return;
        } else if (e.type === 'tool_use') {
          const entry = [...state.chat].reverse().find((m) => m.role === 'tool' && m.pending && m.id === e.id)
            || [...state.chat].reverse().find((m) => m.role === 'tool' && m.pending && m.toolName === e.name);
          if (entry) {
            entry.toolArgs = { ...(entry.toolArgs || {}), ...(e.args || {}) };
            // AgentSwarm: turn the args into a live member list so the progress
            // block renders from the moment the swarm is announced. Every item
            // starts "queued" and flips as the tool reports progress.
            if (e.name === 'AgentSwarm') {
              const a = entry.toolArgs || {};
              entry.swarmDescription = a.description || '';
              entry.swarmModel = a.subagent_type || '';
              if (!entry.swarmMembers && Array.isArray(a.items)) {
                entry.swarmMembers = a.items.map(() => ({ phase: 'queued', ratio: 0, latestText: '' }));
              }
            }
            // Edit: build the +/- diff. The tool now reports the text it actually
            // replaced on the tool_result (`editDiff`), which is the only way a
            // LINE-RANGE edit (start_line/end_line/new_content) can produce a
            // diff — it has no `old_string` in its args. Args still seed a
            // provisional diff so the rows appear while the edit is still running.
            if (e.name === 'Edit' && e.args && typeof e.args.old_string === 'string') {
              let startLine = 1;
              try {
                const file = path.isAbsolute(e.args.path || '') ? e.args.path : path.resolve(state.cwd, e.args.path || '');
                const before = fs.readFileSync(file, 'utf8').split(/\r?\n/);
                const at = before.indexOf(String(e.args.old_string).split(/\r?\n/)[0]);
                if (at >= 0) startLine = at + 1;
              } catch { }
              entry.diff = lineDiff(e.args.old_string, e.args.new_string, startLine);
            }
          }
          // The args just changed: repaint so "Using <Tool> (<arg>)" appears
          // as soon as they arrive instead of waiting for the next event.
          renderSoon();
        } else if (e.type === 'tool_result') {
          const entry = [...state.chat].reverse().find((m) => m.role === 'tool' && m.pending && m.id === e.id)
            || [...state.chat].reverse().find((m) => m.role === 'tool' && m.pending && m.toolName === e.name);
          // A failed run must be visible on the TOOL line too: the status bullet
          // turns red (see messageLines).
          const failedRun = isFailureResult(e.content, e.name);
          if (entry) {
            entry.pending = false; entry.id = undefined; entry.failed = failedRun;
            // The AUTHORITATIVE diff comes from the tool itself (`editDiff`): it
            // knows the text it really replaced, so this is the only source that
            // covers line-range edits. Fall back to the provisional diff built
            // from the args for older/other callers.
            if (e.editDiff && typeof e.editDiff.old === 'string') {
              entry.diff = lineDiff(e.editDiff.old, e.editDiff.new, e.editDiff.startLine || 1);
            }
            // Hand the counts to the TOOL row (which keeps `+N -N` next to its
            // name) and the diff to the RESULT row (rendered beneath the `↳`).
            if (entry.diff) entry._diffCounts = entry.diff;
            // A finished swarm has no `↳` dump: the progress block IS the result.
            // Settle every member so the grid and the pip bar read as final.
            if (entry.toolName === 'AgentSwarm' && Array.isArray(entry.swarmMembers)) {
              entry.swarmFailed = failedRun;
              entry.swarmMembers.forEach((mem) => {
                if (mem.phase === 'queued' || mem.phase === 'working' || mem.phase === 'prompting') {
                  mem.phase = failedRun ? 'failed' : 'completed';
                }
                mem.ratio = mem.phase === 'completed' ? 1 : mem.ratio;
              });
            }
          }
          // An AgentSwarm is the ONE exception: it has already rendered its own
          // result as the live progress block above (cells + status pip bar), so a
          // `↳ Swarm finished: …` dump underneath would print the same thing twice.
          const isSwarm = e.name === 'AgentSwarm' && entry && Array.isArray(entry.swarmMembers);
          // No diff for Write. A write REPLACES a file rather than editing a span of
          // it, so the "before/after" the renderer would show is the whole old
          // content against the whole new one — a new file turns into every line
          // being an addition, and the result row fills the screen with `+` lines
          // that say nothing about what the model did. The receipt line ("File
          // written: … N bytes") already reports the outcome, and the Write row
          // itself streams the content while it arrives.
          const resultMsg = normalizeMsg({
            role: 'tool_result', text: e.content, failed: failedRun,
            diff: e.name === 'Write' ? undefined : (entry && entry.diff),
            // `bodyOnToolRow`: the TOOL row already drew this result's body (a Write
            // streams the file's content there), so the receipt below it must not
            // open a second `↳` block. Without this flag the renderer could only
            // guess, and it guessed wrong — a Write showed
            //     ↳  1 line one
            //     ↳ File written: a.txt (1372 bytes)
            // with two markers for one body.
            bodyOnToolRow: e.name === 'Write' && !!(entry && entry.streamContent),
            _conv: true,
});
          if (entry && !isSwarm) {
            const at = state.chat.indexOf(entry);
            // Skip any rows already sitting between the call and the transcript
            // tail (the result rows of EARLIER calls in this same step), so each
            // block reads call -> its result -> call -> its result.
            let ins = at + 1;
            while (ins < state.chat.length && state.chat[ins].role === 'tool_result') ins++;
            state.chat.splice(ins, 0, resultMsg);
            renderFrame();
          } else if (!isSwarm) {
            addChat(resultMsg);
          } else {
            renderFrame();
          }
          // NOTE: queued input is deliberately NOT drained into the running turn
          // here. A message typed while the agent works is a NEW turn, so it waits
          // for this turn to finish (see the drain after `agent.run()`). Ctrl-S
          // remains the explicit "steer it into the running turn now" escape hatch.
          // A finished tool result IS a completed step, so the transcript is
          // persisted here too — the other half of the step-boundary save above.
          persistTurnProgress(messages);
        } else if (e.type === 'error') addChat({ role: 'tool_result', text: (e.error && e.error.message) || String(e.error) });
        else if (e.type === 'truncation_recovery') {
          // The answer hit the output cap mid-way and the agent asked the model to
          // continue. Without a row here the transcript simply grew a second
          // assistant bubble with no sign of why, which reads as a glitch.
          addChat({ role: 'system', text: `Output limit reached — the answer continues (attempt ${e.attempt}/3).` });
        }
        else if (e.type === 'results_trimmed') {
          // Old tool result bodies were replaced by a pointer to disk to shrink the
          // request (agent.js's trim pass). Say so, including that nothing was lost:
          // without a row the transcript quietly looks like output went missing, and
          // the user has no way to know the text is still readable.
          addChat({ role: 'system', text: `Trimmed ${e.elided} old tool result(s) to free context (${fmtTokens(e.before)} → ${fmtTokens(e.after)}); the removed text is saved on disk. You can modify or disable this feature by using "/auto-trim"` });
        }
else if (e.type === 'todos') { state.todos = e.todos || []; if (session) session.todos = state.todos; if (web && hub) { try { hub.pubStatusField('todos', [...state.todos]); } catch { /* best-effort */ } } }
        renderFrame();
      },
    });
    state.agent = agent;
    if (agent.ctx && agent.ctx.tasks) state.tasks = agent.ctx.tasks;
    if (web && hub) { try { hub.pubStatusField('tasks', Object.values(state.tasks || {}).map((t) => ({ id: t.id || t.taskId || '', kind: t.kind || 'bash', status: t.status || 'running', summary: t.summary || t.description || t.prompt || '', startedAt: t.startedAt || t.startAt || 0, agentId: t.agentId || '' }))); } catch { /* best-effort */ } }
    // A background subagent (Agent {run_in_background:true}, or an AgentSwarm)
    // finishes AFTER the turn that launched it returned. The tools call
    // `ctx._onBackgroundTaskDone`, which nothing installed, so the parent was
    // never told: its result sat in the task store until the user opened /tasks.
    // Post it into the transcript when it lands (mirroring how a queued message
    // arrives after the turn), so the parent model sees it on its next turn.
    if (agent.ctx) {
      agent.ctx._onBackgroundTaskDone = (task) => {
        if (!task) return;
        // kimi-style lifecycle card: bullet colour by phase, a headline naming
        // the kind (agent / bash / question task) and what happened, and a dim
        // detail line. The task's conclusion is kept as the expandable body.
        const card = backgroundTaskCard(task);
        const body = String(task.output || '').trim();
        addChat({ role: 'bg_task', card, text: body });
      };
    }
    await agent.run();
    messages = agent.messages;
    if (agent.ctx && agent.ctx.tasks) state.tasks = agent.ctx.tasks;
    state.agent = null;
    if (web && hub) { try { hub.pubStatusField('tasks', Object.values(state.tasks || {}).map((t) => ({ id: t.id || t.taskId || '', kind: t.kind || 'bash', status: t.status || 'running', summary: t.summary || t.description || t.prompt || '', startedAt: t.startedAt || t.startAt || 0, agentId: t.agentId || '' }))); } catch { /* best-effort */ } }
    const liveThink = [...state.chat].reverse().find((m) => m.role === 'thinking' && m.pending);
    if (liveThink) liveThink.pending = false;
    // The first turn also names the session. It runs HERE — after the answer is
    // complete — because the old code tried to parse a title out of the streamed
    // chunks while `state.running` was still true, so the branch never fired. It
    // is a separate, tiny request rather than an instruction in the system prompt:
    // a hidden instruction leaked into the answer and a heading-like first chunk
    // was mistaken for the title.
    if (needsTitle) await generateTitle(text);


    // ---- PLAN MODE: finalize the plan and ask to proceed --------------------
    // The plan bubble is ALREADY on screen (appendAssistant streams the text after
    // the plan tag straight into it), so this only: closes the tags out of the prose,
    // asks for approval, and clears the streaming buffer.
    let approvedPlan = null;
    if (state.plan) {
      // Clearing the buffer is what makes the rest of this block correct, and it was
      // the one part the comment above promised and the code never did: the review
      // prompt and the plan the user approves are read OUT of the bubbles, while the
      // paced buffer can still be holding the tail of the reply (a burst drains over
      // seconds). Reading early summarised — and approved — a truncated plan.
      flushStream();
      const lastAssistant = [...state.chat].reverse().find((m) => m.role === 'assistant' && (m.text || '').trim());
      // Prefer what arrived on the wire; fall back to scanning the prose for the
      // case where the tags were split across bubbles.
      const streamedPlan = [...state.chat].reverse().find((m) => m.role === 'plan');
      const planText = (streamedPlan && String(streamedPlan.text).trim())
        || extractPlan(lastAssistant ? lastAssistant.text : '');
      if (planText) {
        // Make sure the bubble holds the final, complete text, and drop any
        // leftover tag remnants from the prose.
        if (streamedPlan) streamedPlan.text = planText;
        else addChat({ role: 'plan', text: planText });
        if (lastAssistant) {
          lastAssistant.text = String(lastAssistant.text).replace(/<\/?plan>/gi, '').trim();
          // This is a REPLACEMENT, not an append, so the length-based render-cache
          // fingerprint could coincide with the previous value and leave a stale
          // frame. Drop the cache explicitly.
          lastAssistant._cache = null;
          if (!lastAssistant.text.trim()) {
            const i = state.chat.indexOf(lastAssistant);
            if (i >= 0) state.chat.splice(i, 1);
          }
        }
        // ask / yolo -> the user decides; auto -> approved without asking, which
        // is the whole point of Auto. The review resolves to one of
        // 'approve' | 'edit' | 'keep':
        //   approve — execute the plan as written
        //   edit    — open the plan in the editor, then execute the EDITED text
        //   keep    — stay in Plan mode, do not execute
        const cur = state.mode || 'ask';
        let outcome = cur === 'auto' ? 'approve' : await new Promise((resolve) => {
          state.planPending = { plan: planText, resolve };
          renderFrame();
        });
        state.planPending = null;
        if (outcome === 'edit') {
          // Let the user revise the plan before it is executed. The editor is
          // synchronous from the agent's point of view: we wait for save.
          const edited = await new Promise((resolve) => {
            openEditor({
              title: 'Review plan — edit before executing',
              text: planText,
              caretRow: 0,
              caretCol: 0,
              onSave: (value) => resolve(String(value || '').trim()),
              onCancel: () => resolve(null),
            });
            renderFrame();
          });
          if (edited) {
            // Keep the on-screen bubble in sync with the edited text.
            const bubble = [...state.chat].reverse().find((m) => m.role === 'plan');
            if (bubble) { bubble.text = edited; bubble._cache = null; }
            approvedPlan = edited;
            outcome = 'approve';
          } else {
            outcome = 'keep';
          }
        }
        if (outcome === 'approve') {
          approvedPlan = planText;
          // Persist the approved plan next to the project so it survives the
          // session and can be reviewed with the change (or handed to an issue).
          try {
            const saved = savePlan(planText, state.workspace || cfg.workspace);
            if (saved.ok) addChat({ role: 'system', text: `Plan saved: ${saved.path}` });
          } catch { /* persistence is best-effort */ }
        }
      }
    }

    const approx = estimateMessagesTokens(messages, cfg);
    state.ctxTokens = approx;
    state.ctxMax = cfg.maxContextTokens || state.ctxMax;
    state.ctxPercent = usagePercent(approx, state.ctxMax);
    // `session.messages` now holds the full request, system prompt included, so the bar
    // reads the real text from here on and the turn-scoped copy must not be counted too.
    state.turnSystemPrompt = null;
    session.messages = messages;
    session.rounds = state.rounds;
    session.steps = state.steps;
    session.rounds = state.rounds;
    session.steps = state.steps;
    // The todo list is part of the session's visible state: persist it here
    // too, so resuming (or `hncode -c`) brings the panel back.
    session.todos = state.todos || [];
    // Focus is one turn: the turn it was set for has now ended, so it goes off. Done
    // HERE, before the save below, so `session.focus` is written false and resuming
    // the session does not bring the narrowed toolset back. `focusAtTurnStart` (not
    // the current value) decides, so a /focus issued while the turn ran still stands.
    if (focusAtTurnStart) state.focus = false;
    session.focus = !!state.focus;
    session.swarm = !!state.swarm;
    // The turn's token totals, so a resumed session keeps the running cost rather
    // than restarting it at zero (the numbers have to sum across the whole
    // session for a cost readout to mean anything).
    session.usage = state.usage || {};
    sess.saveSession(session);
    const turnMs = state.turnStart ? Date.now() - state.turnStart : 0;
    const dur = fmtDuration(turnMs);
    // The live row is `<phrase> <gray>[<dur>]`. At the end we keep the same row
    // shape — `[<word> <dur>]` — and only rewrite the word, so the brackets and
    // the duration stay put and the time is never repeated. `…` is part of the
    // phrase and is preserved.
    const wordFrom = String(state.workMsg || WORKING_MESSAGES[0]);
    state.finishAnim = {
      start: Date.now(),
      wordFrom,
      wordTo: 'turn took',
      tail: ` ${dur}]`,   // fixed right-hand side, e.g. " 59s]"
    };
    const animStart = Date.now();
    while (Date.now() - animStart < 520) {
      renderFrame();
      await new Promise((r) => setTimeout(r, 20));
    }
    state.finishAnim = null;
    // Also clear startAnim if it's still active (should be cleared already by composeFrame)
    state.startAnim = null;
    // The turn is over: everything the model said must be on screen NOW. Draining here
    // is what stops the last of the reply from trickling out behind the "[turn took …]"
    // row and behind whatever the next turn draws.
    flushStream();
    state.running = false;
    // The agent may have written or edited files this turn: refresh the git badge
    // now so the diff totals reflect it immediately, instead of waiting for the
    // 15s timer.
    refreshGitInfo(state, { force: true });

    if (turnMs > 0) {
      state.lastTurnMs = turnMs;
      session.lastTurnMs = turnMs;
      sess.saveSession(session);
      // The turn is on screen but may NOT be on disk. A save failure was silent apart
      // from a line in ~/.hncode/session-errors.log, and a session whose transcript had
      // grown past the string limit failed every save for over an hour without the user
      // being told — each turn looked saved and was not. Say so where they are looking.
      const saveErr = sess.lastSaveFailure();
      if (saveErr && saveErr.id === session.id) {
        addChat({ role: 'warn', text: `This turn could NOT be saved: ${saveErr.detail}. The conversation is on screen only — see ~/.hncode/session-errors.log.` });
      }
      // Same shape the sweep animated into: `[turn took <dur>]`.
      addChat({ role: 'system', text: `[turn took ${dur}]` });
    }
    renderFrame();
    if (state.queued.length) {
      // Anything still queued was never injected (the turn ended first), so it
      // becomes its own turn. Texts the agent DID consume were removed from
      // state.queued by the `steer` handler above.
      const next = state.queued.shift();
      if (next) { void submit(next); }
      // Queue shrank: push the updated list to the web queue pane immediately.
      if (web && hub) { try { hub.pubStatusField('queued', [...state.queued]); } catch { /* best-effort */ } }
    }
    // Approved plan: Plan mode OFF (write tools come back), then re-enter the agent
    // with the plan as a SYSTEM message. Deliberately NOT via submit(): that path
    // posts a user bubble and re-runs the whole submit flow, which is what produced
    // a stray user message and an extra turn teardown before the work started.
    // Done LAST so it cannot race the queue drain above.
    if (approvedPlan) {
      state.plan = false;
      session.plan = false;
      persistState();
      addChat({ role: 'system', text: 'Plan approved — Plan mode is off, executing.' });
      renderFrame();
      void runAgent(PLAN_EXECUTE_PREFIX, { asSystem: true });
    }
  }

  // Remember the session's working mode (permission / plan / focus / effort)
  // so resuming it comes back the way the user left it. Written immediately:
  // these are settings, not conversation, and must survive an abrupt exit.
  function persistState() {
    if (!session) return;
    session.mode = state.mode;
    session.plan = !!state.plan;
    session.planPath = state.planPath || null;
    session.focus = !!state.focus;
    session.swarm = !!state.swarm;
    session.effort = state.effort || '';
    // Theme removed - forced dark only
    session.steps = state.steps || 0;
    session.rounds = state.rounds || 0;
    if (state.lastTurnMs) session.lastTurnMs = state.lastTurnMs;
    // How much of the display-only transcript reaches disk. Persisted with the rest of the
    // session settings, so `/save-history` survives a restart instead of silently reverting
    // to the default on the next launch.
    session.saveHistory = state.saveHistory !== false;
    session.saveThinking = state.saveThinking !== false;
    try { sess.saveSession(session); } catch {}
  }

  // ---- /web: serve this session to a browser ---------------------------------
  // Started on demand. The browser talks to the SAME session: prompts it sends go
  // through `submit` (identical to typing), slash commands through `dispatch`, and
  // its transcript is the TUI's own `state.chat` mirrored by syncChat() on every
  // paint. Nothing here reimplements agent behaviour — it only relays.
  async function startWeb(bindIp, port) {
    if (web) { notice(`Web UI already running at ${web.url}`); return web; }
    hub = new SessionHub();
    // Actions the browser can take. Each one calls the SAME function the keyboard
    // calls, which is what keeps the two front-ends behaviourally identical.
    hub.actions.submit = async (text) => {
      if (typeof text !== 'string' || !text.trim()) throw new Error('empty message');
      await submit(text);
    };
    hub.actions.dispatch = async (cmd, arg) => {
      const name = String(cmd || '').trim();
      if (!name.startsWith('/')) throw new Error('not a command');
      const sp = name.indexOf(' ');
      const c = sp === -1 ? name : name.slice(0, sp);
      const a = sp === -1 ? String(arg || '') : name.slice(sp + 1).trim();
      dispatch(c, a, state, cfg, session, host, submit, stdout);
      if (state._quit) quit();
      renderFrame();
    };
    hub.actions.interrupt = async () => {
      if (!state.agent || typeof state.agent.interrupt !== 'function') throw new Error('nothing is running');
      state.agent.interrupt();
    };
    hub.actions.stopTask = async (id) => {
      const ctxLike = state.agent && state.agent.ctx ? state.agent.ctx : { tasks: state.tasks };
      stopTask(ctxLike, String(id || ''));
    };
    hub.actions.setMode = async (mode) => {
      const m = String(mode || '');
      if (!['ask', 'yolo', 'auto'].includes(m)) throw new Error('unknown mode: ' + m);
      setPermission(state, m);
      persistState();
      renderFrame();
    };
    hub.actions.shell = async (cmd) => {
      const c = String(cmd || '').trim();
      if (!c) throw new Error('empty command');
      await runShellCommand(c);
    };
    // The two handshakes the agent blocks on. Resolving these from the browser is
    // what lets a phone answer an approval the terminal is showing.
    hub.actions.approve = async (id, ok) => {
      const ap = state.approvalPending;
      if (!ap) throw new Error('no approval is pending');
      state.approvalPending = null;
      ap.resolve(!!ok);
      renderFrame();
    };
    // The plan under review in Plan mode. Same idea as `approve`: the turn is blocked on a
    // promise, and a browser has to be able to settle it. Without this, a plan raised in
    // Plan mode left the web UI stuck on a spinning turn with no way forward except finding
    // the terminal that raised it.
    hub.actions.answerPlan = async (id, outcome) => {
      const pp = state.planPending;
      if (!pp) throw new Error('no plan is pending');
      const want = String(outcome || '').toLowerCase();
      // The terminal produces exactly these three (handleKey: enter -> approve, e -> edit,
      // esc -> keep). An unknown one is refused rather than coerced, so a stale browser tab
      // cannot settle a review with a meaning nobody chose.
      if (!['approve', 'edit', 'keep'].includes(want)) {
        throw new Error(`unknown plan outcome: ${outcome} (expected approve, edit or keep)`);
      }
      state.planPending = null;
      pp.resolve(want);
      renderFrame();
    };
    // The full-screen editor's Save and Cancel, so the six commands that open one
    // (/memory, /personal, /permissions, /output-style, /keybindings, /set-system-prompt)
    // are usable from a browser. They call the SAME `onSave` the terminal's Ctrl+S calls,
    // so a value written from the web takes the identical path — including the validation
    // the command puts in its own onSave.
    hub.actions.saveEditor = async (id, text) => {
      const ed = state.editor;
      if (!ed) throw new Error('no editor is open');
      if (typeof ed.onSave !== 'function') {
        throw new Error('this editor is read-only: no onSave handler');
      }
      const value = String(text == null ? '' : text);
      // Close first, then save: onSave may itself open a picker or write a notice, and it
      // must not be overwritten by a stale editor still being on screen.
      state.editor = null;
      renderFrame();
      ed.onSave(value);
    };
    hub.actions.cancelEditor = async (id) => {
      if (!state.editor) throw new Error('no editor is open');
      state.editor = null;
      renderFrame();
    };
    hub.actions.answerQuestion = async (id, answers, extra, note, advance) => {
      const q = state.question;
      if (!q) throw new Error('no question is pending');
      const list = Array.isArray(answers) ? answers : [];
      const cur = (q.items && q.items[q.index]) || {};
      const key = cur.question || 'answer';
      // The per-question answer: the picked option label(s), unless a free-text
      // "Other" was provided (then that wins, matching the terminal).
      const other = extra == null ? '' : String(extra).trim();
      if (other) q.answers[key] = other;
      else if (list.length) q.answers[key] = list.join(', ');
      // The whole-request note is only meaningful on the last question; store it
      // for the final resolve rather than as this question's answer.
      if (note != null) q.supplement = String(note);

      const total = (q.items || []).length;
      const isLast = q.index >= total - 1;
      const more = advance !== false && !isLast;
      if (more) {
        // Advance to the next question and let the status broadcast re-open the
        // modal with it. Do NOT resolve yet — the agent is still blocked.
        q.index += 1;
        q.sel = 0;
        q.picked = new Set();
        try { syncWebNow(); } catch { /* best-effort */ }
        renderFrame();
        return { ok: true, index: q.index, total };
      }
      const answersOut = { ...q.answers };
      state.question = null;
      q.resolve({ answers: answersOut, additional: q.supplement || '' });
      try { syncWebNow(); } catch { /* best-effort */ }
      renderFrame();
      return { ok: true, done: true };
    };

    // ---- session settings the browser can change ------------------------------
    //
    // Every one of these runs the SAME code the terminal's slash command does, and
    // persists, so a change made in the browser survives a restart and shows up in
    // the terminal immediately. Nothing is reimplemented here — the point is that
    // the two front-ends are views of one session.

    /** Push the transcript and status to the hub right now, not on the next paint. */
    function syncWebNow() {
      if (!web || !hub) return;
      try { hub.syncChat(state.chat); } catch { /* the UI must never break the TUI */ }
      try { hub.setStatus(webStatus()); } catch { /* best-effort */ }
      renderFrame();
    }

    hub.actions.setTitle = async (title) => {
      const t = String(title || '').trim();
      if (!t) throw new Error('title required');
      session.title = t.slice(0, 200);
      try { sess.saveSession(session); } catch { /* the title is cosmetic */ }
      stdout.write(`\x1b]0;${session.title}\x07`);
      syncWebNow();
    };


    // Steer: inject text into the RUNNING turn instead of queueing a new one.
    // `agent.steer()` buffers it for the next model call — nothing can be inserted
    // into a request already in flight.
    hub.actions.steer = async (text) => {
      const t = String(text || '').trim();
      if (!t) throw new Error('text required');
      if (!state.running || !state.agent) throw new Error('nothing is running');
      state.agent.steer(t);
      addChat({ role: 'steer', text: t });
    };

    // Edit a QUEUED message: pull it back out of the queue so the browser can put
    // it in the composer, exactly like the terminal's ↑-to-recall (see
    // recallQueued). Matched by TEXT, not index — the browser's list is rebuilt on
    // every status frame, so an index captured at click time can point at a
    // different item by the time it arrives.
    //
    // Returns the removed text so the caller can seed its composer with it.
    hub.actions.editQueued = async (text) => {
      const t = String(text == null ? '' : text);
      const i = state.queued.findIndex((q) => String(q) === t);
      if (i < 0) throw new Error('that message is no longer queued');
      state.queued.splice(i, 1);
      // Drop the matching transcript entry too: the message is now being edited,
      // not waiting, so leaving a `queued` row would double it.
      for (let k = state.chat.length - 1; k >= 0; k--) {
        if (state.chat[k].role === 'queued' && state.chat[k].text === t) { state.chat.splice(k, 1); break; }
      }
      if (web && hub) { try { hub.pubStatusField('queued', [...state.queued]); } catch { /* best-effort */ } }
      syncWebNow();
      return { ok: true, text: t };
    };

    // Remove a queued message outright (the browser's ✕), without editing it.
    hub.actions.dropQueued = async (text) => {
      const t = String(text == null ? '' : text);
      const i = state.queued.findIndex((q) => String(q) === t);
      if (i < 0) throw new Error('that message is no longer queued');
      state.queued.splice(i, 1);
      for (let k = state.chat.length - 1; k >= 0; k--) {
        if (state.chat[k].role === 'queued' && state.chat[k].text === t) { state.chat.splice(k, 1); break; }
      }
      if (web && hub) { try { hub.pubStatusField('queued', [...state.queued]); } catch { /* best-effort */ } }
      syncWebNow();
      return { ok: true };
    };

    // The effective config, with secrets REPLACED by a set/unset flag. The browser
    // needs to show what is in force without ever receiving a key.
    hub.actions.getConfig = async () => effectiveSnapshot(cfg);

    /**
     * Set one root-level key in config.toml.
     *
     * `key` is whitelisted: this surface can be reached over the network, and
     * "write any key" would let a caller rewrite the whole file, including the
     * provider table and the access token.
     */
    hub.actions.setConfig = async (key, value) => {
      const ALLOWED = new Set([
        'calm_mode', 'auto_update', 'auto_compact', 'prompt_cache',
        'tool_allow_external_paths', 'subagent_model', 'swarm_mode', 'theme',
      ]);
      const k = String(key || '');
      if (!ALLOWED.has(k)) throw new Error(`not a settable key: ${k}`);
      const raw = String(value);
      if (/^(true|false)$/i.test(raw)) setConfigBool(k, /^true$/i.test(raw));
      else setConfigString(k, raw);
      // Re-read so the change is live without a restart.
      Object.assign(cfg, resolveConfig());
      state.reasoning = !!cfg.reasoning;
      syncWebNow();
      return effectiveSnapshot(cfg);
    };

    // ---- providers and models -------------------------------------------------
    //
    // These edit config.toml through the same helpers /provider uses, then
    // re-resolve so the change is live. The option caches are invalidated because
    // `webStatus` reuses arrays by identity — without that the browser would keep
    // showing a provider that has just been deleted.

    function invalidateOptionCaches() {
      toolsCache = null;
      commandsCache = null;
      wsFilesCache = { root: '', at: 0, files: null };
    }

    /** Every provider with its base URL and model count, for the settings UI. */
    hub.actions.listProviders = async () => {
      const pr = (cfg.raw && cfg.raw.providers) || {};
      const models = (cfg.raw && cfg.raw.models) || {};
      return Object.keys(pr).map((name) => ({
        name,
        baseUrl: String(pr[name].base_url || pr[name].baseUrl || ''),
        protocol: String(pr[name].protocol || 'openai'),
        keySet: !!(pr[name].api_key || pr[name].apiKey),
        current: name === cfg.provider,
        models: Object.keys(models).filter((k) => (models[k].provider || '') === name),
      }));
    };

    hub.actions.addProvider = async (name, baseUrl, apiKey, protocol) => {
      const n = String(name || '').trim();
      if (!n) throw new Error('provider name required');
      if (!/^[A-Za-z0-9_-]+$/.test(n)) throw new Error('name may contain letters, digits, - and _ only');
      // Accept the protocol value OR a Type label ("OpenAI Responses").
      const proto = typeToProtocol(protocol);
      addProvider(n, { base_url: String(baseUrl || ''), api_key: String(apiKey || ''), protocol: proto });
      cfg.raw.providers = cfg.raw.providers || {};
      cfg.raw.providers[n] = { base_url: String(baseUrl || ''), api_key: String(apiKey || ''), protocol: proto };
      invalidateOptionCaches();
      syncWebNow();
      return hub.actions.listProviders();
    };

    hub.actions.removeProvider = async (name) => {
      const n = String(name || '');
      if (!n) throw new Error('provider name required');
      const pr = (cfg.raw && cfg.raw.providers) || {};
      if (!pr[n]) throw new Error(`no such provider: ${n}`);
      removeProvider(n);
      delete pr[n];
      // Its models go too: a model keyed to a provider that no longer exists is
      // unselectable and only clutters the picker.
      for (const key of Object.keys(cfg.raw.models || {})) {
        if (key.split('/')[0] === n) delete cfg.raw.models[key];
      }
      if (cfg.provider === n) { cfg.provider = ''; state.provider = ''; }
      invalidateOptionCaches();
      syncWebNow();
      return hub.actions.listProviders();
    };

    // Read the provider's model list from its /models endpoint and register every
    // model, so the picker fills in without the user typing ids. Best-effort: an
    // unreachable endpoint leaves the provider added.
    hub.actions.discoverModels = async (name) => {
      const n = String(name || '');
      const pr = (cfg.raw && cfg.raw.providers) || {};
      const p = pr[n];
      if (!p) throw new Error(`no such provider: ${n}`);
      const baseUrl = p.base_url || p.baseUrl || '';
      if (!baseUrl) throw new Error('provider has no base_url');
      // `throwOnError`: the caller asked for this explicitly, so an unreachable
      // endpoint or a rejected key must surface as an error rather than as
      // "found 0 models", which is indistinguishable from an empty catalogue.
      const found = await fetchModels({
        baseUrl,
        apiKey: p.api_key || p.apiKey || '',
        protocol: p.protocol || 'openai',
        throwOnError: true,
      });
      cfg.raw.models = cfg.raw.models || {};
      let added = 0;
      for (const m of found) {
        const key = modelKey(n, m.id);
        if (!cfg.raw.models[key]) added++;
        addModel(n, m.id, { display_name: m.display, contextLength: m.contextLength, maxTokens: m.maxTokens });
        cfg.raw.models[key] = {
          provider: n, model: m.id,
          display_name: m.display || undefined,
          maxTokens: m.maxTokens || undefined,
          contextLength: m.contextLength || undefined,
          reasoning: m.reasoning || undefined,
          efforts: m.efforts || undefined,
        };
      }
      invalidateOptionCaches();
      syncWebNow();
      return { found: found.length, added };
    };

    // The models.dev catalogue, for "import a known provider".
    hub.actions.listKnownProviders = async () => {
      const catalog = await fetchCatalog();
      if (!catalog) throw new Error('could not reach models.dev');
      return Object.values(catalog)
        .filter((p) => p && p.id && p.api)
        .map((p) => ({ id: p.id, name: p.name || p.id, api: p.api }))
        .sort((a, b) => String(a.name).localeCompare(String(b.name)));
    };

    /**
     * Import a models.dev entry as a provider, then discover its models.
     *
     * The key is required from the caller: models.dev publishes endpoints, not
     * credentials, so this cannot complete without the user supplying one.
     */
    hub.actions.importKnownProvider = async (catalogId, name, apiKey) => {
      const catalog = await fetchCatalog();
      if (!catalog) throw new Error('could not reach models.dev');
      const entry = catalog[String(catalogId || '')];
      if (!entry || !entry.api) throw new Error(`unknown provider: ${catalogId}`);
      const n = String(name || entry.id || '').trim();
      if (!n) throw new Error('provider name required');
      const proto = /anthropic/i.test(String(entry.api)) ? 'anthropic' : 'openai';
      addProvider(n, { base_url: entry.api, api_key: String(apiKey || ''), protocol: proto });
      cfg.raw.providers = cfg.raw.providers || {};
      cfg.raw.providers[n] = { base_url: entry.api, api_key: String(apiKey || ''), protocol: proto };
      invalidateOptionCaches();
      syncWebNow();
      // Models are a bonus — a bad key must not undo the provider.
      let discovered = { found: 0, added: 0 };
      try { discovered = await hub.actions.discoverModels(n); } catch { /* best-effort */ }
      return { name: n, baseUrl: entry.api, protocol: proto, ...discovered };
    };



    const srv = await startWebServer({
      hub,
      bindIp: bindIp || '127.0.0.1',
      port: port == null ? 0 : port,
      onNotice: (m, k) => notice(m, k),
    });
    web = srv;
    // Seed the browser with what already exists, so opening the page mid-session
    // shows the conversation rather than an empty pane.
    try { hub.syncChat(state.chat); hub.setStatus(webStatus()); } catch { /* best-effort */ }
    return srv;
  }

  function stopWeb() {
    if (!web) { notice('Web UI is not running', 'error'); return false; }
    // Tell the daemon first, so its directory stops listing this session instead
    // of showing a link to a port that is about to disappear.
    if (webDaemon) {
      try { webDaemon.detach(); } catch { /* best-effort */ }
      webDaemon = null;
    }
    try { web.close(); } catch { /* already gone */ }
    web = null;
    hub = null;
    return true;
  }

  /**
   * Bring up the GLOBAL web UI for this session.
   *
   * Two servers are involved and the distinction matters:
   *   * `startWeb()` here — this session's OWN server, holding the transcript,
   *     the actions and the SSE stream. It binds a random loopback port.
   *   * the daemon — one per machine, on the FIXED port from config.toml. It
   *     serves the directory and proxies /s/<id>/* to the session above.
   *
   * The user asked for a fixed address that survives restarts and lists every
   * session, so the daemon is what they open. If one is already running this
   * session just registers with it — that is the "reuse, do not start another"
   * behaviour, and it is also the only option, since a second daemon could not
   * bind the fixed port anyway.
   */
  async function attachGlobalWeb(bindIp, port) {
    // The bind address: an explicit /web argument wins, else the config value,
    // else loopback. It decides BOTH bindings — the session's own server and the
    // daemon the browser actually opens — so `/web 0.0.0.0` is really reachable
    // from another machine instead of silently listening on 127.0.0.1.
    const host = String(bindIp || cfg.webHost || '127.0.0.1');
    // The session's own server first: the daemon needs a port to proxy to.
    const srv = await startWeb(host, port == null ? 0 : port);
    try {
      webDaemon = await attachToDaemon({
        id: (session && session.id) || 'session',
        port: srv.port,
        token: srv.token,
        title: (session && session.title) || '',
        workspace: state.cwd || cfg.workspace || '',
        host,
      });
    } catch (e) {
      // The daemon is a convenience layer; the session's own server still works,
      // so fall back to reporting that rather than failing /web outright.
      notice(`Global web UI unavailable (${e.message}); this session is still served directly`, 'error');
      webDaemon = null;
    }
    // The daemon's token is the one the user pastes into the login page. It comes
    // from config.toml, so it is the same value every session reports — which is
    // the point: a saved browser login keeps working.
    return { srv, daemon: webDaemon, token: ensureWebToken() };
  }



  const host = {
    addChat, openPicker, openForm, notice, openPanel, openEditor, openTasksPanel, openRegistryBrowser,
    // While the side-thread box is open, a typed message goes to the SIDE THREAD, not
    // to the agent — this is the half of kimi's design that makes the box usable:
    // its `sendUserInput` feeds the panel from the ordinary composer, so a follow-up
    // needs no command. `opts.toMain` is the escape hatch for the paths that must
    // reach the agent regardless (a schedule, a command's own prompt).
    sendPrompt: (text, opts) => {
      const o = opts || {};
      if (state.btwPanel && !o.toMain && !o.fromSchedule) {
        void askSideQuestion(state, cfg, text, renderSoon);
        return;
      }
      void runAgent(text, o);
    },
    quit: () => { state._quit = true; },
saveSession: (s) => { (async () => { try { const { runHooks } = await import('./plugin.js'); await runHooks('onSessionSave', s || session); } catch {} })(); sess.saveSession(s); },
    // Rebinds the closure's session AND the mirror on `state`. /move replaces it, and without
    // this the caller and the command disagreed about which session was current — every later
    // save wrote the old object, still stamped with the directory it was moved away from.
    replaceSession: (s) => { if (!s) return; session = s; state.session = s; if (s.workspace) state.workspace = s.workspace; },
    // Rebinds the closure's session. /move replaces it, and without this the caller and the
    // command disagreed about which session was current — every later save wrote the old one.
    replaceSession: (s) => { if (s) session = s; },
    getMessages: () => (session && session.messages ? session.messages : []),
    clearSession: () => { if (session) session.messages = []; if (state) { state.ctxTokens = 0; state.ctxPercent = 0; } renderFrame(); },
    getConfig: (key) => (cfg && key != null ? cfg[key] : undefined),
    setConfig: (key, val) => { if (cfg && key != null) cfg[key] = val; },
    // Persist a TOML root-level key to config.toml and keep the live cfg in sync.
    persistConfig: (key, val) => {
      try {
        setConfigString(String(key), typeof val === 'string' ? val : JSON.stringify(val));
        if (cfg && key != null) cfg[key] = val;
        return true;
      } catch (e) { return false; }
    },
    reloadConfig: () => resolveConfig(),
    // Full reload: unload the current plugins, then re-run discovery/load and return
    // any notices (so a freshly added/edited plugin shows up without restarting).
    // `fresh: true` re-imports each file with a cache-busting query — without it the
    // ESM cache hands back the module instance from the previous load and an EDIT to
    // a plugin file would change nothing.
    reloadPlugins: async () => {
      const { loadPlugins, takePluginNotices } = await import('./plugin.js');
      await loadPlugins(cfg.pluginDir || undefined, { fresh: true });
      return takePluginNotices();
    },
    persistState,
    startWeb,
    startWebGlobal: attachGlobalWeb,
    stopWeb,
    webInfo: () => web,
    // `dispatch` is module-level and was declared with a `renderFrame` parameter
    // that NONE of its four callers ever passed. That was harmless until /compact
    // started calling it, which threw "renderFrame is not a function". Reaching it
    // through `host` means a future caller cannot forget it again.
    renderFrame,

    // ---- capabilities a plugin can drive -------------------------------------
    //
    // These forward to the SAME code the slash commands use, so a plugin cannot reach a
    // state the command could not: opening the tree runs the identical builder, and
    // switching the theme drops `lastFrame` the same way /theme does (without which the
    // differential painter would emit nothing and the screen would keep the old colours).

    openFileTree(filter) {
      const cwd = state.cwd || cfg.workspace || process.cwd();
      let files = [];
      try { files = walkFiles(cwd, { includeIgnored: false }); } catch { return false; }
      const root = buildTree(files, cwd);
      if (!root.children.length) return false;
      const expanded = new Set();
      for (const c of root.children) if (c.dir) expanded.add(c.rel);
      state.fileTree = { root, expanded, sel: 0, scroll: 0, filter: String(filter || '').trim(), cwd };
      state.picker = null; state.form = null; state.panel = null; state.menuOpen = false;
      renderFrame();
      return true;
    },
    closeFileTree() {
      if (!state.fileTree) return;
      state.fileTree = null;
      state.hoverHit = null;
      renderFrame();
    },
    getTheme() { return state.theme || null; },
    setTheme(name) {
      if (!hasTheme(name)) return false;
      state.theme = name;
      setTheme(name);
      try { setConfigString('theme', name); } catch { /* the session still uses it */ }
      // The full repaint: see the same note in the /theme command.
      lastFrame = null;
      renderFrame();
      return true;
    },
    subagents() { return listRuns().map((r) => ({ id: r.agentId, runId: r.runId, taskId: r.taskId, type: r.type, description: r.description, startedAt: r.startedAt })); },
    messageSubagent(ref, text) { return sendToRun(ref, text); },
    interruptSubagent(ref) { return ref ? interruptRun(ref) : interruptAll(); },
    closeSubagent(ref) { return closeRun(ref); },
    isKeyBound(key) {
      const k = normalizeKey(key);
      if (!k) return false;
      // Three sources, and all three have to be checked or a plugin gets a wrong answer:
      //   * the user's own keybindings file (a data structure);
      //   * a plugin's claim from registerKeybind (also data);
      //   * the BUILT-IN keys the TUI dispatches in its switch — not data, so the list
      //     below is the subset a plugin would realistically take and silently break.
      if (keybindings.bindings.has(k)) return true;
      if (pluginKeybinds().some((kb) => kb.key === k)) return true;
      return BUILTIN_KEYS.has(k);
    },
    boundKeys() {
      const out = new Set([...keybindings.bindings.keys()]);
      for (const k of BUILTIN_KEYS) out.add(k);
      for (const kb of pluginKeybinds()) out.add(kb.key);
      return [...out];
    },
  };

  // Hand the full host surface to the plugin system so api.* can forward (sendPrompt,
  // openPanel, notice, getMessages, setConfig, ...). Done once, here, after `host` exists.
  (async () => { try { const { setPluginHost } = await import('./plugin.js'); setPluginHost(host); } catch {} })();

  // Surface what the plugins did. `loadPlugins()` already ran (index.js, before the TUI
  // existed) and collected its notices, including any load failure — which previously went
  // only to stderr, invisible while the TUI owns the screen. A plugin that failed to load
  // simply did not appear, with nothing explaining why.
  void (async () => {
    try {
      const { takePluginNotices, runHooks } = await import('./plugin.js');
      // onStartup: plugins that want to greet / schedule / open a panel on launch.
      try { await runHooks('onStartup'); } catch (e) { console.error('[hncode-plugin] onStartup error:', e.message); }
      const notes = takePluginNotices();
      if (!notes.length) return;
      // ONE collapsible block instead of a wall of lines: a plugin set can emit
      // dozens of notices, which pushed the actual conversation off screen at
      // startup. Collapsed it is a single summary line; Ctrl+L expands it in place
      // (see the `c-l` handler next to the other Ctrl shortcuts).
      const icon = { error: '✗', warn: '!', info: '•' };
      const detail = notes.map((n) => `${icon[n.level] || '•'} plugin: ${n.text}`);
      const errs = notes.filter((n) => n.level === 'error').length;
      const first = notes[0];
      const summary = `plugin: ${first.text}`;
      const suffix = notes.length > 1
        ? `  (+${notes.length - 1} more${errs ? `, ${errs} error${errs === 1 ? '' : 's'}` : ''} · ctrl+l)`
        : '';
      const msg = {
        role: notes.some((n) => n.level === 'error') ? 'aborted' : 'system',
        text: summary + suffix,
        // Collapsed by default; Ctrl+L flips `expanded` and the renderer prints
        // `allLines` instead of the single summary.
        pluginLog: true,
        expanded: false,
        allLines: detail,
      };
      state.chat.push(msg);
      renderFrame();
    } catch { /* notices are best-effort; never break startup */ }
  })();

  // Appending streamed text can also add rows (the message wraps as it grows).
  // No arithmetic is needed here: renderChatLines() anchors the scrolled-up window
  // by row against the exact row count, so this only has to schedule a repaint.
  // Kept as a named hook because the streaming path calls it in several places.
  function anchorScroll() {
    renderSoon();
  }
  // ---- paced streaming ------------------------------------------------------
  // Answer and reasoning deltas are NOT painted as they arrive: they go into a
  // StreamBuffer that drips them out at a smooth, time-paced rate. A provider that
  // coalesces its deltas into lumps (Anthropic) then looks the same as one that emits
  // token-level deltas (OpenAI); see src/stream-buffer.js for the controller.
  //
  // The buffer holds BOTH kinds in one ordered queue, so a reasoning block can never
  // overtake the answer text that followed it, and the reasoning region closes at
  // exactly the point the provider closed it.
  const streamBuf = new StreamBuffer();

  // Apply revealed ops to the transcript. EVERY producer of ops goes through here.
  //
  // The push methods (`pushText` / `pushReasoning`) do not only queue: they return the
  // characters the pacing controller says are due RIGHT NOW, and those characters are
  // already off the queue when they come back. A caller that drops the return value
  // therefore loses them for good — that is exactly how the first ~30 characters of
  // every provider delta went missing, and with them the prose (and the `<|plan|>` tag)
  // at the head of a Plan-mode reply.
  function applyStreamOps(ops) {
    if (!ops || !ops.length) return false;
    for (const o of ops) {
      if (o.op === StreamOp.Text) appendAssistant(o.text);
      else if (o.op === StreamOp.Reasoning) appendThinking(o.text);
      else if (o.op === StreamOp.CloseReasoning) settleThinking();
    }
    return true;
  }

  // Apply whatever the buffer has ready. Called from the paced tick (so a lone burst
  // still drains); the delta handlers reveal through the push return value instead.
  function drainStream() {
    return applyStreamOps(streamBuf.flushSmoothFrame());
  }

  // Stop the still-pending reasoning block: the provider moved on to the answer, so the
  // "reasoned, then acted" split has to be visible. Shared by the close marker and the
  // turn-end paths so the block can never be left spinning.
  function settleThinking() {
    const t = [...state.chat].reverse().find((m) => m.role === 'thinking' && m.pending);
    if (t) t.pending = false;
  }

  // Reveal everything still buffered, RIGHT NOW. Every path that ends the turn (a tool
  // starting, an abort, an error, the turn finishing) must call this: leaving text in
  // the buffer would let the answer keep trickling out after the turn it belonged to
  // had already ended, which reads as the UI lagging behind reality.
  function flushStream() {
    return applyStreamOps(streamBuf.flush());
  }

  // Live split of the streamed reply into prose vs. plan block.
  // While Plan mode is on and the model is inside the plan tags, the text is routed into
  // a `plan` bubble so it renders in its frame AS IT ARRIVES — the old behaviour
  // buffered the whole reply and only showed the plan at turn end, so the user watched
  // prose and then the plan popped in.
  // While Plan mode is on and the model is inside the plan tags, the text is routed into
  // a `plan` bubble so it renders in its frame AS IT ARRIVES — the old behaviour
  // buffered the whole reply and only showed the plan at turn end, so the user watched
  // prose and then the plan popped in.
  function appendAssistant(text) {
    if (state.plan && typeof text === 'string' && text) {
      state._planBuf = (state._planBuf || '') + text;
      const buf = state._planBuf;
      const open = buf.toLowerCase().indexOf(PLAN_OPEN_TAG);
      if (open === -1) {
        // Still in the prose part (or the tag has not finished arriving).
        const last = state.chat[state.chat.length - 1];
        if (last && last.role === 'assistant') last.text += text;
        else state.chat.push({ role: 'assistant', text });
        anchorScroll();
        return;
      }
      // Everything before the tag is prose; everything after it is the plan body.
      const prose = buf.slice(0, open);
      const body = buf.slice(open + PLAN_OPEN_TAG.length);
      const close = body.toLowerCase().indexOf(PLAN_CLOSE_TAG);
      const planSoFar = close === -1 ? body : body.slice(0, close);
      setStreamedProse(prose);
      setStreamedPlan(planSoFar);
      anchorScroll();
      return;
    }
    appendAssistantRaw(text);
  }

  // Replace the trailing assistant bubble with exactly `prose`.
  // Order is FIXED: prose bubbles are BEFORE the plan bubble (the plan is last).
  // Pushing an assistant AFTER the plan put `plan` mid-list on the next update, so
  // setStreamedPlan saw a non-plan tail, pushed ANOTHER plan, and repeated — every
  // stream chunk created a new plan bubble (the "1, 12, 123, 1234" spam the user
  // reported). Find the prose bubble that PRECEDES the plan and update it.
  function setStreamedProse(prose) {
    const trimmed = String(prose).replace(/^\s*\n/, '');
    // Find the FIRST plan bubble; prose must be updated BEFORE it, never after.
    let planIdx = -1;
    for (let i = 0; i < state.chat.length; i++) {
      if (state.chat[i].role === 'plan') { planIdx = i; break; }
    }
    // Look for the assistant bubble right BEFORE the plan; with no plan, take the
    // LAST assistant. This loop indexes UP TO planIdx so it can never miss one —
    // the old code broke at the first plan it hit from the tail, so it never saw
    // the assistant in front of it and duplicated the prose on every chunk.
    const bound = planIdx >= 0 ? planIdx : state.chat.length;
    let proseIdx = -1;
    for (let i = bound - 1; i >= 0; i--) {
      if (state.chat[i].role === 'assistant') { proseIdx = i; break; }
    }
    if (proseIdx >= 0) {
      state.chat[proseIdx].text = trimmed;
      state.chat[proseIdx]._cache = null;   // replacement, not append: see fp()
      if (!trimmed.trim()) state.chat.splice(proseIdx, 1);   // nothing left: drop it
    } else if (trimmed.trim()) {
      state.chat.unshift({ role: 'assistant', text: trimmed, _conv: true });
    }
  }

  // Create/update the live plan bubble, always at the END of the transcript.
  function setStreamedPlan(planSoFar) {
    let last = state.chat[state.chat.length - 1];
    if (last && last.role === 'plan') {
      last.text = planSoFar;
      last._cache = null;   // replacement, not append: see fp()
    } else {
      state.chat.push({ role: 'plan', text: planSoFar });
    }
  }

  function appendAssistantRaw(text) {
    const last = state.chat[state.chat.length - 1];
    if (last && last.role === 'assistant') {
      last.text += text;
    } else {
      state.chat.push({ role: 'assistant', text: text || '', _conv: true });
    }


    anchorScroll();
  }


  // Name the session from the user's FIRST message, with a dedicated one-shot
  // request. The reply is untrusted: it can come back multi-line, prefixed
  // ("Title: none"), or as prose, and it is scrubbed down to one short line
  // before it is written anywhere.
  //
  // Three things made this fail silently before, and all three are fixed here:
  //   * the request inherited the session's thinking effort, so a reasoning model
  //     burnt the whole 64-token budget on `reasoning_content` and returned an
  //     EMPTY answer (`finish_reason: "length"`). It is sent with noReasoning now.
  //   * it carried the whole ~25 KB tool block, which no title request needs.
  //   * it ran exactly once. `needsTitle` only held on the very first turn, so a
  //     failure (offline, aborted, empty reply) left the session nameless forever.
  //     state.titleAttempts now allows a few retries on later turns.
  async function generateTitle(userText) {
    const asked = String(userText || '').replace(/\s+/g, ' ').trim().slice(0, 400);
    if (!asked) return;
    let raw = '';
    // 64 tokens is enough once thinking is off, but a model that answers in prose
    // can still be cut off — so escalate once rather than give up.
    for (const budget of [64, 256]) {
      try {
        const titleCfg = { ...cfg, temperature: 0.2, maxOutputTokens: budget };
        const llm = new LLM(titleCfg);
        // NOT wired to Esc: abort() belongs to the turn's own request, and a
        // title request shares this LLM instance.
        const got = await llm.requestText([
          { role: 'system', content: TITLE_PROMPT },
          { role: 'user', content: `The entry message is:\n${asked}` },
        ], { noReasoning: true, noTools: true });
        if (got) { raw = got; break; }
        // '' means "hit the output cap" — a bigger budget may still land it.
        // null means the request itself failed; retrying the same way is pointless.
        if (got === null) break;
      } catch { raw = ''; break; }
    }
    const title = cleanTitle(raw);
    if (!title) return;
    session.title = title;
    try { saveSession(session); } catch { /* the title is cosmetic; never fail a turn over it */ }
    stdout.write(`\x1b]0;${title}\x07`);
    notice(`Auto-generated title: "${title}"`);
  }

  // The one-shot namer. Sentence-case, 3-7 words, with worked examples — a bare
  // "at most 50 characters" let the model echo "你好" back as a title for a
  // greeting, which is not a name anyone can find in a list.
  const TITLE_PROMPT = 'You name coding-agent sessions. Reply with ONLY the title: one line, 3 to 7 words, sentence case (capitalize only the first word and proper nouns), at most 50 characters. No quotes, no trailing punctuation, no "Title:" label, no explanation.\n'
    + '\n'
    + 'Capture the main topic or goal so the user recognises the session in a list.\n'
    + 'Good: "Fix login button on mobile", "Add OAuth authentication", "Debug failing CI tests", "Refactor API client error handling"\n'
    + 'Bad (too vague): "Code changes", "Greeting", "你好"\n'
    + 'Bad (too long): "Investigate and fix the issue where the login button does not respond on mobile devices"';

  // Model output -> a single short title, or '' when there is nothing usable.
  // The old heuristic took the first streamed chunk if it was under 80 chars and
  // on one line, which made ordinary prose ("Let me look at the file.") the title.
  function cleanTitle(s) {
    let t = String(s == null ? '' : s).trim();
    if (!t) return '';
    // A model that answers with a heading or a label instead of a bare title.
    t = t.replace(/^\s*(?:title|标题)\s*[:：]\s*/i, '');
    t = t.replace(/^#+\s*/, '').replace(/^["'“”‘’*_`]+|["'“”‘’*_`]+$/g, '');
    t = t.split('\n')[0];                 // keep the first non-empty line only
    t = t.replace(/\s+/g, ' ').trim();
    t = t.replace(/[.。;；,，:：!?！？]+$/, '').trim();   // trailing punctuation
    // A model that wraps its answer in JSON despite being told not to.
    const json = t.match(/^\{.*"title"\s*:\s*"([^"]*)"/);
    if (json) t = json[1].trim();
    if (!t || t.length < 3) return '';
    return t.length > 60 ? t.slice(0, 60).trim() : t;
  }


  function appendThinking(text) {
    const last = state.chat[state.chat.length - 1];
    let live;
    if (last && last.role === 'thinking' && last.pending) {
      last.text += text;
      last.spin = state.spin || 0;
      live = last;
    } else {
      live = { role: 'thinking', text: text || '', pending: true, spin: state.spin || 0 };
      state.chat.push(live);
    }
    // Reasoning does not go through addChat, so it is recorded here. `live` is the same
    // block the previous chunk extended, so this appends to the open entry rather than
    // writing one per character.
    recordTranscriptRow(live);
    anchorScroll();
  }

  function normalizeMsg(m) {
    // Keep `failed`: a failed tool result must render in RED. Dropping it here
    // made every failure look like ordinary gray output.
    // Keep `diff`: an Edit's diff travels ON the tool_result message so it renders
    // below the `↳` receipt (see messageLines). Dropping it removed the diff.
    const out = {
      role: m && m.role ? m.role : 'system',
      text: m && m.text != null ? String(m.text) : '',
      failed: !!(m && m.failed),
    };
    if (m && Array.isArray(m.diff)) out.diff = m.diff;
    // `bodyOnToolRow`: the tool row above already rendered this result's body, so the
    // receipt must not open a second `↳` marker (see the tool_result branch).
    if (m && m.bodyOnToolRow) out.bodyOnToolRow = true;
    // Keep `card`: a background-task lifecycle card carries its phase/headline/detail
    // here (see the `bg_task` renderer). The comment claimed this while the line itself
    // was missing, so every card fell back to its placeholder text.
    if (m && m.card) out.card = m.card;
    if (m && m._conv) out._conv = true;
    // Keep the compaction block's live fields: the header is rebuilt from `phase`,
    // the token pair and the (collapsed) summary every frame, so dropping them left
    // the row stuck at whatever the first paint happened to show.
    if (m && m.role === 'compaction') {
      out.phase = m.phase || 'running';
      out.tokensBefore = m.tokensBefore;
      out.tokensAfter = m.tokensAfter;
      out.startedAt = m.startedAt;
      out.instruction = m.instruction || '';
    }
    return out;
  }

  let stopped = false;
  function stop() {
    if (stopped) return;
    stopped = true;
    try { if (wasRaw) stdin.setRawMode(false); } catch {}
    try { stdin.pause(); } catch {}
    if (tipTimer) clearInterval(tipTimer);
    if (spinTimer) clearInterval(spinTimer);
    if (streamTimer) clearInterval(streamTimer);
    if (tokTimer) clearInterval(tokTimer);
    if (confirmTimer) clearTimeout(confirmTimer);
    // The /tasks panel owns a flash timer; leaving it armed keeps the process
    // alive until it fires after exit.
    if (state.tasksPanel && state.tasksPanel.flashTimer) clearTimeout(state.tasksPanel.flashTimer);
    // Leaving the daemon registered would keep this session listed as "live" in
    // the browser until its heartbeat went stale. Deregistering now flips the page
    // to the read-only view straight away.
    if (webDaemon) {
      try { webDaemon.detach(); } catch { /* best-effort */ }
      webDaemon = null;
    }
    try { sess.saveSession(session); } catch {}
    stdout.write('\x1b[<u\x1b[?2004l\x1b[?1006l\x1b[?1003l\x1b[?1002l\x1b[?1000l');
    stdout.write(alternateScreen(false));
    stdout.write(showCursor());
    const id = session && session.id;
    const work = session && session.workspace;
    if (id) {
      let hint = '';
      hint += `\r\n  Session saved as ${id}\r\n`;
      hint += `  Continue here:  hncode --continue\r\n`;
      if (work) hint += `  Or resume the exact session:  hncode --resume ${id}\r\n`;
      hint += '\r\n';
      stdout.write(hint);
    }
  }
// Run the SessionEnd hook, then exit. Bounded: a hung hook must not stop the
// process from quitting, so the whole thing races a short timer.
function quit() {
  // Let plugins clean up (close files, flush logs, cancel timers) before we exit.
  try { runHooks('onShutdown'); } catch (e) {}
  stop();
  let done = false;
  const bye = () => { if (!done) { done = true; process.exit(0); } };
  try {
    const workspace = process.cwd();
    const { hooks } = loadHooks(workspace);
    if (hooks && hooks.SessionEnd && hooks.SessionEnd.length) {
      setTimeout(bye, 5000).unref?.();
      Promise.resolve(runShellHooks({ hooks }, 'SessionEnd', {}, workspace)).then(bye, bye);
      return;
    }
  } catch { /* fall through to a plain exit */ }
  bye();
}
  process.on('SIGWINCH', () => renderFrame());
  process.on('SIGINT', () => quit());

  /**
   * Append one line to ~/.hncode/keys.log. Used only when HNCODE_TRACE_KEYS=1.
   *
   * A swallowed keystroke and an undelivered one look identical from the outside: the
   * screen simply does not react. A terminal may send Ctrl+C as raw 0x03, as a kitty CSI-u
   * sequence, or as SIGINT with no bytes at all — and each of those needs a different fix.
   * This records which one actually arrived, so the question is answered by bytes rather
   * than by guessing. Append-only and best-effort: a failed write must never break input.
   */
  function traceKey(kind, value) {
    try {
      const dir = process.env.HNCODE_HOME || path.join(os.homedir(), '.hncode');
      fs.mkdirSync(dir, { recursive: true });
      const shown = typeof value === 'string'
        ? [...value].map((c) => {
          const n = c.charCodeAt(0);
          return n < 0x20 ? `\\x${n.toString(16).padStart(2, '0')}` : c;
        }).join('')
        : JSON.stringify(value);
      fs.appendFileSync(path.join(dir, 'keys.log'),
        `${new Date().toISOString()} ${kind} ${shown}\n`);
    } catch { /* diagnostics must never break the keyboard */ }
  }
  /**
   * Record WHY the process ended, before it does.
   *
   * A TUI that exits on its own leaves nothing behind: the alternate screen is
   * restored in the exit handler, so the user sees their prompt back and no error,
   * and the reason is gone with the process. That is indistinguishable from a
   * normal /exit — which made "it just quits mid-tool-call sometimes" impossible
   * to diagnose from the outside.
   *
   * Every exit now appends one line to ~/.hncode/exit.log: the reason, whether it
   * was requested (quit()/exit command) or the runtime deciding for us, and the
   * active handles at the moment it happened. A tool-only exit shows up as
   * `beforeExit`/`stdin end` with a running agent; a crash shows up as
   * uncaughtException with a stack.
   */
  function noteExit(reason) {
    try {
      const dir = process.env.HNCODE_HOME || path.join(os.homedir(), '.hncode');
      fs.mkdirSync(dir, { recursive: true });
      const line = JSON.stringify({
        at: new Date().toISOString(),
        reason,
        running: !!state.running,
        busy: !!state.agent,
        raw: wasRaw,
        // A stop() running means the TUI already tore down its terminal state, i.e.
        // a deliberate exit; without it this was a shutdown nobody asked for.
        tornDown: stopped,
        // The handles still keeping the loop alive (empty => nothing left to do,
        // which is what lets Node exit on its own).
        handles: process._getActiveHandles ? process._getActiveHandles().map((h) => h && h.constructor && h.constructor.name).filter(Boolean) : [],
        session: session && session.id,
      }) + '\n';
      fs.appendFileSync(path.join(dir, 'exit.log'), line);
    } catch { /* diagnostics must never be the reason an exit fails */ }
  }
  process.on('exit', (code) => {
    // Save on every exit, not just the graceful path. stop() (a normal quit) saves,
    // but a process.exit elsewhere or a crash skips it; the one place a session
    // survives an abrupt halt is right here. sess.saveSession is synchronous fs.
    try { sess.saveSession(session); } catch {}
    // Pasted screenshots are temp files with no further use once we are leaving;
    // delete them here so they cannot pile up in the temp dir. Synchronous, and it
    // runs on the graceful AND the crash path because 'exit' always fires.
    try { cleanupPastedImages(); } catch { /* never block the exit */ }
    noteExit(`exit code=${code}`);
    if (stopped) return;
    try { stdout.write('\x1b[<u\x1b[?2004l\x1b[?1006l\x1b[?1003l\x1b[?1002l\x1b[?1000l' + alternateScreen(false) + showCursor()); } catch {}
  });
  // stdin reaching EOF is the one exit that is COMPLETELY silent: Node has no more
  // readable input, the event loop drains, and the process ends without any exit
  // handler having a reason to report. That is the shape a "TUI quit by itself"
  // takes. Log it (and the agent state) so the next occurrence is identifiable.
  try {
    stdin.on('end', () => noteExit('stdin end (EOF)'));
    stdin.on('close', () => noteExit('stdin close'));
    stdin.on('error', (e) => noteExit(`stdin error: ${e && e.message}`));
  } catch { /* a non-TTY stdin has no such events */ }
  process.on('SIGHUP', () => noteExit('SIGHUP'));
  process.on('beforeExit', () => noteExit('beforeExit'));
  // A crash between messages used to lose the whole current turn: the only save
  // lived at turn end (or in stop()), so anything typed or streamed before it died
  // with the process. Save whatever arrived so far, then re-raise so the fault is
  // still visible instead of being silently swallowed.
  process.on('uncaughtException', (err) => {
    try { sess.saveSession(session); } catch {}
    noteExit(`uncaughtException: ${(err && err.message) || err}\n${(err && err.stack) || ''}`);
    console.error('\nhncode crashed:', (err && err.stack) || err);
    process.exit(1);
  });
  process.on('unhandledRejection', (reason) => {
    try { sess.saveSession(session); } catch {}
    // The STACK is the whole point: the message alone ("...of undefined") does not
    // say which line. console.error() writes into the alternate screen, which the
    // exit handler then wipes, so the user never sees it — the log is the only
    // place the trace survives.
    noteExit(`unhandledRejection: ${(reason && reason.message) || reason}\n${(reason && reason.stack) || ''}`);
    console.error('\nhncode unhandled rejection:', reason);
    process.exit(1);
  });

  // REMOTE CONTROL (--control): expose a local socket so a script can queue a
  // prompt on this running session, query its status, or interrupt it. Opt-in —
  // nothing listens unless the user asked for it. Failures are non-fatal (a
  // second instance may already hold the socket).
  let control = null;
  if (opts.control != null) {
    try {
        control = await startControlServer({
        prompt: async (text) => { await submit(text); },
        status: async () => ({
          busy: !!(state.running),
          session: (session && session.id) || '',
          model: cfg.model || '',
          cwd: state.cwd || cfg.workspace || '',
          queued: (state.queued || []).length,
        }),
        interrupt: async () => { if (state.agent && typeof state.agent.interrupt === 'function') state.agent.interrupt(); },
      }, { path: opts.control || undefined });
      if (control.error) {
        try { stdout.write(`\r\n  control socket unavailable: ${control.error}\r\n`); } catch {}
      } else {
        addChat({ role: 'system', text: `Remote control listening on ${control.path}` });
        renderFrame();
      }
    } catch (e) {
      try { stdout.write(`\r\n  control socket failed: ${e.message}\r\n`); } catch {}
    }
  }
  if (control && control.server) process.on('exit', () => { try { control.close(); } catch {} });



  // WEB UI (--web): same opt-in shape as --control. It starts AFTER the first
  // paint (the UI is already up by this point), and a failure is reported in the
  // transcript rather than killing the session — a port already in use must not
  // stop the user from working.
  if (opts.web && typeof opts.web === 'object') {
    try {
      const srv = await startWeb(opts.web.bindIp, opts.web.port);
      const lan = !srv.loopback;
      addChat({
        role: 'system',
        text: [
          `Web UI: ${srv.url}`,
          `Bind:   ${srv.host}:${srv.port}${lan ? '  (reachable from the network)' : '  (this machine only)'}`,
          '',
          'Access token (paste it into the login page):',
          '',
          `    ${srv.token}`,
          '',
          'Anyone with this token can run commands as you in this workspace.',
          'Stop the server with /web off.',
        ].join('\n'),
      });
      renderFrame();
    } catch (e) {
      addChat({ role: 'warn', text: `Could not start the web UI: ${e.message}` });
      renderFrame();
    }
  }
  process.on('exit', () => { try { if (web) web.close(); } catch { /* already gone */ } });


  // Keep the process alive for the whole session. startTUI is async and returns
  // as soon as the TUI is wired up; without a pending promise, main()'s await
  // resolves immediately and Node exits (the "flash of UI then quit" bug).
  return new Promise(() => {});
}
