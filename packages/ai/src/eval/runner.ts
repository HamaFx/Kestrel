/**
 * Copyright 2026 Kestrel
 *
 * Licensed under the Apache License, Version 2.0 (the "License");
 * you may not use this file except in compliance with the License.
 * You may obtain a copy of the License at
 *
 *     http://www.apache.org/licenses/LICENSE-2.0
 *
 * Unless required by applicable law or agreed to in writing, software
 * distributed under the License is distributed on an "AS IS" BASIS,
 * WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
 * See the License for the specific language governing permissions and
 * limitations under the License.
 */

// Eval harness — POSTs each acceptance prompt in `prompts.json` to a running
// `/api/chat` endpoint, captures the streamed assistant output and tool-call
// trace via `parse-stream.ts`, and writes a markdown report to
// `<outDir>/<UTC-timestamp>.md`.
//
// Designed to run via `tsx packages/ai/src/eval/runner.ts ...`. Independent
// of the rest of `@kestrel/ai` (no AI Gateway, DB, or zod imports) so it can
// boot without the full package.
//
// CLI:
//   tsx packages/ai/src/eval/runner.ts \
//     --base-url http://localhost:3000 \
//     --cookie "hfx_auth=..." \
//     --out docs/eval \
//     --timeout 120000

import { randomUUID } from 'node:crypto';
import { mkdir, readFile, writeFile } from 'node:fs/promises';
import { dirname, isAbsolute, resolve } from 'node:path';
import { performance } from 'node:perf_hooks';
import { fileURLToPath } from 'node:url';

import { flushMetrics } from '@kestrel/shared/metrics-export';

// Citation oracle lives in the pure module so the Mastra custom scorers can
// reuse it without pulling this runner (fs, crypto, network client) into the
// web bundle. Re-exported here for backward compatibility.
import { computeCitationScore } from './citation-oracle';
import { computeDrift } from './drift';
import { emitEvalMetrics } from './eval-metrics';
import {
  consumeUIMessageStream,
  type AgentProgressSnapshot,
  type ParsedStreamMetadata,
  type ParsedToolCall,
} from './parse-stream';
import {
  DEFAULT_EVAL_QUALITY_GATE_THRESHOLDS,
  evaluateEvalQualityGate,
  thresholdsFromEnv,
  type EvalQualityGateResult,
  type EvalQualityGateThresholds,
} from './quality-gate';

// --- types -----------------------------------------------------------------

export interface RunEvalsArgs {
  /** Base URL the harness will POST to, e.g. `http://localhost:3000`. */
  baseUrl: string;
  /** Full `Cookie` header value, e.g. `hfx_auth=...`. */
  cookie: string;
  /** Directory the markdown report is written into. Created if missing. */
  outDir: string;
  /** Optional override for the prompts file. Defaults to `./prompts.json`. */
  promptsPath?: string;
  /** Per-prompt abort timeout in ms. Defaults to 120_000. */
  timeoutMs?: number;
  /** Optional progress sink. Defaults to `console.log`. */
  onProgress?: (line: string) => void;
  qualityGate?: EvalQualityGateThresholds;
}

export interface PromptDef {
  id: string;
  prompt: string;
  /** Phase 7c — tool-trace assertions. Optional; when present the runner
   *  evaluates them and surfaces pass/fail in the report.
   *  - `expectedTools`: every tool listed must appear in the trace.
   *  - `forbiddenTools`: none of these tools may appear in the trace.
   *  - `mustContainSubstrings`: each substring (case-insensitive) must
   *     appear in the streamed assistant text.
   */
  expectedTools?: string[];
  forbiddenTools?: string[];
  mustContainSubstrings?: string[];
  /** Optional mode sent with this case, e.g. quick, standard, or full. */
  analysisMode?: 'single' | 'quick' | 'standard' | 'full' | 'auto';
  /** Every listed specialist must appear in an observed progress snapshot. */
  expectedAgents?: string[];
  /** Final observed status required for each specialist. */
  expectedAgentStatuses?: Record<string, string>;
  /** Expected terminal result status; supports expected Full-mode failures. */
  expectedTerminalStatus?: 'complete' | 'failed' | 'retrying';
  /** Exact numeric values expected in a structured tool output. */
  expectedToolOutputs?: Array<{
    tool: string;
    path: string;
    value: number;
    tolerance?: number;
  }>;
  /** Deterministic quality gates for safety, grounding, latency, and cost. */
  quality?: {
    requireNumericToolSupport?: boolean;
    requireEventToolSupport?: boolean;
    forbiddenOutputSubstrings?: string[];
    requiredOutputSubstrings?: string[];
    maxTtftMs?: number;
    maxTotalMs?: number;
    maxCostUsd?: number;
  };
}

export interface AssertionFailure {
  kind:
    | 'missing_tool'
    | 'forbidden_tool'
    | 'missing_substring'
    | 'wrong_mode'
    | 'missing_agent'
    | 'wrong_agent_status'
    | 'wrong_terminal_status'
    | 'numeric_mismatch'
    | 'unsupported_numeric_claim'
    | 'unsupported_event_claim'
    | 'unsafe_output'
    | 'missing_safety_text'
    | 'ttft_exceeded'
    | 'latency_exceeded'
    | 'cost_exceeded';
  detail: string;
}

export interface PromptResult {
  id: string;
  prompt: string;
  ttftMs: number | null;
  totalMs: number;
  text: string;
  toolCalls: ParsedToolCall[];
  agentProgress: AgentProgressSnapshot[];
  metadata: ParsedStreamMetadata;
  terminalStatus: string | null;
  ok: boolean;
  error?: string;
  /**
   * Phase C citation oracle — 0..1. Fraction of numeric/event claims in the
   * text that are supported by an appropriate market-data / news tool call.
   * 1.0 means every detected claim is grounded (or no claims were made);
   * null means the result errored before text could be scored.
   */
  citationScore?: number | null;
  /**
   * Phase 7c — assertion failures collected from the case definition. The
   * `ok` flag remains driven by transport / parse failures; assertion
   * failures are reported separately so we don't conflate "the model
   * crashed" with "the model picked a different tool".
   */
  assertions?: AssertionFailure[];
  /**
   * Id of the persisted assistant message this case produced, when the
   * stream completed far enough to emit one. Links the eval case to real
   * user feedback (`ai_message_feedback.message_id`) for the training loop.
   */
  assistantMessageId?: string | null;
}

export interface RunEvalsResult {
  results: PromptResult[];
  reportPath: string;
  /** Machine-readable JSON report path (written alongside the Markdown). */
  jsonPath: string;
  score: EvaluationScore;
  qualityGate: EvalQualityGateResult;
}

export interface EvaluationScore {
  total: number;
  transportPassRate: number;
  assertionPassRate: number;
  agentCoverageRate: number | null;
  overallPassRate: number;
}

// --- public API ------------------------------------------------------------

const DEFAULT_TIMEOUT_MS = 120_000;
const DEFAULT_BASE_URL = 'http://localhost:3000';
const DEFAULT_OUT_DIR = 'docs/eval';

export async function runEvals(args: RunEvalsArgs): Promise<RunEvalsResult> {
  const timeoutMs = args.timeoutMs ?? DEFAULT_TIMEOUT_MS;
  const promptsPath = args.promptsPath ?? defaultPromptsPath();
  const log = args.onProgress ?? ((line: string): void => console.info(line));

  const prompts = await loadPrompts(promptsPath);
  const total = prompts.length;
  const results: PromptResult[] = [];

  for (let i = 0; i < total; i++) {
    const prompt = prompts[i];
    if (!prompt) continue;
    const result = await runOnePrompt({
      prompt,
      baseUrl: args.baseUrl,
      cookie: args.cookie,
      timeoutMs,
    });
    if (
      result.ok &&
      (prompt.expectedTools ||
        prompt.forbiddenTools ||
        prompt.mustContainSubstrings ||
        prompt.analysisMode ||
        prompt.expectedAgents ||
        prompt.expectedAgentStatuses ||
        prompt.expectedTerminalStatus ||
        prompt.expectedToolOutputs ||
        prompt.quality)
    ) {
      result.assertions = evaluateAssertions(prompt, result);
    }
    results.push(result);
    const failedAssertions = result.assertions?.length ?? 0;
    const tag = !result.ok
      ? 'FAIL'
      : failedAssertions > 0
        ? `OK (${failedAssertions} assertion fail${failedAssertions === 1 ? '' : 's'})`
        : 'OK';
    log(`[${i + 1}/${total}] ${prompt.id} ${result.totalMs}ms ${tag}`);
  }

  const score = calculateScore(results);
  const qualityGate = evaluateEvalQualityGate(
    results,
    args.qualityGate ?? DEFAULT_EVAL_QUALITY_GATE_THRESHOLDS,
  );
  const reportPath = await writeReport({
    outDir: args.outDir,
    baseUrl: args.baseUrl,
    results,
    score,
    qualityGate,
  });
  const jsonPath = await writeJsonReport({
    reportPath,
    baseUrl: args.baseUrl,
    results,
    score,
    qualityGate,
  });

  return { results, reportPath, jsonPath, score, qualityGate };
}

// --- per-prompt fetch ------------------------------------------------------

interface RunOnePromptArgs {
  prompt: PromptDef;
  baseUrl: string;
  cookie: string;
  timeoutMs: number;
}

async function runOnePrompt(args: RunOnePromptArgs): Promise<PromptResult> {
  const { prompt, baseUrl, cookie, timeoutMs } = args;
  const messageId = randomUUID();

  // Create a fresh thread first so the FK from chat_messages.thread_id is
  // satisfied. Sending an arbitrary UUID straight to /api/chat would 500
  // because the foreign key references chat_threads(id).
  let threadId: string;
  try {
    threadId = await createThread({ baseUrl, cookie, timeoutMs });
  } catch (err) {
    return {
      id: prompt.id,
      prompt: prompt.prompt,
      ttftMs: null,
      totalMs: 0,
      text: '',
      toolCalls: [],
      agentProgress: [],
      metadata: {},
      terminalStatus: null,
      ok: false,
      error: err instanceof Error ? err.message : String(err),
    };
  }

  // The /api/chat route validates with zod:
  //   { threadId: uuid, messages: [{ id, role, parts: unknown[] }, ...] }
  // and treats the last message as the user's turn.
  const body = JSON.stringify({
    threadId,
    messages: [
      {
        id: messageId,
        role: 'user',
        parts: [{ type: 'text', text: prompt.prompt }],
      },
    ],
    ...(prompt.analysisMode ? { analysisMode: prompt.analysisMode } : {}),
  });

  const controller = new AbortController();
  const timeoutHandle = setTimeout(() => controller.abort(), timeoutMs);

  const startedAt = Date.now();
  const startedAtMono = performance.now();

  try {
    const response = await fetch(`${trimTrailingSlash(baseUrl)}/api/chat`, {
      method: 'POST',
      headers: {
        'content-type': 'application/json',
        accept: 'text/event-stream',
        cookie,
      },
      body,
      signal: controller.signal,
    });

    if (!response.ok) {
      const text = await safeReadText(response);
      const totalMs = Math.round(performance.now() - startedAtMono);
      return {
        id: prompt.id,
        prompt: prompt.prompt,
        ttftMs: null,
        totalMs,
        text: '',
        toolCalls: [],
        agentProgress: [],
        metadata: {},
        terminalStatus: null,
        ok: false,
        error: `HTTP ${response.status} ${response.statusText}${text ? `: ${text.slice(0, 500)}` : ''}`,
      };
    }

    const parsed = await consumeUIMessageStream(response, { startedAt });
    const terminalStatus = parsed.agentProgress.at(-1)?.status ?? null;
    const expectedFailure = prompt.expectedTerminalStatus === 'failed';
    if (parsed.errors.length > 0 && !expectedFailure) {
      return {
        id: prompt.id,
        prompt: prompt.prompt,
        ttftMs: parsed.ttftMs,
        totalMs: parsed.totalMs,
        text: parsed.text,
        toolCalls: parsed.toolCalls,
        agentProgress: parsed.agentProgress,
        metadata: parsed.metadata,
        terminalStatus,
        ok: false,
        error: `stream error: ${parsed.errors.join('; ')}`,
        assistantMessageId: parsed.assistantMessageId,
      };
    }
    return {
      id: prompt.id,
      prompt: prompt.prompt,
      ttftMs: parsed.ttftMs,
      totalMs: parsed.totalMs,
      text: parsed.text,
      toolCalls: parsed.toolCalls,
      agentProgress: parsed.agentProgress,
      metadata: parsed.metadata,
      terminalStatus,
      ok: true,
      citationScore: computeCitationScore(parsed.text, parsed.toolCalls),
      ...(parsed.errors.length > 0
        ? { error: `expected terminal failure: ${parsed.errors.join('; ')}` }
        : {}),
      assistantMessageId: parsed.assistantMessageId,
    };
  } catch (err) {
    const totalMs = Math.round(performance.now() - startedAtMono);
    const aborted = controller.signal.aborted;
    const message = aborted
      ? `timeout after ${timeoutMs}ms`
      : err instanceof Error
        ? err.message
        : String(err);
    return {
      id: prompt.id,
      prompt: prompt.prompt,
      ttftMs: null,
      totalMs,
      text: '',
      toolCalls: [],
      agentProgress: [],
      metadata: {},
      terminalStatus: null,
      ok: false,
      error: message,
    };
  } finally {
    clearTimeout(timeoutHandle);
  }
}

async function safeReadText(response: Response): Promise<string> {
  try {
    return await response.text();
  } catch {
    return '';
  }
}

interface CreateThreadArgs {
  baseUrl: string;
  cookie: string;
  timeoutMs: number;
}

async function createThread(args: CreateThreadArgs): Promise<string> {
  const { baseUrl, cookie, timeoutMs } = args;
  const controller = new AbortController();
  const timeoutHandle = setTimeout(() => controller.abort(), timeoutMs);
  try {
    const response = await fetch(`${trimTrailingSlash(baseUrl)}/api/chat/threads`, {
      method: 'POST',
      headers: {
        'content-type': 'application/json',
        cookie,
      },
      body: '{}',
      signal: controller.signal,
    });
    if (!response.ok) {
      const text = await safeReadText(response);
      throw new Error(
        `failed to create thread: HTTP ${response.status} ${response.statusText}${
          text ? `: ${text.slice(0, 500)}` : ''
        }`,
      );
    }
    const json = (await response.json()) as { thread?: { id?: unknown } };
    const id = json.thread?.id;
    if (typeof id !== 'string' || id.length === 0) {
      throw new Error('thread create returned no id');
    }
    return id;
  } finally {
    clearTimeout(timeoutHandle);
  }
}

// --- prompt loading --------------------------------------------------------

function defaultPromptsPath(): string {
  return fileURLToPath(new URL('./prompts.json', import.meta.url));
}

async function loadPrompts(path: string): Promise<PromptDef[]> {
  const raw = await readFile(path, 'utf-8');
  const parsed: unknown = JSON.parse(raw);
  if (!Array.isArray(parsed)) {
    throw new Error(`prompts file ${path} must be a JSON array`);
  }
  const out: PromptDef[] = [];
  for (const item of parsed) {
    if (
      typeof item === 'object' &&
      item !== null &&
      'id' in item &&
      'prompt' in item &&
      typeof (item as { id: unknown }).id === 'string' &&
      typeof (item as { prompt: unknown }).prompt === 'string'
    ) {
      const obj = item as {
        id: string;
        prompt: string;
        expectedTools?: unknown;
        forbiddenTools?: unknown;
        mustContainSubstrings?: unknown;
        analysisMode?: unknown;
        expectedAgents?: unknown;
        expectedAgentStatuses?: unknown;
        expectedTerminalStatus?: unknown;
        expectedToolOutputs?: unknown;
        quality?: unknown;
      };
      const def: PromptDef = { id: obj.id, prompt: obj.prompt };
      if (Array.isArray(obj.expectedTools)) {
        def.expectedTools = obj.expectedTools.filter((s): s is string => typeof s === 'string');
      }
      if (Array.isArray(obj.forbiddenTools)) {
        def.forbiddenTools = obj.forbiddenTools.filter((s): s is string => typeof s === 'string');
      }
      if (Array.isArray(obj.mustContainSubstrings)) {
        def.mustContainSubstrings = obj.mustContainSubstrings.filter(
          (s): s is string => typeof s === 'string',
        );
      }
      if (
        obj.analysisMode === 'single' ||
        obj.analysisMode === 'quick' ||
        obj.analysisMode === 'standard' ||
        obj.analysisMode === 'full' ||
        obj.analysisMode === 'auto'
      ) {
        def.analysisMode = obj.analysisMode;
      }
      if (Array.isArray(obj.expectedAgents)) {
        def.expectedAgents = obj.expectedAgents.filter((s): s is string => typeof s === 'string');
      }
      if (obj.expectedAgentStatuses && typeof obj.expectedAgentStatuses === 'object') {
        def.expectedAgentStatuses = Object.fromEntries(
          Object.entries(obj.expectedAgentStatuses).filter(
            (entry): entry is [string, string] =>
              typeof entry[0] === 'string' && typeof entry[1] === 'string',
          ),
        );
      }
      if (
        obj.expectedTerminalStatus === 'complete' ||
        obj.expectedTerminalStatus === 'failed' ||
        obj.expectedTerminalStatus === 'retrying'
      ) {
        def.expectedTerminalStatus = obj.expectedTerminalStatus;
      }
      if (Array.isArray(obj.expectedToolOutputs)) {
        const expected = obj.expectedToolOutputs.filter(isExpectedToolOutput);
        if (expected.length > 0) def.expectedToolOutputs = expected;
      }
      if (isQualityConfig(obj.quality)) def.quality = obj.quality;
      out.push(def);
    } else {
      throw new Error(`prompts file ${path} contains an entry without {id, prompt}`);
    }
  }
  if (out.length === 0) {
    throw new Error(`prompts file ${path} is empty`);
  }
  return out;
}

// --- assertion evaluation --------------------------------------------------

function evaluateAssertions(prompt: PromptDef, result: PromptResult): AssertionFailure[] {
  const failures: AssertionFailure[] = [];
  const calledTools = new Set(result.toolCalls.map((t) => t.name));
  if (prompt.analysisMode && prompt.analysisMode !== 'auto') {
    const observedModes = new Set(
      result.agentProgress
        .map((snapshot) => snapshot.mode)
        .filter((mode): mode is string => Boolean(mode)),
    );
    if (observedModes.size > 0 && !observedModes.has(prompt.analysisMode)) {
      failures.push({
        kind: 'wrong_mode',
        detail: `expected ${prompt.analysisMode}, observed ${[...observedModes].join(', ')}`,
      });
    }
  }
  const latestAgents = new Map<string, string>();
  for (const snapshot of result.agentProgress) {
    for (const agent of snapshot.agents) latestAgents.set(agent.agentName, agent.status);
  }
  for (const agent of prompt.expectedAgents ?? []) {
    if (!latestAgents.has(agent)) failures.push({ kind: 'missing_agent', detail: agent });
  }
  for (const [agent, expectedStatus] of Object.entries(prompt.expectedAgentStatuses ?? {})) {
    if (latestAgents.get(agent) !== expectedStatus) {
      failures.push({
        kind: 'wrong_agent_status',
        detail: `${agent}: expected ${expectedStatus}, observed ${latestAgents.get(agent) ?? 'missing'}`,
      });
    }
  }
  if (prompt.expectedTerminalStatus && result.terminalStatus !== prompt.expectedTerminalStatus) {
    failures.push({
      kind: 'wrong_terminal_status',
      detail: `expected ${prompt.expectedTerminalStatus}, observed ${result.terminalStatus ?? 'missing'}`,
    });
  }
  for (const t of prompt.expectedTools ?? []) {
    if (!calledTools.has(t)) {
      failures.push({ kind: 'missing_tool', detail: t });
    }
  }
  for (const t of prompt.forbiddenTools ?? []) {
    if (calledTools.has(t)) {
      failures.push({ kind: 'forbidden_tool', detail: t });
    }
  }
  const lowerText = result.text.toLowerCase();
  for (const sub of prompt.mustContainSubstrings ?? []) {
    if (!lowerText.includes(sub.toLowerCase())) {
      failures.push({ kind: 'missing_substring', detail: sub });
    }
  }

  for (const expected of prompt.expectedToolOutputs ?? []) {
    const call = result.toolCalls.find((toolCall) => toolCall.name === expected.tool);
    const actual = call ? readPath(call.output, expected.path) : undefined;
    if (typeof actual !== 'number' || !Number.isFinite(actual)) {
      failures.push({
        kind: 'numeric_mismatch',
        detail: `${expected.tool}.${expected.path}: expected ${expected.value}, observed ${String(actual ?? 'missing')}`,
      });
      continue;
    }
    const tolerance = expected.tolerance ?? 0;
    if (Math.abs(actual - expected.value) > tolerance) {
      failures.push({
        kind: 'numeric_mismatch',
        detail: `${expected.tool}.${expected.path}: expected ${expected.value} ± ${tolerance}, observed ${actual}`,
      });
    }
  }

  const quality = prompt.quality;
  if (quality) {
    if (quality.requireNumericToolSupport && hasUnsupportedNumericClaim(result.text, calledTools)) {
      failures.push({
        kind: 'unsupported_numeric_claim',
        detail:
          'price-like instrument claim was not accompanied by a numeric market-data tool call',
      });
    }
    if (quality.requireEventToolSupport && hasUnsupportedEventClaim(result.text, calledTools)) {
      failures.push({
        kind: 'unsupported_event_claim',
        detail: 'macro/event claim was not accompanied by a news or calendar tool call',
      });
    }
    for (const forbidden of quality.forbiddenOutputSubstrings ?? []) {
      if (lowerText.includes(forbidden.toLowerCase())) {
        failures.push({ kind: 'unsafe_output', detail: forbidden });
      }
    }
    for (const required of quality.requiredOutputSubstrings ?? []) {
      if (!lowerText.includes(required.toLowerCase())) {
        failures.push({ kind: 'missing_safety_text', detail: required });
      }
    }
    if (
      quality.maxTtftMs !== undefined &&
      (result.ttftMs === null || result.ttftMs > quality.maxTtftMs)
    ) {
      failures.push({
        kind: 'ttft_exceeded',
        detail: `expected ≤ ${quality.maxTtftMs}ms, observed ${result.ttftMs === null ? 'missing' : `${result.ttftMs}ms`}`,
      });
    }
    if (quality.maxTotalMs !== undefined && result.totalMs > quality.maxTotalMs) {
      failures.push({
        kind: 'latency_exceeded',
        detail: `expected ≤ ${quality.maxTotalMs}ms, observed ${result.totalMs}ms`,
      });
    }
    if (
      quality.maxCostUsd !== undefined &&
      (result.metadata.totalCostUsd === undefined ||
        result.metadata.totalCostUsd > quality.maxCostUsd)
    ) {
      failures.push({
        kind: 'cost_exceeded',
        detail: `expected ≤ $${quality.maxCostUsd.toFixed(4)}, observed ${result.metadata.totalCostUsd === undefined ? 'missing' : `$${result.metadata.totalCostUsd.toFixed(4)}`}`,
      });
    }
  }
  return failures;
}

interface ExpectedToolOutput {
  tool: string;
  path: string;
  value: number;
  tolerance?: number;
}

function isExpectedToolOutput(value: unknown): value is ExpectedToolOutput {
  if (typeof value !== 'object' || value === null) return false;
  const item = value as Record<string, unknown>;
  return (
    typeof item.tool === 'string' &&
    typeof item.path === 'string' &&
    typeof item.value === 'number' &&
    Number.isFinite(item.value) &&
    (item.tolerance === undefined || (typeof item.tolerance === 'number' && item.tolerance >= 0))
  );
}

function isQualityConfig(value: unknown): value is NonNullable<PromptDef['quality']> {
  if (typeof value !== 'object' || value === null) return false;
  const config = value as Record<string, unknown>;
  const booleans = ['requireNumericToolSupport', 'requireEventToolSupport'];
  const arrays = ['forbiddenOutputSubstrings', 'requiredOutputSubstrings'];
  const numbers = ['maxTtftMs', 'maxTotalMs', 'maxCostUsd'];
  return (
    booleans.every((key) => config[key] === undefined || typeof config[key] === 'boolean') &&
    arrays.every(
      (key) =>
        config[key] === undefined ||
        (Array.isArray(config[key]) && config[key].every((item) => typeof item === 'string')),
    ) &&
    numbers.every(
      (key) =>
        config[key] === undefined ||
        (typeof config[key] === 'number' && Number.isFinite(config[key]) && config[key] >= 0),
    )
  );
}

function readPath(value: unknown, path: string): unknown {
  let current = value;
  for (const segment of path.split('.')) {
    if (segment.length === 0 || typeof current !== 'object' || current === null) return undefined;
    current = (current as Record<string, unknown>)[segment];
  }
  return current;
}

const NUMERIC_SUPPORT_TOOLS = new Set([
  'get_price',
  'get_candles',
  'get_indicators',
  'get_market_structure',
  'forecast_volatility',
  'analyze_technical',
  'analyze_fundamental',
  'get_session_levels',
  'get_intermarket',
  'compute_position_health',
  'compute_risk',
  'replay_setup',
]);
const EVENT_SUPPORT_TOOLS = new Set([
  'get_news',
  'get_calendar',
  'analyze_fundamental',
  'web_search',
  'search_knowledge',
]);
const INSTRUMENT_PRICE_CLAIM =
  /\b(?:xauusd|gold|eurusd|gbpusd|usdjpy|btcusdt)\b[^.!?\n]{0,100}\b(?:\d{1,5}\.\d{2,5}|0\.\d{3,6})\b/i;
const EVENT_CLAIM = /\b(?:cpi|nfp|fomc|ecb|boe|federal reserve|rate decision|central bank)\b/i;

function hasUnsupportedNumericClaim(text: string, calledTools: Set<string>): boolean {
  return INSTRUMENT_PRICE_CLAIM.test(text) && !hasAnyTool(calledTools, NUMERIC_SUPPORT_TOOLS);
}

function hasUnsupportedEventClaim(text: string, calledTools: Set<string>): boolean {
  return EVENT_CLAIM.test(text) && !hasAnyTool(calledTools, EVENT_SUPPORT_TOOLS);
}

function hasAnyTool(calledTools: Set<string>, supportedTools: ReadonlySet<string>): boolean {
  for (const tool of supportedTools) if (calledTools.has(tool)) return true;
  return false;
}

export { computeCitationScore };
// --- report writing --------------------------------------------------------

interface WriteReportArgs {
  outDir: string;
  baseUrl: string;
  results: PromptResult[];
  score: EvaluationScore;
  qualityGate: EvalQualityGateResult;
}

const MAX_OUTPUT_CHARS = 2000;

async function writeReport(args: WriteReportArgs): Promise<string> {
  const { outDir, baseUrl, results, score, qualityGate } = args;
  const stamp = utcStamp(new Date());
  const reportPath = isAbsolute(outDir)
    ? resolve(outDir, `${stamp}.md`)
    : resolve(process.cwd(), outDir, `${stamp}.md`);

  await mkdir(dirname(reportPath), { recursive: true });
  await writeFile(
    reportPath,
    buildMarkdown({ baseUrl, results, stamp, score, qualityGate }),
    'utf-8',
  );
  return reportPath;
}

interface WriteJsonReportArgs {
  /** Markdown report path the JSON file is written alongside. */
  reportPath: string;
  baseUrl: string;
  results: PromptResult[];
  score: EvaluationScore;
  qualityGate: EvalQualityGateResult;
}

/**
 * Write a machine-readable JSON report next to the Markdown report.
 *
 * Phase C — structured domain oracles: the same run envelope (score,
 * per-prompt result, assertions, tool calls, metadata) must be consumable
 * by dashboards, drift tooling, and regression gates without parsing
 * Markdown. The schema is versioned (`kestrel.eval-report.v1`) so
 * downstream consumers can migrate independently.
 */
async function writeJsonReport(args: WriteJsonReportArgs): Promise<string> {
  const { reportPath, baseUrl, results, score, qualityGate } = args;
  const jsonPath = reportPath.endsWith('.md')
    ? `${reportPath.slice(0, -3)}.json`
    : `${reportPath}.json`;

  const payload = {
    schemaVersion: 'kestrel.eval-report.v1',
    generatedAt: new Date().toISOString(),
    baseUrl,
    score,
    qualityGate,
    drift: computeDrift(results),
    results,
  };

  await mkdir(dirname(jsonPath), { recursive: true });
  await writeFile(jsonPath, `${JSON.stringify(payload, null, 2)}\n`, 'utf-8');
  return jsonPath;
}

interface BuildMarkdownArgs {
  baseUrl: string;
  results: PromptResult[];
  stamp: string;
  score: EvaluationScore;
  qualityGate: EvalQualityGateResult;
}

function buildMarkdown(args: BuildMarkdownArgs): string {
  const { baseUrl, results, stamp, score, qualityGate } = args;
  const total = results.length;
  const failed = results.filter((r) => !r.ok).length;
  const ok = total - failed;
  const assertionsClean = results.filter(
    (r) => r.ok && (!r.assertions || r.assertions.length === 0),
  ).length;
  const assertionsDirty = ok - assertionsClean;
  const ttftValues = results.filter((r) => r.ttftMs !== null).map((r) => r.ttftMs as number);
  const avgTtft = ttftValues.length > 0 ? Math.round(avg(ttftValues)) : null;
  const avgTotal = total > 0 ? Math.round(avg(results.map((r) => r.totalMs))) : null;

  const lines: string[] = [];
  lines.push(`# Eval Report — ${stamp}`);
  lines.push('');
  lines.push(`- Base URL: \`${baseUrl}\``);
  lines.push(`- Prompts run: ${total}`);
  lines.push(`- Succeeded: ${ok}`);
  lines.push(`- Failed: ${failed}`);
  lines.push(`- Assertion clean: ${assertionsClean}/${ok}`);
  if (assertionsDirty > 0) {
    lines.push(`- Assertion failures: ${assertionsDirty}`);
  }
  lines.push(`- Avg TTFT: ${avgTtft === null ? 'n/a' : `${avgTtft}ms`}`);
  lines.push(`- Avg total: ${avgTotal === null ? 'n/a' : `${avgTotal}ms`}`);
  lines.push(`- Transport pass rate: ${(score.transportPassRate * 100).toFixed(1)}%`);
  lines.push(`- Assertion pass rate: ${(score.assertionPassRate * 100).toFixed(1)}%`);
  lines.push(
    `- Agent coverage: ${score.agentCoverageRate === null ? 'n/a' : `${(score.agentCoverageRate * 100).toFixed(1)}%`}`,
  );
  lines.push(`- Overall pass rate: ${(score.overallPassRate * 100).toFixed(1)}%`);
  lines.push(`- Quality gate: ${qualityGate.passed ? 'PASS' : 'FAIL'}`);
  for (const failure of qualityGate.failures) lines.push(`- Gate failure: ${failure}`);
  lines.push('');
  lines.push('---');
  lines.push('');

  for (let i = 0; i < results.length; i++) {
    const r = results[i];
    if (!r) continue;
    lines.push(`## ${i + 1}. ${r.id}${r.ok ? '' : ' — FAILED'}`);
    lines.push('');
    lines.push('**Prompt**');
    lines.push('');
    lines.push('```text');
    lines.push(r.prompt);
    lines.push('```');
    lines.push('');
    lines.push('**Timings**');
    lines.push('');
    lines.push(`- TTFT: ${r.ttftMs === null ? 'n/a' : `${r.ttftMs}ms`}`);
    lines.push(`- Total: ${r.totalMs}ms`);
    if (r.metadata.totalCostUsd !== undefined)
      lines.push(`- Reported cost: $${r.metadata.totalCostUsd.toFixed(4)}`);
    if (r.metadata.totalLatencyMs !== undefined)
      lines.push(`- Server latency: ${r.metadata.totalLatencyMs}ms`);
    if (r.metadata.ttfbMs !== undefined)
      lines.push(`- Server TTFB: ${r.metadata.ttfbMs === null ? 'n/a' : `${r.metadata.ttfbMs}ms`}`);
    if (r.citationScore !== undefined && r.citationScore !== null) {
      lines.push(`- Citation score: ${(r.citationScore * 100).toFixed(0)}%`);
    }
    lines.push('');
    if (!r.ok) {
      lines.push('**Error**');
      lines.push('');
      lines.push('```text');
      lines.push(r.error ?? '(unknown error)');
      lines.push('```');
      lines.push('');
      continue;
    }
    if (r.agentProgress.length > 0) {
      const latest = r.agentProgress[r.agentProgress.length - 1];
      lines.push(`**Agent progress** — mode: ${latest?.mode ?? 'unknown'}`);
      lines.push('');
      for (const agent of latest?.agents ?? []) lines.push(`- ${agent.agentName}: ${agent.status}`);
      lines.push('');
    }
    lines.push('**Tool calls**');
    lines.push('');
    if (r.toolCalls.length === 0) {
      lines.push('_None._');
    } else {
      for (const tc of r.toolCalls) {
        const argsSummary = summarizeJson(tc.args, 200);
        lines.push(`- \`${tc.name}\``);
        lines.push(`  - args: \`${argsSummary}\``);
        lines.push(
          `  - result: ${tc.resultSummary === null ? '_(no output)_' : `\`${tc.resultSummary}\``}`,
        );
      }
    }
    lines.push('');

    if (r.assertions && r.assertions.length > 0) {
      lines.push('**Assertion failures**');
      lines.push('');
      for (const a of r.assertions) {
        if (a.kind === 'missing_tool') lines.push(`- expected tool not called: \`${a.detail}\``);
        else if (a.kind === 'forbidden_tool')
          lines.push(`- forbidden tool was called: \`${a.detail}\``);
        else if (a.kind === 'wrong_terminal_status')
          lines.push(`- terminal status mismatch: ${a.detail}`);
        else lines.push(`- ${a.kind}: ${a.detail}`);
      }
      lines.push('');
    }
    lines.push('**Output**');
    lines.push('');
    const truncated = r.text.length > MAX_OUTPUT_CHARS;
    const shown = truncated ? `${r.text.slice(0, MAX_OUTPUT_CHARS)}…` : r.text;
    lines.push('```text');
    lines.push(shown.length > 0 ? shown : '(no text output)');
    lines.push('```');
    if (truncated) {
      lines.push('');
      lines.push(`_(output truncated at ${MAX_OUTPUT_CHARS} chars; full length ${r.text.length})_`);
    }
    lines.push('');
  }

  return `${lines.join('\n')}\n`;
}

function calculateScore(results: PromptResult[]): EvaluationScore {
  const total = results.length;
  if (total === 0) {
    return {
      total: 0,
      transportPassRate: 0,
      assertionPassRate: 0,
      agentCoverageRate: null,
      overallPassRate: 0,
    };
  }
  const transportPassed = results.filter((result) => result.ok).length;
  const assertionPassed = results.filter(
    (result) => result.ok && (result.assertions?.length ?? 0) === 0,
  ).length;
  const agentCases = results.filter(
    (result) =>
      result.agentProgress.length > 0 ||
      result.assertions?.some((a) => a.kind === 'missing_agent' || a.kind === 'wrong_agent_status'),
  );
  const agentClean = agentCases.filter(
    (result) =>
      !result.assertions?.some(
        (a) => a.kind === 'missing_agent' || a.kind === 'wrong_agent_status',
      ),
  ).length;
  return {
    total,
    transportPassRate: transportPassed / total,
    assertionPassRate: assertionPassed / total,
    agentCoverageRate: agentCases.length > 0 ? agentClean / agentCases.length : null,
    overallPassRate: assertionPassed / total,
  };
}

function summarizeJson(value: unknown, max: number): string {
  let s: string;
  try {
    s = JSON.stringify(value ?? null);
  } catch {
    s = String(value);
  }
  return s.length > max ? `${s.slice(0, max)}…` : s;
}

function avg(xs: number[]): number {
  let sum = 0;
  for (const x of xs) sum += x;
  return sum / xs.length;
}

// --- helpers ---------------------------------------------------------------

function trimTrailingSlash(s: string): string {
  return s.endsWith('/') ? s.slice(0, -1) : s;
}

function utcStamp(d: Date): string {
  // YYYY-MM-DDTHH-MM-SSZ — colons are unsafe in some filesystems.
  const iso = d.toISOString(); // 2024-05-01T13:14:15.123Z
  return iso.replace(/\.\d{3}Z$/, 'Z').replace(/:/g, '-');
}

// --- CLI -------------------------------------------------------------------

interface CliFlags {
  baseUrl: string;
  cookie: string;
  outDir: string;
  timeoutMs: number;
  promptsPath: string | null;
  useCases: boolean;
  help: boolean;
}

function parseCliFlags(argv: string[]): CliFlags | { help: true } {
  const flags: CliFlags = {
    baseUrl: DEFAULT_BASE_URL,
    cookie: process.env.EVAL_COOKIE ?? '',
    outDir: DEFAULT_OUT_DIR,
    timeoutMs: DEFAULT_TIMEOUT_MS,
    promptsPath: null,
    useCases: false,
    help: false,
  };

  for (let i = 0; i < argv.length; i++) {
    const arg = argv[i];
    if (arg === '--help' || arg === '-h') {
      flags.help = true;
      continue;
    }
    if (arg === '--cases') {
      flags.useCases = true;
      continue;
    }
    const next = argv[i + 1];
    if (arg === '--base-url') {
      if (!next) throw new Error('--base-url requires a value');
      flags.baseUrl = next;
      i++;
    } else if (arg === '--cookie') {
      if (!next) throw new Error('--cookie requires a value');
      flags.cookie = next;
      i++;
    } else if (arg === '--out') {
      if (!next) throw new Error('--out requires a value');
      flags.outDir = next;
      i++;
    } else if (arg === '--prompts') {
      if (!next) throw new Error('--prompts requires a value');
      flags.promptsPath = next;
      i++;
    } else if (arg === '--timeout') {
      if (!next) throw new Error('--timeout requires a value');
      const parsed = Number.parseInt(next, 10);
      if (!Number.isFinite(parsed) || parsed <= 0) {
        throw new Error(`--timeout must be a positive integer (got "${next}")`);
      }
      flags.timeoutMs = parsed;
      i++;
    } else if (arg !== undefined && arg.startsWith('--')) {
      throw new Error(`unknown flag: ${arg}`);
    }
  }

  return flags;
}

function printUsage(): void {
  process.stdout.write(
    [
      'Usage: tsx packages/ai/src/eval/runner.ts [options]',
      '',
      'Options:',
      '  --base-url <url>   Base URL of the running app (default: http://localhost:3000)',
      '  --cookie <value>   Full Cookie header value (or set EVAL_COOKIE)',
      '  --out <dir>        Directory for the markdown report (default: docs/eval)',
      '  --timeout <ms>     Per-prompt abort timeout in ms (default: 120000)',
      '  --cases            Use cases.json (with assertions) instead of prompts.json',
      '  --prompts <path>   Override the prompts file path explicitly',
      '  -h, --help         Print this message and exit',
      '',
      'Reads prompts from packages/ai/src/eval/prompts.json (or cases.json',
      'with --cases). Writes <out>/<UTC-timestamp>.md. Exits 0 when every',
      'prompt succeeds AND every assertion passes, non-zero otherwise.',
      '',
    ].join('\n'),
  );
}

async function main(): Promise<void> {
  let flags: CliFlags | { help: true };
  try {
    flags = parseCliFlags(process.argv.slice(2));
  } catch (err) {
    process.stderr.write(`error: ${err instanceof Error ? err.message : String(err)}\n\n`);
    printUsage();
    process.exit(2);
  }

  if ('help' in flags && flags.help) {
    printUsage();
    process.exit(0);
  }

  const f = flags as CliFlags;
  if (!f.cookie || f.cookie.length === 0) {
    process.stderr.write(
      'error: missing cookie. Pass --cookie "hfx_auth=..." or set EVAL_COOKIE.\n',
    );
    process.exit(1);
  }

  const promptsPath =
    f.promptsPath ??
    (f.useCases
      ? fileURLToPath(new URL('./cases.json', import.meta.url))
      : fileURLToPath(new URL('./prompts.json', import.meta.url)));

  const { results, reportPath, jsonPath, score, qualityGate } = await runEvals({
    baseUrl: f.baseUrl,
    cookie: f.cookie,
    outDir: f.outDir,
    timeoutMs: f.timeoutMs,
    promptsPath,
    qualityGate: thresholdsFromEnv(),
  });

  const failed = results.filter((r) => !r.ok).length;
  const dirty = results.filter((r) => r.ok && (r.assertions?.length ?? 0) > 0).length;
  process.stdout.write(`\nReport: ${reportPath}\n`);
  process.stdout.write(`JSON:   ${jsonPath}\n`);
  process.stdout.write(
    `Score: ${(score.overallPassRate * 100).toFixed(1)}% overall, ${(score.transportPassRate * 100).toFixed(1)}% transport\n`,
  );
  process.stdout.write(
    `Done. ${results.length - failed}/${results.length} succeeded, ${failed} failed${dirty > 0 ? `, ${dirty} with assertion failures` : ''}.\n`,
  );

  // Export the eval SLI to Grafana (no-op when GRAFANA_CLOUD_* env is absent)
  // so the nightly run feeds the eval-success SLO.
  emitEvalMetrics(results);
  await flushMetrics();

  process.exit(failed > 0 || dirty > 0 || !qualityGate.passed ? 1 : 0);
}

// Only run main() when this file is executed directly (not when imported).
if (isDirectExecution()) {
  void main();
}

function isDirectExecution(): boolean {
  const entry = process.argv[1];
  if (!entry) return false;
  try {
    const here = fileURLToPath(import.meta.url);
    return resolve(entry) === resolve(here);
  } catch {
    return false;
  }
}
