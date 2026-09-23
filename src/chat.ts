import { Hooks } from './hooks.ts';
import { Metrics } from './metrics.ts';
import { parseToolCalls, salvageToolCall, stripCallFragments, stripThinking, type ToolCall } from './toolcalls.ts';
import { resolveTransformers, detectDtype, availableDtypes, detectDevice, readLogit, type Device, type RuntimeOptions, type TransformersLike } from './runtime.ts';
import { dtypeProbe, resolveSource, type ModelSource } from './source.ts';

export type ToolHandler = (args: Record<string, unknown>) => unknown | Promise<unknown>;

export interface ToolSchema {
  type: 'function';
  function: {
    name: string;
    description: string;
    parameters: { type: 'object'; properties: Record<string, unknown>; required: string[] };
  };
}

export interface ChatMessage {
  role: 'system' | 'user' | 'assistant' | 'tool';
  content: string;
  name?: string;
}

export interface LoadOptions extends RuntimeOptions {
  /** Quantization variant. 'auto' probes which variants the source has. */
  dtype?: string | 'auto';
  /** 'auto' (default) uses WebGPU when available, else WASM/CPU. */
  device?: Device;
  onProgress?: (p: unknown) => void;
}

export interface ChatOptions {
  maxNewTokens?: number;
  /** Whether a tool call is optional or mandatory for this turn.
   *
   *  'auto' (default) — generate normally; if the model produced no tool call
   *  and tools are registered, generate ONCE more with the call syntax already
   *  started, which leaves it no way to answer except by completing a call.
   *  'required'  — start the call syntax immediately, skipping the free turn.
   *  'none'      — never force; the model answers or it doesn't. */
  toolChoice?: 'auto' | 'required' | 'none';
  /** Divides the logit of any token already generated, so the next one is less
   *  likely to be the same. Decoding is greedy, and greedy decoding on a small
   *  model has no escape from a loop: once a phrase becomes the argmax it stays
   *  the argmax forever. This is the only thing that breaks that cycle — no
   *  system prompt can, because the loop is not a comprehension failure.
   *
   *  1.1 by default: enough to break loops, mild enough that the structural
   *  tokens JSON legitimately repeats (`"`, `,`, `:`) still win their positions.
   *  Set 1 to disable. Above ~1.2 tool-call JSON starts to malform. */
  repetitionPenalty?: number;
  /** How the tool call is extracted from the model.
   *
   *  'auto' (default) — inline first, because a model trained on tool calling
   *  does it in one generation. If that produces no call, and priming the call
   *  syntax does not either, fall back to stepwise rather than give up. You do
   *  not have to know which models need this, which is the point: the library
   *  finds out per question, at no cost to models that never need it.
   *
   *  'inline' — one generation produces the whole call as JSON, and if that
   *  fails, it failed. Use this to opt out of the extra round trips.
   *
   *  'stepwise' — skip inline entirely. Ask a closed question to pick the tool,
   *  then one question per argument, and assemble the call here. The tool name
   *  is CHOSEN from your list rather than WRITTEN by the model, so a
   *  hallucinated name cannot be produced, and no step requires emitting valid
   *  JSON. Measured: Qwen2.5-0.5B at q8 emits {"name": "rain"} inline and
   *  selects correctly stepwise — and on models that already work it is no
   *  slower, because 1+N short generations beat one 256-token one. */
  strategy?: 'auto' | 'inline' | 'stepwise';
}

export interface DecisionOption {
  choice: string;
  /** The letter the model was scored on: A, B, C… */
  label: string;
  probability: number;
  logprob: number;
  logit: number;
}

export interface Decision {
  /** The most probable option — always one of the choices passed in. */
  choice: string;
  probability: number;
  /** Every option, in the order it was given. */
  options: DecisionOption[];
  ms: number;
  inputTokens: number;
}

/** Verdict from {@link NexusChat.selfCheck}. */
export interface ToolCallCheck {
  /** Called a tool AND answered from its result. The only value worth gating on. */
  ok: boolean;
  called: boolean;
  grounded: boolean;
  /** True when the model only called because the library primed the syntax —
   *  it works, but it is closer to the edge than a model that volunteers. */
  needed_forcing: boolean;
  model: string;
  device: string;
  dtype: string;
  answer: string;
  /** One sentence you can show a user verbatim. */
  detail: string;
}

type ChatEvents = {
  token: [string];
  toolCall: [ToolCall, unknown];
  round: [number];
  answer: [string];
  metric: [string, number];
  /** The prompt as the model actually received it, per round. The single most
   *  useful thing to see when a model won't call a tool — it shows whether the
   *  schemas and tool results really made it into the template. */
  prompt: [string, number];
  /** Raw generation before parsing, per round, with what was parsed out of it.
   *  "The model answered instead of calling" and "the model called but we
   *  failed to parse it" look identical from the outside without this. */
  raw: [string, ToolCall[], number];
  /** A forced attempt: the primed generation, what was salvaged from it (null
   *  if nothing trustworthy), and the round. Without this a discarded forced
   *  turn is invisible — you see "no tool call" and cannot tell whether the
   *  model refused, named something unregistered, or emitted unparseable text. */
  forced: [string, ToolCall | null, number];
  /** One stepwise question: which step ('select' | 'arg:<name>'), the model's
   *  raw reply, what it resolved to, and the round. Stepwise is many small
   *  generations, so without this a wrong argument is invisible — you see a
   *  bad call and cannot tell which question produced it. */
  step: [string, string, string | null, number];
};

/** Tool-calling chat over a converted browser model.
 *
 *   const chat = await NexusChat.load('Qwen/Qwen3-0.6B');
 *   chat.tool('get_weather', 'Current weather', { city: 'string' }, getWeather);
 *   chat.on('token', t => render(t));
 *   const answer = await chat.chat('Weather in Chennai?');
 */
export class NexusChat extends Hooks<ChatEvents> {
  readonly metrics = new Metrics();
  maxRounds = 4;
  /** Steers the model *toward* calling a tool, before any results exist.
   *
   *  Small models follow a worked example far better than an instruction, so
   *  this shows the exact bytes expected rather than describing them. Measured
   *  on Qwen2.5-0.5B: the earlier prose-only prompt left q8 calling 0/3. */
  systemPrompt =
    'You have access to tools. You MUST call a tool instead of guessing, ' +
    'calculating, or inventing data — even if you think you know the answer.\n' +
    'To call a tool, reply with ONLY this, and nothing else:\n' +
    '<tool_call>\n{"name": "the_tool_name", "arguments": {"arg": "value"}}\n</tool_call>\n' +
    'Do not explain what you are about to do. Do not describe the tool. ' +
    'Emit the tool call itself.';

  /** How a forced tool call is started. The parser accepts this tag from any
   *  model family, so priming it works even where the model was trained on a
   *  different call syntax. */
  toolCallPrefix = '<tool_call>\n{"name": "';
  /** Replaces `systemPrompt` once tool results are in the conversation.
   *
   *  These have to be two different instructions. "You MUST call the tool
   *  instead of guessing" is what makes a small model emit a call in round one
   *  — and the same sentence, still in context in round two, reads as *the
   *  tool has not been called yet*, so the model apologises for a failure that
   *  never happened instead of reading the result sitting right above it.
   *  Measured on Qwen2.5-0.5B: the call-phase prompt answers "there was an
   *  error while fetching the weather information" with a perfectly good
   *  tool_response in context; this one reports the value. */
  answerPrompt =
    'You have received tool results. Report them to the user in a sentence. Never invent data.';
  messages: ChatMessage[] = [];

  private tools = new Map<string, { schema: ToolSchema; handler: ToolHandler }>();

  private constructor(
    private generator: any,
    readonly dtype: string,
    readonly device: string,
    private tjs: TransformersLike,
    readonly modelId: string,
  ) {
    super();
  }

  /**
   * Load a chat model. The source is always explicit — this library never
   * guesses a host or a path convention:
   *
   *   NexusChat.load({ hub: 'onnx-community/Qwen3-0.6B-ONNX' })   // Hugging Face
   *   NexusChat.load({ base: '/models/', id: 'Qwen/Qwen3-0.6B' }) // your server
   *   NexusChat.load({ archive: fileFromInput })                  // a portable zip
   *   NexusChat.load({ archive: 'https://host/model.zip' })
   */
  static async load(source: ModelSource, opts: LoadOptions = {}): Promise<NexusChat> {
    const tjs = await resolveTransformers(opts);
    const modelId = await resolveSource(tjs, source);
    const device = await detectDevice(opts.device ?? 'auto');
    const dtype =
      !opts.dtype || opts.dtype === 'auto'
        ? await detectDtype(tjs, modelId, device, dtypeProbe(source, tjs))
        : opts.dtype;
    const t0 = Date.now();
    const generator = await tjs.pipeline('text-generation', modelId, {
      dtype,
      device,
      progress_callback: opts.onProgress,
    });
    const chat = new NexusChat(generator, dtype, device, tjs, modelId);
    chat.metrics.time('load', Date.now() - t0);
    return chat;
  }

  /** Load a model that provably calls tools — or fail loudly saying nothing did.
   *
   *  `load()` picks the first dtype the host *serves*, which is a statement
   *  about the host and not about whether anything works. This asks the only
   *  question that matters: it loads a candidate, runs {@link selfCheck} against
   *  a throwaway tool returning an unguessable token, and keeps the first one
   *  that both calls the tool and answers from its result. A candidate that
   *  fails is disposed before the next is tried, so only one model is resident.
   *
   *      const chat = await NexusChat.loadForTools({ hub: 'onnx-community/Qwen3-0.6B-ONNX' });
   *
   *  Pass an explicit `dtype` and that is the only candidate — this still tells
   *  you whether it works, it just will not go looking for another. Every
   *  attempt is reported through `onAttempt` so a UI can narrate the retry
   *  rather than appear to hang on a second download.
   *
   *  Cost is the honest tradeoff: a rejected candidate was still downloaded.
   *  Weights are cached, so it is paid once per dtype per browser. */
  static async loadForTools(
    source: ModelSource,
    opts: LoadOptions & {
      /** Called after each candidate is judged, pass or fail. */
      onAttempt?: (check: ToolCallCheck) => void;
      /** Accept a model that only calls when the syntax is primed. Default true —
       *  forcing is a supported path, not a defect. Set false to demand a model
       *  that volunteers the call unaided. */
      allowForcing?: boolean;
    } = {},
  ): Promise<NexusChat> {
    const tjs = await resolveTransformers(opts);
    const modelId = await resolveSource(tjs, source);
    const device = await detectDevice(opts.device ?? 'auto');
    const candidates =
      opts.dtype && opts.dtype !== 'auto'
        ? [opts.dtype]
        : await availableDtypes(tjs, modelId, device, dtypeProbe(source, tjs));

    const tried: ToolCallCheck[] = [];
    for (const dtype of candidates) {
      let chat: NexusChat;
      try {
        chat = await NexusChat.load(source, { ...opts, dtype, transformers: tjs });
      } catch (err) {
        // A dtype the host serves can still fail to run — fp16 on some
        // runtimes throws inside the session rather than 404ing. That is a
        // failed candidate, not a failed load.
        tried.push({
          ok: false, called: false, grounded: false, needed_forcing: false,
          model: modelId, device, dtype, answer: '',
          detail: `${modelId} (${device}/${dtype}) failed to load: ${(err as Error).message}`,
        });
        opts.onAttempt?.(tried[tried.length - 1]!);
        continue;
      }
      const check = await chat.selfCheck();
      tried.push(check);
      opts.onAttempt?.(check);
      if (check.ok && (opts.allowForcing !== false || !check.needed_forcing)) {
        chat.metrics.count('dtypes_rejected', tried.length - 1);
        return chat;
      }
      await chat.dispose();
    }

    // Suggesting the model that just failed reads as a bug, so only name it
    // when it is not the one in hand.
    const KNOWN_GOOD = 'onnx-community/Qwen3-0.6B-ONNX';
    throw new Error(
      `no dtype of ${modelId} could call a tool on ${device}. Tried:\n` +
        tried.map((t) => `  ${t.dtype}: ${t.detail}`).join('\n') +
        (modelId.includes(KNOWN_GOOD)
          ? ''
          : `\nModels below ~0.5B generally cannot pick a tool name from a list; try ${KNOWN_GOOD}.`),
    );
  }

  /** Register a tool. Properties accept shorthand: { city: 'string' }. */
  tool(
    name: string,
    description: string,
    properties: Record<string, string | Record<string, unknown>>,
    handler: ToolHandler,
    opts: { required?: string[] } = {},
  ): this {
    const props = Object.fromEntries(
      Object.entries(properties).map(([k, v]) => [k, typeof v === 'string' ? { type: v } : v]),
    );
    this.tools.set(name, {
      schema: {
        type: 'function',
        function: {
          name,
          description,
          parameters: { type: 'object', properties: props, required: opts.required ?? Object.keys(props) },
        },
      },
      handler,
    });
    return this;
  }

  get toolSchemas(): ToolSchema[] {
    return [...this.tools.values()].map((t) => t.schema);
  }

  /** Load a tools file by URL and register everything it defines.
   *
   *      await chat.loadTools('./tools.js');
   *
   *  The whole point of keeping tools in one plain `.js` file is that it stays
   *  a file — editable, diffable, servable, swappable at runtime without a
   *  rebuild. Fetching it and passing the text to {@link evalTools} is three
   *  lines every caller was going to write identically, including the error
   *  handling nobody writes: a 404 on a tools file otherwise arrives as
   *  "tool is not defined" from inside eval, which points at the wrong thing.
   *
   *  The file is NOT an ES module — it is a body that calls `tool(...)`, so it
   *  needs no export and no build step. Pass `fetch` to route it through your
   *  own loader (auth headers, a bundler's ?raw import, a test double). */
  async loadTools(url: string | URL, opts: { fetch?: typeof fetch } = {}): Promise<string[]> {
    const href = String(url);
    const get = opts.fetch ?? globalThis.fetch;
    if (typeof get !== 'function') throw new Error('no fetch available — pass { fetch }');
    let res: Response;
    try {
      res = await get(href);
    } catch (e) {
      throw new Error(`could not fetch tools file ${href}: ${(e as Error).message}`);
    }
    if (!res.ok) throw new Error(`could not fetch tools file ${href}: HTTP ${res.status}`);
    const code = await res.text();
    // A missing file often comes back as an HTML 404 page with a 200, and
    // eval'ing HTML fails somewhere unrecognisable. Say what actually happened.
    if (/^\s*<(!doctype|html)/i.test(code)) {
      throw new Error(`${href} returned HTML, not JavaScript — check the path`);
    }
    return this.evalTools(code);
  }

  /** Evaluate user-written JS that defines tools via `tool(...)` — the
   *  decorator pattern as a function. Replaces existing tools. */
  async evalTools(code: string): Promise<string[]> {
    this.tools.clear();
    const register = (
      name: string,
      description: string,
      properties: Record<string, string | Record<string, unknown>>,
      handler: ToolHandler,
    ) => this.tool(name, description, properties, handler);
    const fn = new Function('tool', `'use strict';\nreturn (async () => {\n${code}\n})();`);
    await fn(register);
    return [...this.tools.keys()];
  }

  private async generate(opts: ChatOptions, round = 0, prefix = '', withTools = true): Promise<string> {
    const tok = this.generator.tokenizer;
    // Once results are in, swap the call-phase instruction for the answer-phase
    // one. Only our own injected system message is touched — a system message
    // the caller wrote themselves is left exactly as they wrote it.
    const answering = this.hasResultsThisTurn();
    const messages = answering
      ? this.messages.map((m) =>
          m.role === 'system' && m.content === this.systemPrompt ? { ...m, content: this.answerPrompt } : m,
        )
      : this.messages;
    // A prefix is appended AFTER the generation prompt, so the model resumes
    // mid-token-stream with the call syntax already open. There is no valid
    // continuation that is prose — that is what makes the call happen rather
    // than merely being requested.
    const prompt: string =
      tok.apply_chat_template(messages, {
        tools: withTools && this.tools.size ? this.toolSchemas : undefined,
        tokenize: false,
        add_generation_prompt: true,
        enable_thinking: false,
      }) + prefix;
    this.emit('prompt', prompt, round);
    let tokens = 0;
    const streamer = this.tjs.TextStreamer
      ? new this.tjs.TextStreamer(tok, {
          skip_prompt: true,
          callback_function: (t: string) => {
            tokens++;
            this.emit('token', t);
          },
        })
      : undefined;
    const out: any = await this.metrics.measure('generate', () =>
      this.generator(prompt, {
        max_new_tokens: opts.maxNewTokens ?? 256,
        do_sample: false,
        repetition_penalty: opts.repetitionPenalty ?? 1.1,
        return_full_text: false,
        streamer,
      }),
    );
    this.metrics.count('tokens_out', tokens);
    // The prefix was our text, not the model's, but the parser has to see the
    // whole call — so stitch it back on.
    return prefix + (out[0].generated_text as string);
  }

  /** Ask a one-off closed question in the conversation's context, without
   *  putting it in the history. Short cap: every stepwise question has a
   *  one-token-ish answer, and a long budget only gives room to ramble. */
  private async probe(
    question: string,
    maxNewTokens: number,
    opts: ChatOptions,
    prefix = '',
  ): Promise<string> {
    const messages = [...this.messages, { role: 'user' as const, content: question }];
    const prompt: string =
      this.generator.tokenizer.apply_chat_template(messages, {
        tokenize: false,
        add_generation_prompt: true,
        enable_thinking: false,
      }) + prefix;
    const out: any = await this.metrics.measure('generate', () =>
      this.generator(prompt, {
        max_new_tokens: maxNewTokens,
        do_sample: false,
        repetition_penalty: opts.repetitionPenalty ?? 1.1,
        return_full_text: false,
      }),
    );
    return stripThinking(String(out[0].generated_text)).trim();
  }

  /** Build a tool call by asking closed questions instead of asking for JSON.
   *
   *  Two properties make this hard to get wrong. The tool name is matched
   *  against the registered list rather than parsed out of free text, so the
   *  model can pick wrong but cannot invent — and arguments are collected one
   *  at a time as bare values, so there is no JSON for it to malform. What the
   *  model is asked to do at each step is roughly "say one word". */
  private async stepwiseCall(opts: ChatOptions, round: number): Promise<ToolCall | null> {
    const names = [...this.tools.keys()];
    const menu = names
      .map((n) => `- ${n}: ${this.tools.get(n)!.schema.function.description}`)
      .join('\n');

    const pickedRaw = await this.probe(
      `Which of these tools is needed to answer my question?\n${menu}\n` +
        `Reply with exactly one tool name from the list above, or NONE. Nothing else.`,
      16,
      opts,
    );
    // Matched against the registered list — the model selects, it does not name.
    const lower = pickedRaw.toLowerCase();
    const picked =
      names.find((n) => new RegExp(`\\b${n.toLowerCase()}\\b`).test(lower)) ??
      names.find((n) => lower.includes(n.toLowerCase()));
    this.emit('step', 'select', pickedRaw, picked ?? null, round);
    if (!picked) return null;

    const params = this.tools.get(picked)!.schema.function.parameters;
    const required = params.required.length ? params.required : Object.keys(params.properties);
    const args: Record<string, unknown> = {};
    for (const key of required) {
      const spec = (params.properties as Record<string, { type?: string; description?: string }>)[key] ?? {};
      const numeric = spec.type === 'number' || spec.type === 'integer';
      // Prime the value, exactly as a forced tool call primes the syntax.
      // Asking politely for "only the value" gets "The city is Chennai." — the
      // right answer wrapped in a sentence, which then becomes the argument.
      // Opening the quote leaves the model nowhere to put the sentence.
      const prefix = numeric ? `${key} = ` : `${key} = "`;
      const raw = await this.probe(
        `To use ${picked} I need the value of "${key}"` +
          (spec.description ? ` (${spec.description})` : '') +
          `. Based on my question, what is it?`,
        24,
        opts,
        prefix,
      );
      let value: unknown;
      if (numeric) {
        const n = raw.match(/-?\d[\d,]*\.?\d*/);
        value = n ? Number(n[0].replace(/,/g, '')) : raw.split('\n')[0]!.trim();
      } else {
        // Up to the closing quote the prefix opened; fall back to the first
        // line with a leading "The <key> is" stripped off.
        const quoted = raw.match(/^([^"\n]*)"/);
        value = quoted
          ? quoted[1]!.trim()
          : raw
              .split('\n')[0]!
              .replace(new RegExp(`^\\s*(the\\s+)?${key}\\s+(is|=|:)\\s*`, 'i'), '')
              .replace(/^["'\`]|["'\`.]$/g, '')
              .trim();
      }
      if (spec.type === 'boolean') value = /^(true|yes)$/i.test(String(value));
      args[key] = value;
      this.emit('step', `arg:${key}`, raw, picked, round);
    }
    return { name: picked, arguments: args };
  }

  /** Run the handlers and put their results in the conversation.
   *
   *  Shared by both strategies on purpose: whether the call was parsed out of
   *  JSON or assembled from closed questions, everything downstream — metrics,
   *  the toolCall event, the tool message the answer phase reads — must be
   *  identical, or stepwise would be a second code path that silently drifts.
   *
   *  `assistantText` is what the model actually produced; stepwise has no such
   *  text, so it records the call it built instead of nothing, keeping the
   *  transcript readable. */
  private async dispatch(calls: ToolCall[], assistantText: string, _round: number): Promise<void> {
    this.messages.push({
      role: 'assistant',
      content: assistantText || calls.map((c) => `${c.name}(${JSON.stringify(c.arguments)})`).join(' '),
    });
    for (const call of calls) {
      this.metrics.count('tool_calls');
      let result: unknown;
      try {
        result = await this.tools.get(call.name)!.handler((call.arguments as Record<string, unknown>) ?? {});
        this.metrics.count('tool_calls_ok');
      } catch (e) {
        result = { error: String((e as Error).message ?? e) };
        this.metrics.count('tool_calls_failed');
      }
      this.emit('toolCall', call, result);
      this.messages.push({ role: 'tool', name: call.name, content: JSON.stringify(result) });
    }
  }

  /** Chat with the automatic tool loop; returns the final grounded answer. */
  async chat(userText: string, opts: ChatOptions = {}): Promise<string> {
    if (this.tools.size && !this.messages.some((m) => m.role === 'system')) {
      this.messages.unshift({ role: 'system', content: this.systemPrompt });
    }
    this.messages.push({ role: 'user', content: userText });
    this.metrics.count('chats');

    const choice = opts.toolChoice ?? 'auto';
    const answered = () => this.hasResultsThisTurn();

    for (let round = 0; round < this.maxRounds; round++) {
      this.emit('round', round);
      // 'required' skips the free turn on the first round; after results exist
      // the model must be free to answer, or the loop could never terminate.
      const forceNow = choice === 'required' && !answered();

      // Stepwise: never ask for JSON. Ask which tool, then each argument, and
      // build the call here. Only before results exist — once they are in
      // context the model is answering, not calling.
      if (opts.strategy === 'stepwise' && this.tools.size && choice !== 'none' && !answered()) {
        const built = await this.stepwiseCall(opts, round);
        if (built) {
          this.metrics.count('tool_calls_stepwise');
          await this.dispatch([built], '', round);
          continue;
        }
        this.metrics.count('tool_calls_stepwise_declined');
        // Nothing selected: fall through and let it answer normally.
      }

      let raw = await this.generate(opts, round, forceNow ? this.toolCallPrefix : '');
      let parsed = parseToolCalls(raw);
      let calls = parsed.filter((c) => this.tools.has(c.name));

      // The model declined to call anything. Asking again politely does not
      // work on small models — so generate once more with the call syntax
      // already open, leaving no continuation that isn't a call. Only before
      // any results exist: afterwards, "no call" is the correct final answer.
      if (!calls.length && choice === 'auto' && this.tools.size && !answered() && !forceNow) {
        this.metrics.count('tool_calls_forced');
        const forced = await this.generate(opts, round, this.toolCallPrefix);
        // Lenient on purpose: a primed small model routinely emits nearly-valid
        // JSON, and discarding a correctly-named call over a missing brace
        // wastes the whole forced turn.
        const salvaged = salvageToolCall(forced, [...this.tools.keys()]);
        this.emit('forced', forced, salvaged, round);
        const forcedParsed = salvaged ? [salvaged] : parseToolCalls(forced);
        const forcedCalls = forcedParsed.filter((c) => this.tools.has(c.name));
        // Keep the forced turn only if it named a real tool; a hallucinated
        // name is worse than the answer the model gave us unprompted.
        if (forcedCalls.length) {
          raw = forced;
          parsed = forcedParsed;
          calls = forcedCalls;
        } else {
          // Loud on purpose. The model was handed open call syntax and still
          // could not name a registered tool — that is a capability limit, not
          // a transient miss, and silently returning its prose hides it.
          this.metrics.count('tool_calls_force_failed');
          const named = forced.match(/"name"\s*:\s*"([^"]{1,40})"/)?.[1];
          if (named) this.emit('metric', `forced_call_named_unknown_tool:${named}`, 1);

          // Last resort before giving up on the call. Inline failed and priming
          // the syntax failed, which means the model cannot produce the FORMAT
          // — so stop asking it to. Selecting from a list and naming one value
          // at a time is a strictly easier task, and the caller should not have
          // to know in advance which models need it.
          if ((opts.strategy ?? 'auto') === 'auto') {
            const built = await this.stepwiseCall(opts, round);
            if (built) {
              this.metrics.count('tool_calls_stepwise_rescued');
              await this.dispatch([built], '', round);
              continue;
            }
          }
        }
      }

      // Emit what was parsed, not just what survived the name filter — a call
      // to a tool that isn't registered is a different problem from no call at
      // all, and both end the loop the same silent way.
      this.emit('raw', raw, parsed, round);
      if (!calls.length) {
        let answer = stripThinking(raw);
        if (answered()) {
          // Answer phase. The model still sees the tool schemas and sometimes
          // opens a call again and stops; that fragment is not an answer.
          const cleaned = stripCallFragments(answer);
          if (!cleaned) {
            // Nothing but call syntax came back. Ask once more with the tools
            // removed from the template, so prose is the only thing it can
            // produce. Observed live: the tool ran, and the user was shown the
            // literal text "<tool_call>".
            this.metrics.count('answer_retried_without_tools');
            answer = stripCallFragments(stripThinking(await this.generate(opts, round, '', false)));
          } else {
            answer = cleaned;
          }
        }
        this.messages.push({ role: 'assistant', content: answer });
        this.emit('answer', answer);
        return answer;
      }
      await this.dispatch(calls, raw, round);
    }
    const answer = `tool loop exceeded ${this.maxRounds} rounds`;
    this.messages.push({ role: 'assistant', content: answer });
    this.emit('answer', answer);
    return answer;
  }

  /** Can THIS model, as loaded, actually call a tool and answer from it?
   *
   *  The published matrix cannot cover a model someone just uploaded from a
   *  zip or served from their own host, so ask the model itself: register a
   *  throwaway tool whose result is a token nothing could guess, ask for it,
   *  and see whether the token comes back in the answer. Roughly one
   *  generation pair — cheap next to loading the weights.
   *
   *  Registered tools and conversation history are saved and restored, so this
   *  is safe to run immediately after load. Note that `token`/`toolCall`/`raw`
   *  hooks DO fire during the check; ignore them by their round if your UI
   *  cares.
   *
   *    const check = await chat.selfCheck();
   *    if (!check.ok) warn(check.detail);
   */
  async selfCheck(opts: ChatOptions = {}): Promise<ToolCallCheck> {
    const savedTools = new Map(this.tools);
    const savedMessages = this.messages;
    this.tools = new Map();
    this.messages = [];

    // Unguessable by construction: the only way into the answer is a real call.
    const TOKEN = 'QX-7731';
    let called = false;
    this.tool(
      'lookup_sensor',
      'Read the current value of a sensor by its id. Use this for any sensor question.',
      { id: 'string' },
      async ({ id }) => {
        called = true;
        return { id, reading: TOKEN };
      },
    );

    let answer = '';
    try {
      answer = await this.chat('What is the reading of sensor A9? Include the reading exactly.', opts);
    } catch (e) {
      answer = `error: ${String((e as Error).message ?? e)}`;
    }

    const forced = (this.metrics.counters.get('tool_calls_forced') ?? 0) > 0;
    const grounded = answer.includes(TOKEN);
    this.tools = savedTools;
    this.messages = savedMessages;

    const ok = called && grounded;
    const detail = ok
      ? `${this.modelId} (${this.device}/${this.dtype}) calls tools correctly` +
        (forced ? ', but only when the call syntax is forced — expect the occasional miss.' : '.')
      : called
        ? `${this.modelId} (${this.device}/${this.dtype}) calls tools but does not report the result accurately — answers may look right and be wrong.`
        : `${this.modelId} (${this.device}/${this.dtype}) does not call tools. Try another quantization, or a larger model — below ~0.5B this usually cannot be fixed.`;

    return { ok, called, grounded, needed_forcing: forced, model: this.modelId, device: this.device, dtype: this.dtype, answer, detail };
  }

  /** Instruction for {@link decide}. Short on purpose: the options are in the
   *  user message, and the answer is read from logits, never from prose. */
  decidePrompt = 'Choose one option.';

  /** Jev-style "System One" decision: one forward pass, and a probability for
   *  every option you allowed. Nothing is generated, so nothing is parsed, and
   *  the answer can only ever be one of `choices`.
   *
   *      const d = await chat.decide('Email: …', ['Legitimate', 'Spam', 'Phishing']);
   *      d.choice;       // 'Phishing'
   *      d.options;      // [{ choice, label, probability, logprob, logit }, …]
   *
   *  Options are labelled A, B, C… and scored by the logit of each label's
   *  token at the position right after the assistant turn opens. The
   *  conversation history is neither read nor changed. */
  async decide(prompt: string, choices: string[], opts: { system?: string } = {}): Promise<Decision> {
    if (choices.length < 2 || choices.length > 26) {
      throw new Error(`decide needs 2–26 choices, got ${choices.length}`);
    }
    const tok = this.generator.tokenizer;
    const labels = choices.map((_, i) => String.fromCharCode(65 + i));
    const ids = labels.map((l) => Number(tok.encode(l, { add_special_tokens: false })[0]));
    if (new Set(ids).size !== ids.length) {
      throw new Error(`decide: this tokenizer does not give labels ${labels.join(',')} distinct tokens`);
    }
    const text: string = tok.apply_chat_template(
      [
        { role: 'system', content: opts.system ?? this.decidePrompt },
        { role: 'user', content: `${prompt}\n\n${choices.map((c, i) => `${labels[i]}. ${c}`).join('\n')}` },
      ],
      { tokenize: false, add_generation_prompt: true, enable_thinking: false },
    );

    const t0 = Date.now();
    const inputs = tok(text, { add_special_tokens: false });
    const { logits } = await this.generator.model(inputs);
    const [, seq, vocab] = logits.dims as number[];
    const row = (seq! - 1) * vocab!;
    const raw = ids.map((id) => readLogit(logits, row + id));
    const ms = Date.now() - t0;
    this.metrics.time('decide', ms);
    this.metrics.count('decisions');

    const max = Math.max(...raw);
    const lse = max + Math.log(raw.reduce((s, v) => s + Math.exp(v - max), 0));
    const options = choices.map((choice, i) => ({
      choice,
      label: labels[i]!,
      logit: raw[i]!,
      logprob: raw[i]! - lse,
      probability: Math.exp(raw[i]! - lse),
    }));
    const best = options.reduce((a, b) => (b.probability > a.probability ? b : a));
    return { choice: best.choice, probability: best.probability, options, ms, inputTokens: seq! };
  }

  /** Tool results since the latest user message. Over the whole history, one
   *  tool call early in a conversation would put every later turn in answer
   *  phase, so later questions were never steered or forced to call. */
  private hasResultsThisTurn(): boolean {
    for (let i = this.messages.length - 1; i >= 0; i--) {
      const role = this.messages[i]!.role;
      if (role === 'tool') return true;
      if (role === 'user') return false;
    }
    return false;
  }

  reset(): void {
    this.messages = [];
  }

  dispose(): Promise<void> {
    return this.generator.dispose();
  }
}
