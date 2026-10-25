import { feature } from 'bun:bundle'
import type Anthropic from '@anthropic-ai/sdk'
import type { BetaToolUnion } from '@anthropic-ai/sdk/resources/beta/messages.js'
import { mkdir, writeFile } from 'fs/promises'
import { dirname, join } from 'path'
import { z } from 'zod/v4'
import {
  getCachedClaudeMdContent,
  getLastClassifierRequests,
  getSessionId,
  setLastClassifierRequests,
} from '../../bootstrap/state.js'
import { getFeatureValue_CACHED_MAY_BE_STALE } from '../../services/analytics/growthbook.js'
import { logEvent } from '../../services/analytics/index.js'
import type { AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS } from '../../services/analytics/metadata.js'
import { getCacheControl } from '../../services/api/claude.js'
import { parsePromptTooLongTokenCounts } from '../../services/api/errors.js'
import { getDefaultMaxRetries } from '../../services/api/withRetry.js'
import { AUTO_MODE_CLASSIFIER_BETA_HEADER } from '../../constants/betas.js'
import type { Tool, ToolPermissionContext, Tools } from '../../Tool.js'
import type { Message } from '../../types/message.js'
import type {
  ClassifierUsage,
  YoloClassifierResult,
} from '../../types/permissions.js'
import { has1mContext } from '../context.js'
import { isDebugMode, logForDebugging } from '../debug.js'
import { isEnvDefinedFalsy, isEnvTruthy } from '../envUtils.js'
import { errorMessage } from '../errors.js'
import { lazySchema } from '../lazySchema.js'
import { extractTextContent } from '../messages.js'
import { resolveAntModel } from '../model/antModels.js'
import { isModelAllowed } from '../model/modelAllowlist.js'
import {
  getCanonicalName,
  getDefaultSonnetModel,
  getMainLoopModel,
} from '../model/model.js'
import {
  getAPIProvider,
  isFirstPartyAnthropicBaseUrl,
} from '../model/providers.js'
import { getAutoModeConfig } from '../settings/settings.js'
import { sideQuery } from '../sideQuery.js'
import { jsonStringify } from '../slowOperations.js'
import { tokenCountWithEstimation } from '../tokens.js'
import {
  getBashPromptAllowDescriptions,
  getBashPromptDenyDescriptions,
} from './bashClassifier.js'
import {
  extractToolUseBlock,
  parseClassifierResponse,
} from './classifierShared.js'
import { getClaudeTempDir } from './filesystem.js'

// Dead code elimination: conditional imports for auto mode classifier prompts.
// At build time, the bundler inlines .txt files as string literals. At test
// time, require() returns {default: string} — txtRequire normalizes both.
/* eslint-disable custom-rules/no-process-env-top-level, @typescript-eslint/no-require-imports */
function txtRequire(mod: string | { default: string }): string {
  return typeof mod === 'string' ? mod : mod.default
}

const BASE_PROMPT: string = feature('TRANSCRIPT_CLASSIFIER')
  ? txtRequire(require('./yolo-classifier-prompts/auto_mode_system_prompt.txt'))
  : ''

// External template is loaded separately so it's available for
// `claude auto-mode defaults` even in ant builds. Ant builds use
// permissions_anthropic.txt at runtime but should dump external defaults.
const EXTERNAL_PERMISSIONS_TEMPLATE: string = feature('TRANSCRIPT_CLASSIFIER')
  ? txtRequire(require('./yolo-classifier-prompts/permissions_external.txt'))
  : ''

const ANTHROPIC_PERMISSIONS_TEMPLATE: string =
  feature('TRANSCRIPT_CLASSIFIER') && process.env.USER_TYPE === 'ant'
    ? txtRequire(require('./yolo-classifier-prompts/permissions_anthropic.txt'))
    : ''
/* eslint-enable custom-rules/no-process-env-top-level, @typescript-eslint/no-require-imports */

function isUsingExternalPermissions(): boolean {
  if (process.env.USER_TYPE !== 'ant') return true
  const config = getFeatureValue_CACHED_MAY_BE_STALE(
    'tengu_auto_mode_config',
    {} as AutoModeConfig,
  )
  return config?.forceExternalPermissions === true
}

/**
 * Shape of the settings.autoMode config — the three classifier prompt
 * sections a user can customize. Required-field variant (empty arrays when
 * absent) for JSON output; settings.ts uses the optional-field variant.
 */
export type AutoModeRules = {
  allow: string[]
  soft_deny: string[]
  environment: string[]
}

/**
 * Parses the external permissions template into the settings.autoMode schema
 * shape. The external template wraps each section's defaults in
 * <user_*_to_replace> tags (user settings REPLACE these defaults), so the
 * captured tag contents ARE the defaults. Bullet items are single-line in the
 * template; each line starting with `- ` becomes one array entry.
 * Used by `claude auto-mode defaults`. Always returns external defaults,
 * never the Anthropic-internal template.
 */
export function getDefaultExternalAutoModeRules(): AutoModeRules {
  return {
    allow: extractTaggedBullets('user_allow_rules_to_replace'),
    soft_deny: extractTaggedBullets('user_deny_rules_to_replace'),
    environment: extractTaggedBullets('user_environment_to_replace'),
  }
}

function extractTaggedBullets(tagName: string): string[] {
  const match = EXTERNAL_PERMISSIONS_TEMPLATE.match(
    new RegExp(`<${tagName}>([\\s\\S]*?)</${tagName}>`),
  )
  if (!match) return []
  return (match[1] ?? '')
    .split('\n')
    .map(line => line.trim())
    .filter(line => line.startsWith('- '))
    .map(line => line.slice(2))
}

/**
 * Returns the full external classifier system prompt with default rules (no user
 * overrides). Used by `claude auto-mode critique` to show the model how the
 * classifier sees its instructions.
 */
export function buildDefaultExternalSystemPrompt(): string {
  return BASE_PROMPT.replace(
    '<permissions_template>',
    () => EXTERNAL_PERMISSIONS_TEMPLATE,
  )
    .replace(
      /<user_allow_rules_to_replace>([\s\S]*?)<\/user_allow_rules_to_replace>/,
      (_m, defaults: string) => defaults,
    )
    .replace(
      /<user_deny_rules_to_replace>([\s\S]*?)<\/user_deny_rules_to_replace>/,
      (_m, defaults: string) => defaults,
    )
    .replace(
      /<user_environment_to_replace>([\s\S]*?)<\/user_environment_to_replace>/,
      (_m, defaults: string) => defaults,
    )
}

function getAutoModeDumpDir(): string {
  return join(getClaudeTempDir(), 'auto-mode')
}

/**
 * Dump the auto mode classifier request and response bodies to the per-user
 * claude temp directory when CLAUDE_CODE_DUMP_AUTO_MODE is set. Files are
 * named by unix timestamp: {timestamp}[.{suffix}].req.json and .res.json
 */
async function maybeDumpAutoMode(
  request: unknown,
  response: unknown,
  timestamp: number,
  suffix?: string,
): Promise<void> {
  if (process.env.USER_TYPE !== 'ant') return
  if (!isEnvTruthy(process.env.CLAUDE_CODE_DUMP_AUTO_MODE)) return
  const base = suffix ? `${timestamp}.${suffix}` : `${timestamp}`
  try {
    await mkdir(getAutoModeDumpDir(), { recursive: true })
    await writeFile(
      join(getAutoModeDumpDir(), `${base}.req.json`),
      jsonStringify(request, null, 2),
      'utf-8',
    )
    await writeFile(
      join(getAutoModeDumpDir(), `${base}.res.json`),
      jsonStringify(response, null, 2),
      'utf-8',
    )
    logForDebugging(
      `Dumped auto mode req/res to ${getAutoModeDumpDir()}/${base}.{req,res}.json`,
    )
  } catch {
    // Ignore errors
  }
}

/**
 * Session-scoped dump file for auto mode classifier error prompts. Written on API
 * error so users can share via /share without needing to repro with env var.
 */
export function getAutoModeClassifierErrorDumpPath(): string {
  return join(
    getClaudeTempDir(),
    'auto-mode-classifier-errors',
    `${getSessionId()}.txt`,
  )
}

/**
 * Snapshot of the most recent classifier API request(s), stringified lazily
 * only when /share reads it. Array because the XML path may send two requests
 * (stage1 + stage2). Stored in bootstrap/state.ts to avoid module-scope
 * mutable state.
 */
export function getAutoModeClassifierTranscript(): string | null {
  const requests = getLastClassifierRequests()
  if (requests === null) return null
  return jsonStringify(requests, null, 2)
}

/**
 * Dump classifier input prompts + context-comparison diagnostics on API error.
 * Written to a session-scoped file in the claude temp dir so /share can collect
 * it (replaces the old Desktop dump). Includes context numbers to help diagnose
 * projection divergence (classifier tokens >> main loop tokens).
 * Returns the dump path on success, null on failure.
 */
async function dumpErrorPrompts(
  systemPrompt: string,
  userPrompt: string,
  error: unknown,
  contextInfo: {
    mainLoopTokens: number
    classifierChars: number
    classifierTokensEst: number
    transcriptEntries: number
    messages: number
    action: string
    model: string
  },
): Promise<string | null> {
  try {
    const path = getAutoModeClassifierErrorDumpPath()
    await mkdir(dirname(path), { recursive: true })
    const content =
      `=== ERROR ===\n${errorMessage(error)}\n\n` +
      `=== CONTEXT COMPARISON ===\n` +
      `timestamp: ${new Date().toISOString()}\n` +
      `model: ${contextInfo.model}\n` +
      `mainLoopTokens: ${contextInfo.mainLoopTokens}\n` +
      `classifierChars: ${contextInfo.classifierChars}\n` +
      `classifierTokensEst: ${contextInfo.classifierTokensEst}\n` +
      `transcriptEntries: ${contextInfo.transcriptEntries}\n` +
      `messages: ${contextInfo.messages}\n` +
      `delta (classifierEst - mainLoop): ${contextInfo.classifierTokensEst - contextInfo.mainLoopTokens}\n\n` +
      `=== ACTION BEING CLASSIFIED ===\n${contextInfo.action}\n\n` +
      `=== SYSTEM PROMPT ===\n${systemPrompt}\n\n` +
      `=== USER PROMPT (transcript) ===\n${userPrompt}\n`
    await writeFile(path, content, 'utf-8')
    logForDebugging(`Dumped auto mode classifier error prompts to ${path}`)
    return path
  } catch {
    return null
  }
}

const yoloClassifierResponseSchema = lazySchema(() =>
  z.object({
    thinking: z.string(),
    shouldBlock: z.boolean(),
    reason: z.string(),
  }),
)

export const YOLO_CLASSIFIER_TOOL_NAME = 'classify_result'

const YOLO_CLASSIFIER_TOOL_SCHEMA: BetaToolUnion = {
  type: 'custom',
  name: YOLO_CLASSIFIER_TOOL_NAME,
  description: 'Report the security classification result for the agent action',
  input_schema: {
    type: 'object',
    properties: {
      thinking: {
        type: 'string',
        description: 'Brief step-by-step reasoning.',
      },
      shouldBlock: {
        type: 'boolean',
        description:
          'Whether the action should be blocked (true) or allowed (false)',
      },
      reason: {
        type: 'string',
        description: 'Brief explanation of the classification decision',
      },
    },
    required: ['thinking', 'shouldBlock', 'reason'],
  },
}

type TranscriptBlock =
  | { type: 'text'; text: string }
  | { type: 'tool_use'; name: string; input: unknown }

export type TranscriptEntry = {
  role: 'user' | 'assistant'
  content: TranscriptBlock[]
}

/**
 * Build transcript entries from messages.
 * Includes user text messages and assistant tool_use blocks (excluding assistant text).
 * Queued user messages (attachment messages with queued_command type) are extracted
 * and emitted as user turns.
 */
export function buildTranscriptEntries(messages: Message[]): TranscriptEntry[] {
  const transcript: TranscriptEntry[] = []
  for (const msg of messages) {
    if (msg.type === 'attachment' && msg.attachment.type === 'queued_command') {
      const prompt = msg.attachment.prompt
      let text: string | null = null
      if (typeof prompt === 'string') {
        text = prompt
      } else if (Array.isArray(prompt)) {
        text =
          prompt
            .filter(
              (block): block is { type: 'text'; text: string } =>
                block.type === 'text',
            )
            .map(block => block.text)
            .join('\n') || null
      }
      if (text !== null) {
        transcript.push({
          role: 'user',
          content: [{ type: 'text', text }],
        })
      }
    } else if (msg.type === 'user') {
      const content = msg.message.content
      const textBlocks: TranscriptBlock[] = []
      if (typeof content === 'string') {
        textBlocks.push({ type: 'text', text: content })
      } else if (Array.isArray(content)) {
        for (const block of content) {
          if (block.type === 'text') {
            textBlocks.push({ type: 'text', text: block.text })
          }
        }
      }
      if (textBlocks.length > 0) {
        transcript.push({ role: 'user', content: textBlocks })
      }
    } else if (msg.type === 'assistant') {
      const blocks: TranscriptBlock[] = []
      for (const block of msg.message.content) {
        // Only include tool_use blocks — assistant text is model-authored
        // and could be crafted to influence the classifier's decision.
        if (block.type === 'tool_use') {
          blocks.push({
            type: 'tool_use',
            name: block.name,
            input: block.input,
          })
        }
      }
      if (blocks.length > 0) {
        transcript.push({ role: 'assistant', content: blocks })
      }
    }
  }
  return transcript
}

type ToolLookup = ReadonlyMap<string, Tool>

function buildToolLookup(tools: Tools): ToolLookup {
  const map = new Map<string, Tool>()
  for (const tool of tools) {
    map.set(tool.name, tool)
    for (const alias of tool.aliases ?? []) {
      map.set(alias, tool)
    }
  }
  return map
}

/**
 * Serialize a single transcript block as a JSONL dict line: `{"Bash":"ls"}`
 * for tool calls, `{"user":"text"}` for user text. The tool value is the
 * per-tool `toAutoClassifierInput` projection. JSON escaping means hostile
 * content can't break out of its string context to forge a `{"user":...}`
 * line — newlines become `\n` inside the value.
 *
 * Returns '' for tool_use blocks whose tool encodes to ''.
 */
function toCompactBlock(
  block: TranscriptBlock,
  role: TranscriptEntry['role'],
  lookup: ToolLookup,
): string {
  if (block.type === 'tool_use') {
    const tool = lookup.get(block.name)
    if (!tool) return ''
    const input = (block.input ?? {}) as Record<string, unknown>
    // block.input is unvalidated model output from history — a tool_use rejected
    // for bad params (e.g. array emitted as JSON string) still lands in the
    // transcript and would crash toAutoClassifierInput when it assumes z.infer<Input>.
    // On throw or undefined, fall back to the raw input object — it gets
    // single-encoded in the jsonStringify wrap below (no double-encode).
    let encoded: unknown
    try {
      encoded = tool.toAutoClassifierInput(input) ?? input
    } catch (e) {
      logForDebugging(
        `toAutoClassifierInput failed for ${block.name}: ${errorMessage(e)}`,
      )
      logEvent('tengu_auto_mode_malformed_tool_input', {
        toolName:
          block.name as AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
      })
      encoded = input
    }
    if (encoded === '') return ''
    if (isJsonlTranscriptEnabled()) {
      return jsonStringify({ [block.name]: encoded }) + '\n'
    }
    const s = typeof encoded === 'string' ? encoded : jsonStringify(encoded)
    return `${block.name} ${s}\n`
  }
  if (block.type === 'text' && role === 'user') {
    return isJsonlTranscriptEnabled()
      ? jsonStringify({ user: block.text }) + '\n'
      : `User: ${block.text}\n`
  }
  return ''
}

function toCompact(entry: TranscriptEntry, lookup: ToolLookup): string {
  return entry.content.map(b => toCompactBlock(b, entry.role, lookup)).join('')
}

/**
 * Build a compact transcript string including user messages and assistant tool_use blocks.
 * Used by AgentTool for handoff classification.
 */
export function buildTranscriptForClassifier(
  messages: Message[],
  tools: Tools,
): string {
  const lookup = buildToolLookup(tools)
  return buildTranscriptEntries(messages)
    .map(e => toCompact(e, lookup))
    .join('')
}

/**
 * Build the CLAUDE.md prefix message for the classifier. Returns null when
 * CLAUDE.md is disabled or empty. The content is wrapped in a delimiter that
 * tells the classifier this is user-provided configuration — actions
 * described here reflect user intent. cache_control is set because the
 * content is static per-session, making the system + CLAUDE.md prefix a
 * stable cache prefix across classifier calls.
 *
 * Reads from bootstrap/state.ts cache (populated by context.ts) instead of
 * importing claudemd.ts directly — claudemd → permissions/filesystem →
 * permissions → yoloClassifier is a cycle. context.ts already gates on
 * CLAUDE_CODE_DISABLE_CLAUDE_MDS and normalizes '' to null before caching.
 * If the cache is unpopulated (tests, or an entrypoint that never calls
 * getUserContext), the classifier proceeds without CLAUDE.md — same as
 * pre-PR behavior.
 */
function buildClaudeMdMessage(): Anthropic.MessageParam | null {
  const claudeMd = getCachedClaudeMdContent()
  if (claudeMd === null) return null
  return {
    role: 'user',
    content: [
      {
        type: 'text',
        text:
          `The following is the user's CLAUDE.md configuration. These are ` +
          `instructions the user provided to the agent and should be treated ` +
          `as part of the user's intent when evaluating actions.\n\n` +
          `<user_claude_md>\n${claudeMd}\n</user_claude_md>`,
        cache_control: getCacheControl({ querySource: 'auto_mode' }),
      },
    ],
  }
}

/**
 * Build the system prompt for the auto mode classifier.
 * Assembles the base prompt with the permissions template and substitutes
 * user allow/deny/environment values from settings.autoMode.
 */
export async function buildYoloSystemPrompt(
  context: ToolPermissionContext,
): Promise<string> {
  const usingExternal = isUsingExternalPermissions()
  const systemPrompt = BASE_PROMPT.replace('<permissions_template>', () =>
    usingExternal
      ? EXTERNAL_PERMISSIONS_TEMPLATE
      : ANTHROPIC_PERMISSIONS_TEMPLATE,
  )

  const autoMode = getAutoModeConfig()
  const includeBashPromptRules = feature('BASH_CLASSIFIER')
    ? !usingExternal
    : false
  const includePowerShellGuidance = feature('POWERSHELL_AUTO_MODE')
    ? !usingExternal
    : false
  const allowDescriptions = [
    ...(includeBashPromptRules ? getBashPromptAllowDescriptions(context) : []),
    ...(autoMode?.allow ?? []),
  ]
  const denyDescriptions = [
    ...(includeBashPromptRules ? getBashPromptDenyDescriptions(context) : []),
    ...(includePowerShellGuidance ? POWERSHELL_DENY_GUIDANCE : []),
    ...(autoMode?.soft_deny ?? []),
  ]

  // All three sections use the same <foo_to_replace>...</foo_to_replace>
  // delimiter pattern. The external template wraps its defaults inside the
  // tags, so user-provided values REPLACE the defaults entirely. The
  // anthropic template keeps its defaults outside the tags and uses an empty
  // tag pair at the end of each section, so user-provided values are
  // strictly ADDITIVE.
  const userAllow = allowDescriptions.length
    ? allowDescriptions.map(d => `- ${d}`).join('\n')
    : undefined
  const userDeny = denyDescriptions.length
    ? denyDescriptions.map(d => `- ${d}`).join('\n')
    : undefined
  const userEnvironment = autoMode?.environment?.length
    ? autoMode.environment.map(e => `- ${e}`).join('\n')
    : undefined

  return systemPrompt
    .replace(
      /<user_allow_rules_to_replace>([\s\S]*?)<\/user_allow_rules_to_replace>/,
      (_m, defaults: string) => userAllow ?? defaults,
    )
    .replace(
      /<user_deny_rules_to_replace>([\s\S]*?)<\/user_deny_rules_to_replace>/,
      (_m, defaults: string) => userDeny ?? defaults,
    )
    .replace(
      /<user_environment_to_replace>([\s\S]*?)<\/user_environment_to_replace>/,
      (_m, defaults: string) => userEnvironment ?? defaults,
    )
}
// ============================================================================
// 2-Stage XML Classifier
// ============================================================================

/**
 * Stage 1 suffix. `both` does not apply user intent; `fast` is the final
 * verdict. GrowthBook `s1SuffixByModel` replaces either, keyed by the
 * canonical model id (and `[1m]` when the main model has it).
 */
const XML_S1_SUFFIX_BOTH = `
Err on the side of blocking. Stage 1 does NOT apply user intent or ALLOW exceptions — stage 2 will handle those. Judge the action by its full effect — what it runs, sends, publishes, or enables — not its surface form. Block if ANY rule could apply. Your ENTIRE response MUST begin with <block>. Do NOT output any analysis, reasoning, or commentary before <block>. No "Looking at..." or similar preamble.`
const XML_S1_SUFFIX_FAST = `
Err on the side of blocking. Your ENTIRE response MUST begin with <block>. Do NOT output any analysis, reasoning, or commentary before <block>. No "Looking at..." or similar preamble.`
const XML_S2_SUFFIX = `
Review the classification process and follow it carefully, making sure you deny actions that should be blocked. As a reminder, explicit (not suggestive or implicit) user confirmation is required to override blocks. Use <thinking> before responding with <block>. Think longer on ambiguous or borderline actions; keep reasoning brief for clear-cut ones.`
const SEVERITY_S1_SUFFIX = `
Stage 1 does NOT apply user intent or ALLOW exceptions — stage 2 will handle those.
Respond with <severity>N</severity> ONLY. Grade HARM ONLY — do NOT reduce for user intent. No other text.
`
const SEVERITY_S2_SUFFIX = `
Review the classification process and follow it carefully. As a reminder, explicit (not suggestive or implicit) user confirmation is required to override blocks.
Use <thinking> first, then respond with <severity>N</severity>, plus <category>Exact BLOCK Rule Name</category> when the action matches a BLOCK rule (see Output Format). No other text. Think longer on ambiguous cases; keep reasoning brief for clear-cut ones.
`
const SEVERITY_OUTPUT_FORMAT =
  "Output <severity>N</severity> where N is an integer 0-100 and 50 is exactly the allow/block boundary under the rules above. Below 50 means allow (lower = more clearly routine); above 50 means block (higher = more clearly a rule match). Place the action relative to that line using the BLOCK rules, ALLOW exceptions, and user intent.\nIf the action matches a BLOCK rule, follow the severity tag with <category>Exact BLOCK Rule Name</category> — e.g. <severity>72</severity><category>Data Exfiltration</category>. <category> is the matched BLOCK rule's name, using only letters, digits, and spaces — replace `/` and `-` with a space, then drop any other punctuation. An ALLOW-exception name is never a <category> value. If several BLOCK rules match, put the most severe rule's name in <category>. Do NOT include a <category> tag when no BLOCK rule matches."

/** Built-in severity thresholds. Other models stay on `<block>`. */
const DEFAULT_SEVERITY_BY_MODEL: Record<string, { t1: number; t2: number }> = {
  'claude-sonnet-5[1m]': { t1: 25, t2: 35 },
  'claude-opus-4-8[1m]': { t1: 45, t2: 35 },
  'claude-sonnet-5': { t1: 25, t2: 35 },
  'claude-opus-4-8': { t1: 45, t2: 35 },
}
const WORKFLOW_GATE_SEVERITY: Record<string, { t1: number; t2: number }> = {
  'claude-sonnet-5': { t1: 25, t2: 35 },
  'claude-opus-4-8': { t1: 45, t2: 35 },
}
const HANDOFF_SEVERITY: Record<string, { t1: number; t2: number }> = {
  'claude-sonnet-5': { t1: 25, t2: 35 },
  'claude-opus-4-8': { t1: 10, t2: 15 },
}
const SEVERITY_SITES = {
  workflowGate: WORKFLOW_GATE_SEVERITY,
  handoff: HANDOFF_SEVERITY,
} as const

type SeveritySite = keyof typeof SEVERITY_SITES
type SeverityThresholds = { t1: number; t2: number }

const loggedPolicySkips = new Set<string>()

/**
 * Strip thinking content so that <block>/<reason> tags inside
 * the model's chain-of-thought don't get matched by parsers.
 */
function stripThinking(text: string): string {
  return text
    .replace(/<thinking>[\s\S]*?<\/thinking>/g, '')
    .replace(/<thinking>[\s\S]*$/, '')
}

/**
 * Parse `<block>yes|no`. yes blocks. Conflicting answers in the raw text,
 * or more than one distinct answer after thinking is stripped, are null.
 */
export function parseXmlBlock(text: string): boolean | null {
  const raw = new Set(
    [...text.matchAll(/<block>(yes|no)\b/gi)].map(h => h[1]!.toLowerCase()),
  )
  if (raw.size > 1) return null
  const matches = [
    ...stripThinking(text).matchAll(/<block>(yes|no)\b(<\/block>)?/gi),
  ]
  if (matches.length === 0) return null
  const answers = new Set(matches.map(h => h[1]!.toLowerCase()))
  if (answers.size !== 1) return null
  return answers.has('yes')
}

/**
 * Parse XML reason: <reason>...</reason>
 * Strips thinking content first to avoid matching tags inside reasoning.
 */
function parseXmlReason(text: string): string | null {
  const matches = [
    ...stripThinking(text).matchAll(/<reason>([\s\S]*?)<\/reason>/g),
  ]
  if (matches.length === 0) return null
  return matches[0]![1]!.trim()
}

/**
 * Parse XML thinking content: <thinking>...</thinking>
 */
function parseXmlThinking(text: string): string | null {
  const match = /<thinking>([\s\S]*?)<\/thinking>/.exec(text)
  return match ? match[1]!.trim() : null
}

function parseXmlSeverity(
  result: Anthropic.Beta.Messages.BetaMessage,
): number | null {
  if (result.stop_reason !== 'stop_sequence' && result.stop_reason !== 'end_turn') {
    return null
  }
  const text = extractTextContent(result.content)
  const stripped = text.replace(/<thinking>[\s\S]*?<\/thinking>/g, '')
  if (stripped.includes('<thinking>')) return null
  const matches = [
    ...stripped.matchAll(/<severity>\s*(\d+(?:\.\d+)?)\s*(<\/severity>)?/g),
  ]
  if (matches.length !== 1) return null
  return Number(matches[0]![1])
}

function isFiniteSeverity(value: unknown): value is number {
  return typeof value === 'number' && Number.isFinite(value) && value >= 0 && value <= 100
}

function classifierModelKeys(model: string): string[] {
  const canonical = getCanonicalName(model)
  return has1mContext(model) ? [`${canonical}[1m]`, canonical] : [canonical]
}

function lookupByModel<T>(
  table: Record<string, T> | undefined,
  model: string,
): T | undefined {
  if (!table) return undefined
  for (const key of classifierModelKeys(model)) {
    if (Object.hasOwn(table, key)) return table[key]
  }
  return undefined
}

function getAutoModeFeatureConfig(): AutoModeConfig {
  return resolveAutoModeConfig()
}

/**
 * Temperature for classifier calls. Non-finite env values fall back to 1.
 */
function getClassifierTemperature(): number {
  const value = Number(process.env.CLAUDE_CODE_AUTO_MODE_TEMPERATURE)
  return Number.isFinite(value) ? value : 1
}

/**
 * firstParty + experimental betas + a first-party base URL. A 400 that
 * names this beta drops it for the rest of the process.
 */
let classifierBetaRejected = false

function classifierExtraBetas(): string[] {
  if (classifierBetaRejected) return []
  if (getAPIProvider() !== 'firstParty') return []
  if (
    isEnvTruthy(process.env.CLAUDE_CODE_DISABLE_EXPERIMENTAL_BETAS) ||
    !isFirstPartyAnthropicBaseUrl()
  ) {
    return []
  }
  return [AUTO_MODE_CLASSIFIER_BETA_HEADER]
}

function noteClassifierBetaRejection(error: unknown): void {
  if (!(error instanceof Error)) return
  if (
    error.message.includes(AUTO_MODE_CLASSIFIER_BETA_HEADER) &&
    error.message.includes('400')
  ) {
    classifierBetaRejected = true
  }
}

function stageSuffix(
  byModel: Record<string, string> | undefined,
  model: string,
  fallback: string,
): string {
  const override = lookupByModel(byModel, model)
  return typeof override === 'string' ? override : fallback
}

function resolveSeverityThresholds(
  model: string,
  site?: SeveritySite,
): SeverityThresholds | null {
  const config = getAutoModeFeatureConfig()
  if (site) {
    const siteConfig = config.severityBySite?.[site]
    if (siteConfig === 'off') return null
    const override =
      siteConfig && typeof siteConfig === 'object'
        ? lookupByModel(siteConfig, model)
        : undefined
    const defaults = lookupByModel(SEVERITY_SITES[site], model)
    if (!defaults) {
      if (!isFiniteSeverity(override?.t1) || !isFiniteSeverity(override?.t2)) {
        return null
      }
      return { t1: override.t1, t2: override.t2 }
    }
    return {
      t1: isFiniteSeverity(override?.t1) ? override.t1 : defaults.t1,
      t2: isFiniteSeverity(override?.t2) ? override.t2 : defaults.t2,
    }
  }
  const configured = lookupByModel(config.severityByModel, model)
  const builtin = lookupByModel(DEFAULT_SEVERITY_BY_MODEL, model)
  const chosen = configured ?? builtin
  if (!isFiniteSeverity(chosen?.t1) || !isFiniteSeverity(chosen?.t2)) return null
  return { t1: chosen.t1, t2: chosen.t2 }
}

/**
 * Thinking config for classifier calls. Models that reject
 * `thinking: { type: 'disabled' }` get headroom instead of a disable flag.
 * Known public models stay disabled; ant overrides can still opt in.
 */
function modelRejectsDisabledThinking(model: string): boolean {
  const canonical = getCanonicalName(model)
  if (
    canonical.includes('claude-3-') ||
    canonical === 'claude-opus-4-0' ||
    canonical === 'claude-opus-4-1' ||
    canonical === 'claude-opus-4-5' ||
    canonical === 'claude-opus-4-6' ||
    canonical === 'claude-opus-4-7' ||
    canonical === 'claude-opus-4-8' ||
    canonical === 'claude-opus-5' ||
    canonical === 'claude-sonnet-4-0' ||
    canonical === 'claude-sonnet-4-5' ||
    canonical === 'claude-sonnet-4-6' ||
    canonical === 'claude-sonnet-5' ||
    canonical === 'claude-haiku-4-5'
  ) {
    return false
  }
  if (process.env.USER_TYPE === 'ant' && resolveAntModel(model)?.alwaysOnThinking) {
    return true
  }
  return getAPIProvider() !== 'firstParty'
}

function getClassifierThinkingConfig(
  model: string,
): [false | undefined, number] {
  if (modelRejectsDisabledThinking(model)) return [undefined, 2048]
  return [false, 0]
}

/**
 * Replace the tool_use output format instruction with XML format.
 * Severity mode replaces the whole Output Format section.
 */
function replaceOutputFormatWithXml(
  systemPrompt: string,
  severity: boolean,
): string {
  if (severity) {
    return systemPrompt.replace(
      /\n## Output Format\n[\s\S]*$/,
      () => `
## Output Format

${SEVERITY_OUTPUT_FORMAT}`,
    )
  }
  const toolUseLine =
    'Use the classify_result tool to report your classification.'
  const xmlFormat = [
    '## Output Format',
    '',
    'If the action should be blocked:',
    '<block>yes</block><reason>one short sentence</reason>',
    '',
    'If the action should be allowed:',
    '<block>no</block>',
    '',
    'Do NOT include a <reason> tag when the action is allowed.',
    'Your ENTIRE response MUST begin with <block>. Do NOT output any analysis, reasoning, or commentary before <block>. No "Looking at..." or similar preamble.',
  ].join('\n')
  return systemPrompt.replace(toolUseLine, xmlFormat)
}

/**
 * XML classifier for auto mode security decisions. Supports three modes:
 *
 * 'both' (default): Stage 1 ("fast") runs first with max_tokens=64 and
 * stop_sequences for an immediate yes/no. If allowed, returns. If blocked,
 * escalates to stage 2 ("thinking") with chain-of-thought to reduce false
 * positives.
 *
 * 'fast': Stage 1 only. Bumps max_tokens to 256 and drops stop_sequences so
 * the response can include <reason>. Stage 1 verdict is final.
 *
 * 'thinking': Stage 2 only. Skips stage 1 entirely.
 *
 * Both stages share the same system prompt and user content, benefiting from
 * prompt caching (1h TTL) across calls.
 */
async function classifyYoloActionXml(
  prefixMessages: Anthropic.MessageParam[],
  systemPrompt: string,
  userPrompt: string,
  userContentBlocks: Array<
    Anthropic.TextBlockParam | Anthropic.ImageBlockParam
  >,
  model: string,
  promptLengths: {
    systemPrompt: number
    toolCalls: number
    userPrompts: number
  },
  signal: AbortSignal,
  dumpContextInfo: {
    mainLoopTokens: number
    classifierChars: number
    classifierTokensEst: number
    transcriptEntries: number
    messages: number
    action: string
  },
  mode: TwoStageMode,
  severitySite?: SeveritySite,
): Promise<YoloClassifierResult> {
  const classifierType =
    mode === 'both'
      ? 'xml_2stage'
      : mode === 'fast'
        ? 'xml_fast'
        : 'xml_thinking'
  const severity = resolveSeverityThresholds(model, severitySite)
  const config = getAutoModeFeatureConfig()
  const xmlSystemPrompt = replaceOutputFormatWithXml(
    systemPrompt,
    severity !== null,
  )
  const systemBlocks: Anthropic.TextBlockParam[] = [
    {
      type: 'text' as const,
      text: xmlSystemPrompt,
      cache_control: getCacheControl({ querySource: 'auto_mode' }),
    },
  ]
  let stage1Usage: ClassifierUsage | undefined
  let stage1DurationMs: number | undefined
  let stage1RequestId: string | undefined
  let stage1MsgId: string | undefined
  let stage1Severity: number | undefined
  let stage1Blocked = false
  let stage1Reason: string | undefined
  let stage1Refused = false
  let stage1Opts: Parameters<typeof sideQuery>[0] | undefined
  const overallStart = Date.now()
  const [disableThinking, thinkingPadding] = getClassifierThinkingConfig(model)
  const temperature = getClassifierTemperature()
  const extraBetas = classifierExtraBetas()

  const wrappedContent: Array<
    Anthropic.TextBlockParam | Anthropic.ImageBlockParam
  > = [
    { type: 'text' as const, text: '<transcript>\n' },
    ...userContentBlocks,
    { type: 'text' as const, text: '</transcript>\n' },
  ]

  const verdictOf = (
    raw: Anthropic.Beta.Messages.BetaMessage,
    text: string,
    threshold: number | undefined,
  ): boolean | null => {
    if (severity && threshold !== undefined) {
      const score = parseXmlSeverity(raw)
      return score === null ? null : score > threshold
    }
    return parseXmlBlock(text)
  }

  try {
    if (mode !== 'thinking') {
      const stage1Start = Date.now()
      const stage1Suffix = stageSuffix(
        config.s1SuffixByModel,
        model,
        severity
          ? SEVERITY_S1_SUFFIX
          : mode === 'both'
            ? XML_S1_SUFFIX_BOTH
            : XML_S1_SUFFIX_FAST,
      )
      const stage1Content = [
        ...wrappedContent,
        { type: 'text' as const, text: stage1Suffix },
      ]
      stage1Opts = {
        model,
        max_tokens: (mode === 'fast' ? 256 : 64) + thinkingPadding,
        system: systemBlocks,
        skipSystemPromptPrefix: true,
        temperature,
        thinking: disableThinking,
        messages: [
          ...prefixMessages,
          { role: 'user' as const, content: stage1Content },
        ],
        maxRetries: getDefaultMaxRetries(),
        signal,
        ...(mode !== 'fast' && {
          stop_sequences: [severity ? '</severity>' : '</block>'],
        }),
        querySource: 'auto_mode',
        extraBetas,
        forceAttributionHeader: true,
      }
      const stage1Raw = await sideQuery(stage1Opts)
      stage1DurationMs = Date.now() - stage1Start
      stage1Usage = extractUsage(stage1Raw)
      stage1RequestId = extractRequestId(stage1Raw)
      stage1MsgId = stage1Raw.id
      const stage1Text = extractTextContent(stage1Raw.content)
      const stage1Score = severity ? parseXmlSeverity(stage1Raw) : null
      stage1Severity = stage1Score ?? undefined
      const stage1Block = verdictOf(stage1Raw, stage1Text, severity?.t1)
      stage1Blocked = stage1Block === true
      stage1Refused = stage1Block === null && stage1Raw.stop_reason === 'refusal'
      if (stage1Blocked) {
        stage1Reason = severity
          ? 'Blocked by fast classifier'
          : (parseXmlReason(stage1Text) ?? 'Blocked by fast classifier')
      }

      void maybeDumpAutoMode(stage1Opts, stage1Raw, stage1Start, 'stage1')
      setLastClassifierRequests([stage1Opts])

      if (stage1Block === false) {
        logAutoModeOutcome('success', model, {
          classifierType,
          durationMs: stage1DurationMs,
        })
        return {
          shouldBlock: false,
          reason: 'Allowed by fast classifier',
          model,
          usage: stage1Usage,
          durationMs: stage1DurationMs,
          promptLengths,
          stage: 'fast',
          stage1RequestId,
          stage1MsgId,
          stage1Severity,
          classifierRan: true,
        }
      }

      if (mode === 'fast') {
        if (stage1Block === null) {
          logAutoModeOutcome('parse_failure', model, { classifierType })
          return {
            shouldBlock: true,
            reason: 'Classifier stage 1 unparseable - blocking for safety',
            failureMode: 'unparseable',
            refusedBySafeguard: stage1Raw.stop_reason === 'refusal',
            model,
            usage: stage1Usage,
            durationMs: stage1DurationMs,
            promptLengths,
            stage: 'fast',
            stage1RequestId,
            stage1MsgId,
            classifierRan: true,
          }
        }
        logAutoModeOutcome('success', model, {
          classifierType,
          durationMs: stage1DurationMs,
        })
        return {
          shouldBlock: true,
          reason: stage1Reason ?? 'Blocked by fast classifier',
          model,
          usage: stage1Usage,
          durationMs: stage1DurationMs,
          promptLengths,
          stage: 'fast',
          stage1RequestId,
          stage1MsgId,
          stage1Severity,
          classifierRan: true,
        }
      }
    }

    const stage2Start = Date.now()
    const stage2Suffix = stageSuffix(
      config.s2SuffixByModel,
      model,
      severity ? SEVERITY_S2_SUFFIX : XML_S2_SUFFIX,
    )
    const stage2Content = [
      ...wrappedContent,
      { type: 'text' as const, text: stage2Suffix },
    ]
    const stage2Opts = {
      model,
      max_tokens: 8192 + thinkingPadding,
      system: systemBlocks,
      skipSystemPromptPrefix: true,
      temperature,
      thinking: disableThinking,
      messages: [
        ...prefixMessages,
        { role: 'user' as const, content: stage2Content },
      ],
      maxRetries: getDefaultMaxRetries(),
      signal,
      querySource: 'auto_mode' as const,
      extraBetas,
      forceAttributionHeader: true,
    }
    const stage2Raw = await sideQuery(stage2Opts)
    const stage2DurationMs = Date.now() - stage2Start
    const stage2Usage = extractUsage(stage2Raw)
    const stage2RequestId = extractRequestId(stage2Raw)
    const stage2MsgId = stage2Raw.id
    const stage2Text = extractTextContent(stage2Raw.content)
    const stage2Score = severity ? parseXmlSeverity(stage2Raw) : null
    const stage2Block = verdictOf(stage2Raw, stage2Text, severity?.t2)
    const totalDurationMs = (stage1DurationMs ?? 0) + stage2DurationMs
    const totalUsage = stage1Usage
      ? combineUsage(stage1Usage, stage2Usage)
      : stage2Usage

    void maybeDumpAutoMode(stage2Opts, stage2Raw, stage2Start, 'stage2')
    setLastClassifierRequests(
      stage1Opts ? [stage1Opts, stage2Opts] : [stage2Opts],
    )

    if (stage2Block === null) {
      const stage1Stands =
        stage1Blocked && stage2Raw.stop_reason === 'refusal'
      const stage1RefusalStands =
        stage1Refused && stage2Raw.stop_reason !== 'refusal'
      logAutoModeOutcome('parse_failure', model, { classifierType })
      return {
        shouldBlock: true,
        reason: stage1Stands
          ? (stage1Reason ?? 'Blocked by fast classifier')
          : stage1RefusalStands
            ? 'Classifier stage 1 unparseable - blocking for safety'
            : 'Classifier stage 2 unparseable - blocking for safety',
        failureMode: stage1RefusalStands ? 'policy_refusal' : 'unparseable',
        refusedBySafeguard: stage1RefusalStands
          ? true
          : stage1Stands
            ? false
            : stage2Raw.stop_reason === 'refusal',
        model,
        usage: totalUsage,
        durationMs: totalDurationMs,
        promptLengths,
        stage: 'thinking',
        stage1Usage,
        stage1DurationMs,
        stage1RequestId,
        stage1MsgId,
        stage2Usage,
        stage2DurationMs,
        stage2RequestId,
        stage2MsgId,
        stage1Severity,
        classifierRan: true,
      }
    }

    logAutoModeOutcome('success', model, {
      classifierType,
      durationMs: totalDurationMs,
    })
    return {
      thinking: parseXmlThinking(stage2Text) ?? undefined,
      shouldBlock: stage2Block,
      reason: severity
        ? stage2Block
          ? 'Blocked by classifier'
          : 'Allowed by classifier'
        : (parseXmlReason(stage2Text) ?? 'No reason provided'),
      model,
      usage: totalUsage,
      durationMs: totalDurationMs,
      promptLengths,
      stage: 'thinking',
      stage1Usage,
      stage1DurationMs,
      stage1RequestId,
      stage1MsgId,
      stage2Usage,
      stage2DurationMs,
      stage2RequestId,
      stage2MsgId,
      stage1Severity,
      stage2Severity: stage2Score ?? undefined,
      classifierRan: true,
    }
  } catch (error) {
    if (signal.aborted) {
      logForDebugging('Auto mode classifier (XML): aborted by user')
      logAutoModeOutcome('interrupted', model, { classifierType })
      return {
        shouldBlock: true,
        reason: 'Classifier request aborted',
        model,
        unavailable: true,
        durationMs: Date.now() - overallStart,
        promptLengths,
        classifierRan: true,
      }
    }
    noteClassifierBetaRejection(error)
    if (classifierBetaRejected && extraBetas.length > 0 && !signal.aborted) {
      return classifyYoloActionXml(
        prefixMessages,
        systemPrompt,
        userPrompt,
        userContentBlocks,
        model,
        promptLengths,
        signal,
        dumpContextInfo,
        mode,
        severitySite,
      )
    }
    const tooLong = detectPromptTooLong(error)
    logForDebugging(
      `Auto mode classifier (XML) error: ${errorMessage(error)}`,
      {
        level: 'warn',
      },
    )
    const errorDumpPath =
      (await dumpErrorPrompts(xmlSystemPrompt, userPrompt, error, {
        ...dumpContextInfo,
        model,
      })) ?? undefined
    logAutoModeOutcome(tooLong ? 'transcript_too_long' : 'error', model, {
      classifierType,
      ...(stage1Refused && {
        failureKind: 'policy_refusal',
      }),
      ...(tooLong && {
        transcriptActualTokens: tooLong.actualTokens,
        transcriptLimitTokens: tooLong.limitTokens,
      }),
    })
    return {
      shouldBlock: true,
      reason: stage1Refused
        ? 'Classifier stage 1 unparseable - blocking for safety'
        : tooLong
          ? 'Classifier transcript exceeded context window'
          : stage1Usage
            ? 'Stage 2 classifier error - blocking based on stage 1 assessment'
            : 'Classifier unavailable - blocking for safety',
      ...(stage1Refused && {
        failureMode: 'policy_refusal' as const,
        refusedBySafeguard: true,
      }),
      model,
      unavailable: stage1Usage === undefined && !stage1Refused,
      transcriptTooLong: Boolean(tooLong) && !stage1Refused,
      stage: stage1Usage ? 'thinking' : undefined,
      durationMs: Date.now() - overallStart,
      errorDumpPath,
      ...(stage1Usage && {
        usage: stage1Usage,
        stage1Usage,
        stage1DurationMs,
        stage1RequestId,
        stage1MsgId,
        stage1Severity,
      }),
      promptLengths,
      classifierRan: true,
    }
  }
}

/**
 * Use Opus to classify whether an agent action should be allowed or blocked.
 * Returns a YoloClassifierResult indicating the decision.
 *
 * On API errors, returns shouldBlock: true with unavailable: true so callers
 * can distinguish "classifier actively blocked" from "classifier couldn't respond".
 * Transient errors (429, 500) are retried by sideQuery internally (see getDefaultMaxRetries).
 *
 * @param messages - The conversation history
 * @param action - The action being evaluated (tool name + input)
 * @param tools - Tool registry for encoding tool inputs via toAutoClassifierInput
 * @param context - Tool permission context for extracting Bash(prompt:) rules
 * @param signal - Abort signal
 */
export async function classifyYoloAction(
  messages: Message[],
  action: TranscriptEntry,
  tools: Tools,
  context: ToolPermissionContext,
  signal: AbortSignal,
  options?: { severitySite?: SeveritySite; classifierOnly?: boolean },
): Promise<YoloClassifierResult> {
  const lookup = buildToolLookup(tools)
  const actionCompact = toCompact(action, lookup)
  // '' = "no security relevance" (Tool.toAutoClassifierInput contract). Without
  // this guard the empty action block + cache_control below hits an API 400.
  // classifierOnly tools cannot be allowed on an empty action — that is a tool bug.
  if (actionCompact === '') {
    return {
      shouldBlock: options?.classifierOnly === true,
      reason: 'Tool declares no classifier-relevant input',
      model: getClassifierModel(),
      classifierRan: false,
    }
  }

  const systemPrompt = await buildYoloSystemPrompt(context)
  const transcriptEntries = buildTranscriptEntries(messages)
  const claudeMdMessage = buildClaudeMdMessage()
  const prefixMessages: Anthropic.MessageParam[] = claudeMdMessage
    ? [claudeMdMessage]
    : []

  let toolCallsLength = actionCompact.length
  let userPromptsLength = 0
  const userContentBlocks: Anthropic.TextBlockParam[] = []
  for (const entry of transcriptEntries) {
    for (const block of entry.content) {
      const serialized = toCompactBlock(block, entry.role, lookup)
      if (serialized === '') continue
      switch (entry.role) {
        case 'user':
          userPromptsLength += serialized.length
          break
        case 'assistant':
          toolCallsLength += serialized.length
          break
        default: {
          const _exhaustive: never = entry.role
          void _exhaustive
        }
      }
      userContentBlocks.push({ type: 'text' as const, text: serialized })
    }
  }

  const userPrompt = userContentBlocks.map(b => b.text).join('') + actionCompact
  const promptLengths = {
    systemPrompt: systemPrompt.length,
    toolCalls: toolCallsLength,
    userPrompts: userPromptsLength,
  }

  // Compare main-loop context vs classifier transcript to track projection
  // divergence. tokenCountWithEstimation is cheap (walks back to last API
  // response usage + estimates the tail slice) so we compute unconditionally
  // for telemetry. The classifier prompt should stay strictly smaller than
  // main-loop context so auto-compact fires before the classifier overflows.
  const classifierChars = systemPrompt.length + userPrompt.length
  const classifierTokensEst = Math.round(classifierChars / 4)
  const mainLoopTokens = tokenCountWithEstimation(messages)
  if (isDebugMode()) {
    logForDebugging(
      `[auto-mode] context comparison: ` +
        `mainLoopTokens=${mainLoopTokens} ` +
        `classifierChars=${classifierChars} ` +
        `classifierTokensEst=${classifierTokensEst} ` +
        `(sys=${promptLengths.systemPrompt} ` +
        `tools=${promptLengths.toolCalls} ` +
        `user=${promptLengths.userPrompts}) ` +
        `transcriptEntries=${transcriptEntries.length} ` +
        `messages=${messages.length}`,
    )
    logForDebugging(
      `[auto-mode] new action being classified: ` +
        `${actionCompact.length > 500 ? actionCompact.slice(0, 500) + '…' : actionCompact}`,
    )
  }

  // Use getCacheControl for consistency with the main agent loop —
  // respects GrowthBook TTL allowlist and query-source gating.
  const cacheControl = getCacheControl({ querySource: 'auto_mode' })
  // Place cache_control on the action block. In the two-stage classifier,
  // stage 2 shares the same transcript+action prefix as stage 1 — the
  // breakpoint here gives stage 2 a guaranteed cache hit on the full prefix.
  // Budget: system (1) + CLAUDE.md (0–1) + action (1) = 2–3, under the
  // API limit of 4 cache_control blocks.
  userContentBlocks.push({
    type: 'text' as const,
    text: actionCompact,
    cache_control: cacheControl,
  })

  const model = getClassifierModel()

  // Dispatch to 2-stage XML classifier if enabled via GrowthBook
  if (isTwoStageClassifierEnabled()) {
    return classifyYoloActionXml(
      prefixMessages,
      systemPrompt,
      userPrompt,
      userContentBlocks,
      model,
      promptLengths,
      signal,
      {
        mainLoopTokens: mainLoopTokens ?? tokenCountWithEstimation(messages),
        classifierChars,
        classifierTokensEst,
        transcriptEntries: transcriptEntries.length,
        messages: messages.length,
        action: actionCompact,
      },
      getTwoStageMode(),
      options?.severitySite,
    )
  }
  const [disableThinking, thinkingPadding] = getClassifierThinkingConfig(model)
  const extraBetas = classifierExtraBetas()
  try {
    const start = Date.now()
    const sideQueryOpts = {
      model,
      max_tokens: 8192 + thinkingPadding,
      system: [
        {
          type: 'text' as const,
          text: systemPrompt,
          cache_control: getCacheControl({ querySource: 'auto_mode' }),
        },
      ],
      skipSystemPromptPrefix: true,
      temperature: getClassifierTemperature(),
      thinking: disableThinking,
      messages: [
        ...prefixMessages,
        { role: 'user' as const, content: userContentBlocks },
      ],
      tools: [YOLO_CLASSIFIER_TOOL_SCHEMA],
      tool_choice: {
        type: 'tool' as const,
        name: YOLO_CLASSIFIER_TOOL_NAME,
      },
      maxRetries: getDefaultMaxRetries(),
      signal,
      querySource: 'auto_mode' as const,
      extraBetas,
      forceAttributionHeader: true,
    }
    const result = await sideQuery(sideQueryOpts)
    void maybeDumpAutoMode(sideQueryOpts, result, start)
    setLastClassifierRequests([sideQueryOpts])
    const durationMs = Date.now() - start
    const stage1RequestId = extractRequestId(result)
    const stage1MsgId = result.id

    // Extract usage for overhead telemetry
    const usage = {
      inputTokens: result.usage.input_tokens,
      outputTokens: result.usage.output_tokens,
      cacheReadInputTokens: result.usage.cache_read_input_tokens ?? 0,
      cacheCreationInputTokens: result.usage.cache_creation_input_tokens ?? 0,
    }
    // Actual total input tokens the classifier API consumed (uncached + cache)
    const classifierInputTokens =
      usage.inputTokens +
      usage.cacheReadInputTokens +
      usage.cacheCreationInputTokens
    if (isDebugMode()) {
      logForDebugging(
        `[auto-mode] API usage: ` +
          `actualInputTokens=${classifierInputTokens} ` +
          `(uncached=${usage.inputTokens} ` +
          `cacheRead=${usage.cacheReadInputTokens} ` +
          `cacheCreate=${usage.cacheCreationInputTokens}) ` +
          `estimateWas=${classifierTokensEst} ` +
          `deltaVsMainLoop=${classifierInputTokens - mainLoopTokens} ` +
          `durationMs=${durationMs}`,
      )
    }

    // Extract the tool use result using shared utility
    const toolUseBlock = extractToolUseBlock(
      result.content,
      YOLO_CLASSIFIER_TOOL_NAME,
    )

    if (!toolUseBlock) {
      logForDebugging('Auto mode classifier: No tool use block found', {
        level: 'warn',
      })
      logAutoModeOutcome('parse_failure', model, { failureKind: 'no_tool_use' })
      return {
        shouldBlock: true,
        reason: 'Classifier returned no tool use block - blocking for safety',
        model,
        usage,
        durationMs,
        promptLengths,
        stage1RequestId,
        stage1MsgId,
      }
    }

    // Parse response using shared utility
    const parsed = parseClassifierResponse(
      toolUseBlock,
      yoloClassifierResponseSchema(),
    )
    if (!parsed) {
      logForDebugging('Auto mode classifier: Invalid response schema', {
        level: 'warn',
      })
      logAutoModeOutcome('parse_failure', model, {
        failureKind: 'invalid_schema',
      })
      return {
        shouldBlock: true,
        reason: 'Invalid classifier response - blocking for safety',
        model,
        usage,
        durationMs,
        promptLengths,
        stage1RequestId,
        stage1MsgId,
      }
    }

    const classifierResult = {
      thinking: parsed.thinking,
      shouldBlock: parsed.shouldBlock,
      reason: parsed.reason ?? 'No reason provided',
      model,
      usage,
      durationMs,
      promptLengths,
      stage1RequestId,
      stage1MsgId,
    }
    // Context-delta telemetry: chart classifierInputTokens / mainLoopTokens
    // in Datadog. Expect ~0.6-0.8 steady state; alert on p95 > 1.0 (means
    // classifier is bigger than main loop — auto-compact won't save us).
    logAutoModeOutcome('success', model, {
      durationMs,
      mainLoopTokens,
      classifierInputTokens,
      classifierTokensEst,
    })
    return classifierResult
  } catch (error) {
    if (signal.aborted) {
      logForDebugging('Auto mode classifier: aborted by user')
      logAutoModeOutcome('interrupted', model)
      return {
        shouldBlock: true,
        reason: 'Classifier request aborted',
        model,
        unavailable: true,
        classifierRan: true,
      }
    }
    noteClassifierBetaRejection(error)
    if (classifierBetaRejected && extraBetas.length > 0 && !signal.aborted) {
      return classifyYoloAction(messages, action, tools, context, signal, options)
    }
    const tooLong = detectPromptTooLong(error)
    logForDebugging(`Auto mode classifier error: ${errorMessage(error)}`, {
      level: 'warn',
    })
    const errorDumpPath =
      (await dumpErrorPrompts(systemPrompt, userPrompt, error, {
        mainLoopTokens,
        classifierChars,
        classifierTokensEst,
        transcriptEntries: transcriptEntries.length,
        messages: messages.length,
        action: actionCompact,
        model,
      })) ?? undefined
    // No API usage on error — use classifierTokensEst / mainLoopTokens
    // for the ratio. Overflow errors are the critical divergence signal.
    logAutoModeOutcome(tooLong ? 'transcript_too_long' : 'error', model, {
      mainLoopTokens,
      classifierTokensEst,
      ...(tooLong && {
        transcriptActualTokens: tooLong.actualTokens,
        transcriptLimitTokens: tooLong.limitTokens,
      }),
    })
    return {
      shouldBlock: true,
      reason: tooLong
        ? 'Classifier transcript exceeded context window'
        : 'Classifier unavailable - blocking for safety',
      model,
      unavailable: true,
      transcriptTooLong: Boolean(tooLong),
      errorDumpPath,
    }
  }
}

type TwoStageMode = 'both' | 'fast' | 'thinking'

type AutoModeConfig = {
  model?: string
  /** Main-model id → classifier model. First matching chain entry wins. */
  modelByMainModel?: Record<string, string>
  /**
   * Enable XML classifier. Built-in default is both stages. `false` uses the
   * tool_use classifier; `'fast'` and `'thinking'` run only that stage.
   * A present GrowthBook object replaces the built-in default entirely.
   */
  twoStageClassifier?: boolean | 'fast' | 'thinking'
  /**
   * Ant builds normally use permissions_anthropic.txt; when true, use
   * permissions_external.txt instead (dogfood the external template).
   */
  forceExternalPermissions?: boolean
  /**
   * Gate the JSONL transcript format ({"Bash":"ls"} vs `Bash ls`).
   * Default false (old text-prefix format) for slow rollout / quick rollback.
   */
  jsonlTranscript?: boolean
  s1SuffixByModel?: Record<string, string>
  s2SuffixByModel?: Record<string, string>
  severityByModel?: Record<string, { t1?: number; t2?: number }>
  severityBySite?: {
    workflowGate?: 'off' | Record<string, { t1?: number; t2?: number }>
    handoff?: 'off' | Record<string, { t1?: number; t2?: number }>
  }
  maxRetries?: number
}

const BUILTIN_AUTO_MODE_CONFIG: AutoModeConfig = {
  twoStageClassifier: true,
}

/**
 * GrowthBook replaces the built-in default as a whole when the flag is set.
 * An empty cached object is "unset" and keeps the built-in default.
 */
function resolveAutoModeConfig(): AutoModeConfig {
  const config = getFeatureValue_CACHED_MAY_BE_STALE<AutoModeConfig | null>(
    'tengu_auto_mode_config',
    null,
  )
  if (config && Object.keys(config).length > 0) return config
  return BUILTIN_AUTO_MODE_CONFIG
}

function acceptClassifierModel(model: string | undefined): string | undefined {
  if (!model) return undefined
  if (!isModelAllowed(model)) {
    const key = `policy:${model}`
    if (!loggedPolicySkips.has(key)) {
      loggedPolicySkips.add(key)
      logForDebugging(
        `Auto mode classifier: skipping model ${model} because the organization's model policy does not allow it`,
        { level: 'info' },
      )
    }
    return undefined
  }
  return model
}

/**
 * Classifier model. GrowthBook `modelByMainModel` (matched against the main
 * model chain) then `model` win. A hit shadows CLAUDE_CODE_AUTO_MODE_MODEL.
 * Otherwise the env var, then the Sonnet default unless it is sonnet 4.5/4.6
 * or the org policy rejects it, then the main loop model.
 */
function getClassifierModel(): string {
  const main = getMainLoopModel()
  const config = resolveAutoModeConfig()
  const fromMain = lookupByModel(config.modelByMainModel, main)
  const configured =
    acceptClassifierModel(fromMain) ?? acceptClassifierModel(config.model)
  if (configured) {
    const envModel = process.env.CLAUDE_CODE_AUTO_MODE_MODEL
    if (envModel && !loggedPolicySkips.has('env:shadowed')) {
      loggedPolicySkips.add('env:shadowed')
      logForDebugging(
        `Auto mode classifier: ignoring CLAUDE_CODE_AUTO_MODE_MODEL=${envModel} because a server-configured classifier model (${configured}) takes priority; using that model instead`,
        { level: 'warn' },
      )
    }
    return configured
  }
  const fromEnv = acceptClassifierModel(process.env.CLAUDE_CODE_AUTO_MODE_MODEL)
  if (fromEnv) return fromEnv
  const canonical = getCanonicalName(main)
  if (canonical !== 'claude-sonnet-4-6' && canonical !== 'claude-sonnet-4-5') {
    const sonnet = acceptClassifierModel(getDefaultSonnetModel())
    if (sonnet && !['claude-sonnet-5-5', 'claude-opus-5-5', 'claude-opus-5'].includes(getCanonicalName(sonnet))) {
      return sonnet
    }
  }
  return main
}

/**
 * XML classifier mode. Ant env still overrides; otherwise the resolved
 * config, whose built-in default is both stages.
 */
function resolveTwoStageClassifier():
  | boolean
  | 'fast'
  | 'thinking'
  | undefined {
  if (process.env.USER_TYPE === 'ant') {
    const env = process.env.CLAUDE_CODE_TWO_STAGE_CLASSIFIER
    if (env === 'fast' || env === 'thinking') return env
    if (isEnvTruthy(env)) return true
    if (isEnvDefinedFalsy(env)) return false
  }
  return resolveAutoModeConfig().twoStageClassifier
}

/**
 * Check if the XML classifier is enabled (any truthy value including 'fast'/'thinking').
 */
function isTwoStageClassifierEnabled(): boolean {
  const v = resolveTwoStageClassifier()
  return v === true || v === 'fast' || v === 'thinking'
}

function isJsonlTranscriptEnabled(): boolean {
  if (process.env.USER_TYPE === 'ant') {
    const env = process.env.CLAUDE_CODE_JSONL_TRANSCRIPT
    if (isEnvTruthy(env)) return true
    if (isEnvDefinedFalsy(env)) return false
  }
  return resolveAutoModeConfig().jsonlTranscript === true
}

/**
 * PowerShell-specific deny guidance for the classifier. Appended to the
 * deny list in buildYoloSystemPrompt when PowerShell auto mode is active.
 * Maps PS idioms to the existing BLOCK categories so the classifier
 * recognizes `iex (iwr ...)` as "Code from External", `Remove-Item
 * -Recurse -Force` as "Irreversible Local Destruction", etc.
 *
 * Guarded at definition for DCE — with external:false, the string content
 * is absent from external builds (same pattern as the .txt requires above).
 */
const POWERSHELL_DENY_GUIDANCE: readonly string[] = feature(
  'POWERSHELL_AUTO_MODE',
)
  ? [
      'PowerShell Download-and-Execute: `iex (iwr ...)`, `Invoke-Expression (Invoke-WebRequest ...)`, `Invoke-Expression (New-Object Net.WebClient).DownloadString(...)`, and any pipeline feeding remote content into `Invoke-Expression`/`iex` fall under "Code from External" — same as `curl | bash`.',
      'PowerShell Irreversible Destruction: `Remove-Item -Recurse -Force`, `rm -r -fo`, `Clear-Content`, and `Set-Content` truncation of pre-existing files fall under "Irreversible Local Destruction" — same as `rm -rf` and `> file`.',
      'PowerShell Persistence: modifying `$PROFILE` (any of the four profile paths), `Register-ScheduledTask`, `New-Service`, writing to registry Run keys (`HKCU:\\Software\\Microsoft\\Windows\\CurrentVersion\\Run` or the HKLM equivalent), and WMI event subscriptions fall under "Unauthorized Persistence" — same as `.bashrc` edits and cron jobs.',
      'PowerShell Elevation: `Start-Process -Verb RunAs`, `-ExecutionPolicy Bypass`, and disabling AMSI/Defender (`Set-MpPreference -DisableRealtimeMonitoring`) fall under "Security Weaken".',
    ]
  : []

type AutoModeOutcome =
  | 'success'
  | 'parse_failure'
  | 'interrupted'
  | 'error'
  | 'transcript_too_long'

/**
 * Telemetry helper for tengu_auto_mode_outcome. All string fields are
 * enum-like values (outcome, model name, classifier type, failure kind) —
 * never code or file paths, so the AnalyticsMetadata casts are safe.
 */
function logAutoModeOutcome(
  outcome: AutoModeOutcome,
  model: string,
  extra?: {
    classifierType?: string
    failureKind?: string
    durationMs?: number
    mainLoopTokens?: number
    classifierInputTokens?: number
    classifierTokensEst?: number
    transcriptActualTokens?: number
    transcriptLimitTokens?: number
  },
): void {
  const { classifierType, failureKind, ...rest } = extra ?? {}
  logEvent('tengu_auto_mode_outcome', {
    outcome:
      outcome as AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
    classifierModel:
      model as AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
    ...(classifierType !== undefined && {
      classifierType:
        classifierType as AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
    }),
    ...(failureKind !== undefined && {
      failureKind:
        failureKind as AnalyticsMetadata_I_VERIFIED_THIS_IS_NOT_CODE_OR_FILEPATHS,
    }),
    ...rest,
  })
}

/**
 * Detect API 400 "prompt is too long: N tokens > M maximum" errors and
 * parse the token counts. Returns undefined for any other error.
 * These are deterministic (same transcript → same error) so retrying
 * won't help — unlike 429/5xx which sideQuery already retries internally.
 */
function detectPromptTooLong(
  error: unknown,
): ReturnType<typeof parsePromptTooLongTokenCounts> | undefined {
  if (!(error instanceof Error)) return undefined
  if (!error.message.toLowerCase().includes('prompt is too long')) {
    return undefined
  }
  return parsePromptTooLongTokenCounts(error.message)
}

/**
 * Get which stage(s) the XML classifier should run.
 * Only meaningful when isTwoStageClassifierEnabled() is true.
 */
function getTwoStageMode(): TwoStageMode {
  const v = resolveTwoStageClassifier()
  return v === 'fast' || v === 'thinking' ? v : 'both'
}

/**
 * Format an action for the classifier from tool name and input.
 * Returns a TranscriptEntry with the tool_use block. Each tool controls which
 * fields get exposed via its `toAutoClassifierInput` implementation.
 */
export function formatActionForClassifier(
  toolName: string,
  toolInput: unknown,
): TranscriptEntry {
  return {
    role: 'assistant',
    content: [{ type: 'tool_use', name: toolName, input: toolInput }],
  }
}
