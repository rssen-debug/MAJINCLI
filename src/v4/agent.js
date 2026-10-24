/**
 * MAJIN V4 — the turn engine.
 *
 * One user message becomes one durable V2 Goal:
 *
 *   REQUESTED(=CREATED) -> PLANNING -> READY -> RUNNING
 *        -> [WAITING_FOR_TOOL -> RUNNING]*
 *        -> WAITING_FOR_APPROVAL?  (strict policy)
 *        -> VERIFYING -> COMPLETED
 *
 * Every tool call is a receipt. A workspace write is only called done after
 * the V2 file verifier re-read the file from disk and matched its SHA-256.
 * The model's own words are never the evidence.
 */
import crypto from 'node:crypto';
import fs from 'node:fs';
import path from 'node:path';
import { Approvals } from '../v2/safety/approvals.js';
import { Goal } from '../v2/runtime/goal.js';
import { STATES } from '../v2/runtime/states.js';
import { runVerifier } from '../v2/runtime/verifiers.js';
import { runTool } from '../v2/tools/runner.js';
import { nextRecoveryStep, recoveryPlan } from '../v2/recover/advisor.js';
import { buildMessages } from './context.js';
import { memoryForPrompt } from './memory.js';
import { renderSkills } from './skills.js';
import { renderLearned } from './learning.js';
import { TOOL_SCHEMAS, safeFileName, schemasFromRegistry } from './tools.js';
import { createToolExposure } from './tool-exposure.js';
import { createTeamTools } from './teams.js';
import { createGraphTool } from './graph.js';
import { runInTurn, turnState, hostSessionId } from './turn-state.js';
import { closeFor } from '../core/browser.js';
import { z } from 'zod';
import { publicGoal, newId } from './store.js';
import { explainModelError } from './model.js';
import { t } from './ui/strings.js';
import { hasApprovalContinuation } from './approval-continuation.js';

const SYSTEM_PROMPT = `You are MAJIN, a private assistant running on the owner's own Windows machine.
You speak in the language the user writes in (Swedish or English) and you are brief.
You have tools. The exact list is in this request; use whatever is offered. Always the
workspace tools: workspace_write (create a NEW text file), workspace_read, workspace_list,
memory_save (durable preference) and memory_search. The workspace is a flat, create-only
sandbox. When host tools are enabled you also get real filesystem, shell and Windows control
tools; they run on the owner's machine and sensitive ones require the owner's approval.

Choosing tools:
- Prefer the narrowest tool that answers the question. workspace_list lists files; fs_read reads
  a real path on the host; exec_start runs a command.
- To find a file you only know the name of, use fs_find with the folder as its path argument.
  Do not assume the workspace is the only place the owner keeps things.
- A tool call that returns failure is a failure. Never describe it as done.
- Forms: browser_form, browser_form_fill, browser_form_submit. Observe changes,
  verify receipts; hand off authentication/CAPTCHA. Tool descriptions explain recovery.
- The tool list can be partial on a large host. If the capability you need is not listed, call
  tools_search with a plain-words description, then tools_activate with the exact names, and call
  them in the next step. Never invent a tool name and never claim a capability you cannot see.
- For a sub-problem that benefits from its own focus (analyse several files, check several
  hypotheses, gather facts for one section), call agent_delegate. It runs with its own step
  budget, sees only the tools you name, and returns a compressed factual answer. It cannot
  approve anything for you, and its tool calls are receipts on this same task.
- When the work has real dependencies or genuinely parallel parts (analyse three inputs, then
  combine), use agent_graph. Each step is a bounded subagent, steps without a dependency run in
  parallel, and a later step receives the results of the steps it depends on.
- When the owner has a standing team (roles that persist between sessions), use team_manage to
  read or change the roster and blackboard and team_run to run a goal graph against it. A team
  run is checkpointed, so it can be resumed by runId without repeating finished work.
- For work requested on a schedule or after the app closes, discover task_manage and task_list.
  Create a durable bounded task with the owner's requested schedule and success criteria.
  For monitoring a JSON source without repeated model calls, supply task_manage.condition:
  url, JSON Pointer, operator eq/lt/lte/gt/gte and a typed threshold value. Inspect the source
  first when its actual schema is unknown. A task string alone runs the model every time;
  it does not create a deterministic condition. Set notify only for authorized notifications.
  Never claim monitoring or push delivery from merely creating a task; inspect actual history.

Rules:
- Never say a file was created, saved or changed unless the tool result confirms it.
- If a tool fails, say exactly what failed and what you did NOT change.
- Ask at most one short clarifying question, and only when the request cannot be executed safely.
- Never invent file paths, URLs, prices, job listings or test results.
- Never reveal secrets, API keys or system internals.`;

/**
 * A subagent is not a second personality. It is the same model in a smaller box:
 * one task, no conversation history, a tool subset the parent names, and a hard
 * step budget. It is told to return evidence, not narration.
 */
const SUBAGENT_PROMPT = `You are a MAJIN subagent. You get one bounded task and you deliver a compressed, factual answer.
Rules:
- Use the tools you were given; they are the only ones you can call.
- Never say something was done unless a tool result confirms it.
- Return 3-12 lines: what you found, the exact values/paths, and what you could not determine.
- You cannot ask the owner questions and you cannot delegate further.`;

function createBus() {
  const handlers = new Set();
  return {
    emit(type, payload) {
      for (const fn of handlers) {
        try {
          fn(type, payload);
        } catch { /* a broken listener must not break a turn */ }
      }
    },
    on(fn) {
      handlers.add(fn);
      return () => handlers.delete(fn);
    },
  };
}

function parseArgs(json) {
  if (json == null || json === '') return {};
  if (typeof json === 'object') return json;
  try {
    const v = JSON.parse(String(json));
    return v && typeof v === 'object' && !Array.isArray(v) ? v : {};
  } catch {
    return null;
  }
}

/**
 * True when this message continues the same work rather than starting
 * something else: same artifact, an explicit correction word, or a short
 * follow-up. Deliberately conservative — a wrong "correction" would hide a
 * genuinely new task.
 */
export function looksLikeCorrection(message, priorGoal) {
  const text = String(message || '').toLowerCase();
  if (!priorGoal) return false;
  const artifacts = (priorGoal.acceptance || [])
    .map((a) => String(a.id).replace(/^artifact:/, '').toLowerCase())
    .filter(Boolean);
  const mentionsArtifact = artifacts.some((name) => name && text.includes(name));
  const correctionWord = /\b(nej|inte|rätt|ändra|istället|i stället|glöm|instead|actually|no,|rather|change|fix)\b/.test(text);
  const followUp = /\b(igen|också|too|again|also|continue|fortsätt)\b/.test(text);
  return mentionsArtifact || correctionWord || followUp;
}

function safeJson(value) {
  try {
    return JSON.stringify(value);
  } catch {
    return 'null';
  }
}

/**
 * Telemetry is optional by design: the agent works without it (tests, embedded
 * use). When present it is V2's `TelemetryLedger`, whose serializer drops any
 * field outside a fixed allowlist — message contents, paths and secrets cannot
 * reach the log even by accident.
 */
export function createAgent({
  config,
  conversations,
  goals,
  tools,
  model,
  telemetry = null,
  audit = null,
  skills = null,
  access = null,
  learning = null,
}) {
  const record = (event, payload) => {
    if (!telemetry) return;
    try {
      telemetry.append(event, payload);
    } catch(error) {
      if(error.code==='AUDIT_INTEGRITY')throw error;
      /* telemetry must never break a turn */
    }
  };
  const bus = createBus();
  const approvals = new Approvals(bus);
  if (config.approvals.policy === 'sandbox-auto') {
    // Workspace writes are create-only inside the sandbox and verified after
    // the fact, so they are auto-approved in the default policy. `strict`
    // requires a human confirmation per call.
    approvals.grant('tool:workspace_write', { user: 'owner', mode: 'session', maxUses: 1_000_000 });
    approvals.grant('tool:memory_save', { user: 'owner', mode: 'session', maxUses: 1_000_000 });
    // A team roster and blackboard live inside the same create-only workspace
    // sandbox, so they follow the same rule. Anything a member writes through a
    // host tool is still approved on its own.
    approvals.grant('tool:team_manage', { user: 'owner', mode: 'session', maxUses: 1_000_000 });
  }

  const running = new Map(); // conversationId -> AbortController
  const lastGoal = new Map(); // conversationId -> goalId (the goal the user is working on)
  // Idempotency survives a dropped connection: the same requestId returns the
  // stored turn instead of running tools twice. Bounded and ordered.
  const recentRequests = new Map();

  /**
   * Conversation history, bounded by the configured token budget instead of a
   * fixed message count. Error notices are excluded: they are UI copy, not
   * something the model should learn from.
   */
  function historyFor(conv, currentMessage = '', learned = []) {
    const all = conv.messages
      .filter((m) => (m.role === 'user' || m.role === 'assistant') && !m.meta?.error)
      .map((m) => ({ role: m.role, content: m.content }));

    // Where the tools may actually look. A grant the model is not told about is
    // a grant it never uses — the reported "MAJIN cannot find my CV".
    let accessSection = '';
    try {
      const view = access?.() || null;
      if (view) {
        const lines = [];
        if (view.workspace) lines.push(`- sandbox workspace: ${view.workspace}`);
        for (const folder of view.folders || []) lines.push(`- granted folder: ${folder}`);
        if (lines.length) {
          accessSection = [
            'Filesystem access (real paths on this machine):',
            ...lines,
            'Use fs_find to locate a file by name inside a granted folder (or fs_list / fs_grep for content), '
            + 'then fs_read or document_read with the absolute path. If a file is outside every listed folder, '
            + 'say which folder would need to be granted instead of guessing a path.',
            view.folders?.length
              ? ''
              : 'No folder is granted yet, so only the sandbox workspace is reachable. Say that plainly if the '
                + 'request needs a real file the owner did not upload.',
          ].filter(Boolean).join('\n');
        }
      }
    } catch {
      accessSection = '';
    }

    // What the owner stored, injected only when it is relevant to this turn.
    // Retrieval failure must never take a turn down, so it is guarded here.
    let memorySection = '';
    try {
      memorySection = memoryForPrompt({ memory: tools.memory, query: currentMessage }).section;
    } catch {
      memorySection = '';
    }
    // Procedures the owner installed, only the ones whose tools are actually
    // available right now. A skill the agent cannot execute is not mentioned.
    let skillSection = '';
    try {
      if (skills?.usable) skillSection = renderSkills(skills.usable(learned));
    } catch {
      skillSection = '';
    }
    // Procedures this MAJIN learned from its own verified work, ranked for THIS
    // request so a related (not identical) task finds them.
    let learnedSection = '';
    try {
      learnedSection = renderLearned(learned);
    } catch {
      learnedSection = '';
    }

    const delegationNote = tools.registry.get('agent_delegate')
      ? ''
      : 'Delegation is not granted on this host. Do the work yourself with the tools that are listed.';
    const system = [SYSTEM_PROMPT, delegationNote, accessSection, learnedSection, memorySection, skillSection]
      .filter(Boolean)
      .join('\n\n');

    return buildMessages({
      system,
      messages: all,
      budgetTokens: config.limits.maxContextTokens || 8000,
    });
  }

  /**
   * Run one tool call, and when it fails, ask V2's recovery advisor what to do.
   *
   * The advisor (`src/v2/recover/advisor.js`) is pure and proven: failure class
   * -> ordered, bounded plan. V4 executes only the steps that are safe here:
   *
   *   retry_simple / retry_backoff  — re-run identical input, but ONLY for tools
   *                                   without side effects (tier 'read'). Retrying
   *                                   a write could duplicate an effect that
   *                                   actually landed before the error surfaced.
   *   everything else               — reported, never silently attempted.
   *
   * The budget comes from the advisor, so no class can retry forever.
   */
  async function executeToolWithRecovery({ call, goal, conversationId, emit, signal = null, turn = null }) {
    const toolName = String(call.name || '');
    const def = tools.registry.get(toolName);
    const retryable = def?.tier === 'read';
    const consumed = {};
    let attempt = 0;
    let last = null;

    for (;;) {
      attempt += 1;
      const outcome = await executeToolCall({ call, goal, conversationId, emit, attempt, signal, turn });
      if (outcome.ok || outcome.waiting) return outcome;
      last = outcome;

      if (!retryable) return outcome;

      const step = nextRecoveryStep(outcome.code || 'UNKNOWN', consumed);
      if (!step || !['retry_simple', 'retry_backoff'].includes(step.step)) {
        // The advisor may still have advice (escalate, ask, replan) — but those
        // are decisions for a human, not something a tool loop may invent.
        if (outcome.code) {
          const plan = recoveryPlan(outcome.code);
          emit('recovery', {
            tool: toolName,
            failureClass: outcome.code,
            action: 'none',
            advice: plan.plan.map((p) => p.step),
            budget: plan.totalBudget,
          });
        }
        return outcome;
      }

      consumed[step.step] = (consumed[step.step] || 0) + 1;
      emit('recovery', {
        tool: toolName,
        failureClass: outcome.code || 'UNKNOWN',
        action: step.step,
        attempt: step.attempt,
      });
      if (step.step === 'retry_backoff') {
        await new Promise((r) => setTimeout(r, 50 * 2 ** (step.attempt - 1)));
      }
    }
  }

  /**
   * A per-call view of the tool registry that hands the execute function an
   * AbortSignal, and a deadline.
   *
   * V2's runner calls `def.execute(input)` with one argument and V2 is not ours
   * to change. Rather than mutating the shared definition (unsafe with two
   * turns running), this facade returns a wrapped definition for THIS call only.
   *
   * The signal fires for two reasons, and both mean "stop now":
   *   - the owner pressed stop (turn abort)
   *   - the call passed its deadline (the runner's Promise.race already rejects,
   *     so without this the tool would keep working after the goal was failed)
   *
   * A tool that ignores the signal keeps working exactly as before; one that
   * honours it stops while there is still nobody to receive a late effect.
   */
  function registryForCall(signal, timeoutMs) {
    return {
      get(name) {
        const def = tools.registry.get(name);
        if (!def) return null;
        return {
          ...def,
          execute: async (input) => {
            // One controller per call covers both stop and deadline. The timer
            // is cleared in finally so a fast tool leaves no pending handle.
            const callCtl = new AbortController();
            const onTurnAbort = () => callCtl.abort(new Error('cancelled'));
            if (signal?.aborted) callCtl.abort(new Error('cancelled'));
            else signal?.addEventListener?.('abort', onTurnAbort, { once: true });
            const deadline = Number.isFinite(timeoutMs) && timeoutMs > 0
              ? setTimeout(() => callCtl.abort(new Error('deadline exceeded')), timeoutMs)
              : null;
            try {
              return await def.execute(input, { signal: callCtl.signal });
            } finally {
              if (deadline) clearTimeout(deadline);
              signal?.removeEventListener?.('abort', onTurnAbort);
            }
          },
        };
      },
      list() {
        return tools.registry.list();
      },
    };
  }

  async function executeToolCall({ call, goal, conversationId, emit, attempt = 1, signal = null, turn = null }) {
    audit?.assertHealthy();
    // A tool called by a SUBAGENT runs while the parent's delegate call is
    // itself mid-flight (goal already WAITING_FOR_TOOL). Letting the child drive
    // the parent state machine produced "illegal transition WAITING_FOR_TOOL ->
    // WAITING_FOR_TOOL". Nested calls add receipts; only the parent call moves
    // the goal.
    const nested = (turn?.depth || 0) > 0;
    const args = parseArgs(call.argsJson);
    if (args === null) {
      return { ok: false, error: 'tool arguments were not valid JSON', code: 'INVALID_JSON', name: call.name };
    }
    const toolName = String(call.name || '');
    if (toolName === 'workspace_write' && typeof args.fileName === 'string') {
      const acceptanceId = `artifact:${args.fileName}`;
      if (!goal.acceptance.some((a) => a.id === acceptanceId)) {
        goal.acceptance.push({
          id: acceptanceId,
          description: `Create and verify ${args.fileName}`,
          coveredBy: [],
        });
      }
    }
    emit('tool_start', { id: call.id, name: toolName, input: redactInput(toolName, args) });

    /**
     * The trace entry records which tool ran with which argument NAMES — never
     * the values. That is what makes it safe to persist as a learned procedure:
     * no paths, keys, e-mail addresses or selectors can ride along.
     */
    const argsShape = Object.keys(args || {}).sort().join(',');
    const traceStep = { name: toolName, argsShape, ok: false, cls: null, verified: false, at: Date.now() };
    if (turn?.trace) turn.trace.push(traceStep);

    // A strategy this MAJIN already proved wrong must not be repeated blindly.
    // Only exact (tool + argument-Names) matches recorded from a verified run
    // are refused, and only when a relevant skill was retrieved for this turn.
    const avoided = (turn?.learned || []).flatMap((skill) => (skill.learned?.avoid || [])
      .filter((a) => a.action === `${toolName}${argsShape ? `(${argsShape})` : ''}` || a.action === toolName)
      .map((a) => ({ ...a, skill: skill.name })));
    if (avoided.length && !turn?.allowAvoided) {
      const first = avoided[0];
      traceStep.ok = false;
      traceStep.cls = 'LEARNED_AVOID';
      emit('tool_result', {
        id: call.id,
        name: toolName,
        ok: false,
        verified: false,
        summary: 'LEARNED_AVOID',
        error: `not repeated: ${first.action} failed with ${first.failedWith} in a verified run`,
      });
      emit('learning', { event: 'avoided', tool: toolName, skill: first.skill, failedWith: first.failedWith });
      record('task.result', { action: `learning:avoided:${toolName}`, taskId: first.skill, result: 'success' });
      return {
        ok: false,
        error: `This approach is recorded as failed (${first.failedWith}) for a related task in skill "${first.skill}". `
          + 'Do not repeat it: follow the procedure that worked, or choose a different tool.',
        code: 'LEARNED_AVOID',
        name: toolName,
      };
    }

    if (!nested) goal.transition(STATES.WAITING_FOR_TOOL, `tool ${toolName}`);
    let result;
    try {
      const runOnce = () => runTool(
        { tool: toolName, input: args, callId: call.id },
        {
          registry: registryForCall(signal, config.limits.toolTimeoutMs),
          approvals,
          mode: 'balanced',
          timeoutMs: config.limits.toolTimeoutMs,
          events: bus,
        },
      );
      // The turn handle lets discovery/delegation tools act on THIS turn without
      // changing the V2 `execute(input)` contract every other tool uses.
      result = turn ? await runInTurn(turn, runOnce) : await runOnce();
    } catch (err) {
      // The runner throws classified ToolErrors (unknown tool, schema mismatch,
      // timeout, executor crash). The goal must leave WAITING_FOR_TOOL, record
      // the failure and keep the turn honest — never stay mid-flight.
      const cls = err?.cls || 'UNKNOWN';
      traceStep.ok = false;
      traceStep.cls = cls;
      if (!nested) goal.transition(STATES.RUNNING, `tool ${toolName} threw ${cls}`);
      goal.addReceipt({
        action: `tool:${toolName}`,
        target: args.fileName || null,
        result: 'failure',
        errorClass: cls,
      });
      record('task.result', { action: `tool:${toolName}`, result: 'failure', errorCls: cls, attempt: attempt || 1 });
      emit('tool_result', { id: call.id, name: toolName, ok: false, verified: false, summary: cls, error: String(err?.message || err) });
      return { ok: false, error: err?.message || String(err), code: cls, name: toolName };
    }

    if (!result.ok && result.decision === 'waiting') {
      traceStep.cls = 'WAITING_FOR_APPROVAL';
      // WAITING_FOR_TOOL can only go back to RUNNING; the approval wait is
      // entered from RUNNING. Skipping the hop left the goal stuck.
      if (!nested) {
        goal.transition(STATES.RUNNING, 'tool requires consent');
        goal.transition(STATES.WAITING_FOR_APPROVAL, `consent required for ${toolName}`);
      }
      return { ok: false, waiting: true, scope: result.pendingScope, reason: result.reason, name: toolName, input: args, call };
    }

    if (!nested) goal.transition(STATES.RUNNING, `tool ${toolName} finished`);

    if (!result.ok) {
      const cls = result.error?.cls || 'TOOL_FAILURE';
      traceStep.ok = false;
      traceStep.cls = cls;
      goal.addReceipt({ action: `tool:${toolName}`, target: args.fileName || null, result: 'failure', errorClass: cls });
      emit('tool_result', { id: call.id, name: toolName, ok: false, verified: false, summary: cls });
      return { ok: false, error: result.error || 'tool failed', code: cls, name: toolName };
    }

    const data = result.data;

    // A subagent's verified file writes are the parent task's evidence too.
    // Without this the turn could report success for work that was never
    // verified on the goal the owner sees. Delegation, graphs and team runs all
    // report artifacts the same way.
    if (Array.isArray(data?.artifacts)) {
      for (const artifact of data.artifacts) {
        if (!goal.acceptance.some((a) => a.id === artifact.acceptanceId)) {
          goal.acceptance.push({
            id: artifact.acceptanceId,
            description: `Create and verify ${artifact.fileName}`,
            coveredBy: [],
          });
        }
        const lifted = goal.addReceipt({
          action: 'subagent.verify',
          target: artifact.fileName,
          result: 'success',
          evidence: { ...artifact.evidence, via: 'subagent' },
          acceptanceId: artifact.acceptanceId,
        });
        goal.verifyReceipt(lifted.id, { ...artifact.evidence, via: 'subagent' });
      }
    }

    const evidence = data?.sha256
      ? { bytes: data.bytes, sha256: data.sha256, path: data.path }
      : { summary: summarize(data) };
    const receipt = goal.addReceipt({
      action: `tool:${toolName}`,
      target: data?.fileName || args.fileName || toolName,
      result: 'success',
      evidence,
      acceptanceId: data?.fileName ? `artifact:${data.fileName}` : null,
    });

    let verified = false;
    let verification = null;
    if (toolName === 'workspace_write' && data?.path) {
      verification = await runVerifier('file', { path: data.path, minBytes: data.bytes, hash: data.sha256 });
      if (verification.verified) {
        goal.verifyReceipt(receipt.id, { ...verification.evidence, verifier: 'v2.file', expectedSha256: data.sha256 });
        verified = true;
      } else {
        goal.addReceipt({
          action: 'verification.file',
          target: data.fileName,
          result: 'failure',
          errorClass: verification.error?.cls || 'VERIFICATION_FAILURE',
          acceptanceId: `artifact:${data.fileName}`,
        });
      }
    } else if (toolName === 'workspace_read' && data?.content != null) {
      // Verify a read against the file itself: same size, same bytes.
      const target = path.join(tools.root, safeFileName(data.fileName));
      const check = await runVerifier('file', {
        path: target,
        minBytes: data.bytes,
        hash: crypto.createHash('sha256').update(Buffer.from(data.content, 'utf8')).digest('hex'),
      });
      if (check.verified) {
        goal.verifyReceipt(receipt.id, { ...check.evidence, verifier: 'v2.file', kindOfRead: true });
        verified = true;
      }
    } else if (toolName === 'workspace_list' && Array.isArray(data?.files)) {
      // Verify a listing against the directory: same names, same count.
      const actual = fs.readdirSync(tools.root, { withFileTypes: true })
        .filter((e) => e.isFile()).map((e) => e.name).sort();
      const claimed = data.files.map((f) => f.name).sort();
      if (actual.length === claimed.length && actual.every((n, i) => n === claimed[i])) {
        goal.verifyReceipt(receipt.id, { kind: 'listing', entries: actual.length, verifier: 'v4.workspace-list' });
        verified = true;
      }
    } else if (toolName === 'memory_save' && data?.saved) {
      const stored = tools.memory ? tools.memory.get('preference', data.key) : null;
      if (stored) {
        goal.verifyReceipt(receipt.id, { kind: 'memory', key: data.key, at: stored.at });
        verified = true;
      }
    } else if (!data?.path && !data?.fileName) {
      // Nothing external happened (e.g. a search): the receipt stays unverified
      // on purpose rather than being marked verified without a check.
      verified = false;
    }

    traceStep.ok = true;
    traceStep.verified = Boolean(verified);
    traceStep.cls = null;
    record('task.result', { action: `tool:${toolName}`, result: 'success', attempt: attempt || 1 });
    if (verified) record('verification', { goalId: goal.id, kind: 'file', verified: true });
    emit('tool_result', {
      id: call.id,
      name: toolName,
      ok: true,
      verified,
      summary: summarize(data),
      receiptId: receipt.id,
      ...(toolName==='browser_form_fill'?{formProgress:{verifiedFields:data?.meta?.verifiedFields||0,recoveries:data?.meta?.recoveries||0,strategies:Array.isArray(data?.meta?.strategies)?data.meta.strategies.filter(s=>['live_field','semantic_reground','native_type_retry'].includes(s)):[]}}:{}),
    });
    return { ok: true, data, verified, receiptId: receipt.id, name: toolName };
  }

  function redactInput(toolName, args) {
    if (toolName === 'workspace_write') {
      return { fileName: args.fileName, chars: typeof args.content === 'string' ? args.content.length : 0 };
    }
    return args;
  }

  function summarize(data) {
    if (!data || typeof data !== 'object') return String(data ?? '');
    if (data.status === 'created') return `${data.fileName} · ${data.bytes} byte`;
    if (Array.isArray(data.files)) return t('agent.files', { count: data.files.length });
    if (Array.isArray(data.matches)) return t('agent.matches', { count: data.matches.length });
    if (data.saved) return `sparad: ${data.key}`;
    if (typeof data.content === 'string') return `${data.fileName} · ${data.bytes} byte`;
    return t('agent.summaryDone');
  }

  /**
   * Run one turn. `emit(type, payload)` is the SSE sink. Returns a summary the
   * HTTP layer can log without leaking content.
   */
  async function runTurn({ conversationId, text, voiceTurn = false, requestId = null, signal, emit = () => {} }) {
    const conv = conversationId ? conversations.get(conversationId) : null;
    if (conversationId && !conv) throw Object.assign(new Error('conversation not found'), { status: 404 });

    const conversation = conv || conversations.create();
    const message = String(text ?? '').trim();
    if (!message) throw Object.assign(new Error('message is empty'), { status: 400 });
    if (message.length > config.limits.maxMessageChars) {
      throw Object.assign(new Error(`message exceeds ${config.limits.maxMessageChars} characters`), { status: 413 });
    }

    /**
     * A repeated requestId must never re-run tools (side effects are real), so
     * the answer is replayed from storage. But storage is bounded: after enough
     * turns the answer may have been truncated away. Sending an empty replay
     * would look like MAJIN answered nothing, so that case gets its own status.
     */
    const replayOf = (conversationIdForReplay, messageId, found) => {
      if (found) {
        emit('replay', { messageId, content: found.content, conversationId: conversationIdForReplay });
        emit('done', { status: 'replayed', conversationId: conversationIdForReplay, messageId });
        return { status: 'replayed', conversationId: conversationIdForReplay, messageId };
      }
      emit('replay', { messageId, content: '', truncated: true, conversationId: conversationIdForReplay });
      emit('done', { status: 'already_handled', conversationId: conversationIdForReplay, messageId });
      return { status: 'already_handled', conversationId: conversationIdForReplay, messageId };
    };

    const inMemory = requestId ? recentRequests.get(requestId) : null;
    if (inMemory?.messageId) {
      const conv = conversations.get(inMemory.conversationId);
      const found = conv?.messages.find((m) => m.id === inMemory.messageId);
      if (conv) return replayOf(inMemory.conversationId, inMemory.messageId, found);
    }

    const prior = conversations.getRequest(conversation.id, requestId);
    if (prior?.status === 'completed' && prior.messageId) {
      const found = conversations.get(conversation.id).messages.find((m) => m.id === prior.messageId);
      return replayOf(conversation.id, prior.messageId, found);
    }

    conversations.appendMessage(conversation.id, { role: 'user', content: message });
    emit('user', { content: message });

    // A correction is not a new task. When the previous goal in this
    // conversation is still the user's active context, the new turn is recorded
    // as a revision of it so history shows one thread instead of orphans.
    const priorGoalId = lastGoal.get(conversation.id) || null;
    const priorGoal = priorGoalId ? goals.get(priorGoalId) : null;
    const lineage = priorGoal && looksLikeCorrection(message, priorGoal)
      ? { revisionOf: priorGoal.id, revision: (priorGoal.revision || 0) + 1 }
      : null;

    const goal = goals.track(new Goal({
      objective: message.slice(0, 500),
      acceptance: [],
      risk: 'low',
      permissions: ['workspace.file:create', 'workspace.file:read', 'memory.preference:write'],
      budgets: { toolCalls: config.limits.maxToolCallsPerTurn, modelRounds: config.limits.maxModelRounds },
    }));
    goal.revisionOf = lineage?.revisionOf || null;
    goal.revision = lineage?.revision || 0;
    lastGoal.set(conversation.id, goal.id);
    record('goal.start', { goalId: goal.id, objectiveLen: message.length, risk: goal.risk });
    goal.transition(STATES.PLANNING, lineage ? `revision ${goal.revision} of ${lineage.revisionOf}` : 'turn accepted');
    goals.save(goal);
    emit('goal', publicGoal(goal));

    const turnStartedAt = Date.now();
    // Per-turn view of the registry: core + everything that fits + whatever this
    // turn activates. Two devices cannot leak tool activation into each other.
    const exposure = createToolExposure({
      registry: tools.registry,
      maxVisible: config.limits.maxVisibleTools || 64,
    });
    // Retrieval happens once per turn: the same ranked list is used for the
    // prompt and for the "do not repeat" guard, so what the model is told and
    // what it is held to cannot drift apart.
    let learnedForTurn = [];
    try {
      learnedForTurn = learning?.retrieve?.(message) || [];
    } catch {
      learnedForTurn = [];
    }
    const turn = {
      exposure,
      depth: 0,
      goal,
      conversationId: conversation.id,
      emit,
      signal,
      model,
      // The tool trace of this turn: what was attempted, in order, with the
      // argument NAMES only. It is the raw material for learning and contains
      // no values, so nothing sensitive can leak into a stored skill.
      trace: [],
      learned: learnedForTurn,
    };
    const packed = historyFor(conversations.get(conversation.id), message, learnedForTurn);
    const modelMessages = packed.messages;
    if (voiceTurn && modelMessages[0]?.role === 'system') {
      modelMessages[0].content += '\nThis is a spoken conversation. Reply in the language the user just spoke. Usually use one short natural sentence, around 20 words, unless the task needs detail. Do not recite capabilities or menus. Keep all tool and verification rules.';
    }
    if (packed.dropped > 0 || packed.truncated) {
      // Say it once in the stream; the UI shows a quiet note, not an error.
      emit('context', { dropped: packed.dropped, truncated: packed.truncated, tokens: packed.tokens });
    }

    return executeModelLoop({ conversation, goal, exposure, turn, modelMessages, signal, emit, turnStartedAt, requestId });
  }

  // The same bounded loop handles fresh turns and durable approval continuations.
  async function executeModelLoop({ conversation, goal, exposure, turn, modelMessages, signal, emit, turnStartedAt, requestId, continuation = null }) {
    let finalText = continuation?.finalText || '';
    let toolCallsUsed = continuation?.toolCallsUsed || 0;
    let rounds = continuation?.rounds || 0;
    let assistantMessageId = null;
    // A turn may not end in a confident sentence after an unrecovered tool
    // failure. The last tool outcome decides whether the answer is allowed to
    // be treated as a success.
    let lastOutcome = null;
    let lastRefusal = null;
    let finishedReasoning = false;

    try {
      if (!continuation) {
        goal.transition(STATES.READY, 'model route resolved');
        goal.transition(STATES.RUNNING, 'executing turn');
      }
      goals.save(goal);

      while (continuation || rounds < config.limits.maxModelRounds) {
        let response, toolMessages = [], startAt = 0;
        if (continuation) {
          response = continuation.response;
          toolMessages = continuation.toolMessages;
          startAt = continuation.startAt;
          continuation = null;
        } else {
          rounds += 1;
          if (signal?.aborted) throw Object.assign(new Error('cancelled'), { code: 'ABORTED' });

          emit('state', { state: 'thinking', round: rounds });
          const budgetNote = `\nExecution budget for this response: ${config.limits.maxModelRounds - rounds + 1} model responses including this one, ${config.limits.maxToolCallsPerTurn - toolCallsUsed} tool calls left. Batch independent, already-grounded actions when useful; tools execute in order. Re-observe after actions that change control identities. Correct named schema arguments before retrying. Reserve a response to verify and report the actual outcome. Never repeat an irreversible action merely because verification failed.`;
          const requestMessages = modelMessages.map((message, index) => index === 0 && message.role === 'system'
            ? { ...message, content: message.content + budgetNote } : message);
          response = await model.chat({
            messages: requestMessages,
            // Every registered tool, not a fixed list. This was the reported bug:
            // the model was only ever told about five workspace tools, so host
            // file/shell/Windows tools could not be called even when registered.
            tools: exposure.schemas(),
            signal,
            modelId: conversation.modelId || null,
            onEvent: (ev) => {
              if (signal?.aborted) return;
              if (ev.type === 'delta') emit('delta', { text: ev.text });
              else if (ev.type === 'thinking') emit('thinking', { text: ev.text });
            },
          });

          record('model.call', {
            provider: response.provider || model.info.provider,
            model: response.model || model.info.model,
            elapsedMs: response.elapsedMs || 0,
            usageInput: response.usage?.input || 0,
            usageOutput: response.usage?.output || 0,
            usageTotal: (response.usage?.input || 0) + (response.usage?.output || 0),
            result: 'ok',
          });
          if (response.text) finalText += response.text;
          if (response.refused) lastRefusal = response.refused;

          if (!response.toolCalls?.length) { finishedReasoning = true; break; }
        }
        if (toolCallsUsed + response.toolCalls.length - startAt > config.limits.maxToolCallsPerTurn) {
          throw Object.assign(new Error(`tool budget exceeded (${config.limits.maxToolCallsPerTurn})`), { code: 'TOOL_BUDGET' });
        }
        for (const [index, call] of response.toolCalls.entries()) {
          if (index < startAt) continue;
          if (signal?.aborted) throw Object.assign(new Error('cancelled'), { code: 'ABORTED' });
          toolCallsUsed += 1;
          const outcome = await executeToolWithRecovery({ call, goal, conversationId: conversation.id, emit, signal, turn });
          goals.save(goal);
          emit('goal', publicGoal(goal));

          lastOutcome = outcome;
          if (outcome.ok && (call.name === 'tools_activate' || call.name === 'tools_search' || call.name === 'agent_delegate')) {
            emit('tool_note', {
              tool: call.name,
              ...(call.name === 'tools_activate' ? { activated: outcome.data?.activated || [] } : {}),
              ...(call.name === 'agent_delegate' ? { subTools: outcome.data?.tools || [] } : {}),
            });
          }
          if (outcome.waiting) {
            conversation.pendingApproval = {
              turnId: newId('turn'),
              goalId: goal.id,
              tool: outcome.name,
              input: outcome.input,
              callId: outcome.call.id,
              scope: outcome.scope,
              reason: outcome.reason,
              requestedAt: new Date().toISOString(),
              continuation: {
                v: 1, modelMessages, response: { text: response.text || null, toolCalls: response.toolCalls },
                toolMessages, startAt: index, finalText, toolCallsUsed: toolCallsUsed - 1, rounds,
                requestId, turnStartedAt, exposed: exposure.schemas().map((schema) => schema.name),
              },
            };
            conversations.save(conversation);
            emit('approval_required', {
              scope: outcome.scope,
              tool: outcome.name,
              reason: outcome.reason,
              input: redactInput(outcome.name, outcome.input),
            });
            emit('goal', publicGoal(goal));
            emit('done', { status: 'awaiting_approval', conversationId: conversation.id, goalId: goal.id });
            return { status: 'awaiting_approval', conversationId: conversation.id, goalId: goal.id };
          }

          toolMessages.push({
            role: 'tool',
            tool_call_id: call.id,
            content: safeJson(outcome.ok ? { ok: true, data: outcome.data } : { ok: false, error: outcome.error }),
          });
        }

        modelMessages.push({ role: 'assistant', content: response.text || null, tool_calls: response.toolCalls });
        modelMessages.push(...toolMessages);
      }

      if (!finishedReasoning) throw Object.assign(new Error(`model round budget exhausted (${config.limits.maxModelRounds}); task is incomplete`), { code: 'MODEL_BUDGET' });
      if (lastRefusal && toolCallsUsed === 0) {
        throw Object.assign(new Error(lastRefusal.reason || t('common.toolFailed')), {
          code: 'REQUEST_REFUSED',
          cls: lastRefusal.code || 'INVALID_TOOL_INPUT',
        });
      }

      if (lastOutcome && !lastOutcome.ok && !lastOutcome.verified) {
        throw Object.assign(new Error(lastOutcome.error || t('common.toolFailed')), {
          code: 'TOOL_FAILED_UNRECOVERED',
          cls: lastOutcome.code || 'TOOL_FAILURE',
        });
      }

      if (!finalText.trim()) {
        finalText = t('common.done');
      }

      emit('state', { state: 'verifying' });
      const stored = conversations.appendMessage(conversation.id, {
        role: 'assistant',
        content: finalText,
        meta: {
          goalId: goal.id,
          model: model.info.label,
          demo: model.info.demo,
          requests: rounds,
          toolCalls: toolCallsUsed,
        },
      });
      assistantMessageId = stored.id;

      // Independent check that the answer really landed in durable storage.
      const reread = conversations.get(conversation.id)?.messages.find((m) => m.id === stored.id);
      if (!reread || reread.content !== finalText) {
        throw Object.assign(new Error('assistant message did not persist'), { code: 'PERSIST_FAILURE' });
      }

      goal.transition(STATES.VERIFYING, 'checking acceptance and receipts');
      const receipt = goal.addReceipt({
        action: 'chat.reply',
        target: stored.id,
        result: 'success',
        evidence: { messageId: stored.id, chars: finalText.length, model: model.info.model },
        acceptanceId: null,
      });
      goal.verifyReceipt(receipt.id, { kind: 'persistence', messageId: stored.id, bytes: Buffer.byteLength(finalText) });

      const uncovered = goal.uncoveredAcceptance();
      if (uncovered.length) throw Object.assign(new Error(`missing evidence for: ${uncovered.map((u) => u.id).join(', ')}`), { code: 'EVIDENCE_MISSING' });

      goal.complete();
      goals.save(goal);

      /**
       * EXTRACT SKILL → STORE.
       *
       * Runs only after this turn reached COMPLETED with an independently
       * verified receipt, so a model's own claim can never become a skill. The
       * store decides the state; a failure here must never fail a turn that
       * already succeeded.
       */
      let learned = null;
      try {
        learned = learning?.observe?.({
          goal,
          trace: turn.trace || [],
          // The goal carries the objective; the transcript is not needed to
          // learn a procedure, and not copying it keeps the store free of text.
          conversationId: conversation.id,
        }) || null;
        if (learned) emit('learning', { event: 'observed', ...learned });
      } catch (err) {
        learned = { action: 'error', reason: String(err?.message || err) };
        record('learning.error', { message: String(err?.message || err).slice(0, 120) });
      }

      conversations.rememberRequest(conversation.id, requestId, {
        status: 'completed',
        messageId: stored.id,
        goalId: goal.id,
      });
      if (requestId) {
        recentRequests.set(requestId, {
          conversationId: conversation.id,
          messageId: stored.id,
          goalId: goal.id,
          at: Date.now(),
        });
        if (recentRequests.size > 200) recentRequests.delete(recentRequests.keys().next().value);
      }

      record('goal.finish', {
        goalId: goal.id,
        finalState: goal.state,
        durationMs: Date.now() - turnStartedAt,
        receipts: goal.receipts.length,
        verifiedReceipts: goal.receipts.filter((r) => r.verified).length,
        acceptanceCount: goal.acceptance.length,
      });
      emit('goal', publicGoal(goal));
      emit('done', {
        status: 'completed',
        conversationId: conversation.id,
        messageId: stored.id,
        goalId: goal.id,
        demo: model.info.demo,
        ...(learned?.learning ? { learned: { action: learned.action, name: learned.name, state: learned.state } } : {}),
      });
      return {
        status: 'completed',
        conversationId: conversation.id,
        messageId: stored.id,
        goalId: goal.id,
        ...(learned?.learning ? { learned } : {}),
      };
    } catch (err) {
      const aborted = err?.code === 'ABORTED' || err?.name === 'AbortError' || signal?.aborted;
      const reason = aborted ? 'cancelled by the user' : explainModelError(err);

      if (![STATES.FAILED, STATES.CANCELLED, STATES.COMPLETED].includes(goal.state)) {
        try {
          goal.transition(aborted ? STATES.CANCELLED : STATES.FAILED, reason.slice(0, 200));
          goals.save(goal);
        } catch {
          /* keep the stored state if the hop is not legal */
        }
      }

      /**
       * LEARN FROM THE FAILURE.
       *
       * A failed turn used to leave no trace in the skill store, so a procedure
       * that a changed website broke kept looking healthy. The failure is now
       * attributed to the step that failed and recorded; a step that keeps
       * failing marks the skill STALE rather than silently deleting it.
       */
      let failedLearning = null;
      try {
        const retrieved = turn?.learned || [];
        if (!aborted && retrieved.length && typeof learning?.observeFailure === 'function') {
          failedLearning = learning.observeFailure({
            skills: retrieved,
            trace: turn?.trace || [],
          });
          emit('learning', { event: 'failure-observed', skills: failedLearning });
        }
      } catch (err) {
        record('task.result', { action: 'learning:failure-error', result: 'failure', errorCls: 'UNKNOWN', taskId: String(err?.message || err).slice(0, 60) });
      }

      const note = aborted
        ? t('msg.cancelled')
        : t('agent.failed', { reason });
      const stored = conversations.appendMessage(conversation.id, {
        role: 'assistant',
        content: note,
        meta: { error: true, goalId: goal.id },
      });
      record('goal.finish', {
        goalId: goal.id,
        finalState: goal.state,
        durationMs: Date.now() - turnStartedAt,
        receipts: goal.receipts.length,
        verifiedReceipts: goal.receipts.filter((r) => r.verified).length,
        acceptanceCount: goal.acceptance.length,
      });
      emit('goal', publicGoal(goal));
      emit(aborted ? 'cancelled' : 'error', { message: reason, messageId: stored.id, goalId: goal.id });
      emit('done', { status: aborted ? 'cancelled' : 'failed', conversationId: conversation.id, goalId: goal.id });
      return { status: aborted ? 'cancelled' : 'failed', conversationId: conversation.id, goalId: goal.id };
    } finally {
      // Keep the page while consent is pending. Completed/cancelled headless
      // tasks return their browser slot; owner-visible windows remain open.
      if (goal.state !== STATES.WAITING_FOR_APPROVAL) {
        await closeFor(hostSessionId('v4', turn), { wait: true, headlessOnly: true });
      }
    }
  }

  /** One telemetry row per finished goal, from any path that finishes one. */
  function recordGoalFinish(goal, startedAt) {
    record('goal.finish', {
      goalId: goal.id,
      finalState: goal.state,
      durationMs: Math.max(0, Date.now() - (startedAt || Date.now())),
      receipts: goal.receipts.length,
      verifiedReceipts: goal.receipts.filter((r) => r.verified).length,
      acceptanceCount: goal.acceptance.length,
    });
  }

  /**
   * Resume a goal that the host marked BLOCKED (crash, restart, or a failed
   * verification). The resume is evidence-driven: every acceptance item that
   * can be re-checked is re-checked against reality. If all of them pass, the
   * goal completes. If not, it stays BLOCKED with the reason — a resume never
   * turns into a silent success.
   */
  async function resumeGoal({ goalId, conversationId = null, emit = () => {} }) {
    const goal = goals.get(goalId);
    if (!goal) throw Object.assign(new Error('goal not found'), { status: 404 });
    if (![STATES.BLOCKED, STATES.RECOVERING].includes(goal.state)) {
      throw Object.assign(new Error(`goal is ${goal.state}, only BLOCKED goals can be resumed`), { status: 409 });
    }

    const startedAt = Date.now();
    goal.transition(STATES.RUNNING, 'owner requested resume');
    goals.save(goal);
    emit('goal', publicGoal(goal));

    const results = [];
    for (const item of goal.acceptance) {
      const name = String(item.id).startsWith('artifact:') ? item.id.slice('artifact:'.length) : null;
      if (!name) {
        results.push({ id: item.id, verified: false, reason: 'no independent verifier for this item' });
        continue;
      }
      let fileName;
      try {
        fileName = safeFileName(name);
      } catch (err) {
        results.push({ id: item.id, verified: false, reason: err.message });
        continue;
      }
      const target = path.join(tools.root, fileName);
      if (!fs.existsSync(target)) {
        results.push({ id: item.id, verified: false, reason: 'artifact is missing on disk' });
        continue;
      }
      // Compare against the hash recorded when the work was done. Hashing the
      // file and comparing it with itself would always pass and prove nothing.
      const recorded = [...goal.receipts]
        .reverse()
        .find((r) => r.verified && r.acceptanceId === item.id && r.evidence?.sha256);
      const expectedSha = recorded?.evidence?.sha256 || null;
      const expectedBytes = Number(recorded?.evidence?.bytes ?? 0);
      if (!expectedSha) {
        results.push({ id: item.id, verified: false, reason: 'no recorded hash to compare against' });
        continue;
      }
      const verification = await runVerifier('file', { path: target, minBytes: expectedBytes, hash: expectedSha });
      if (!verification.verified) {
        results.push({ id: item.id, verified: false, reason: verification.error?.message || 'verification failed' });
        continue;
      }
      // Receipts are legal in RUNNING, so the goal stays in one state while
      // every acceptance item is re-checked. Only the final hop is VERIFYING.
      const receipt = goal.addReceipt({
        action: 'resume.verify',
        target: fileName,
        result: 'success',
        evidence: { ...verification.evidence, verifier: 'v2.file', resumed: true },
        acceptanceId: item.id,
      });
      goal.verifyReceipt(receipt.id, { ...verification.evidence, verifier: 'v2.file', resumed: true });
      results.push({ id: item.id, verified: true, sha256: expectedSha });
    }
    goals.save(goal);

    /**
     * A resume changes the world: the goal may complete. Leaving that only in a
     * toast means the user reopens the conversation and sees the old state with
     * no record of what happened. Write it down.
     */
    const writeMessage = (text, { error = false } = {}) => {
      if (!conversationId) return null;
      try {
        return conversations.appendMessage(conversationId, {
          role: 'assistant',
          content: text,
          meta: { goalId, resumed: true, ...(error ? { error: true } : {}) },
        });
      } catch {
        return null;
      }
    };

    const missing = goal.uncoveredAcceptance();
    // Old receipts are history, not proof that the world still looks the same.
    // A resume only succeeds when EVERY acceptance item was re-verified in this
    // pass, even if a previous run had already marked it covered.
    const allFresh = results.length > 0 && results.every((r) => r.verified);
    if (missing.length === 0 && allFresh) {
      goal.transition(STATES.VERIFYING, 'all acceptance items re-verified after resume');
      goal.complete();
      goals.save(goal);
      writeMessage(t('goal.resumed'));
      recordGoalFinish(goal, startedAt);
      emit('goal', publicGoal(goal));
      return { status: 'completed', goal: publicGoal(goal), results };
    }

    const failed = results.filter((r) => !r.verified).map((r) => r.id);
    // "missing" answers one question: what is not verified right now?
    const notVerified = [...new Set([...missing.map((m) => m.id), ...failed])];
    goal.transition(STATES.BLOCKED, `resume could not verify: ${notVerified.join(', ')}`.slice(0, 180));
    goals.save(goal);
    writeMessage(t('goal.stillBlocked', { items: notVerified.join(', ') || '?' }), { error: true });
    recordGoalFinish(goal, startedAt);
    emit('goal', publicGoal(goal));
    return { status: 'blocked', goal: publicGoal(goal), results, missing: notVerified };
  }

  /** Resolve a pending strict-policy approval for a conversation. */
  async function resolveApproval({ conversationId, approve, emit = () => {}, owner = null }) {
    const key = `conv:${conversationId}`;
    if (running.has(key)) throw Object.assign(new Error('conversation is already running'), { status: 409 });
    const goalId = conversations.get(conversationId)?.pendingApproval?.goalId;
    const controller = beginTurn(key, { owner });
    try { return await continueApproval({ conversationId, approve, emit, signal: controller.signal }); }
    finally {
      endTurn(key, controller);
      const goal = goalId ? goals.get(goalId) : null;
      if (goal && goal.state !== STATES.WAITING_FOR_APPROVAL) await closeFor(hostSessionId('v4', { goal }), { wait: true, headlessOnly: true });
    }
  }

  async function continueApproval({ conversationId, approve, emit, signal }) {
    const conversation = conversations.get(conversationId);
    if (!conversation) throw Object.assign(new Error('conversation not found'), { status: 404 });
    const pending = conversation.pendingApproval;
    if (!pending) throw Object.assign(new Error('no pending approval'), { status: 409 });
    const goal = goals.get(pending.goalId);
    if (!goal || goal.state !== STATES.WAITING_FOR_APPROVAL) throw Object.assign(new Error('approval goal is not waiting'), { status: 409 });
    if (approve && !hasApprovalContinuation(pending)) throw Object.assign(new Error('approval checkpoint is invalid or unavailable; no action was executed'), { status: 409 });
    audit?.assertHealthy();
    audit?.consent({conversationId,tool:pending.tool,approved:approve});

    conversation.pendingApproval = null;
    conversations.save(conversation);
    emit('approval_resolved', { approve: Boolean(approve), tool: pending.tool });

    if (!approve) {
      if (goal && goal.state === STATES.WAITING_FOR_APPROVAL) {
        goal.transition(STATES.CANCELLED, 'approval denied by the owner');
        goals.save(goal);
      }
      const stored = conversations.appendMessage(conversation.id, {
        role: 'assistant',
        content: t('agent.denied'),
        meta: { error: true, goalId: pending.goalId },
      });
      emit('goal', publicGoal(goal));
      emit('done', { status: 'denied', conversationId, messageId: stored.id });
      return { status: 'denied', conversationId };
    }

    approvals.grant(pending.scope, { user: 'owner', mode: 'once', maxUses: 1 });
    if (goal && goal.state === STATES.WAITING_FOR_APPROVAL) {
      goal.transition(STATES.RUNNING, 'approval granted by the owner');
    }

    emit('state', { state: 'working' });
    const saved = pending.continuation;
    const exposure = createToolExposure({ registry: tools.registry, maxVisible: config.limits.maxVisibleTools || 64 });
    exposure.activate(saved.exposed || []);
    const turn = { exposure, depth: 0, goal, conversationId, emit, signal, model };
    return executeModelLoop({ conversation, goal, exposure, turn, modelMessages: saved.modelMessages, signal, emit,
      turnStartedAt: saved.turnStartedAt, requestId: saved.requestId, continuation: saved });
  }

  /**
   * Run one bounded sub-task with its own context and a filtered tool set.
   *
   * Everything it does goes through the SAME approval policy and the same
   * runner, so delegation adds focus, never authority. Receipts live on the
   * subagent's own goal: the parent goal is in WAITING_FOR_TOOL while this call
   * runs, and V2 does not accept receipts there. Verified file artifacts are
   * lifted onto the parent when the call returns. A subagent cannot delegate
   * again, and a tool that needs the owner's consent stops it instead of
   * self-approving.
   */
  async function runSubtask({
    task,
    tools: wanted = null,
    maxRounds = 3,
    maxCalls = 6,
    turn,
    instructions = '',
    digest = '',
    countsAgainstCap = true,
  }) {
    const allowed = Array.isArray(wanted)
      ? new Set(wanted.map((n) => {
        const raw = String(n);
        return raw.includes('.') ? raw.toLowerCase().replace(/[^a-z0-9_]/g, '_') : raw;
      }))
      : null;
    const subRegistry = {
      get(name) {
        if (name === 'agent_delegate') return null;
        if (allowed && !allowed.has(name)) return null;
        return tools.registry.get(name);
      },
      list() {
        return tools.registry.list().filter((t) => t.name !== 'agent_delegate' && (!allowed || allowed.has(t.name)));
      },
    };
    const subExposure = createToolExposure({ registry: subRegistry, maxVisible: 24 });
    // The subagent gets its OWN goal object. Its receipts, acceptance items and
    // file verifications are real, but they must not drive the parent's state
    // machine while the parent is inside the delegate tool call (the goal is in
    // WAITING_FOR_TOOL, where V2 does not allow actions). Verified artifacts are
    // lifted back onto the parent after the call returns.
    const subGoal = new Goal({
      objective: `subagent: ${String(task).slice(0, 400)}`,
      acceptance: [],
      risk: 'low',
      permissions: [],
      budgets: {},
    });
    subGoal.transition(STATES.PLANNING, 'subagent accepted');
    subGoal.transition(STATES.READY, 'subagent ready');
    subGoal.transition(STATES.RUNNING, 'subagent started');
    const subTurn = { ...turn, depth: (turn?.depth || 0) + 1, exposure: subExposure, goal: subGoal };
    // A team member is not a generic subagent: it has a standing role and a
    // shared blackboard. Both come from V1's TeamStore, injected here as prompt
    // text so the worker stays the same bounded loop.
    const sections = [SUBAGENT_PROMPT];
    if (instructions) sections.push(`Your standing role:\n${String(instructions).slice(0, 2000)}`);
    if (digest) sections.push(`Shared team blackboard (facts other members recorded):\n${String(digest).slice(0, 900)}`);
    const messages = [
      { role: 'system', content: sections.join('\n\n') },
      { role: 'user', content: String(task).slice(0, 4000) },
    ];
    const used = [];
    let text = '';
    let calls = 0;
    let failure = null;
    let usedRounds = 0;
    let finished = false;
    const rounds = Math.max(1, Math.min(5, Number(maxRounds) || 3));
    for (let round = 1; round <= rounds; round += 1) {
      if (turn?.signal?.aborted) throw Object.assign(new Error('cancelled'), { code: 'ABORTED' });
      const res = await model.chat({
        messages,
        tools: subExposure.schemas(),
        signal: turn?.signal,
        modelId: null,
        onEvent: () => {},
      });
      usedRounds = round;
      if (res.text) text += res.text;
      if (!res.toolCalls?.length) { finished = true; break; }
      const toolMessages = [];
      for (const call of res.toolCalls) {
        if (calls >= Math.max(1, Math.min(6, Number(maxCalls) || 6))) {
          failure = 'subagent tool budget exhausted';
          break;
        }
        calls += 1;
        const outcome = await executeToolWithRecovery({
          call,
          goal: subGoal,
          conversationId: turn.conversationId,
          emit: turn.emit,
          signal: turn.signal,
          turn: subTurn,
        });
        used.push(call.name);
        if (outcome.waiting) {
          failure = `subagent tool ${call.name} needs the owner's approval`;
          break;
        }
        toolMessages.push({
          role: 'tool',
          tool_call_id: call.id,
          content: safeJson(outcome.ok ? { ok: true, data: outcome.data } : { ok: false, error: outcome.error }),
        });
        if (!outcome.ok) failure = String(outcome.error || 'subagent tool failed');
      }
      messages.push({ role: 'assistant', content: res.text || null, tool_calls: res.toolCalls });
      messages.push(...toolMessages);
      if (failure) break;
    }
    if (!finished && !failure) failure = `subagent model round budget exhausted (${rounds}); task is incomplete`;
    const artifacts = subGoal.receipts
      .filter((r) => r.verified && r.acceptanceId && r.evidence)
      .map((r) => ({
        fileName: String(r.acceptanceId).replace(/^artifact:/, ''),
        acceptanceId: r.acceptanceId,
        evidence: r.evidence,
      }));
    return { answer: text.trim(), tools: [...new Set(used)], calls, rounds: usedRounds, failure, artifacts };
  }

  /**
   * Standing teams and dependency graphs.
   *
   * Both are built ON the reused V1/V2 engines and executed by `runSubtask`, so
   * they inherit the parent turn's approval policy, cancellation and receipts.
   * They are registered only when the owner grants the `agent` lane (see the
   * server's refreshHostTools), exactly like delegation.
   */
  const teamTools = createTeamTools({
    workspaceDir: config.workspaceDir,
    runSubtask,
  });
  const graphTool = createGraphTool({ runSubtask });
  const orchestrationTools = [...teamTools, graphTool];
  const ownsOrchestrationTool = (name) => orchestrationTools.some((t) => t.name === name);
  for (const tool of orchestrationTools) {
    if (!tools.registry.get(tool.name)) tools.registry.define(tool);
  }

  /**
   * The delegation tool. Registered by the server only when the owner has
   * granted the `agent` lane; the definition lives here because it needs this
   * agent's model, registry and turn context.
   */
  const delegationTool = {
    name: 'agent_delegate',
    description:
      'Send one bounded sub-task to a subagent with its own step budget and its own context. '
      + 'It sees only the tools you name (empty = all except delegation) and returns a compressed '
      + 'factual answer. Use it to analyse several files, check several hypotheses, or gather facts '
      + 'for one section without filling this conversation. It cannot approve anything for you.',
    tier: 'read',
    inputSchema: z.object({
      task: z.string().min(3).max(4000),
      tools: z.array(z.string().min(1).max(80)).max(20).optional(),
      maxRounds: z.number().int().min(1).max(5).optional(),
    }),
    outputSchema: z.object({
      answer: z.string(),
      tools: z.array(z.string()),
      calls: z.number(),
      rounds: z.number(),
      warning: z.string().optional(),
      artifacts: z.array(z.object({
        fileName: z.string(),
        acceptanceId: z.string(),
        evidence: z.unknown(),
      })).optional(),
    }),
    execute: async ({ task, tools: wanted = null, maxRounds = 3 }) => {
      const st = turnState();
      if (!st) throw Object.assign(new Error('agent_delegate can only run inside a turn'), { cls: 'INVALID_TOOL_INPUT' });
      if ((st.depth || 0) >= 1) throw Object.assign(new Error('a subagent cannot delegate further'), { cls: 'PERMISSION_DENIED' });
      // Each delegate call is one parent tool call, so without this a model
      // could fan out to dozens of subagents inside a six-call budget. A graph
      // or team run is ONE parent call and manages its own budget instead.
      st.subagents = (st.subagents || 0) + 1;
      if (st.subagents > 2) {
        throw Object.assign(new Error('at most two subagents per turn'), { cls: 'TOOL_BUDGET' });
      }
      const out = await runSubtask({ task, tools: wanted, maxRounds, turn: st, countsAgainstCap: false });
      if (!out.answer && out.failure) {
        throw Object.assign(new Error(out.failure), { cls: 'TOOL_FAILURE' });
      }
      return {
        answer: out.answer || t('common.done'),
        tools: out.tools,
        calls: out.calls,
        rounds: out.rounds,
        ...(out.failure ? { warning: out.failure } : {}),
        ...(out.artifacts.length ? { artifacts: out.artifacts } : {}),
      };
    },
  };
  if (!tools.registry.get('agent_delegate')) tools.registry.define(delegationTool);

  function beginTurn(key, { owner = null } = {}) {
    const controller = new AbortController();
    if (key) {
      running.get(key)?.controller?.abort();
      running.set(key, { controller, owner });
    }
    return controller;
  }

  function endTurn(key, controller) {
    const entry = running.get(key);
    if (key && entry?.controller === controller) running.delete(key);
  }

  function cancel(key) {
    const entry = running.get(key);
    if (!entry) return false;
    entry.controller.abort();
    return true;
  }

  /**
   * Stop every turn a revoked session started.
   *
   * Logging out used to leave the turn running to completion: the revoked
   * device could not see the result (its cookie is dead), but the work it asked
   * for still landed. If an owner revokes a stolen phone, that pending work
   * should stop too.
   */
  function cancelOwnedBy(owner) {
    if (!owner) return 0;
    let stopped = 0;
    for (const [, entry] of running) {
      if (entry.owner === owner) {
        entry.controller.abort();
        stopped += 1;
      }
    }
    return stopped;
  }

  /** Change the model for one conversation only (never the global route). */
  function setConversationModel({ conversationId, modelId }) {
    const conv = conversations.get(conversationId);
    if (!conv) throw Object.assign(new Error('conversation not found'), { status: 404 });
    conv.modelId = modelId || null;
    conversations.save(conv);
    return { conversationId, modelId: conv.modelId, info: model.infoFor(conv.modelId) };
  }

  return {
    approvals,
    bus,
    delegationTool,
    orchestrationTools,
    ownsOrchestrationTool,
    setConversationModel,
    resumeGoal,
    runTurn,
    resolveApproval,
    beginTurn,
    endTurn,
    cancel,
    cancelOwnedBy,
    isRunning: (id) => running.has(id),
    get modelInfo() { return model.info; },
  };
}
