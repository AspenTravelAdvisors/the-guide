// app/api/guide/route.ts — Base Camp "The Guide" (Claude tool-use, streaming)
//
// Next.js port of api/guide.js. The Guide runs a Claude tool-use loop: the
// model calls search_offerings, we execute it against the live Atlas data
// layer, feed the real results back, and stream the grounded reply plus map
// metadata to the client as SSE frames ({status|delta|meta|done|error}).
//
// The hand-rolled Anthropic SSE parser from the original is replaced by the
// official SDK's messages.stream() + finalMessage().
//
// Env: ANTHROPIC_API_KEY (required), CLAUDE_MODEL and GUIDE_EFFORT (optional). Atlas inventory is
//      served in-process from lib/atlas (no external atlas API base needed).

import Anthropic from "@anthropic-ai/sdk";
import { GUIDE_PROMPT } from "@/lib/guide-prompt.js";
import {
  SEARCH_OFFERINGS_TOOL,
  luxuryCruiseAdvisorIntent,
  prioritizeMentionedPlace,
  searchOfferings,
} from "@/lib/search-offerings.js";
import { SEARCH_EXPERIENCES_TOOL, searchExperiences } from "@/lib/experiences.js";
import type {
  ChatMessage,
  ExperiencesMeta,
  GuideFrame,
  GuideMeta,
  GuideToolMeta,
} from "@/lib/types";
import { corsHeaders } from "@/lib/guide-cors";
import { ADVISOR_HANDOFF } from "@/lib/types";
import { leadTool } from "@/lib/guide-meta";
import { isRateLimited, isRouteSaturated } from "@/lib/rate-limit";
import {
  addRound,
  logGuideTurn,
  newUsage,
  requestShape,
  type GuideUsage,
} from "@/lib/guide-telemetry";
import { checkDailyBudget, recordGuideSpend } from "@/lib/guide-budget";
import { classifyCaller, wouldRefuse } from "@/lib/guide-botid";
import { boundHistory, toolResultForModel, withRollingCache } from "@/lib/guide-tokens";
import { blockedResponse, isBlockedCountry } from "@/lib/blocked-countries";

export const runtime = "nodejs";
// Raised from 60 on 9 November 2026. A cross-atlas answer is several search
// rounds and then two to three thousand tokens of prose; at 60 the long ones
// were killed mid-sentence. The turn keeps its own clock inside this limit
// (TURN_DEADLINE_MS below), so nothing should ever actually reach it.
export const maxDuration = 120;

const EFFORTS = ["low", "medium", "high", "max"] as const;
type Effort = (typeof EFFORTS)[number];

// GUIDE_EFFORT, read leniently: an unknown value falls back to `low` rather
// than failing every turn on a typo in a dashboard field.
function guideEffort(raw: string | undefined): Effort | null {
  const v = (raw || "low").trim().toLowerCase();
  if (v === "none") return null;
  return (EFFORTS as readonly string[]).includes(v) ? (v as Effort) : "low";
}

// Claude Sonnet 5.5 since 23 October 2026, from Sonnet 4.6: about a third
// cheaper per token ($2/$10 per MTok against $3/$15), though its tokenizer
// counts the same text as roughly 30% more tokens. To roll back, set
// CLAUDE_MODEL=claude-sonnet-4-6 and GUIDE_EFFORT=none: that restores the model
// and the no-thinking behaviour it ran with (the larger MAX_TOKENS below is
// harmless there).
const MODEL = process.env.CLAUDE_MODEL || "claude-sonnet-5-5";
// How hard the model thinks. Sonnet 4.6 ran this route with no thinking at
// all; Sonnet 5.5 thinks adaptively unless told otherwise, and from `medium`
// up it thinks before almost every reply, which a traveler waits through before
// the first word appears. `low` skips thinking on most simple requests and is
// the recommended starting point for chat and search; raise it only if replies
// measurably need it. "none" sends no effort field at all, for a model that
// rejects it (Haiku 4.5) or to restore Sonnet 4.6's old default.
const EFFORT = guideEffort(process.env.GUIDE_EFFORT);
// A full answer now carries a scene-setting open, a fit read, three to five
// products with real dates, a cross-channel aside, hand-off framing and the
// trailing [[BRIEF]] tag — and a cross-atlas reply carries that per pillar. At
// 1500 the tail was the part that got cut, and the tail is where the brief
// lives: stripControlTags hides an unterminated "[[", so a truncated reply lost
// the advisor brief silently. Headroom is cheaper than a lost lead.
//
// 2400 was set for Sonnet 4.6. Sonnet 5.5 counts the same reply as ~30% more
// tokens, and any thinking it does counts against this cap too, so the same
// answer needs more room. This is a ceiling, not a spend: unused tokens cost
// nothing.
const MAX_TOKENS = 4096;
// A cross-atlas "ways to visit X" answer is instructed to call search_offerings
// once per pillar (hotel, cruise, jet, worldcruise, train). Batched into one
// assistant turn that is a single round, but the model routinely serialises
// them, and at 4 the loop ran out of budget mid-sweep and returned no final
// text at all. 6 covers the five-category sweep plus a refining call.
const MAX_TOOL_ROUNDS = 6;
// A function that reaches maxDuration is killed with no chance to say anything:
// the traveler's stream just stops, and the rounds already paid for never reach
// the day's ledger. So the turn keeps its own clock, inside that limit. At
// TURN_DEADLINE_MS it aborts the round in flight; in the last stretch before
// that it will not open another one, since a round started then cannot finish.
// Either way the turn ends with a sentence, a `done` or `error` frame, and its
// spend recorded. Keep the deadline comfortably under maxDuration above.
const TURN_DEADLINE_MS = Number(process.env.GUIDE_TURN_DEADLINE_MS) || 105_000;
const ROUND_CUTOFF_MS = TURN_DEADLINE_MS - 20_000;
// Claude occasionally returns a transient overloaded_error (HTTP 529) or a
// 429 / 5xx, especially at peak. Those are not real failures — Anthropic asks
// callers to back off and retry — so we do, rather than dumping the raw error
// JSON into the chat (which is what travelers were seeing).
const MAX_MODEL_ATTEMPTS = Number(process.env.GUIDE_MODEL_ATTEMPTS) || 4;
// Requests per minute across ALL callers. The per-IP limit cannot see a flood
// spread over a proxy pool — on 19 September 1,359 requests arrived in two
// hours from twenty-odd countries without one IP reaching 10/min — so the route
// carries its own ceiling. Blunt by design: see lib/rate-limit.ts.
//
// This shipped at 30 and that was too high to do anything. The flood it was
// written for ran at 11-14/min, so the cap sat above the attack and would never
// have fired. A ceiling is only worth the number on it: against a measured
// baseline of ~25 turns a DAY, 10/min still allows 14,400 a day — roughly 500x
// normal traffic — while sitting below any flood worth the name. Raise it via
// env if a real surge ever trips it, rather than guessing higher now.
const RATE_GLOBAL_MAX = Number(process.env.GUIDE_RATE_GLOBAL_MAX) || 10;
// Turns per IP per minute. Kept well under the ceiling above on purpose: when
// both were 10, one caller's allowance WAS the route's, and a single address
// could hold the Guide shut for everybody. A turn takes ten to twenty seconds
// to answer, so a traveler cannot reach five a minute by asking questions.
// scripts/verify-guide-budget.mjs holds the two numbers apart.
const RATE_IP_MAX = Number(process.env.GUIDE_RATE_IP_MAX) || 5;
// Turns per IP per day. The per-minute limit stops a burst, but at 10/min it
// still allows 14,400 a day, so a caller pacing itself at one question every
// few minutes never meets it. That is exactly the shape of the traffic after
// BotID started enforcing: the 23 September Console export shows ~125 turns by
// 16:00 UTC against a ~25/day baseline, arriving every one to eight minutes,
// every sampled line from one country and classified "human". A traveler
// planning a real trip asks a handful of questions, not forty.
const RATE_DAILY_MAX = Number(process.env.GUIDE_RATE_DAILY_MAX) || 40;
const DAY_MS = 24 * 60 * 60 * 1000;
const RETRYABLE_STATUS = new Set([408, 409, 429, 500, 502, 503, 504, 529]);

type Send = (frame: GuideFrame) => void;

const sleep = (ms: number) => new Promise((r) => setTimeout(r, ms));

// True for the transient upstream conditions worth retrying: an overloaded or
// rate-limited model, or a gateway/5xx blip. Recognizes both the SDK's typed
// APIError (status / error.type) and a raw mid-stream error event surfaced as a
// message string (e.g. {"type":"error","error":{"type":"overloaded_error"...}}).
function isRetryableModelError(err: unknown): boolean {
  if (!err || typeof err !== "object") return false;
  const e = err as { status?: number; error?: { type?: string }; message?: string };
  if (typeof e.status === "number" && RETRYABLE_STATUS.has(e.status)) return true;
  if (/overloaded_error|rate_limit_error|api_error|overloaded/i.test(e.error?.type || "")) return true;
  return /overloaded|rate[\s_-]?limit|\b(429|500|502|503|504|529)\b/i.test(String(e.message || ""));
}

// Never surface raw provider text to the traveler. Transient capacity issues get
// a calm "try again" line. Everything else gets a plain one too: a non-retryable
// API error's message is the provider's own JSON ("Your credit balance is too
// low...", an invalid-request body), which is ours to read in the logs — the
// caller logs the error itself — and nothing a traveler can act on.
function friendlyModelError(err: unknown): string {
  if (isRetryableModelError(err)) {
    return "The Guide is in unusually high demand right now and could not complete that reply. Please try again in a moment.";
  }
  return "The Guide could not complete that reply. Please try again, or use Talk to an advisor and a person will pick it up.";
}

const TIMEOUT_TEXT =
  "The Guide ran out of time on that one. Please ask again — a single destination or one way of travelling comes back fastest.";

// CORS preflight. Allowed origins get a 204 carrying the headers; disallowed
// cross-origin preflights get 403 with none, so the browser refuses the real
// request. (Legitimate callers are same-origin; see lib/guide-cors.ts.)
export async function OPTIONS(req: Request) {
  const cors = corsHeaders(req);
  const allowed = Object.keys(cors).length > 0;
  return new Response(null, { status: allowed ? 204 : 403, headers: cors });
}

export async function POST(req: Request) {
  // Also refused site-wide by the Vercel Firewall "China" rule; repeated here
  // because this is the route that spends money, and it must not depend on a
  // dashboard toggle staying on.
  if (isBlockedCountry(req.headers)) return blockedResponse();
  const cors = corsHeaders(req);
  // Read off the request before the stream starts: once we hand the response
  // back, the turn runs inside the ReadableStream and `req` is out of scope of
  // anything that should still be touching it.
  const shape = requestShape(req);
  const startedAt = Date.now();
  const usage = newUsage();

  // Per-IP only here. The route-wide ceiling is counted further down, once the
  // request is known to be a real turn that will reach the model.
  const limited = await isRateLimited(req, cors, { max: RATE_IP_MAX });
  if (limited) return limited;
  const daily = await isRateLimited(req, cors, {
    bucket: "guide-day",
    max: RATE_DAILY_MAX,
    windowMs: DAY_MS,
    message:
      "You've reached today's limit for The Guide. An advisor can pick this up with you — " +
      "use Talk to an advisor and you'll hear back within 24 hours.",
  });
  if (daily) return daily;

  let body: { messages?: unknown };
  try {
    body = await req.json();
  } catch {
    return Response.json({ error: "Invalid JSON body" }, { status: 400, headers: cors });
  }
  // Bounded before anything is spent: see lib/guide-tokens.ts.
  const bounded = boundHistory(body?.messages);
  if (!bounded.ok) {
    return Response.json({ error: bounded.error }, { status: bounded.status, headers: cors });
  }
  const messages: ChatMessage[] = bounded.messages;
  if (!process.env.ANTHROPIC_API_KEY) {
    return Response.json(
      { error: "Claude API key not configured. Set ANTHROPIC_API_KEY." },
      { status: 500, headers: cors },
    );
  }

  // Who is calling. The check costs milliseconds against a turn that runs for
  // ten to twenty seconds, and it cannot throw; see lib/guide-botid.ts.
  const caller = await classifyCaller();

  // ENFORCING. A caller classified as automated gets a real reply and a route
  // to a person — it just does not get a model round. Deliberately NOT a 403:
  // the whole design turns on a misclassified traveler still reaching an
  // advisor, so the refusal is an ordinary 200 SSE turn that reads as the Guide
  // choosing to hand over rather than as the site breaking. A bot learns
  // nothing from it either, which is the same property from the other side.
  if (wouldRefuse(caller)) {
    logGuideTurn({
      shape,
      usage,
      startedAt,
      stopReason: ADVISOR_HANDOFF,
      ok: true,
      usd: 0,
      // No `store`: nothing was spent, so the spend ceiling's backing counter
      // is not what this line is reporting on.
      bot: caller.verdict,
      botName: caller.name,
    });
    return advisorHandoffStream(cors);
  }

  // The day's money is already spent. Refuse before opening a stream: there is
  // nothing to say that is worth another model round, and 503 + Retry-After is
  // what tells a well-behaved caller to stop rather than retry in a loop.
  const budget = await checkDailyBudget();
  if (budget.over) {
    console.warn(
      JSON.stringify({
        evt: "guide_budget_exhausted",
        spentUsd: Number(budget.spentUsd.toFixed(4)),
        budgetUsd: budget.budgetUsd,
        store: budget.store,
        ref: shape.ref,
      }),
    );
    return Response.json(
      {
        error:
          "The Guide has reached its daily limit. It will be available again shortly — " +
          "an advisor can help you in the meantime.",
      },
      {
        status: 503,
        headers: { ...cors, "Retry-After": String(secondsUntilUtcMidnight()) },
      },
    );
  }

  // The route-wide ceiling, counted last so that only turns about to spend take
  // a place under it. Counted any earlier, an empty POST, a caller past their
  // daily cap and a refused bot each used up the allowance real travelers need.
  const saturated = await isRouteSaturated(cors, { bucket: "guide", globalMax: RATE_GLOBAL_MAX });
  if (saturated) return saturated;

  // Ends the turn's model calls when nobody is listening any more — the
  // traveler pressed Stop, closed the tab, or a script hung up. Without it the
  // tool loop ran every remaining round, and paid for it, into a closed socket.
  const hangup = new AbortController();
  req.signal?.addEventListener("abort", () => hangup.abort(), { once: true });
  // The turn's own clock; see TURN_DEADLINE_MS.
  const deadline = new AbortController();
  const deadlineTimer = setTimeout(
    () => deadline.abort(),
    Math.max(0, TURN_DEADLINE_MS - (Date.now() - startedAt)),
  );
  const signal = AbortSignal.any([hangup.signal, deadline.signal]);

  const encoder = new TextEncoder();
  const stream = new ReadableStream<Uint8Array>({
    async start(controller) {
      const send: Send = (frame) => {
        if (hangup.signal.aborted) return;
        try {
          controller.enqueue(encoder.encode(`data: ${JSON.stringify(frame)}\n\n`));
        } catch {
          // The consumer is gone; treat it as a hang-up.
          hangup.abort();
        }
      };
      let stopReason = "error";
      let ok = false;
      try {
        const turn = await runGuideTurnStream({ messages, send, usage, signal, startedAt });
        stopReason = turn.stopReason;
        ok = true;
        send({
          type: "meta",
          ...summarizeMeta(turn.toolMeta, turn.experiences),
          // A declined turn shows the client's advisor button like any other
          // hand-off; the log line below keeps "refusal" so the two stay
          // countable apart.
          stopReason: stopReason === "refusal" ? ADVISOR_HANDOFF : stopReason,
        });
        send({ type: "done" });
      } catch (err) {
        if (hangup.signal.aborted) {
          stopReason = "client_closed";
        } else if (deadline.signal.aborted) {
          stopReason = "timeout";
          send({ type: "error", error: TIMEOUT_TEXT });
        } else {
          console.error("Guide error:", err);
          send({ type: "error", error: friendlyModelError(err) });
        }
      } finally {
        clearTimeout(deadlineTimer);
        // Charge the day's ledger before anything else: a turn that threw still
        // spent tokens on the rounds it completed, and those are exactly the
        // ones that must not go uncounted. Bounded by the store timeout, and
        // never allowed to fail the response.
        let usd = 0;
        try {
          usd = await recordGuideSpend(usage, MODEL);
        } catch (e) {
          console.error("Guide spend not recorded:", e);
        }
        // One line per turn, whatever happened. A turn that fails expensively
        // is exactly the one worth seeing in the logs.
        logGuideTurn({
          shape,
          usage,
          startedAt,
          stopReason,
          ok,
          usd,
          store: budget.store,
          bot: caller.verdict,
          botName: caller.name,
        });
        try {
          controller.close();
        } catch {
          // Already cancelled by the consumer.
        }
      }
    },
    cancel() {
      clearTimeout(deadlineTimer);
      hangup.abort();
    },
  });

  return new Response(stream, {
    headers: {
      ...cors,
      "Content-Type": "text/event-stream; charset=utf-8",
      "Cache-Control": "no-cache, no-transform",
      "X-Accel-Buffering": "no",
    },
  });
}

async function runGuideTurnStream({
  messages,
  send,
  usage,
  signal,
  startedAt,
}: {
  messages: ChatMessage[];
  send: Send;
  signal: AbortSignal;
  /** When the request arrived, for the turn's time budget. */
  startedAt: number;
  // Mutated in place rather than returned, so a turn that throws mid-sweep
  // still reports the rounds it already paid for.
  usage: GuideUsage;
}): Promise<{
  text: string;
  toolMeta: GuideToolMeta[];
  experiences: ExperiencesMeta | null;
  stopReason: string;
}> {
  const client = new Anthropic();
  const convo: Anthropic.MessageParam[] = messages.map((m) => ({
    role: m.role,
    content: m.content,
  }));
  const toolMeta: GuideToolMeta[] = [];
  // The experiences summary rides beside the tool list rather than in it —
  // prose-only records must not reach the card / map / hand-off pipeline. It is
  // what tells the funnel the call happened and the chat not to re-offer a
  // question it just answered.
  let experiences: ExperiencesMeta | null = null;
  const latestUserText = latestUserContent(messages);
  let text = "";

  // Today's date lets the model resolve relative timing ("spring break week",
  // "the week after Christmas") into real checkIn/checkOut dates. Resolve it
  // once for the whole turn: recomputing per round would change the system text
  // mid-conversation if a turn straddles midnight UTC, and a changed prefix is a
  // missed cache on every remaining round.
  const today = new Date().toISOString().slice(0, 10);
  // The two tool schemas (~22k tokens) and GUIDE_PROMPT (~14k) are byte-identical
  // on every request and every round, and both sit ahead of `messages` in the
  // cache prefix (tools, then system, then messages) — so one breakpoint on the
  // last system block covers the whole ~36k. Without it we re-billed that prefix
  // at full input rate on each of up to MAX_TOOL_ROUNDS requests per question,
  // which was ~88% of this endpoint's token spend.
  //
  // The default five-minute TTL covers the tool-use rounds inside a turn and
  // back-to-back travelers. The prefix only actually changes when `today` rolls
  // over, so `ttl: "1h"` is the next lever if traffic stays bursty — it bills the
  // write at 2x base instead of 1.25x, which one extra hit repays.
  const system: Anthropic.TextBlockParam[] = [
    {
      type: "text",
      text: `${GUIDE_PROMPT}\n\nToday's date is ${today}.`,
      cache_control: { type: "ephemeral" },
    },
  ];

  send({ type: "status", text: "Reading your trip style..." });

  for (let round = 0; round < MAX_TOOL_ROUNDS; round++) {
    if (signal.aborted) throw new Error("client closed");
    // Out of time to open another round and still finish inside the function's
    // limit. Close with what the searches already found: the cards and the map
    // still arrive on the meta frame, and the sentence says why the prose is
    // short rather than leaving a reply that simply stops.
    if (round > 0 && Date.now() - startedAt > ROUND_CUTOFF_MS) {
      const note =
        (text.trim() ? "\n\n" : "") +
        "That search ran longer than I can hold open in one reply. Ask again with a single " +
        "destination or one way of travelling and I will go properly deep on it.";
      text += note;
      send({ type: "delta", text: note });
      return { text: text.trim(), toolMeta, experiences, stopReason: "time_budget" };
    }
    const data = await streamRoundWithRetry(
      client,
      {
        model: MODEL,
        max_tokens: MAX_TOKENS,
        ...(EFFORT ? { output_config: { effort: EFFORT } } : {}),
        system,
        messages: withRollingCache(convo),
        tools: [
          SEARCH_OFFERINGS_TOOL as Anthropic.Tool,
          SEARCH_EXPERIENCES_TOOL as Anthropic.Tool,
        ],
      },
      (delta) => {
        text += delta;
        send({ type: "delta", text: delta });
      },
      () => send({ type: "status", text: "The Guide is in high demand — retrying..." }),
      signal,
    );
    addRound(usage, data.usage);

    if (data.stop_reason === "tool_use") {
      const toolUses = data.content.filter(
        (c): c is Anthropic.ToolUseBlock => c.type === "tool_use",
      );
      convo.push({ role: "assistant", content: data.content });

      if (toolUses.length) {
        send({ type: "status", text: statusForToolUses(toolUses) });
      }

      const toolResults: Anthropic.ToolResultBlockParam[] = [];
      for (const tu of toolUses) {
        let result: unknown;
        try {
          const input =
            tu.name === "search_offerings"
              ? prioritizeMentionedPlace(tu.input || {}, latestUserText)
              : tu.input || {};
          if (tu.name === "search_offerings") {
            result = await searchOfferings(input);
          } else if (tu.name === "search_experiences") {
            result = await searchExperiences(input);
          } else {
            result = { error: `unknown tool ${tu.name}` };
          }
          tu.input = input;
        } catch (e) {
          result = { error: e instanceof Error ? e.message : String(e) };
        }
        // The result-card / map pipeline (toolMeta -> summarizeMeta -> ResultCards
        // / AtlasShell + advisor CTA) is fed by hotel/cruise inventory only.
        // Experiences themselves stay prose-only, but a search_experiences call
        // also returns a few area hotels (result.hotels) that DO anchor the map,
        // render as cards, and unlock the advisor hand-off — so push those.
        if (tu.name === "search_offerings") {
          toolMeta.push({
            ...(result as object),
            input: tu.input as Record<string, unknown>,
            results: (result as GuideToolMeta)?.results || [],
          } as GuideToolMeta);
        } else if (tu.name === "search_experiences") {
          const r = (result || {}) as {
            hotels?: GuideToolMeta;
            total?: number;
            preferredCount?: number;
            unavailable?: boolean;
            error?: unknown;
          };
          const hotels = r.hotels;
          if (hotels && (hotels.results?.length ?? 0) > 0) {
            toolMeta.push({
              ...hotels,
              input: tu.input as Record<string, unknown>,
              results: hotels.results || [],
            } as GuideToolMeta);
          }
          // Summarize the experiences half for the client. Last call wins: a
          // turn that searched twice was refining, and the refinement is the
          // one the reply is built on.
          experiences = {
            total: Number(r.total) || 0,
            preferredCount: Number(r.preferredCount) || 0,
            // A thrown call lands here as { error } — that is the catalogue
            // being unreachable, not the catalogue being empty, and the two
            // must not read the same in the numbers.
            unavailable: !!r.unavailable || !!r.error,
            place: String((tu.input as Record<string, unknown>)?.place || "") || null,
          };
        }
        toolResults.push({
          type: "tool_result",
          tool_use_id: tu.id,
          // The model's copy, without the card/map/booking fields; the full
          // result already went to toolMeta above.
          content: toolResultForModel(result),
        });
      }

      send({ type: "status", text: "Narrowing the strongest fit..." });
      convo.push({ role: "user", content: toolResults });
      continue;
    }

    // Sonnet 5.5's safety classifiers can decline a turn: an ordinary 200 with
    // stop_reason "refusal", and whatever streamed before it is all the reply
    // there will be. The categories (cyber, bio, building rival AI models,
    // extracting the model's reasoning, other harms) are nowhere near a trip
    // question, so this is mostly what a probe sees. Close the turn with the
    // same way through to a person every other hand-off gets, rather than a
    // reply that stops mid-sentence or never starts.
    if (data.stop_reason === "refusal") {
      // The category reads null on the pinned SDK (0.74), whose stream
      // accumulator predates stop_details; the refusal itself is still logged.
      const category =
        (data as { stop_details?: { category?: string | null } }).stop_details?.category ?? null;
      console.warn(JSON.stringify({ evt: "guide_refusal", category, model: MODEL }));
      const note = (text.trim() ? "\n\n" : "") + REFUSAL_TEXT;
      text += note;
      send({ type: "delta", text: note });
      return { text: text.trim(), toolMeta, experiences, stopReason: "refusal" };
    }

    return {
      text: text.trim(),
      toolMeta,
      experiences,
      stopReason: data.stop_reason || "end_turn",
    };
  }

  return { text: text.trim(), toolMeta, experiences, stopReason: "max_tool_rounds" };
}

// One model round, with backoff on transient overload. We only retry when the
// failure landed before any text was streamed for this attempt — once deltas
// have reached the client, restarting would duplicate the reply, so we surface
// the error instead. Overloaded errors arrive at request time (no text yet), so
// in practice they retry cleanly.
async function streamRoundWithRetry(
  client: Anthropic,
  params: Anthropic.MessageStreamParams,
  onText: (delta: string) => void,
  onRetry: () => void,
  signal: AbortSignal,
): Promise<Anthropic.Message> {
  for (let attempt = 1; ; attempt++) {
    let emitted = false;
    try {
      const stream = client.messages.stream(params, { signal });
      stream.on("text", (delta) => {
        emitted = true;
        onText(delta);
      });
      return await stream.finalMessage();
    } catch (err) {
      if (
        signal.aborted ||
        attempt >= MAX_MODEL_ATTEMPTS ||
        emitted ||
        !isRetryableModelError(err)
      ) {
        throw err;
      }
      onRetry();
      // Exponential backoff with jitter: ~0.6s, 1.2s, 2.4s (capped at 8s).
      const backoff = Math.min(8000, 600 * 2 ** (attempt - 1)) + Math.random() * 300;
      await sleep(backoff);
    }
  }
}

// What a refused caller is told. Warm, specific about the way forward, and
// silent about why — a traveler wrongly caught by the classifier should read
// this as the Guide handing over rather than as an accusation, and an actual
// scraper should learn nothing about what tripped it.
const ADVISOR_HANDOFF_TEXT =
  "I can't run that search from here right now — but an Aspen advisor can, and they " +
  "have the same inventory I do plus the supplier relationships that never fit in a " +
  "chat window. Use **Talk to an advisor** just above and tell them what you're " +
  "planning; you'll hear back within 24 hours.";

// What closes a turn the model declined (stop_reason "refusal"). Plain and
// short: it may follow a half-written reply, and it says nothing about why.
const REFUSAL_TEXT =
  "I can't help with that one here. For anything about your trip, use **Talk to an " +
  "advisor** just above and an Aspen advisor will come back to you within 24 hours.";

// The refusal, shaped as an ordinary finished turn: one delta, a meta frame
// carrying the stopReason the client keys its advisor button off, then done.
// No status frames — nothing is being searched, and a spinner that resolves to
// a hand-off reads worse than the hand-off arriving straight away.
function advisorHandoffStream(cors: Record<string, string>): Response {
  const encoder = new TextEncoder();
  const frames: GuideFrame[] = [
    { type: "delta", text: ADVISOR_HANDOFF_TEXT },
    {
      type: "meta",
      deepLink: null,
      chartRegion: null,
      tools: [],
      experiences: null,
      stopReason: ADVISOR_HANDOFF,
    },
    { type: "done" },
  ];
  return new Response(
    new ReadableStream<Uint8Array>({
      start(controller) {
        for (const f of frames) {
          controller.enqueue(encoder.encode(`data: ${JSON.stringify(f)}\n\n`));
        }
        controller.close();
      },
    }),
    {
      headers: {
        ...cors,
        "Content-Type": "text/event-stream; charset=utf-8",
        "Cache-Control": "no-cache, no-transform",
        "X-Accel-Buffering": "no",
      },
    },
  );
}

// Retry-After for a tripped daily ceiling. The budget key is a UTC day, so the
// honest answer is "when that day rolls over", not a flat guess.
function secondsUntilUtcMidnight(now: number = Date.now()): number {
  const next = Date.UTC(
    new Date(now).getUTCFullYear(),
    new Date(now).getUTCMonth(),
    new Date(now).getUTCDate() + 1,
  );
  return Math.max(1, Math.ceil((next - now) / 1000));
}

function statusForToolUses(toolUses: Anthropic.ToolUseBlock[]): string {
  // Experiences lookups can run alongside or instead of an inventory search.
  const exp = toolUses.find((tu) => tu.name === "search_experiences");
  if (exp && !toolUses.some((tu) => tu.name === "search_offerings")) {
    const where = String((exp.input as Record<string, unknown>)?.place || "").trim();
    return where ? `Looking at things to do in ${where}...` : "Looking at things to do nearby...";
  }

  const input =
    (toolUses.find((tu) => tu.name === "search_offerings")?.input as
      | Record<string, unknown>
      | undefined) || {};
  const type = String(input.type || "any").toLowerCase();
  if (
    (type === "cruise" || type === "yacht" || type === "any") &&
    luxuryCruiseAdvisorIntent(input, type)
  ) {
    return "Routing the Luxury Cruise request to an advisor...";
  }
  if (type === "cruise") return "Checking approved Expedition Cruise and yacht inventory...";
  if (type === "jet") return "Checking private jet journey inventory...";
  if (type === "yacht") return "Checking luxury hotel yacht sailings...";
  if (type === "villa") return "Checking private villa inventory...";
  return "Checking approved hotel inventory...";
}

function latestUserContent(messages: ChatMessage[]): string {
  for (let i = messages.length - 1; i >= 0; i--) {
    const m = messages[i];
    if (m?.role === "user" && typeof m.content === "string") return m.content;
  }
  return "";
}

// Bubble up the most relevant Atlas handoff for the client (map plot + button).
function summarizeMeta(
  toolMeta: GuideToolMeta[],
  experiences: ExperiencesMeta | null = null,
): GuideMeta {
  const tools: GuideToolMeta[] = toolMeta.map((t) => ({
    input: t.input,
    type: t.type,
    total: t.total,
    count: t.count,
    deepLink: t.deepLink ?? null,
    chartRegion: t.chartRegion ?? null,
    unavailable: !!t.unavailable,
    // Carried so the hand-off can tell "no live inventory by design" (an
    // advisor-sourced Luxury Cruise) apart from "expedition sailings", which
    // share the type "cruise" and otherwise look identical downstream.
    advisorOnly: !!t.advisorOnly,
    sources: t.sources ?? null,
    results: t.results || [],
    related: t.related ?? null,
    ...(t.trip ? { trip: t.trip } : {}),
  }));
  const lead = leadTool(tools);
  return {
    deepLink: lead ? (lead.deepLink ?? null) : null,
    chartRegion: lead ? (lead.chartRegion ?? null) : null,
    tools,
    experiences,
  };
}
