import { err, ok, type Result } from "~/lib/result";
import { z } from "zod";
import type { AiDecisionTask, AiObjectTask, AiTask } from "~/ai/task";
import type { AiCaller, AiGate } from "~/ai/gate";
import type { ModelRole } from "~/ai/roles";
import {
  AiError,
  GATED_MODEL_ID,
  isRetriable,
  type AiFailureReason,
  type AiUsage,
  type GeneratedStream,
  type TextGenerator,
} from "~/ports/ai";
import type { Decider } from "~/ports/ai-decision";
import type { AiRepository } from "~/ports/ai-repository";
import type { Clock, Ids } from "~/ports/runtime";

/**
 * RUN AN AI TASK. One method for every feature, and two for streaming.
 *
 * Everything a feature would otherwise have to remember lives here exactly once:
 *
 *   gate → resolve the purpose's chain → try candidates → meter every attempt
 *        → write health back → return a Result
 *
 * A new feature is a `defineAiTask` file and a call. It cannot forget the gate,
 * cannot skip the ledger, and cannot pin itself to a model — because none of
 * those are its job.
 *
 * Two properties hold for every task, by construction:
 *
 * **AI degrades, never blocks.** Every path returns a `Result`, never throws. A
 * missing model, a refused caller or a dead provider costs the feature and
 * nothing else (@rules/data.md: degrade decoration, never correctness).
 *
 * **Every call is metered.** One `ai_runs` row per attempt including refusals
 * and failures, because tokens are what cost money and a gap that leaves no row
 * looks exactly like a feature nobody used.
 */

export interface AiServiceDependencies {
  readonly repo: AiRepository;
  readonly generator: TextGenerator;
  /** Serves the decision purposes; the text purposes never reach it. */
  readonly decider: Decider;
  readonly clock: Clock;
  /** Names each `ai_runs` row. */
  readonly ids: Ids;
  readonly gate: AiGate;
}

/** A stream, plus the promise that settles the ledger once it drains. */
export interface AiStream {
  readonly textStream: AsyncIterable<string>;
  /** Hand this to `waitUntil` — it records the run and never rejects. */
  readonly done: Promise<void>;
}

export class AiService {
  constructor({ repo, generator, decider, clock, ids, gate }: AiServiceDependencies) {
    this.repo = repo;
    this.ids = ids;
    this.generator = generator;
    this.decider = decider;
    this.clock = clock;
    this.gate = gate;
  }

  private readonly repo: AiRepository;
  private readonly generator: TextGenerator;
  private readonly decider: Decider;
  private readonly clock: Clock;
  private readonly ids: Ids;
  private readonly gate: AiGate;

  /** Run a task to completion. */
  async run<Input>(
    task: AiTask<Input>,
    input: Input,
    caller: AiCaller,
  ): Promise<Result<string, AiFailureReason>> {
    const messages = task.buildMessages(input);

    return this.walkChain(task, caller, async (model) => {
      const result = await this.generator.generate({
        model,
        messages,
        ...(task.maxTokens === undefined ? {} : { maxTokens: task.maxTokens }),
      });

      // Whitespace is a failed answer, not an answer — and another model may
      // well produce words, so it is worth the retry.
      const text = result.text.trim();
      return text === "" ? null : { value: text, usage: result.usage };
    });
  }

  /**
   * Run a task that wants a VALUE of a known shape.
   *
   * Identical machinery to `run` — gate, chain, fallback, metering, health —
   * with one extra step: the provider's answer is validated against the task's
   * own schema before any caller sees it. A shape mismatch is treated as a
   * failed attempt, so the NEXT model gets a turn; re-asking the same model the
   * same question returns the same bad answer and bills for it twice.
   */
  async runObject<Input, Output>(
    task: AiObjectTask<Input, Output>,
    input: Input,
    caller: AiCaller,
  ): Promise<Result<Output, AiFailureReason>> {
    const messages = task.buildMessages(input);
    const schema = z.toJSONSchema(task.schema);

    return this.walkChain(task, caller, async (model) => {
      const result = await this.generator.generateObject({
        model,
        messages,
        schema,
        ...(task.maxTokens === undefined ? {} : { maxTokens: task.maxTokens }),
      });

      const parsed = task.schema.safeParse(result.value);
      return parsed.success ? { value: parsed.data, usage: result.usage } : null;
    });
  }

  /**
   * Run a task that asks a yes/no question and wants a PROBABILITY.
   *
   * The same machinery again, over the decision models of its purpose. A probability outside 0..1 is a failed
   * answer, not a number to pass on: the next model gets a turn.
   */
  async runDecision<Input>(
    task: AiDecisionTask<Input>,
    input: Input,
    caller: AiCaller,
  ): Promise<Result<number, AiFailureReason>> {
    const state = task.state(input);

    return this.walkChain(task, caller, async (model) => {
      const decided = await this.decider.decide({ model, state, question: task.question });
      const valid = decided.probability >= 0 && decided.probability <= 1;
      return valid ? { value: decided.probability, usage: decided.usage } : null;
    });
  }

  /**
   * Run a task as a stream.
   *
   * Falls forward through the chain only while OPENING. Once the first byte has
   * reached the client, swapping models would splice two different answers
   * together, so a mid-stream failure ends the stream instead.
   */
  async stream<Input>(
    task: AiTask<Input>,
    input: Input,
    caller: AiCaller,
  ): Promise<Result<AiStream, AiFailureReason>> {
    const refusal = await this.refused(task, caller);
    if (refusal) return err(refusal);

    const startedAt = this.clock.now();
    const messages = task.buildMessages(input);
    const chain = await this.repo.chainFor(task.role, this.clock.now());
    if (chain.length === 0) {
      await this.record({ task, caller, model: "(none)", reason: "no_model", startedAt });
      return err("no_model");
    }

    let opened: GeneratedStream | null = null;
    let model = "";
    let last: AiFailureReason = "provider";

    for (const candidate of chain) {
      try {
        opened = await this.generator.stream({
          model: candidate,
          messages,
          ...(task.maxTokens === undefined ? {} : { maxTokens: task.maxTokens }),
        });
        model = candidate;
        break;
      } catch (cause) {
        last = reasonOf(cause);
        await this.afterFailure({ task, caller, model: candidate, reason: last, startedAt });
        if (!isRetriable(last)) return err(last);
      }
    }

    if (!opened) return err(last);
    const stream = opened;

    return ok({
      textStream: stream.textStream,
      // Usage is only known once the stream finishes, so reading it eagerly
      // would meter every streamed call at zero.
      done: stream.usage
        .then((usage) => this.afterSuccess({ task, caller, model, usage, startedAt }))
        .catch(async (cause: unknown) => {
          await this.afterFailure({ task, caller, model, reason: reasonOf(cause), startedAt });
        }),
    });
  }

  /**
   * The machinery every non-streaming task shares:
   *
   *   gate → resolve the purpose's chain → try each model → meter every attempt → write health back
   *
   * `attempt` asks ONE model and returns its answer with its usage, or `null` for an answer that cannot be used
   * (empty, the wrong shape): that is a failed attempt, and the next model gets a turn. It throws `AiError` for a
   * provider failure.
   */
  private async walkChain<Value>(
    task: { feature: string; role: ModelRole },
    caller: AiCaller,
    attempt: (model: string) => Promise<{ value: Value; usage: AiUsage } | null>,
  ): Promise<Result<Value, AiFailureReason>> {
    const refusal = await this.refused(task, caller);
    if (refusal) return err(refusal);

    const chain = await this.repo.chainFor(task.role, this.clock.now());
    if (chain.length === 0) {
      await this.record({ task, caller, model: "(none)", reason: "no_model", startedAt: this.clock.now() });
      return err("no_model");
    }

    let last: AiFailureReason = "provider";

    for (const model of chain) {
      const startedAt = this.clock.now();

      try {
        const answered = await attempt(model);
        if (!answered) {
          last = "provider";
          await this.afterFailure({ task, caller, model, reason: last, startedAt });
          continue;
        }

        await this.afterSuccess({ task, caller, model, usage: answered.usage, startedAt });
        return ok(answered.value);
      } catch (cause) {
        last = reasonOf(cause);
        await this.afterFailure({ task, caller, model, reason: last, startedAt });
        // Nothing another model can do about it.
        if (!isRetriable(last)) return err(last);
      }
    }

    // Chain exhausted: the caller hears about the last thing that went wrong.
    return err(last);
  }

  /**
   * The gate, checked ONCE and before any model is resolved.
   *
   * Ahead of the chain deliberately: a refusal that arrives after the spend is
   * not a gate. It still leaves a ledger row, so "why did nothing happen" has
   * an answer.
   */
  private async refused(
    task: { feature: string; role: ModelRole },
    caller: AiCaller,
  ): Promise<AiFailureReason | null> {
    const reason = await this.gate.refuse({ caller, role: task.role });
    if (!reason) return null;

    await this.record({ task, caller, model: GATED_MODEL_ID, reason, startedAt: this.clock.now() });
    return reason;
  }

  private async afterSuccess(input: {
    task: { feature: string; role: ModelRole };
    caller: AiCaller;
    model: string;
    usage: AiUsage;
    startedAt: number;
  }): Promise<void> {
    await this.repo.recordRun({
      id: this.ids.uuid(),
      role: input.task.role,
      modelId: input.model,
      feature: input.task.feature,
      shop: input.caller.shop,
      status: "ok",
      reasonCode: null,
      inputTokens: input.usage.inputTokens,
      outputTokens: input.usage.outputTokens,
      latencyMs: this.clock.now() - input.startedAt,
      createdAt: this.clock.now(),
    });

    // Clears a prior failure, so one bad minute does not sideline a model for
    // the whole recovery window.
    await this.repo.markHealth({
      role: input.task.role,
      modelId: input.model,
      healthy: true,
      at: this.clock.now(),
    });
  }

  private async afterFailure(input: {
    task: { feature: string; role: ModelRole };
    caller: AiCaller;
    model: string;
    reason: AiFailureReason;
    startedAt: number;
  }): Promise<void> {
    await this.record(input);

    // Only the model is demoted, and only for a failure it can be blamed for.
    if (isRetriable(input.reason)) {
      await this.repo.markHealth({
        role: input.task.role,
        modelId: input.model,
        healthy: false,
        at: this.clock.now(),
      });
    }
  }

  private record(input: {
    task: { feature: string; role: ModelRole };
    caller: AiCaller;
    model: string;
    reason: AiFailureReason;
    startedAt: number;
  }): Promise<void> {
    return this.repo.recordRun({
      id: this.ids.uuid(),
      role: input.task.role,
      modelId: input.model,
      feature: input.task.feature,
      shop: input.caller.shop,
      status: "error",
      reasonCode: input.reason,
      inputTokens: null,
      outputTokens: null,
      latencyMs: this.clock.now() - input.startedAt,
      createdAt: this.clock.now(),
    });
  }
}

/** Anything that is not one of ours is reported as a provider failure. */
function reasonOf(cause: unknown): AiFailureReason {
  return cause instanceof AiError ? cause.reason : "provider";
}

export type { ModelRole };
