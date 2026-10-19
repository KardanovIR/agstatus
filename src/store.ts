import crypto from 'crypto';
import type { Pool } from 'pg';

export const STATUSES = ['idle', 'planning', 'coding', 'testing', 'blocked', 'done'] as const;
export type Status = (typeof STATUSES)[number];

/** Apps a session can be hosted in; anything else the hook reports becomes 'other'. */
export const HOST_SLUGS = [
  'agterm', 'iterm2', 'kitty', 'wezterm', 'terminal', 'ghostty', 'alacritty', 'warp',
  'vscode', 'cursor', 'windsurf', 'jetbrains', 'zed', 'claude-desktop', 'codex-desktop',
  'herdr', 'tmux', 'zellij', 'screen', 'windows-terminal', 'other',
] as const;
export type HostSlug = (typeof HOST_SLUGS)[number];

export const HOST_KINDS = ['terminal', 'multiplexer', 'ide', 'desktop-app', 'unknown'] as const;
export type HostKind = (typeof HOST_KINDS)[number];

/**
 * Where a session runs, as far as the board needs to know: a label for the
 * card and a per-board machine id to route a focus command to. Opt-in on the
 * hook side, so most sessions have none. Never a path, tty, pid or bundle id.
 */
export interface Host {
  machine: { id: string; name: string };
  app: { slug: HostSlug; name: string; kind: HostKind };
}

// A per-board hash the hook derives from its machine id, never the raw id.
export const MACHINE_ID_RE = /^[0-9a-f]{32}$/;
// The listener's credential for that id: the hash the id is itself derived
// from (id = sha256(key)[0..32]). Every board viewer sees the id; only the
// machine holds the key, so a viewer cannot claim, ack or pose as it.
export const MACHINE_KEY_RE = /^[0-9a-f]{64}$/;
export const machineIdForKey = (key: string): string =>
  crypto.createHash('sha256').update(key).digest('hex').slice(0, 32);

/**
 * `sha256(key)[0..32] === machineId`, compared without an early exit.
 * Both sides are public-derivable (every viewer sees the id, and anyone can
 * hash a key they already hold), so the timing channel a `!==` opens here
 * leaks nothing an attacker could not compute offline — but this is the one
 * check standing between a viewer and a machine's stream, and a reader
 * should not have to reconstruct that argument to trust it.
 */
export const machineKeyMatches = (key: string, machineId: string): boolean => {
  const a = Buffer.from(machineIdForKey(key));
  const b = Buffer.from(machineId);
  return a.length === b.length && crypto.timingSafeEqual(a, b);
};
const HOST_NAME_MAX = 32;
const CONTROL_CHARS_RE = /[\u0000-\u001F\u007F]/g;

const isHostSlug = (s: unknown): s is HostSlug =>
  typeof s === 'string' && (HOST_SLUGS as readonly string[]).includes(s);
const isHostKind = (s: unknown): s is HostKind =>
  typeof s === 'string' && (HOST_KINDS as readonly string[]).includes(s);

/** A host label: control characters stripped, trimmed, truncated; blank or non-string → fallback. */
const hostName = (v: unknown, fallback: string): string => {
  const s = typeof v === 'string' ? v.replace(CONTROL_CHARS_RE, '').trim().slice(0, HOST_NAME_MAX) : '';
  return s || fallback;
};

/**
 * Rebuilds a Host key by key from whatever came in — a webhook body or a
 * stored column — so the board only ever sees these six values. null unless
 * raw is a plain object whose machine.id is well-formed; unknown slugs and
 * kinds are downgraded, names are cleaned and defaulted, every other key is
 * dropped.
 */
export function normalizeHost(raw: unknown): Host | null {
  if (typeof raw !== 'object' || raw === null || Array.isArray(raw)) return null;
  const h = raw as Record<string, unknown>;
  const machine = (typeof h.machine === 'object' && h.machine !== null ? h.machine : {}) as Record<string, unknown>;
  const app = (typeof h.app === 'object' && h.app !== null ? h.app : {}) as Record<string, unknown>;
  if (typeof machine.id !== 'string' || !MACHINE_ID_RE.test(machine.id)) return null;
  const slug = isHostSlug(app.slug) ? app.slug : 'other';
  return {
    machine: { id: machine.id, name: hostName(machine.name, 'Machine') },
    app: { slug, name: hostName(app.name, slug), kind: isHostKind(app.kind) ? app.kind : 'unknown' },
  };
}

export interface Session {
  id: string;
  name: string;
  status: Status;
  message: string;
  project: string;
  /** Agent kind that owns the session ("claude", "codex", …). */
  source: string;
  /** Absent or null = the hook did not report a host. Stored as null. */
  host?: Host | null;
  createdAt: number;
  updatedAt: number;
  /**
   * Lifetime tokens the agent's own logs attribute to this session, when the
   * board holds a total for it. Never part of the stored card: it arrives on
   * its own endpoint, is keyed by (source, id) rather than by the card, and
   * is attached on the way out (see withTokens). Absent — not zero — when
   * nothing has been reported, so a card never claims a session spent nothing.
   */
  tokens?: number;
}

export interface UpsertInput {
  id: string;
  status: Status;
  // undefined = carry the previous value forward (v1 semantics)
  name?: string;
  message?: string;
  project?: string;
  source?: string;
  // undefined = carry forward, null = clear (the hook opted out), object = set
  host?: Host | null;
}

export interface Device {
  deviceToken: string;
  notifyDone: boolean;
  /**
   * APNs endpoint this token last authenticated against. A development build's
   * token only works against the sandbox and an App Store build's only against
   * production, and nothing in the token says which — so it is learned on
   * first delivery and remembered. Null until then.
   */
  apnsServer: string | null;
}

/** One plan-limit window (e.g. the 5-hour session window or a weekly cap). */
export interface UsageWindow {
  id: string;
  label: string;
  /** Percent of the limit consumed, 0–100. */
  usedPct: number;
  /** Epoch ms when the window resets; null when unknown. */
  resetsAt: number | null;
}

/** Plan usage reported by an agent's hook, one entry per source ("claude", …). */
export interface Usage {
  source: string;
  windows: UsageWindow[];
  updatedAt: number;
}

/** Usage older than this is dropped from reads — stale percentages mislead. */
export const USAGE_TTL_MS = 24 * 60 * 60 * 1000;

/** One recorded reading of a limit window's utilization. */
export interface UsagePoint {
  at: number; // epoch milliseconds
  usedPct: number;
}

/** Tokens one agent spent on one project during one UTC day. */
export interface ProjectDay {
  source: string;
  project: string;
  day: string; // YYYY-MM-DD, UTC
  tokens: number;
}

/**
 * One session's lifetime token total, as the agent's own logs report it.
 *
 * Keyed by (source, sessionId) and NOT by the card: the two agents mint ids
 * independently, and the number does not mean quite the same thing in each
 * (Claude counts input + output + cache creation, Codex reports its own
 * cumulative total which includes cache reads) — so the source has to travel
 * with it, and two agents can never collide on one id.
 *
 * This is not a slice of the project-day series: a project-day sums across
 * sessions, this sums across days and, for Claude, across folders. Neither
 * converts into the other and neither is a percentage of any plan limit.
 */
export interface SessionTotal {
  source: string;
  sessionId: string;
  /** Absolute lifetime tokens for that session — what was reported, never a delta. */
  tokens: number;
  /** When the server received this value; the clock retention runs on. */
  updatedAt: number;
}

/**
 * How long a session total outlives its last report.
 *
 * Not the card's 24 hours. The total arrives on the hook's own schedule (a
 * 15-minute throttle, and only for sessions whose number moved), so a session
 * resumed after a weekend gets its card back from the first webhook but its
 * total only from the first usage run after that. Retention shorter than the
 * gap would show a live card with no number for as long as a quarter of an
 * hour, every time.
 *
 * Not the 90 days the project-day rows get either. Those are a series a chart
 * looks back over; this number is only ever read through a card, and a card
 * cannot be older than SESSION_TTL_MS. A week covers a weekend plus the slack,
 * and is the shortest window that does.
 */
export const SESSION_TOTAL_TTL_MS = 7 * 24 * 60 * 60 * 1000;

/**
 * Totals held per workspace. A workspace holds at most 50 live sessions and a
 * week of turnover is nowhere near this — the cap is not about honest boards
 * but about what anyone holding the token could otherwise pin: the endpoint
 * shares the webhook budget (120 posts a minute) and takes 100 rows a post.
 *
 * At the cap a NEW (source, session_id) is refused; an update to a key already
 * held always lands, and so does a total for a session that has a card on this
 * board right now (at most 50 more). This used to accept the new key and evict
 * the oldest instead, which kept memory at 500 and did nothing for Postgres:
 * every evicted row is only flagged, never removed, so a token posting fresh
 * ids wrote 12,000 permanent rows a minute while the heap looked healthy.
 * Refusing is the only bound that holds on disk as well as in memory.
 */
const MAX_SESSION_TOTALS_PER_WORKSPACE = 500;

/**
 * Distinct (source, project, day) rows held per workspace.
 *
 * Sized against a real heavy board rather than a guess: one developer running
 * Claude Code and Codex all day, with agent workflows spawning dozens of git
 * worktrees — and a worktree is its own folder name, so its own project here.
 * Counted from that machine's own hook scan state in October 2026, it held
 * 278 rows across the full 90 days, and never more than 16 folders in a
 * single day. Every day of the window as busy as its busiest
 * day, for both agents, is 16 × 2 × 92 ≈ 2,950; this leaves room above that
 * for a small team sharing one board.
 *
 * The bound is about what one free token could otherwise pin: 200 rows a
 * report on the shared 120-a-minute budget is 24,000 new rows a minute, each
 * one a Map entry and a permanent Postgres row. At the cap a NEW key is
 * refused rather than an old one evicted, for the reason given at
 * MAX_SESSION_TOTALS_PER_WORKSPACE: eviction only flags, so it bounds memory
 * and leaves the disk to grow. Updates to a key already held always land, and
 * days that age out of the window free their slots (pruneProjectDays). At
 * roughly 260 bytes a row this is about 1.3 MB of heap per workspace.
 */
export const MAX_PROJECT_DAYS_PER_WORKSPACE = 5000;

/**
 * Distinct usage sources a workspace may report under, across /usage,
 * /usage/projects and /usage/sessions together.
 *
 * Not an allow-list of 'claude' and 'codex', although those are the only two
 * the bundled hook has ever sent to these endpoints (every version guards
 * them with `SOURCE !== 'claude' && SOURCE !== 'codex'`, or earlier with
 * Claude alone): docs/api.md documents `source` as an open agent kind, and a
 * self-hosted board fed by someone's own reporter for a third agent must keep
 * working. Four times what an honest board uses is still a small constant.
 *
 * Every source multiplies everything keyed by it — a usage entry, up to six
 * history series, its own project-day and session-total keys — and the usage
 * frame re-sorts and re-serialises every source on every post. Uncapped, one
 * token minted a new source per post. A new source past the cap is refused
 * (429); one already held always lands.
 */
export const MAX_USAGE_SOURCES_PER_WORKSPACE = 8;

/** Windows one usage report may carry (the hook trims to the same number). */
export const MAX_USAGE_WINDOWS = 6;

/**
 * Limit-history series — one per (source, window id) — held per workspace:
 * every admitted source reporting a full set of windows at once.
 *
 * The source cap alone does not bound the series, because window ids are as
 * open as sources were: six fresh ids a post under one source is 720 new
 * series a minute, each its own history rows. An honest board has two sources
 * with at most six windows each; the rest is room for the ids that follow
 * model names (week_opus, week_sonnet, …) and so change as models come and go.
 * At the cap a new series is not recorded — the limit bar itself still shows,
 * only its history is not kept — after first forgetting any series that has
 * been silent for the whole history window, which is what a restart forgets.
 */
const MAX_USAGE_SERIES_PER_WORKSPACE = MAX_USAGE_SOURCES_PER_WORKSPACE * MAX_USAGE_WINDOWS;

/**
 * The closest two recorded points of one series may be.
 *
 * Every chart that reads this series step-samples it once per UTC day —
 * sampleSeries in public/app.js, UsageHistory.sampleSeries on iOS,
 * UsageDetail.sampleSeries on Android — and the hook reports a source at most
 * every five minutes per machine, so an honest board never comes near this. What it stops is a sender alternating usedPct: six series
 * a post changed every time, 720 permanent usage_history rows a minute.
 * A reading inside the minute still moves the live bar; only its history
 * point is skipped, and the next report after the minute records whatever the
 * value is by then.
 */
const USAGE_POINT_MIN_INTERVAL_MS = 60_000;

export const COMMAND_TYPES = ['focus', 'resume'] as const;
export type CommandType = (typeof COMMAND_TYPES)[number];

export const COMMAND_RESULTS = ['focused', 'activated', 'selected', 'resumed', 'failed'] as const;
export type CommandResult = (typeof COMMAND_RESULTS)[number];

/**
 * How far the listener got: the exact pane, a tab, a window, only the app, or a
 * desktop app's own conversation (a Codex thread, a Claude Desktop session).
 */
export const COMMAND_REACHES = ['pane', 'tab', 'window', 'app', 'thread'] as const;
export type CommandReach = (typeof COMMAND_REACHES)[number];

/** Why a command failed. An enum on purpose: a free-text reason would leak cwd/tty/stderr to every viewer. */
export const COMMAND_REASONS = [
  'no-record', 'remote', 'not-running', 'app-not-running', 'consent-needed', 'mux-detached',
  'ambiguous', 'unsupported-host', 'bad-record', 'respawn-failed', 'unsupported-type',
  'superseded', 'expired',
] as const;
export type CommandReason = (typeof COMMAND_REASONS)[number];

export type CommandState = 'pending' | 'claimed' | 'done' | 'expired';

/**
 * A tap on a card, waiting for the listener on the machine that hosts the
 * session. Carries only ids: the listener derives every action from its own
 * local record. In memory only (like pairing codes) — a two-minute object
 * must not become a permanent soft-deleted row, and a restart just lets the
 * phone time out.
 */
export interface Command {
  id: string;
  wsId: string;
  type: CommandType;
  sessionId: string;
  machineId: string;
  state: CommandState;
  createdAt: number;
  expiresAt: number;
  claimedAt?: number;
  doneAt?: number;
  result?: CommandResult;
  reach?: CommandReach;
  reason?: CommandReason;
}

export type ClaimError = 'not_found' | 'wrong_machine' | 'already_claimed' | 'expired';
export type AckError = 'not_found' | 'wrong_machine' | 'not_claimed' | 'already_done' | 'expired';

/** How far back the usage detail view may look. */
export const MAX_HISTORY_DAYS = 90;
/** Points held in memory per (source, window) — a plan limit moves slowly. */
const MAX_USAGE_POINTS = 2000;

const DAY_MS = 24 * 60 * 60 * 1000;

/** The UTC day an instant falls in, as YYYY-MM-DD. */
export function dayKey(at: number): string {
  return new Date(at).toISOString().slice(0, 10);
}

/**
 * Whether a YYYY-MM-DD string names a day that exists. The shape check alone
 * (`\d{4}-\d{2}-\d{2}`) let `9999-99-99` and `2026-13-45` through, and each
 * such string is a key the store would hold — and one that sorts after every
 * real day, so no age-based cutoff ever reached it. A round trip through Date
 * is the whole check: an impossible date either fails to parse or comes back
 * as a different day (V8 rolls `2026-02-30` over into March).
 */
export function isCalendarDay(day: string): boolean {
  const at = Date.parse(`${day}T00:00:00Z`);
  return Number.isFinite(at) && dayKey(at) === day;
}

/**
 * The project days the store will hold at `now`: the history window back, and
 * one day forward. The day is the reporter's UTC day, so a clock a little
 * ahead of the server's lands on tomorrow just after midnight; anything past
 * that is not a day anyone's logs can have yet.
 */
export function projectDayWindow(now: number): { oldest: string; newest: string } {
  return { oldest: dayKey(now - MAX_HISTORY_DAYS * DAY_MS), newest: dayKey(now + DAY_MS) };
}

/** One entry in a session's timeline: what the agent switched to, and when. */
export interface SessionEvent {
  /** Monotonically increasing per session; stable identity for clients. */
  seq: number;
  status: Status;
  message: string;
  at: number;
}

/** History kept per session; older entries are soft-deleted, newest wins. */
export const MAX_EVENTS_PER_SESSION = 100;

/** Reserved workspace key for single-tenant (legacy) mode. */
export const LEGACY_WS = '_legacy';

export const TOKEN_RE = /^ags_[A-Za-z0-9_-]{32}$/;

const WEBHOOKS_PER_MINUTE = 120;
const COMMANDS_PER_MINUTE = 10;
// Every listener connect is broadcast to every viewer; a reconnect loop must not flood them.
const LISTENER_CONNECTS_PER_MINUTE = 30;
export const MAX_PENDING_COMMANDS_PER_WORKSPACE = 10;
/** Done and expired commands stay readable this long, so a phone that backgrounded can still poll them. */
export const COMMAND_GRACE_MS = 10 * 60 * 1000;
const LAST_SEEN_WRITE_THROTTLE_MS = 60_000;
const MAX_DEVICES_PER_WORKSPACE = 10;
/**
 * Device registrations and removals per workspace per minute. The app posts
 * when notifications are switched on, when a flag changes and once at launch,
 * and deletes when they are switched off or the board is left — a handful in
 * a busy minute. Unthrottled, a register-then-delete loop added one permanent
 * flagged row per pair, limited only by how fast HTTP goes.
 */
const DEVICE_CHANGES_PER_MINUTE = 10;
/**
 * Device tokens a workspace may ever have on disk, live AND flagged. The
 * window above slows a register/delete loop; only this ends it, because a
 * delete flags the row and the live cap of 10 never sees it again. A token
 * already on disk — live, or flagged and coming back — never counts twice.
 * APNs issues a new token on a reinstall, a restore or a new phone, and ten
 * full turnovers of the live cap is years of that for a small team; a board
 * that does reach it can be replaced with a fresh one in seconds.
 */
const MAX_DEVICE_TOKENS_PER_WORKSPACE = 100;
/**
 * GET /api/usage/history per workspace per minute. Each read sorts and
 * serialises the whole held series — bounded now by the caps above, but not
 * free — on the one Node thread every tenant shares. The web board reads it
 * when the usage screen opens and the iOS board once per connect (its streak),
 * and a workspace has at most 10 viewer streams; three reads a viewer a minute
 * is far past either.
 */
const HISTORY_READS_PER_MINUTE = 30;

// Pairing codes: short-lived, single-use, in-memory only (never SQLite).
// No I/L/O/0/1 to keep the codes unambiguous when read aloud or typed.
const PAIR_CODE_ALPHABET = 'ABCDEFGHJKMNPQRSTUVWXYZ23456789';
const PAIR_CODE_LENGTH = 8;
export const PAIR_CODE_TTL_MS = 15 * 60 * 1000;
const MAX_PAIR_CODES_PER_WORKSPACE = 3;

function hashToken(token: string): string {
  return crypto.createHash('sha256').update(token).digest('hex');
}

interface WorkspaceMeta {
  createdAt: number;
  lastSeenAt: number;
}

export class Store {
  private sessions = new Map<string, Map<string, Session>>();
  private workspaces = new Map<string, WorkspaceMeta>();
  // Push-notification device tokens per workspace (token → notifyDone + createdAt).
  private deviceTokens = new Map<
    string,
    Map<string, { notifyDone: boolean; createdAt: number; apnsServer: string | null }>
  >();
  // Tokens whose device row is flagged on disk, per workspace. Never pushed to;
  // kept so the lifetime cap can count them and so re-registering one revives
  // its row instead of counting as a new token. Bounded by that cap.
  private retiredDeviceTokens = new Map<string, Set<string>>();
  private webhookWindows = new Map<string, { windowStart: number; count: number }>();
  private deviceWindows = new Map<string, { windowStart: number; count: number }>();
  private historyWindows = new Map<string, { windowStart: number; count: number }>();
  // Plan-limit usage per workspace, keyed by source ("claude", "codex", …).
  private usageBySource = new Map<string, Map<string, Usage>>();
  // Sources each workspace reports usage under, across all three usage
  // endpoints; at most MAX_USAGE_SOURCES_PER_WORKSPACE. Rebuilt from what
  // load() keeps, so a source with nothing left in memory is forgotten.
  private usageSources = new Map<string, Set<string>>();
  // Per-session timelines (ascending seq), wsId → sessionId → events.
  private events = new Map<string, Map<string, SessionEvent[]>>();
  // Limit utilization over time, wsId → `${source}\n${windowId}` → ascending points.
  private usagePoints = new Map<string, Map<string, UsagePoint[]>>();
  // Token spend per agent and project, wsId → `${source}\n${project}\n${day}` → row.
  private projectDays = new Map<string, Map<string, ProjectDay>>();
  // Lifetime tokens per session, wsId → `${source}\n${sessionId}` → row. Kept
  // apart from `sessions` on purpose: the rows arrive on their own endpoint,
  // outlive the cards they describe, and exist for ids that never had a card.
  private sessionTotals = new Map<string, Map<string, SessionTotal>>();
  // The next session_events seq, for every session of every workspace. One
  // number, not one per session: the counter it replaced was a Map entry per
  // session id ever seen, which nothing could ever remove — forgetting one
  // would restart that session at 0, collide with its soft-deleted rows on the
  // primary key, and the upsert would overwrite and un-delete them. A single
  // counter seeded past MAX(seq) over every row, flagged ones included, never
  // reuses a key and costs eight bytes however many sessions come and go.
  // It is still what every reader of seq relies on: unique within a session
  // (it is unique everywhere) and increasing within one (it increases
  // everywhere); it is no longer dense or zero-based, which nothing assumes.
  private nextSeq = 0;
  // Escrowed pairing codes, keyed by the normalized (dash-less) code.
  private pairCodes = new Map<string, { rawToken: string; expiresAt: number }>();
  // Focus commands, wsId → id → command; in memory only, swept like pair codes.
  private commands = new Map<string, Map<string, Command>>();
  private commandWindows = new Map<string, { windowStart: number; count: number }>();
  private listenerWindows = new Map<string, { windowStart: number; count: number }>();
  // Commands the server finished itself — expired (by the sweep or lazily on
  // read) or cancelled with their session — and has not yet handed to app.ts,
  // so each gets exactly one command_ack broadcast.
  private unannounced: Command[] = [];
  private pool: Pool | null = null;
  // Writes are fire-and-forget but strictly ordered: each is chained onto this
  // queue so an upsert can never overtake the delete that preceded it.
  private writeQueue: Promise<void> = Promise.resolve();
  /** Resolves once the schema exists and persisted state is loaded into memory. */
  readonly ready: Promise<void>;

  constructor(databaseUrl: string) {
    if (!databaseUrl) {
      this.ready = Promise.resolve();
      return;
    }
    // Lazy require keeps the module optional for pure in-memory use.
    // eslint-disable-next-line @typescript-eslint/no-var-requires
    const { Pool } = require('pg') as typeof import('pg');
    this.pool = new Pool({ connectionString: databaseUrl, max: 4 });
    // Idle-client errors surface on the pool; a dropped connection must not
    // take the server down (the pool reconnects on the next query).
    this.pool.on('error', (err) => console.warn(`Postgres pool error: ${err.message}`));
    this.ready = this.init();
    this.writeQueue = this.ready.catch(() => undefined);
  }

  private async init(): Promise<void> {
    const pool = this.pool!;
    // Soft deletes only: rows are never removed, deletion sets deleted_at and
    // every load filters on it. Upserts resurrect a flagged row (deleted_at
    // back to NULL) so a re-posted session or re-registered device just works.
    await pool.query(`
      CREATE TABLE IF NOT EXISTS workspaces (
        id TEXT PRIMARY KEY,
        created_at BIGINT NOT NULL,
        last_seen_at BIGINT NOT NULL,
        deleted_at BIGINT
      );
      CREATE TABLE IF NOT EXISTS sessions (
        workspace_id TEXT NOT NULL,
        id TEXT NOT NULL,
        name TEXT NOT NULL,
        status TEXT NOT NULL,
        message TEXT NOT NULL,
        project TEXT NOT NULL,
        source TEXT NOT NULL DEFAULT 'claude',
        created_at BIGINT NOT NULL,
        updated_at BIGINT NOT NULL,
        deleted_at BIGINT,
        host TEXT,
        PRIMARY KEY (workspace_id, id)
      );
      CREATE TABLE IF NOT EXISTS devices (
        workspace_id TEXT NOT NULL,
        device_token TEXT NOT NULL,
        platform TEXT NOT NULL,
        notify_done INTEGER NOT NULL,
        created_at BIGINT NOT NULL,
        updated_at BIGINT NOT NULL,
        deleted_at BIGINT,
        apns_server TEXT,
        PRIMARY KEY (workspace_id, device_token)
      );
      CREATE TABLE IF NOT EXISTS usage_limits (
        workspace_id TEXT NOT NULL,
        source TEXT NOT NULL,
        windows TEXT NOT NULL,
        updated_at BIGINT NOT NULL,
        deleted_at BIGINT,
        PRIMARY KEY (workspace_id, source)
      );
      CREATE TABLE IF NOT EXISTS usage_history (
        workspace_id TEXT NOT NULL,
        source TEXT NOT NULL,
        window_id TEXT NOT NULL,
        at BIGINT NOT NULL,
        used_pct DOUBLE PRECISION NOT NULL,
        deleted_at BIGINT,
        PRIMARY KEY (workspace_id, source, window_id, at)
      );
      CREATE TABLE IF NOT EXISTS usage_project_days (
        workspace_id TEXT NOT NULL,
        source TEXT NOT NULL,
        project TEXT NOT NULL,
        day TEXT NOT NULL,
        tokens BIGINT NOT NULL,
        updated_at BIGINT NOT NULL,
        deleted_at BIGINT,
        PRIMARY KEY (workspace_id, source, project, day)
      );
      CREATE TABLE IF NOT EXISTS usage_session_totals (
        workspace_id TEXT NOT NULL,
        source TEXT NOT NULL,
        session_id TEXT NOT NULL,
        tokens BIGINT NOT NULL,
        updated_at BIGINT NOT NULL,
        deleted_at BIGINT,
        PRIMARY KEY (workspace_id, source, session_id)
      );
      CREATE TABLE IF NOT EXISTS session_events (
        workspace_id TEXT NOT NULL,
        session_id TEXT NOT NULL,
        seq BIGINT NOT NULL,
        status TEXT NOT NULL,
        message TEXT NOT NULL,
        at BIGINT NOT NULL,
        deleted_at BIGINT,
        PRIMARY KEY (workspace_id, session_id, seq)
      );
    `);

    // Databases created before these columns existed.
    await pool.query('ALTER TABLE devices ADD COLUMN IF NOT EXISTS apns_server TEXT');
    await pool.query('ALTER TABLE sessions ADD COLUMN IF NOT EXISTS host TEXT');

    // node-postgres returns BIGINT as string to avoid precision loss; every
    // epoch-ms value here fits a double, so Number() them on the way in.
    const workspaces = await pool.query(
      'SELECT id, created_at, last_seen_at FROM workspaces WHERE deleted_at IS NULL'
    );
    for (const row of workspaces.rows as Array<{ id: string; created_at: string; last_seen_at: string }>) {
      this.workspaces.set(row.id, {
        createdAt: Number(row.created_at),
        lastSeenAt: Number(row.last_seen_at),
      });
    }

    const sessions = await pool.query('SELECT * FROM sessions WHERE deleted_at IS NULL');
    for (const row of sessions.rows as Array<Record<string, unknown>>) {
      const wsId = row.workspace_id as string;
      let map = this.sessions.get(wsId);
      if (!map) {
        map = new Map();
        this.sessions.set(wsId, map);
      }
      // Re-validated on the way in: a column that is not JSON, or is JSON of
      // the wrong shape, loads as no host; the next post with one overwrites it.
      let host: Host | null = null;
      try {
        if (typeof row.host === 'string') host = normalizeHost(JSON.parse(row.host));
      } catch {
        // not JSON at all
      }
      map.set(row.id as string, {
        id: row.id as string,
        name: row.name as string,
        status: row.status as Status,
        message: row.message as string,
        project: row.project as string,
        source: (row.source as string) || 'claude',
        host,
        createdAt: Number(row.created_at),
        updatedAt: Number(row.updated_at),
      });
    }

    const devices = await pool.query(
      'SELECT workspace_id, device_token, notify_done, created_at, apns_server FROM devices WHERE deleted_at IS NULL'
    );
    for (const row of devices.rows as Array<{
      workspace_id: string; device_token: string; notify_done: number; created_at: string;
      apns_server: string | null;
    }>) {
      let map = this.deviceTokens.get(row.workspace_id);
      if (!map) {
        map = new Map();
        this.deviceTokens.set(row.workspace_id, map);
      }
      map.set(row.device_token, {
        notifyDone: row.notify_done === 1,
        createdAt: Number(row.created_at),
        apnsServer: row.apns_server ?? null,
      });
    }

    // The flagged device rows of live boards, which the lifetime cap counts.
    // Ranked in SQL rather than capped here: a register/delete loop from before
    // that cap existed can have left any number of them, and pg hands back the
    // whole result at once — a cap applied after the query would come too late
    // to keep startup from holding all of it.
    const retired = await pool.query(
      `SELECT workspace_id, device_token FROM (
         SELECT d.workspace_id, d.device_token,
                ROW_NUMBER() OVER (PARTITION BY d.workspace_id ORDER BY d.deleted_at DESC) AS rank
         FROM devices d JOIN workspaces w ON w.id = d.workspace_id AND w.deleted_at IS NULL
         WHERE d.deleted_at IS NOT NULL
       ) ranked
       WHERE rank <= $1`,
      [MAX_DEVICE_TOKENS_PER_WORKSPACE]
    );
    for (const row of retired.rows as Array<{ workspace_id: string; device_token: string }>) {
      let set = this.retiredDeviceTokens.get(row.workspace_id);
      if (!set) {
        set = new Set();
        this.retiredDeviceTokens.set(row.workspace_id, set);
      }
      set.add(row.device_token);
    }

    // Only reports young enough for getUsage() to serve: an older one would
    // be filtered out of every read anyway, so loading it only spent memory —
    // and spent it on whatever a source flood left behind. Ranked per
    // workspace for the reason given at the retired-device query above.
    const usage = await pool.query(
      `SELECT workspace_id, source, windows, updated_at FROM (
         SELECT workspace_id, source, windows, updated_at,
                ROW_NUMBER() OVER (PARTITION BY workspace_id ORDER BY updated_at DESC) AS rank
         FROM usage_limits
         WHERE deleted_at IS NULL AND updated_at >= $1
       ) ranked
       WHERE rank <= $2
       ORDER BY updated_at DESC`,
      [Date.now() - USAGE_TTL_MS, MAX_USAGE_SOURCES_PER_WORKSPACE]
    );
    for (const row of usage.rows as Array<{
      workspace_id: string; source: string; windows: string; updated_at: string;
    }>) {
      let windows: UsageWindow[];
      try {
        windows = JSON.parse(row.windows) as UsageWindow[];
      } catch {
        continue; // corrupt row — skip, it will be overwritten on the next report
      }
      if (!this.admitUsageSource(row.workspace_id, row.source)) continue;
      let map = this.usageBySource.get(row.workspace_id);
      if (!map) {
        map = new Map();
        this.usageBySource.set(row.workspace_id, map);
      }
      map.set(row.source, { source: row.source, windows, updatedAt: Number(row.updated_at) });
    }

    // Only the retained window is loaded: older points are left on disk rather
    // than deleted, per the soft-delete rule, but never reach memory. Within
    // it, only what memory would hold anyway — the newest MAX_USAGE_POINTS of
    // each series, and the MAX_USAGE_SERIES_PER_WORKSPACE series heard from
    // most recently — chosen in SQL, because these rows were never bounded on
    // disk: a series flood from before the caps can sit inside the window in
    // any quantity, and pg would hand all of it to startup in one result.
    const historySince = Date.now() - MAX_HISTORY_DAYS * DAY_MS;
    const points = await pool.query(
      `SELECT workspace_id, source, window_id, at, used_pct FROM (
         SELECT workspace_id, source, window_id, at, used_pct,
                DENSE_RANK() OVER (
                  PARTITION BY workspace_id ORDER BY newest DESC, source, window_id
                ) AS series_rank
         FROM (
           SELECT workspace_id, source, window_id, at, used_pct,
                  ROW_NUMBER() OVER (PARTITION BY workspace_id, source, window_id ORDER BY at DESC) AS point_rank,
                  MAX(at) OVER (PARTITION BY workspace_id, source, window_id) AS newest
           FROM usage_history
           WHERE deleted_at IS NULL AND at >= $1
         ) series_points
         WHERE point_rank <= $2
       ) ranked
       WHERE series_rank <= $3
       ORDER BY at`,
      [historySince, MAX_USAGE_POINTS, MAX_USAGE_SERIES_PER_WORKSPACE]
    );
    for (const row of points.rows as Array<{
      workspace_id: string; source: string; window_id: string; at: string; used_pct: string;
    }>) {
      if (!this.admitUsageSource(row.workspace_id, row.source)) continue;
      let ws = this.usagePoints.get(row.workspace_id);
      if (!ws) {
        ws = new Map();
        this.usagePoints.set(row.workspace_id, ws);
      }
      const key = `${row.source}\n${row.window_id}`;
      let list = ws.get(key);
      if (!list) {
        list = [];
        ws.set(key, list);
      }
      list.push({ at: Number(row.at), usedPct: Number(row.used_pct) });
    }
    for (const ws of this.usagePoints.values()) {
      for (const list of ws.values()) {
        if (list.length > MAX_USAGE_POINTS) list.splice(0, list.length - MAX_USAGE_POINTS);
      }
    }

    // The same window the write path admits, at both ends. It used to be
    // bounded below only, so a row dated 9999-… passed every restart's filter
    // forever — and a flood big enough to exhaust memory at runtime would have
    // been reloaded whole on the next boot, crash-looping the process until
    // someone flagged the rows by hand. Within the window, the newest
    // MAX_PROJECT_DAYS_PER_WORKSPACE days of each board, ranked in SQL for the
    // reason given at the usage_history query above: rows written before the
    // cap existed are not bounded on disk. A string inside the window that is
    // not a real day (2026-09-45) is skipped here; it can only be left over
    // from before the write path checked.
    const projectWindow = projectDayWindow(Date.now());
    const projectDays = await pool.query(
      `SELECT workspace_id, source, project, day, tokens FROM (
         SELECT workspace_id, source, project, day, tokens,
                ROW_NUMBER() OVER (PARTITION BY workspace_id ORDER BY day DESC, updated_at DESC) AS rank
         FROM usage_project_days
         WHERE deleted_at IS NULL AND day >= $1 AND day <= $2
       ) ranked
       WHERE rank <= $3`,
      [projectWindow.oldest, projectWindow.newest, MAX_PROJECT_DAYS_PER_WORKSPACE]
    );
    for (const row of projectDays.rows as Array<{
      workspace_id: string; source: string; project: string; day: string; tokens: string;
    }>) {
      if (!isCalendarDay(row.day)) continue;
      if (!this.admitUsageSource(row.workspace_id, row.source)) continue;
      let ws = this.projectDays.get(row.workspace_id);
      if (!ws) {
        ws = new Map();
        this.projectDays.set(row.workspace_id, ws);
      }
      ws.set(`${row.source}\n${row.project}\n${row.day}`, {
        source: row.source,
        project: row.project,
        day: row.day,
        tokens: Number(row.tokens),
      });
    }

    // Session totals run on their own retention (SESSION_TOTAL_TTL_MS, by
    // received-at rather than by day), so they need their own filter here:
    // anything older is left on disk, per the soft-delete rule, and never
    // reaches memory. Ordered oldest-first so the per-workspace cap below
    // keeps the freshest rows when a database holds more than memory should.
    const totalsSince = Date.now() - SESSION_TOTAL_TTL_MS;
    const sessionTotals = await pool.query(
      `SELECT workspace_id, source, session_id, tokens, updated_at FROM usage_session_totals
       WHERE deleted_at IS NULL AND updated_at >= $1 ORDER BY updated_at`,
      [totalsSince]
    );
    for (const row of sessionTotals.rows as Array<{
      workspace_id: string; source: string; session_id: string; tokens: string; updated_at: string;
    }>) {
      if (!this.admitUsageSource(row.workspace_id, row.source)) continue;
      let ws = this.sessionTotals.get(row.workspace_id);
      if (!ws) {
        ws = new Map();
        this.sessionTotals.set(row.workspace_id, ws);
      }
      ws.set(`${row.source}\n${row.session_id}`, {
        source: row.source,
        sessionId: row.session_id,
        tokens: Number(row.tokens),
        updatedAt: Number(row.updated_at),
      });
      // Insertion order is the load order, which is oldest-first: dropping
      // from the front keeps the newest MAX_SESSION_TOTALS_PER_WORKSPACE.
      if (ws.size > MAX_SESSION_TOTALS_PER_WORKSPACE) {
        const oldest = ws.keys().next();
        if (!oldest.done) ws.delete(oldest.value);
      }
    }

    const events = await pool.query(
      `SELECT workspace_id, session_id, seq, status, message, at FROM session_events
       WHERE deleted_at IS NULL ORDER BY seq`
    );
    for (const row of events.rows as Array<{
      workspace_id: string; session_id: string; seq: string; status: string; message: string; at: string;
    }>) {
      let ws = this.events.get(row.workspace_id);
      if (!ws) {
        ws = new Map();
        this.events.set(row.workspace_id, ws);
      }
      let list = ws.get(row.session_id);
      if (!list) {
        list = [];
        ws.set(row.session_id, list);
      }
      list.push({
        seq: Number(row.seq),
        status: row.status as Status,
        message: row.message,
        at: Number(row.at),
      });
    }
    // The counter continues past soft-deleted rows, so MAX is over every row —
    // which is what guarantees no new event can land on a flagged row's key.
    // One scalar: this used to be a GROUP BY that loaded a counter for every
    // session id the database had ever seen, deleted boards included.
    const seq = await pool.query(
      'SELECT COALESCE(MAX(seq), -1) + 1 AS next_seq FROM session_events'
    );
    // max(): never backwards, even past an event recorded before load finished.
    this.nextSeq = Math.max(this.nextSeq, Number((seq.rows[0] as { next_seq: string }).next_seq));
  }

  /**
   * Enqueues a persistence write. Failures are logged, never thrown — memory
   * stays authoritative and the dashboard keeps working through DB outages.
   */
  private exec(text: string, values: unknown[]): void {
    // Capture the pool now: close() nulls the field, but writes already
    // enqueued must still drain against the live pool.
    const pool = this.pool;
    if (!pool) return;
    this.writeQueue = this.writeQueue
      .then(() => pool.query(text, values))
      .then(() => undefined)
      .catch((err: unknown) =>
        console.warn(`Postgres write failed: ${err instanceof Error ? err.message : String(err)}`)
      );
  }

  /** Resolves when every write enqueued so far has been flushed to Postgres. */
  flush(): Promise<void> {
    return this.writeQueue;
  }

  private static readonly INSERT_WS =
    `INSERT INTO workspaces (id, created_at, last_seen_at) VALUES ($1, $2, $3)
     ON CONFLICT (id) DO UPDATE SET deleted_at = NULL`;

  createWorkspace(): { token: string } {
    const token = 'ags_' + crypto.randomBytes(24).toString('base64url');
    const wsId = hashToken(token);
    const now = Date.now();
    this.workspaces.set(wsId, { createdAt: now, lastSeenAt: now });
    this.exec(Store.INSERT_WS, [wsId, now, now]);
    return { token };
  }

  /** Returns the workspace id for a valid, known token; null otherwise. */
  resolveToken(token: string): string | null {
    if (!TOKEN_RE.test(token)) return null;
    const wsId = hashToken(token);
    const meta = this.workspaces.get(wsId);
    if (!meta) return null;
    const now = Date.now();
    if (now - meta.lastSeenAt > LAST_SEEN_WRITE_THROTTLE_MS) {
      meta.lastSeenAt = now;
      this.exec('UPDATE workspaces SET last_seen_at = $1 WHERE id = $2', [now, wsId]);
    }
    return wsId;
  }

  hasWorkspace(wsId: string): boolean {
    return this.workspaces.has(wsId);
  }

  workspaceCount(): number {
    return this.workspaces.size;
  }

  deleteWorkspace(wsId: string): boolean {
    const existed = this.workspaces.delete(wsId);
    this.sessions.delete(wsId);
    this.webhookWindows.delete(wsId);
    this.deviceWindows.delete(wsId);
    this.historyWindows.delete(wsId);
    this.deviceTokens.delete(wsId);
    this.retiredDeviceTokens.delete(wsId);
    this.usageBySource.delete(wsId);
    this.usageSources.delete(wsId);
    this.events.delete(wsId);
    this.usagePoints.delete(wsId);
    this.projectDays.delete(wsId);
    this.sessionTotals.delete(wsId);
    this.commands.delete(wsId);
    this.commandWindows.delete(wsId);
    this.listenerWindows.delete(wsId);
    if (existed) {
      const now = Date.now();
      // `host` used to be nulled here, which was the one place this store
      // DESTROYED data rather than hiding it: the machine label and the app a
      // session ran in were overwritten and unrecoverable. Every other column
      // survives a delete, and now so does this one. Deleting a board flags its
      // rows; it does not erase them.
      this.exec('UPDATE sessions SET deleted_at = $2 WHERE workspace_id = $1 AND deleted_at IS NULL', [wsId, now]);
      this.exec('UPDATE devices SET deleted_at = $2 WHERE workspace_id = $1 AND deleted_at IS NULL', [wsId, now]);
      this.exec('UPDATE usage_limits SET deleted_at = $2 WHERE workspace_id = $1 AND deleted_at IS NULL', [wsId, now]);
      this.exec('UPDATE session_events SET deleted_at = $2 WHERE workspace_id = $1 AND deleted_at IS NULL', [wsId, now]);
      this.exec('UPDATE usage_history SET deleted_at = $2 WHERE workspace_id = $1 AND deleted_at IS NULL', [wsId, now]);
      this.exec('UPDATE usage_project_days SET deleted_at = $2 WHERE workspace_id = $1 AND deleted_at IS NULL', [wsId, now]);
      this.exec('UPDATE usage_session_totals SET deleted_at = $2 WHERE workspace_id = $1 AND deleted_at IS NULL', [wsId, now]);
      this.exec('UPDATE workspaces SET deleted_at = $2 WHERE id = $1', [wsId, now]);
    }
    return existed;
  }

  upsertSession(
    wsId: string,
    input: UpsertInput,
    maxSessions: number
  ): { session: Session; evictedId: string | null; prevStatus: Status | null } {
    let map = this.sessions.get(wsId);
    if (!map) {
      map = new Map();
      this.sessions.set(wsId, map);
      // Legacy mode has no createWorkspace() call; keep the DB row present so
      // persisted sessions satisfy the workspace_id relationship.
      if (this.pool && !this.workspaces.has(wsId)) {
        const now = Date.now();
        this.exec(Store.INSERT_WS, [wsId, now, now]);
      }
    }

    const now = Date.now();
    const prev = map.get(input.id);
    const session: Session = {
      id: input.id,
      name: input.name !== undefined ? input.name || prev?.name || input.id : prev?.name || input.id,
      status: input.status,
      message: input.message !== undefined ? input.message : prev?.message ?? '',
      project: input.project !== undefined ? input.project : prev?.project ?? '',
      source: input.source ?? prev?.source ?? 'claude',
      // Always a key (null, never undefined) so the wire shape is stable.
      host: input.host !== undefined ? input.host : prev?.host ?? null,
      createdAt: prev?.createdAt ?? now,
      updatedAt: now,
    };

    let evictedId: string | null = null;
    if (!prev && map.size >= maxSessions) {
      let oldest: Session | null = null;
      for (const s of map.values()) {
        if (!oldest || s.updatedAt < oldest.updatedAt) oldest = s;
      }
      if (oldest) {
        map.delete(oldest.id);
        // Flagged, not erased — `host` stays on the row. This used to null it,
        // which made a cap eviction destroy the machine and app a session ran
        // on, unrecoverably and without anyone asking for a delete at all.
        this.exec(
          'UPDATE sessions SET deleted_at = $3 WHERE workspace_id = $1 AND id = $2',
          [wsId, oldest.id, now]
        );
        this.dropEvents(wsId, oldest.id);
        this.cancelCommands(wsId, oldest.id);
        evictedId = oldest.id;
      }
    }

    map.set(session.id, session);
    // Timeline: record real transitions, not keep-alive re-posts of the same
    // status+message (PreToolUse fires between every tool call).
    if (!prev || prev.status !== session.status || prev.message !== session.message) {
      this.recordEvent(wsId, session.id, session.status, session.message, now);
    }
    this.exec(
      `INSERT INTO sessions (workspace_id, id, name, status, message, project, source, host, created_at, updated_at)
       VALUES ($1, $2, $3, $4, $5, $6, $7, $8, $9, $10)
       ON CONFLICT (workspace_id, id) DO UPDATE SET
         name = EXCLUDED.name, status = EXCLUDED.status, message = EXCLUDED.message,
         project = EXCLUDED.project, source = EXCLUDED.source, host = EXCLUDED.host,
         updated_at = EXCLUDED.updated_at, deleted_at = NULL`,
      [
        wsId,
        session.id,
        session.name,
        session.status,
        session.message,
        session.project,
        session.source,
        session.host ? JSON.stringify(session.host) : null,
        session.createdAt,
        session.updatedAt,
      ]
    );
    return { session: this.withTokens(wsId, session), evictedId, prevStatus: prev?.status ?? null };
  }

  /**
   * Registers (or updates) a push-notification device token. Tokens are
   * normalized to lowercase. Returns 'cap' only when a NEW device would exceed
   * the per-workspace limit of live devices, and 'lifetime' when a token the
   * workspace has never had would take it past MAX_DEVICE_TOKENS_PER_WORKSPACE
   * rows on disk; updates to existing devices always succeed, and a token
   * whose row is flagged comes back without counting as new.
   */
  upsertDevice(wsId: string, deviceToken: string, notifyDone: boolean): 'ok' | 'cap' | 'lifetime' {
    const token = deviceToken.toLowerCase();
    let map = this.deviceTokens.get(wsId);
    if (!map) {
      map = new Map();
      this.deviceTokens.set(wsId, map);
    }
    const existing = map.get(token);
    const retired = this.retiredDeviceTokens.get(wsId);
    if (!existing && map.size >= MAX_DEVICES_PER_WORKSPACE) return 'cap';
    if (!existing && !retired?.has(token)
        && map.size + (retired?.size ?? 0) >= MAX_DEVICE_TOKENS_PER_WORKSPACE) {
      return 'lifetime';
    }
    retired?.delete(token); // the upsert below un-flags its row
    const now = Date.now();
    const createdAt = existing?.createdAt ?? now;
    // Re-registering keeps the learned endpoint: the same token on the same
    // build still belongs to the same APNs environment.
    map.set(token, { notifyDone, createdAt, apnsServer: existing?.apnsServer ?? null });
    this.exec(
      `INSERT INTO devices (workspace_id, device_token, platform, notify_done, created_at, updated_at)
       VALUES ($1, $2, 'ios', $3, $4, $5)
       ON CONFLICT (workspace_id, device_token) DO UPDATE SET
         notify_done = EXCLUDED.notify_done, updated_at = EXCLUDED.updated_at, deleted_at = NULL`,
      [wsId, token, notifyDone ? 1 : 0, createdAt, now]
    );
    return 'ok';
  }

  deleteDevice(wsId: string, deviceToken: string): boolean {
    const token = deviceToken.toLowerCase();
    const removed = this.deviceTokens.get(wsId)?.delete(token) ?? false;
    if (removed) {
      // The row stays on disk, flagged, so the lifetime cap keeps counting it.
      let retired = this.retiredDeviceTokens.get(wsId);
      if (!retired) {
        retired = new Set();
        this.retiredDeviceTokens.set(wsId, retired);
      }
      retired.add(token);
      this.exec(
        'UPDATE devices SET deleted_at = $3 WHERE workspace_id = $1 AND device_token = $2',
        [wsId, token, Date.now()]
      );
    }
    return removed;
  }

  devices(wsId: string): Device[] {
    const map = this.deviceTokens.get(wsId);
    if (!map) return [];
    return Array.from(map, ([deviceToken, d]) => ({
      deviceToken,
      notifyDone: d.notifyDone,
      apnsServer: d.apnsServer,
    }));
  }

  /**
   * Records which APNs endpoint accepted this token, so later pushes go
   * straight there instead of rediscovering it. No-op for unknown devices.
   */
  setDeviceApnsServer(wsId: string, deviceToken: string, server: string): void {
    const token = deviceToken.toLowerCase();
    const entry = this.deviceTokens.get(wsId)?.get(token);
    if (!entry || entry.apnsServer === server) return;
    entry.apnsServer = server;
    this.exec(
      'UPDATE devices SET apns_server = $3 WHERE workspace_id = $1 AND device_token = $2',
      [wsId, token, server]
    );
  }

  deviceCount(wsId: string): number {
    return this.deviceTokens.get(wsId)?.size ?? 0;
  }

  /**
   * Whether `source` may report usage to this workspace — one it already
   * reports under, or a new one while it holds fewer than
   * MAX_USAGE_SOURCES_PER_WORKSPACE — and records it if so. app.ts asks once a
   * report has passed validation, so a malformed post never takes a slot;
   * load() asks for every row it keeps, so a database holding more sources
   * than that (written before the cap) restarts with the cap.
   */
  admitUsageSource(wsId: string, source: string): boolean {
    let sources = this.usageSources.get(wsId);
    if (!sources) {
      sources = new Set();
      this.usageSources.set(wsId, sources);
    }
    if (sources.has(source)) return true;
    if (sources.size >= MAX_USAGE_SOURCES_PER_WORKSPACE) return false;
    sources.add(source);
    return true;
  }

  /** Stores the latest plan usage for one source and returns the stamped record. */
  setUsage(wsId: string, source: string, windows: UsageWindow[]): Usage {
    let map = this.usageBySource.get(wsId);
    if (!map) {
      map = new Map();
      this.usageBySource.set(wsId, map);
      // Same legacy-mode concern as upsertSession: keep the workspace row
      // present so persisted usage satisfies the workspace_id relationship.
      if (this.pool && !this.workspaces.has(wsId)) {
        const now = Date.now();
        this.exec(Store.INSERT_WS, [wsId, now, now]);
      }
    }
    const usage: Usage = { source, windows, updatedAt: Date.now() };
    map.set(source, usage);
    this.recordUsagePoints(wsId, source, windows, usage.updatedAt);
    this.exec(
      `INSERT INTO usage_limits (workspace_id, source, windows, updated_at)
       VALUES ($1, $2, $3, $4)
       ON CONFLICT (workspace_id, source) DO UPDATE SET
         windows = EXCLUDED.windows, updated_at = EXCLUDED.updated_at, deleted_at = NULL`,
      [wsId, source, JSON.stringify(windows), usage.updatedAt]
    );
    return usage;
  }

  /**
   * Appends a point for every window whose utilization actually moved. A plan
   * limit is a step function and reports arrive every few minutes, mostly
   * repeating the last value, so recording only the changes keeps the series
   * small without losing its shape.
   *
   * Two bounds on top of that, both refusals rather than evictions so that
   * what reaches usage_history is bounded too: no new series past
   * MAX_USAGE_SERIES_PER_WORKSPACE, and no point closer than
   * USAGE_POINT_MIN_INTERVAL_MS to the one before it in its series. The second
   * also keeps a series in order if the clock ever steps back.
   */
  private recordUsagePoints(wsId: string, source: string, windows: UsageWindow[], at: number): void {
    let ws = this.usagePoints.get(wsId);
    if (!ws) {
      ws = new Map();
      this.usagePoints.set(wsId, ws);
    }
    for (const w of windows) {
      const key = `${source}\n${w.id}`;
      let list = ws.get(key);
      if (!list) {
        if (ws.size >= MAX_USAGE_SERIES_PER_WORKSPACE) this.forgetSilentSeries(ws, at);
        if (ws.size >= MAX_USAGE_SERIES_PER_WORKSPACE) continue;
        list = [];
        ws.set(key, list);
      }
      const prev = list[list.length - 1];
      if (prev && prev.usedPct === w.usedPct) continue;
      if (prev && at - prev.at < USAGE_POINT_MIN_INTERVAL_MS) continue;
      list.push({ at, usedPct: w.usedPct });
      if (list.length > MAX_USAGE_POINTS) list.splice(0, list.length - MAX_USAGE_POINTS);
      this.exec(
        `INSERT INTO usage_history (workspace_id, source, window_id, at, used_pct)
         VALUES ($1, $2, $3, $4, $5)
         ON CONFLICT (workspace_id, source, window_id, at) DO NOTHING`,
        [wsId, source, w.id, at, w.usedPct]
      );
    }
  }

  /**
   * Drops, from memory only, every series whose newest point is older than
   * the history window — the series a restart would not load. Their rows stay
   * on disk unflagged, exactly like every other point that has aged out of the
   * window. Only run when the series cap is reached, so a board whose window
   * ids followed a model that has since gone gets the slot back.
   */
  private forgetSilentSeries(ws: Map<string, UsagePoint[]>, now: number): void {
    const cutoff = now - MAX_HISTORY_DAYS * DAY_MS;
    for (const [key, list] of ws) {
      const newest = list[list.length - 1];
      if (!newest || newest.at < cutoff) ws.delete(key);
    }
  }

  /**
   * Recorded utilization per (source, window) since `since`. Each series keeps
   * the last reading from *before* the cutoff as its first point: without that
   * anchor a step chart has nothing to draw from until the first change lands
   * inside the window.
   */
  getUsageHistory(
    wsId: string,
    since: number
  ): Array<{ source: string; windowId: string; points: UsagePoint[] }> {
    const ws = this.usagePoints.get(wsId);
    if (!ws) return [];
    const out: Array<{ source: string; windowId: string; points: UsagePoint[] }> = [];
    for (const [key, list] of ws) {
      const [source, windowId] = key.split('\n');
      let start = list.findIndex((p) => p.at >= since);
      if (start === -1) start = list.length - 1; // all older: keep the newest as the anchor
      else if (start > 0) start -= 1;
      const points = start < 0 ? [] : list.slice(start);
      if (points.length > 0) out.push({ source, windowId, points });
    }
    return out.sort(
      (a, b) => a.source.localeCompare(b.source) || a.windowId.localeCompare(b.windowId)
    );
  }

  /**
   * Replaces the token totals for the given (source, project, day) rows. Whole
   * days are replaced rather than incremented so a re-run — a backfill, or a
   * hook re-reporting today — converges instead of double-counting.
   *
   * Not every row is held, and the counts say what became of each:
   * - dropped: not a real day, or outside projectDayWindow. Silently, not a
   *   400 — `--backfill` sends everything the logs still have, and the logs
   *   can reach further back than the window does. Rows that are only too old
   *   are the hook's business; rows dated 9999-99-99 are nobody's.
   * - refused: a new key with the workspace at MAX_PROJECT_DAYS_PER_WORKSPACE.
   * - stored: everything else, which is written through as before.
   */
  setProjectDays(
    wsId: string,
    source: string,
    days: Array<{ project: string; day: string; tokens: number }>
  ): { stored: number; dropped: number; refused: number } {
    let ws = this.projectDays.get(wsId);
    if (!ws) {
      ws = new Map();
      this.projectDays.set(wsId, ws);
      // Same legacy-mode concern as upsertSession: keep the workspace row
      // present so persisted rows satisfy the workspace_id relationship.
      if (this.pool && !this.workspaces.has(wsId)) {
        const now = Date.now();
        this.exec(Store.INSERT_WS, [wsId, now, now]);
      }
    }
    const now = Date.now();
    const { oldest, newest } = projectDayWindow(now);
    // Before admitting anything, so the days that just aged out free their
    // slots for today's.
    this.pruneProjectDays(wsId, ws, oldest, now);
    let stored = 0;
    let dropped = 0;
    let refused = 0;
    for (const d of days) {
      if (!isCalendarDay(d.day) || d.day < oldest || d.day > newest) {
        dropped += 1;
        continue;
      }
      const key = `${source}\n${d.project}\n${d.day}`;
      if (!ws.has(key) && ws.size >= MAX_PROJECT_DAYS_PER_WORKSPACE) {
        refused += 1;
        continue;
      }
      ws.set(key, {
        source,
        project: d.project,
        day: d.day,
        tokens: d.tokens,
      });
      stored += 1;
      this.exec(
        `INSERT INTO usage_project_days (workspace_id, source, project, day, tokens, updated_at)
         VALUES ($1, $2, $3, $4, $5, $6)
         ON CONFLICT (workspace_id, source, project, day) DO UPDATE SET
           tokens = EXCLUDED.tokens, updated_at = EXCLUDED.updated_at, deleted_at = NULL`,
        [wsId, source, d.project, d.day, d.tokens, now]
      );
    }
    return { stored, dropped, refused };
  }

  /**
   * Forgets the days that have fallen out of the history window — out of
   * memory now, flagged (never removed) on disk — the way pruneSessionTotals
   * retires totals. Runs on the write path rather than on a timer, like that
   * one: the map only grows when a report arrives. Until now nothing removed a
   * project day while the process ran at all; only a restart's load filter
   * did, so a long-lived process kept every day it had ever been sent.
   *
   * One UPDATE per workspace, and only when something in memory actually aged
   * out — the cutoff moves once a day — rather than one per row. It flags
   * every live row of the board older than the cutoff, which is the same set
   * plus whatever a restart had already declined to load.
   */
  private pruneProjectDays(wsId: string, ws: Map<string, ProjectDay>, oldest: string, now: number): void {
    let pruned = false;
    for (const [key, row] of ws) {
      if (row.day < oldest) {
        ws.delete(key);
        pruned = true;
      }
    }
    if (pruned) {
      this.exec(
        `UPDATE usage_project_days SET deleted_at = $3
         WHERE workspace_id = $1 AND day < $2 AND deleted_at IS NULL`,
        [wsId, oldest, now]
      );
    }
  }

  /** Token spend per (source, project, day) on or after `sinceDay` (YYYY-MM-DD). */
  getProjectDays(wsId: string, sinceDay: string): ProjectDay[] {
    const ws = this.projectDays.get(wsId);
    if (!ws) return [];
    return Array.from(ws.values())
      .filter((d) => d.day >= sinceDay)
      .sort(
        (a, b) =>
          a.day.localeCompare(b.day) ||
          a.source.localeCompare(b.source) ||
          a.project.localeCompare(b.project)
      );
  }

  /**
   * Replaces the stored total for each (source, session_id) row and returns
   * the ids whose value actually moved, so only cards with news are
   * rebroadcast.
   *
   * A reported total is ABSOLUTE and replaces what is held — including
   * downwards. A decrease is not corruption and must not be max()'d away: the
   * hook's counter legitimately restarts when its state file is lost with the
   * log already pruned, or when a session was evicted by its 400-entry cap and
   * later resumed. Storing what we are sent keeps the board agreeing with the
   * machine that can actually see the logs; keeping the larger number would
   * pin a wrong figure on the card forever.
   *
   * Replacement also makes the post idempotent: a duplicate costs nothing and
   * one that never lands costs only freshness.
   *
   * With the workspace at MAX_SESSION_TOTALS_PER_WORKSPACE a new key is
   * refused (counted, not stored, not written) unless its session has a card
   * on this board right now — the one number a viewer is looking for. Totals
   * past their retention are retired first, so they free their slots.
   */
  setSessionTotals(
    wsId: string,
    source: string,
    rows: Array<{ sessionId: string; tokens: number }>
  ): { changed: string[]; stored: number; refused: number } {
    let ws = this.sessionTotals.get(wsId);
    if (!ws) {
      ws = new Map();
      this.sessionTotals.set(wsId, ws);
      // Same legacy-mode concern as upsertSession: keep the workspace row
      // present so persisted rows satisfy the workspace_id relationship.
      if (this.pool && !this.workspaces.has(wsId)) {
        const now = Date.now();
        this.exec(Store.INSERT_WS, [wsId, now, now]);
      }
    }
    const now = Date.now();
    this.pruneSessionTotals(wsId, ws, now);
    const cards = this.sessions.get(wsId);
    const changed: string[] = [];
    let refused = 0;
    for (const row of rows) {
      const key = `${source}\n${row.sessionId}`;
      const prev = ws.get(key);
      if (!prev && ws.size >= MAX_SESSION_TOTALS_PER_WORKSPACE) {
        // Cards are capped too (50 a workspace on a hosted board), so this
        // exception lifts the map at most that far past its own cap.
        const card = cards?.get(row.sessionId);
        if (!card || card.source !== source) {
          refused += 1;
          continue;
        }
      }
      // Re-set rather than mutate so the entry moves to the end of the Map:
      // insertion order is freshness order, which is what load() keeps the
      // newest of when a database holds more than the cap.
      ws.delete(key);
      ws.set(key, { source, sessionId: row.sessionId, tokens: row.tokens, updatedAt: now });
      if (!prev || prev.tokens !== row.tokens) changed.push(row.sessionId);
      this.exec(
        `INSERT INTO usage_session_totals (workspace_id, source, session_id, tokens, updated_at)
         VALUES ($1, $2, $3, $4, $5)
         ON CONFLICT (workspace_id, source, session_id) DO UPDATE SET
           tokens = EXCLUDED.tokens, updated_at = EXCLUDED.updated_at, deleted_at = NULL`,
        [wsId, source, row.sessionId, row.tokens, now]
      );
    }
    return { changed, stored: rows.length - refused, refused };
  }

  /**
   * Retires totals past the retention window. Runs on the write path rather
   * than on a timer: the map only grows when a report arrives, and that report
   * walks it anyway. The cap is no longer enforced here by dropping the
   * oldest — setSessionTotals refuses new keys instead — because a drop only
   * flags the row, and a flag bounds memory while the table keeps growing.
   */
  private pruneSessionTotals(wsId: string, ws: Map<string, SessionTotal>, now: number): void {
    const cutoff = now - SESSION_TOTAL_TTL_MS;
    for (const [key, total] of ws) {
      if (total.updatedAt < cutoff) this.dropSessionTotal(wsId, ws, key, total, now);
    }
  }

  /** Forgets one total: out of memory now, flagged (never removed) on disk. */
  private dropSessionTotal(
    wsId: string,
    ws: Map<string, SessionTotal>,
    key: string,
    total: SessionTotal,
    now: number
  ): void {
    ws.delete(key);
    this.exec(
      `UPDATE usage_session_totals SET deleted_at = $4
       WHERE workspace_id = $1 AND source = $2 AND session_id = $3 AND deleted_at IS NULL`,
      [wsId, total.source, total.sessionId, now]
    );
  }

  /**
   * The lifetime tokens held for one session, or null when there is none.
   *
   * Filtered on read as well as on the write path, the way getUsage() drops a
   * stale percentage: a value whose retention ran out between two reports must
   * not surface just because nothing has posted since.
   */
  getSessionTokens(wsId: string, source: string, sessionId: string): number | null {
    const total = this.sessionTotals.get(wsId)?.get(`${source}\n${sessionId}`);
    if (!total || total.updatedAt < Date.now() - SESSION_TOTAL_TTL_MS) return null;
    return total.tokens;
  }

  /**
   * The card as it goes on the wire: the stored session plus whatever total is
   * held under its (source, id). The key is absent, not zero, when nothing has
   * been reported — a board with usage reporting off, an agent other than
   * Claude or Codex, or a session whose total aged out all look the same to a
   * client, and none of them means "this session spent nothing".
   *
   * The stored object is returned unchanged in that case, so a board that
   * never receives a total emits exactly the frames it emitted before.
   */
  private withTokens(wsId: string, session: Session): Session {
    const tokens = this.getSessionTokens(wsId, session.source, session.id);
    return tokens === null ? session : { ...session, tokens };
  }

  /** Current plan usage for a workspace, freshest first. Stale entries are dropped. */
  getUsage(wsId: string): Usage[] {
    const map = this.usageBySource.get(wsId);
    if (!map) return [];
    const cutoff = Date.now() - USAGE_TTL_MS;
    return Array.from(map.values())
      .filter((u) => u.updatedAt >= cutoff)
      .sort((a, b) => a.source.localeCompare(b.source));
  }

  /** Appends a timeline entry, trimming (soft-deleting) beyond the cap. */
  private recordEvent(wsId: string, sessionId: string, status: Status, message: string, at: number): void {
    let ws = this.events.get(wsId);
    if (!ws) {
      ws = new Map();
      this.events.set(wsId, ws);
    }
    let list = ws.get(sessionId);
    if (!list) {
      list = [];
      ws.set(sessionId, list);
    }
    const seq = this.nextSeq++;

    list.push({ seq, status, message, at });
    this.exec(
      `INSERT INTO session_events (workspace_id, session_id, seq, status, message, at)
       VALUES ($1, $2, $3, $4, $5, $6)
       ON CONFLICT (workspace_id, session_id, seq) DO UPDATE SET
         status = EXCLUDED.status, message = EXCLUDED.message, at = EXCLUDED.at, deleted_at = NULL`,
      [wsId, sessionId, seq, status, message, at]
    );
    while (list.length > MAX_EVENTS_PER_SESSION) {
      const trimmed = list.shift()!;
      this.exec(
        'UPDATE session_events SET deleted_at = $4 WHERE workspace_id = $1 AND session_id = $2 AND seq = $3',
        [wsId, sessionId, trimmed.seq, at]
      );
    }
  }

  /** The session's timeline, newest first. Empty for unknown sessions. */
  getHistory(wsId: string, sessionId: string): SessionEvent[] {
    const list = this.events.get(wsId)?.get(sessionId);
    if (!list) return [];
    return [...list].reverse();
  }

  /** Drops a session's timeline (memory now, rows via soft-delete flags). */
  private dropEvents(wsId: string, sessionId: string): void {
    const removed = this.events.get(wsId)?.delete(sessionId) ?? false;
    if (removed) {
      this.exec(
        'UPDATE session_events SET deleted_at = $3 WHERE workspace_id = $1 AND session_id = $2 AND deleted_at IS NULL',
        [wsId, sessionId, Date.now()]
      );
    }
  }

  getSession(wsId: string, id: string): Session | null {
    const session = this.sessions.get(wsId)?.get(id);
    return session ? this.withTokens(wsId, session) : null;
  }

  getSessions(wsId: string): Session[] {
    const map = this.sessions.get(wsId);
    if (!map) return [];
    return Array.from(map.values(), (s) => this.withTokens(wsId, s)).sort(
      (a, b) => b.updatedAt - a.updatedAt
    );
  }

  deleteSession(wsId: string, id: string): boolean {
    const removed = this.sessions.get(wsId)?.delete(id) ?? false;
    if (removed) {
      // Flagged, not erased. `host` stays on the row like every other column:
      // dismissing a card hides it, and hiding is not destroying.
      this.exec(
        'UPDATE sessions SET deleted_at = $3 WHERE workspace_id = $1 AND id = $2',
        [wsId, id, Date.now()]
      );
      this.dropEvents(wsId, id);
      this.cancelCommands(wsId, id);
    }
    return removed;
  }

  clearSessions(wsId: string): void {
    const map = this.sessions.get(wsId);
    if (map) {
      for (const id of map.keys()) this.dropEvents(wsId, id);
      map.clear();
    }
    this.cancelCommands(wsId, null);
    // Flagged, not erased — `host` survives a clear like every other column.
    this.exec(
      'UPDATE sessions SET deleted_at = $2 WHERE workspace_id = $1 AND deleted_at IS NULL',
      [wsId, Date.now()]
    );
  }

  /** Fixed-window webhook rate limit per workspace. */
  allowWebhook(wsId: string): boolean {
    return this.allowInWindow(this.webhookWindows, wsId, WEBHOOKS_PER_MINUTE);
  }

  /** Fixed-window Focus-command rate limit per workspace, separate from the webhook budget. */
  allowCommand(wsId: string): boolean {
    return this.allowInWindow(this.commandWindows, wsId, COMMANDS_PER_MINUTE);
  }

  /** Fixed-window limit on listener connects per workspace (each one is broadcast to every viewer). */
  allowListenerConnect(wsId: string): boolean {
    return this.allowInWindow(this.listenerWindows, wsId, LISTENER_CONNECTS_PER_MINUTE);
  }

  /** Fixed-window limit on device registrations and removals per workspace, one budget for both. */
  allowDeviceChange(wsId: string): boolean {
    return this.allowInWindow(this.deviceWindows, wsId, DEVICE_CHANGES_PER_MINUTE);
  }

  /** Fixed-window limit on usage-history reads per workspace, apart from every write budget. */
  allowHistoryRead(wsId: string): boolean {
    return this.allowInWindow(this.historyWindows, wsId, HISTORY_READS_PER_MINUTE);
  }

  private allowInWindow(
    windows: Map<string, { windowStart: number; count: number }>,
    wsId: string,
    perMinute: number,
  ): boolean {
    const now = Date.now();
    const win = windows.get(wsId);
    if (!win || now - win.windowStart >= 60_000) {
      windows.set(wsId, { windowStart: now, count: 1 });
      return true;
    }
    win.count += 1;
    return win.count <= perMinute;
  }

  /**
   * Escrows rawToken under a fresh single-use pairing code (returned WITHOUT
   * the display dash). Null when the workspace already has 3 outstanding
   * unexpired codes. The raw token is the workspace identity here, so the
   * cap counts codes escrowing the same rawToken.
   */
  createPairCode(rawToken: string): string | null {
    this.sweepExpiredPairCodes();
    let outstanding = 0;
    for (const entry of this.pairCodes.values()) {
      if (entry.rawToken === rawToken) outstanding += 1;
    }
    if (outstanding >= MAX_PAIR_CODES_PER_WORKSPACE) return null;

    let code: string;
    do {
      code = '';
      for (let i = 0; i < PAIR_CODE_LENGTH; i++) {
        // randomInt uses rejection sampling, so no modulo bias.
        code += PAIR_CODE_ALPHABET[crypto.randomInt(PAIR_CODE_ALPHABET.length)];
      }
    } while (this.pairCodes.has(code)); // 31^8 keyspace; collisions are ~impossible but cheap to rule out
    this.pairCodes.set(code, { rawToken, expiresAt: Date.now() + PAIR_CODE_TTL_MS });
    return code;
  }

  /**
   * Consumes a pairing code (normalized: uppercase, dashes/whitespace
   * stripped) and returns the escrowed token. Null for unknown or expired
   * codes; either way the code is gone afterwards (single-use).
   */
  claimPairCode(code: string): { rawToken: string } | null {
    const normalized = code.toUpperCase().replace(/[-\s]/g, '');
    const entry = this.pairCodes.get(normalized);
    if (!entry) return null;
    this.pairCodes.delete(normalized);
    if (Date.now() >= entry.expiresAt) return null;
    return { rawToken: entry.rawToken };
  }

  /** Drops expired pairing codes. Also runs lazily inside create/claim. */
  sweepExpiredPairCodes(): void {
    const now = Date.now();
    for (const [code, entry] of this.pairCodes) {
      if (now >= entry.expiresAt) this.pairCodes.delete(code);
    }
  }

  // ---- Focus commands ------------------------------------------------------

  private isPending(cmd: Command, now: number): boolean {
    return cmd.state === 'pending' && now < cmd.expiresAt;
  }

  /** Fails a live command on the server's behalf; the caller decides how its ack gets out. */
  private failCommand(cmd: Command, now: number, state: 'done' | 'expired', reason: CommandReason): void {
    cmd.state = state;
    cmd.doneAt = now;
    cmd.result = 'failed';
    cmd.reason = reason;
  }

  /** Flips a live command to expired and queues it for the sweep's broadcast. */
  private expireCommand(cmd: Command, now: number): void {
    this.failCommand(cmd, now, 'expired', 'expired');
    this.unannounced.push(cmd);
  }

  /** The command, expired on the spot if its TTL passed; null when unknown or already swept. */
  private liveCommand(wsId: string, id: string, now: number): Command | null {
    const cmd = this.commands.get(wsId)?.get(id);
    if (!cmd) return null;
    if ((cmd.state === 'pending' || cmd.state === 'claimed') && now >= cmd.expiresAt) {
      this.expireCommand(cmd, now);
    }
    return cmd;
  }

  /**
   * Records a new pending command. Null when the id is already taken in this
   * workspace (the phone retried with the same client uuid; it should poll
   * the existing one instead).
   */
  createCommand(
    input: { wsId: string; id: string; type: CommandType; sessionId: string; machineId: string },
    ttlMs: number,
  ): Command | null {
    let map = this.commands.get(input.wsId);
    if (!map) {
      map = new Map();
      this.commands.set(input.wsId, map);
    }
    if (map.has(input.id)) return null;
    const now = Date.now();
    const cmd: Command = {
      id: input.id,
      wsId: input.wsId,
      type: input.type,
      sessionId: input.sessionId,
      machineId: input.machineId,
      state: 'pending',
      createdAt: now,
      expiresAt: now + ttlMs,
    };
    map.set(cmd.id, cmd);
    return cmd;
  }

  getCommand(wsId: string, id: string): Command | null {
    return this.liveCommand(wsId, id, Date.now());
  }

  /**
   * pending → claimed, only from pending and only with the key of the machine
   * the command was routed to. The key never reaches a viewer, so the machine
   * id alone (which every viewer sees) cannot claim.
   */
  claimCommand(wsId: string, id: string, machineKey: string): { ok: true; command: Command } | { ok: false; error: ClaimError } {
    const now = Date.now();
    const cmd = this.liveCommand(wsId, id, now);
    if (!cmd) return { ok: false, error: 'not_found' };
    if (!machineKeyMatches(machineKey, cmd.machineId)) return { ok: false, error: 'wrong_machine' };
    if (cmd.state === 'expired') return { ok: false, error: 'expired' };
    if (cmd.state !== 'pending') return { ok: false, error: 'already_claimed' };
    cmd.state = 'claimed';
    cmd.claimedAt = now;
    return { ok: true, command: cmd };
  }

  /** claimed → done, with the machine's key as for claim. The outcome is enums only; nothing free-form is ever stored. */
  ackCommand(
    wsId: string,
    id: string,
    machineKey: string,
    outcome: { result: CommandResult; reach?: CommandReach; reason?: CommandReason },
  ): { ok: true; command: Command } | { ok: false; error: AckError } {
    const now = Date.now();
    const cmd = this.liveCommand(wsId, id, now);
    if (!cmd) return { ok: false, error: 'not_found' };
    if (!machineKeyMatches(machineKey, cmd.machineId)) return { ok: false, error: 'wrong_machine' };
    if (cmd.state === 'expired') return { ok: false, error: 'expired' };
    if (cmd.state === 'done') return { ok: false, error: 'already_done' };
    if (cmd.state === 'pending') return { ok: false, error: 'not_claimed' };
    cmd.state = 'done';
    cmd.doneAt = now;
    cmd.result = outcome.result;
    if (outcome.reach) cmd.reach = outcome.reach;
    if (outcome.reason) cmd.reason = outcome.reason;
    return { ok: true, command: cmd };
  }

  /** Unclaimed, unexpired commands routed to one machine — what a (re)connecting listener has missed. */
  pendingCommandsFor(wsId: string, machineId: string): Command[] {
    const now = Date.now();
    const pending: Command[] = [];
    for (const cmd of this.commands.get(wsId)?.values() ?? []) {
      if (cmd.machineId === machineId && this.isPending(cmd, now)) pending.push(cmd);
    }
    return pending.sort((a, b) => a.createdAt - b.createdAt);
  }

  countPending(wsId: string): number {
    const now = Date.now();
    let n = 0;
    for (const cmd of this.commands.get(wsId)?.values() ?? []) {
      if (this.isPending(cmd, now)) n += 1;
    }
    return n;
  }

  /** The pending command a new one for the same card would coalesce with, if any. */
  private findPending(wsId: string, sessionId: string, type: CommandType, machineId: string, now: number): Command | null {
    for (const cmd of this.commands.get(wsId)?.values() ?? []) {
      if (cmd.sessionId !== sessionId || cmd.type !== type || cmd.machineId !== machineId) continue;
      if (this.isPending(cmd, now)) return cmd;
    }
    return null;
  }

  /** Whether a new command for this card would supersede one that is still pending. */
  hasPending(wsId: string, sessionId: string, type: CommandType, machineId: string): boolean {
    return this.findPending(wsId, sessionId, type, machineId, Date.now()) !== null;
  }

  /**
   * Coalesces a re-tap: an older pending command for the same session, type
   * and machine is finished as failed/superseded and returned so its ack can
   * be broadcast. Null when there was none.
   */
  supersedePending(wsId: string, sessionId: string, type: CommandType, machineId: string): Command | null {
    const now = Date.now();
    const cmd = this.findPending(wsId, sessionId, type, machineId, now);
    if (!cmd) return null;
    this.failCommand(cmd, now, 'done', 'superseded');
    return cmd;
  }

  /**
   * Fails the pending commands aimed at one session (null: at every session
   * of the workspace) as superseded — the card is gone, so nobody is waiting
   * and the listener must not raise a window for it. Claimed ones are left to
   * ack or expire. Queued for app.ts to broadcast (takeFinishedCommands).
   */
  private cancelCommands(wsId: string, sessionId: string | null): void {
    const now = Date.now();
    for (const cmd of this.commands.get(wsId)?.values() ?? []) {
      if (sessionId !== null && cmd.sessionId !== sessionId) continue;
      if (!this.isPending(cmd, now)) continue;
      this.failCommand(cmd, now, 'done', 'superseded');
      this.unannounced.push(cmd);
    }
  }

  /**
   * Every command the server finished itself since the last call — expired,
   * or cancelled with its session — each for exactly one broadcast.
   */
  takeFinishedCommands(): Command[] {
    const finished = this.unannounced;
    this.unannounced = [];
    return finished;
  }

  /**
   * Expires live commands past their TTL and forgets finished ones past the
   * grace period. Returns what finished server-side since the last drain
   * (including what a read expired lazily) so app.ts can broadcast each
   * exactly once.
   */
  sweepCommands(now: number = Date.now()): Command[] {
    for (const [wsId, map] of this.commands) {
      for (const [id, cmd] of map) {
        if (cmd.state === 'pending' || cmd.state === 'claimed') {
          if (now >= cmd.expiresAt) this.expireCommand(cmd, now);
        } else if (now >= (cmd.doneAt ?? cmd.expiresAt) + COMMAND_GRACE_MS) {
          map.delete(id);
        }
      }
      if (map.size === 0) this.commands.delete(wsId);
    }
    return this.takeFinishedCommands();
  }

  /** Removes sessions not updated within ttlMs. Returns what was removed, for broadcasting. */
  sweepExpiredSessions(ttlMs: number): Array<{ wsId: string; id: string }> {
    const cutoff = Date.now() - ttlMs;
    const removed: Array<{ wsId: string; id: string }> = [];
    for (const [wsId, map] of this.sessions) {
      for (const [id, s] of map) {
        if (s.updatedAt < cutoff) {
          map.delete(id);
          // Flagged, not erased. This is the path that matters most: the TTL
          // fires on its own every day, so nulling `host` here destroyed the
          // machine and app of every session that simply went quiet — without
          // anyone asking for anything to be deleted.
          this.exec(
            'UPDATE sessions SET deleted_at = $3 WHERE workspace_id = $1 AND id = $2',
            [wsId, id, Date.now()]
          );
          this.dropEvents(wsId, id);
          this.cancelCommands(wsId, id);
          removed.push({ wsId, id });
        }
      }
    }
    return removed;
  }

  /** Deletes workspaces idle beyond maxIdleMs. Returns their ids so SSE streams can be closed. */
  sweepIdleWorkspaces(maxIdleMs: number): string[] {
    const cutoff = Date.now() - maxIdleMs;
    const deleted: string[] = [];
    for (const [wsId, meta] of this.workspaces) {
      if (meta.lastSeenAt < cutoff) {
        this.deleteWorkspace(wsId);
        deleted.push(wsId);
      }
    }
    return deleted;
  }

  /** Drains pending writes, then closes the connection pool. */
  async close(): Promise<void> {
    const pool = this.pool;
    this.pool = null; // no new writes may be enqueued past this point
    await this.writeQueue;
    await pool?.end();
  }
}
