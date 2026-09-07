import {
  spawn,
  type ChildProcess,
  type ChildProcessByStdio,
} from "node:child_process";
import { randomBytes, randomUUID, timingSafeEqual } from "node:crypto";
import fs from "node:fs";
import os from "node:os";
import path from "node:path";
import type { Readable } from "node:stream";
import {
  CLAUDE_BIN,
  MCP_SELF_URL,
  WORKSPACE_MOUNTS,
  WORKSPACE_ROOT,
} from "./config";
import { db } from "./db";
import {
  chatGuards,
  getSettings,
  narrowGuards,
  type RunGuards,
} from "./settings";
import { assistRefusal } from "./review";
import { dataDirRefusal } from "./serverLock";
import { installBudgetRefusal } from "./installBudget";
import { opsLog } from "./ops";
import {
  newChatTurnAccumulator,
  readChatEvent,
  type ChatTurnAccumulator,
} from "./chatStream";
import { totalTokens } from "./pricing";
import {
  chatChildCredentials,
  chownForChild,
  chownToGroup,
  mcpConfigOwnership,
  privilegeSeparated,
  type McpConfigOwnership,
} from "./privsep";
import {
  createRun,
  dependencyCycle,
  githubEnv,
  sandboxArgsFor,
  SEARCH_TOOLS,
  signalTree,
  topologicalOrder,
  type CreateRunInput,
  type DependencyEdge,
  type RunDependencyInput,
} from "./orchestrator";
import { getTemplate, type RunTemplate } from "./templates";
import {
  agentDefinition,
  agentKnowledgeOf,
  agentRefusal,
  getAgent,
  sessionAgentArgs,
  type AgentDefinition,
  type RegistryAgent,
} from "./agents";

/**
 * The orchestrator chat: a conversation that proposes runs.
 *
 * **This is the fourth kind of child process this app spawns**, after git, the
 * agent, and the one-shot review. `review.ts` says adding a third was a
 * decision rather than a detail; so is this, and it is worth saying what makes
 * it a separate kind rather than a fifth caller of `startAssist`:
 *
 *   - It is a *conversation*. It resumes, it accumulates a thread, and its
 *     spend is per turn rather than per invocation — which is why it has its
 *     own table with a running total instead of a row per call.
 *   - It has tools this app implements. No other child talks back to this
 *     server; see `/api/mcp` and the capability token below.
 *   - It is the only child that reaches GitHub *without* doing work. The
 *     invariant used to be "GitHub credentials reach a work cycle and nothing
 *     else"; this widens it to "a work cycle, and the chat that decides what
 *     the work should be", which is a real widening and is why it is written
 *     down here rather than absorbed quietly.
 *
 * What it is **not** allowed to be is a route to spend nobody authorised. It
 * cannot start a run: everything it writes *through this app* is form input — a
 * `chat_proposals` row, or a `run_templates` prompt — neither of which holds a
 * folder claim, consumes a concurrency slot, or does anything at all until a
 * person approves it. Every tool that could widen what an agent may do is
 * absent from that list rather than guarded inside it.
 *
 * Its *own* tool surface, by contrast, is now unrestricted: it runs
 * `bypassPermissions` with no allowlist, so it can read anything, run anything
 * and — with the GitHub token above in its environment — reach the network.
 * That is a deliberate trade, and the reasoning is in `runTurn` where the flag
 * is set. What keeps it an orchestrator is the system prompt, not the mode.
 *
 * Its own cost never reaches `runs.spent_usd`, exactly as a review's does not.
 */

/* ------------------------------------------------------------------ */
/* Rows                                                                */
/* ------------------------------------------------------------------ */

export type ChatStatus = "idle" | "thinking" | "failed";
export type ChatRole = "user" | "assistant" | "system";
export type ProposalStatus = "pending" | "approved" | "rejected" | "failed";

/**
 * What became of a question the chat put to the operator.
 *
 * `superseded` is the operator answering by saying something else, and it is a
 * third state rather than a deletion for `chat_proposals`' reason: the thread
 * has to read as what happened, and a question that vanished reads as one
 * nobody was ever asked.
 */
export type QuestionStatus = "pending" | "answered" | "superseded";

/**
 * What a proposal is a proposal *of*.
 *
 * `run` is the original and the default, for the reason `WorkflowNode.kind`
 * defaults to `run`: every row written before this existed says nothing there,
 * and the other reading would turn a queued run into a graph nobody wrote.
 *
 * `workflow` is the second, and what approving one does is deliberately weaker:
 * it **saves a workflow** and starts nothing. That is what keeps a graph a
 * person's rather than a model's — a saved workflow is form input exactly as a
 * template is, and the press of Run that turns it into agents is still the
 * operator's, on a page that draws the whole graph. The card in the chat is the
 * first of those two gates and it has to spell out what a canvas would show:
 * which guard set each block runs under, how many runs a deciding block may
 * start, and whether a merge block may pay to reconcile a conflict.
 */
export type ProposalKind = "run" | "workflow";

/**
 * "Start this proposal's run after that one's."
 *
 * `specId` is the **chat's own label** rather than a proposal id, because the
 * model writes several proposals in one turn and has to be able to point one at
 * another before either has an id. It is resolved to a run id at approval —
 * against a sibling in the same batch, or against a proposal of this chat that
 * has already become a run — and a label that resolves to neither fails that
 * one proposal by name rather than starting it with no dependency at all, which
 * is a run told to wait that does not.
 */
export interface ProposalDependency {
  specId: string;
  edge: DependencyEdge;
  /** Carry on that run's branch rather than cutting a new one. */
  continueBranch: boolean;
}

export interface ChatRow {
  id: string;
  created_at: number;
  updated_at: number;
  title: string | null;
  session_id: string | null;
  status: ChatStatus;
  cost_usd: number;
  tokens: number;
  error: string | null;
  /**
   * What the turn in flight has said so far, or null when none is.
   *
   * A live view and never the stored message: a settled turn still appends the
   * CLI's own `result` string, so what a finished thread looks like is
   * unchanged. Cleared by the claim and by the settle, so a value here always
   * belongs to the turn the row is on.
   */
  partial_text: string | null;
  partial_at: number | null;
  /** Usage the CLI reported this turn — measured, and summed across requests. */
  turn_tokens: number;
  /**
   * This app's own price for those tokens: a **guard** figure, never shown
   * beside `cost_usd` as though it were the same kind of number. It exists so
   * the install's rolling ceiling can see a turn that is spending right now,
   * exactly as `runs.spent_usd_est` lets it see a cycle in flight.
   */
  turn_cost_est: number;
  /**
   * Estimates for turns that never settled, accumulated. Shown beside
   * `cost_usd` and never folded into it, because no measured figure is coming.
   */
  cost_usd_est: number;
  /**
   * When the turn in flight began, and null when none is. Deliberately not
   * `updated_at`: the chat's own `save_template` tool writes a system message
   * mid-turn, which moves that column and would push the timeout out by
   * however long the turn had already been running.
   */
  turn_started_at: number | null;
  /**
   * Which turn this row is in. Bumped by the claim, never reset, and what a
   * settle has to match to be allowed to change anything — see `finishTurn`.
   */
  turn_seq: number;
}

export interface ChatMessageRow {
  id: string;
  chat_id: string;
  ts: number;
  /** Insert order across every chat. What the thread is ordered by; see below. */
  seq: number;
  role: ChatRole;
  text: string;
}

export interface ChatQuestionRow {
  id: string;
  chat_id: string;
  created_at: number;
  question: string;
  /** JSON `string[]`, or `'[]'`. Read through `questionChoices`. */
  choices: string;
  /** SQLite has no boolean; 1 is "the operator may type instead of picking". */
  allow_text: number;
  status: QuestionStatus;
  /** The operator's words, verbatim. Null until answered, and on a superseded one. */
  answer: string | null;
  answered_at: number | null;
}

export interface ChatProposalRow {
  id: string;
  chat_id: string;
  created_at: number;
  kind: ProposalKind;
  /** Null when the proposal runs under `settings.chatDefaultGuards` instead. */
  template_id: string | null;
  /**
   * The saved agent this run is started as, by id, or null.
   *
   * An id rather than a copy — see the column note in `db.ts` — and on the
   * *work* side of the proposal beside the task and the folder, never on the
   * guard side: an agent holds no tool list and no permission mode, so naming
   * one decides who the run *is* and never what the run may do.
   */
  agent_id: string | null;
  /**
   * The model this run is started on, as the chat named it, or null for none.
   *
   * On the *work* side beside the agent and never on the guard side, and the
   * column note in `db.ts` is where the argument for that is: a model moves what
   * a run costs and never what it may do, so naming one widens nothing. Null
   * falls back to the template's model and then to `settings.defaultModel` —
   * one precedence, resolved in `planProposal`.
   */
  model: string | null;
  title: string;
  task: string;
  /** The prompt the task is appended to, when the chat wrote one for this run. */
  prompt_override: string | null;
  mount_id: string | null;
  folder: string | null;
  /** The chat's own label for this proposal, or null when it named none. */
  spec_id: string | null;
  /** JSON `ProposalDependency[]`, or null. Read through `proposalDeps`. */
  depends_on: string | null;
  /**
   * A workflow proposal's graph, as `normalizeWorkflowInput` left it. Null on a
   * run proposal — the two kinds carry different things and neither should be
   * read off the other's column.
   */
  graph: string | null;
  /**
   * The untemplated guard set frozen at proposal time, as JSON, or null.
   *
   * Null on a templated proposal, on a workflow one, and on every row written
   * before the column existed — read through `proposalGuards`, which falls back
   * to the live set rather than trusting any of those three to mean the same
   * thing as an empty guard set.
   */
  guards_json: string | null;
  status: ProposalStatus;
  run_id: string | null;
  /** What a workflow proposal became. Never a run; approving one starts nothing. */
  workflow_id: string | null;
  decided_at: number | null;
  error: string | null;
}

/**
 * The dependencies on a row, or none.
 *
 * Never throws: the column is written by this module and read back by it, but a
 * row hand-edited or written by an older build must not be able to make a chat
 * page 500. An unreadable list is no dependencies, which is the reading that
 * *fails safe* in only one direction — the proposal starts immediately instead
 * of waiting — so it is logged nowhere and shown everywhere: the card carries
 * what it is waiting for, so a list that silently emptied is visible before the
 * operator approves it rather than after.
 */
export function proposalDeps(
  row: Pick<ChatProposalRow, "depends_on">,
): ProposalDependency[] {
  if (!row.depends_on) return [];
  try {
    const parsed = JSON.parse(row.depends_on) as unknown;
    if (!Array.isArray(parsed)) return [];
    return parsed.flatMap((entry) => {
      const e = (entry ?? {}) as Record<string, unknown>;
      const specId = String(e.specId ?? "");
      const edge = String(e.edge ?? "");
      if (!specId || (edge !== "on-success" && edge !== "on-finish")) return [];
      return [{ specId, edge, continueBranch: e.continueBranch === true }];
    });
  } catch {
    return [];
  }
}

/**
 * The choices a question offered, or none.
 *
 * Never throws, for `proposalDeps`' reason: the column is written by this module
 * and read back by it, but a row an older build or a hand edit left must not be
 * able to 500 the chat page. An unreadable list is *no* choices, which is the
 * reading that fails safe in only one direction — the question is still
 * answerable when `allow_text` is set, and unanswerable rather than silently
 * answerable with something nobody offered when it is not.
 */
export function questionChoices(
  row: Pick<ChatQuestionRow, "choices">,
): string[] {
  if (!row.choices) return [];
  try {
    const parsed = JSON.parse(row.choices) as unknown;
    if (!Array.isArray(parsed)) return [];
    return parsed.flatMap((c) => (typeof c === "string" && c ? [c] : []));
  } catch {
    return [];
  }
}

/**
 * How many unanswered questions one chat may hold.
 *
 * `MAX_PENDING_PROPOSALS`' reasoning against a much smaller thing, which is why
 * the number is a fifth of it: a proposal is a card to scan and a question is a
 * decision to make, and past a handful of decisions the panel stops being a
 * question and becomes a form. A form gets skimmed, and a skimmed answer is
 * worse than no answer — the model proposes on it either way, and only one of
 * those two is something the operator will remember agreeing to.
 */
export const MAX_OPEN_QUESTIONS = 5;

/**
 * How many concrete answers one question may offer.
 *
 * The same argument one level down, and a larger number because picking from a
 * list is cheaper than answering one more question. Past this the choices are a
 * search rather than a decision, and what the operator wants then is to type.
 */
export const MAX_QUESTION_CHOICES = 8;

/**
 * How many undecided proposals one chat may hold.
 *
 * The failure this bounds is specific and cheap to reach: "open a run for every
 * issue" against a repository with four hundred of them. Nothing downstream
 * would break — proposals are inert — but an approval list nobody can read is
 * an approval gate that gets clicked through, which is the same as not having
 * one. The tool refuses past this and says so, so the model asks for a filter
 * instead of silently proposing the first twenty-five.
 */
export const MAX_PENDING_PROPOSALS = 25;

/** How much of the thread is replayed when there is no session to resume. */
const THREAD_REPLAY_MESSAGES = 20;
const THREAD_REPLAY_BYTES = 20_000;

/** A chat turn that has not finished in this long is not going to. */
export const CHAT_TIMEOUT_MS = 10 * 60_000;

/**
 * How long past that bound the sweeper waits before failing a row out.
 *
 * The in-closure timer above fires at exactly `CHAT_TIMEOUT_MS` and then gives
 * the child five seconds to die, so a turn that is being stopped properly
 * settles well inside this margin. What is left over when the margin expires is
 * a turn whose `close` is not coming — the case this whole path exists for.
 */
export const STALE_TURN_MARGIN_MS = 60_000;

/** How often a `thinking` row is checked against that deadline. */
const CHAT_SWEEP_MS = 30_000;

/** How long `close` is given to deliver the last of stdout after the exit. */
const EXIT_DRAIN_MS = 2_000;

/* ------------------------------------------------------------------ */
/* Storage                                                             */
/* ------------------------------------------------------------------ */

export function createChat(): ChatRow {
  const id = randomUUID();
  const now = Date.now();
  db()
    .prepare(
      "INSERT INTO chat_sessions (id, created_at, updated_at, status) VALUES (?, ?, ?, 'idle')",
    )
    .run(id, now, now);
  return getChat(id)!;
}

export function getChat(id: string): ChatRow | null {
  return (
    (db().prepare("SELECT * FROM chat_sessions WHERE id = ?").get(id) as
      | ChatRow
      | undefined) ?? null
  );
}

export function listChats(limit = 30): ChatRow[] {
  return db()
    .prepare("SELECT * FROM chat_sessions ORDER BY updated_at DESC LIMIT ?")
    .all(limit) as ChatRow[];
}

/** The widest page `findChats` will answer with, whatever it was asked for. */
export const CHAT_PAGE_MAX = 100;

/**
 * Threads matching a search, past the newest thirty.
 *
 * The cap above is not a bug and stays: it is the sidebar's live list, re-read
 * on every poll while a turn runs, and a page that streamed every thread into
 * that payload would grow with the install. What was missing is any *other* way
 * to reach a thread, so an approved proposal's reasoning became unreachable the
 * moment thirty conversations had happened since — no paging, no search, no
 * index, and `/api/chat` read no parameters at all.
 *
 * The text matches a title **or** any message in the thread, and the second
 * half is the point: a title is written by the model from the opening line, so
 * searching titles alone finds the conversations somebody already remembers.
 * `EXISTS` rather than a join, so a thread with forty matching messages is one
 * row rather than forty.
 */
export function findChats(o: {
  q?: string;
  limit?: number;
  offset?: number;
}): { chats: ChatRow[]; total: number } {
  const q = (o.q ?? "").trim();
  const limit = Math.max(1, Math.min(CHAT_PAGE_MAX, Math.trunc(o.limit ?? 30) || 30));
  const offset = Math.max(0, Math.trunc(o.offset ?? 0) || 0);

  // `LIKE` with the operator's text as a bound parameter, never interpolated.
  // The wildcards are ours; `\` escapes the two LIKE metacharacters so a search
  // for a literal `%` is a search for that character rather than for everything.
  const where = q
    ? " WHERE (COALESCE(s.title, '') LIKE ? ESCAPE '\\'" +
      " OR EXISTS (SELECT 1 FROM chat_messages m WHERE m.chat_id = s.id" +
      " AND m.text LIKE ? ESCAPE '\\'))"
    : "";
  const pattern = `%${q.replace(/[\\%_]/g, (c) => `\\${c}`)}%`;
  const args = q ? [pattern, pattern] : [];

  const total = (
    db()
      .prepare(`SELECT COUNT(*) AS n FROM chat_sessions s${where}`)
      .get(...args) as { n: number }
  ).n;

  const chats = db()
    .prepare(
      `SELECT s.* FROM chat_sessions s${where} ORDER BY s.updated_at DESC` +
        " LIMIT ? OFFSET ?",
    )
    .all(...args, limit, offset) as ChatRow[];

  return { chats, total };
}

/** The newest chat, or a fresh one. The page opens on a thread, not a list. */
export function latestChat(): ChatRow {
  return listChats(1)[0] ?? createChat();
}

/**
 * A thread, in the order it was written.
 *
 * Ordered by `seq` alone rather than by `ts` and then something: the timestamp
 * is a tie for every message a turn writes — `finishTurn` appends the reply,
 * an error and a denial note in one synchronous block — and the tiebreak it
 * used to fall through to was `id`, which is a random UUID. A denial note is a
 * footnote about the reply above it, so half the time the operator was told
 * "the tool was refused, and separately here is an answer". `seq` is the order
 * the rows were written and nothing else can reorder them, including a clock
 * that steps backwards mid-conversation.
 *
 * **`afterSeq` is what keeps the chat page's poll off the whole thread.** That
 * page re-asks this route every three seconds for as long as it is open, so a
 * read of the whole conversation is a cost that rises with the conversation and
 * never comes down — the longest threads, which are the ones worth having, are
 * the dearest to leave on screen. `chat_messages` is the one store here that
 * only ever grows by appending (nothing updates or deletes a row), which is what
 * makes a cursor sound: a message the page already holds cannot have changed, so
 * anything past the highest `seq` it holds is the entire difference. Proposals
 * and questions are not read this way and must not be, because both are updated
 * in place after they are written.
 *
 * Zero means the whole thread, which is what every caller that is not the poll
 * wants and what `seq > 0` gives for free — `appendMessage` hands out `MAX + 1`
 * from one, and the backfill in `migrate()` uses `rowid`, so no row has ever
 * carried a lower number. One statement rather than a branch for the same
 * reason: two spellings of "this thread, in order" are two plans to keep in
 * step. The bound is only real with `idx_chat_messages_seq` — see the argument
 * beside it in `migrate()`.
 */
export function listMessages(chatId: string, afterSeq = 0): ChatMessageRow[] {
  return db()
    .prepare(
      "SELECT * FROM chat_messages WHERE chat_id = ? AND seq > ? ORDER BY seq",
    )
    .all(chatId, afterSeq) as ChatMessageRow[];
}

export function appendMessage(
  chatId: string,
  role: ChatRole,
  text: string,
): ChatMessageRow {
  const id = randomUUID();
  const now = Date.now();
  db()
    .prepare(
      // `seq` is taken inside the INSERT rather than read first: better-sqlite3
      // is synchronous and this app is a single writer, so one statement is the
      // only shape in which "the next number" cannot be handed out twice.
      "INSERT INTO chat_messages (id, chat_id, ts, seq, role, text)" +
        " VALUES (?, ?, ?, (SELECT IFNULL(MAX(seq), 0) + 1 FROM chat_messages), ?, ?)",
    )
    .run(id, chatId, now, role, text);
  db()
    .prepare("UPDATE chat_sessions SET updated_at = ? WHERE id = ?")
    .run(now, chatId);
  return db()
    .prepare("SELECT * FROM chat_messages WHERE id = ?")
    .get(id) as ChatMessageRow;
}

export function listProposals(chatId: string): ChatProposalRow[] {
  return db()
    .prepare(
      "SELECT * FROM chat_proposals WHERE chat_id = ? ORDER BY created_at, id",
    )
    .all(chatId) as ChatProposalRow[];
}

export function getProposal(id: string): ChatProposalRow | null {
  return (
    (db().prepare("SELECT * FROM chat_proposals WHERE id = ?").get(id) as
      | ChatProposalRow
      | undefined) ?? null
  );
}

export function pendingProposals(chatId: string): ChatProposalRow[] {
  return listProposals(chatId).filter((p) => p.status === "pending");
}

/* ------------------------------------------------------------------ */
/* Questions to the operator                                           */
/* ------------------------------------------------------------------ */

/**
 * **A pending question is derived from this table and is not a chat status.**
 *
 * The alternative was a fourth `chat_sessions.status`, and it was rejected for
 * three reasons that are each on their own sufficient. The row is settled by
 * `finishTurn` under `WHERE status='thinking'`, which is the settle-once latch
 * every stranded-turn path depends on — a status meaning "asked and waiting"
 * would have to be written by that same statement, so a cancelled or timed-out
 * turn that had already asked would settle as `failed` and lose the question, or
 * settle as `asking` and lose the failure. Second, `reconcileChatsOnBoot` fails
 * out `thinking` rows because the child is gone with the process; a question is
 * a row in a database and survives a restart intact, so a state that meant both
 * would have to be excluded there by hand — a silent way for a restart to eat
 * every open question. Third, `sendChatMessage` refuses to send into a
 * `thinking` chat, and an answer *is* a message: a status meaning "waiting for
 * the operator" would sit next to that guard and be one careless `<>` away from
 * refusing the very answer it exists to collect.
 *
 * What this costs is one query on the page's poll, which is the same query the
 * proposals already pay for. What it buys is that nothing about the turn
 * lifecycle changes at all: a turn that asks ends `idle` like any other, an
 * answer is an ordinary message, and a question outlives every way a turn can
 * die.
 */
export function listQuestions(chatId: string): ChatQuestionRow[] {
  return db()
    .prepare(
      // `rowid` rather than `id`, which is `listMessages`' correction one table
      // over and the same defect: every question of one call shares a
      // `created_at`, so the tiebreak decides the order — and `id` is a random
      // UUID, which shuffles a numbered list of questions the model wrote in a
      // deliberate order and shuffles the answer message quoting them back.
      // Not a `seq` column, because there is nothing here to backfill: unlike
      // `chat_messages` this table has never shipped, so insert order and
      // `rowid` order have never been able to disagree.
      "SELECT * FROM chat_questions WHERE chat_id = ? ORDER BY created_at, rowid",
    )
    .all(chatId) as ChatQuestionRow[];
}

/** Not exported: everything outside this module reads a chat's questions as a
 *  set, because that is how they are asked and how they are settled. */
function getQuestion(id: string): ChatQuestionRow | null {
  return (
    (db().prepare("SELECT * FROM chat_questions WHERE id = ?").get(id) as
      | ChatQuestionRow
      | undefined) ?? null
  );
}

export function pendingQuestions(chatId: string): ChatQuestionRow[] {
  return listQuestions(chatId).filter((q) => q.status === "pending");
}

export interface QuestionInput {
  question: string;
  /** Concrete answers offered, already normalized. Empty for free text. */
  choices: readonly string[];
  /** May the operator type instead of picking? */
  allowText: boolean;
}

/**
 * Record what one turn asked, in the order it asked it.
 *
 * One row per question rather than one row holding a list, because an answer
 * has to attach to the sentence it answers — the operator may answer two of
 * three and leave the third, and what happens to the third is a fact about that
 * question rather than about the set. `created_at` is shared across the call so
 * the page can show them as the set they were asked as, and `listQuestions`
 * breaks that tie on `rowid` so they stay in the order the model wrote them.
 */
export function createQuestions(
  chatId: string,
  inputs: readonly QuestionInput[],
): ChatQuestionRow[] {
  const now = Date.now();
  const insert = db().prepare(
    `INSERT INTO chat_questions
       (id, chat_id, created_at, question, choices, allow_text, status)
     VALUES (?, ?, ?, ?, ?, ?, 'pending')`,
  );
  return inputs.map((input) => {
    const id = randomUUID();
    insert.run(
      id,
      chatId,
      now,
      input.question,
      JSON.stringify([...input.choices]),
      input.allowText ? 1 : 0,
    );
    return getQuestion(id)!;
  });
}

/**
 * Close every question this message settles, and supersede whatever is left.
 *
 * Called from inside `sendChatMessage`'s no-`await` window, so a request that
 * lost the claim settles nothing. Both statements are bounded by
 * `status='pending'` and by the chat, which makes the pass idempotent and makes
 * an id that has stopped being open a no-op rather than a resurrection — the
 * refusal a person can act on is `settleQuestions`, decided before any of this
 * is paid for.
 *
 * The second statement is the whole supersede rule and it covers both doors:
 * an ordinary message settles nothing and supersedes everything, and an answer
 * to two of three questions supersedes the third. `answered_at` is deliberately
 * left null there — it is the instant an answer was given, and a superseded
 * question was never answered.
 */
function settleOpenQuestions(
  chatId: string,
  answers: readonly QuestionAnswer[],
): void {
  const now = Date.now();
  const answer = db().prepare(
    `UPDATE chat_questions SET status='answered', answer=?, answered_at=?
      WHERE id=? AND chat_id=? AND status='pending'`,
  );
  for (const a of answers) answer.run(a.answer, now, a.id, chatId);
  db()
    .prepare(
      "UPDATE chat_questions SET status='superseded' WHERE chat_id=? AND status='pending'",
    )
    .run(chatId);
}

/**
 * The choices a question may offer, from whatever the tool call carried.
 *
 * Pure and unit-tested, because every way of getting it wrong produces a
 * *question* rather than an error: a choices array that arrived as a string, or
 * held nulls, or repeated an option twice, renders as a card with no buttons or
 * with two identical ones, and the operator's answer then means something the
 * model did not offer. Anything not a string is dropped rather than stringified:
 * `String(null)` is the word "null", which is a choice nobody wrote and one an
 * operator could click.
 *
 * It deliberately does **not** cap the list, though `MAX_QUESTION_CHOICES`
 * exists: a caller that silently truncated would leave the model believing it
 * had offered choices the operator was never shown. The cap is `askOperator`'s
 * refusal, and it is applied to what this returns rather than to what arrived —
 * so "twenty choices" and "twenty copies of one choice" are told apart, and the
 * count in the refusal is the count that would have been rendered.
 */
export function normalizeChoices(raw: unknown): string[] {
  if (!Array.isArray(raw)) return [];
  const seen = new Set<string>();
  for (const entry of raw) {
    if (typeof entry !== "string") continue;
    const choice = entry.trim();
    if (choice) seen.add(choice);
  }
  return [...seen];
}

/** One question and what the operator said to it, as the next turn reads it. */
export interface AnsweredQuestion {
  question: string;
  /** Null when the operator left this one alone. */
  answer: string | null;
}

/**
 * What the answering turn is actually sent.
 *
 * Pure and unit-tested, and the failure it exists against is the one the whole
 * mechanism turns on: the answer reaches a **fresh child**, resumed against the
 * session but with no memory of the tool call in its own process. A bare
 * "pnpm" is a message the model has to guess the referent of, and the guess is
 * silent — it proposes against whichever question it decided that answered.
 * Quoting the question back costs a few dozen tokens and removes the guess.
 *
 * An unanswered question is named too, rather than left out. Left out, it is
 * indistinguishable from a question that was never asked, and the model's next
 * move is to ask it again — which is a second turn, a second ten-minute window
 * and a second card, for a question the operator has already declined once.
 */
export function answerMessage(entries: readonly AnsweredQuestion[]): string {
  const lines = ["Answers to your questions:"];
  for (const entry of entries) {
    lines.push("", `Q: ${entry.question}`, `A: ${entry.answer ?? "(not answered)"}`);
  }
  return lines.join("\n");
}

export type QuestionSettlement =
  | {
      ok: true;
      /** Every open question, in the order it was asked, for `answerMessage`. */
      entries: AnsweredQuestion[];
      /** The ones with an answer against them, for the UPDATE that closes them. */
      answered: QuestionAnswer[];
    }
  | { ok: false; reason: string };

/**
 * The whole of what a set of answers decides, before anything is written.
 *
 * Pure and unit-tested, for `planApprovalBatch`'s reason: this is the step where
 * what a person clicked becomes what a model is told, and every way of getting
 * it wrong is silent. It answers all three questions the caller has — whether to
 * refuse, what the message says, and which rows close — and everything it
 * returns is used, so a wrong partition is a wrong message rather than a value
 * nobody reads.
 *
 * **An id that is not open fails the whole call** rather than being dropped,
 * which is where this diverges from the proposals route. There the ids are
 * independent and a stale one costs nothing; here they compose one message, so
 * a dropped id is the operator's typed answer silently absent from the text the
 * model reads — and the model then answers about the questions that did survive
 * as though those were all it asked.
 *
 * **The refusal may not tell the operator to reload.** The drafts are `useState`
 * local to the question card, so a reload is precisely what destroys the four
 * answers that were fine. It names what survives instead, which is true because
 * this decides before anything is written.
 *
 * **Every open question is in `entries`, answered or not.** A question left out
 * is indistinguishable from one that was never asked, and the model's next move
 * is to ask it again — a second turn and a second ten-minute window for
 * something the operator has already declined once.
 *
 * What is deliberately *not* here is the supersede rule. Nothing an operator
 * sends leaves a question open, and that is enforced by a single
 * `WHERE status='pending'` UPDATE in `settleOpenQuestions` covering both doors —
 * an ordinary message never reaches this function at all. The rule is in the
 * query, so it is pinned against a database rather than here.
 */
export function settleQuestions(
  open: ReadonlyArray<Pick<ChatQuestionRow, "id" | "question">>,
  answering: ReadonlyArray<QuestionAnswer>,
): QuestionSettlement {
  const byId = new Map<string, string>();
  const ids = new Set(open.map((q) => q.id));
  for (const { id, answer } of answering) {
    if (!ids.has(id)) {
      return {
        ok: false,
        reason:
          "One of these is no longer waiting for an answer — it was answered " +
          "or the conversation moved past it — so nothing was sent. Your " +
          "other answers are still here; press Answer again.",
      };
    }
    if (byId.has(id)) {
      return { ok: false, reason: "That question was answered twice in one request." };
    }
    byId.set(id, answer);
  }
  return {
    ok: true,
    // In the order they were asked rather than the order they were answered, so
    // the message reads back as the list the model wrote.
    entries: open.map((q) => ({
      question: q.question,
      answer: byId.get(q.id) ?? null,
    })),
    answered: open.flatMap((q) =>
      byId.has(q.id) ? [{ id: q.id, answer: byId.get(q.id)! }] : [],
    ),
  };
}

/**
 * Did this conversation start that run?
 *
 * What `/api/mcp` scopes `get_run_diff` by. A capability token *is* the caller's
 * identity, so nothing here can tell a chat's own turn from a work-cycle agent
 * that read the token out of a sibling's config file — which means the only
 * thing that bounds a stolen one is what its subject may ask for. Patch text is
 * the expensive answer: a work cycle is confined to the folder it was started
 * in (only `runOrchestratorChild` passes `--add-dir` for every mount), so an
 * unscoped `get_run_diff` was the source of every repository this install has
 * run against, reachable from a run that could not otherwise read any of them.
 *
 * Scoped to the runs this thread proposed rather than to the runs it *knows
 * about*: `list_runs` and `get_run` stay install-wide on purpose, because
 * "what is already in flight" is the question the orchestrator exists to answer
 * and a file list is not a patch.
 */
export function chatOwnsRun(chatId: string, runId: string): boolean {
  return (
    db()
      .prepare(
        "SELECT 1 FROM chat_proposals WHERE chat_id = ? AND run_id = ? LIMIT 1",
      )
      .get(chatId, runId) !== undefined
  );
}

export interface ProposalInput {
  kind?: ProposalKind;
  /** Null runs it under the operator's untemplated guard set. */
  templateId: string | null;
  /** A saved agent the run is started as, by id. Null is the ordinary run. */
  agentId?: string | null;
  /**
   * The model the run is started on. Null takes the template's, then settings'.
   *
   * The one field on this object that is neither work nor a guard: it decides
   * what the run costs, which every cost guard already covers, and nothing
   * about what the run may do. See the column note in `db.ts`.
   */
  model?: string | null;
  title: string;
  task: string;
  /** Replaces the template's prompt for this run only. Null keeps it. */
  promptOverride: string | null;
  mountId: string | null;
  folder: string | null;
  /** The chat's own label for this proposal. Null when nothing names it. */
  specId?: string | null;
  dependsOn?: readonly ProposalDependency[];
  /** A workflow proposal's normalized graph, as JSON. Null on a run one. */
  graph?: string | null;
}

export function createProposal(
  chatId: string,
  input: ProposalInput,
): ChatProposalRow {
  const id = randomUUID();
  const deps = input.dependsOn ?? [];
  const kind = input.kind ?? "run";
  db()
    .prepare(
      `INSERT INTO chat_proposals
         (id, chat_id, created_at, kind, template_id, agent_id, model, title,
          task, prompt_override, mount_id, folder, spec_id, depends_on, graph,
          guards_json, status)
       VALUES (?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?, 'pending')`,
    )
    .run(
      id,
      chatId,
      Date.now(),
      kind,
      input.templateId,
      input.agentId ?? null,
      // Written from the argument, unlike `guards_json` below, and the two
      // sitting next to each other is the distinction worth keeping in view: a
      // model decides what this run costs and a guard set decides what it may
      // do, so only one of them is a thing a model may name.
      input.model ?? null,
      input.title,
      input.task,
      input.promptOverride,
      input.mountId,
      input.folder,
      input.specId ?? null,
      deps.length > 0 ? JSON.stringify(deps) : null,
      input.graph ?? null,
      // Read here rather than at the click, and read from *settings* rather
      // than from anything on `input`: the card an untemplated proposal draws
      // spells its guards out, so the values it shows and the values the run
      // starts under have to be one value taken once. `ProposalInput` has no
      // field that could carry them and must not grow one — a guard a model
      // could name is the one thing this whole path exists to make unreachable.
      //
      // Only a run proposal, and only an untemplated one. A template is a
      // handle the operator can go and read, so it is resolved live at the
      // click; and approving a *workflow* proposal saves a graph rather than
      // starting anything, so the guards that matter there are the ones its
      // blocks name when somebody later presses Run.
      kind === "run" && input.templateId === null
        ? JSON.stringify(chatGuards())
        : null,
    );
  return getProposal(id)!;
}

/* ------------------------------------------------------------------ */
/* The two pure decisions                                              */
/* ------------------------------------------------------------------ */

export type ProposalPlan =
  | { ok: true; input: Omit<CreateRunInput, "origin"> }
  | { ok: false; reason: string };

/**
 * The guard set an untemplated proposal froze when it was written, or null.
 *
 * Both readers of it — the card and the click — take it through here and fall
 * back to the live `chatGuards()` on null, which is what the two of them did
 * before any set was frozen. That fallback is the *only* thing null means, and
 * it means it for three separate rows: a templated proposal, whose guards are a
 * handle read live on purpose; a workflow one, which starts nothing; and every
 * proposal already pending across the upgrade that added the column, which must
 * still approve rather than refuse.
 *
 * A blob that will not parse is null too, and that is not the same act as
 * accepting half of one. What comes back from `JSON.parse` is narrowed by
 * `narrowGuards` exactly as the settings blob is, so a snapshot missing fields
 * — an older build's shape, a hand-edited row — resolves to `plan`, a checkout
 * of its own and one work cycle. Every direction this can be wrong in is
 * therefore narrower than what was asked for, which is the one property that
 * matters: a guard set arriving from storage may never widen what a run may do.
 *
 * Pure, for `planProposal`'s reason and with its failure mode: what it decides
 * is what an agent is allowed to do to a directory, and a wrong answer here is
 * a run under rules nobody agreed to, which nothing throws over and no page
 * shows.
 */
export function proposalGuards(
  proposal: Pick<ChatProposalRow, "guards_json">,
): RunGuards | null {
  if (!proposal.guards_json) return null;
  let raw: unknown;
  try {
    raw = JSON.parse(proposal.guards_json);
  } catch {
    return null;
  }
  // An array is as much "not a guard set" as a bare string is: it would narrow
  // to `plan`, isolated, one cycle — a perfectly safe set that nobody wrote —
  // where falling back gives the operator the set their Settings page shows.
  if (typeof raw !== "object" || raw === null || Array.isArray(raw)) return null;
  return narrowGuards(raw as Partial<RunGuards>);
}

/**
 * Turn an approved proposal into the run it asks for, or say why not.
 *
 * Pure — it takes the proposal, the template and the untemplated guard set
 * rather than reading any of them — and unit-tested, for the reason `planItem`
 * and `landRefusal` are: it is the step where something a model wrote becomes a
 * process with write access to a directory, and every branch of it is a
 * decision an operator would want to have been made the same way twice.
 *
 * The division of labour it enforces is the whole design: **the proposal says
 * what work to do, and something a person wrote says what an agent may do**.
 * There are two of those now — a named template, or `settings.chatDefaultGuards`
 * when the proposal names none, which is what lets the chat be useful on an
 * install with no templates saved. What has not changed is the branch that is
 * *not* here: no value off a proposal sets a guard, a permission mode or an
 * isolation choice, because a proposal is text a model produced and
 * `--permission-mode` is not a thing a model should be able to reach for.
 *
 * The prompt is the exception, and it is an exception on purpose: prompt text
 * *is* the half of a run a model may write. A proposal can therefore replace
 * the template's prompt for one run, and the card says when it did.
 *
 * **The model is resolved here and is the third thing a proposal may write, and
 * it is not an exception to the paragraph above either.** A model moves cost
 * rather than capability — `agents.ts`'s own ground for `agents.model` — and
 * every cost guard already covers it, since the run's spend lands on its own
 * `result` event and in its telemetry whatever model produced it. So a model
 * the chat names changes what this run costs and nothing about what it may do:
 * the budget, the work-cycle limit, the permission mode and the isolation
 * choice below still come from the template or from settings, and there is
 * still no field anywhere that reaches one. A reader who finds `model` on
 * `ProposalInput` and no note like this one will read the rule as having
 * quietly lapsed; it has not.
 *
 * Precedence is stated once and applied once, right here: the proposal's model,
 * then the template's, then null — which `createRun` turns into
 * `settings.defaultModel`.
 *
 * **The agent is the second exception and is not one either.** A saved agent is
 * a description and a prompt: the registry refuses a tool list at the door and
 * has no column for a permission mode, so naming one is the same class of act as
 * writing the task text beside it — it decides *who the run is*, and every guard
 * below still comes from the template or from settings. It is resolved by the
 * caller for the reason the template is, so this function stays pure, and a
 * named agent that has gone is refused **by name** rather than falling back to
 * none: the operator approved the card that said "as the reviewer", and a run
 * that silently is not the reviewer is bit-for-bit a run that was never given
 * one.
 */
export function planProposal(
  proposal: Pick<
    ChatProposalRow,
    | "task"
    | "mount_id"
    | "folder"
    | "status"
    | "title"
    | "template_id"
    | "agent_id"
    | "model"
    | "prompt_override"
  >,
  template: RunTemplate | null,
  defaults: RunGuards,
  // Required rather than defaulted: a caller that forgot it would take the
  // refusal below on every agent-bearing proposal, which is safe but is a
  // refusal for the wrong reason. `planNode` takes it the same way.
  agent: RegistryAgent | null,
): ProposalPlan {
  if (proposal.status !== "pending") {
    return {
      ok: false,
      reason: `This proposal was already ${proposal.status}.`,
    };
  }

  if (proposal.template_id !== null && !template) {
    // Reachable by ordinary use: the chat proposes against a template, the
    // operator tidies their templates, then approves. Failing by name is what
    // lets them re-propose rather than wonder which run did not start. Not
    // silently falling back to the untemplated guard set: the operator picked
    // that template, and a run starting under different rules than the card
    // said is the one outcome this gate exists to prevent.
    return {
      ok: false,
      reason:
        "The template this proposal was made against no longer exists, so " +
        "there are no guards to start it under. Ask the chat to propose it " +
        "again — against a template that does, or against no template, which " +
        "uses the guards in Settings.",
    };
  }

  // Read as truthy rather than against null, `planNode`'s rule one level over:
  // a proposal written before this column existed carries `undefined` here on
  // an install that has not restarted, and `undefined !== null` would refuse
  // every proposal already waiting for a decision.
  if (proposal.agent_id) {
    const refusal = agentRefusal(proposal.agent_id, agentKnowledgeOf(agent));
    if (refusal) return { ok: false, reason: refusal };
  }

  const task = proposal.task.trim();
  if (!task) {
    return { ok: false, reason: "This proposal has no task text." };
  }

  // Null on the proposal means "wherever the template says". The empty string
  // does not: on both a template and a proposal it is the mount root, the one
  // selection that blocks every other run in the tree, so collapsing the two
  // would silently promote "no folder named" into "the whole workspace".
  const mountId = proposal.mount_id ?? template?.mountId ?? null;
  const folder =
    proposal.mount_id !== null ? proposal.folder : (template?.folder ?? null);

  if (mountId === null) {
    return {
      ok: false,
      reason: template
        ? `Neither this proposal nor the “${template.name}” template names a ` +
          "folder to work in, so there is nothing to start it against."
        : "This proposal names no folder to work in, and it names no template " +
          "to take one from.",
    };
  }

  const guards: RunGuards = template
    ? {
        permissionMode: template.permissionMode,
        isolate: template.isolate,
        budget: template.budget,
      }
    : defaults;

  return {
    ok: true,
    input: {
      folder: folder ?? "",
      mountId,
      prompt: composeTask(basePrompt(proposal, template), task),
      // Every one of these comes from the template or from settings, and none
      // of them from the proposal. See the note above.
      permissionMode: guards.permissionMode,
      isolate: guards.isolate,
      budget: guards.budget,
      // And this one comes from the proposal and from nowhere else, because it
      // is work rather than permission. `createRun` freezes the definition onto
      // the row, so an agent deleted after the click cannot reach a later cycle
      // of the run this starts.
      agent: proposal.agent_id && agent ? agentDefinition(agent) : null,
      // The proposal's, then the template's, then null — the whole of the
      // precedence, applied in the one place, and the only fallback left below
      // it is `createRun`'s `?? settings.defaultModel`. Resolving it twice is
      // how two surfaces stop agreeing about what a run costs.
      //
      // Truthy rather than `?? `: a row written before the column existed reads
      // `undefined` on an install that has not restarted, and the empty string
      // is what a trimmed-to-nothing argument leaves — both mean "named none"
      // and neither may become `--model ""`, which is a spawn that fails.
      //
      // The proposal wins where the agent does not, and the asymmetry is what
      // the two fields are for. Naming an agent decides who the run *is*, which
      // the template also decided, so the proposal's answer is the later of two
      // answers to one question. A model is a price, and the chat is the
      // surface that knows what this particular job is worth paying for.
      model: proposal.model?.trim() || template?.model || null,
    },
  };
}

/**
 * The standing instructions the task is appended to, or null for none.
 *
 * An override written by the chat wins over the template's own prompt, which
 * reads backwards until you notice what a template is: a saved *form*, and the
 * prompt field is the one field on it a person expects to edit before pressing
 * start. The chat doing that for a run it is proposing is the same edit, and
 * the alternative — restating the standing instructions inside the task — puts
 * the same text in the run either way with nothing recording that it happened.
 */
function basePrompt(
  proposal: Pick<ChatProposalRow, "prompt_override">,
  template: RunTemplate | null,
): string | null {
  const override = proposal.prompt_override?.trim();
  if (override) return override;
  return template?.prompt ?? null;
}

/**
 * The prompt a proposed run is started with.
 *
 * The standing instructions lead, because that is the part written to hold for
 * every run; the chat's task follows as the specific instance. Kept in this
 * order and separated by a heading rather than interleaved, so an operator
 * reading the run afterwards can see which half came from a model. With no
 * template and no override there is nothing to lead with, and the task is the
 * whole prompt rather than a heading with nothing above it.
 */
export function composeTask(base: string | null, task: string): string {
  const lead = base?.trim();
  return lead
    ? `${lead}\n\n## This run specifically\n\n${task.trim()}`
    : task.trim();
}

/**
 * What the child is asked, given what it can and cannot remember.
 *
 * With a session to resume, the thread is already in the conversation and
 * restating it is spend for no information — the same reasoning
 * `DEFAULT_CONTINUATION_PROMPT` follows. With no session, the turn is a fresh
 * conversation: a turn that failed before the CLI reported a session id leaves
 * the chat looking continuous on screen while the model has never seen a word
 * of it, and answering the next message with no idea what was already agreed is
 * worse than paying to re-read a few short messages.
 *
 * Pure and unit-tested, because both branches are billed and the wrong one is
 * invisible — a model that silently lost the thread still answers confidently.
 */
export function chatPrompt(
  o: { sessionId: string | null; history: Array<{ role: ChatRole; text: string }> },
  message: string,
): string {
  if (o.sessionId) return message;

  const recent = o.history.slice(-THREAD_REPLAY_MESSAGES);
  let budget = THREAD_REPLAY_BYTES;
  const kept: string[] = [];
  // Newest first while filling, so what survives a small budget is the part
  // nearest the question rather than the opening pleasantries.
  for (let i = recent.length - 1; i >= 0; i--) {
    const line = `${recent[i].role}: ${recent[i].text}`;
    if (line.length > budget) break;
    budget -= line.length;
    kept.unshift(line);
  }

  if (kept.length === 0) return message;

  return [
    "This conversation was interrupted and you do not have its history. Here is",
    "what was said before, oldest first:",
    "",
    "<thread>",
    ...kept,
    "</thread>",
    "",
    "Now answer this message:",
    "",
    message,
  ].join("\n");
}

/* ------------------------------------------------------------------ */
/* The batch — pure                                                    */
/* ------------------------------------------------------------------ */

/** One proposal as the batch planner reads it. */
export interface BatchProposal {
  id: string;
  /** The chat's own label, or null when nothing can point at this one. */
  specId: string | null;
  title: string;
  dependsOn: readonly ProposalDependency[];
}

/** What a proposal in this chat that is *not* in the batch already became. */
export interface SettledProposal {
  status: ProposalStatus;
  /** The run it became, or null — pending, rejected, or failed to start. */
  runId: string | null;
}

/**
 * One resolved edge: a run that exists, or one this same pass will create.
 *
 * A discriminated union rather than two nullable ids, because the caller has to
 * do something different with each — substitute a run id it has just minted, or
 * pass one straight through — and a shape where both can be absent is a shape
 * where it can forget to check which it has.
 */
export type BatchDependency = { edge: DependencyEdge; continueBranch: boolean } & (
  | { on: "run"; runId: string }
  | { on: "proposal"; proposalId: string }
);

export type BatchStep =
  | { ok: true; id: string; title: string; dependsOn: BatchDependency[] }
  | { ok: false; id: string; title: string; reason: string };

/**
 * The order one click on Approve creates its runs in, and what each waits for.
 *
 * Pure and unit-tested, for the reason `planProposal` and `releasableRuns` are,
 * and it inherits both of their failure modes at once. A batch created in the
 * wrong order is a proposal naming a run that does not exist yet — `createRun`
 * refuses it as a missing run rather than as the ordering mistake it is, which
 * puts an artefact of what the page happened to display in front of the
 * operator as a fact about their work. A dependency silently *dropped* is
 * worse and is the one this exists for: a run told to wait for another and
 * started with no dependency at all looks exactly like a run that was never
 * told, and the two agents then work in the same checkout in the order the
 * queue felt like.
 *
 * So an unresolvable label fails its proposal **by name**, and everything
 * behind it fails too — the cascade `releasableRuns` runs one level down, for
 * the same reason: every proposal in a chain gets its own sentence naming the
 * one in front of it rather than one shared verdict about a label at the head
 * it never heard of. The rest of the batch still starts; a chain that cannot be
 * wired is not a reason to refuse unrelated work in the same click.
 *
 * What it deliberately does **not** re-decide is anything `admitDependencies`
 * already decides — at most one branch handed over, both ends isolated, no
 * rival continuation, no loop against the *live* graph. Those need rows, they
 * are checked where the edge is actually created, and a second copy here would
 * be a second set of rules to keep in step.
 */
export function planApprovalBatch(
  batch: readonly BatchProposal[],
  outside: ReadonlyMap<string, SettledProposal>,
): BatchStep[] {
  const bySpec = new Map<string, BatchProposal>();
  const duplicated = new Set<string>();
  for (const p of batch) {
    if (!p.specId) continue;
    if (bySpec.has(p.specId)) duplicated.add(p.specId);
    else bySpec.set(p.specId, p);
  }

  const failed = new Map<string, string>();
  const resolved = new Map<string, BatchDependency[]>();

  for (const p of batch) {
    if (p.specId && duplicated.has(p.specId)) {
      failed.set(
        p.id,
        `Two proposals in this batch are labelled “${p.specId}”, so a ` +
          "dependency naming it names both.",
      );
      continue;
    }

    const links: BatchDependency[] = [];
    let refusal: string | null = null;

    for (const dep of p.dependsOn) {
      if (dep.specId === p.specId) {
        refusal = `“${p.title}” is set to start after itself.`;
        break;
      }
      const sibling = bySpec.get(dep.specId);
      if (sibling) {
        links.push({
          on: "proposal",
          proposalId: sibling.id,
          edge: dep.edge,
          continueBranch: dep.continueBranch,
        });
        continue;
      }
      const settled = outside.get(dep.specId);
      if (settled?.runId) {
        links.push({
          on: "run",
          runId: settled.runId,
          edge: dep.edge,
          continueBranch: dep.continueBranch,
        });
        continue;
      }
      // Three different facts, and the operator can act on a different thing in
      // each: approve the other one too, look at why it did not start, or ask
      // the chat what it meant. Collapsing them into "unknown dependency" is
      // the sentence that sends someone to read the database.
      refusal =
        settled === undefined
          ? `“${p.title}” is set to start after “${dep.specId}”, which is not ` +
            "in this batch and is not a proposal in this chat."
          : settled.status === "pending"
            ? `“${p.title}” is set to start after “${dep.specId}”, which is ` +
              "still waiting for a decision. Approve them together."
            : `“${p.title}” is set to start after “${dep.specId}”, which was ` +
              `${settled.status} and never became a run.`;
      break;
    }

    if (refusal) failed.set(p.id, refusal);
    else resolved.set(p.id, links);
  }

  // A loop among the batch's own edges. `admitDependencies` re-runs the same
  // check against the live graph at every insert, but it would meet this one as
  // "no such run to depend on" — the first member names a sibling that has not
  // been created, because in a loop there is no first member to create.
  const byId = new Map(batch.map((p) => [p.id, p]));
  const loop = dependencyCycle(
    [...resolved].flatMap(([id, links]) =>
      links
        .filter((l) => l.on === "proposal")
        .map((l) => ({
          runId: id,
          dependsOn: (l as { proposalId: string }).proposalId,
          edge: l.edge,
        })),
    ),
  );
  if (loop) {
    const named = loop.map((id) => `“${byId.get(id)?.title ?? id}”`).join(" → ");
    for (const id of loop) {
      resolved.delete(id);
      failed.set(
        id,
        `These proposals wait for each other in a loop, so none of them could ` +
          `ever start: ${named}.`,
      );
    }
  }

  // The cascade: a proposal that cannot start is a dependency that will never
  // exist, so everything behind it cannot start either. A fixed point rather
  // than one pass, because the run behind the run behind a failure is as stuck
  // as the first one and deserves to be told so by name.
  for (let changed = true; changed; ) {
    changed = false;
    for (const [id, links] of resolved) {
      const dead = links.find(
        (l) => l.on === "proposal" && failed.has(l.proposalId),
      );
      if (!dead) continue;
      const blocker = byId.get((dead as { proposalId: string }).proposalId);
      resolved.delete(id);
      failed.set(
        id,
        `“${byId.get(id)!.title}” is set to start after “${blocker?.title ?? "another proposal"}”, ` +
          "which is not being started.",
      );
      changed = true;
    }
  }

  // Every survivor after everything it waits for, so the run a dependency names
  // exists by the time the dependent is created.
  const survivors = batch.filter((p) => resolved.has(p.id));
  const { order } = topologicalOrder({
    nodes: survivors,
    edges: [...resolved].flatMap(([id, links]) =>
      links
        .filter((l) => l.on === "proposal")
        .map((l) => ({ from: (l as { proposalId: string }).proposalId, to: id })),
    ),
  });

  const steps: BatchStep[] = order.map((id) => ({
    ok: true as const,
    id,
    title: byId.get(id)!.title,
    dependsOn: resolved.get(id)!,
  }));
  // Failures last and in the order they were proposed: the caller only tallies
  // them, and a stable order is what keeps two identical clicks reporting the
  // same thing in the same sequence.
  for (const p of batch) {
    const reason = failed.get(p.id);
    if (reason) steps.push({ ok: false, id: p.id, title: p.title, reason });
  }
  return steps;
}

/* ------------------------------------------------------------------ */
/* Approval                                                            */
/* ------------------------------------------------------------------ */

export type ApprovalOutcome =
  | { ok: true; runId: string }
  | { ok: false; reason: string };

/**
 * The two things `createRun` refuses for that will not still be true tomorrow.
 *
 * Asked *before* the call rather than told apart inside the catch below, and
 * they are both already sentences from named functions so nothing here matches
 * on a string. `dataDirRefusal` is a fact about which process holds the lock
 * right now, and `installBudgetRefusal`'s window is rolling — it clears with no
 * operator action at all — so neither is a verdict on a proposal. Marking one
 * `failed` for either destroys it: that status is terminal, `planProposal`
 * refuses anything not `pending` and the route only ever offers what is
 * pending, so a proposal refused for a condition that has since passed can
 * never be approved again, and getting the work back means a billed turn.
 *
 * Everything else `createRun` refuses for is a property of the proposal — a
 * folder outside every mount, a folder that does not exist, a template or agent
 * that has been deleted, a rival already continuing the branch — and stays
 * terminal, which is what the catch below is for.
 */
function transientRefusal(): string | null {
  // `createRun`'s own order, so the sentence read here is the one the throw
  // would have carried.
  return dataDirRefusal() ?? installBudgetRefusal();
}

/**
 * Start the run a proposal asks for.
 *
 * Synchronous from the plan to the INSERT, which is not an accident: it calls
 * `createRun`, whose folder claim is only atomic because one event-loop turn
 * covers deciding a folder is free and recording that it was taken. Approving a
 * batch is this function in a loop for the same reason — one `await` between
 * two approvals of the same folder would let both decide it was free.
 */
export function approveProposal(
  id: string,
  dependsOn: readonly RunDependencyInput[] = [],
): ApprovalOutcome {
  const proposal = getProposal(id);
  if (!proposal) return { ok: false, reason: "No such proposal." };
  if (proposal.kind !== "run") {
    // Reachable only by calling this directly; the route partitions by kind.
    // Named rather than silently planned as a run, because a workflow proposal
    // has no task and would fail with "this proposal has no task text" — a
    // sentence about the wrong thing entirely.
    return {
      ok: false,
      reason: "This proposal is a workflow, not a run.",
    };
  }

  const plan = planProposal(
    proposal,
    proposal.template_id ? getTemplate(proposal.template_id) : null,
    // Read at the *proposal* rather than at the click, which is the one of the
    // three that goes the other way and is the whole of why: the card spells
    // these values out, so re-deriving them here starts the run under whatever
    // Settings says now and the card in front of the operator says something
    // else — silently, for at least one poll interval. The template above is
    // read live because a name is a handle they can go and read; a set of
    // values is a promise. Null is a row that froze none, and that falls back
    // to the live set exactly as this line used to.
    proposalGuards(proposal) ?? chatGuards(),
    // Read at the click rather than at the proposal, which is what an id on the
    // row buys: an agent the operator has since fixed is used as it stands now,
    // and one they have since deleted is refused by name a line above.
    proposal.agent_id ? getAgent(proposal.agent_id) : null,
  );
  if (!plan.ok) {
    markProposal(id, "failed", { error: plan.reason });
    return { ok: false, reason: plan.reason };
  }

  // Before `createRun` rather than in the catch, because the catch is terminal
  // and neither of these is about this proposal. `approveRunBatch` asks the
  // same question once for a whole click, so no batch ever arrives here with
  // one of them live; what this covers is the direct caller, which must not
  // burn a proposal on a condition nobody could have acted on either.
  const transient = transientRefusal();
  if (transient) return { ok: false, reason: transient };

  try {
    const run = createRun({
      ...plan.input,
      dependsOn: [...dependsOn],
      // The proposal rather than the chat: a thread holds many proposals and
      // only one of them authorised this run. A plain id, so it keeps reading
      // true after the chat — and with it, by cascade, the proposal row — has
      // been deleted.
      origin: "chat",
      originRef: proposal.id,
    });
    markProposal(id, "approved", { runId: run.id });
    return { ok: true, runId: run.id };
  } catch (err) {
    // Everything left is a property of the proposal rather than of the moment
    // it was clicked in — the two that clear on their own were asked above.
    // `createRun` refuses a folder outside every mount and a folder that does
    // not exist; a folder merely *busy* queues instead, which is why this is a
    // failure rather than a retry.
    const reason = err instanceof Error ? err.message : String(err);
    markProposal(id, "failed", { error: reason });
    return { ok: false, reason };
  }
}

/** What approving a batch of run proposals came to. */
export interface BatchOutcome {
  started: string[];
  failed: Array<{ title: string; reason: string }>;
  /**
   * Set when the whole click was refused before anything was decided, and the
   * sentence saying why. Deliberately not a `failed` entry per proposal: those
   * are verdicts, recorded on the row and terminal, and this is the absence of
   * one — every proposal is still pending and the caller answers 400, which is
   * what the route already does with a batch holding nothing to act on.
   */
  refused?: string;
}

/**
 * Approve several run proposals at once, wiring whatever depends on what.
 *
 * Synchronous end to end and with no `await` anywhere in it, for the reason the
 * route already documents: `createRun`'s folder claim is only atomic inside one
 * event-loop turn, so two proposals for the same folder must not both get to
 * decide it is free. That property is now load-bearing twice over — a
 * dependency also has to name a run that exists, and every one it can name is
 * created in this same pass.
 *
 * A proposal whose own `createRun` throws leaves its dependents naming nothing,
 * so they are failed here by name rather than left to `createRun` to refuse as
 * a missing run. That is the same cascade `planApprovalBatch` runs for a label
 * that never resolved, arriving from the other direction: there it is a
 * dependency that was never going to exist, here it is one that was going to
 * and did not.
 *
 * The two refusals that clear on their own refuse the **click** instead, once
 * and before any of it — `refused` rather than a `failed` per member. That is
 * not a fourth validation pass over what a proposal may be: it is the one
 * question on this path whose answer is about the moment rather than the work,
 * and `admitDependencies` is left the sole owner of everything else.
 */
export function approveRunBatch(
  chatId: string,
  ids: readonly string[],
): BatchOutcome {
  const wanted = new Set(ids);
  const proposals = listProposals(chatId).filter(
    (p) => wanted.has(p.id) && p.kind === "run",
  );

  // One question for the whole click, before anything is decided, because a
  // condition that will have cleared by the time the operator looks again is
  // not a verdict on any of these proposals. Asked here rather than per member
  // for the reason the loop below has no early exit: one tripped ceiling used
  // to fail every proposal in the batch in turn, each one terminally, so a
  // single click destroyed twenty. Only when there is a run to start — a click
  // of workflow proposals alone claims no folder and spends nothing, and
  // neither condition bears on saving a graph.
  if (proposals.length > 0) {
    const transient = transientRefusal();
    if (transient) {
      return {
        started: [],
        failed: [],
        refused:
          `${transient} Nothing was decided — every proposal in this click ` +
          "is still waiting.",
      };
    }
  }

  // Every labelled proposal of this chat that is *not* in the batch, so a
  // dependency on one approved in an earlier click resolves to its run.
  const outside = new Map<string, SettledProposal>();
  for (const p of listProposals(chatId)) {
    if (wanted.has(p.id) || !p.spec_id) continue;
    outside.set(p.spec_id, { status: p.status, runId: p.run_id });
  }

  const steps = planApprovalBatch(
    proposals.map((p) => ({
      id: p.id,
      specId: p.spec_id,
      title: p.title,
      dependsOn: proposalDeps(p),
    })),
    outside,
  );

  const started: string[] = [];
  const failed: Array<{ title: string; reason: string }> = [];
  /** What each proposal in this pass became, for the ones behind it. */
  const minted = new Map<string, string>();
  const stillborn = new Map<string, string>();

  for (const step of steps) {
    if (!step.ok) {
      markProposal(step.id, "failed", { error: step.reason });
      failed.push({ title: step.title, reason: step.reason });
      continue;
    }

    const dead = step.dependsOn.find(
      (d) => d.on === "proposal" && !minted.has(d.proposalId),
    );
    if (dead) {
      const reason =
        `“${step.title}” is set to start after “${stillborn.get((dead as { proposalId: string }).proposalId) ?? "another proposal"}”, ` +
        "which could not be started.";
      markProposal(step.id, "failed", { error: reason });
      stillborn.set(step.id, step.title);
      failed.push({ title: step.title, reason });
      continue;
    }

    const res = approveProposal(
      step.id,
      step.dependsOn.map((d) => ({
        runId: d.on === "run" ? d.runId : minted.get(d.proposalId)!,
        edge: d.edge,
        continueBranch: d.continueBranch,
      })),
    );
    if (res.ok) {
      minted.set(step.id, res.runId);
      started.push(res.runId);
    } else {
      stillborn.set(step.id, step.title);
      failed.push({ title: step.title, reason: res.reason });
    }
  }

  return { started, failed };
}

export function rejectProposal(id: string): boolean {
  const res = db()
    .prepare(
      "UPDATE chat_proposals SET status='rejected', decided_at=? WHERE id=? AND status='pending'",
    )
    .run(Date.now(), id);
  return res.changes > 0;
}

/** What one click on Approve or Reject did, in the terms the thread records it. */
export interface DecisionTally {
  action: "approve" | "reject";
  started: number;
  rejected: number;
  /**
   * `kind` is what the sentence's verb comes from: a run proposal could not be
   * *started* and a workflow proposal could not be *saved*, and telling an
   * operator a workflow "could not be started" describes an attempt this app
   * never makes.
   */
  failed: Array<{ title: string; reason: string; kind?: ProposalKind }>;
  /**
   * Workflow proposals approved, which **saved** a workflow and started
   * nothing. Counted apart from `started` rather than added to it: a sentence
   * that says "approved and queued 3 runs" about two runs and a saved graph is
   * a claim that agents are working, which is the one thing this note exists to
   * report honestly.
   */
  saved: number;
  /** Proposals of this chat that are no longer pending. */
  decided: number;
  /** Ids naming no proposal of this chat — another thread's, or gone. */
  foreign: number;
}

/**
 * The sentence a decision is recorded by — a note in the thread when something
 * happened, and the refusal when nothing did.
 *
 * Pure and unit-tested because it is the *only* account the operator gets of a
 * click that acted on nothing. The route's scoping to `pendingProposals(id)`
 * already stops a stale id being approved, so what is left to get wrong is a
 * true 200 carrying a false explanation: `decided` and `foreign` are two
 * different facts, and reporting the second as the first tells one thread that
 * proposals still waiting in another were "already decided". Nothing throws on
 * that and nothing typechecks it away — it is a permanent, wrong line in a
 * conversation the operator later reads back as a record of what they did.
 */
export function decisionNote(t: DecisionTally): string {
  const parts = [
    t.started > 0 ? `Approved and queued ${t.started} run(s).` : "",
    t.saved > 0
      ? `Saved ${t.saved} workflow(s). Nothing is running — open one and press ` +
        "Run when you want it to."
      : "",
    t.rejected > 0 ? `Rejected ${t.rejected} proposal(s).` : "",
    ...t.failed.map(
      (f) =>
        `Could not ${f.kind === "workflow" ? "save" : "start"} “${f.title}”: ${f.reason}`,
    ),
    t.decided > 0
      ? `${t.decided} proposal(s) had already been decided and were left alone.`
      : "",
    t.foreign > 0
      ? `${t.foreign} selected proposal(s) are not in this chat and were left alone.`
      : "",
  ].filter(Boolean);

  // Nothing moved, so the first thing said has to be that nothing moved. Left
  // to the clauses above, a batch that did nothing reads as a report of two
  // proposals it declined to touch, which is what "the button appears to have
  // done nothing" looks like from the thread.
  const acted =
    t.started > 0 || t.saved > 0 || t.rejected > 0 || t.failed.length > 0;
  if (!acted && parts.length > 0) {
    parts.unshift(
      t.action === "approve" ? "Nothing was approved." : "Nothing was rejected.",
    );
  }

  return parts.join(" ");
}

/**
 * Record what became of a proposal.
 *
 * Exported because a workflow proposal settles onto `workflow_id` and the
 * function that knows how to build a workflow lives in `workflows.ts`, which
 * imports this module. One writer either way — a second UPDATE over these
 * columns is a second place to forget `decided_at`, which is what stops a
 * decided proposal being offered for decision again.
 */
export function markProposal(
  id: string,
  status: ProposalStatus,
  o: { runId?: string; workflowId?: string; error?: string },
): void {
  db()
    .prepare(
      "UPDATE chat_proposals SET status=?, decided_at=?, run_id=?," +
        " workflow_id=?, error=? WHERE id=?",
    )
    .run(
      status,
      Date.now(),
      o.runId ?? null,
      o.workflowId ?? null,
      o.error ?? null,
      id,
    );
}

/* ------------------------------------------------------------------ */
/* The capability token                                                */
/* ------------------------------------------------------------------ */

/**
 * Who a bearer token speaks for.
 *
 * Two kinds now, and they are deliberately a discriminated union rather than a
 * pair of optional ids: `/api/mcp` publishes a *different tool list* to each —
 * a chat may propose and save templates, an orchestrator block may emit runs
 * and neither may do the other's — and a shape where both ids can be absent is
 * a shape where the route can forget to check which it has.
 */
export type CapabilitySubject =
  | { kind: "chat"; chatId: string }
  | { kind: "block"; instanceId: string; nodeId: string };

/**
 * What lets an orchestrator child call back into this server, and nothing else.
 *
 * `/api/mcp` is exempt from `middleware.ts` because the middleware runs in the
 * edge runtime and cannot reach SQLite to check a per-turn credential — so the
 * route authenticates itself, and this is the thing it checks. Deliberately
 * **not** `UF_AUTH_TOKEN`: that one opens every route in the app, and handing it
 * to a child would undo the reason `gitEnv`/`reviewEnv`/`childEnv` all strip
 * `UF_*` in the first place.
 *
 * In memory only, and revoked the moment the turn's child exits. It never
 * outlives the process that minted it, which is the property that makes it
 * cheap: a token recovered from a `ps` listing after the fact opens nothing.
 * On `globalThis` for the reason every other long-lived singleton here is —
 * `next dev` would otherwise re-evaluate the module and invalidate a live
 * child's credential mid-turn.
 */
interface Capability {
  subject: CapabilitySubject;
  expiresAt: number;
}

const caps = ((globalThis as unknown as { __ufChatCaps?: Map<string, Capability> })
  .__ufChatCaps ??= new Map<string, Capability>());

export function mintCapability(subject: CapabilitySubject): string {
  const token = randomBytes(32).toString("base64url");
  caps.set(token, { subject, expiresAt: Date.now() + CHAT_TIMEOUT_MS + 60_000 });
  return token;
}

export function revokeCapability(token: string): void {
  caps.delete(token);
}

/**
 * What a bearer token speaks for, or null.
 *
 * Compared in constant time against every live token rather than looked up by
 * key: a `Map.get` on a secret leaks its prefix through timing, and the number
 * of live tokens here is the number of orchestrator turns in flight — one chat
 * turn, plus whatever blocks of a workflow are deciding right now.
 */
export function subjectForCapability(token: string): CapabilitySubject | null {
  if (!token) return null;
  const offered = Buffer.from(token);
  const now = Date.now();
  let found: CapabilitySubject | null = null;

  for (const [candidate, cap] of caps) {
    if (cap.expiresAt < now) {
      caps.delete(candidate);
      continue;
    }
    const known = Buffer.from(candidate);
    if (
      known.length === offered.length &&
      timingSafeEqual(known, offered)
    ) {
      found = cap.subject;
    }
  }
  return found;
}

/* ------------------------------------------------------------------ */
/* The turn                                                            */
/* ------------------------------------------------------------------ */

export type ChatOutcome = { ok: true } | { ok: false; reason: string };

const ALREADY_THINKING: ChatOutcome = {
  ok: false,
  reason: "This chat is still working on the last message.",
};

/**
 * Take the turn, or return null because this chat is already in one.
 *
 * A conditional UPDATE whose `changes` count decides, exactly as `startRun`
 * claims a queued run. Reading the status and then writing it is the
 * check-then-act shape `createRun`'s folder claim is built to avoid, and here
 * the two halves were separated by `await assistRefusal()` — a full transcript
 * scan, seconds long on a large `~/.claude`. Every message that arrived inside
 * that window read `idle` and started a second billed child on the same
 * conversation, with a second capability token live beside the first and
 * `status` left last-write-wins between them.
 *
 * `<> 'thinking'` rather than `= 'idle'`: a turn that failed leaves the row
 * `failed`, and the next message is how an operator retries it.
 *
 * `turn_started_at` is written by this same statement rather than beside it,
 * for the same reason the claim is a single statement at all: it is what
 * `staleTurn` reads, and a turn that became unstoppable between two writes is
 * exactly the turn that has to have a deadline on it.
 *
 * `turn_seq` likewise, and for the stronger version of the same reason: it is
 * the turn's identity, so a turn that existed before it had one is a turn whose
 * child could settle somebody else's row.
 *
 * Returns the row as it stood at the claim, because a read taken before that
 * await is stale by definition — `session_id` above all, which decides whether
 * the turn resumes the conversation or pays to replay the thread, and
 * `turn_seq`, which is what the child spawned below settles under.
 */
function claimTurn(chatId: string): ChatRow | null {
  const now = Date.now();
  const claim = db()
    .prepare(
      // The four per-turn columns are cleared in the same statement that takes
      // the turn, for `error`'s reason: they describe the turn the row is on,
      // and a value surviving into the next one is the previous turn's text
      // and the previous turn's money attributed to this one.
      `UPDATE chat_sessions
          SET status='thinking', error=NULL, updated_at=?, turn_started_at=?,
              turn_seq = turn_seq + 1,
              partial_text=NULL, partial_at=NULL,
              turn_tokens=0, turn_cost_est=0
        WHERE id=? AND status<>'thinking'`,
    )
    .run(now, now, chatId);
  return claim.changes === 1 ? getChat(chatId) : null;
}

/** stdin is "ignore", so the child has readable stdout/stderr and no stdin. */
export type ChatProcess = ChildProcessByStdio<null, Readable, Readable>;

/**
 * The chats with a child this process can still signal.
 *
 * The row says a turn is in flight; this says whether anything is still there
 * to stop. The two disagree exactly when a turn is stranded — which is the
 * state this map exists to make recoverable rather than to prevent. On
 * `globalThis` for the reason every other long-lived singleton here is: a dev
 * hot reload would otherwise re-evaluate the module and lose the handle on a
 * live child, leaving the operator with an unstoppable turn and a billed agent.
 */
const turns = ((globalThis as unknown as {
  __ufChatTurns?: Map<string, ChatProcess>;
}).__ufChatTurns ??= new Map<string, ChatProcess>());

const sweeper = ((globalThis as unknown as {
  __ufChatSweep?: { timer: NodeJS.Timeout | null };
}).__ufChatSweep ??= { timer: null });

/**
 * What the row and the thread say afterwards. The three causes must not read
 * alike — each is a different thing for the operator to do next — and each is
 * one constant because the row's copy and the conversation's copy of the same
 * ending drifting apart is a thread that contradicts itself.
 */
const CANCELLED_REASON =
  "You stopped this message while it was being answered.";
const TIMED_OUT_REASON =
  `The chat did not answer within ${CHAT_TIMEOUT_MS / 60_000} minutes and was stopped.`;
/** `reconcileChatsOnBoot`'s, hoisted so the row and the thread cannot drift. */
const RESTARTED_REASON =
  "The server restarted while this message was being answered.";

/**
 * Whether a turn has outlived the bound on one, given the row and the clock.
 *
 * Pure and unit-tested, for the reason `landRefusal` and `planItem` are: every
 * way of getting it wrong is silent. Too eager and a legitimate three-minute
 * turn is failed out from under a live child; never true and the ten-minute
 * bound quietly stops existing, which is the state this issue started from —
 * a thread that says "Thinking…" for ever with nothing in the process able to
 * move it.
 */
export function staleTurn(
  chat: Pick<ChatRow, "status" | "turn_started_at" | "updated_at">,
  now: number,
): boolean {
  if (chat.status !== "thinking") return false;
  // A row that was already `thinking` when this column was added has no start
  // instant. `updated_at` is the conservative stand-in — mid-turn writes only
  // ever move it forward, so the fallback waits longer than the real deadline
  // rather than ending a turn early.
  const startedAt = chat.turn_started_at ?? chat.updated_at;
  return now - startedAt >= CHAT_TIMEOUT_MS + STALE_TURN_MARGIN_MS;
}

/**
 * End a turn now, and signal whatever is still running it.
 *
 * The row is settled *here* rather than when the child closes, which is the
 * whole point: the turns that need ending are the ones whose `close` is not
 * coming. `finishTurn` latches on this turn's own `turn_seq` as well as on
 * `status='thinking'`, so a `close` that does arrive afterwards cannot move the
 * row back, overwrite what this said, or — because the operator is invited to
 * retry the instant this returns — settle the turn that replaced it.
 *
 * The signal ladder is `interruptRun`'s, and SIGINT leads for the same reason:
 * it is the signal a CLI is most likely to handle deliberately, and a chat turn
 * is spawned `detached` under the same `killProcessGroup` setting an agent is,
 * so what has to die is the group rather than the wrapper.
 *
 * Each step re-checks that *this* child is still running rather than that it is
 * still the registered one, which is where this diverges from `interruptRun`:
 * the row is usable the instant this returns, so the operator can send a new
 * message — and register a new child under the same id — while the old one is
 * still working through the ladder. Not `child.killed`, which records only that
 * a signal was sent and is already true by the second step.
 */
/**
 * Keep what a turn had produced when it is ending without a verdict.
 *
 * Three endings reach this and none of them gets a `result` event: a cancel, a
 * timeout, and the install ceiling closing on a turn that is still going. A
 * fourth — a restart — reaches it from `reconcileChatsOnBoot`. Before the child
 * streamed there was nothing to keep: the text existed in the dead process's
 * memory and the money existed nowhere at all, so the install's rolling ceiling
 * never learned it had been spent, which is the one direction a ceiling must
 * never move by accident.
 *
 * Two figures and they are deliberately different kinds of number.
 * `turn_tokens` is what the CLI itself reported and is **measured**, so it goes
 * straight into the thread's count. `turn_cost_est` is this app's own price for
 * those tokens and is a **guard** figure, so it lands in `cost_usd_est` beside
 * the total and never inside it, and the `chat_turn_spend` row it writes is
 * marked `estimated` so `installSpend` can put it in the guard reading and keep
 * it out of the shown one. That is `runs.spent_usd_est`'s rule, one table over.
 *
 * The text becomes an ordinary assistant message, because a half-answer that
 * the operator can read is worth more than a note saying one existed — and
 * because the sentence the caller appends afterwards refers to it.
 */
function keepPartialTurn(chatId: string): void {
  const row = getChat(chatId);
  if (!row) return;

  const text = (row.partial_text ?? "").trim();
  const tokens = row.turn_tokens ?? 0;
  const estimate = row.turn_cost_est ?? 0;
  if (!text && tokens === 0 && estimate === 0) return;

  db()
    .prepare(
      `UPDATE chat_sessions
          SET partial_text=NULL, partial_at=NULL, turn_tokens=0, turn_cost_est=0,
              tokens = tokens + ?, cost_usd_est = cost_usd_est + ?
        WHERE id=?`,
    )
    .run(tokens, estimate, chatId);

  if (estimate > 0) {
    db()
      .prepare(
        "INSERT INTO chat_turn_spend (chat_id, ts, cost_usd, estimated)" +
          " VALUES (?, ?, ?, 1)",
      )
      .run(chatId, Date.now(), estimate);
  }

  if (text) appendMessage(chatId, "assistant", text);
}

function endTurn(chatId: string, error: string): boolean {
  const changed =
    db()
      .prepare(
        "UPDATE chat_sessions SET status='failed', error=?, updated_at=?," +
          " turn_started_at=NULL WHERE id=? AND status='thinking'",
      )
      .run(error, Date.now(), chatId).changes > 0;
  // Whatever the turn had said, before the sentence about how it ended — in
  // that order, because the note reads as a footnote to the half-answer above
  // it and the other way round it reads as a note followed by an answer that
  // arrived afterwards.
  if (changed) keepPartialTurn(chatId);
  // In the thread as well as on the row: the conversation should read as what
  // happened to it, and a turn that stops without a word looks like an answer
  // that never came.
  if (changed) appendMessage(chatId, "system", error);

  const child = turns.get(chatId);
  if (!child) return false;

  const running = () => child.exitCode === null && child.signalCode === null;
  signalTree(child, "SIGINT");
  setTimeout(() => {
    if (running()) signalTree(child, "SIGTERM");
  }, 3_000).unref?.();
  setTimeout(() => {
    if (running()) signalTree(child, "SIGKILL");
  }, 8_000).unref?.();
  return true;
}

export type CancelOutcome =
  | { ok: true; outcome: "signalled" | "cleared" }
  | { ok: false; reason: string };

/**
 * Stop the turn a chat is waiting on, from the page.
 *
 * The counterpart to `stopRun`, and it reports the same distinction for the
 * same reason: `signalled` means a child was told to stop, `cleared` means
 * there was nothing left to stop and only the row needed clearing. Both are
 * successes — reporting the second as a failure (which a bare boolean would)
 * makes a working button look broken in precisely the case it was added for.
 *
 * It does not send anything, and it deliberately leaves the `thinking` guard in
 * `sendChatMessage` alone: that guard is what stops two billed children on one
 * conversation, and the recovery is a way to *end* the turn, not around it.
 */
export function cancelChatTurn(chatId: string): CancelOutcome {
  const chat = getChat(chatId);
  if (!chat) return { ok: false, reason: "No such chat." };
  if (chat.status !== "thinking") {
    return { ok: false, reason: "This chat is not working on a message." };
  }
  return {
    ok: true,
    outcome: endTurn(chatId, CANCELLED_REASON) ? "signalled" : "cleared",
  };
}

/**
 * Fail out every turn that has outlived the bound.
 *
 * The backstop under the in-closure timer in `runTurn`, which cannot be one:
 * that timer signals the child and then waits for `close`, so it rescues
 * nothing when `close` is what went missing, and it does not exist at all for a
 * turn whose child was never spawned. This reads the row instead, so the
 * ten-minute bound holds however the turn was lost.
 *
 * Nothing is resumed or re-asked — same rule `reconcileChatsOnBoot` follows,
 * and for the same reason: a chat turn is a question somebody put minutes ago,
 * and re-asking it unattended is spend nobody is present to want.
 */
function sweepStuckChats(): void {
  const thinking = db()
    .prepare("SELECT * FROM chat_sessions WHERE status='thinking'")
    .all() as ChatRow[];
  if (thinking.length === 0) {
    stopChatSweeper();
    return;
  }
  const now = Date.now();
  for (const chat of thinking) {
    if (staleTurn(chat, now)) endTurn(chat.id, TIMED_OUT_REASON);
  }
}

/** Lazily started when a turn begins, stopped when none is left to watch. */
function startChatSweeper(): void {
  if (sweeper.timer) return;
  sweeper.timer = setInterval(sweepStuckChats, CHAT_SWEEP_MS);
  sweeper.timer.unref?.();
}

function stopChatSweeper(): void {
  if (!sweeper.timer) return;
  clearInterval(sweeper.timer);
  sweeper.timer = null;
}

/** One open question and what the operator typed or picked for it. */
export interface QuestionAnswer {
  id: string;
  answer: string;
}

/**
 * Send a message and return as soon as the child is on its way.
 *
 * The child outlives the request for the reason a review's does: it runs for
 * minutes and holding an HTTP connection open for it fails behind any proxy.
 * The row is the handle, and the page polls it.
 *
 * `answers` is what makes this the *only* door a turn starts from, rather than
 * the answer route growing a second copy of the claim, the two spend gates and
 * the no-`await` window. An answer is a message; what is different about it is
 * only which rows it settles, and those are settled inside the same window the
 * message is appended in — so a request that loses the claim marks nothing
 * answered, exactly as it appends nothing.
 */
export async function sendChatMessage(
  chatId: string,
  message: string,
  answers: readonly QuestionAnswer[] = [],
): Promise<ChatOutcome> {
  // A turn is a billed child and a claim on a row in a shared table, and the
  // claim is only a claim because one process makes it. Refused ahead of
  // everything else, so a second server neither spends nor strands the thread
  // at `thinking`.
  const notOwner = dataDirRefusal();
  if (notOwner) return { ok: false, reason: notOwner };

  const chat = getChat(chatId);
  if (!chat) return { ok: false, reason: "No such chat." };
  // Answers the common case without paying for a transcript scan first. It
  // decides nothing — `claimTurn` below is the check that holds.
  if (chat.status === "thinking") return ALREADY_THINKING;

  const text = message.trim();
  if (!text) return { ok: false, reason: "Nothing to send." };

  // The same gate a review passes: the operator's own configured ceiling is
  // already spent. A chat turn spends against the same window as everything
  // else, and unlike a run it goes through no `evaluateBudget` — there is no
  // per-chat fraction and inventing one would be a threshold nobody set.
  // …and the install-wide ceiling, which is the one limit in this app a chat
  // turn was never measured against at all: `chatTurnBudgetUSD` bounds *this*
  // turn and nothing bounds the hundredth.
  const refusal = (await assistRefusal()) ?? installBudgetRefusal();
  if (refusal) return { ok: false, reason: refusal };

  // From here to the spawn there is deliberately no `await`: one event-loop
  // turn covers claiming the chat, recording the message and starting the
  // child, so a request that loses the claim adds nothing to the thread.
  const claimed = claimTurn(chatId);
  if (!claimed) return ALREADY_THINKING;

  appendMessage(chatId, "user", text);
  settleOpenQuestions(chatId, answers);
  const history = listMessages(chatId)
    .slice(0, -1)
    .map((m) => ({ role: m.role, text: m.text }));

  // The sweeper watches `thinking` rows, and this row became one at the claim
  // above — which is also where `turn_started_at` was written, in that same
  // statement, so the deadline exists from the instant the turn does.
  startChatSweeper();

  const prompt = chatPrompt({ sessionId: claimed.session_id, history }, text);

  // The child outlives this call: it runs for minutes and the row is what
  // reports on it, so nothing here waits for it.
  //
  // Wrapped, because `runTurn` is not `async`: it mints the capability and
  // writes the MCP config synchronously, so a throw from either happens right
  // here. Unhandled, it would propagate out of this function with the row
  // already claimed as `thinking` — a state nothing but a restart clears, and
  // one this function refuses to send into.
  try {
    runTurn(claimed, prompt);
  } catch (err) {
    const reason = `Could not start the turn: ${
      err instanceof Error ? err.message : String(err)
    }`;
    finishTurn(chatId, claimed.turn_seq, { status: "failed", error: reason });
    return { ok: false, reason };
  }

  return { ok: true };
}

/**
 * Answer what the chat asked, and start the turn that reads the answers.
 *
 * The counterpart to the composer, and the reason it is a second entry point
 * rather than a second implementation: everything that bounds a turn —
 * `dataDirRefusal`, `assistRefusal`, the install ceiling, the claim, the
 * sweeper — is in `sendChatMessage`, and an answer that reached the CLI around
 * any of them would be a route to spend nobody gated. All this adds is the two
 * things only this door knows: which rows are being settled, and what the
 * message the model reads has to say.
 *
 * **It refuses the whole call when any id is not open**, which is
 * `settleQuestions`' rule and not the proposals route's. There the ids are
 * independent, so a stale one is dropped and reported; here they compose one
 * message, and dropping one means the operator's typed answer is silently
 * absent from the text the model reads — which is worse than the refusal,
 * because the model then proposes on a question it thinks nobody answered.
 *
 * An empty list is refused for the reason an empty approval batch is: a 200
 * that started a billed turn saying nothing was answered is indistinguishable
 * from one that worked, and a caller that clears its state on `res.ok` has no
 * way to tell them apart.
 */
export async function answerChatQuestions(
  chatId: string,
  answers: readonly QuestionAnswer[],
): Promise<ChatOutcome> {
  const chat = getChat(chatId);
  if (!chat) return { ok: false, reason: "No such chat." };

  const given = answers.flatMap((a) => {
    const answer = a.answer.trim();
    return answer ? [{ id: a.id, answer }] : [];
  });
  if (given.length === 0) {
    return { ok: false, reason: "Nothing to answer." };
  }

  const settlement = settleQuestions(pendingQuestions(chatId), given);
  if (!settlement.ok) return { ok: false, reason: settlement.reason };

  return sendChatMessage(
    chatId,
    answerMessage(settlement.entries),
    settlement.answered,
  );
}

export interface TurnResult {
  status: "idle" | "failed";
  text?: string;
  error?: string;
  costUSD?: number;
  tokens?: number;
  sessionId?: string | null;
  denials?: string[];
}

/** Everything one headless orchestrator turn differs from another by. */
export interface OrchestratorChildOptions {
  /** What its capability token speaks for, and so which tools it is offered. */
  subject: CapabilitySubject;
  prompt: string;
  /** The role, stated. This is the boundary — see `systemPrompt`. */
  appendSystemPrompt: string;
  /** A conversation to continue, or null for a one-shot turn. */
  resumeSessionId?: string | null;
  /**
   * Where the child runs. Defaults to the first mount, which is what a chat
   * wants; a workflow block passes its own folder so `Read` and `git log` land
   * on the repository it was pointed at. Every mount is `--add-dir`ed either
   * way, so this widens nothing — it only decides where a bare path resolves.
   */
  cwd?: string;
  /**
   * The agent this turn **is**, or null.
   *
   * Selected rather than offered — `sessionAgentArgs` emits the definition and
   * picks it by name, so the saved prompt is the turn's own. Nothing here widens
   * the turn's boundary: its tool surface is still whatever `/api/mcp` publishes
   * for its subject, `--strict-mcp-config` and the capability token are
   * untouched, and the spend still lands inside `--max-budget-usd` below.
   *
   * Only one of this function's two callers ever passes one. A workflow's
   * orchestrator block hands over the agent its node names, which is the whole
   * point of that field; `runTurn` withholds one, and the note there is the
   * reason rather than an omission.
   */
  agent?: AgentDefinition | null;
  /** `--max-budget-usd`, the only thing bounding the spend inside the CLI. */
  maxBudgetUSD: number | null;
  timeoutMs: number;
  /** What the row says when the timeout is what ended it. */
  timedOutMessage: string;
  /** Called with the child the moment it exists, so a caller can signal it. */
  onSpawn?: (child: ChatProcess) => void;
  /**
   * Called as the turn produces output, with what has arrived so far.
   *
   * Optional, and only the chat passes one: a workflow's orchestrator block has
   * no surface anybody watches while it runs and nothing to recover from a
   * crash — its runs are what it produces, and they are created after it
   * settles. The flags say what moved, so a caller can persist on the events
   * that changed something rather than on every line: a turn reading a large
   * file produces hundreds of `user` events carrying tool output and the
   * operator is waiting on none of them.
   */
  onProgress?: (
    acc: ChatTurnAccumulator,
    moved: { textGrew: boolean; spendGrew: boolean },
  ) => void;
  /** Called exactly once, whatever happened. */
  onSettle: (result: TurnResult) => void;
}

/**
 * Spawn one headless orchestrator turn.
 *
 * **The fourth kind of child process, invoked a second way — not a fifth kind.**
 * `review.ts` says adding a third was a decision rather than a detail, and the
 * chat says the same of the fourth. A workflow's orchestrator block is the same
 * child with the same argv, the same environment, the same capability token and
 * the same MCP config file; what differs is that there is no thread to resume
 * and nobody typing. That is why this function exists rather than a second
 * `spawn` call site: two of those would be two sets of flags to keep in step,
 * and the flags are what bound the child.
 *
 * Everything about *what* it may do is a caller's argument — the subject decides
 * its tool list, the system prompt states its role — and everything about how it
 * is contained is here and identical for both.
 */
export function runOrchestratorChild(o: OrchestratorChildOptions): void {
  const token = mintCapability(o.subject);
  let configPath: string;
  try {
    configPath = writeMcpConfig(token);
  } catch (err) {
    // `land` is the only thing that revokes, and it is inside the promise this
    // never reaches — so a token minted for a turn that cannot start would
    // stay live in memory until it expired, an hour later. The caller records
    // the failure on the row; this releases what the failed setup took.
    revokeCapability(token);
    throw err;
  }

  const settings = getSettings();
  const args = [
    "-p",
    o.prompt,
    // Line-delimited events rather than one object at exit, and the reason is
    // durability rather than presentation. Under `json` the whole turn — the
    // assistant's text, the cost, the session id — existed only in this
    // process's memory until the child was done, so a restart in the middle
    // lost all of it together while the money stayed spent, and the page had a
    // spinner and nothing else for as long as the turn ran. The run loop has
    // used this format since it was written, for `emit()`'s reason: persist,
    // then publish, and reconnect is lossless because of the order.
    //
    // `--verbose` is not optional beside it — the CLI gates streaming output on
    // the pair, and without it this prints nothing until the end exactly as
    // before, which would be the same defect with a different flag on it.
    "--output-format",
    "stream-json",
    "--verbose",
    // Every tool the CLI has, with the system prompt above as the boundary
    // rather than a list of names.
    //
    // This used to be `manual` plus an allowlist — this app's tools,
    // `Read`/`Glob`/`Grep`, read-only `gh` and three `git` subcommands — and
    // that allowlist was the whole guarantee, because `plan` (what
    // `review.ts` uses) refuses MCP tool calls outright ("Cannot call
    // mcp__uf__list_templates while in plan mode") and would leave the chat
    // able to see GitHub and not this app. Its cost was every question the
    // list did not anticipate: a build log, a test run, `gh api`, `git -C
    // <path> log`, anything compound. Each came back refused, and an
    // orchestrator that cannot look proposes work badly — which is the one
    // failure this feature has no other defence against, since a bad
    // proposal is approved by a person who is trusting it to have looked.
    //
    // `bypassPermissions` rather than `acceptEdits`: that mode holds every
    // mutating shell command for an approval a `-p` child has nobody to give
    // — measured, in the isolated-run failure that `ISOLATED_GIT_TOOLS`
    // exists to fix — so it would reproduce exactly the refusals this is
    // removing, only less predictably.
    //
    // What bounds this child is therefore not the mode. Its tool surface is
    // whatever `/api/mcp` publishes for its *subject* — a chat may propose,
    // an orchestrator block may emit, and neither can start a run under
    // guards it chose; `--strict-mcp-config` keeps the mounted `~/.claude`'s
    // own MCP servers out; the capability token dies with the turn; and
    // `chatTurnBudgetUSD` caps the spend. It can, however, write to the
    // mounts and reach GitHub with the token in its environment, and the
    // chat page says so.
    "--permission-mode",
    "bypassPermissions",
    "--mcp-config",
    configPath,
    // Without this, an MCP server configured in the mounted ~/.claude joins
    // this child — a tool surface the operator never granted this feature.
    "--strict-mcp-config",
    "--append-system-prompt",
    o.appendSystemPrompt,
  ];

  // Access to the mounts, so "look at what this repo is like" works. Under
  // `bypassPermissions` this is no longer read-only, which is the half of
  // the trade above that costs something: a chat told to leave the work
  // alone is now the only thing stopping it from editing a checkout.
  const addDirs = WORKSPACE_MOUNTS.filter((m) => fs.existsSync(m.path)).map(
    (m) => m.path,
  );
  for (const dir of addDirs) args.push("--add-dir", dir);

  // The one allowlist this child carries, and it grants nothing: naming
  // `Grep` and `Glob` is what makes the pinned CLI offer them at all, and
  // under `bypassPermissions` there is no prompt for them to skip. Without
  // it an orchestrator asked to look at a repository has `Read` and no way
  // to find out what to read — which is the failure the mode above was
  // chosen to prevent, arriving through the tool list instead of the
  // permission system.
  args.push("--allowedTools", ...SEARCH_TOOLS);

  // And the same list again as this child's write set, if anything confines
  // it at all. The same encoder the work cycle and the reviewer use, and
  // deliberately the widest of the three sets it produces: this child is
  // `bypassPermissions` with every mount already on its argv above, so a
  // narrower write set would be this app disagreeing with itself one line
  // later — an orchestrator refused inside a tool call, on a directory it was
  // handed on purpose. What bounds it is its MCP tool surface, a capability
  // that dies with the turn and `chatTurnBudgetUSD`, not its filesystem.
  args.push(...sandboxArgsFor({ kind: "chat", dirs: addDirs }));

  // One encoder for every spawn site, so there is one place that knows the
  // shape — silent when a member is only offered, a failed spawn when it is
  // selected. The appended system prompt above still reaches a session started
  // this way (measured on the pin), which is what keeps the boundary this
  // child is bounded by in front of it.
  args.push(...sessionAgentArgs(o.agent));

  if (o.resumeSessionId) args.push("--resume", o.resumeSessionId);
  if (settings.defaultModel) args.push("--model", settings.defaultModel);
  if (o.maxBudgetUSD !== null) {
    // A hard stop inside the CLI. Everything else here bounds a *run*; this
    // is the only thing bounding an orchestrator turn, which can otherwise
    // read issues and repositories for as long as it likes.
    args.push("--max-budget-usd", String(o.maxBudgetUSD));
  }

  // No shell, as everywhere else: the prompt is operator text and whatever a
  // GitHub issue body happens to contain.
  const child = spawn(CLAUDE_BIN, args, {
    cwd: o.cwd && fs.existsSync(o.cwd) ? o.cwd : chatCwd(),
    env: chatEnv(),
    // Dropped like every other child, and this is the one that most needs it:
    // it runs `bypassPermissions` with no allowlist, so the only thing between
    // it and the server's own files is that it is not the server's uid.
    //
    // The agents' uid and *not* their gid: the group is what carries this
    // turn's capability file, which every other child is kept out of.
    ...chatChildCredentials(),
    stdio: ["ignore", "pipe", "pipe"],
    detached: settings.killProcessGroup && process.platform !== "win32",
  });

  // Registered before anything can go wrong with it, so an operator pressing
  // Stop reaches the child rather than orphaning it.
  o.onSpawn?.(child);

  // Folded line by line rather than buffered whole: the accumulator *is* the
  // turn's state now, and the caller's `onProgress` is what makes it durable.
  // The raw buffer is kept only for the failure path, where the useful thing
  // is whatever the CLI actually printed.
  const acc = newChatTurnAccumulator();
  let stdoutBuf = "";
  let stderr = "";
  child.stdout.setEncoding("utf8");
  child.stderr.setEncoding("utf8");
  child.stdout.on("data", (chunk: string) => {
    stdoutBuf += chunk;
    let nl: number;
    while ((nl = stdoutBuf.indexOf("\n")) !== -1) {
      const line = stdoutBuf.slice(0, nl).trim();
      stdoutBuf = stdoutBuf.slice(nl + 1);
      if (!line) continue;
      const moved = readChatEvent(acc, line);
      if (moved.textGrew || moved.spendGrew) o.onProgress?.(acc, moved);
    }
  });
  child.stderr.on("data", (c: string) => (stderr += c.slice(0, 4_096)));

  let timedOut = false;
  const timer = setTimeout(() => {
    timedOut = true;
    signalTree(child, "SIGTERM");
    setTimeout(() => signalTree(child, "SIGKILL"), 5_000).unref?.();
  }, o.timeoutMs);
  timer.unref?.();

  let settled = false;
  const land = (result: TurnResult) => {
    if (settled) return;
    settled = true;
    clearTimeout(timer);
    // Both of these are why the token is worth having: the credential dies
    // with the turn, and the file that carried it does not outlive it either.
    revokeCapability(token);
    removeMcpConfig(configPath);
    o.onSettle(result);
  };

  child.on("error", (err) => {
    land({ status: "failed", error: `Could not launch ${CLAUDE_BIN}: ${err.message}` });
  });

  settleOnExit(child, (code) => {
    // A last line with no newline after it. The CLI terminates the `result`
    // event, but a child killed mid-write does not, and a turn's whole answer
    // sitting unparsed in a buffer is exactly what this file is being changed
    // to stop happening.
    const tail = stdoutBuf.trim();
    if (tail) readChatEvent(acc, tail);

    // Counted, never dropped: a CLI that renames an event goes on producing
    // turns that look thinner rather than turns that fail, which is the
    // asymmetry `chatStream.ts` refuses to add a third parser to.
    if (acc.unknownTypes.size > 0 || acc.unreadable > 0) {
      opsLog("warn", "chat.stream_unread", {
        unknown_types: [...acc.unknownTypes].join(",") || null,
        unreadable_lines: acc.unreadable,
      });
    }

    if (timedOut) {
      land({ status: "failed", error: o.timedOutMessage });
      return;
    }
    land(turnResultOf(acc, stderr, code));
  });
}

/**
 * One chat turn: the shared child, wired to this chat's row — and the one caller
 * of `runOrchestratorChild` that names no agent.
 *
 * Everything that decides what the child *is* lives in `runOrchestratorChild`;
 * what is left here is what makes it a conversation — the session to resume, the
 * registry an operator's Stop reaches into, and the row the answer lands on.
 *
 * **The withholding is deliberate, and the singular flag makes it more so.** The
 * plumbing is right there: `runOrchestratorChild` takes an `agent`, and a
 * workflow's orchestrator block hands it the one its node names.
 *
 * While the flag was `--agents` the reason was a doubt — a member carries a
 * system prompt of its own, and whether `--append-system-prompt` also reached
 * the turn it was delegated was not verified against the pin, which mattered
 * here and nowhere else because this is the only child whose boundary is
 * *prose*. That doubt is now measured and gone: an agent told to reply with a
 * secret word stated only in the appended text replied with it, so the appended
 * prompt reaches a `--agent` session alongside the agent's own.
 *
 * What replaces it is the stronger half of the same argument, and it is not a
 * doubt. This child runs `bypassPermissions` with no allowlist, so
 * `systemPrompt()`'s look-do-not-build paragraph is the whole of what stands
 * between an orchestrator and an agent that fixes the bug it was asked to write
 * a proposal about. Selecting an agent here would make some saved prompt the
 * orchestrator's own role — reachable from a registry a chat proposal can
 * name — which is precisely what that paragraph exists to prevent, and no
 * measurement can make it safe.
 *
 * The second half is unchanged: there is no work here for one to do. A chat turn
 * looks and proposes; it produces a `chat_proposals` row and a sentence, so what
 * an agent would change is how the orchestrator *thinks*.
 *
 * A workflow's orchestrator block is not the counter-example it looks like: its
 * agent is one field on a graph a person saved and read as a whole, and what
 * that turn may *do* with it is bounded by `planEmission` and by guards off a
 * template rather than by prose. The `@`-mention in the composer is the answer
 * to what an operator actually wants here — it names the agent the proposed
 * **run** is started as, which is a fact about work that is approved before it
 * happens.
 */
function runTurn(chat: ChatRow, prompt: string): void {
  const settings = getSettings();
  let spawned: ChatProcess | null = null;
  runOrchestratorChild({
    subject: { kind: "chat", chatId: chat.id },
    prompt,
    appendSystemPrompt: systemPrompt(),
    resumeSessionId: chat.session_id,
    maxBudgetUSD: settings.chatTurnBudgetUSD,
    timeoutMs: CHAT_TIMEOUT_MS,
    timedOutMessage: TIMED_OUT_REASON,
    onSpawn: (child) => {
      spawned = child;
      turns.set(chat.id, child);
    },
    onProgress: (acc, moved) => recordProgress(chat, acc, moved),
    onSettle: (result) => {
      // Only this child's own entry, and only this child's own turn: a turn
      // cancelled and re-sent while the old child was still dying would
      // otherwise have its live handle deleted — and its row settled — by the
      // corpse of the previous one. `chat` is the row as it stood at the claim,
      // so `turn_seq` here is the turn this child was spawned under and not
      // whatever the row has since become.
      if (spawned && turns.get(chat.id) === spawned) turns.delete(chat.id);
      finishTurn(chat.id, chat.turn_seq, result);
    },
  });
}

/**
 * How often a turn in flight may write what it has produced so far.
 *
 * A turn writing prose emits an `assistant` event every few hundred
 * milliseconds and the page polls every three seconds, so writing on every one
 * of them would be a row update nobody reads for every update somebody does.
 * Half a second is under the poll and over the event rate, which is the whole
 * of the choice.
 */
const PROGRESS_WRITE_MS = 500;

/**
 * How often a turn in flight re-asks whether the install's ceiling still lets
 * it run.
 *
 * The ceiling is a rolling 24 hours and the query behind it is a scan of three
 * tables, so it is not something to ask per event. Ten seconds bounds the
 * overshoot at ten seconds of one turn's spend, which is the same shape the
 * live run guard's own interval takes and for the same reason: the answer moves
 * slowly and the question is not free.
 */
const CEILING_CHECK_MS = 10_000;

/** Per-turn pacing, keyed on the chat. Cleared when the turn settles. */
const progress = ((globalThis as unknown as {
  __ufChatProgress?: Map<string, { wroteAt: number; checkedAt: number }>;
}).__ufChatProgress ??= new Map<string, { wroteAt: number; checkedAt: number }>());

/**
 * Persist what the turn has said so far, and stop it if the install's ceiling
 * has since been reached.
 *
 * **Persist, then publish** — `emit()`'s order, arriving at the one path that
 * never had it. There is nothing to publish to here beyond the row, because the
 * page polls it, so the whole of "publish" is that the row has changed; what
 * matters is that the write happens *before* anything reads, which for a poll
 * is automatic and for the crash case is the entire point. A turn killed
 * half-way now leaves its text and its measured tokens behind instead of
 * leaving nothing but the bill.
 *
 * **The ceiling check is the second half and it is B4's actual subject.** The
 * install's rolling 24 hours was read once, at admission, and never again — so
 * a turn admitted at 99% of the ceiling could run for ten minutes past it, and
 * a turn admitted before three runs finished ran against a figure that had
 * moved. `chatTurnBudgetUSD` bounds *this* turn inside the CLI and always did;
 * what nothing bounded was the install while this turn was going. The estimate
 * this function has just written is what `installSpend` reads for it, so the
 * check includes the turn asking it.
 */
function recordProgress(
  chat: ChatRow,
  acc: ChatTurnAccumulator,
  moved: { textGrew: boolean; spendGrew: boolean },
): void {
  const now = Date.now();
  const pace = progress.get(chat.id) ?? { wroteAt: 0, checkedAt: now };
  progress.set(chat.id, pace);

  if (now - pace.wroteAt >= PROGRESS_WRITE_MS) {
    pace.wroteAt = now;
    // Guarded on `turn_seq` for `finishTurn`'s reason: a turn cancelled and
    // re-sent while the old child is still dying must not write the corpse's
    // text into the live turn's row.
    db()
      .prepare(
        `UPDATE chat_sessions
            SET partial_text=?, partial_at=?, turn_tokens=?, turn_cost_est=?
          WHERE id=? AND status='thinking' AND turn_seq=?`,
      )
      .run(
        acc.text || null,
        now,
        totalTokens(acc.tokens),
        acc.costGuardUSD,
        chat.id,
        chat.turn_seq,
      );
  }

  if (!moved.spendGrew || now - pace.checkedAt < CEILING_CHECK_MS) return;
  pace.checkedAt = now;
  const refusal = installBudgetRefusal();
  if (refusal) {
    // The same ending a timeout gets, and deliberately not a silent stop: the
    // operator has to be able to tell a turn that was cut off from one that
    // answered briefly, and the sentence names the ceiling rather than the
    // symptom.
    endTurn(
      chat.id,
      `${refusal} This turn was stopped part-way; what it had said is above.`,
    );
  }
}

/**
 * Settle a turn on the child's `exit`, giving `close` a grace period first.
 *
 * `close` is the better signal — it means stdout has been fully drained — but
 * it fires only once every inherited pipe has shut, and the CLI's own children
 * hold those. A `claude` that leaves a grandchild behind has *exited* and will
 * never *close*, so a turn wired to `close` alone sits at "Thinking…" until the
 * ten-minute timeout kills the group and throws the answer away — and for ever
 * when `killProcessGroup` is off, because then there is no group to kill and
 * nothing else reaps the grandchild.
 *
 * `runIteration` settles the identical hazard the identical way, and for the
 * same reason: `exit` is the guarantee, `close` is the fast path, and the grace
 * period exists only so a normal exit flushes its last chunk through `close`
 * before anything is parsed.
 *
 * Exported because the shape it exists for — a child that exits while a
 * grandchild holds its stdout — is only reachable from a test through this
 * seam; `runTurn` itself needs a database, a settings row and a spend gate.
 */
export function settleOnExit(
  child: ChildProcess,
  settle: (code: number | null) => void,
): void {
  let done = false;
  const once = (code: number | null) => {
    if (done) return;
    done = true;
    settle(code);
  };

  child.on("exit", (code) => {
    setTimeout(() => once(code), EXIT_DRAIN_MS).unref?.();
  });
  child.on("close", (code) => once(code));
}

/**
 * Read the CLI's `--output-format json` object.
 *
 * Same contract `parseReviewOutput` reads, from the same pinned build:
 * `total_cost_usd` is authoritative per invocation and is never re-derived from
 * tokens. `permission_denials` is read as well and surfaced, because a chat
 * that quietly could not run `gh` reads as a chat that found no issues.
 */
export function parseTurnOutput(
  stdout: string,
  stderr: string,
  code: number | null,
): TurnResult {
  const acc = newChatTurnAccumulator();
  for (const line of stdout.split("\n")) {
    const text = line.trim();
    if (text) readChatEvent(acc, text);
  }
  return turnResultOf(acc, stderr, code);
}

/**
 * The turn's verdict, from whatever the stream produced.
 *
 * Split from the parsing above so the live path and the settle path shape the
 * result the same way — the child folds events as they arrive and this is what
 * it lands with, while `parseTurnOutput` exists for a caller holding a whole
 * buffer. Two functions reading the same object differently is how a turn ends
 * up saying one thing on the page and another in the row.
 */
export function turnResultOf(
  acc: ChatTurnAccumulator,
  stderr: string,
  code: number | null,
): TurnResult {
  const parsed = acc.result;

  if (!parsed) {
    return {
      status: "failed",
      error:
        stderr.trim().split("\n").slice(-3).join(" ") ||
        `The chat produced no readable output (exit ${code ?? "?"}).`,
      // Even with no verdict the tokens are real and were billed. Carried so a
      // caller can record what the turn cost rather than losing it with the
      // answer, which is the whole of what the old shape did.
      tokens: totalTokens(acc.tokens),
      sessionId: acc.sessionId,
    };
  }

  const n = (v: unknown) => (typeof v === "number" ? v : 0);
  const usage = (parsed.usage ?? {}) as Record<string, unknown>;
  const tokens =
    n(usage.input_tokens) +
    n(usage.output_tokens) +
    n(usage.cache_creation_input_tokens) +
    n(usage.cache_read_input_tokens);
  const costUSD = n(parsed.total_cost_usd);
  const text = typeof parsed.result === "string" ? parsed.result : "";
  const sessionId =
    typeof parsed.session_id === "string" && parsed.session_id
      ? parsed.session_id
      // The `system` init event carries it too, and arrives first. Falling back
      // to that is what lets a turn whose `result` was truncated still resume.
      : acc.sessionId;

  const denials = Array.isArray(parsed.permission_denials)
    ? (parsed.permission_denials as Array<Record<string, unknown>>)
        .map((d) => String(d.tool_name ?? ""))
        .filter(Boolean)
    : [];

  // Cost is recorded even for a failed turn: it was billed either way.
  if (parsed.is_error === true || (parsed.subtype && parsed.subtype !== "success")) {
    return {
      status: "failed",
      error: text || `The chat failed (${String(parsed.subtype ?? "unknown")}).`,
      costUSD,
      tokens,
      sessionId,
      denials,
    };
  }

  return { status: "idle", text, costUSD, tokens, sessionId, denials };
}

/**
 * Settle the turn this result belongs to, and nothing else.
 *
 * `turnSeq` is the identity, and it is what makes the latch a latch. Status
 * alone is what `cancelChatTurn` and the sweeper need to end a turn without
 * waiting for a `close` that may never come — a late settle lands here and
 * changes nothing, rather than reviving the thread or replacing "you stopped
 * this" with whatever the killed child left on stderr. But `failed` is exactly
 * what invites the operator to retry, and `endTurn` returns while the child it
 * signalled is still working through an eight-second ladder, so the row is
 * routinely `thinking` again — under a *different* turn — by the time the old
 * child exits. Status alone let that child settle the new turn's row: its text
 * appended as the answer to a question it never read, its cost and session id
 * adopted, the live child left unwatched by a sweeper that reads only
 * `thinking` rows, its own answer later discarded against an `idle` row, and a
 * third message admitted by a guard that reads the row rather than the process.
 *
 * `runTurn`'s `onSettle` already applies this test to the process map, for this
 * scenario, one line above the call to this function.
 *
 * What a refused settle costs is a superseded child's own figures, and that is
 * the right trade rather than a free one: the CLI reports cost and session id
 * only in the final JSON object, which a child that was signalled is not
 * expected to print — but if one does, this drops it. Recording it would mean
 * adding another turn's spend to a row the operator is watching a live turn on,
 * which is the mis-attribution this exists to stop.
 */
function finishTurn(chatId: string, turnSeq: number, r: TurnResult): void {
  const now = Date.now();
  const prior = getChat(chatId)?.session_id ?? null;

  // Read before the UPDATE clears it: this is the turn's own running estimate,
  // and it is the only figure there is if the CLI never reported a cost.
  const estimate = getChat(chatId)?.turn_cost_est ?? 0;

  const changed =
    db()
      .prepare(
        `UPDATE chat_sessions
            SET status=?, error=?, updated_at=?, turn_started_at=NULL,
                cost_usd = cost_usd + ?, tokens = tokens + ?,
                session_id = COALESCE(?, session_id),
                partial_text=NULL, partial_at=NULL,
                turn_tokens=0, turn_cost_est=0
          WHERE id=? AND status='thinking' AND turn_seq=?`,
      )
      .run(
        r.status,
        r.error ?? null,
        now,
        r.costUSD ?? 0,
        r.tokens ?? 0,
        r.sessionId,
        chatId,
        turnSeq,
      ).changes > 0;
  if (!changed) return;

  // The same money again, as one dated row rather than as a running total.
  //
  // Both are needed and neither is derivable from the other: the column above
  // answers "what has this thread cost", which is what the chat page shows,
  // and this answers "what did this install spend on chat inside the window",
  // which is what the install-wide ceiling reads. Summing the running total
  // charged a thread's whole history to whichever 24 hours its last message
  // fell in — see `chat_turn_spend` in db.ts. Written after the latch above
  // rather than beside it, so a late settle that changed no total adds no row.
  if ((r.costUSD ?? 0) > 0) {
    db()
      .prepare(
        "INSERT INTO chat_turn_spend (chat_id, ts, cost_usd) VALUES (?, ?, ?)",
      )
      .run(chatId, now, r.costUSD ?? 0);
  } else if (estimate > 0) {
    // A turn that settled without the CLI reporting a cost — a child killed
    // after it had worked, a `result` that never arrived. The money was spent
    // either way, so the estimate is recorded rather than the turn reading as
    // free; marked, and kept out of the thread's own total, for the reason
    // `keepPartialTurn` gives.
    db()
      .prepare(
        "UPDATE chat_sessions SET cost_usd_est = cost_usd_est + ? WHERE id=?",
      )
      .run(estimate, chatId);
    db()
      .prepare(
        "INSERT INTO chat_turn_spend (chat_id, ts, cost_usd, estimated)" +
          " VALUES (?, ?, ?, 1)",
      )
      .run(chatId, now, estimate);
  }

  // Session id is adopted rather than compared, and a change is recorded rather
  // than treated as a failure — same posture the run loop takes. Which id the
  // CLI reports for a resumed conversation is its business; what must not
  // happen is continuing a conversation nobody chose without saying so.
  if (r.sessionId && prior && r.sessionId !== prior) {
    appendMessage(
      chatId,
      "system",
      `Claude Code answered under a different session id (${r.sessionId}) than ` +
        `the one this chat resumed (${prior}). Continuing with the new one.`,
    );
  }

  if (r.text) appendMessage(chatId, "assistant", r.text);
  if (r.error) appendMessage(chatId, "system", r.error);

  // A denial is the difference between "there are no open issues" and "I was
  // not allowed to look", and only one of those is worth acting on. Kept now
  // that the chat runs unrestricted precisely because it should be empty: a
  // refusal here is the CLI declining something on its own, which is worth
  // seeing rather than reading as a chat that looked and found nothing.
  if (r.denials && r.denials.length > 0) {
    appendMessage(
      chatId,
      "system",
      `Refused tool calls this turn: ${[...new Set(r.denials)].join(", ")}. ` +
        "The chat runs with no tool allowlist, so this is the CLI itself " +
        "declining the call.",
    );
  }

  // The first thing said names the thread, so the list reads as a list of
  // subjects rather than of timestamps.
  const chat = getChat(chatId);
  if (chat && !chat.title) {
    const first = listMessages(chatId).find((m) => m.role === "user");
    if (first) {
      db()
        .prepare("UPDATE chat_sessions SET title=? WHERE id=?")
        .run(first.text.replace(/\s+/g, " ").slice(0, 80), chatId);
    }
  }

  // This turn just gave a slot back to the process budget, and a block's
  // deciding turn deferred by that budget is left `waiting` rather than failed —
  // so whatever frees a slot has to wake it. `review.ts` carries the same four
  // lines for the same reason, and for the same reason imports dynamically:
  // `workflows.ts` imports this module.
  void import("./workflows")
    .then((m) => m.advanceInstances())
    .catch(() => {
      /* a workflow that cannot be advanced is not a reason to fail a turn */
    });
}

/**
 * Fail out chat turns a restart left mid-flight.
 *
 * Same reasoning as `reconcileOnBoot` and `reconcileReviewsOnBoot`: the child
 * is gone with the process that started it, and a row left saying `thinking`
 * spins an indicator for ever. Nothing is resumed — a chat turn is a question
 * somebody asked minutes ago, and re-asking it unattended is spend nobody is
 * present to want.
 *
 * Still the cheapest way out of a stranded turn, and no longer the only one:
 * `cancelChatTurn` clears one on request and the sweeper clears one that has
 * run past its deadline, so recovering a thread no longer means restarting the
 * server for everything else running in it.
 *
 * The ids are read before the write because the write is what makes them
 * unfindable: `status='thinking'` is the only mark a stranded turn carries.
 */
export function reconcileChatsOnBoot(): void {
  // Safe as two statements where nothing else is: better-sqlite3 is
  // synchronous, and on boot nothing in this process has claimed a turn yet.
  const stranded = db()
    .prepare("SELECT id FROM chat_sessions WHERE status='thinking'")
    .all() as Array<Pick<ChatRow, "id">>;
  // Before the status moves, because `keepPartialTurn` is what turns the four
  // per-turn columns into a message, a token count and a dated row the
  // install's ceiling can read — and this is the ending that most needs it.
  // The other three have somebody present; this one is what the operator finds
  // when they come back, and before the child streamed the whole turn was gone
  // by then with only the bill left behind.
  for (const { id } of stranded) keepPartialTurn(id);
  db()
    .prepare(
      "UPDATE chat_sessions SET status='failed', turn_started_at=NULL," +
        " error=? WHERE status='thinking'",
    )
    .run(RESTARTED_REASON);
  // In the thread as well as on the row, for `endTurn`'s reason and hardest
  // here of the four endings: `claimTurn` clears `error` on the next message,
  // so the row is the only trace of a turn lost to a restart and the
  // operator's attempt to recover from it — the first thing they do — is what
  // erases it. Without this the conversation reads afterwards as their question
  // followed by their next one with nothing in between, which is an answer that
  // never came rather than a turn the restart killed.
  for (const { id } of stranded) appendMessage(id, "system", RESTARTED_REASON);
}

/* ------------------------------------------------------------------ */
/* What the child is told to be                                        */
/* ------------------------------------------------------------------ */

/**
 * What the child is, in the absence of a mechanism that makes it so.
 *
 * This carried the *role* when the allowlist carried the *limits*. It now
 * carries both, because the child runs `bypassPermissions` — so the paragraph
 * below about not doing the work is the only thing between an orchestrator and
 * an agent that fixes the bug it was asked to write a proposal about. It is
 * stated as a job description rather than a list of forbidden tools on purpose:
 * a model told "you may not edit" reaches for the nearest thing that is not
 * editing, where one told "your job is to look and propose" has nowhere to go
 * but the proposal.
 *
 * **The half about calling tools lives in `src/app/api/mcp/route.ts` and is
 * deliberately not repeated here.** The tool list and this string arrive in the
 * same request, so every sentence describing what `list_folders` returns or
 * what `agentId` does was being paid for twice per turn — and the schema is the
 * copy that cannot drift from the tool, because it *is* the tool. What survives
 * here is only what no schema can carry: an instruction to look before
 * proposing, the facts a description has no field to hang on (a folder on disk
 * is `<mount path>/<folder>`; a deleted agent is refused by name), and what to
 * *say* in the reply, which is about this conversation rather than about a
 * call. Before deleting a sentence from a description over there, check it is
 * not the only copy left.
 *
 * The asking paragraph is there on exactly that test and no other. `ask_operator`'s
 * own description says what the tool does with what it is handed and that no
 * answer comes back through it; what a schema has no field for is **when to
 * reach for it at all** — which is a judgement against the other tools rather
 * than a fact about this one, and it fails in both directions. A model that
 * never asks proposes on a guess; a model that asks freely turns a chat into a
 * form, and every question is a turn, a card and a decision bought with an
 * operator's attention. So the paragraph is two rules and a bound: only what
 * the operator alone knows, prefer a stated assumption, and one is a question
 * where four is a form.
 */
function systemPrompt(): string {
  return [
    "You are the orchestrator for UsageFoundry, a tool that runs unattended",
    "Claude Code agents against folders on this machine. You are talking to its",
    "operator in a chat panel.",
    "",
    "You cannot start, stop or resume a run, and you cannot press Run on a",
    "workflow. The two things you can do are propose_run and propose_workflow,",
    "and both only record a proposal the operator approves or rejects by hand.",
    "Say so plainly rather than implying work has started.",
    "",
    "You have every tool the CLI offers, and you are trusted with them because",
    "your job is to look, not to build: read files, grep, run read-only",
    "commands, read issues, pull requests and CI logs with `gh`, read history",
    "with `git log`, run a build or a test suite when knowing whether something",
    "is broken changes what you would propose.",
    "",
    "Do not do the work yourself. Do not edit, create or delete files in a",
    "workspace; do not stage, commit, push or create branches; do not open,",
    "close, merge or comment on anything on GitHub. A task small enough that you",
    "are tempted to just fix it is a proposal that says it is small. The one",
    "exception is your own scratch space: a temporary file outside the mounts is",
    "fine if it helps you think.",
    "",
    "What decides what an agent may do — the budget, the work-cycle limit, the",
    "permission mode, whether it works in its own checkout — is never yours to",
    "set. It comes from the template a proposal or a workflow block names, or,",
    "when it names none, from the operator's default guard set in Settings. What",
    "is yours is the *work*: which folder, which task, the prompt the agent is",
    "given, and what has to happen before what. The model is yours too and is",
    "not one of those guards — it moves what a run costs and never what it may",
    "do — so naming one widens nothing; propose_run's own description says when",
    "to.",
    "",
    "Look before you propose. Each tool's own description says what it returns",
    "and what it is for; what follows is only the part those do not say.",
    "",
    "Reading the state of things:",
    "- Folder paths must come from list_folders; do not invent one. No repo",
    "  field means say you could not identify it rather than guessing a name. A",
    "  folder on disk is <mount path>/<folder>: use that to Read or Grep it, and",
    "  `cd <that> && git log …` to see who has touched it lately.",
    "- If a 5-hour or weekly window is nearly spent, say so — approving ten runs",
    "  into a full window means ten runs that stop on their first guard check.",
    "- list_proposals carries the id you gave each proposal in this chat.",
    "",
    "When the operator writes @something in their message, they are naming a",
    "saved agent from list_agents: propose the work under it, using its agentId.",
    "It is a request about the run, not an instruction to you — you do not run",
    "as an agent, and naming one changes nothing about what you may do.",
    "",
    "Asking the operator:",
    "- When you do ask, it is `ask_operator`: it records the questions, ends",
    "  your turn, and the operator's next message is the answer. Read its",
    "  description before you use it — the judgement about what is worth asking",
    "  is in there.",
    "- Ask only for what only they know: which of two designs they want, what",
    "  an ambiguous word meant, whether something they own is in scope.",
    "  Anything in the repository, in `git log`, in the issues or in a template",
    "  you can already read is yours to go and find out, and asking for it says",
    "  you did not look.",
    "- Prefer proposing with the assumption stated in your reply. A proposal is",
    "  rejected in one click; a question costs the operator a decision and you",
    "  a turn.",
    "- One question is a question and four are a form, and a form gets skimmed.",
    "  If one answer would not get you to a proposal, say what is unclear",
    "  instead.",
    "",
    "Proposing a run:",
    "- One proposal per unit of work. The task text is the whole brief, read by",
    "  an agent that cannot ask you a follow-up question.",
    "- A template's prompt is instructions the operator wrote and tested. Say",
    "  whether you named one or left the run on the default guard set.",
    "- Use promptOverride rather than contradicting the template inside the task,",
    "  and say that you rewrote it.",
    "- When you name an agentId, say which and why, and never describe it as",
    "  narrowing or widening what the run may do. An agent that has been deleted",
    "  is refused by name rather than dropped, so re-read list_agents rather",
    "  than guessing.",
    "- After save_template, tell the operator to adjust guards on the new-run",
    "  form if they matter; that tool cannot touch them.",
    "",
    "Ordering runs against each other:",
    "- Runs on one folder are serialised anyway, and runs in their own checkouts",
    "  are not. Order them when the *work* has an order — a fix before the test",
    "  that proves it, a refactor before what builds on it — not to avoid a",
    "  collision the folder claim already prevents.",
    "- dependsOn has no default edge: pick the one you mean, because on-success",
    "  ends a chain the operator meant to run regardless and on-finish starts",
    "  work on top of a run that crashed.",
    "- Say in your reply that they have to be approved in the same click. A",
    "  dependent approved on its own is failed by name rather than started.",
    "",
    "Proposing a workflow:",
    "- Never say a workflow you proposed is running: approving one saves it, and",
    "  the operator presses Run themselves.",
    "- Propose an orchestrator block only when the work genuinely cannot be",
    "  written out in advance, because what it emits starts with no approval.",
    "- Say what each block does and, for any orchestrator block, how many runs it",
    "  may start. That is the number the operator is agreeing to.",
    "- Tell the operator to set a workflow-wide budget in the editor; without one",
    "  the workflow cannot be put on a schedule.",
    "",
    "Be brief. When you have proposed, reply with a short list of what you",
    "proposed and what you deliberately left out. The proposals appear in the",
    "panel beside this conversation, so do not repeat their full text.",
  ].join("\n");
}

/**
 * Where the chat's child runs.
 *
 * The first mount, so `Read`/`Grep` land somewhere useful, falling back to a
 * temporary directory when nothing is mounted — a spawn with a cwd that does
 * not exist fails with an ENOENT that reads like a missing `claude` binary.
 */
function chatCwd(): string {
  return fs.existsSync(WORKSPACE_ROOT) ? WORKSPACE_ROOT : os.tmpdir();
}

/**
 * Environment for the chat.
 *
 * The same four exclusions every other child gets — this app's own `UF_*`
 * configuration, any inherited telemetry routing, `DATA_DIR` (written out
 * in full over `childEnv` in `orchestrator.ts`; this child runs
 * `bypassPermissions` with no allowlist, so of the four it is the one most able
 * to start a second server against the database), and the `NODE_OPTIONS`
 * compose sets to bound *this* process's heap — plus `githubEnv()`, which
 * until now reached work cycles and nothing else. That widening is the point of
 * the feature: a chat asked to look at open issues cannot, otherwise, and it
 * would fail inside a tool call the way `git push` used to. With no allowlist
 * above it, that token now authenticates *writes* as well; the system prompt is
 * what says not to make them, and `UF_*` still leaves by namespace, so nothing
 * hands this child the app's own credentials.
 *
 * The token is the **install-wide** one, and this is the one child where that is
 * still right: a work cycle takes the credential its own repository is
 * configured with (`selectGithubToken`, off `runs.repo_root`), where an
 * orchestrator turn's whole job is to look across every mount before it knows
 * which repository it is proposing work in. Narrowing it to `o.cwd` would
 * silently withhold the credential from every question about a repository the
 * turn had not yet been pointed at, which is the failure this feature was
 * widened to remove. Leaving `UF_GITHUB_TOKEN` blank and configuring only
 * `UF_GITHUB_TOKENS` is what withholds it here — deliberately, and the same
 * lever as everywhere else.
 *
 * No telemetry, for the reason a review gets none: `otlp_requests.run_id` is
 * compared against a run's own spend, and a chat's requests in that comparison
 * would make an accounted-for run look unaccounted-for.
 */
function chatEnv(): NodeJS.ProcessEnv {
  const env: NodeJS.ProcessEnv = { ...process.env, FORCE_COLOR: "0" };
  for (const key of Object.keys(env)) {
    if (
      key.startsWith("UF_") ||
      key.startsWith("OTEL_") ||
      key === "ANTHROPIC_ADMIN_KEY" ||
      key === "OPENAI_API_KEY" ||
      key === "CODEX_API_KEY" ||
      key === "CLAUDE_CODE_ENABLE_TELEMETRY" ||
      key === "DATA_DIR" ||
      key === "NODE_OPTIONS"
    ) {
      delete env[key];
    }
  }
  return { ...env, ...githubEnv() };
}

/**
 * Where a turn's MCP config goes: a directory of its own, never a shared one.
 *
 * Under privilege separation this is a fixed base the *server* owns, mode 0711
 * — traversable by a child that has been handed a path, and not listable by
 * anything. `/tmp` was the whole of the problem: 1777 and world-readable, so
 * `ls /tmp/uf-mcp-*.json` found a live capability without guessing the random
 * name, and any of the twenty-five concurrent agents could run it.
 *
 * Without separation there is no boundary to build and no point pretending
 * otherwise, so it falls back to `os.tmpdir()` — one uid means a sibling reads
 * whatever this process can write, wherever it is put.
 */
export const MCP_CONFIG_BASE = "/run/uf-mcp";

function mcpConfigBase(): string {
  if (!privilegeSeparated()) return os.tmpdir();
  fs.mkdirSync(MCP_CONFIG_BASE, { recursive: true, mode: 0o711 });
  // `mkdir` masks the mode through the umask and does nothing at all when the
  // directory already exists, so the mode is set rather than requested.
  fs.chmodSync(MCP_CONFIG_BASE, 0o711);
  return MCP_CONFIG_BASE;
}

/**
 * The MCP config, as a file rather than an argv string.
 *
 * `--mcp-config` takes either, and a string would put the capability token in
 * the child's command line — readable by every process on the host for as long
 * as the turn lasts. The file is written 0600, in a per-turn directory of its
 * own, and both are removed when the turn ends.
 *
 * **Who owns it is what decides, and the owner is a group.** The directory and
 * the file were 0700/0600 owned by the agents' uid, which excluded nobody: this
 * turn's child has to *read* the file, every child in this app is one uid, and
 * `--mcp-config <path>` is an argv element that `/proc/<pid>/cmdline` publishes
 * to every process on the box. A work-cycle agent read the path off a sibling's
 * command line and opened a file its own uid owned. Moving out of `/tmp` closed
 * the enumeration route and only that.
 *
 * So under `UF_CHAT_GID` both are handed to a group that the chat and block
 * child is in and no work cycle is — 0710 on the directory (traverse by group,
 * and no listing for anyone) and 0040 on the file. A work-cycle agent that knows
 * the exact path now fails the owner check, fails the group check, and is left
 * with the "other" bits, which are zero. See `privsep.ts` for why this is a gid
 * rather than a second uid.
 *
 * Without that group — `UF_CHAT_GID` cleared, or no privilege separation at all
 * — this falls back to the previous arrangement whole rather than half-applying
 * it, because a config the child cannot read is a turn with no tools, which
 * reads as a model that chose not to call any.
 *
 * @param ownership defaulted from `privsep.ts`; a parameter so the modes can be
 *   tested without a second uid, which a unit test in this process cannot have.
 */
export function writeMcpConfig(
  token: string,
  ownership: McpConfigOwnership | null = mcpConfigOwnership(),
): string {
  const dir = path.join(
    mcpConfigBase(),
    `uf-mcp-${randomBytes(9).toString("hex")}`,
  );
  const file = path.join(dir, "config.json");
  const dirMode = ownership?.dirMode ?? 0o700;
  const fileMode = ownership?.fileMode ?? 0o600;
  try {
    fs.mkdirSync(dir, { recursive: false, mode: dirMode });
    // `mkdir` masks the mode through the umask, and `writeFile`'s does the same,
    // so both are set afterwards rather than requested — 0710 under the image's
    // 0022 umask would otherwise arrive as 0710 by luck and 0700 under any
    // umask an operator changed.
    fs.chmodSync(dir, dirMode);
    fs.writeFileSync(
      file,
      JSON.stringify({
        mcpServers: {
          uf: {
            type: "http",
            url: MCP_SELF_URL,
            headers: { Authorization: `Bearer ${token}` },
          },
        },
      }),
      { mode: fileMode },
    );
    fs.chmodSync(file, fileMode);
    // Written by the server, read by the child, and they are no longer the same
    // uid. Both halves: a directory the child cannot enter is a turn with no
    // tools at all, which reads as a model that chose not to call any.
    if (ownership) {
      chownToGroup(dir, ownership.gid);
      chownToGroup(file, ownership.gid);
    } else {
      chownForChild(dir);
      chownForChild(file);
    }
  } catch (err) {
    // A write that fails part-way — ENOSPC, the likeliest of these — leaves the
    // file behind with whatever reached the disk, and what it carries is the
    // capability token. Nothing else would ever remove it: the cleanup in `land`
    // is inside a promise this failure never reaches.
    removeMcpConfig(file);
    throw err;
  }
  return file;
}

/**
 * Remove a turn's config and the directory that held it.
 *
 * Both, and in that order: the directory is per-turn, so one left behind is a
 * slow leak in a path nothing else cleans, and `rmdir` after the unlink cannot
 * take anything that is not ours. Never throws — this runs on the settle path
 * of every turn, and a turn is not worth failing over a file that is already
 * gone or a read-only `/tmp`.
 */
export function removeMcpConfig(file: string): void {
  try {
    fs.unlinkSync(file);
  } catch {
    // Never created, or the same condition that failed the write.
  }
  try {
    fs.rmdirSync(path.dirname(file));
  } catch {
    // Not empty, never created, or the tmpdir fallback's own parent — none of
    // which is worth a word.
  }
}
