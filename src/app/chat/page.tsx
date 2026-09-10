"use client";

import { useCallback, useEffect, useMemo, useRef, useState } from "react";
import Link from "next/link";
import type {
  AgentDTO,
  AmbientAgentDTO,
  ChatDTO,
  ChatListEntryDTO,
  ChatMessageDTO,
  ChatProposalDTO,
  ChatQuestionDTO,
  ProposedBlockDTO,
} from "@/lib/apiTypes";
import { chatRequest } from "@/lib/chatRequest";
import { mergeMessages, threadItems, turnStartInstant } from "@/lib/chatThread";
import {
  describeAmbientAgents,
  fmtDateTime,
  fmtDuration,
  fmtRelative,
  fmtUSD,
  pollFailureMessage,
} from "@/lib/format";
import { Markdown } from "@/components/Markdown";
import { Badge } from "@/components/ui/Badge";
import { Button, ButtonRow, type ButtonVariant } from "@/components/ui/Button";
import { Card, CardTitle, Empty, type CardEmphasis } from "@/components/ui/Card";
import { Disclosure } from "@/components/ui/Disclosure";
import { Input } from "@/components/ui/Field";
import { Hint } from "@/components/ui/Hint";
import { Icon } from "@/components/ui/Icon";
import { ListGroup } from "@/components/ui/List";
import { Spinner } from "@/components/ui/Log";
import { Notice } from "@/components/ui/Notice";
import {
  SegmentedControl,
  type SegmentedOption,
} from "@/components/ui/SegmentedControl";

/**
 * The orchestrator chat.
 *
 * Two halves that mean different things and are kept visually apart for that
 * reason: a conversation, which costs money and produces text, and a list of
 * proposals, which costs nothing until a person clicks. Nothing in the left
 * half starts work. Everything that does is a button in the right half — which
 * is why a proposal is drawn as an object with a border, a folder and a guard
 * set rather than as another paragraph in the thread, and why the approve row
 * says how many unattended runs the click starts.
 */

/** Faster only while a turn is in flight — the same rule the dashboard follows. */
const POLL_IDLE_MS = 10_000;
const POLL_ACTIVE_MS = 3_000;

/**
 * Within this of the bottom counts as reading the latest, so an arriving turn
 * follows the reader down. Past it the page must not move at all: a poll that
 * scrolls somebody out of the paragraph they are reading is the one jank this
 * page can produce on its own.
 */
const NEAR_BOTTOM_PX = 48;

/** About ten lines. Past that the composer scrolls rather than eating the thread. */
const COMPOSER_MAX_PX = 208;

/**
 * How many saved agents the mention list offers at once.
 *
 * A completion list is read at a glance or not at all, and this one sits over
 * the conversation. Past a handful the answer is a narrower query, not a
 * taller popover.
 */
const MENTION_LIMIT = 6;

/** Complete class strings per state, never interpolated — the kit's rule. */
const MENTION_ROW: Record<"active" | "idle", string> = {
  active: "bg-selection",
  idle: "bg-transparent",
};

/** Where an `@`-mention starts in the draft, and what has been typed after it. */
interface MentionToken {
  /** Index of the `@` itself, so an insertion replaces the whole token. */
  start: number;
  query: string;
}

/**
 * The `@`-mention under the caret, or null.
 *
 * **What this is, before what it does.** The chat's child is `claude -p`, so
 * there is no interactive `@` on the wire and nothing here completes into the
 * model's own context: a mention is *text the operator writes*, and what it
 * does is tell the orchestrator which saved agent to start the proposed run as.
 * It names the *run's* agent and never this turn's — the chat's own child is
 * deliberately started as none, which `chat.ts` argues beside `runTurn`.
 * The orchestrator reads it, calls `list_agents`, and passes an `agentId` to
 * `propose_run` — where the agent is refused by name if it has gone. This app
 * never parses the mention back out of the message, which is why a name with a
 * space in it is inserted as it stands rather than quoted into a syntax nobody
 * else here speaks: the only reader is a model that has the list.
 *
 * Pure, and it only ever looks left from the caret. Two rules bound it, and
 * both exist to stop ordinary prose opening a list over the conversation: the
 * `@` has to open a word, so `user@host` is an address rather than a mention;
 * and a mention is one word, so the first space closes it instead of reading
 * the rest of a paragraph as a very long agent name.
 */
function mentionAt(text: string, caret: number): MentionToken | null {
  const upto = text.slice(0, caret);
  const start = upto.lastIndexOf("@");
  if (start === -1) return null;
  if (start > 0 && !/\s/.test(upto[start - 1])) return null;
  const query = upto.slice(start + 1);
  if (/\s/.test(query)) return null;
  return { start, query };
}

const PROPOSAL_TONE = {
  pending: "accent",
  approved: "ok",
  rejected: "neutral",
  // Neutral beside `rejected` and never `danger`: the chat replaced its own
  // card with a corrected one, which is not a failure and must not be drawn as
  // one — the same reading a superseded question gets below.
  superseded: "neutral",
  failed: "danger",
} as const;

/**
 * Complete class strings per state, never interpolated — Tailwind scans source
 * as text, so a computed class name emits nothing at all and does it silently.
 * Same rule the kit's own tone maps follow.
 *
 * A wash rather than a border, because these are now rows of one grouped box
 * and a row that gained a border on selection would shift the two beside it. It
 * is `--selection` — the app's own "this one" wash, which takes the operator's
 * accent where the browser exposes it — at an alpha that leaves the row's text
 * at its own contrast whatever that accent turns out to be.
 */
const PROPOSAL_ROW: Record<"selected" | "idle", string> = {
  selected: "bg-selection",
  idle: "bg-transparent hover:bg-fill-hover",
};

const GUARD_TONE: Record<"missing" | "set", string> = {
  missing: "text-danger",
  set: "text-ink-muted",
};

/**
 * The refusals the card already states, so `Select all` can agree to what will
 * happen rather than to what is on screen.
 *
 * These are exactly the three facts `Proposal` draws in `text-danger` with the
 * words "will be refused" — a deleted template, an agent that is gone or has
 * decayed, and a graph that could not be read — and each is the client-visible
 * half of a refusal the approve route already makes: `planProposal` refuses the
 * first two by name and `planWorkflowProposal` the third, which is what leaves
 * `blocks` empty in the first place. A card saying approval will be refused and
 * a selection that includes it is the page contradicting itself, and the count
 * the operator agrees to is the one that goes wrong.
 *
 * Deliberately **not** the whole refusal set. The rest of it is a folder on
 * disk, an install-wide ceiling and the live dependency graph, none of which
 * this page can see; guessing at those would skip a proposal that would have
 * started. Under-selecting costs one tick, over-selecting is the defect.
 */
function approvalRefused(proposal: ChatProposalDTO): boolean {
  return proposal.kind === "workflow"
    ? proposal.blocks.length === 0
    : proposal.guardsSource === "missing" || proposal.agentMissing;
}

/**
 * The DOM id a proposal card carries, in either list.
 *
 * Only the "Replaced by" line on a superseded card reads it, and it exists
 * because the two cards are almost never in the same list: a replacement is
 * still waiting and the card it replaced is decided, so naming the replacement
 * without a way to reach it leaves the operator matching a title across a tab
 * switch by hand. Not a general anchor scheme — nothing else on this page links
 * to a proposal, and `dependsOn` deliberately names a sibling by label instead.
 */
function proposalAnchorId(id: string): string {
  return `proposal-${id}`;
}

/**
 * The leading edge of a question card, per state. Complete class strings, the
 * kit's rule — an interpolated one emits nothing at all and does it silently.
 *
 * Accent while it is open, and only there. On this page accent already means
 * "this is waiting for you" — the proposals badge, the current row in the
 * thread list — and a question is the one thing in the *transcript* that is.
 * Settled, it takes the same neutral edge a `system` turn wears, because it is
 * then a record of what happened rather than something to do.
 */
const QUESTION_EDGE: Record<"open" | "settled", string> = {
  open: "border-l-accent",
  settled: "border-l-line-strong",
};

/**
 * A `system` turn's edge and text, per kind. Complete class strings, as above.
 *
 * `Message`'s docblock argues that what the app did must not be drawn as though
 * the model said it; the same argument separates what the app *did* from what
 * went *wrong*. "The chat saved a new template" and "the chat produced nothing
 * for 15 minutes and was stopped" are the same grey today, and only one of
 * them is something to act on.
 *
 * **The page infers which is which, because the row does not say.**
 * `chat_messages` carries no kind, so a failure is "the last message of a
 * `failed` chat, saying what the row's `error` says" — right about the ending
 * being looked at now, and wrong about the ones behind it: `claimTurn` clears
 * both on the next message, so an older failure in a thread that was re-sent
 * reverts to grey. The durable answer is a column on the table, which is a
 * migration for a tone.
 */
const SYSTEM_EDGE: Record<"note" | "failure", string> = {
  note: "border-l-line-strong text-ink-muted",
  failure: "border-l-danger text-ink",
};

/**
 * A choice button, per state.
 *
 * Only reachable while more than one question is open — with one, a choice
 * *is* the answer and there is nothing to mark as chosen. See `AskedQuestions`.
 */
const CHOICE_VARIANT: Record<"chosen" | "offered", ButtonVariant> = {
  chosen: "primary",
  offered: "secondary",
};

/** What a proposed block is, in the words the workflow pages already use. */
const BLOCK_KIND: Record<ProposedBlockDTO["kind"], string> = {
  run: "run",
  orchestrator: "decides what to run",
  merge: "lands branches",
  loop: "repeats a task",
};

/**
 * `bg-transparent` and `font-normal` are not redundant: the legacy stylesheet
 * still styles every bare `button` as a filled accent control, so a row that
 * names no background gets one.
 */
const CHAT_ROW: Record<"current" | "other", string> = {
  current: "border-l-accent bg-accent-dim/40 text-ink",
  other: "border-l-transparent bg-transparent text-ink-muted hover:bg-inset hover:text-ink",
};

/** Shown by fading in place rather than by mounting, so nothing pops. */
const JUMP_STATE: Record<"shown" | "hidden", string> = {
  shown: "translate-y-0 opacity-100",
  hidden: "pointer-events-none translate-y-1 opacity-0",
};

/**
 * The card rises when it has something waiting for a decision.
 *
 * **This is the only card on the page allowed to move, and the conversation
 * beside it is deliberately not the other half of a pair.** Both were
 * `primary` at once, which by `Card`'s own rule means the page had no lead at
 * all — so one of them had to stop rising. The obvious repair was to make the
 * conversation the inverse of this map, and it is wrong: `emphasis` carries
 * padding as well as elevation (`p-5` against `p-4`), so a conversation keyed
 * on `pending` would re-pad the scrolled transcript and shift the composer
 * under the reader's hands the moment a proposal arrived — on a surface that
 * polls. This card holds neither a scroll position nor a text field, which is
 * exactly why it is the one that may change size.
 *
 * The conversation is therefore a flat `default` in every state, and the page
 * has one lead while something is waiting and none otherwise. That is a state
 * §1.1 names as legitimate, and on this page it is honest: with nothing
 * waiting, the thread is already the larger half by three columns and does not
 * need a shadow to say so.
 */
const PROPOSALS_EMPHASIS: Record<"waiting" | "clear", CardEmphasis> = {
  waiting: "primary",
  clear: "default",
};

/**
 * The three lists that stand beside the conversation, one at a time.
 *
 * They used to be three cards stacked in a 360px column, and a column is the
 * one arrangement that cannot bound them: proposals accumulate for as long as
 * nobody decides, decided ones accumulate for ever, and conversations do too —
 * so "which thread am I in" ended up several screens below a panel whose top
 * half was work already dealt with. One box with a tab bar is the same trade
 * the run page already makes for its five panes, and it is offered on the same
 * two rules: a tab exists only when there is something behind it, and **nothing
 * switches tabs on its own** — a proposal arriving while somebody is reading
 * another list must not move them. What that costs is a pending count nobody
 * can see from the other two tabs, which is why the badge beside the control is
 * drawn from any tab rather than on the Proposals segment.
 */
type SideTab = "proposals" | "decided" | "chats";

function prefersReducedMotion(): boolean {
  return (
    typeof window !== "undefined" &&
    window.matchMedia("(prefers-reduced-motion: reduce)").matches
  );
}

export default function ChatPage() {
  const [chat, setChat] = useState<ChatDTO | null>(null);
  const [chats, setChats] = useState<ChatListEntryDTO[]>([]);
  // The search over *every* thread, held apart from the list above and not for
  // tidiness: that list rides both polled routes and is overwritten every few
  // seconds, so a result set kept in it would be wiped mid-read. Null means
  // nobody is searching and the live list is what the tab shows.
  const [chatQuery, setChatQuery] = useState("");
  const [found, setFound] = useState<{
    q: string;
    chats: ChatListEntryDTO[];
    total: number;
  } | null>(null);
  const [findError, setFindError] = useState<string | null>(null);
  const [finding, setFinding] = useState(false);
  const [draft, setDraft] = useState("");
  // Three action errors rather than one, because each belongs beside the
  // control that failed: a refused approval reported above the composer is a
  // sentence about a button that is not on screen. `pollError` is separate
  // again — the handlers clear theirs on every click, and a poll lands between
  // clicks, so one state would have each wiping the other's sentence.
  const [error, setError] = useState<string | null>(null);
  const [sendError, setSendError] = useState<string | null>(null);
  const [decideError, setDecideError] = useState<string | null>(null);
  // A fourth, for the same reason there are three: the question card is in the
  // transcript, and a refused answer reported under the composer is a sentence
  // about buttons that may be several screens up.
  const [answerError, setAnswerError] = useState<string | null>(null);
  const [pollError, setPollError] = useState<string | null>(null);
  const [busy, setBusy] = useState(false);
  const [selected, setSelected] = useState<Set<string>>(new Set());
  const [side, setSide] = useState<SideTab>("proposals");
  const [atBottom, setAtBottom] = useState(true);
  const [unseen, setUnseen] = useState(0);
  // The registry the composer completes from, and the definitions on disk this
  // app did not write — off one payload, so no surface here can describe the
  // set differently from the run form or the workflow canvas. A failed read
  // leaves the list empty and costs the completion, never the message: the
  // mention is text either way, and the orchestrator resolves it server-side.
  const [agents, setAgents] = useState<AgentDTO[]>([]);
  const [ambient, setAmbient] = useState<AmbientAgentDTO[]>([]);
  const [mention, setMention] = useState<MentionToken | null>(null);
  const [mentionIndex, setMentionIndex] = useState(0);
  /**
   * The token offset Esc dismissed, so the list stays shut while it is typed.
   *
   * An offset rather than a boolean: a mention the operator dismissed must not
   * reopen on the next keystroke, and one they open later somewhere else must
   * not inherit that decision.
   */
  const [mentionClosed, setMentionClosed] = useState<number | null>(null);
  /** Where the caret goes after an insertion, applied once the draft has it. */
  const [caretTo, setCaretTo] = useState<number | null>(null);

  const threadRef = useRef<HTMLDivElement>(null);
  const composerRef = useRef<HTMLTextAreaElement>(null);
  // The scroll position the *effect* reads. State drives the button; a ref is
  // what tells an arriving message whether the reader was at the bottom, and it
  // must not be one render behind.
  const atBottomRef = useRef(true);
  const seen = useRef<{ chatId: string | null; count: number }>({
    chatId: null,
    count: 0,
  });
  /**
   * Where the next poll resumes from, so it asks for a tail and not a thread.
   *
   * A ref rather than state because `load` is its only reader: in state it would
   * be a dependency of the callback, the callback is a dependency of the
   * interval, and the interval would then be torn down and re-armed by every
   * message that arrives — restarting the three-second period mid-turn, which is
   * exactly when it is being counted on.
   *
   * Mirrored out of the thread on screen rather than kept beside it, because
   * what the page holds is what it has drawn and a second count maintained by
   * hand is a second thing that can be wrong. Keyed by thread: switching
   * conversations must ask for a whole one rather than resume another's number.
   */
  const cursor = useRef<{ chatId: string | null; seq: number }>({
    chatId: null,
    seq: 0,
  });

  const chatId = chat?.id ?? null;
  const thinking = chat?.status === "thinking";
  const messageCount = chat?.messages.length ?? 0;
  // Up here with the other derived facts rather than beside the proposal lists,
  // because an effect below depends on the count: a `const` declared after a
  // `useEffect` that names it in its dependency array is read before it is
  // initialised, and that is a ReferenceError on the first render rather than
  // anything subtle.
  const questions = chat?.questions ?? [];
  const openQuestions = questions.filter((q) => q.status === "pending").length;
  // The transcript with the questions put back where they were asked. Derived
  // on every render rather than held in state, for the reason the proposal
  // lists are: it is a projection of the poll's answer, and a copy would be one
  // more thing that can disagree with what the server just said.
  const items = threadItems(chat?.messages ?? [], questions);

  /**
   * Neither failure may be dropped. A poll that returns early leaves the last
   * snapshot on screen as though it were current — a thread that was thinking
   * when the polls started failing then shows "Thinking…" for ever, which is
   * indistinguishable from a turn still working.
   */
  const load = useCallback(async (id: string | null) => {
    try {
      // The thread past what is already on screen, which is what makes the cost
      // of leaving this page open flat rather than a function of how long the
      // conversation has got. Zero — the whole thread — on the first poll of a
      // thread and on every poll of a thread this page has not drawn yet.
      const after = id !== null && cursor.current.chatId === id ? cursor.current.seq : 0;
      const query = after > 0 ? `?after=${after}` : "";
      const res = await fetch(id ? `/api/chat/${id}${query}` : "/api/chat", {
        cache: "no-store",
      });
      // Parsed before the status check: a 500 from inside `chatDTO` carries no
      // JSON, and letting that throw would report a reachable server as an
      // unreachable one.
      const data = (await res.json().catch(() => ({}))) as {
        chat?: ChatDTO;
        chats?: ChatListEntryDTO[];
        error?: string;
      };
      if (!res.ok || !data.chat) {
        const detail = data.error ?? (res.ok ? "no thread in the response" : null);
        setPollError(pollFailureMessage(res.status, detail));
        return;
      }
      const answered = data.chat;
      setChat((prev) => {
        // Appended rather than replaced when the answer is a tail, and only
        // onto the thread it is a tail *of*.
        if (prev && prev.id === answered.id) {
          return {
            ...answered,
            messages: mergeMessages(
              prev.messages,
              answered.messages,
              answered.messagesFrom,
            ),
          };
        }
        // A tail that arrives after the page has moved on — New chat pressed
        // while this request was out — is not a conversation and must not be
        // drawn as one. Dropped rather than shown headless; the poll after it
        // carries no cursor and answers with the whole thread.
        return answered.messagesFrom > 0 ? prev : answered;
      });
      // A proposal this thread was holding can be decided somewhere this page
      // cannot see — another tab, another window — and its id then stays in
      // `selected` with no row left to untick. The route refuses it by id, so
      // nothing wrong reaches the data; what it costs is the two claims this
      // page makes about the selection. `allSelected` compares a size against
      // `pending.length` and so reads true while a visible row is unticked,
      // and "the explicit list of the ids the page displayed" becomes a
      // sentence about the render before this one. So the poll's answer is
      // what the set is reconciled against, here rather than in `pending`:
      // approval stays one synchronous pass over an explicit list of ids that
      // state holds, and deriving it from the render would be a different
      // gate. `prev` is returned unchanged where nothing was dropped, because
      // this runs on every poll and a fresh Set each time would re-render the
      // rows for nothing.
      const stillPending = new Set(
        data.chat.proposals.filter((p) => p.status === "pending").map((p) => p.id),
      );
      setSelected((prev) => {
        if (prev.size === 0) return prev;
        const next = new Set([...prev].filter((id) => stillPending.has(id)));
        return next.size === prev.size ? prev : next;
      });
      // Both routes answer with the list, so this lands on every poll. Still
      // guarded: the body above is untrusted, and a payload without it must
      // leave the sidebar as it was rather than emptying it.
      if (data.chats) setChats(data.chats);
      setPollError(null);
    } catch (err) {
      // `void load(id)` from an interval: without this the rejection is an
      // unhandled one and, again, nothing on screen changes.
      const cause = err instanceof Error ? err.message : String(err);
      setPollError(pollFailureMessage(null, cause));
    }
  }, []);

  /**
   * Every thread matching a search, not only the newest thirty.
   *
   * Its own request rather than parameters on the poll: the poll's job is to
   * keep the open thread and the live list current, and a search that rode it
   * would re-run on a three-second timer over a query the operator has stopped
   * typing. `offset` appends, so pressing More twice reads two pages rather
   * than one longer one.
   */
  const search = useCallback(
    async (q: string, offset = 0) => {
      const text = q.trim();
      if (!text) {
        setFound(null);
        setFindError(null);
        return;
      }
      setFinding(true);
      try {
        const res = await fetch(
          `/api/chat?q=${encodeURIComponent(text)}&offset=${offset}&limit=30`,
          { cache: "no-store" },
        );
        const data = (await res.json().catch(() => ({}))) as {
          chats?: ChatListEntryDTO[];
          total?: number;
          error?: string;
        };
        if (!res.ok || !data.chats) {
          setFindError(pollFailureMessage(res.status, data.error ?? null));
          return;
        }
        const page = data.chats;
        setFound((prev) =>
          offset > 0 && prev && prev.q === text
            ? { q: text, chats: [...prev.chats, ...page], total: data.total ?? 0 }
            : { q: text, chats: page, total: data.total ?? 0 },
        );
        setFindError(null);
      } catch (err) {
        setFindError(
          pollFailureMessage(null, err instanceof Error ? err.message : String(err)),
        );
      } finally {
        setFinding(false);
      }
    },
    [],
  );

  // What the page holds, so the next poll can ask for what it does not. Taken
  // from the thread after it is merged rather than from the answer before it,
  // because the cursor may only move over a message that is actually on screen
  // — a poll firing before this lands re-asks for one or two, and `mergeMessages`
  // drops them, which is the overlap it is written for.
  useEffect(() => {
    cursor.current = { chatId, seq: chat?.messages.at(-1)?.seq ?? 0 };
  }, [chatId, chat]);

  useEffect(() => {
    void load(null);
  }, [load]);

  // Once, and deliberately not on the poll: the registry changes when somebody
  // edits it on another page, which is not something this composer has to track
  // between keystrokes. A failure is swallowed for the reason stated where the
  // state is declared — it costs a completion, and the door still decides.
  useEffect(() => {
    let live = true;
    fetch("/api/agents", { cache: "no-store" })
      .then((r) => r.json())
      .then((d: { agents?: AgentDTO[]; ambient?: AmbientAgentDTO[] }) => {
        if (!live) return;
        setAgents(d.agents ?? []);
        setAmbient(d.ambient ?? []);
      })
      .catch(() => void 0);
    return () => {
      live = false;
    };
  }, []);

  // Both halves come back from this one request — the thread route answers with
  // the list too — so the list stays current on the thread's own period and
  // never on a timer of its own.
  // No `if (!chatId) return`: a first load that fails leaves no thread to poll
  // for, so the guard that used to stand here meant the page never tried again
  // and the failure notice stood for ever. The cadence is unchanged — with no
  // thread there is no `thinking` status, so this is the idle timer.
  //
  // **A chat waiting on an answer stays on the idle period, and that is a
  // decision rather than an omission.** The fast cadence exists to catch a turn
  // landing; a chat with a question open has no child and nothing on the server
  // can produce the answer, so three-second polling would be three times the
  // requests for a row that cannot move until a person clicks. It does not
  // stand down either, which is the half worth stating: the answer can arrive
  // from another tab, and the thread list beside it moves for reasons that have
  // nothing to do with this conversation — so ten seconds, not never.
  useEffect(() => {
    const period = chat?.status === "thinking" ? POLL_ACTIVE_MS : POLL_IDLE_MS;
    const t = setInterval(() => void load(chatId), period);
    return () => clearInterval(t);
  }, [chatId, chat?.status, load]);

  const scrollToLatest = useCallback((smooth: boolean) => {
    const el = threadRef.current;
    if (!el) return;
    // `behavior` is not covered by the reduced-motion rule in globals.css —
    // that one can only flatten CSS transitions, and this is a scroll.
    el.scrollTo({
      top: el.scrollHeight,
      behavior: smooth && !prefersReducedMotion() ? "smooth" : "auto",
    });
    atBottomRef.current = true;
    setAtBottom(true);
    setUnseen(0);
  }, []);

  const onScroll = () => {
    const el = threadRef.current;
    if (!el) return;
    const near = el.scrollHeight - el.scrollTop - el.clientHeight <= NEAR_BOTTOM_PX;
    atBottomRef.current = near;
    setAtBottom(near);
    if (near) setUnseen(0);
  };

  /**
   * The one place the thread is allowed to move on its own.
   *
   * A poll that adds nothing moves nothing, and a poll that adds a turn moves
   * the view only for a reader who was already at the bottom. Everyone else
   * gets a count on the jump control instead — the alternative is being pulled
   * out of the paragraph you were reading every three seconds while a turn
   * lands.
   */
  useEffect(() => {
    const el = threadRef.current;
    if (!el) return;
    if (seen.current.chatId !== chatId) {
      // A different conversation opens at its latest message, however the last
      // one was left.
      seen.current = { chatId, count: messageCount };
      el.scrollTo({ top: el.scrollHeight });
      atBottomRef.current = true;
      setAtBottom(true);
      setUnseen(0);
      return;
    }
    const added = messageCount - seen.current.count;
    seen.current.count = messageCount;
    if (added <= 0) return;
    if (atBottomRef.current) scrollToLatest(true);
    else setUnseen((n) => n + added);
  }, [chatId, messageCount, scrollToLatest]);

  // The waiting row is content too: it appears under the message just sent, and
  // for a reader at the bottom it should not be the thing that is cut off.
  useEffect(() => {
    if (thinking && atBottomRef.current) scrollToLatest(false);
  }, [thinking, scrollToLatest]);

  // A question is content that arrives with no message behind it —
  // `ask_operator` writes the row mid-turn, so the card can land while the
  // thread is still thinking and `messageCount` has not moved. Same rule as the
  // waiting row above: it follows a reader who was already at the bottom and
  // moves nobody else.
  useEffect(() => {
    if (openQuestions > 0 && atBottomRef.current) scrollToLatest(false);
  }, [openQuestions, scrollToLatest]);

  useEffect(() => {
    const el = composerRef.current;
    if (!el) return;
    el.style.height = "auto";
    el.style.height = `${Math.min(el.scrollHeight, COMPOSER_MAX_PX)}px`;
  }, [draft]);

  // After the insertion, not with it: the caret is a property of the DOM node
  // and the draft it belongs to has to be rendered first, or the position lands
  // in the text as it was before the name went in.
  useEffect(() => {
    if (caretTo === null) return;
    const el = composerRef.current;
    if (el) {
      el.focus();
      el.setSelectionRange(caretTo, caretTo);
    }
    setCaretTo(null);
  }, [caretTo]);

  /* ---------------------------------------------------------------- */
  /* The mention list                                                  */
  /* ---------------------------------------------------------------- */

  const ambientLine = useMemo(() => describeAmbientAgents(ambient), [ambient]);

  // An unusable agent is listed rather than hidden, marked, for the reason the
  // run form's picker lists one: it is a row the operator saved, and a registry
  // that quietly stops showing it is a registry that disagrees with the page
  // they saved it on. Mentioning one costs a refusal with a sentence naming the
  // fix, which is a better answer than an agent that appears not to exist.
  const matches = useMemo(() => {
    if (!mention || mentionClosed === mention.start) return [];
    const query = mention.query.toLowerCase();
    return agents
      .filter((a) => a.name.toLowerCase().includes(query))
      .slice(0, MENTION_LIMIT);
  }, [agents, mention, mentionClosed]);

  const mentionOpen = matches.length > 0;
  // Clamped rather than reset on every filter: the list narrows as the operator
  // types, and an index left past its end would highlight nothing while Tab
  // still had something to insert.
  const active = Math.min(mentionIndex, matches.length - 1);

  /** Read the token under the caret. Called wherever the caret can have moved. */
  const readMention = (value: string, caret: number | null) => {
    const token = caret === null ? null : mentionAt(value, caret);
    if (mention?.start === token?.start && mention?.query === token?.query) return;
    setMention(token);
    setMentionIndex(0);
  };

  const insertMention = (name: string) => {
    const el = composerRef.current;
    if (!el || !mention) return;
    const caret = el.selectionStart ?? draft.length;
    const before = draft.slice(0, mention.start);
    // The trailing space closes the token, which is what hides the list without
    // a second piece of state deciding when it is finished.
    const inserted = `@${name} `;
    setDraft(before + inserted + draft.slice(caret));
    setMention(null);
    setMentionClosed(null);
    setCaretTo(before.length + inserted.length);
  };

  const send = async () => {
    const message = draft.trim();
    // `thinking` is checked here and not only on the button: the composer stays
    // usable while a turn runs so a reply can be written, and Enter must not
    // send into the guard that keeps one billed child per conversation.
    if (!message || !chatId || busy || thinking) return;
    setBusy(true);
    setSendError(null);
    try {
      const result = await chatRequest(`/api/chat/${chatId}/message`, { message });
      // The draft is cleared on success only. A failed send that ate the text
      // is a failure the operator cannot retry.
      if (!result.ok) setSendError(result.error ?? "The message could not be sent.");
      else {
        setDraft("");
        if (result.chat) setChat(result.chat);
      }
    } finally {
      // `busy` disables every button here at once and only this line clears it,
      // so it is released on the way out however the request ended. No `catch`:
      // `chatRequest` returns the transport failure instead of throwing it, and
      // anything still reaching here is a bug that should not be swallowed.
      setBusy(false);
    }
  };

  /**
   * Stop a turn that is not going to finish.
   *
   * The only way back from a thread stuck on "Thinking…" short of restarting
   * the server — which stops every run in flight to clear one conversation. It
   * is deliberately not a send: the guard that refuses a message while a turn
   * is in flight is what stops two billed children on one conversation.
   */
  const stop = async () => {
    if (!chatId || busy) return;
    setBusy(true);
    setSendError(null);
    try {
      const result = await chatRequest(`/api/chat/${chatId}/cancel`);
      if (!result.ok) setSendError(result.error ?? "The turn could not be stopped.");
      else if (result.chat) setChat(result.chat);
    } finally {
      // `send`'s reasoning, and this handler is the one that most needs it: a
      // turn worth stopping is one where something has already gone wrong.
      setBusy(false);
    }
  };

  /**
   * Answer what the chat asked, which starts the turn that reads the answer.
   *
   * Deliberately its own door rather than a composer send: the route settles
   * the rows this names and quotes each question above its answer, so the fresh
   * child resumed against the session reads what it asked rather than a bare
   * string. Sending the same words through the composer would *supersede* the
   * questions instead, which is a different fact and one the model is told.
   *
   * `busy` is shared with the composer and the approve row for the reason it
   * always was: one billed child per conversation, and every control that can
   * start one is out while a request that might have is in flight.
   */
  const answer = async (answers: Array<{ id: string; answer: string }>) => {
    if (!chatId || answers.length === 0 || busy || thinking) return;
    setBusy(true);
    setAnswerError(null);
    try {
      const result = await chatRequest(`/api/chat/${chatId}/questions`, { answers });
      if (!result.ok) {
        setAnswerError(result.error ?? "That answer could not be sent.");
      } else if (result.chat) {
        setChat(result.chat);
      }
    } finally {
      setBusy(false);
    }
  };

  const decide = async (action: "approve" | "reject", ids: string[]) => {
    if (!chatId || ids.length === 0 || busy) return;
    setBusy(true);
    setDecideError(null);
    try {
      const result = await chatRequest(`/api/chat/${chatId}/proposals`, { action, ids });
      if (!result.ok) {
        setDecideError(result.error ?? "That could not be applied.");
        // The refusal is about the page's picture of what is pending being
        // stale — a proposal decided in another tab, or one the chat itself
        // replaced while this list was on screen — and the route answers a
        // refusal with the error alone. Without this the card the message is
        // about goes on reading as pending for up to a poll, so the sentence
        // under the button contradicts the row above it and pressing Approve
        // again earns the same refusal. Not awaited: the message is already up
        // and the row it corrects can arrive a moment later.
        void load(chatId);
      } else {
        setSelected(new Set());
        if (result.chat) setChat(result.chat);
      }
    } finally {
      setBusy(false);
    }
  };

  const newChat = async () => {
    setError(null);
    try {
      const res = await fetch("/api/chat", { method: "POST" });
      const data = (await res.json().catch(() => ({}))) as {
        chat?: ChatDTO;
        error?: string;
      };
      // Reported rather than returned from silently: a New chat button that
      // does nothing at all reads as a broken page.
      if (!res.ok || !data.chat) {
        setError(data.error ?? "A new chat could not be started.");
        return;
      }
      setChat(data.chat);
      setSelected(new Set());
      // Same rule the thread list's own switch follows: a refusal names a
      // proposal of the thread being left. It outlives an empty proposals list
      // now that the sentence is drawn without one, so this has to say so.
      setDecideError(null);
      void load(null);
    } catch (err) {
      setError(err instanceof Error ? err.message : String(err));
    }
  };

  const proposals = chat?.proposals ?? [];
  const pending = proposals.filter((p) => p.status === "pending");
  const decided = proposals.filter((p) => p.status !== "pending");
  // What `Select all` may tick, and what it left behind. Every id it does not
  // tick is one the route drops anyway, so this only aligns the number agreed
  // to with the number that happens — seeded at 26 pending, the button read
  // `Approve 26` above a sentence about 26 unattended runs when two of them
  // could never start. `every` rather than a size comparison because the two
  // sets are no longer the same size: with a refused proposal ticked by hand,
  // the button still has to offer Select none.
  const approvable = pending.filter((p) => !approvalRefused(p));
  const refusedCount = pending.length - approvable.length;
  const allSelected =
    approvable.length > 0 && approvable.every((p) => selected.has(p.id));
  const showJump = !atBottom && messageCount > 0;

  // Proposals is always offered, empty or not: it is what the panel is for, and
  // a tab bar that appeared only once the chat had proposed something would
  // move the other two under the reader on the first turn.
  const sideTabs: SegmentedOption<SideTab>[] = [
    { value: "proposals", label: "Proposals" },
    ...(decided.length > 0
      ? [{ value: "decided" as const, label: "Decided" }]
      : []),
    // The current thread is one of these, so a lone conversation used to mean a
    // list with nothing to choose from. It is offered from one now, because the
    // tab is also where the search lives and an install past thirty threads has
    // no other way to reach the thirty-first — the sidebar's list is capped.
    ...(chats.length > 0 ? [{ value: "chats" as const, label: "Chats" }] : []),
  ];
  // Derived rather than corrected in an effect: opening a thread with nothing
  // decided while the Decided tab is selected must fall back on the render that
  // drops the tab, not one frame later.
  const activeSide = sideTabs.some((t) => t.value === side) ? side : "proposals";
  const waitingBadge = pending.length > 0 && (
    <Badge tone="accent">{pending.length} waiting</Badge>
  );

  const lastMessage = messageCount > 0 ? chat?.messages[messageCount - 1] : undefined;
  // A turn that ends badly is written to the row *and* appended to the thread,
  // so rendering both says it twice. This is the belt for the case where only
  // the row carries it — and it belongs at the end of the conversation, where
  // the turn failed, rather than at the top of the page.
  const turnFailure =
    chat?.status === "failed" && chat.error && chat.error !== lastMessage?.text
      ? chat.error
      : null;
  // Which message in the thread is the failure note — see `SYSTEM_EDGE` for
  // what this inference is right and wrong about. Paired with `turnFailure`
  // above on the same comparison, so exactly one of the two draws the ending:
  // the note when the thread carries it, the belt when only the row does.
  const failureMessageId =
    chat?.status === "failed" &&
    lastMessage?.role === "system" &&
    lastMessage.text === chat.error
      ? lastMessage.id
      : null;
  // The words the failed turn was answering, offered back to the composer. They
  // are still in the thread; what is gone is the turn. `at(-1)` over a filter
  // rather than `findLast`, which is ES2023 and this target is ES2022.
  const lastUserMessage =
    chat?.messages.filter((m) => m.role === "user").at(-1) ?? null;
  // The turn started when the server claimed it, not when the thread last
  // moved — see `turnStartInstant`. `Date.now()` is the last resort for a
  // render with no chat at all, which is a render with nothing to draw a clock
  // beside; it reads as "just now" rather than as 1970.
  const waitingSince =
    turnStartInstant(chat?.turnStartedAt, lastMessage?.ts ?? chat?.updatedAt) ??
    Date.now();
  // `thinking` implies a chat, but nothing here narrows the optional, and a
  // ceiling nobody sent is one the page must not state.
  const turnIdleLimitMs = chat?.turnIdleTimeoutMs ?? null;

  // What the click does, counted, above the button that does it. "Approve"
  // alone is a word; this is the sentence a person needs before pressing it.
  //
  // The two kinds are counted apart rather than summed, because approving them
  // does two different things and only one of them spends money: a run
  // proposal starts an unattended agent, a workflow proposal *saves a graph*
  // and starts nothing. A single sentence over both would have to be true of
  // the stronger one, which would claim four agents are about to work when
  // three of the four selections were workflows.
  const chosen = pending.filter((p) => selected.has(p.id));
  const runCount = chosen.filter((p) => p.kind === "run").length;
  const graphCount = chosen.length - runCount;
  const approveConsequence =
    chosen.length === 0
      ? "Approving starts each run under the guards shown on it, and saves each workflow without starting it."
      : [
          runCount === 1
            ? "Approve starts one unattended run that spends real money, under the guards shown on it."
            : runCount > 1
              ? `Approve starts ${runCount} unattended runs that spend real money, under the guards shown on each.`
              : "",
          graphCount === 1
            ? "It saves one workflow without starting it — press Run on the workflow itself when you want it."
            : graphCount > 1
              ? `It saves ${graphCount} workflows without starting them — press Run on each when you want it.`
              : "",
        ]
          .filter(Boolean)
          .join(" ");

  const toggle = (id: string) => {
    setSelected((prev) => {
      const next = new Set(prev);
      if (next.has(id)) next.delete(id);
      else next.add(id);
      return next;
    });
  };

  /**
   * Put a proposal on screen, whichever of the two lists holds it.
   *
   * Scrolled from the click rather than from an effect keyed on the id, because
   * pressing the same link twice has to move the list both times and an effect
   * whose dependency did not change does nothing the second time.
   * `requestAnimationFrame` because the card is usually on the *other* tab and
   * does not exist in the DOM until React has committed the switch above it; a
   * frame that somehow arrives early costs the scroll and not the tab.
   */
  const showProposal = (proposal: ChatProposalDTO) => {
    setSide(proposal.status === "pending" ? "proposals" : "decided");
    requestAnimationFrame(() => {
      document
        .getElementById(proposalAnchorId(proposal.id))
        ?.scrollIntoView({ block: "nearest" });
    });
  };

  /* The page is exactly the pane at `lg`, and nothing on it may make the
     pane scroll. Both boxes in the row below already scroll themselves, so a
     scrollbar out here is one the reader works through *behind* two that are
     doing the same job — and the first thing it pushes past the fold is the
     composer, the one control this page exists to be typed into.

     The shell's column stays `min-h-full`, because every other page depends
     on growing past the pane, so the bound is this page's own — and it is
     two boxes rather than one. The outer takes what the column has left
     over. The inner is taken *out of flow*, which is the half that is not
     obvious: an in-flow box with no height of its own reports its content as
     its intrinsic height, so a long thread grows the column back through the
     very item meant to bound it. Measured in Chromium against this exact
     nesting — `h-full`, `flex-1` with `min-h-0`, `height: 0` with `grow`,
     and `overflow-hidden` all hand the column the whole transcript, and only
     the out-of-flow box does not. It contributes nothing to that
     measurement and simply takes the box it was given, which is the trade
     `Log`'s `pane` size already makes one page over.

     Below `lg` neither half applies and the page composes as it always did:
     the proposals sit *under* the thread, which is a second column of
     content the page is meant to scroll, and both cards keep the bounded
     `max-h-[34rem]` they have there. The wrapper is a flex column at every
     width all the same, so the margins between the header's own blocks stay
     uncollapsed exactly as they were when the shell's column held them. */
  return (
    <div className="relative flex flex-col lg:min-h-0 lg:flex-1">
      <div className="flex flex-col lg:absolute lg:inset-0">
        <div className="mb-3 flex flex-wrap items-center gap-3">
          <h1 className="text-xl font-semibold tracking-tight">Orchestrator</h1>
          {/* Beside the heading rather than under it, and not because it
              matters less. This row's height is already the New chat button's,
              so up to two lines of it are free; the same two lines below the
              heading came straight off the row underneath, which is the one
              holding the list of things to approve — 1.8 of 26 cards at
              1440x900. Same size and colour it had inside the quiet notice,
              one position higher, and the `<strong>` carries the weight the
              notice used to lend it.

              Every width states its own layout and neither overrides the
              other's, so nothing here depends on which order Tailwind emits
              two utilities that set one property in. From `lg`, where the
              split starts and the pane is what runs out, it takes the room
              between the heading and the actions and wraps *inside* the row.
              Below it there is no pane to run out of, so it takes a line of
              its own — last, so that New chat stays where it has always been
              rather than being pushed under a paragraph. Source order is the
              reading order at both. */}
          <p className="text-xs leading-normal text-ink-muted max-lg:order-last max-lg:basis-full lg:min-w-0 lg:flex-1">
            <strong className="font-semibold text-ink">
              Nothing here starts a run.
            </strong>{" "}
            Each proposal waits for you, and then runs under the guards of the
            template it names — never under anything the chat chose.
          </p>
          <div className="ml-auto flex items-center gap-3 max-md:w-full max-md:flex-wrap max-md:gap-y-2">
            {/* What the figure counts is said, because what it leaves out is
                the turn the operator is most likely watching: the CLI reports a
                cost only with its final event, so a turn in flight has spent
                money this number cannot yet see. Unsaid, a total that does not
                move for the length of a long turn reads as a turn that is not
                costing anything. */}
            {chat && chat.costUSD > 0 && (
              <span className="text-xs tabular-nums text-ink-muted max-md:basis-full">
                {fmtUSD(chat.costUSD)} this chat, settled turns only
              </span>
            )}
            {/* Beside it and never added to it. A turn that was cut off — a
                cancel, a timeout, a restart, the install's ceiling — never gets
                a cost from the CLI, so this is what the app priced the tokens
                the CLI *did* report at. Two kinds of number in one figure would
                be a total nobody could act on; separate, "settled" above still
                means settled. */}
            {chat && chat.costEstUSD > 0 && (
              <span className="text-xs tabular-nums text-ink-faint max-md:basis-full">
                + {fmtUSD(chat.costEstUSD)} estimated, turns that were cut off
              </span>
            )}
            <Button
              variant="secondary"
              className="max-md:ml-auto"
              onClick={() => void newChat()}
            >
              New chat
            </Button>
          </div>
        </div>

        {/* Two paragraphs of standing context stood between the heading and a box
            that fills what is left of the pane, and everything they cost came off
            the box — which is how the composer at the foot of it ended up under
            the fold on a short window. What is left here is the half that is read
            once, a press away with its subject named on the summary; the sentence
            that has to be read before anything on this page is pressed did not go
            behind the fold, it went up beside the `<h1>`, where the row it joined
            was already that tall. A fact a decision is approved against is never
            folded however rare it is — what changed is only that keeping it
            visible now costs the box below nothing. */}
        <Notice tone="info" quiet>
          <Disclosure summary="What the chat itself may do, and what its turns cost">
            <p className="mt-2">
              A proposal that names no template runs under the default guard set
              in <Link href="/settings">Settings</Link>.
            </p>
            <p className="mt-2">
              The chat itself runs with no tool restrictions, so it can read, run
              commands and reach GitHub while it works out what to propose; the
              instruction not to do the work, rather than a permission mode, is
              what keeps it out of your checkouts. Its turns spend against the
              same 5-hour window as everything else, and that cost is shown here
              only — never added to a run&rsquo;s, or to the dashboard meters.
            </p>
          </Disclosure>
        </Notice>

        {pollError && <Notice tone="danger">{pollError}</Notice>}
        {error && <Notice tone="danger">{error}</Notice>}

        {/* Takes what the header above it has left of the pane rather than 68vh
            of the window, which is a taller box than the pane it sits in — the
            composer went under the fold and the page grew a second scrollbar
            behind a thread that was already scrolling itself. Everything above
            this row is furniture that neither shrinks nor scrolls, so this is
            the one thing on the page that gives, and the two boxes inside it
            absorb what it gives up by scrolling as they already do.

            Only at `lg`, where the proposals sit *beside* the thread. Stacked
            under it there is a second column of content below the fold and the
            page is meant to scroll, so the card stays a bounded box there.

            `lg:min-h-0` and deliberately no floor. There was a 22rem one, and
            with the page bounded a floor is the last thing left that can push
            the composer out of the pane: on a 700px window with the notice's
            disclosure open and an error banner up there is less than 22rem to
            give, and a row that refuses to go under it overflows the bound
            rather than shrinking inside it — which is the defect, one layer
            further in. What the floor was buying was a thread too short to be
            worth reading; what it cost was the composer, and a short thread
            still scrolls. */}
        {/* The single column is stated rather than left implicit. An implicit
            track is `auto`, which is floored at the content's min-content
            width, so one long path in a message sized this column at 584px
            inside a 358px pane and every card in it was cut off at the right —
            silently, because the shell clips rather than scrolling sideways, so
            nothing that asserts about `scrollWidth` can see it. `lg` already
            spells its own tracks out and is unaffected. */}
        <div className="grid grid-cols-[minmax(0,1fr)] gap-4 lg:min-h-0 lg:flex-1 lg:grid-cols-[minmax(0,1fr)_360px]">
          {/* `max-h` in rem and not vh, for the reason a box inside the pane is
              never sized in viewport units: the pane is the window less the
              toolbar less its own padding less everything above this row, so
              60vh was a cap that could sit either side of the edge depending on
              the window and never on the box it was capping. Both caps are
              released at `lg`, where the row above is what says how tall the
              cards are. */}
          <Card
            emphasis="default"
            /* The 34rem cap is a bounded box for a stacked *window*, and on a
               390px screen it is smaller than the questions and the composer
               inside it: the thread took the shortfall, `flex-1` collapsed it
               to nothing, and the conversation was not on the page at all.
               Below the breakpoint the card is sized by its content and the
               pane scrolls, which is what the stacked layout already does. */
            className="flex max-h-[34rem] min-h-[22rem] flex-col max-md:max-h-none max-md:min-h-0 lg:max-h-none lg:min-h-0"
          >
            <div className="relative min-h-0 flex-1">
              <div
                ref={threadRef}
                onScroll={onScroll}
                /* `h-full` of a content-sized card resolves to `auto`, which
                   would stop this being a scroll container at all and take the
                   jump control, the unseen count and every rule above about
                   what may move the thread with it. A height off `--pane-h`
                   keeps it one and leaves room for the composer under it; the
                   composer's own height is what the 16rem is. It shrinks with
                   the keyboard because `--pane-h` already subtracts it. */
                className="h-full overflow-y-auto pr-1 max-md:h-[calc(var(--pane-h)-16rem)] max-md:min-h-[10rem]"
              >
                {/* `additions` only: the waiting row's elapsed time changes every
                    second inside this region, and the default `additions text`
                    would read the whole thing out again each time. */}
                <div
                  role="log"
                  aria-live="polite"
                  aria-relevant="additions"
                  aria-label="Conversation"
                  className="flex flex-col"
                >
                  {chat === null ? (
                    <div className="py-10 text-center text-sm text-ink-muted">
                      {pollError ? "The conversation could not be loaded." : "Loading…"}
                    </div>
                  ) : messageCount === 0 ? (
                    <div className="px-2 py-10 text-center">
                      <p className="text-sm text-ink">Nothing asked yet</p>
                      <p className="mx-auto mt-1 max-w-[46ch] text-xs leading-normal text-ink-muted">
                        Ask it to look at something — &ldquo;check the open issues
                        on usagefoundry and propose a run for each bug&rdquo;.
                      </p>
                    </div>
                  ) : (
                    items.map((item, i) => {
                      if (item.kind === "questions") {
                        return (
                          <AskedQuestions
                            // The set as asked, so an operator part-way through
                            // typing an answer keeps it across a poll — the ids
                            // do not change when a sibling is answered.
                            key={item.questions[0].id}
                            questions={item.questions}
                            busy={busy}
                            thinking={thinking}
                            turnFailed={chat.status === "failed"}
                            error={answerError}
                            onAnswer={(answers) => void answer(answers)}
                          />
                        );
                      }
                      // Read off the *item* before it and not the message before
                      // it: a question card between two turns of one speaker
                      // means they are no longer one utterance, so the second one
                      // gets its name and its time back.
                      const prev = items[i - 1];
                      return (
                        <Message
                          key={item.message.id}
                          message={item.message}
                          grouped={
                            prev?.kind === "message" &&
                            prev.message.role === item.message.role
                          }
                          systemKind={
                            item.message.id === failureMessageId
                              ? "failure"
                              : "note"
                          }
                        />
                      );
                    })
                  )}

                  {/* What the turn has said so far, drawn above the spinner
                      rather than instead of it: the wait is still a wait, and
                      the elapsed clock beside it is still the only honest
                      progress there is. The text is persisted by the server, so
                      what is on screen here is what would survive the process
                      producing it — which is the whole reason it is a column
                      and not a stream. It becomes an ordinary message when the
                      turn settles, and the DTO nulls this at the same moment so
                      the answer is never drawn twice. */}
                  {thinking && chat?.partialText && (
                    <div className="mt-5 max-w-[70ch] text-sm leading-normal text-ink-muted">
                      <Markdown text={chat.partialText} />
                    </div>
                  )}

                  {thinking && (
                    <Waiting
                      since={waitingSince}
                      heardAt={chat?.turnHeardAt ?? null}
                      idleLimitMs={turnIdleLimitMs}
                      stale={pollError !== null}
                    />
                  )}

                  {turnFailure && (
                    <div className="mt-5 max-w-[70ch] rounded-sm border-l-2 border-l-danger bg-inset px-3 py-2 text-xs leading-normal text-danger">
                      {turnFailure}
                    </div>
                  )}

                  {/* What survives an ending, under it. The button fills the
                      composer and focuses it; it does not post, and that is
                      the whole reason it is allowed — nothing may start a turn
                      but the operator pressing Send, and nothing stranded may
                      be re-asked unattended. `caretTo` is the same mechanism
                      the mention list inserts with. */}
                  {chat?.status === "failed" && lastUserMessage && (
                    <div className="mt-2 flex max-w-[70ch] flex-wrap items-center gap-2 text-xs leading-normal text-ink-muted">
                      Your message is still in the thread.
                      <Button
                        size="compact"
                        variant="secondary"
                        onClick={() => {
                          setDraft(lastUserMessage.text);
                          setCaretTo(lastUserMessage.text.length);
                        }}
                      >
                        Send it again
                      </Button>
                    </div>
                  )}
                </div>
              </div>

              <button
                type="button"
                onClick={() => scrollToLatest(true)}
                aria-hidden={!showJump}
                tabIndex={showJump ? 0 : -1}
                className={`absolute right-3 bottom-3 flex h-8 cursor-pointer items-center gap-1.5 rounded-full border border-line-strong bg-surface px-3 text-xs font-medium text-ink shadow-e2 transition duration-[var(--motion-base)] ease-standard hover:border-ink-faint ${
                  JUMP_STATE[showJump ? "shown" : "hidden"]
                }`}
              >
                <Icon name="chevron-down" size="sm" />
                {unseen > 0 ? `${unseen} new` : "Latest"}
              </button>
            </div>

            {/* Pinned to the foot of the pane: the card is a flex column and the
                thread above it is the only thing that scrolls, so the composer
                stays where the hand expects it however long the conversation
                gets.

                Below the shell's breakpoint the card is not bounded by the pane
                — the standing sentence and the notice above it are most of a
                390px screen, so the card starts below the fold and the composer
                would start below that. `sticky` is what keeps the same promise
                there: it rides the foot of the pane until the card ends. The
                negative margin is only so its own background covers the card's
                bottom padding, which the thread would otherwise scroll through.
                Nothing here reads the keyboard: `--pane-h` and the shell's own
                height already subtract `--keyboard-inset`. */}
            <div className="relative mt-4 border-t border-line pt-4 max-md:sticky max-md:bottom-0 max-md:z-10 max-md:-mb-4 max-md:bg-surface max-md:pb-4">
              {mentionOpen && (
                // Above the composer, because the composer is at the foot of the
                // pane. `mousedown` rather than `click` on a row, with the
                // default prevented: a click would blur the textarea first, and
                // the insertion needs the caret it is about to move.
                <div className="absolute bottom-full left-0 z-10 mb-1 w-80 max-w-full overflow-hidden rounded-lg border border-line bg-surface shadow-e2">
                  <ul id="agent-mentions" role="listbox" aria-label="Saved agents" className="py-1">
                    {matches.map((a, i) => (
                      <li
                        key={a.id}
                        id={`agent-mention-${a.id}`}
                        role="option"
                        aria-selected={i === active}
                        onMouseDown={(e) => {
                          e.preventDefault();
                          insertMention(a.name);
                        }}
                        onMouseEnter={() => setMentionIndex(i)}
                        className={`cursor-pointer px-2.5 py-1.5 ${
                          MENTION_ROW[i === active ? "active" : "idle"]
                        }`}
                      >
                        <span className="block truncate text-xs font-medium text-ink">
                          {a.name}
                          {!a.usable && (
                            <span className="ml-1.5 font-normal text-danger">
                              incomplete
                            </span>
                          )}
                        </span>
                        <span className="block truncate text-2xs text-ink-muted">
                          {a.description}
                        </span>
                      </li>
                    ))}
                  </ul>
                  {/* Enter is named here because it is the one thing about this
                      list that would otherwise be found out by losing a message:
                      it sends, exactly as it does with the list shut. */}
                  <div className="border-t border-line px-2.5 py-1.5 text-2xs text-ink-faint">
                    Tab inserts · Enter still sends
                    {ambientLine && <span className="mt-0.5 block">{ambientLine}</span>}
                  </div>
                </div>
              )}
              <textarea
                ref={composerRef}
                aria-label="Message the orchestrator"
                aria-autocomplete="list"
                aria-expanded={mentionOpen}
                aria-controls={mentionOpen ? "agent-mentions" : undefined}
                aria-activedescendant={
                  mentionOpen && matches[active]
                    ? `agent-mention-${matches[active].id}`
                    : undefined
                }
                // No focus ring of its own. @layer base draws one halo for every
                // focusable thing in the app, and the `outline-none` plus 3px
                // box-shadow that used to be here was the second treatment that
                // rule exists to have none of.
                //
                // `max-md:text-[16px]` for the reason CONTROL_BASE in ui/Field
                // states it: under 16px iOS Safari zooms the page in on focus and
                // never zooms back out. This is the one text control in the app
                // written by hand rather than taken from the kit, so it is the
                // one that has to repeat it.
                className="ui-transition min-h-[4.5rem] w-full resize-none overflow-y-auto rounded-sm border border-line bg-inset px-3 py-2.5 font-sans text-sm max-md:text-[16px] leading-normal text-ink placeholder:text-ink-faint hover:border-line-strong focus:border-accent"
                rows={3}
                placeholder="Ask the orchestrator to look at something and propose runs…"
                value={draft}
                onChange={(e) => {
                  setDraft(e.target.value);
                  readMention(e.target.value, e.target.selectionStart);
                }}
                // Caret moves that are not edits — a click, Home, an arrow key —
                // change which token is under it, so the list has to be read
                // there too or it survives the caret leaving the mention.
                onSelect={(e) =>
                  readMention(
                    e.currentTarget.value,
                    e.currentTarget.selectionStart,
                  )
                }
                // Not on blur alone: a row's `mousedown` prevents the blur, so
                // this only fires when focus really has left the composer.
                onBlur={() => setMention(null)}
                onKeyDown={(e) => {
                  // The mention list gets the keys nothing else here claims, and
                  // **never Enter or ⌘↩**. That is the whole rule: this composer
                  // sends on Enter, so a list that accepted a completion with it
                  // would swallow the send whenever the operator happened to be
                  // at the end of a name — which is exactly when they are most
                  // likely to be finished. Tab inserts instead, the popover says
                  // so, and the send chords fall through untouched below.
                  //
                  // Skipped entirely mid-composition: an IME owns the keyboard
                  // while a candidate is up, and a layer that took Tab or the
                  // arrows from it would break the candidate list rather than
                  // this one.
                  if (mentionOpen && !e.nativeEvent.isComposing) {
                    if (e.key === "ArrowDown") {
                      e.preventDefault();
                      setMentionIndex((active + 1) % matches.length);
                      return;
                    }
                    if (e.key === "ArrowUp") {
                      e.preventDefault();
                      setMentionIndex((active - 1 + matches.length) % matches.length);
                      return;
                    }
                    if (e.key === "Tab" && !e.shiftKey) {
                      e.preventDefault();
                      insertMention(matches[active].name);
                      return;
                    }
                    if (e.key === "Escape") {
                      // Dismissed for this token only, so typing more of the
                      // name does not reopen what was just shut. Consumed,
                      // because closing the list is what Esc means here — the
                      // shell binds it to nothing and there is no dialog under
                      // this to fall through to.
                      e.preventDefault();
                      setMentionClosed(mention?.start ?? null);
                      return;
                    }
                  }
                  // Two ways to send and one of them is the platform's. ⌘↩ is the
                  // commit chord this app already uses on the run form, and the
                  // shell's keyboard layer deliberately binds it to nothing so a
                  // field's own can never be swallowed. Enter stays, because it is
                  // what a conversation is typed with everywhere else.
                  //
                  // `isComposing` is the one that is not obvious: an IME takes
                  // Enter to accept the candidate it is showing, and sending there
                  // posts half a word. It cannot apply to ⌘↩, which is why that
                  // branch is tested first.
                  if (e.key !== "Enter") return;
                  if (e.metaKey) {
                    e.preventDefault();
                    void send();
                    return;
                  }
                  if (e.shiftKey || e.nativeEvent.isComposing) return;
                  e.preventDefault();
                  void send();
                }}
              />
              <ButtonRow className="mt-2">
                {/* The composer is deliberately *not* disabled or pre-filled
                    while a question is open: the chat is `idle`, there is no
                    child, and the operator may say anything they like. What it
                    owes them is what saying it does — an ordinary message is the
                    operator declining and redirecting, and the server closes
                    every open question as overtaken in the same statement that
                    records it. Left unsaid, a question answered in prose here
                    reads as still waiting, and the card stays clickable a week
                    later to start a billed turn about a conversation nothing in
                    the thread is about any more. */}
                <span className="mr-auto text-xs text-ink-faint">
                  {thinking
                    ? "Stop ends this turn and signals the process answering it"
                    : openQuestions > 0
                      ? `Answer above, or send a message — sending closes the ${
                          openQuestions === 1 ? "question" : "questions"
                        } as overtaken`
                      : "⌘↩ or Enter sends · Shift+Enter for a new line"}
                </span>
                {thinking && (
                  <Button variant="secondary" disabled={busy} onClick={() => void stop()}>
                    Stop
                  </Button>
                )}
                <Button
                  onClick={() => void send()}
                  disabled={thinking || busy || !draft.trim()}
                  aria-keyshortcuts="Meta+Enter"
                >
                  Send
                  <span aria-hidden="true" className="text-xs opacity-70">
                    ⌘↩
                  </span>
                </Button>
              </ButtonRow>
              {sendError && <Hint tone="danger">{sendError}</Hint>}
            </div>
          </Card>

          {/* One box the height of the row, holding one list at a time. Three
              stacked cards each grew without limit, so the column was taller than
              the pane whatever the pane did — and the two lists nobody is acting
              on were what you scrolled past to reach the one you were.

              The card is the scroll container's parent rather than the scroll
              container: what scrolls is the list, so the tab bar stays on screen
              and so does the row that approves things. */}
          <Card
            emphasis={PROPOSALS_EMPHASIS[pending.length > 0 ? "waiting" : "clear"]}
            className="flex max-h-[34rem] flex-col lg:max-h-none lg:min-h-0"
          >
            {/* A radiogroup with one option is a chip that does nothing, which is
                what a fresh install would open on — so until there is a second
                list to reach, this is the title it always was.

                The count sits beside the control rather than on the Proposals
                segment either way: a number only visible from the tab it belongs
                to is one nobody reads from the other two, and this is the one on
                the page that means somebody is waiting on a decision. */}
            {sideTabs.length > 1 ? (
              <div className="mb-3 flex flex-wrap items-center gap-2">
                <SegmentedControl
                  label="What to show beside the conversation"
                  options={sideTabs}
                  value={activeSide}
                  onChange={setSide}
                />
                {waitingBadge}
              </div>
            ) : (
              <CardTitle>
                Proposals
                {waitingBadge}
              </CardTitle>
            )}

            <div className="min-h-0 flex-1 overflow-y-auto pr-1">
              {activeSide === "proposals" &&
                (pending.length === 0 ? (
                  <Empty>Nothing waiting for approval.</Empty>
                ) : (
                  // One grouped box, hairlines between the rows: a proposal is an
                  // object in a list of objects, and the stack of separately
                  // bordered cards this replaces read as five unrelated panels in
                  // a 360px column.
                  <ListGroup>
                    {pending.map((p) => (
                      <Proposal
                        key={p.id}
                        proposal={p}
                        checked={selected.has(p.id)}
                        onToggle={() => toggle(p.id)}
                      />
                    ))}
                  </ListGroup>
                ))}

              {activeSide === "decided" && (
                <div className="flex flex-col divide-y divide-line">
                  {decided
                    .slice()
                    .reverse()
                    .map((p) => {
                      // Resolved here rather than carried on the DTO: the row
                      // holds an id, and the card it names is already in this
                      // thread's own list. Null where it is not — a swept row,
                      // or a `superseded_by` pointing outside what was sent.
                      const replacement =
                        proposals.find((q) => q.id === p.supersededBy) ?? null;
                      return (
                        <Decided
                          key={p.id}
                          proposal={p}
                          replacement={replacement}
                          onShowReplacement={() => {
                            if (replacement) showProposal(replacement);
                          }}
                        />
                      );
                    })}
                </div>
              )}

              {/* The current thread is in this list rather than filtered out of
                  it, because "which one am I in" is the first thing the list has
                  to answer and a row missing from a list cannot answer it. */}
              {activeSide === "chats" && (
                <div className="flex flex-col gap-0.5">
                  {/* The list above is the newest thirty and is re-read on every
                      poll; this is the only way to reach the thirty-first. It
                      searches titles and message text, because a title is
                      written from the opening line and the conversation somebody
                      is looking for is usually remembered by what was decided
                      in it. */}
                  <form
                    className="mb-1.5"
                    onSubmit={(e) => {
                      e.preventDefault();
                      void search(chatQuery);
                    }}
                  >
                    <Input
                      type="search"
                      value={chatQuery}
                      placeholder="Search every thread"
                      aria-label="Search every thread"
                      onChange={(e) => {
                        setChatQuery(e.target.value);
                        if (!e.target.value.trim()) {
                          setFound(null);
                          setFindError(null);
                        }
                      }}
                    />
                  </form>
                  {findError && (
                    <Notice tone="warn" className="mb-1.5">
                      {findError}
                    </Notice>
                  )}
                  {found && (
                    <Hint>
                      {found.total === 0
                        ? "No thread matches"
                        : `${found.chats.length} of ${found.total} matching thread${
                            found.total === 1 ? "" : "s"
                          }`}
                    </Hint>
                  )}
                  {(found ? found.chats : chats).map((c) => (
                    <ChatRow
                      key={c.id}
                      entry={c}
                      current={c.id === chatId}
                      onOpen={() => {
                        // Ticked ids belong to the thread they were ticked in.
                        // `newChat` clears them for the same reason; carried
                        // over, they describe proposals not on screen and are
                        // sent to a chat that has never held them.
                        setSelected(new Set());
                        setDecideError(null);
                        // Same rule: a refusal names a question of the thread
                        // being left, and carried over it annotates a card in a
                        // conversation it was never about.
                        setAnswerError(null);
                        void load(c.id);
                      }}
                    />
                  ))}
                  {found && found.chats.length < found.total && (
                    <Button
                      variant="ghost"
                      className="mt-1.5"
                      busy={finding}
                      onClick={() => void search(found.q, found.chats.length)}
                    >
                      More
                    </Button>
                  )}
                </div>
              )}
            </div>

            {/* Outside the scroll region: what the click starts, counted, has to
                be on screen beside the button that starts it — a twentieth
                proposal must not push the sentence off the top of the list it is
                about. */}
            {activeSide === "proposals" && pending.length > 0 && (
              <div className="mt-3 shrink-0 border-t border-line pt-3">
                <Hint>
                  {approveConsequence} Runs beyond the concurrency limit queue
                  rather than being refused.
                </Hint>
                {/* The default action at the right edge, which is where this
                    platform puts it and where every sheet in this app already
                    puts it. Select all is not a decision about the work, so it
                    sits at the other end as a ghost. */}
                <ButtonRow className="mt-3 max-md:gap-x-6">
                  <Button
                    variant="ghost"
                    disabled={busy}
                    onClick={() =>
                      setSelected(
                        allSelected
                          ? new Set()
                          : new Set(approvable.map((p) => p.id)),
                      )
                    }
                  >
                    {/* Said on the control rather than left to the cards,
                        because a selection that quietly came up short is
                        indistinguishable from a list that was always that
                        long. The label grows at the *left* end of the row, so
                        a poll that adds a refused proposal moves nothing:
                        Reject and Approve are held at the right by `ml-auto`.

                        The count and not the reason, which is the one thing
                        this parenthesis is not room for. Measured in Chromium
                        against this column: the row fits a ghost of about
                        150px beside Reject and Approve and wraps to two lines
                        past it, and the wrap costs the list under it 44px —
                        more than moving the standing notice's sentence up
                        beside the `<h1>` just gave it back. "2 cannot be
                        approved" is 218px and buys a sentence the two cards
                        it is about already carry in red. */}
                    {allSelected
                      ? "Select none"
                      : refusedCount > 0
                        ? `Select all (skips ${refusedCount})`
                        : "Select all"}
                  </Button>
                  <Button
                    variant="secondary"
                    className="ml-auto"
                    disabled={busy || selected.size === 0}
                    onClick={() => void decide("reject", [...selected])}
                  >
                    Reject
                  </Button>
                  <Button
                    disabled={busy || selected.size === 0}
                    onClick={() => void decide("approve", [...selected])}
                  >
                    {selected.size > 0 ? `Approve ${selected.size}` : "Approve"}
                  </Button>
                </ButtonRow>
              </div>
            )}

            {/* The row goes when there is nothing left to decide and the refusal
                must not go with it. Approving the last pending card and being
                refused — it was decided in another tab, or the chat replaced it
                while this list was on screen — empties `pending` on the answer
                that follows, and drawn inside the row above the sentence was
                unmounted by the very refresh it was about: the operator pressed
                Approve, watched the card disappear and was told nothing. So it is
                gated on itself, and takes the rule and the gap the row would have
                had when the row is not there to give it one. */}
            {activeSide === "proposals" && decideError && (
              <div
                className={`shrink-0 ${
                  pending.length > 0 ? "mt-1" : "mt-3 border-t border-line pt-3"
                }`}
              >
                <Hint tone="danger">{decideError}</Hint>
              </div>
            )}
          </Card>
        </div>
      </div>
    </div>
  );
}

/**
 * One turn.
 *
 * `system` is this app speaking, not the model — a refused tool call, an
 * approval outcome, a failure. Styled apart from `assistant` on purpose: a
 * sentence about what the app did, rendered as though the model said it, is a
 * sentence the operator will later attribute to the wrong party.
 *
 * **Who is speaking is carried by structure, not by colour.** The answer is the
 * pane: plain prose at a readable measure, with nothing drawn round it, because
 * it is what the reader came for. The operator's own words are a bezelled block
 * pulled to the right — a raised chip on a neutral surface, the same treatment
 * every other secondary control in this app wears. It used to be an
 * accent-tinted bubble, which is the web-chat idiom and which spent the app's
 * one accent on saying "a human typed this" — a fact the position and the label
 * already carry, and one that never needs the emphasis a tint claims for it.
 *
 * Only the first turn of a run gets a name and a time: consecutive turns from
 * one speaker are one utterance interrupted by a newline, and repeating the
 * label says nothing.
 */
function Message({
  message,
  grouped,
  systemKind,
}: {
  message: ChatMessageDTO;
  grouped: boolean;
  /** Which kind of `system` turn this is. Nothing else reads it. */
  systemKind: "note" | "failure";
}) {
  const { role, text, ts } = message;

  if (role === "system") {
    return (
      // The kit's quiet notice, in the thread's own rhythm: a hairline box with
      // a leading edge that says which kind it is. Not a `Notice`, only because
      // that component carries a margin of its own that would fight the run
      // spacing here.
      <div
        className={`${
          grouped ? "mt-1.5" : "mt-5"
        } max-w-[70ch] rounded-sm border border-line border-l-[3px] bg-inset px-3 py-2 text-xs leading-normal first:mt-0 ${
          SYSTEM_EDGE[systemKind]
        }`}
      >
        {text}
      </div>
    );
  }

  if (role === "assistant") {
    return (
      <div className={`${grouped ? "mt-2.5" : "mt-5"} max-w-[70ch] first:mt-0`}>
        {!grouped && <Speaker name="Orchestrator" ts={ts} />}
        {/* Markdown for the model's half only. The operator's own text is left
            exactly as typed — an asterisk they meant is not emphasis. */}
        <Markdown text={text} />
      </div>
    );
  }

  return (
    <div
      className={`${grouped ? "mt-1.5" : "mt-5"} flex flex-col items-end first:mt-0`}
    >
      {!grouped && <Speaker name="You" ts={ts} />}
      <div className="max-w-[85%] rounded-lg border border-line bg-bezel px-3 py-2 text-sm leading-normal whitespace-pre-wrap text-ink shadow-e1 [overflow-wrap:anywhere]">
        {text}
      </div>
    </div>
  );
}

/**
 * Who, and when.
 *
 * Sentence case at a weight step rather than 11px uppercase with tracking — the
 * same correction `CardTitle` documents. macOS does not shout a label, and a
 * conversation is the last place to start.
 */
function Speaker({ name, ts }: { name: string; ts: number }) {
  return (
    <div className="mb-1 flex items-baseline gap-2 text-xs">
      <span className="font-semibold text-ink">{name}</span>
      <time
        dateTime={new Date(ts).toISOString()}
        title={fmtDateTime(ts)}
        className="tabular-nums text-ink-faint"
      >
        {fmtRelative(ts)}
      </time>
    </div>
  );
}

/**
 * The wait between sending and the first word.
 *
 * Legible frozen, which is the whole constraint: `@layer base` flattens every
 * animation to one frame under `prefers-reduced-motion`, so a busy state that
 * only exists while it moves is a busy state half the operators never see. What
 * says "working" here is a word, a ring and a clock — the ring stops turning
 * and the other two are unaffected. Nothing claims to know how far through the
 * turn is, because nothing does; the elapsed time is the only real progress
 * there is, and a bar would be an invention.
 *
 * **The ceiling is not that bar by another name, and it is no longer a ceiling
 * on the clock beside it.** The server bounds *silence* rather than duration:
 * a turn may run for as long as it keeps producing something, and what gets
 * stopped is a turn nothing is left of. So the clause reports the quiet, which
 * is a fact the operator can act on — a turn that answered four seconds ago is
 * working, and one that has said nothing for eleven minutes is the reason this
 * bound exists. "of up to 15 min" against the elapsed time would be the one
 * number on this page that is simply false.
 *
 * Two figures rather than one, and they answer different questions: how long
 * this has been going, and whether anything is still coming. The second is
 * stated from the first second rather than past a threshold, because it is the
 * operator's whole basis for deciding whether to wait and it is worth least at
 * the moment they have already waited. Past the bound the clause stops being a
 * ceiling and becomes what is being done about the turn: the sweeper runs every
 * 30s against a 60s margin, so an overrun is a state this page reaches rather
 * than a limit case.
 *
 * `role="status"` holds the word alone — the clocks beside it are hidden from
 * assistive tech, or the turn would be announced once a second.
 */
function Waiting({
  since,
  heardAt,
  idleLimitMs,
  stale,
}: {
  since: number;
  /** When the turn last said anything, which is what the bound is measured on. */
  heardAt: number | null;
  idleLimitMs: number | null;
  stale: boolean;
}) {
  const [now, setNow] = useState(() => Date.now());

  useEffect(() => {
    const t = setInterval(() => setNow(Date.now()), 1_000);
    return () => clearInterval(t);
  }, []);

  // `thinking` is only ever as fresh as the last poll that worked, so once one
  // has failed this may no longer be true.
  if (stale) {
    return (
      <div className="mt-5 max-w-[70ch] text-xs leading-normal text-warn">
        Was thinking when the last refresh failed — state unknown.
      </div>
    );
  }

  const elapsed = Math.max(0, now - since);
  const quiet = Math.max(0, now - (heardAt ?? since));
  const limitMin = idleLimitMs === null ? null : Math.round(idleLimitMs / 60_000);

  return (
    <div className="mt-5 flex flex-wrap items-center gap-2">
      <Spinner />
      <span role="status" className="text-xs font-medium text-ink-muted">
        Thinking…
      </span>
      <span aria-hidden="true" className="text-2xs tabular-nums text-ink-faint">
        {fmtDuration(elapsed)}
      </span>
      {idleLimitMs !== null && (
        <span className="text-2xs text-ink-faint">
          {quiet < idleLimitMs
            ? `last output ${fmtDuration(quiet)} ago; stopped after ${limitMin} min of silence`
            : `silent for ${fmtDuration(quiet)}, past the ${limitMin}-minute limit; being stopped`}
        </span>
      )}
    </div>
  );
}

/**
 * What the chat asked the operator, and what became of it.
 *
 * **It is in the transcript rather than in the panel beside it, and that is the
 * split this page is built on.** The right-hand list is work waiting to be
 * approved and costs nothing until a person clicks; a question is a sentence,
 * answering it starts a chat turn, and it belongs in the half of the page where
 * the other sentences are. It is drawn as an object for `Proposal`'s reason —
 * it has controls on it — but it is deliberately not a `Card`: `emphasis`
 * carries padding as well as elevation, and this box is inside the scrolled
 * conversation, which is the one region on this page that must not re-pad
 * itself under a reader's hands while it polls.
 *
 * **A settled question stays.** Answered or overtaken, it keeps its place above
 * the message that settled it, because a card that disappeared when it was
 * answered reads as a question nobody was ever asked — and the message beside
 * it, which quotes each question above its answer, then reads as text that
 * arrived from nowhere. `superseded` is drawn as neither a failure nor an
 * answer: the operator said something else, which *is* an answer, and drawing
 * it in danger red would report a redirection as a fault.
 *
 * **When a click sends, and when it only fills something in.** A choice sends
 * on one press whenever it is the last question open — that is the whole point
 * of offering buttons, and with nothing else open there is nothing the send can
 * take with it. With siblings still open it cannot, because the answer message
 * settles the set and supersedes whatever it did not name: one hasty press
 * would close two questions the operator was still reading. So above one, the
 * choices fill in and the row's own button sends them together, and the card
 * says as much rather than leaving it to be found out.
 */
function AskedQuestions({
  questions,
  busy,
  thinking,
  turnFailed,
  error,
  onAnswer,
}: {
  questions: ChatQuestionDTO[];
  busy: boolean;
  thinking: boolean;
  /** The chat's last turn ended badly. A question outlives that; say so. */
  turnFailed: boolean;
  error: string | null;
  onAnswer: (answers: Array<{ id: string; answer: string }>) => void;
}) {
  // Keyed by question id and local to the card, so a poll landing mid-sentence
  // re-renders around the draft rather than through it.
  const [drafts, setDrafts] = useState<Record<string, string>>({});

  const open = questions.filter((q) => q.status === "pending");
  // Out while a turn is in flight, and said in words below. `sendChatMessage`
  // refuses a second billed child on one conversation, so a press here during a
  // turn is a refusal — and a question can be open while its own turn is still
  // running, since `ask_operator` records the row and returns rather than
  // blocking on the click.
  const disabled = busy || thinking;

  const submit = (override?: { id: string; answer: string }) => {
    const answers = open.flatMap((q) => {
      const value = (
        override?.id === q.id ? override.answer : (drafts[q.id] ?? "")
      ).trim();
      return value ? [{ id: q.id, answer: value }] : [];
    });
    if (answers.length === 0) return;
    onAnswer(answers);
  };

  const choose = (id: string, choice: string) => {
    if (open.length === 1) {
      submit({ id, answer: choice });
      return;
    }
    setDrafts((d) => ({ ...d, [id]: choice }));
  };

  // Nothing to press it with where every open question is a shortlist and there
  // is only one of them — the choices are the button, and a second one that
  // never has anything to send is a control that reads as broken.
  const sends = open.length > 1 || open.some((q) => q.allowText);
  const ready = open.some((q) => (drafts[q.id] ?? "").trim().length > 0);

  return (
    <div
      className={`mt-5 max-w-[70ch] rounded-sm border border-line border-l-[3px] bg-inset px-3 py-2.5 first:mt-0 ${
        QUESTION_EDGE[open.length > 0 ? "open" : "settled"]
      }`}
    >
      <div className="mb-2 flex flex-wrap items-baseline gap-2">
        <span className="text-xs font-semibold text-ink">
          {open.length > 0 ? "Waiting on you" : "Asked you"}
        </span>
        {open.length > 1 && (
          <span className="text-2xs text-ink-muted">
            {open.length} questions, answered together — anything left blank is
            sent as not answered
          </span>
        )}
      </div>

      {/* Hairlines between them, `Decided`'s construction one card over. A
          question with a text field under it and the next question's sentence
          below that is three blocks at one spacing, and the field then reads as
          belonging to whichever of the two the eye reached first — which is a
          typed answer filed against the wrong question. A rule is what says
          where one decision ends. It costs nothing with a single question,
          which is the common case: `divide-y` draws between siblings. */}
      <div className="flex flex-col divide-y divide-line">
        {questions.map((q) => (
          <div key={q.id} className="py-3 first:pt-0 last:pb-0">
            {/* The model writes this and reaches for a path or a flag in it
                often enough that one unbroken word is wider than a 390px
                column, which takes the row and everything beside it with it.
                `anywhere` for the reason `Markdown.tsx` gives: it is the one
                that comes off the intrinsic minimum too. */}
            <p className="text-sm leading-normal text-ink max-md:[overflow-wrap:anywhere]">
              {q.question}
            </p>

            {q.status === "answered" && (
              <p className="mt-1 text-xs leading-normal text-ink-muted">
                You answered{" "}
                <span className="font-medium text-ink">{q.answer}</span>
              </p>
            )}
            {q.status === "superseded" && (
              <p className="mt-1 text-xs leading-normal text-ink-muted">
                Overtaken by what you said next.
              </p>
            )}

            {q.status === "pending" && (
              <>
                {q.choices.length > 0 && (
                  <ButtonRow className="mt-2">
                    {q.choices.map((choice) => (
                      <Button
                        key={choice}
                        size="compact"
                        variant={
                          CHOICE_VARIANT[
                            drafts[q.id] === choice ? "chosen" : "offered"
                          ]
                        }
                        // A toggle only where it is one. With this the last open
                        // question, the press is the answer and announcing it as
                        // pressed would describe a control that is already gone.
                        aria-pressed={
                          open.length > 1 ? drafts[q.id] === choice : undefined
                        }
                        disabled={disabled}
                        onClick={() => choose(q.id, choice)}
                      >
                        {choice}
                      </Button>
                    ))}
                  </ButtonRow>
                )}

                {q.allowText && (
                  // A kit control, not a hand-written one: below `md`, iOS Safari
                  // zooms the page in on any text control under 16px and never
                  // zooms back out, and `Input` is where that floor lives. The
                  // composer is this app's one hand-written exception and is not
                  // a precedent for a second.
                  <Input
                    className="mt-2"
                    aria-label={q.question}
                    placeholder={
                      q.choices.length > 0 ? "…or type an answer" : "Your answer"
                    }
                    value={drafts[q.id] ?? ""}
                    disabled={disabled}
                    onChange={(e) =>
                      setDrafts((d) => ({ ...d, [q.id]: e.target.value }))
                    }
                    onKeyDown={(e) => {
                      // The composer's chord, in the one other field on this page
                      // that sends. No Shift+Enter branch: this is a single-line
                      // input and there is no newline to make.
                      if (e.key !== "Enter" || e.nativeEvent.isComposing) return;
                      e.preventDefault();
                      if (!disabled) submit();
                    }}
                  />
                )}

                {q.choices.length === 0 && !q.allowText && (
                  // Reachable rather than theoretical: `questionChoices` answers
                  // an unreadable `choices` column with none, which is the
                  // reading that fails safe — and it leaves a question with
                  // nothing on it to press. Said, because the way out is a
                  // different control on a different part of the page.
                  <p className="mt-1 text-2xs leading-normal text-warn">
                    This question offers nothing to press and no way to type an
                    answer. Reply in the composer instead, which closes it.
                  </p>
                )}
              </>
            )}
          </div>
        ))}
      </div>

      {open.length > 0 && (
        <>
          {sends && (
            <ButtonRow className="mt-3">
              <Button
                size="compact"
                disabled={disabled || !ready}
                onClick={() => submit()}
              >
                {open.length > 1 ? `Answer ${open.length}` : "Answer"}
              </Button>
            </ButtonRow>
          )}
          {thinking && (
            <p className="mt-2 text-2xs leading-normal text-ink-faint">
              This turn is still working — you can answer once it finishes.
            </p>
          )}
          {/* The counterpart, and the fact that decides whether the operator
              answers or starts over: a question is a row and survives every way
              a turn can die, so the card is still live — but the child that
              asked is gone, and answering spawns a new one through
              `sendChatMessage` like any other message. */}
          {turnFailed && (
            <p className="mt-2 text-2xs leading-normal text-ink-faint">
              The turn that asked this was stopped. Answering starts a new one.
            </p>
          )}
          {/* Inside the open branch, because the page holds one answer error
              and every question card in the thread is handed it. Drawn
              unconditionally, a refusal would also appear under every settled
              pair further up — a sentence about a press, against a question
              decided last week. */}
          {error && <Hint tone="danger">{error}</Hint>}
        </>
      )}
    </div>
  );
}

/**
 * A proposal waiting on a decision.
 *
 * Drawn as an object rather than as text: it names a folder and a guard set,
 * and approving it starts an unattended agent that spends real money in that
 * folder. The two facts that decide the answer — where, and under whose rules —
 * are the last line, each behind its own mark so they cannot be read as one
 * string.
 */
function Proposal({
  proposal,
  checked,
  onToggle,
}: {
  proposal: ChatProposalDTO;
  checked: boolean;
  onToggle: () => void;
}) {
  const workflow = proposal.kind === "workflow";
  const missing = proposal.guardsSource === "missing";
  const folder = proposal.folderLabel ?? "folder from the template";
  // Named from what is actually behind it rather than from a fixed phrase: a
  // summary promising a prompt on a card that has none is a fold nobody opens
  // twice, and `Disclosure`'s own note says a fold that does not say what is
  // inside is one nobody opens at all.
  const folded = [
    "Full task",
    proposal.guardsDetail ? "guards" : null,
    proposal.promptOverride !== null ? "prompt" : null,
  ]
    .filter(Boolean)
    .join(", ");

  return (
    <label
      id={proposalAnchorId(proposal.id)}
      // `mb-0 font-normal` for the same reason ChatRow names a background: the
      // legacy sheet still gives every `label` a bottom margin and 500 weight.
      // The end rows take the group's corners, because the wash would otherwise
      // square off a box that `ListGroup` deliberately does not clip.
      className={`ui-transition mb-0 flex cursor-pointer gap-2.5 p-3 font-normal first:rounded-t-lg last:rounded-b-lg ${
        PROPOSAL_ROW[checked ? "selected" : "idle"]
      }`}
    >
      <input
        type="checkbox"
        checked={checked}
        onChange={onToggle}
        aria-label={`Select “${proposal.title}”`}
        className="mt-0.5 size-4 shrink-0 accent-tint"
      />
      <div className="min-w-0 flex-1">
        <div className="flex items-start gap-2">
          <div className="min-w-0 flex-1 text-sm leading-snug font-semibold text-ink">
            {proposal.title}
          </div>
          {/* The chat's own label for this proposal, which is the name the
              dependency line at the foot of a *sibling* card prints. Without it
              on a card, "Starts after `auth-fix`" names something that appears
              nowhere on the page and the instruction beside it — tick both — has
              no second thing to tick. Mono and lower case because that line
              prints it that way and a `Badge` would upper-case it: a label that
              reads differently in the two places it appears is not one a reader
              can match. */}
          {proposal.specId && (
            <span className="mono shrink-0 rounded-sm bg-inset px-1 py-0.5 text-2xs text-ink-muted">
              {proposal.specId}
            </span>
          )}
          {workflow && <Badge tone="neutral">workflow</Badge>}
        </div>
        <p className="mt-1 line-clamp-3 text-xs leading-normal text-ink-muted">
          {proposal.task}
        </p>

        {workflow ? (
          <ProposedGraph proposal={proposal} />
        ) : (
          <div className="mt-2 flex flex-wrap items-center gap-x-3 gap-y-1 text-2xs text-ink-muted">
            <span className="inline-flex min-w-0 max-w-full items-center gap-1" title={folder}>
              <Icon name="folder" size="sm" />
              <span className="truncate">{folder}</span>
            </span>
            {/* The one fact in this row that wraps rather than truncating, and
                the folder beside it is why the difference is worth stating: a
                press of Approve is approved against this guard set, so it is a
                fact a decision is taken on — visible with no interaction, and
                a hover title is not a way of reading it at all on touch. The
                row already wraps, so the whole set costs a second line and
                moves nothing. A folder path is context and may still be
                clipped. */}
            <span
              className={`inline-flex min-w-0 max-w-full items-center gap-1 ${
                GUARD_TONE[missing ? "missing" : "set"]
              }`}
            >
              <Icon name="guard" size="sm" />
              <span>{missing ? "template deleted" : proposal.guardsLabel}</span>
            </span>
            {/* Outside the guard mark and never inside it. The agent is what
                the run will be *started as*, which is a larger fact than the
                delegation this used to name — and still not a guard: it carries
                no tool list and no permission mode, so a phrase under the
                shield would claim it bounds something. */}
            {(proposal.agentName || proposal.agentMissing) && (
              <span
                className={`inline-flex min-w-0 max-w-full items-center gap-1 ${
                  GUARD_TONE[proposal.agentMissing ? "missing" : "set"]
                }`}
              >
                {/* Its own glyph, and emphatically not the guard's. The row
                    read icon, icon, bare text — so the two facts that carry a
                    mark looked like the row and this one looked like a
                    remainder. `agents` is the pane's own glyph, which is where
                    a definition for this name would be found. */}
                <Icon name="agents" size="sm" />
                <span className="truncate">
                  {proposal.agentName
                    ? `as ${proposal.agentName}`
                    : "agent deleted"}
                </span>
              </span>
            )}
            {/* The task on the board this proposal came off. Outside the guard
                mark for the agent's reason and one step weaker than it: an
                agent decides who the run is, where this decides nothing at all
                — it records what prompted the work. So it is drawn in the row's
                own muted grey with no tone, because a toned phrase here would
                read as a fact the click acts on, and the click does not: a task
                deleted before the operator presses Approve still starts the run.
                `for` rather than `on` or `as`, since the two neighbouring
                phrases already own those words. */}
            {proposal.taskId && (
              <span className="inline-flex min-w-0 max-w-full items-center gap-1">
                <Icon name="taskboard" size="sm" />
                <span className="truncate">
                  {proposal.taskTitle
                    ? `for “${proposal.taskTitle}”${
                        proposal.taskStatus && proposal.taskStatus !== "open"
                          ? ` (${proposal.taskStatus})`
                          : ""
                      }`
                    : "for a task since deleted"}
                </span>
              </span>
            )}
            {/* The model the chat named, drawn for the reason an untemplated
                card spells its guards out: values on a card are a promise, and
                this one displaces the operator's own default. Outside the
                guard mark and glyphless — `IconName` has nothing in it that
                means a model, and the shield is the one mark ruled out, since
                a model bounds strictly nothing.

                Only where the proposal named one. Where it did not, the run
                takes the template's model or the operator's default, and a row
                asserting either would be this card promising a value it never
                chose and cannot see change. */}
            {proposal.model && (
              <span className="min-w-0 max-w-full truncate">
                on <span className="mono">{proposal.model}</span>
              </span>
            )}
            {/* The model rewrote the operator's own words, and this said so in
                the same muted grey as the folder beside it — the least visible
                fact on the card and the one a person is most likely to want
                back. Toned and weighted rather than given a glyph: `IconName`
                is a closed union with no warning or edit mark in it, and the
                shield is ruled out for the reason the agent phrase above is
                kept outside it. The text is unchanged and stays in this row. */}
            {proposal.promptOverride !== null && (
              <span className="font-medium text-warn">prompt rewritten</span>
            )}
          </div>
        )}

        {/* Shown rather than only acted on: a dependency that did not survive
            approval reads exactly like one that was never asked for, and the
            two agents then work in the same checkout in whatever order the
            queue felt like. It also says the thing the operator has to *do* —
            tick both, or the later one is failed by name. */}
        {proposal.dependsOn.length > 0 && (
          <p className="mt-2 text-2xs leading-normal text-ink-muted">
            Starts after{" "}
            {proposal.dependsOn.map((d, i) => (
              <span key={d.label}>
                {i > 0 && " and "}
                <span className="mono">{d.label}</span>
                {d.edge === "on-success" ? " (only if it succeeds)" : " (either way)"}
                {d.continueBranch && ", on its branch"}
              </span>
            ))}
            . Approve them together, or this one is not started.
          </p>
        )}

        {missing && !workflow && (
          <p className="mt-2 text-2xs leading-normal font-medium text-danger">
            The template this names has been deleted, so approving it will be
            refused.
          </p>
        )}

        {/* Said in full rather than left to the mark above, because the two
            ways of being unusable read differently and only one of them is
            about deletion: an agent missing its description or its prompt is
            one Claude Code will not register, so a run started as it would
            fail the moment it spawned. */}
        {proposal.agentMissing && !workflow && (
          <p className="mt-2 text-2xs leading-normal font-medium text-danger">
            {proposal.agentName
              ? `The “${proposal.agentName}” agent is missing its description or its prompt, so approving this will be refused.`
              : "The agent this names has been deleted, so approving it will be refused."}
          </p>
        )}

        {/* What is being approved is the task, and it is the one field on this
            card that is clipped — 162px of text in a 54px box, with no way to
            read the rest without leaving the page. This is that way, and it is
            a fold rather than a `title` for the reason the guard mark above
            states for itself: a hover title is not a way of reading anything on
            touch.

            Closed, and the geometry is the argument rather than a preference.
            The seeded batch measured 178.5px a card and 1.8 cards of 26 visible
            at 1440×900, where un-clipping the task inline takes a card to ~290px
            and the list to under one — so un-hiding it here would make a long
            batch worse rather than better. What this changes is that the answer
            exists somewhere the operator can reach without leaving the page; a
            reader who does not open it approves on exactly what they had before,
            which is the honest limit of it.

            Inside the `<label>` and safe there: `details` is interactive
            content, so a label's activation behaviour skips a press on the
            summary and anything under it. Measured in Chromium against this
            nesting — the fold opens and the checkbox does not move. */}
        <Disclosure className="mt-2 text-2xs text-ink-muted" summary={folded}>
          <div className="mt-1.5 flex flex-col gap-2 border-l border-line pl-2.5">
            <p className="leading-normal whitespace-pre-wrap">{proposal.task}</p>

            {/* The figures the name stands for. The name stays the card's
                answer and is the link here, which is the other half of "a
                template is a thing the operator wrote and can go and read": the
                run form is the only page that writes, applies or deletes one,
                the workflow editor's picker being a read of the list. */}
            {proposal.guardsDetail && (
              <p className="leading-normal">
                <Link href="/runs/new">{proposal.templateName}</Link> —{" "}
                {proposal.guardsDetail}
              </p>
            )}

            {/* The mark above says a prompt was rewritten and this is the only
                place that says what it now reads — the one half of a run a
                model may write, and until now marked and unreadable. */}
            {proposal.promptOverride !== null && (
              <div>
                <p className="font-medium text-warn">The prompt the chat wrote</p>
                <p className="mt-1 leading-normal whitespace-pre-wrap">
                  {proposal.promptOverride}
                </p>
              </div>
            )}
          </div>
        </Disclosure>
      </div>
    </label>
  );
}

/**
 * A proposed workflow's blocks, and what approving it does.
 *
 * Every guard-shaped fact on one line per block, for the reason the run card
 * carries a folder and a guard set: this is a graph a *model* wrote, and the
 * argument that lets an orchestrator block start agents with nobody looking is
 * that a person fixed its folder, its guard set and its fan-out cap. Approving
 * this card is where that person does the fixing, so the numbers have to be on
 * it — a card that said "a workflow of 5 blocks" would move the decision to a
 * canvas the operator may never open.
 *
 * The sentence about saving leads rather than trails, because it is the one
 * thing that makes approving this different from approving everything else in
 * this panel.
 */
function ProposedGraph({ proposal }: { proposal: ChatProposalDTO }) {
  const fanOut = proposal.blocks.reduce((n, b) => n + (b.fanOut ?? 0), 0);
  const paying = proposal.blocks.some((b) => b.mergeAutoResolve);

  return (
    <div className="mt-2 flex flex-col gap-2">
      <p className="text-2xs leading-normal text-ink-muted">
        Approving <strong className="font-semibold text-ink">saves</strong> this
        workflow and starts nothing. You press Run on it yourself, and it has no
        workflow-wide budget until you set one — so it cannot be scheduled yet.
      </p>

      {proposal.blocks.length === 0 ? (
        <Hint tone="danger">
          This proposal&rsquo;s graph could not be read, so approving it will be
          refused.
        </Hint>
      ) : (
        <ol className="flex flex-col gap-1 border-l border-line pl-2.5">
          {/* Keyed by position, which is the stable identity here: this list is
              a render of a frozen graph on a decided-or-pending row, so it never
              reorders — and two blocks may legitimately share a name, which the
              node ids this list does not carry are what keep apart. */}
          {proposal.blocks.map((b, i) => (
            <li key={i} className="text-2xs leading-normal text-ink-muted">
              <span className="font-semibold text-ink">{b.name}</span>
              <span className="text-ink-muted"> · {BLOCK_KIND[b.kind]}</span>
              {b.folderLabel && (
                <>
                  {" · "}
                  <span className="mono">{b.folderLabel}</span>
                </>
              )}
              <span
                className={b.guardsLabel === "template deleted" ? "text-danger" : ""}
              >
                {" · "}
                {b.guardsLabel}
              </span>
              {/* Its own clause, outside the guard one, for the reason the run
                  card's is: an agent decides what the block's child *is* and
                  never what it may do. */}
              {b.agentLabel && (
                <span
                  className={b.agentLabel === "agent deleted" ? "text-danger" : ""}
                >
                  {" · as "}
                  {b.agentLabel}
                </span>
              )}
              {b.fanOut !== null && (
                <span className="text-warn"> · up to {b.fanOut} run(s), no approval</span>
              )}
              {b.mergeAutoResolve && (
                <span className="text-warn"> · may pay to resolve conflicts</span>
              )}
              {b.after.length > 0 && <> · after {b.after.join(", ")}</>}
            </li>
          ))}
        </ol>
      )}

      {(fanOut > 0 || paying) && (
        <p className="text-2xs leading-normal font-medium text-warn">
          {fanOut > 0 &&
            `Each press of Run may start up to ${fanOut} run(s) that nobody approves individually.`}
          {fanOut > 0 && paying && " "}
          {paying && "A merge block may pay a model to reconcile a conflict."}
        </p>
      )}
    </div>
  );
}

/**
 * What happened to a proposal, and no buttons: it is not a decision any more.
 *
 * A superseded one is drawn here rather than dropped, which is the whole of what
 * `superseded` costs the panel. The card leaves the list it was waiting in — it
 * is not waiting any more, and leaving it there would offer a tick the route
 * refuses — but it must still be *somewhere*, for the reason a superseded
 * question stays in the transcript: a card that vanished under the operator
 * mid-read reads as one the chat never made, and the correction that replaced it
 * then has nothing to be a correction *of*.
 */
function Decided({
  proposal,
  replacement,
  onShowReplacement,
}: {
  proposal: ChatProposalDTO;
  /** The card that replaced this one, where this one was superseded. */
  replacement: ChatProposalDTO | null;
  onShowReplacement: () => void;
}) {
  // A workflow proposal settles onto a workflow, never a run, so the link goes
  // where the thing it made actually is — and where the press of Run it still
  // needs lives. Reading it off `runId` would leave an approved graph as the
  // one decided row with nothing to click.
  const href = proposal.runId
    ? `/runs/${proposal.runId}`
    : proposal.workflowId
      ? `/workflows/${proposal.workflowId}`
      : null;

  return (
    <div
      id={proposalAnchorId(proposal.id)}
      className="flex items-start gap-2 py-2 first:pt-0 last:pb-0"
    >
      <Badge tone={PROPOSAL_TONE[proposal.status]}>{proposal.status}</Badge>
      <div className="min-w-0 flex-1">
        {href ? (
          <Link
            href={href}
            title={proposal.title}
            className="block truncate text-xs max-md:whitespace-normal"
          >
            {proposal.title}
            {proposal.workflowId && (
              <span className="text-ink-muted"> — saved, not started</span>
            )}
          </Link>
        ) : (
          <div
            className="truncate text-xs text-ink-muted max-md:whitespace-normal"
            title={proposal.title}
          >
            {proposal.title}
          </div>
        )}
        {/* The direction that matters, and only that direction: from the card
            that is gone to the card that answers it. The replacement carries the
            *same* `specId` — `createProposalReplacing` hands the label over on
            purpose, so a sibling's `dependsOn` still resolves — so the label is
            no use for telling the two apart here and the title is what is
            drawn. What it is now comes with it, because "still waiting" is the
            other tab and every other status is this list.

            Written from the row's own `supersededBy` rather than gated on the
            status, so a `superseded` row whose replacement has since been swept
            says what happened to it instead of nothing at all.

            Two lines rather than one sentence with the title inside it, and the
            reason is the element: Chromium blockifies a `button`, so
            `display: inline` on it is ignored and the trailing clause landed on
            a line of its own under a centred title. What is on the second line
            is exactly what the link is *for*, which is the arrangement to keep
            even if that ever changes. */}
        {proposal.status === "superseded" &&
          (replacement ? (
            <>
              <p className="mt-1 text-2xs leading-normal text-ink-muted">
                Replaced by a proposal{" "}
                {replacement.status === "pending"
                  ? "still waiting"
                  : `now ${replacement.status}`}
                :
              </p>
              <button
                type="button"
                onClick={onShowReplacement}
                className="block cursor-pointer text-left text-2xs leading-normal text-accent hover:underline"
              >
                “{replacement.title}”
              </button>
            </>
          ) : (
            <p className="mt-1 text-2xs leading-normal text-ink-muted">
              Replaced by a later proposal.
            </p>
          ))}
        {proposal.error && <Hint tone="danger">{proposal.error}</Hint>}
      </div>
    </div>
  );
}

/**
 * One row of the thread list.
 *
 * Two lines, because one truncated line in a 360px column was all title: an
 * 80-character first message clipped away both the time and the waiting count,
 * which are the only two things telling these rows apart. Only the title
 * truncates, and it carries the full string for hover and assistive tech — the
 * pairing the runs list already uses.
 */
function ChatRow({
  entry,
  current,
  onOpen,
}: {
  entry: ChatListEntryDTO;
  current: boolean;
  onOpen: () => void;
}) {
  return (
    <button
      type="button"
      onClick={onOpen}
      aria-current={current ? "true" : undefined}
      title={entry.title ?? "Untitled"}
      className={`ui-transition cursor-pointer rounded-sm border-l-2 px-2 py-1.5 text-left font-normal ${
        CHAT_ROW[current ? "current" : "other"]
      }`}
    >
      <span className="block truncate text-xs max-md:whitespace-normal">
        {entry.title ?? "Untitled"}
      </span>
      <span className="mt-0.5 flex flex-wrap items-center gap-1.5 text-2xs text-ink-muted">
        <span className="tabular-nums">{fmtRelative(entry.updatedAt)}</span>
        {entry.status === "thinking" && <span className="text-accent">thinking</span>}
        {/* A word in the row's own voice rather than a second accent chip
            beside the proposals one. Both are things waiting for the operator
            and the DTO keeps the counts apart on purpose — one is approving
            work and the other is answering a sentence — so a badge that looked
            identical to `N waiting` would send the reader to the wrong half of
            the page, which is the confusion not summing them exists to avoid.
            `thinking` is already drawn this way one span over, and the two can
            legitimately be true at once: `ask_operator` records its rows while
            the turn that called it is still running. */}
        {entry.pendingQuestionCount > 0 && (
          <span className="text-accent">
            {entry.pendingQuestionCount === 1
              ? "asked you"
              : `asked you ${entry.pendingQuestionCount}`}
          </span>
        )}
        {entry.pendingCount > 0 && (
          <Badge tone="accent">{entry.pendingCount} waiting</Badge>
        )}
      </span>
    </button>
  );
}
