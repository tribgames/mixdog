// Compaction policy resolution, pressure/target budgeting, telemetry
// persistence, and event emission.
// The fresh-context runner drives the handoff pipeline against live session
// state.
import {
  contextMessagesShapeSignature,
  contextMessagesSignature,
  estimateMessagesTokens,
  estimateRequestReserveTokens,
  estimateToolSchemaTokens,
  providerTokenCalibration,
  resolveSessionCompactPolicy,
  toolSchemaSignature,
} from '../context-utils.mjs';
import { CONTEXT_SHARE_RATIO, COMPACT_TARGET_MIN_TOKENS, COMPACT_SAFETY_PERCENT } from '../compact.mjs';
import { HANDOFF_TIMEOUT_MAX_MS } from '../compact/constants.mjs';
import { envFlag, envPositiveInt } from '../../../../shared/env.mjs';
import { positiveInt } from '../../../../shared/numbers.mjs';
import { cacheWarmUseFor, lastCacheWarmUseAt } from '../../../../shared/idle-auto-clear-gate.mjs';
import { ACCOUNT_PROVIDERS } from '../../../../shared/provider-accounts.mjs';
import { plannedAccountId } from '../../providers/account-pool.mjs';
import { isAgentOwner } from '../../agent-owner.mjs';
import { isAgentModeSession } from '../agent-mode.mjs';
import { providerInputExcludesCache, providerNativePdf } from '../../providers/registry.mjs';
import { contentMediaBytes, contentMediaCount } from '../../providers/media-normalization.mjs';
import { splitProtectedContext } from '../compact/messages.mjs';
import { withLiveCompactionConfig } from '../../runtime-core/compaction-config-keys.mjs';

// Unified context-share rule (compact/constants.mjs CONTEXT_SHARE_RATIO): the
// post-compaction target is 25% of the boundary/context window. One
// number governs every "share of model context" budget.

function resolveCompactTargetRatio(cfg = {}) {
  const raw =
    cfg.targetPercent ??
    cfg.targetPct ??
    cfg.targetRatio ??
    cfg.targetFraction ??
    process.env.MIXDOG_AGENT_COMPACT_TARGET_PERCENT ??
    process.env.MIXDOG_COMPACT_TARGET_PERCENT ??
    CONTEXT_SHARE_RATIO;
  const n = Number(raw);
  if (!Number.isFinite(n) || n <= 0) return CONTEXT_SHARE_RATIO;
  return n > 1 ? n / 100 : n;
}
function resolveCompactTargetTokens(boundaryTokens, cfg = {}) {
  const boundary = positiveInt(boundaryTokens);
  if (!boundary) return null;
  const explicit =
    positiveInt(cfg.targetTokens ?? cfg.target) ||
    envPositiveInt('MIXDOG_AGENT_COMPACT_TARGET_TOKENS') ||
    envPositiveInt('MIXDOG_COMPACT_TARGET_TOKENS');
  if (explicit) return Math.max(1, Math.min(boundary, explicit));
  const minTarget = Math.min(
    boundary,
    positiveInt(cfg.targetMinTokens ?? cfg.minTargetTokens) ||
      envPositiveInt('MIXDOG_AGENT_COMPACT_TARGET_MIN_TOKENS') ||
      envPositiveInt('MIXDOG_COMPACT_TARGET_MIN_TOKENS') ||
      COMPACT_TARGET_MIN_TOKENS
  );
  const byRatio = Math.max(1, Math.floor(boundary * resolveCompactTargetRatio(cfg)));
  return Math.max(1, Math.min(boundary, Math.max(minTarget, byRatio)));
}

function compactTriggerMarginTokens(boundaryTokens) {
  const boundary = positiveInt(boundaryTokens);
  if (!boundary) return 1;
  return Math.max(1, Math.min(1_024, Math.floor(boundary * 0.01)));
}

function legacyCompactTargetBudget(boundaryTokens, targetTokens, reserveTokens) {
  const boundary = positiveInt(boundaryTokens);
  if (!boundary) return null;
  return Math.max(1, Math.min(boundary, targetTokens + reserveTokens));
}

function compactTargetBudgetForTrigger(
  boundaryTokens,
  targetTokens,
  reserveTokens,
  triggerTokens,
  singleShot = false,
  force = false
) {
  const legacyTarget = legacyCompactTargetBudget(boundaryTokens, targetTokens, reserveTokens);
  const trigger = positiveInt(triggerTokens);
  // Degenerate reserve/window combinations cannot leave any post-compact
  // headroom. Keep the legacy target and let the caller compact once only,
  // rather than inventing a zero/negative margin that would immediately loop.
  if (singleShot || !trigger) return legacyTarget;
  const boundedTarget = Math.max(1, Math.min(legacyTarget, trigger - 1));
  // Forced/manual compaction must retain a viable legacy budget when the
  // strict no-repeat clamp would consume all non-reserve working space.
  return force && boundedTarget <= reserveTokens ? legacyTarget : boundedTarget;
}

// The boundary the session compacts against: an explicit boundary clamped to
// the context window, else the window, else the legacy auto limit.
function compactBoundaryFor(sessionRef, cfg) {
  const contextWindow = positiveInt(sessionRef.contextWindow ?? cfg.contextWindow);
  const explicitBoundary = positiveInt(sessionRef.compactBoundaryTokens ?? cfg.boundaryTokens);
  const autoLimit = positiveInt(sessionRef.autoCompactTokenLimit ?? cfg.autoCompactTokenLimit);
  const boundaryTokens =
    explicitBoundary && contextWindow
      ? Math.min(explicitBoundary, contextWindow)
      : explicitBoundary || contextWindow || autoLimit;
  return { contextWindow, boundaryTokens };
}

// Main/user Compact must not land inside its next trigger. Keep a
// 1%-of-boundary (up to 1,024-token) gap above the effective post-compact
// target. Explicit sub-boundary limits and agent triggers retain
// their established precedence/behavior.
function workerTriggerTokens({
  sessionRef,
  policy,
  compactBoundaryTokens,
  legacyTargetBudget,
  singleShot,
  configuredReserve,
}) {
  const minMainTrigger = Math.min(
    compactBoundaryTokens,
    (legacyTargetBudget || 0) + compactTriggerMarginTokens(compactBoundaryTokens)
  );
  const baseTriggerTokens =
    !singleShot && !isAgentOwner(sessionRef) && !policy.autoCompactTokenLimit
      ? Math.max(policy.triggerTokens, minMainTrigger)
      : policy.triggerTokens;
  return Math.max(1, baseTriggerTokens - configuredReserve);
}

function effectiveContextWindowPercent(sessionRef, cfg) {
  const value = Number(sessionRef.effectiveContextWindowPercent ?? cfg.effectiveContextWindowPercent);
  return Number.isFinite(value) ? value : null;
}

export function resolveWorkerCompactPolicy(sessionRef, tools) {
  if (!sessionRef) return null;
  const cfg = sessionRef.compaction || {};
  // Agent mode always compacts on its own: the user is never asked to.
  const auto = (cfg.auto !== false || isAgentModeSession(sessionRef)) && envFlag('MIXDOG_AGENT_COMPACT_AUTO', true);
  if (!auto) return { auto: false };
  const { contextWindow, boundaryTokens } = compactBoundaryFor(sessionRef, cfg);
  if (!boundaryTokens) return null;
  const compactBoundaryTokens = Math.max(1, Math.floor(boundaryTokens * COMPACT_SAFETY_PERCENT));
  // Shared session-compaction policy: main and agent sessions default to
  // full-window trigger (buffer 0 / 100%), with explicit buffer overrides;
  // a truly-explicit sub-boundary limit wins. policy.autoCompactTokenLimit
  // is the sanitized (null when legacy full-window) value so telemetry never
  // re-persists a boundary-collapsing limit.
  const policy = resolveSessionCompactPolicy(sessionRef, compactBoundaryTokens);
  const configuredReserve =
    positiveInt(cfg.reservedTokens) || envPositiveInt('MIXDOG_AGENT_COMPACT_RESERVED_TOKENS') || 0;
  const requestReserve = estimateRequestReserveTokens(tools);
  const reserveTokens = requestReserve + configuredReserve;
  const compactTargetTokens = resolveCompactTargetTokens(compactBoundaryTokens, cfg) || compactBoundaryTokens;
  const legacyTargetBudget = legacyCompactTargetBudget(compactBoundaryTokens, compactTargetTokens, reserveTokens);
  // Request reserve is provider-visible and belongs in the canonical context
  // value. Operator reserve is local headroom, so preserve its early-compact
  // effect by lowering the threshold instead of inflating displayed usage.
  const singleShot = reserveTokens >= policy.triggerTokens;
  const triggerTokens = workerTriggerTokens({
    sessionRef,
    policy,
    compactBoundaryTokens,
    legacyTargetBudget,
    singleShot,
    configuredReserve,
  });
  const bufferTokens = Math.max(0, compactBoundaryTokens - triggerTokens);
  return {
    auto: true,
    boundaryTokens: compactBoundaryTokens,
    triggerTokens,
    bufferTokens,
    bufferRatio: bufferTokens / compactBoundaryTokens,
    compactTargetTokens,
    singleShot,
    contextWindow,
    rawContextWindow: positiveInt(sessionRef.rawContextWindow ?? cfg.rawContextWindow) || contextWindow,
    effectiveContextWindowPercent: effectiveContextWindowPercent(sessionRef, cfg),
    autoCompactTokenLimit: policy.autoCompactTokenLimit,
    // One summary call can run on a slow reasoning model — the session's own
    // model is used whenever the maintenance route is unavailable — and a large
    // transcript takes minutes there. At 30s the call was aborted mid-flight and
    // a recoverable compaction became a failed turn.
    handoffTimeoutMs:
      positiveInt(cfg.timeoutMs) || envPositiveInt('MIXDOG_AGENT_COMPACT_TIMEOUT_MS') || HANDOFF_TIMEOUT_MAX_MS,
    reserveTokens,
    requestReserveTokens: requestReserve,
    configuredReserveTokens: configuredReserve,
    provider: sessionRef.provider || null,
    tokenCalibration: providerTokenCalibration(sessionRef.provider),
    toolSchemaSignature: toolSchemaSignature(tools),
  };
}

// Provider-visible context estimate without operator-only compaction reserve.
// Request/schema reserve remains included because those bytes are sent to the
// model; configured reserve is merely local headroom and must not inflate the
// user-facing context gauge.
export function currentContextEstimateTokens(messageTokensEst, policy) {
  if (messageTokensEst === null) return 0;
  const requestReserve = policyRequestReserveTokens(policy);
  return Math.max(0, Math.round((messageTokensEst + requestReserve) * policyTokenCalibration(policy)));
}

function policyTokenCalibration(policy) {
  return Number(policy?.tokenCalibration) > 0 ? Number(policy.tokenCalibration) : 1;
}

// The request/schema share of the policy reserve: the recorded value, else
// total reserve minus operator headroom, never more than the total.
function policyRequestReserveTokens(policy) {
  const configured = Math.max(0, Number(policy?.configuredReserveTokens) || 0);
  const totalReserve = Math.max(0, Number(policy?.reserveTokens) || 0);
  return Math.min(totalReserve, Math.max(0, Number(policy?.requestReserveTokens ?? totalReserve - configured) || 0));
}

const CONTEXT_USAGE_SNAPSHOT_VERSION = 1;

function contextUsageSnapshotTail(messages) {
  const tail = Array.isArray(messages) ? messages[messages.length - 1] : null;
  return {
    role: String(tail?.role || ''),
    id: String(tail?.uuid || tail?.id || tail?.toolCallId || ''),
  };
}

export function recordContextUsageSnapshot(
  sessionRef,
  policy,
  { messages, usedTokens, messageTokensEst = null, source = 'post_compact', updatedAt = Date.now() } = {}
) {
  if (!sessionRef || !policy || !Array.isArray(messages)) return null;
  const used = Number(usedTokens);
  if (!Number.isFinite(used) || used < 0) return null;
  const messageEstimate = Number.isFinite(Number(messageTokensEst))
    ? Math.max(0, Math.round(Number(messageTokensEst)))
    : estimateMessagesTokens(messages);
  const tail = contextUsageSnapshotTail(messages);
  const snapshot = {
    version: CONTEXT_USAGE_SNAPSHOT_VERSION,
    source: String(source || 'estimated'),
    usedTokens: Math.max(0, Math.round(used)),
    limitTokens: positiveInt(policy.triggerTokens || policy.boundaryTokens) || null,
    messageTokensEst: messageEstimate,
    messageCount: messages.length,
    messagesSignature: contextMessagesSignature(messages),
    tailRole: tail.role,
    tailId: tail.id,
    usageMetricsTurnId: String(sessionRef.usageMetricsTurnId || ''),
    usageMetricsEpoch: Number(sessionRef.usageMetricsEpoch) || 0,
    toolSchemaSignature: policy.toolSchemaSignature || null,
    provider: sessionRef.provider || policy.provider || null,
    model: sessionRef.model || null,
    contextWindow: positiveInt(policy.contextWindow || sessionRef.contextWindow) || null,
    boundaryTokens: positiveInt(policy.boundaryTokens) || null,
    triggerTokens: positiveInt(policy.triggerTokens || policy.boundaryTokens) || null,
    updatedAt: Math.max(0, Math.round(Number(updatedAt) || Date.now())),
  };
  sessionRef.contextUsageSnapshot = snapshot;
  return snapshot;
}

export function resolveContextUsageSnapshot(sessionRef, policy, { messages } = {}) {
  const snapshot = sessionRef?.contextUsageSnapshot;
  if (
    !snapshot ||
    typeof snapshot !== 'object' ||
    snapshot.version !== CONTEXT_USAGE_SNAPSHOT_VERSION ||
    !policy ||
    !Array.isArray(messages)
  )
    return null;
  if (
    String(snapshot.provider || '') !== String(sessionRef?.provider || policy.provider || '') ||
    String(snapshot.model || '') !== String(sessionRef?.model || '')
  )
    return null;
  if (
    Number(snapshot.messageCount) !== messages.length ||
    String(snapshot.usageMetricsTurnId || '') !== String(sessionRef?.usageMetricsTurnId || '') ||
    Number(snapshot.usageMetricsEpoch || 0) !== Number(sessionRef?.usageMetricsEpoch || 0)
  )
    return null;
  const tail = contextUsageSnapshotTail(messages);
  if (String(snapshot.tailRole || '') !== tail.role || String(snapshot.tailId || '') !== tail.id) return null;
  if (
    String(snapshot.toolSchemaSignature || '') !== String(policy.toolSchemaSignature || '') ||
    Number(snapshot.contextWindow || 0) !== Number(policy.contextWindow || sessionRef?.contextWindow || 0) ||
    Number(snapshot.boundaryTokens || 0) !== Number(policy.boundaryTokens || 0) ||
    Number(snapshot.triggerTokens || 0) !== Number(policy.triggerTokens || policy.boundaryTokens || 0)
  )
    return null;
  const exactSignature = contextMessagesSignature(messages);
  if (String(snapshot.messagesSignature || '') !== exactSignature) {
    // Stored-history media normalization can replace inline payloads with
    // durable placeholders without changing the logical transcript. The
    // stable turn/count/tail anchors above preserve the compact snapshot
    // across that serialization boundary while still invalidating it on
    // ordinary subsequent turns.
    const sameLogicalAnchor =
      Number(snapshot.messageCount) === messages.length &&
      String(snapshot.usageMetricsTurnId || '') === String(sessionRef?.usageMetricsTurnId || '') &&
      String(snapshot.tailRole || '') === tail.role &&
      String(snapshot.tailId || '') === tail.id;
    if (!sameLogicalAnchor) return null;
  }
  const used = Number(snapshot.usedTokens);
  return Number.isFinite(used) && used >= 0 ? snapshot : null;
}

export function invalidateContextUsageSnapshot(sessionRef) {
  if (!sessionRef || typeof sessionRef !== 'object') return;
  delete sessionRef.contextUsageSnapshot;
}

function providerPressureTokens(sessionRef, usage) {
  if (!usage || typeof usage !== 'object') return 0;
  // Billed input can repeat context (Gemini long decode); the context input
  // the provider reports then replaces both billed prompt figures.
  const contextInput = Math.max(0, Number(usage.contextInputTokens) || 0);
  const input = contextInput || Math.max(0, Number(usage.inputTokens) || 0);
  const cachedRead = Math.max(0, Number(usage.cachedTokens) || 0);
  const cacheWrite = Math.max(0, Number(usage.cacheWriteTokens) || 0);
  const explicitPrompt = contextInput || Math.max(0, Number(usage.promptTokens) || 0);
  const normalizedPrompt = providerInputExcludesCache(sessionRef?.provider) ? input + cachedRead + cacheWrite : input;
  const prompt = Math.max(explicitPrompt, normalizedPrompt);
  const output = Math.max(0, Number(usage.outputTokens) || 0);
  if (prompt <= 0) {
    // Cursor reports checkpoint occupancy (prompt and response together)
    // instead of a prompt count; that reading already includes the output.
    const occupancy = Number(usage.contextTokens);
    if (Number.isFinite(occupancy) && occupancy > 0) return Math.round(occupancy);
  }
  return Math.max(0, Math.round(prompt + output));
}

/**
 * Align an authoritative provider usage snapshot to the message prefix it
 * covers. Later pressure checks add estimates only for messages after this
 * baseline: actual-usage-plus-growth accounting.
 */
export function recordProviderContextBaseline(
  sessionRef,
  messages,
  usage,
  { boundary = 'complete', sendTools = sessionRef?.tools } = {}
) {
  if (!sessionRef || !Array.isArray(messages)) return false;
  const tokens = providerPressureTokens(sessionRef, usage);
  if (!tokens) return false;
  invalidateContextUsageSnapshot(sessionRef);
  sessionRef.contextPressureBaselineTokens = tokens;
  sessionRef.contextPressureBaselineOutputTokens = Math.max(0, Math.round(Number(usage?.outputTokens) || 0));
  sessionRef.contextPressureBaselineMessageCount = messages.length;
  sessionRef.contextPressureBaselinePrefixSignature = contextMessagesSignature(messages);
  // Second identity for the same prefix, stable across the disk projection's
  // media placeholders, so a cold reader can still prove this anchor belongs
  // to the transcript it just loaded.
  sessionRef.contextPressureBaselineShapeSignature = contextMessagesShapeSignature(messages);
  sessionRef.contextPressureBaselineProvider = sessionRef.provider || null;
  sessionRef.contextPressureBaselineModel = sessionRef.model || null;
  sessionRef.contextPressureBaselineToolSignature = toolSchemaSignature(sendTools);
  sessionRef.contextPressureBaselineRequestReserveTokens = Math.max(
    0,
    Math.round(estimateRequestReserveTokens(sendTools) * providerTokenCalibration(sessionRef.provider))
  );
  // provider_send usage arrives before the response's assistant message is
  // appended. Mark that request boundary so pressure resolution skips the
  // first subsequent assistant representation: its output (including opaque
  // reasoningItems/tool calls) is already authoritative provider usage.
  sessionRef.contextPressureBaselineBoundary = boundary === 'request' ? 'request' : 'complete';
  sessionRef.contextPressureBaselineUpdatedAt = Date.now();
  sessionRef.lastContextTokensStaleAfterCompact = false;
  sessionRef.contextPressureBaselineSource = 'provider';
  delete sessionRef.contextPressureUnanchoredAfterRestart;
  delete sessionRef.contextPressureUnanchoredReason;
  return true;
}

/** A changed transcript cannot reuse usage measured against its old prefix. */
export function invalidateProviderContextBaseline(sessionRef) {
  if (!sessionRef) return;
  sessionRef.contextPressureBaselineTokens = null;
  sessionRef.contextPressureBaselineOutputTokens = null;
  sessionRef.contextPressureBaselineMessageCount = null;
  sessionRef.contextPressureBaselineBoundary = null;
  sessionRef.contextPressureBaselinePrefixSignature = null;
  sessionRef.contextPressureBaselineShapeSignature = null;
  sessionRef.contextPressureBaselineProvider = null;
  sessionRef.contextPressureBaselineModel = null;
  sessionRef.contextPressureBaselineToolSignature = null;
  sessionRef.contextPressureBaselineRequestReserveTokens = null;
  sessionRef.contextPressureBaselineUpdatedAt = null;
  sessionRef.contextPressureBaselineSource = null;
  sessionRef.lastContextTokensStaleAfterCompact = true;
  delete sessionRef.contextPressureUnanchoredAfterRestart;
  delete sessionRef.contextPressureUnanchoredReason;
}

/**
 * Does this anchor still describe this message prefix?
 *
 * The exact signature is authoritative when it matches. It cannot match after a
 * disk round-trip (stored history carries media placeholders instead of inline
 * payloads), so the shape signature answers that case for anchors recorded with
 * one. Anchors that predate the shape signature can only be judged by the
 * identity guards their caller already applied; trusting them while NOTHING has
 * been appended keeps a real provider reading in charge of a transcript the
 * provider itself measured, instead of handing the gauge to an estimate.
 */
function baselinePrefixMatchesTranscript(sessionRef, messages, count) {
  const stored = String(sessionRef.contextPressureBaselinePrefixSignature || '');
  if (!stored) return false;
  if (stored === contextMessagesSignature(messages, count)) return true;
  const storedShape = String(sessionRef.contextPressureBaselineShapeSignature || '');
  if (storedShape) return storedShape === contextMessagesShapeSignature(messages, count);
  return count === messages.length;
}

/**
 * The provider reading that still describes this transcript: its billed total
 * (prompt + output) and the message prefix it covers, with a request-boundary
 * anchor extended over the assistant reply that output usage already paid for.
 * Null when no reading exists or the transcript no longer matches its prefix.
 * Shared by the pressure path below and the /context inspector, which uses it
 * to reconcile its per-item estimates with what the provider actually counted.
 */
export function providerBaselineCoverage(sessionRef, messages) {
  if (!Array.isArray(messages) || !sessionRef || sessionRef.lastContextTokensStaleAfterCompact === true) return null;
  let tokens = positiveInt(sessionRef.contextPressureBaselineTokens);
  const outputTokens = Math.max(0, Number(sessionRef.contextPressureBaselineOutputTokens) || 0);
  let count = Number(sessionRef.contextPressureBaselineMessageCount);
  const baselineAt = Number(sessionRef.contextPressureBaselineUpdatedAt || 0);
  const compactAt = Number(sessionRef.compaction?.lastChangedAt || sessionRef.compaction?.lastCompactAt || 0);
  if (
    !tokens ||
    !Number.isInteger(count) ||
    count < 0 ||
    count > messages.length ||
    (compactAt > 0 && baselineAt > 0 && baselineAt < compactAt) ||
    sessionRef.contextPressureBaselineProvider !== (sessionRef.provider || null) ||
    sessionRef.contextPressureBaselineModel !== (sessionRef.model || null) ||
    !baselinePrefixMatchesTranscript(sessionRef, messages, count)
  )
    return null;
  if (sessionRef.contextPressureBaselineBoundary === 'request') {
    const assistantOffset = messages.slice(count).findIndex((message) => message?.role === 'assistant');
    if (assistantOffset >= 0) {
      // The represented assistant is covered by actual output usage.
      count += assistantOffset + 1;
    } else {
      // Empty/thinking-only continuations append no assistant replay.
      // Their output was billed but is absent from the next request, so
      // remove it and estimate every genuinely later message (the nudge).
      tokens = Math.max(0, tokens - outputTokens);
    }
  }
  return { tokens, count, baselineAt, toolSignature: sessionRef.contextPressureBaselineToolSignature ?? null };
}

function providerBaselinePressureTokens(messages, sessionRef, policy, { includeConfiguredReserve = true } = {}) {
  const aligned = providerBaselineCoverage(sessionRef, messages);
  if (!aligned) return null;
  let { tokens } = aligned;
  const { count, baselineAt } = aligned;
  const calibration = policyTokenCalibration(policy);
  if (sessionRef.contextPressureBaselineToolSignature !== policy?.toolSchemaSignature) {
    const currentRequestReserve = Math.max(0, Math.round((Number(policy?.requestReserveTokens) || 0) * calibration));
    const storedRequestReserve = Number(sessionRef.contextPressureBaselineRequestReserveTokens);
    // A changed deferred/control-tool surface does not invalidate provider
    // usage for the aligned message prefix. Adjust only the request-schema
    // share. Legacy snapshots lack the old share, so conservatively add the
    // current one rather than falling back to a gross full-history estimate.
    tokens =
      Number.isFinite(storedRequestReserve) && storedRequestReserve >= 0
        ? Math.max(0, tokens - Math.round(storedRequestReserve) + currentRequestReserve)
        : tokens + currentRequestReserve;
  }
  // Staleness means usage recording is failing: a provider request completed
  // AFTER this reading without replacing it (every send records its usage
  // after it starts, so a working recorder always leaves the reading newer
  // than the last send) — zero/absent usage keeps the OLD baseline because
  // record() only returns false. Never age on a clock: measured against `now`
  // it discarded the reading of every session that sat unopened for a while
  // (88 of 983 stored sessions), and measured against the session's last
  // activity it discarded it whenever anything was appended more than half an
  // hour after the last request — a user back from a break, an agent's result
  // posted to a waiting Lead — so the next send compacted on the
  // whole-transcript estimate, far above the provider's own count.
  const lastSendAt = Number(sessionRef.lastProviderSendAt) || 0;
  if (messages.length > count && baselineAt > 0 && lastSendAt > baselineAt) return null;
  try {
    // Baseline tokens are authoritative provider billing; only the growth
    // after the baseline is a local estimate and needs billing calibration.
    const growth =
      count < messages.length ? Math.round(estimateMessagesTokens(messages.slice(count)) * calibration) : 0;
    const configuredReserve = includeConfiguredReserve ? Math.max(0, Number(policy?.configuredReserveTokens) || 0) : 0;
    return Math.max(0, tokens + growth + configuredReserve);
  } catch {
    return null;
  }
}

/**
 * Canonical active-context value for display, proactive compaction, and
 * telemetry. Once provider usage exists it is authoritative; only messages
 * appended after that aligned prefix are estimated. The whole-transcript
 * estimate is used only before the first provider reading or after compaction
 * invalidates that reading.
 */
export function resolveContextTokensWithSource(messageTokensEst, policy, { messages, sessionRef } = {}) {
  const baseline = providerBaselinePressureTokens(messages, sessionRef, policy, {
    includeConfiguredReserve: false,
  });
  if (baseline !== null && baseline !== undefined) {
    return { tokens: baseline, source: 'provider' };
  }
  // A crash-recovered transcript whose old provider prefix could not be
  // proven identical keeps the last actual reading for display. It is NOT a
  // proactive-compaction signal: the next real provider response will either
  // refresh the anchor or return an overflow for the existing reactive path.
  if (sessionRef?.contextPressureUnanchoredAfterRestart === true) {
    const lastActual =
      positiveInt(sessionRef.contextPressureBaselineTokens) || positiveInt(sessionRef.lastContextTokens);
    if (lastActual) return { tokens: lastActual, source: 'provider_resume' };
  }
  return {
    tokens: currentContextEstimateTokens(messageTokensEst, policy),
    source: 'estimated',
  };
}

export function resolveContextTokens(messageTokensEst, policy, options = {}) {
  return resolveContextTokensWithSource(messageTokensEst, policy, options).tokens;
}

/**
 * Compatibility names kept for callers while both paths resolve the exact same
 * canonical value.
 */
export function resolveGaugeContextTokens(messageTokensEst, policy, { messages, sessionRef } = {}) {
  return resolveContextTokens(messageTokensEst, policy, { messages, sessionRef });
}

/**
 * The "before" number a compaction row shows: the context the provider last
 * measured, as the gauge displayed it. Falls back to the pass's own value only
 * when no live reading exists (none yet, or invalidated by a prior compaction).
 */
export function compactDisplayBeforeTokens(sessionRef, fallbackTokens) {
  const lastContextTokens = positiveInt(sessionRef?.lastContextTokens);
  if (lastContextTokens && sessionRef.lastContextTokensStaleAfterCompact !== true) return lastContextTokens;
  return fallbackTokens;
}

export function resolveCompactionPressureTokens(messageTokensEst, policy, { messages, sessionRef } = {}) {
  return resolveContextTokens(messageTokensEst, policy, { messages, sessionRef });
}

/** Telemetry pressure when a reactive overflow retry forces the next compact. */
export function compactionTelemetryPressureTokens(
  messageTokensEst,
  policy,
  { reactivePending = false, messages, sessionRef } = {}
) {
  const base = resolveContextTokens(messageTokensEst, policy, { messages, sessionRef });
  if (!reactivePending) return base;
  const floor = positiveInt(policy?.triggerTokens) || positiveInt(policy?.boundaryTokens) || 0;
  return floor ? Math.max(base, floor) : base;
}
/**
 * Translate the total provider-scale target to the raw compactor budget.
 * The builder subtracts reserveTokens; only operator headroom may be added
 * back here. Request schemas already belong INSIDE the displayed target.
 */
export function compactTargetBudget(policy) {
  const boundary = positiveInt(policy?.boundaryTokens);
  if (!boundary) return null;
  const reserve = Math.max(0, Number(policy?.reserveTokens) || 0);
  const gaugeTarget =
    positiveInt(policy?.compactTargetTokens) || resolveCompactTargetTokens(boundary, policy) || boundary;
  const calibration = policyTokenCalibration(policy);
  const requestReserve = policyRequestReserveTokens(policy);
  const toRawTokens = (value) => Math.max(1, Math.floor(value / calibration));
  const rawBoundary = toRawTokens(boundary);
  const rawTarget = Math.max(1, Math.min(rawBoundary, toRawTokens(gaugeTarget)) - requestReserve);
  const gaugeTrigger = positiveInt(policy?.triggerTokens);
  const rawTrigger = gaugeTrigger ? Math.min(rawBoundary, toRawTokens(gaugeTrigger)) : 0;
  // reserveTokens is already raw (estimateRequestReserveTokens plus the
  // configured operator headroom), so it is compared and subtracted as-is.
  const singleShot = policy?.singleShot === true || (rawTrigger > 0 && reserve >= rawTrigger);
  return compactTargetBudgetForTrigger(rawBoundary, rawTarget, reserve, rawTrigger, singleShot, policy?.force === true);
}
const OVERHEAD_TOP_TOOLS = 5;

/**
 * The per-request overhead no compaction can shrink — the finalized wire tool
 * schemas (policy.requestReserveTokens), the protected system/fixed prompt
 * every compaction keeps verbatim, and the configured operator headroom — in
 * the provider-scale units of the compact boundary (calibrated estimates, the
 * configured headroom as configured). Only that fixed estimate can justify a
 * refusal; a provider reading aligned to this prefix and these tool schemas
 * can only withdraw one (it includes compactable history). Null unless the
 * fixed part reaches the boundary: kind 'fixed_overhead' when schemas +
 * system alone do, 'configured_reserve' when the configured headroom pushes
 * the fixed part there.
 */
export function fixedRequestOverhead(policy, messages, tools, sessionRef = null) {
  if (!policy?.auto) return null;
  const boundary = positiveInt(policy.boundaryTokens);
  if (!boundary) return null;
  const calibration = policyTokenCalibration(policy);
  const toProviderScale = (raw) => Math.ceil(Math.max(0, raw) * calibration);
  const toolTokens = toProviderScale(policyRequestReserveTokens(policy));
  const systemTokens = toProviderScale(estimateMessagesTokens(splitProtectedContext(messages || []).protectedPrefix));
  const configuredReserve = Math.max(0, Number(policy.configuredReserveTokens) || 0);
  const fixed = toolTokens + systemTokens;
  // A provider reading of this very prefix with these very tools measured
  // the whole request, compactable history included: an upper bound of the
  // fixed part, never proof of it. When it is not above the estimate, the
  // estimate is known to overstate the fixed part by an unknown amount, so
  // nothing here can show that compaction is futile.
  const measuredRequestTokens = measuredFixedRequestTokens(sessionRef, messages, policy);
  if (measuredRequestTokens !== null && measuredRequestTokens <= fixed) return null;
  // Refuse only when the fixed part itself (plus the headroom, for the
  // reserve kind) reaches the boundary — never on a near miss of a heuristic
  // estimate: those requests compact or go out, and the provider's own
  // overflow handling decides.
  let kind = null;
  if (fixed >= boundary) kind = 'fixed_overhead';
  else if (configuredReserve > 0 && fixed + configuredReserve >= boundary) kind = 'configured_reserve';
  if (!kind) return null;
  const counted = (Array.isArray(tools) ? tools : []).filter(
    (tool) => tool?.deferLoading !== true && tool?.defer_loading !== true
  );
  const largestTools = counted
    .map((tool) => ({
      name: String(tool?.name || tool?.type || 'tool'),
      tokens: toProviderScale(estimateToolSchemaTokens([tool])),
    }))
    .sort((a, b) => b.tokens - a.tokens || a.name.localeCompare(b.name))
    .slice(0, OVERHEAD_TOP_TOOLS);
  return {
    kind,
    contextWindowTokens: positiveInt(policy.contextWindow) || boundary,
    boundaryTokens: boundary,
    toolCount: counted.length,
    toolTokens,
    systemTokens,
    configuredReserveTokens: configuredReserve,
    measuredRequestTokens,
    largestTools,
  };
}

/**
 * Identity of the fixed inputs fixedRequestOverhead judges: the wire tool
 * schemas, the protected system context, the configured headroom and the
 * boundary. A verdict holds while this is unchanged; the provider reading is
 * deliberately not part of it (compaction clears it, fixed overhead stays).
 */
export function fixedRequestOverheadInputs(policy, messages) {
  if (!policy?.auto) return null;
  return JSON.stringify([
    policy.toolSchemaSignature || '',
    contextMessagesSignature(splitProtectedContext(messages || []).protectedPrefix),
    Math.max(0, Number(policy.configuredReserveTokens) || 0),
    positiveInt(policy.boundaryTokens) || 0,
  ]);
}

// The provider-measured size of the last request when it still describes
// this transcript prefix and was sent with the same tool schemas; else null.
function measuredFixedRequestTokens(sessionRef, messages, policy) {
  if (!sessionRef || !Array.isArray(messages)) return null;
  const aligned = providerBaselineCoverage(sessionRef, messages);
  if (!aligned?.toolSignature || aligned.toolSignature !== policy?.toolSchemaSignature) return null;
  return aligned.tokens;
}

// Anthropic refuses a request body over 32 MB (HTTP 413) however few tokens it
// holds, and inline media is what gets there: an image is priced at no more
// than ~1.6k tokens yet carries up to 5 MB of base64. Tool-result media is the
// part compaction drops, so it alone arms this trigger; attachments the user
// sent survive compaction and would only make it repeat.
const REQUEST_MEDIA_COMPACT_BYTES = 24_000_000;
// Providers also cap the number of images plus native documents one request
// may carry (100 on Anthropic); the same tool-result media arms the trigger.
const REQUEST_MEDIA_COMPACT_COUNT = 100;

export function shouldCompactForRequestMedia(messages, provider = '') {
  // A PDF that lowers to text is neither bytes nor a document on the wire.
  const nativePdf = providerNativePdf(provider);
  let bytes = 0;
  let count = 0;
  for (const message of messages) {
    if (message?.role !== 'tool') continue;
    bytes += contentMediaBytes(message.content, { nativePdf });
    count += contentMediaCount(message.content, { nativePdf });
    if (bytes >= REQUEST_MEDIA_COMPACT_BYTES || count > REQUEST_MEDIA_COMPACT_COUNT) return true;
  }
  return false;
}

// Anthropic's 5m message-tail TTL (agent-runtime/cache-strategy.mjs gives it
// to agent sessions). A send this long after the previous one finds the tail
// cache expired and would rewrite the whole accumulated transcript; compacting
// first makes that cold write the compacted transcript instead. The tail was
// last used by the session's own send or by a successful cache warm
// (cache-warm.mjs), which reads and refreshes it without moving
// lastProviderSendAt: a warmed tail has not expired — for a request on the
// warm's provider, model and account only, since the entry lives there.
const AGENT_MESSAGE_CACHE_TTL_MS = 5 * 60_000;

// The account the request would be served by: the roster's first pick for a
// provider with accounts (account-pool.mjs), '' for one without a roster.
function requestAccountId(provider, model, sessionRef, opts, messages) {
  if (!ACCOUNT_PROVIDERS.includes(provider)) return '';
  return plannedAccountId(provider, {
    sessionId: opts?.sessionId || sessionRef?.id || null,
    messages,
    providerState: opts?.providerState,
    model,
  });
}

/** Whether the agent session's 5m message tail expired before this request
 *  on `provider` / `model` (default: the session's route). */
export function shouldCompactForExpiredAgentCache(sessionRef, opts, { provider, model, messages = [] } = {}) {
  if (!isAgentOwner(sessionRef) || opts?.cacheStrategy?.messages !== '5m') return false;
  const lastSendAt = Number(sessionRef.lastProviderSendAt);
  if (!(lastSendAt > 0)) return false;
  const now = Date.now();
  if (now - lastSendAt <= AGENT_MESSAGE_CACHE_TTL_MS) return false;
  // No warm since the last send: the tail expired.
  if (!(lastCacheWarmUseAt(sessionRef.id) > lastSendAt)) return true;
  const route = { provider: provider || sessionRef.provider || '', model: model || sessionRef.model || '' };
  const accountId = requestAccountId(route.provider, route.model, sessionRef, opts, messages);
  if (accountId === null) return true;
  const warmAt = cacheWarmUseFor(sessionRef.id, { ...route, accountId });
  return now - Math.max(lastSendAt, warmAt) > AGENT_MESSAGE_CACHE_TTL_MS;
}

export function shouldCompactForSession(
  messageTokensEst,
  policy,
  { forceReactive = false, messages, sessionRef, pressureTokens } = {}
) {
  if (!policy?.auto || !policy.boundaryTokens) return false;
  // send-with-recovery permits exactly one context-overflow retry per send
  // (`contextOverflowRetryUsed`), so this can consume at most one additional
  // reactive compact after a one-shot attempt; a second overflow is surfaced.
  if (forceReactive) return true;
  // Resume parity: never destroy durable history from an unanchored local
  // estimate. One provider attempt re-establishes actual usage; a genuine
  // overflow still enters through forceReactive above.
  if (sessionRef?.contextPressureUnanchoredAfterRestart === true) return false;
  // A reserve at/above the trigger (or a one-token boundary)
  // can never satisfy target < trigger. Permit one legacy compact attempt,
  // then suppress automatic repeats until an operator intervenes.
  if (policy.singleShot === true && sessionRef?.compaction?.singleShotConsumed === true) return false;
  if (messageTokensEst === null) return true;
  const pressure = Number.isFinite(Number(pressureTokens))
    ? Number(pressureTokens)
    : resolveContextTokens(messageTokensEst, policy, { messages, sessionRef });
  const trigger = policy.triggerTokens || policy.boundaryTokens;
  if (pressure < trigger) return false;
  // The provider's own accounting outranks a local estimate for a transcript
  // the provider ALREADY measured. When the anchor could not be verified the
  // pressure above is that estimate, and compacting on it destroyed history
  // for sessions running at a quarter of their window. This never suppresses
  // a compaction the growth since that reading could justify: it applies only
  // while NOTHING has been appended, so the two numbers describe one
  // transcript. A genuine overflow still enters through forceReactive above.
  if (
    Number(sessionRef?.contextPressureBaselineMessageCount) === (Array.isArray(messages) ? messages.length : -1) &&
    providerReadingBelowTrigger(sessionRef, trigger) &&
    resolveContextTokensWithSource(messageTokensEst, policy, { messages, sessionRef }).source === 'estimated'
  )
    return false;
  return true;
}

/** A last actual prompt size that no compaction has invalidated since. */
function providerReadingBelowTrigger(sessionRef, trigger) {
  const actual = positiveInt(sessionRef?.lastContextTokens);
  if (!actual || !trigger || actual >= trigger) return false;
  if (sessionRef.lastContextTokensStaleAfterCompact === true) return false;
  const compactAt = Number(sessionRef.compaction?.lastChangedAt || sessionRef.compaction?.lastCompactAt || 0);
  const usageAt = Number(sessionRef.lastContextTokensUpdatedAt || 0);
  if (compactAt > 0 && usageAt <= compactAt) return false;
  return true;
}
// Legacy/semantic compaction fields that no longer describe the live policy.
const COMPACTION_TRANSIENT_KEYS = [
  'type',
  'compactType',
  'semantic',
  'recallFastTrack',
  'semanticModel',
  'semanticTimeoutMs',
  'tailTurns',
  'lastSemantic',
  'lastSemanticError',
  'lastRecallFastTrack',
  'lastRecallFastTrackError',
];

// The per-check telemetry record. pre_send and pre_send_check are both
// successful terminal pre-send states — pre_send_check is the no-op path
// after a prior recovered/failing compact, and retaining its old component
// error made status report a failure although this send's compaction stage
// completed successfully — so a terminal success clears a carried error;
// otherwise a meta key that is present (even as null) replaces the previous
// value.
function compactionTelemetryRecord(sessionRef, policy, meta, prev) {
  const changed = meta.compactChanged === true;
  const terminalSuccess = meta.stage === 'pre_send' || meta.stage === 'pre_send_check';
  const carriedError = (present, next, previous) => {
    if (terminalSuccess) return null;
    return present ? (next ?? null) : (previous ?? null);
  };
  // Config-owned fields stay the live ones (withLiveCompactionConfig): `policy`
  // was resolved before a compaction that a reload may have outlived.
  return withLiveCompactionConfig(prev, {
    requestReserveTokens: policy.requestReserveTokens || 0,
    reserveTokens: policy.reserveTokens || 0,
    boundaryTokens: policy.boundaryTokens || null,
    triggerTokens: policy.triggerTokens || null,
    bufferTokens: policy.bufferTokens || 0,
    bufferRatio: policy.bufferRatio ?? prev.bufferRatio ?? null,
    contextWindow: policy.contextWindow || null,
    rawContextWindow: policy.rawContextWindow || null,
    effectiveContextWindowPercent: policy.effectiveContextWindowPercent ?? null,
    autoCompactTokenLimit: policy.autoCompactTokenLimit || null,
    handoffTimeoutMs: policy.handoffTimeoutMs || null,
    lastCheckedAt: Date.now(),
    lastBeforeTokens: meta.beforeTokens ?? null,
    lastAfterTokens: meta.afterTokens ?? null,
    lastPressureTokens: meta.pressureTokens ?? null,
    // A successful compact has already replaced the transcript. Publishing
    // its pre-compact pressure here made persisted/UI state jump back to
    // ~200k immediately after a 20k result and could be mistaken for a
    // second trigger before contextStatus recomputed. Terminal mutations
    // must expose the post-compact estimate.
    currentEstimatedTokens:
      changed && meta.stage === 'pre_send'
        ? (meta.afterTokens ?? meta.pressureTokens ?? prev.currentEstimatedTokens ?? null)
        : (meta.pressureTokens ?? prev.currentEstimatedTokens ?? null),
    lastApiRequestTokens: positiveInt(sessionRef?.lastContextTokens) || prev.lastApiRequestTokens || null,
    lastStage: meta.stage || prev.lastStage || null,
    lastChanged: changed,
    lastTrigger: meta.trigger || prev.lastTrigger || null,
    lastFreshContext: meta.freshContext === true,
    lastFreshContextError: carriedError(
      Object.hasOwn(meta, 'freshContextError'),
      meta.freshContextError,
      prev.lastFreshContextError
    ),
    lastHandoffSource: meta.handoffSource || prev.lastHandoffSource || null,
    lastError: carriedError(
      Object.hasOwn(meta, 'compactError') || Object.hasOwn(meta, 'lastError'),
      meta.compactError ?? meta.lastError,
      prev.lastError
    ),
    // The last compaction's wall time: replaced only by a stage that reports
    // a finished compaction's duration; a plain pre-send check keeps it (the
    // other timing fields stay with `...prev`).
    lastDurationMs:
      meta.durationMs != null && Number.isFinite(Number(meta.durationMs))
        ? Math.max(0, Math.round(Number(meta.durationMs)))
        : (prev.lastDurationMs ?? null),
    compactCount: (prev.compactCount || 0) + (changed ? 1 : 0),
    singleShotConsumed:
      policy.singleShot === true && meta.stage === 'compacting' ? true : prev.singleShotConsumed === true,
  });
}

// Postmortem ring buffer: the per-check telemetry record is overwritten on
// every stage change, which erased all pre-compact evidence when a session
// blew past its trigger without compacting. Keep the last few decisions
// (pressure vs estimate vs trigger plus the live baseline) on the session
// so a missed-trigger incident is diagnosable after the fact.
function recentCompactChecks(sessionRef, policy, meta, prev) {
  const prior = Array.isArray(prev.recentChecks) ? prev.recentChecks : [];
  return [
    ...prior,
    {
      at: Date.now(),
      stage: meta.stage || null,
      pressure: meta.pressureTokens ?? null,
      est: meta.messageTokensEst ?? meta.beforeTokens ?? null,
      trigger: policy.triggerTokens || policy.boundaryTokens || null,
      baseline: positiveInt(sessionRef.contextPressureBaselineTokens) || null,
      baselineAt: Number(sessionRef.contextPressureBaselineUpdatedAt) || null,
    },
  ].slice(-8);
}

// Persists the policy's window/boundary on the session. Only the sanitized
// (sub-boundary) explicit limit is kept: policy.autoCompactTokenLimit is
// already null for legacy derived full-window values, so a stale
// boundary-sized autoCompactTokenLimit on the session is cleared here rather
// than carried forward to re-collapse the buffer next turn.
function persistCompactPolicy(sessionRef, policy) {
  sessionRef.contextWindow = policy.contextWindow || sessionRef.contextWindow;
  sessionRef.rawContextWindow = policy.rawContextWindow || sessionRef.rawContextWindow;
  sessionRef.compactBoundaryTokens = policy.boundaryTokens || sessionRef.compactBoundaryTokens || null;
  const boundary = positiveInt(sessionRef.compactBoundaryTokens);
  const prevLimit = positiveInt(sessionRef.autoCompactTokenLimit);
  const keepPrev = prevLimit && (!boundary || prevLimit < boundary) ? prevLimit : null;
  sessionRef.autoCompactTokenLimit = policy.autoCompactTokenLimit || keepPrev || null;
  if (policy.effectiveContextWindowPercent !== null) {
    sessionRef.effectiveContextWindowPercent = policy.effectiveContextWindowPercent;
  }
}

export function rememberCompactTelemetry(sessionRef, policy, meta = {}) {
  if (!sessionRef || !policy) return;
  const prev = sessionRef.compaction && typeof sessionRef.compaction === 'object' ? { ...sessionRef.compaction } : {};
  for (const key of COMPACTION_TRANSIENT_KEYS) delete prev[key];
  sessionRef.compaction = compactionTelemetryRecord(sessionRef, policy, meta, prev);
  sessionRef.compaction.recentChecks = recentCompactChecks(sessionRef, policy, meta, prev);
  if (meta.compactChanged === true) {
    const changedAt = Date.now();
    sessionRef.compaction.lastChangedAt = changedAt;
    sessionRef.compaction.lastCompactAt = changedAt;
    invalidateProviderContextBaseline(sessionRef);
  }
  persistCompactPolicy(sessionRef, policy);
}

export function emitCompactEvent(opts, event = {}) {
  if (!opts || typeof opts.onCompactEvent !== 'function') return;
  try {
    opts.onCompactEvent({ ts: Date.now(), ...event });
  } catch {
    /* best-effort UI/log hook */
  }
}

// Handoff-summary model override. NO automatic downshift: the runtime cannot
// know which models a given account/gateway can actually serve (an OAuth plan
// or relay may not expose Haiku at all), so guessing a cheaper model risks a
// hard compact failure. The summary runs on the session's own model unless an
// operator explicitly configures compaction.summaryModel.
export function resolveHandoffSummaryModel(sessionRef) {
  const cfg = sessionRef?.compaction && typeof sessionRef.compaction === 'object' ? sessionRef.compaction : {};
  const explicit =
    String(cfg.summaryModel || '').trim() || String(process.env.MIXDOG_AGENT_COMPACT_SUMMARY_MODEL || '').trim();
  if (explicit) return explicit;
  return null;
}
