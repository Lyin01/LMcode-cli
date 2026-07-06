import {
  APIContextOverflowError,
  grandTotal as ltodGrandTotal,
  type ContentPart,
  type Message,
} from '@lmcode-cli/ltod';

import type { Agent } from '..';
import {
  ErrorCodes,
  type LmcodeErrorPayload,
  isLmcodeError,
  makeErrorPayload,
  toLmcodeErrorPayload,
} from '#/errors';
import { isAbortError, isMaxStepsExceededError } from '../../loop/errors';
import {
  createLoopEventDispatcher,
  runTurn,
  type ExecutableToolResult,
  type LoopEvent,
  type LoopRecordedEvent,
  type LoopTurnStopReason,
} from '../../loop/index';
import type { AgentEvent, TurnEndedEvent } from '../../rpc';
import { abortable, userCancellationReason } from '../../utils/abort';
import { USER_PROMPT_ORIGIN, type PromptOrigin } from '../context';
import { renderUserPromptHookBlockResult, renderUserPromptHookResult } from '../../session/hooks';
import { ToolCallDeduplicator } from './tool-dedup';
import CRITIC_SYSTEM_PROMPT from './critic-system.md';
import SPEC_CRITIC_SYSTEM_PROMPT from './spec-critic-system.md';
import VISUAL_AUDITOR_SYSTEM_PROMPT from './visual-auditor-system.md';
import { resolvePathAccessPath } from '../../tools/policies/path-access';
import { validateFileSyntaxWithScreenshots } from '../../utils/self-healing';

interface ActiveTurn {
  controller: AbortController;
  promise: Promise<TurnEndResult>;
}

interface BufferedSteer {
  readonly input: readonly ContentPart[];
  readonly origin: PromptOrigin;
}

export interface TurnEndResult {
  readonly event: TurnEndedEvent;
  readonly stopReason?: LoopTurnStopReason;
}

export const GOAL_COMPLETION_REMINDER_NAME = 'goal_completion_summary';
export const GOAL_BLOCKED_REMINDER_NAME = 'goal_blocked_reason';

const GOAL_CONTINUATION_PROMPT = [
  'Continue working toward the active goal.',
  'Keep the self-audit brief. Do not explore unrelated interpretations once the goal can be',
  'decided. If the objective is simple, already answered, impossible, unsafe, or contradictory,',
  'do not run another goal turn. Explain briefly if useful, then call UpdateGoal with `complete`',
  'or `blocked` in the same turn. Otherwise, weigh the objective and any completion criteria',
  'against the work done so far. Goal mode is iterative: do one coherent slice of work, then',
  'reassess. Call UpdateGoal with `complete` only when all required work is done, any stated',
  'validation has passed, and there is no useful next action. Do not mark complete after only',
  'producing a plan, summary, first pass, or partial result. If an external condition or required',
  'user input prevents progress, or the objective cannot be completed as stated, call UpdateGoal',
  'with `blocked`. Otherwise keep going — use the existing conversation context and your tools,',
  'and do not ask the user for input unless a real blocker prevents progress.',
].join(' ');

const GOAL_CONTINUATION_ORIGIN: PromptOrigin = {
  kind: 'system_trigger',
  name: 'goal_continuation',
};

const SPEC_CRITIC_MAX_REQUEST_CHARS = 6_000;
const SPEC_CRITIC_MAX_RESPONSE_CHARS = 4_000;
const SPEC_CRITIC_MAX_FILES = 30;
const DIRECT_ANSWER_REVIEW_MIN_LENGTH = 20;
const DIRECT_ANSWER_FIDELITY_MAX_CONTINUATIONS = 3;
const DIRECT_ANSWER_REVIEW_PATTERNS: readonly RegExp[] = [
  /可分辨|手感|能看到|看得见|可观察|可检测|可选择|能选择|可控制|提前决定/u,
  /最少|最多|保证|必然|一定|无论|至少|至多/u,
  /必须|不要|不能|不得|输出格式|严格|完整/u,
];

const DIRECT_ANSWER_OBSERVABLE_OR_CONTROL_PATTERN =
  /(?:\u53ef\u5206\u8fa8|\u624b\u611f|\u80fd\u6478\u51fa|\u53ef\u6478\u51fa|\u80fd\u770b\u5230|\u770b\u5f97\u89c1|\u53ef\u89c2\u5bdf|\u53ef\u68c0\u6d4b|\u53ef\u9009\u62e9|\u80fd\u9009\u62e9|\u53ef\u63a7\u5236|\u63d0\u524d\u51b3\u5b9a)/u;
const DIRECT_ANSWER_GUARANTEE_PATTERN =
  /(?:\u6700\u5c11|\u6700\u591a|\u4fdd\u8bc1|\u5fc5\u7136|\u4e00\u5b9a|\u65e0\u8bba|\u81f3\u5c11|\u81f3\u591a)/u;
const DIRECT_ANSWER_STRICT_REQUIREMENT_PATTERN =
  /(?:\u5fc5\u987b|\u4e0d\u8981|\u4e0d\u80fd|\u4e0d\u5f97|\u8f93\u51fa\u683c\u5f0f|\u4e25\u683c|\u5b8c\u6574|output format|strict|must not|do not)/iu;
const DIRECT_ANSWER_DRAWING_OR_SAMPLING_PATTERN =
  /(?:\u6478\u51fa|\u53d6\u51fa|\u62bd\u53d6|\u62ff\u51fa|\u7cd6\u679c|\u888b\u5b50|draw|pick|sample)/iu;
const DIRECT_ANSWER_ATTRIBUTE_DECISION_PATTERN =
  /(?:\br\b[\s\S]*\bs\b|\bs\b[\s\S]*\br\b|\u5706\u5f62[\s\S]*\u4e94\u89d2\u661f|\u4e94\u89d2\u661f[\s\S]*\u5706\u5f62|\u6309\u5f62\u72b6|\u5206\u522b\u53d6)/iu;
const ACTION_MODEL_NAME = '\u884c\u52a8\u6a21\u578b';
const ACTION_MODEL_LABEL = `${ACTION_MODEL_NAME}\uff1a`;
const DRAW_BY_ATTRIBUTE_EXAMPLE =
  '\u53d6 r \u4e2a\u5706\u5f62\u3001s \u4e2a\u4e94\u89d2\u661f\u5f62';
const DIRECT_ANSWER_REQUIREMENT_REMINDER = [
  'Requirement-fidelity reminder for this answer:',
  '- The user request contains observable/controllable conditions and a guarantee/minimum style question.',
  `- Before solving, write "${ACTION_MODEL_LABEL}..." and identify what can be controlled versus what remains random.`,
  `- For drawing/sampling problems, if an attribute can be distinguished by touch/observation, solve over separate decision counts such as "${DRAW_BY_ATTRIBUTE_EXAMPLE}"; do not collapse the whole population into one fully blind pool.`,
  '- Use variables for those decision counts, derive the guarantee conditions per observable class, then minimize the total.',
  '- If the blind-pool answer differs from the controllable-strategy answer, use the controllable strategy and briefly explain why.',
  'Do not mention this reminder itself.',
].join('\n');
const DIRECT_ANSWER_REQUIREMENT_GAP_PROMPT = [
  'Requirement-fidelity check: the answer above does not visibly account for an observable/controllable condition in the original request.',
  `Re-solve from scratch. Start with "${ACTION_MODEL_LABEL}" and separate what the user can control from what remains random.`,
  `For drawing/sampling problems, if an attribute is distinguishable by touch/observation, use separate decision counts such as "${DRAW_BY_ATTRIBUTE_EXAMPLE}" instead of one blind-pool count.`,
  'Set variables for those counts, derive the guarantee conditions per observable class, and minimize their sum.',
  'A max-unsafe-set / 28+1 style blind-pool answer is not valid when the observable attribute can be selected or controlled.',
  'Do not defend the previous blind-pool answer if the controllable-strategy model changes the result.',
].join('\n');

export class TurnFlow {
  private steerBuffer: BufferedSteer[] = [];
  private turnId = -1;
  private activeTurn: 'resuming' | ActiveTurn | null = null;
  private readonly currentStepByTurn = new Map<number, number>();
  private currentStep = 0;

  constructor(protected readonly agent: Agent) {}

  // Returns the new turnId, or null if the turn was marked as resuming.
  prompt(input: readonly ContentPart[], origin: PromptOrigin = USER_PROMPT_ORIGIN): number | null {
    this.agent.records.logRecord({
      type: 'turn.prompt',
      input,
      origin,
    });
    return this.launch(input, origin);
  }

  // Returns the new turnId, or null if the input was buffered as a steer
  // message or the turn was marked as resuming.
  steer(input: readonly ContentPart[], origin: PromptOrigin = USER_PROMPT_ORIGIN): number | null {
    this.agent.records.logRecord({
      type: 'turn.steer',
      input,
      origin,
    });
    if (this.activeTurn) {
      this.steerBuffer.push({ input, origin });
      return null;
    }
    return this.launch(input, origin);
  }

  private launch(input: readonly ContentPart[], origin: PromptOrigin): number | null {
    if (this.activeTurn) {
      this.agent.emitEvent({
        type: 'error',
        ...makeErrorPayload(
          'turn.agent_busy',
          `Cannot launch a new turn while another turn (ID ${this.turnId}) is active`,
          { details: { turnId: this.turnId } },
        ),
      });
      return null;
    }

    // Initialize dream tracker and record new session on first turn
    if (this.turnId === -1) {
      void this.agent.dreamTracker.init().then(() =>
        this.agent.dreamTracker.recordNewSession(),
      );
    }

    // Per-turn setup (usage window, `turn.started`, appending the prompt)
    // lives in `runOneTurn`, so a goal-driven run emits a clean start/end
    // pair per continuation turn rather than one mega-turn.
    const turnId = this.allocateTurnId();
    const controller = new AbortController();
    const promise = this.turnWorker(turnId, input, origin, controller.signal);
    this.activeTurn = { controller, promise };
    return turnId;
  }

  restorePrompt(): void {
    if (this.activeTurn) {
      return;
    }
    this.turnId += 1;
    this.activeTurn = 'resuming';
  }

  restoreSteer(input: readonly ContentPart[], origin: PromptOrigin): void {
    if (this.activeTurn) {
      this.steerBuffer.push({ input, origin });
      return;
    }
    this.turnId += 1;
    this.activeTurn = 'resuming';
  }

  cancel(turnId?: number, reason?: unknown): void {
    this.agent.records.logRecord({ type: 'turn.cancel', turnId });
    if (turnId !== undefined && turnId !== this.currentId) {
      return; // Ignore cancel for non-active turn
    }
    // A direct cancel (RPC / replay) is the user pressing stop. When the cancel
    // is propagated from an aborting signal (e.g. a subagent's deadline via
    // waitForCurrentTurn), carry that original reason instead so a timeout is
    // not mislabeled to the model as a deliberate user interruption.
    const cancelReason = reason ?? userCancellationReason();
    this.abortTurn(cancelReason);
    this.agent.subagentHost?.cancelAll(cancelReason);
  }

  get currentId() {
    return this.turnId;
  }

  get hasActiveTurn(): boolean {
    return this.activeTurn !== null && this.activeTurn !== 'resuming';
  }

  waitForCurrentTurn(signal?: AbortSignal | undefined): Promise<TurnEndResult> {
    const active = this.activeTurn;
    if (active === null || active === 'resuming') {
      return Promise.reject(new Error('No active turn'));
    }
    signal?.throwIfAborted();
    if (signal === undefined) return active.promise;

    const turnId = this.currentId;
    const onAbort = (): void => {
      this.agent.turn.cancel(turnId, signal.reason);
    };
    signal.addEventListener('abort', onAbort, { once: true });

    return abortable(active.promise, signal).finally(() => {
      signal.removeEventListener('abort', onAbort);
    });
  }

  private abortTurn(reason: unknown) {
    if (this.activeTurn !== 'resuming') {
      // The reason (a user cancellation by default, or the originating signal's
      // reason when propagated) travels as signal.reason so tools settling on
      // this signal can report a deliberate user interruption distinctly from a
      // timeout/system abort. linkAbortSignal forwards it to linked subagents.
      this.activeTurn?.controller.abort(reason);
    }
    this.activeTurn = null;
  }

  private flushSteerBuffer(): boolean {
    const steers = this.steerBuffer;
    if (steers.length === 0) return false;
    for (const steer of steers) {
      this.agent.context.appendUserMessage(steer.input, steer.origin);
    }
    steers.length = 0;
    return true;
  }

  finishResume(): void {
    if (this.activeTurn === 'resuming') {
      this.activeTurn = null;
    }
    this.steerBuffer.length = 0;
  }

  private async turnWorker(
    turnId: number,
    input: readonly ContentPart[],
    origin: PromptOrigin,
    signal: AbortSignal,
  ): Promise<TurnEndResult> {
    const ownsActiveTurn = (): boolean =>
      this.activeTurn !== null &&
      this.activeTurn !== 'resuming' &&
      this.activeTurn.controller.signal === signal;
    try {
      const initialGoalStatus = this.agent.goal.getGoal().goal?.status;
      if (initialGoalStatus === 'active') {
        return await this.driveGoal(turnId, input, origin, signal);
      }
      const end = await this.runOneTurn(turnId, input, origin, signal, true);
      const resumedFromPausedOrBlocked =
        initialGoalStatus === 'paused' || initialGoalStatus === 'blocked';
      const currentGoalStatus = this.agent.goal.getGoal().goal?.status;
      if (
        resumedFromPausedOrBlocked &&
        currentGoalStatus === 'active' &&
        end.event.reason !== 'cancelled' &&
        end.event.reason !== 'failed'
      ) {
        return await this.driveGoal(
          this.allocateTurnId(),
          [{ type: 'text', text: GOAL_CONTINUATION_PROMPT }],
          GOAL_CONTINUATION_ORIGIN,
          signal,
        );
      }
      return end;
    } finally {
      if (ownsActiveTurn()) {
        this.activeTurn = null;
      }
    }
  }

  /**
   * Drives an active goal as a sequence of ordinary turns. Each iteration runs
   * one full turn, then reads the goal status the model set via UpdateGoal.
   */
  private async driveGoal(
    firstTurnId: number,
    input: readonly ContentPart[],
    origin: PromptOrigin,
    signal: AbortSignal,
  ): Promise<TurnEndResult> {
    let turnId = firstTurnId;
    let turnInput = input;
    let turnOrigin = origin;
    while (true) {
      const goalBeforeTurn = this.agent.goal.getGoal().goal;
      if (goalBeforeTurn?.status === 'active' && goalBeforeTurn.budget.overBudget) {
        await this.agent.goal.markBlocked({ reason: 'A configured budget was reached' });
        const ended = await this.endGoalTurnWithoutModel(turnId, turnInput, turnOrigin);
        return { event: ended };
      }

      await this.agent.goal.incrementTurn();
      const end = await this.runOneTurn(turnId, turnInput, turnOrigin, signal, false);

      if (end.event.reason === 'cancelled') {
        await this.agent.goal.pauseOnInterrupt({ reason: 'Paused after interruption' });
        return end;
      }
      if (end.event.reason === 'failed') {
        const reason = end.event.error?.message ?? 'Turn failed';
        await this.agent.goal.pauseActiveGoal({ reason });
        return end;
      }

      const goal = this.agent.goal.getGoal().goal;
      if (goal === null || goal.status !== 'active') {
        return end;
      }
      if (goal.budget.overBudget) {
        await this.agent.goal.markBlocked({ reason: 'A configured budget was reached' });
        return end;
      }

      turnId = this.allocateTurnId();
      turnInput = [{ type: 'text', text: GOAL_CONTINUATION_PROMPT }];
      turnOrigin = GOAL_CONTINUATION_ORIGIN;
    }
  }

  private async endGoalTurnWithoutModel(
    turnId: number,
    input: readonly ContentPart[],
    origin: PromptOrigin,
  ): Promise<TurnEndedEvent> {
    this.agent.usage.beginTurn();
    this.agent.emitEvent({ type: 'turn.started', turnId, origin });
    this.agent.context.appendUserMessage(input, origin);
    const ended: TurnEndedEvent = { type: 'turn.ended', turnId, reason: 'completed' };
    this.agent.usage.endTurn();
    this.agent.emitEvent(ended);
    return ended;
  }

  private allocateTurnId(): number {
    this.turnId += 1;
    return this.turnId;
  }

  /**
   * Runs exactly one logical turn end to end: per-turn bookkeeping,
   * `turn.started`, the prompt + goal reminder, the step loop, and `turn.ended`.
   * Goal-agnostic — the driver layers goal semantics on top. Never throws;
   * abnormal ends are mapped to a `cancelled`/`failed` `turn.ended` and returned.
   */
  private async runOneTurn(
    turnId: number,
    input: readonly ContentPart[],
    origin: PromptOrigin,
    signal: AbortSignal,
    standalone: boolean,
  ): Promise<TurnEndResult> {
    this.currentStep = 0;
    this.agent.workingSet.decay(turnId);
    this.currentStepByTurn.set(turnId, 0);
    this.agent.fullCompaction.resetForTurn();
    this.agent.injection.resetForTurn();
    this.agent.usage.beginTurn();
    this.agent.emitEvent({ type: 'turn.started', turnId, origin });
    this.agent.context.appendUserMessage(input, origin);
    const requirementReminder =
      origin.kind === 'user' ? directAnswerRequirementReminder(input) : undefined;
    if (requirementReminder !== undefined) {
      this.agent.context.appendSystemReminder(requirementReminder, {
        kind: 'injection',
        variant: 'direct_answer_requirement_fidelity',
      });
    }

    let ended: TurnEndedEvent;
    let completedStopReason: LoopTurnStopReason | undefined;
    let errorEvent: AgentEvent | undefined;
    try {
      const promptHookEnded = await this.applyUserPromptHook(
        turnId,
        input,
        origin,
        signal,
      );
      if (promptHookEnded !== undefined) {
        ended = promptHookEnded;
      } else {
        const stopReason = await this.runTurn(turnId, signal, input, origin);
        completedStopReason = stopReason;
        ended = {
          type: 'turn.ended',
          turnId,
          reason: stopReason === 'aborted' ? 'cancelled' : 'completed',
        };
      }
    } catch (error) {
      if (isAbortError(error)) {
        ended = {
          type: 'turn.ended',
          turnId,
          reason: 'cancelled',
        };
      } else {
        const summary = summarizeTurnError(error, turnId);
        this.agent.sessionMemory.recordError(
          `${summary.name}: ${summary.message}`,
          this.currentStep,
        );
        void this.agent.hooks?.fireAndForgetTrigger('StopFailure', {
          matcherValue: summary.name,
          inputData: {
            errorType: summary.name,
            errorMessage: summary.message,
          },
        });
        ended = {
          type: 'turn.ended',
          turnId,
          reason: 'failed',
          error: summary,
        };
        errorEvent = { type: 'error', ...summary };
      }
    }
    // Emit the terminal turn.ended and (for a standalone turn) release the active
    // turn in the SAME synchronous frame, so the session is observably idle the
    // instant turn.ended fires. A goal drive keeps the active turn across its
    // continuation turns and releases it in `turnWorker` instead (`standalone`
    // is false for those).
    if (this.currentId === turnId) {
      this.agent.usage.endTurn();
    }
    this.agent.emitEvent(ended);
    if (standalone && this.currentId === turnId) {
      this.activeTurn = null;
    }
    if (errorEvent !== undefined) {
      this.agent.emitEvent(errorEvent);
    }
    this.currentStepByTurn.delete(turnId);
    return {
      event: ended,
      stopReason: completedStopReason,
    };
  }

  private async applyUserPromptHook(
    turnId: number,
    input: readonly ContentPart[],
    origin: PromptOrigin,
    signal: AbortSignal,
  ): Promise<TurnEndedEvent | undefined> {
    if (origin.kind !== 'user') return undefined;
    signal.throwIfAborted();
    const promptHookResults = await this.agent.hooks?.trigger('UserPromptSubmit', {
      matcherValue: input,
      signal,
      inputData: { prompt: input },
    });
    signal.throwIfAborted();
    const blockResult = renderUserPromptHookBlockResult(promptHookResults);
    if (blockResult !== undefined) {
      this.agent.context.appendMessage({
        role: 'assistant',
        content: [{ type: 'text', text: blockResult.text }],
        toolCalls: [],
        origin: { kind: 'hook_result', event: 'UserPromptSubmit', blocked: true },
      });
      this.agent.emitEvent({
        type: 'hook.result',
        turnId,
        hookEvent: blockResult.event,
        content: blockResult.message,
        blocked: true,
      });
      return {
        type: 'turn.ended',
        turnId,
        reason: 'completed',
      };
    }

    const hookResult = renderUserPromptHookResult(promptHookResults);
    if (hookResult === undefined) return undefined;

    this.agent.context.appendUserMessage([{ type: 'text', text: hookResult.text }], {
      kind: 'hook_result',
      event: 'UserPromptSubmit',
    });
    this.agent.emitEvent({
      type: 'hook.result',
      turnId,
      hookEvent: hookResult.event,
      content: hookResult.message,
    });
    return undefined;
  }

  /**
   * Runs a one-shot spec-consistency review over the finished turn on the
   * utility model. Returns the critic's list of unaddressed requirements,
   * or `undefined` when the work passes. The critic must never block a
   * turn from completing, so every failure path degrades to `undefined`.
   */
  private async runSpecCritic(
    signal: AbortSignal,
    input: readonly ContentPart[],
    mutatedPaths: ReadonlySet<string>,
  ): Promise<string | undefined> {
    const requestText = input
      .map((part) => (part.type === 'text' ? part.text : ''))
      .filter((text) => text.length > 0)
      .join('\n')
      .slice(0, SPEC_CRITIC_MAX_REQUEST_CHARS);
    if (requestText.trim().length === 0) return undefined;

    const finalText = lastAssistantText(this.agent.context.history).slice(
      0,
      SPEC_CRITIC_MAX_RESPONSE_CHARS,
    );
    const files = [...mutatedPaths].slice(0, SPEC_CRITIC_MAX_FILES).join('\n');

    try {
      const response = await this.agent.generate(
        this.agent.config.utilityProvider,
        SPEC_CRITIC_SYSTEM_PROMPT,
        [],
        [
          {
            role: 'user',
            content: [
              {
                type: 'text',
                text: [
                  '## Original user request',
                  requestText,
                  '',
                  '## Files the agent changed',
                  files.length > 0 ? files : '(none)',
                  '',
                  '## Agent final response',
                  finalText.length > 0 ? finalText : '(no final text)',
                ].join('\n'),
              },
            ],
            toolCalls: [],
          } satisfies Message,
        ],
        undefined,
        { signal },
      );
      if (response.usage !== null) {
        this.agent.usage.record(this.agent.config.model, response.usage, 'turn');
      }
      const verdict = generateResultText(response).trim();
      if (verdict.length === 0 || verdict.startsWith('SPEC_OK')) return undefined;
      const markerIndex = verdict.indexOf('SPEC_MISSING');
      if (markerIndex < 0) return undefined;
      const missing = verdict
        .slice(markerIndex + 'SPEC_MISSING'.length)
        .replace(/^[:\s]+/, '')
        .trim();
      return missing.length > 0 ? missing : undefined;
    } catch (error) {
      if (isAbortError(error)) throw error;
      this.agent.log.warn('spec critic failed; completing turn without review', { error });
      return undefined;
    }
  }

  private async runTurn(
    turnId: number,
    signal: AbortSignal,
    input: readonly ContentPart[],
    origin: PromptOrigin,
  ): Promise<LoopTurnStopReason> {
    let stopHookContinuationUsed = false;
    // Spec-consistency critic bookkeeping: paths successfully written this
    // turn, and a once-per-turn latch so a critic that keeps finding gaps
    // cannot loop the turn forever.
    let specCriticUsed = false;
    let directAnswerFidelityContinuationCount = 0;
    const specMutatedPaths = new Set<string>();
    const deduper = new ToolCallDeduplicator();
    await this.agent.mcp?.waitForInitialLoad(signal);
    while (true) {
      signal.throwIfAborted();
      const model = this.agent.config.model;
      const loopControl = this.agent.lmcodeConfig?.loopControl;
      try {
        const result = await runTurn({
          turnId: String(turnId),
          signal,
          llm: this.agent.llm,
          buildMessages: () => this.agent.context.messages,
          dispatchEvent: this.buildDispatchEvent(turnId),
          tools: this.agent.tools.loopTools,
          log: this.agent.log,
          maxSteps: loopControl?.maxStepsPerTurn,
          maxRetryAttempts: loopControl?.maxRetriesPerStep,
          hooks: {
            beforeStep: async ({ signal: stepSignal, stepNumber }) => {
              this.flushSteerBuffer();
              await this.agent.fullCompaction.beforeStep(stepSignal);

              // Only inject on the first step of each turn to preserve
              // the prefix-cache across steps within the same turn.
              // Session-memory, dream-suggestions, and injection-manager
              // content is turn-scoped and rarely changes mid-turn.
              if (stepNumber === 1) {
                // Inject session memory summary so the model retains context
                // after compaction strips detailed tool-call history.
                const sessionSummary = this.agent.sessionMemory.getSessionSummary();
                if (sessionSummary.length > 0) {
                  this.agent.context.appendSystemReminder(sessionSummary, {
                    kind: 'injection',
                    variant: 'session_memory',
                  });
                }

                // Suggest /dream on the first step when conditions are met
                if (this.agent.dreamTracker.shouldSuggest()) {
                  this.agent.context.appendSystemReminder(
                    this.agent.dreamTracker.getSuggestionMessage(),
                    { kind: 'injection', variant: 'dream_suggestion' },
                  );
                }

                await this.agent.injection.inject();
              }

              deduper.beginStep();
              return;
            },
            afterStep: async ({ usage }) => {
              this.agent.usage.record(model, usage, 'turn');
              this.agent.usage.recordLlmStep();
              await this.agent.goal.recordTokenUsage(ltodGrandTotal(usage));
              await this.agent.fullCompaction.afterStep();
              deduper.endStep();
            },
            // oxlint-disable-next-line no-loop-func -- stop hook continuation state is scoped to this turn.
            shouldContinueAfterStop: async ({ signal, stopReason }) => {
              if (this.flushSteerBuffer()) return { continue: true };
              signal.throwIfAborted();

              // Stop hooks get one continuation; otherwise a hook that always blocks would loop forever.
              if (!stopHookContinuationUsed) {
                const stopBlock = await this.agent.hooks?.triggerBlock('Stop', {
                  signal,
                  inputData: { stopHookActive: stopHookContinuationUsed },
                });
                signal.throwIfAborted();
                if (stopBlock !== undefined) {
                  stopHookContinuationUsed = true;
                  this.agent.context.appendUserMessage(
                    [{ type: 'text', text: stopBlock.reason }],
                    {
                      kind: 'system_trigger',
                      name: 'stop_hook',
                    },
                  );
                  return { continue: true };
                }
              }

              // ── Spec-consistency critic ──
              // One cheap utility-model pass when a user-driven turn that
              // changed files, or a high-constraint direct-answer request,
              // stops naturally: catch explicit requirements the final
              // response left unaddressed before declaring the turn done.
              // Latched to once per turn, main agent only — subagents are
              // reviewed by their parent.
              const directAnswerRequirementGap =
                directAnswerFidelityContinuationCount <
                  DIRECT_ANSWER_FIDELITY_MAX_CONTINUATIONS &&
                stopReason === 'end_turn' &&
                origin.kind === 'user' &&
                this.agent.type === 'main'
                  ? directAnswerRequirementFidelityGap(
                      input,
                      lastAssistantText(this.agent.context.history),
                    )
                  : undefined;
              if (directAnswerRequirementGap !== undefined) {
                directAnswerFidelityContinuationCount += 1;
                this.agent.context.appendUserMessage(
                  [{ type: 'text', text: directAnswerRequirementGap }],
                  { kind: 'system_trigger', name: 'direct_answer_requirement_fidelity' },
                );
                return { continue: true };
              }

              if (
                stopReason === 'end_turn' &&
                !specCriticUsed &&
                origin.kind === 'user' &&
                this.agent.type === 'main' &&
                this.agent.lmcodeConfig?.enableSpecCritic !== false &&
                (specMutatedPaths.size > 0 ||
                  shouldReviewDirectAnswerForRequirementFidelity(input))
              ) {
                specCriticUsed = true;
                const missing = await this.runSpecCritic(signal, input, specMutatedPaths);
                signal.throwIfAborted();
                if (missing !== undefined) {
                  this.agent.context.appendUserMessage(
                    [
                      {
                        type: 'text',
                        text:
                          'Spec-consistency check: the original request contains ' +
                          'requirements the work above has not addressed yet:\n' +
                          missing +
                          '\nAddress each item now, or state explicitly why it does not apply.',
                      },
                    ],
                    { kind: 'system_trigger', name: 'spec_critic' },
                  );
                  return { continue: true };
                }
              }
              return { continue: false };
            },
            prepareToolExecution: async (ctx) => {
              const cached = deduper.checkSameStep(
                ctx.toolCall.id,
                ctx.toolCall.name,
                ctx.args,
              );
              if (cached !== null) return { syntheticResult: cached };
              return undefined;
            },
            authorizeToolExecution: async (ctx) => {
              return this.agent.permission.beforeToolCall(ctx);
            },
            finalizeToolResult: async (ctx) => {
              // Resolve dedup BEFORE firing the PostToolUse hook so same-step
              // dups (whose ctx.result is the dedup placeholder) report the
              // original's real outcome, not an empty success.
              let finalResult = await deduper.finalizeResult(
                ctx.toolCall.id,
                ctx.toolCall.name,
                ctx.args,
                ctx.result,
              );

              // Track successful file mutations for the spec-consistency
              // critic that runs when the turn stops.
              if (
                finalResult.isError !== true &&
                (ctx.toolCall.name === 'Write' ||
                  ctx.toolCall.name === 'Edit' ||
                  ctx.toolCall.name === 'MultiEdit')
              ) {
                const argRecord = ctx.args as Record<string, unknown>;
                const pathArg = argRecord['path'] ?? argRecord['file_path'];
                if (typeof pathArg === 'string' && pathArg.length > 0) {
                  specMutatedPaths.add(pathArg);
                }
              }

              // ── Post-write self-healing validation ──
              if (
                finalResult.isError !== true &&
                this.agent.lmcodeConfig?.enableSelfHealing !== false &&
                (ctx.toolCall.name === 'Write' ||
                  ctx.toolCall.name === 'Edit' ||
                  ctx.toolCall.name === 'MultiEdit')
              ) {
                const path = pathArgFromToolArgs(ctx.args);
                if (path !== undefined) {
                  try {
                    const workspace = {
                      workspaceDir: this.agent.config.cwd,
                      additionalDirs: [],
                    };
                    const resolvedPath = resolvePathAccessPath(path, {
                      jian: this.agent.jian,
                      workspace,
                      operation: 'write',
                    });
                    const content = await this.agent.jian.readText(resolvedPath);
                    const validationRes = await validateFileSyntaxWithScreenshots(resolvedPath, content);
                    if (validationRes.error) {
                      finalResult = {
                        isError: true,
                        output: `Code validation failed. Please fix the following issue:\n${validationRes.error}`,
                      };
                    } else {
                      // 1. Run LMM Visual Auditor if screenshots are captured
                      let visualRejected = false;
                      let visualFeedback = '';
                      if (
                        validationRes.screenshots &&
                        validationRes.screenshots.length > 0 &&
                        this.agent.config.modelCapabilities.image_in
                      ) {
                        try {
                          // Label each frame by its capture time; the last one
                          // is the terminal/end state where uncleared-buffer
                          // ghosts and never-ending particle fields surface.
                          const keyTimes = validationRes.keyframeTimesMs;
                          const frameLines = validationRes.screenshots
                            .map((_, i) => {
                              const isLast = i === validationRes.screenshots!.length - 1;
                              const at =
                                keyTimes && keyTimes[i] != null
                                  ? `${(keyTimes[i] / 1000).toFixed(1)}s`
                                  : `frame ${i + 1}`;
                              return `- Screenshot ${i + 1}: ${at}${isLast ? ' — TERMINAL / end state' : ''}`;
                            })
                            .join('\n');

                          const visualSystemPrompt = VISUAL_AUDITOR_SYSTEM_PROMPT.replace(
                            '{{FRAME_LINES}}',
                            frameLines,
                          );

                          const { project: projectVisual } = await import('../context/projector');
                          const visualHistory = [...projectVisual(this.agent.context.history)];
                          const contentParts: ContentPart[] = [
                            {
                              type: 'text',
                              text: 'Here are the rendered keyframe screenshots, in order. Verify them against the user request above.',
                            },
                          ];
                          for (const base64Img of validationRes.screenshots) {
                            contentParts.push({
                              type: 'image_url',
                              imageUrl: {
                                url: `data:image/png;base64,${base64Img}`,
                              },
                            });
                          }
                          visualHistory.push({ role: 'user', content: contentParts, toolCalls: [] });

                          const visualResponse = await this.agent.rawGenerate(
                            this.agent.config.provider,
                            visualSystemPrompt,
                            [],
                            visualHistory,
                          );
                          const visualText = contentPartsText(visualResponse.message.content);

                          if (visualText.startsWith('VISUAL_REJECT:')) {
                            visualRejected = true;
                            visualFeedback = `Visual review rejected by LMM Auditor:\n${visualText.substring(14).trim()}`;
                          }
                        } catch (error) {
                          this.agent.log.warn('LMM Visual Auditor failed or timed out', {
                            error: errorMessage(error),
                          });
                        }
                      }

                      if (visualRejected) {
                        finalResult = {
                          isError: true,
                          output: visualFeedback,
                        };
                      } else {
                        // 2. Syntax and Visual passed! Now run Critic LLM review
                        const prompt = `File Path: ${resolvedPath}

Please review the current content of this file:
\`\`\`
${content}
\`\`\`

Evaluate if this file meets high-quality software engineering standards and the original requirements. Reply with APPROVE or REJECT.`;

                        const { project } = await import('../context/projector');
                        const history = [...project(this.agent.context.history)];
                        history.push({
                          role: 'user',
                          content: [{ type: 'text', text: prompt }],
                          toolCalls: [],
                        });

                        const criticResponse = await this.agent.rawGenerate(
                          this.agent.config.provider,
                          CRITIC_SYSTEM_PROMPT,
                          [],
                          history,
                        );
                        const criticText = contentPartsText(criticResponse.message.content);

                        if (criticText.startsWith('REJECT:')) {
                          finalResult = {
                            isError: true,
                            output: `Code review rejected by Critic:\n${criticText.substring(7).trim()}`,
                          };
                        }
                      }
                    }
                  } catch (error) {
                    this.agent.log.warn('Self-healing code validation skipped or failed internally', {
                      error: errorMessage(error),
                      path,
                    });
                  }
                }
              }

              const { isError, output } = finalResult;

              // Count the tool execution for session stats.
              this.agent.usage.recordToolCall(ctx.toolCall.name);

              // Record in session memory for post-compaction context injection
              this.agent.sessionMemory.recordToolExecution(
                ctx.toolCall.name,
                summarizeToolArgs(ctx.args),
                isError === true,
                ctx.stepNumber,
              );

              // Track accessed files for the working-set reminder.
              this.recordWorkingSetPaths(
                ctx.toolCall.name,
                ctx.args,
                Number(ctx.turnId),
              );

              const event = isError === true ? 'PostToolUseFailure' : 'PostToolUse';
              void this.agent.hooks?.fireAndForgetTrigger(event, {
                matcherValue: ctx.toolCall.name,
                inputData: {
                  toolName: ctx.toolCall.name,
                  toolInput: toolInputRecord(ctx.args),
                  toolCallId: ctx.toolCall.id,
                  error: isError === true ? toLmcodeErrorPayload(toolOutputText(output)) : undefined,
                  toolOutput: isError === true ? undefined : toolOutputText(output).slice(0, 2000),
                },
              });
              return finalResult;
            },
          },
        });

        return result.stopReason;
      } catch (error) {
        if (
          error instanceof APIContextOverflowError ||
          (isLmcodeError(error) && error.code === ErrorCodes.CONTEXT_OVERFLOW)
        ) {
          await this.agent.fullCompaction.handleOverflowError(signal, error);
          continue; // Retry with compacted context
        }
        if (isMaxStepsExceededError(error)) {
          this.agent.log.warn('turn hit max steps', {
            turnId,
            steps: this.currentStepByTurn.get(turnId) ?? this.currentStep,
            limit: isLmcodeError(error) ? error.details?.['maxSteps'] : undefined,
          });
        } else {
          this.agent.log.error('turn failed', { turnId, error });
        }
        throw error;
      }
    }
  }

  private recordWorkingSetPaths(toolName: string, args: unknown, turnId: number): void {
    const workingSet = this.agent.workingSet;
    if (toolName === 'Read' || toolName === 'Edit' || toolName === 'Grep' || toolName === 'Write' || toolName === 'ReadMediaFile') {
      const record = (args as { path?: string }).path;
      if (record !== undefined) workingSet.touch(record, turnId);
    }
    if (toolName === 'ReadGroup') {
      const paths = (args as { paths?: string[] }).paths;
      if (Array.isArray(paths)) {
        for (const path of paths) workingSet.touch(path, turnId);
      }
    }
  }

  private buildDispatchEvent(turnId: number) {
    return createLoopEventDispatcher({
      appendTranscriptRecord: async (event: LoopRecordedEvent) => {
        this.agent.context.appendLoopEvent(event);
      },
      emitLiveEvent: (event: LoopEvent) => {
        this.updateCurrentStepFromLoopEvent(event, turnId);
        const mapped = mapLoopEvent(event, turnId);
        if (mapped !== undefined) this.agent.emitEvent(mapped);
      },
    });
  }

  private updateCurrentStepFromLoopEvent(event: LoopEvent, turnId: number): void {
    if (event.type === 'step.begin') {
      this.beginTrackedStep(turnId, event.step);
      return;
    }
    if (event.type === 'step.retrying') {
      this.agent.usage.recordRetry();
      return;
    }
  }

  private beginTrackedStep(turnId: number, step: number): void {
    this.currentStepByTurn.set(turnId, step);
    this.currentStep = step;
  }

}

function mapLoopEvent(event: LoopEvent, turnId: number): AgentEvent | undefined {
  switch (event.type) {
    case 'step.begin':
      return {
        type: 'turn.step.started',
        turnId,
        step: event.step,
        stepId: event.uuid,
      };
    case 'step.end':
      return {
        type: 'turn.step.completed',
        turnId,
        step: event.step,
        stepId: event.uuid,
        usage: event.usage,
        finishReason: event.finishReason,
        llmFirstTokenLatencyMs: event.llmFirstTokenLatencyMs,
        llmStreamDurationMs: event.llmStreamDurationMs,
        providerFinishReason: event.providerFinishReason,
        rawFinishReason: event.rawFinishReason,
      };
    case 'step.retrying':
      return {
        type: 'turn.step.retrying',
        turnId,
        step: event.step,
        stepId: event.stepUuid,
        failedAttempt: event.failedAttempt,
        nextAttempt: event.nextAttempt,
        maxAttempts: event.maxAttempts,
        delayMs: event.delayMs,
        errorName: event.errorName,
        errorMessage: event.errorMessage,
        statusCode: event.statusCode,
      };
    case 'content.part':
      return undefined;
    case 'tool.call':
      return {
        type: 'tool.call.started',
        turnId,
        toolCallId: event.toolCallId,
        name: event.name,
        args: event.args,
        description: event.description,
        display: event.display,
      };
    case 'tool.result':
      return {
        type: 'tool.result',
        turnId,
        toolCallId: event.toolCallId,
        output: event.result.output,
        isError: event.result.isError,
      };
    case 'turn.interrupted':
      if (event.activeStep === undefined) return undefined;
      return {
        type: 'turn.step.interrupted',
        turnId,
        step: event.activeStep,
        reason: event.reason,
        message: event.message,
      };
    case 'text.delta':
      return {
        type: 'assistant.delta',
        turnId,
        delta: event.delta,
      };
    case 'thinking.delta':
      return {
        type: 'thinking.delta',
        turnId,
        delta: event.delta,
      };
    case 'tool.call.delta':
      return {
        type: 'tool.call.delta',
        turnId,
        toolCallId: event.toolCallId,
        name: event.name,
        argumentsPart: event.argumentsPart,
      };
    case 'tool.progress':
      return {
        type: 'tool.progress',
        turnId,
        toolCallId: event.toolCallId,
        update: event.update,
      };
  }
}

const LLM_NOT_SET_MESSAGE =
  'No model configured. Run `lm config` or use `/model` to set a default model.';

function summarizeTurnError(error: unknown, turnId: number): LmcodeErrorPayload {
  const payload = toLmcodeErrorPayload(error);
  const details = { ...payload.details, turnId };

  // Substitute a friendlier TUI-aware message for model-not-configured.
  // The raw "Model not set" / "Provider not set" text is not actionable;
  // this string points the user at the login flow.
  if (payload.code === 'model.not_configured') {
    return { ...payload, message: LLM_NOT_SET_MESSAGE, details };
  }

  return { ...payload, details };
}

function toolInputRecord(args: unknown): Record<string, unknown> {
  return typeof args === 'object' && args !== null && !Array.isArray(args)
    ? (args as Record<string, unknown>)
    : {};
}

function toolOutputText(output: ExecutableToolResult['output']): string {
  if (typeof output === 'string') return output;
  return output
    .filter((part): part is Extract<(typeof output)[number], { type: 'text' }> => {
      return typeof part === 'object' && part !== null && part.type === 'text';
    })
    .map((part) => part.text)
    .join('');
}



/** Extract a short human-readable summary from tool arguments. */
function summarizeToolArgs(args: unknown): string {
  if (typeof args !== 'object' || args === null) return '';
  const a = args as Record<string, unknown>;
  // Common tool arg patterns — try each in priority order
  if (typeof a['file_path'] === 'string') return a['file_path'];
  if (typeof a['path'] === 'string') return a['path'];
  if (typeof a['description'] === 'string') return truncateArg(a['description']);
  if (typeof a['subject'] === 'string') return a['subject'];
  if (typeof a['command'] === 'string') return truncateArg(a['command']);
  if (typeof a['query'] === 'string') return truncateArg(a['query']);
  if (typeof a['url'] === 'string') return a['url'];
  return '';
}

function truncateArg(s: string): string {
  return s.length > 80 ? s.slice(0, 77) + '...' : s;
}

function pathArgFromToolArgs(args: unknown): string | undefined {
  if (typeof args !== 'object' || args === null) return undefined;
  const record = args as Record<string, unknown>;
  const path = record['path'] ?? record['file_path'];
  return typeof path === 'string' && path.length > 0 ? path : undefined;
}

function contentPartsText(content: readonly ContentPart[]): string {
  return content
    .map((part) => (part.type === 'text' ? part.text : ''))
    .join('');
}

function shouldReviewDirectAnswerForRequirementFidelity(input: readonly ContentPart[]): boolean {
  const text = contentPartsText(input).trim();
  if (text.length < DIRECT_ANSWER_REVIEW_MIN_LENGTH) return false;
  return (
    hasDirectAnswerRequirementFidelityTrigger(text) ||
    DIRECT_ANSWER_STRICT_REQUIREMENT_PATTERN.test(text) ||
    DIRECT_ANSWER_REVIEW_PATTERNS.some((pattern) => pattern.test(text))
  );
}

function directAnswerRequirementReminder(
  input: readonly ContentPart[],
): string | undefined {
  const text = contentPartsText(input).trim();
  return hasDirectAnswerRequirementFidelityTrigger(text)
    ? DIRECT_ANSWER_REQUIREMENT_REMINDER
    : undefined;
}

function directAnswerRequirementFidelityGap(
  input: readonly ContentPart[],
  finalText: string,
): string | undefined {
  const requestText = contentPartsText(input).trim();
  if (!hasDirectAnswerRequirementFidelityTrigger(requestText)) return undefined;
  const answerText = finalText.trim();
  if (answerText.length === 0) return DIRECT_ANSWER_REQUIREMENT_GAP_PROMPT;
  const hasActionModel =
    answerText.includes(ACTION_MODEL_NAME) || /action model/i.test(answerText);
  if (!hasActionModel) return DIRECT_ANSWER_REQUIREMENT_GAP_PROMPT;
  if (
    DIRECT_ANSWER_DRAWING_OR_SAMPLING_PATTERN.test(requestText) &&
    !DIRECT_ANSWER_ATTRIBUTE_DECISION_PATTERN.test(answerText)
  ) {
    return DIRECT_ANSWER_REQUIREMENT_GAP_PROMPT;
  }
  return undefined;
}

function hasDirectAnswerRequirementFidelityTrigger(text: string): boolean {
  if (text.length < DIRECT_ANSWER_REVIEW_MIN_LENGTH) return false;
  return (
    DIRECT_ANSWER_OBSERVABLE_OR_CONTROL_PATTERN.test(text) &&
    DIRECT_ANSWER_GUARANTEE_PATTERN.test(text)
  );
}

function errorMessage(error: unknown): string {
  return error instanceof Error ? error.message : String(error);
}

/** Text of the most recent assistant message that has any, for the spec critic. */
function lastAssistantText(history: readonly Message[]): string {
  for (let i = history.length - 1; i >= 0; i--) {
    const message = history[i];
    if (message === undefined || message.role !== 'assistant') continue;
    const text = messageContentText(message.content);
    if (text.trim().length > 0) return text;
  }
  return '';
}

function generateResultText(result: { message: Message }): string {
  return messageContentText(result.message.content);
}

function messageContentText(content: Message['content']): string {
  if (typeof content === 'string') return content;
  return content
    .map((part) => (part.type === 'text' ? part.text : ''))
    .join('');
}
