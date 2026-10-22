/**
 * A real browser, driven programmatically and watched live.
 *
 * Two channels out of one page, deliberately kept apart:
 *
 *  - What the *model* gets is text. `outline()` returns the page's interactive
 *    elements the way a screen reader would announce them, numbered, and
 *    actions take those numbers. A sign-in page is ~110 tokens that way and
 *    ~1,300 as a screenshot, and you cannot click a screenshot.
 *  - What the *person* gets is video. Chrome's own screencast, streamed frame
 *    by frame over the session socket, so you watch the pointer travel, the
 *    click land and the page navigate as it happens -- not a screenshot after
 *    the fact.
 *
 * The second channel is the point of this file. Reading a page programmatically
 * is what makes an agent good at browsing; being unable to see what it did is
 * what makes it impossible to trust. So the pointer is drawn into the page
 * before every click and the click is performed as a real mouse event at real
 * coordinates -- the agent is not miming for the camera, it is genuinely
 * clicking there, and the camera is pointed at it.
 *
 * Frames are ephemeral: they go out over the socket and are never written to
 * the event log. What the log keeps is keyframes -- one after each navigation
 * and each action -- so scrolling back through a session still shows what the
 * page looked like at each step without the log becoming a video file.
 *
 * Playwright is an optional dependency and the browser binary is the system's.
 * Neither being present is an ordinary condition, not a crash: `status()` says
 * what is missing and the thread says so in words.
 */

import { refLine, scrollLine } from "./pagedescribe";
import type { DomItem } from "./domdiff";
import { createHash } from "node:crypto";
import { spawnSync } from "node:child_process";
import fs from "node:fs";
import { launchArgs } from "./extensions";
import os from "node:os";
import path from "node:path";

import { stateFilePath } from "./state";
import { MAX_ARTIFACT_BYTES } from "./artifacts";
import type { BrowserCookie } from "./cookies";
import { humanClick, humanMove, humanPath, humanType, pointIn, wander, type Point } from "./human";
import { DEFAULT_CAPTCHA, findChallenge, findPageCheckbox, solveChallenge, type CaptchaSettings, type SolveReport } from "./captcha";
import { thoughtFromAction } from "../src/lib/thought";
import { browserRoots, settleTree, sweepBrowsers } from "./processes";

/* Playwright's types are not imported: the package is optional, and a type
   import would make the server half fail to compile wherever it is not
   installed. The surface used here is small enough to name locally. */
type Page = any;
type BrowserContext = any;
type CDPSession = any;

/** A dropdown's choices, as the page offers them. */
interface SelectChoice {
  index: number;
  label: string;
  selected: boolean;
  disabled: boolean;
}

/** A dropdown a person tapped: what it is called and what it offers. */
interface SelectInfo {
  name: string;
  multiple: boolean;
  options: SelectChoice[];
}

/** One line of the page's console or one request it made: what DevTools shows. */
interface DevEntry {
  n: number;
  tab: number;
  ts: number;
  kind: "console" | "request";
  /** Console: log, info, warn, error. Request: the resource type. */
  level: string;
  /** Console: the text. Request: the address. */
  text: string;
  method?: string;
  status?: number;
  ms?: number;
  bytes?: number;
  failed?: string;
}

interface BrowserTab {
  id: number;
  url: string;
  title: string;
  active: boolean;
}

interface BrowserStatus {
  /** The tabs this session has open, in order. */
  tabs?: BrowserTab[];
  /** Playwright and a browser binary are both present. */
  available: boolean;
  /** A page is open right now. */
  open: boolean;
  url: string | null;
  title: string | null;
  /** Why it is not available, in words fit to show someone. */
  detail: string | null;
  /** Live frames per second currently being sent. */
  fps: number;
  viewport: { width: number; height: number };
  /** Who currently holds control of the browser (agent, human, or shared). */
  control: { holder: "agent" | "human" | "shared"; reason: string | null };
  /** Where the page's typeable fields are, as [x, y, w, h] in page pixels, so
      a phone can raise its keyboard for a tap on one -- and only on one --
      without waiting for the click to come back. */
  fields: Array<[number, number, number, number]>;
}

/** A file to put into an upload field, bytes and all. */
export interface UploadFile {
  name: string;
  mimeType: string;
  buffer: Buffer;
}

/** One numbered, clickable thing on the page. */
export interface Ref {
  ref: number;
  role: string;
  name: string;
  value: string | null;
  /** Page coordinates of the element's centre, which is where a click goes
      and where the marker is painted in the transcript. */
  x: number;
  y: number;
  w: number;
  h: number;
  href: string | null;
  checked: boolean | null;
  disabled: boolean;
  /** On screen (or within a little of it) when the page was read. The model
      is shown these; the rest are counted, keeping their numbers. */
  inView?: boolean;
  /** An input type other than plain text: email, tel, date, number... */
  type?: string;
  /** What the field is for, from its autocomplete hint or its own name:
      "first name", "shipping ZIP / postal code". */
  purpose?: string;
  placeholder?: string;
  required?: boolean;
  maxLength?: number;
  /** min..max, for numbers and dates. */
  range?: string;
  /** What the page says is wrong with the value, when it says anything. */
  invalid?: string;
  /** The help text the page attaches to the field. */
  hint?: string;
  /** The fieldset, group or heading the field sits under. */
  section?: string;
  /** Something is drawn over this element, so a click on it would land there
      instead: a cookie bar, a newsletter pop-up, a sticky header. What it says. */
  covered?: string;
  /** The listed controls on that covering thing, to dismiss it with. */
  coverRefs?: number[];
  /** A dropdown's choices, the first fifteen, and how many there are. */
  options?: string[];
  optionCount?: number;
  expanded?: boolean;
  selected?: boolean;
  current?: boolean;
  /** The open dialog the element is inside, by name. */
  dialog?: string;
}

/** Where the page is scrolled to: of the page itself, or of the pane that
    does the scrolling in an app whose page never moves. */
export interface ScrollState {
  y: number;
  max: number;
  view: number;
  pane: boolean;
}

export interface PageRead {
  url: string;
  title: string;
  /** The numbered outline the model acts on. */
  outline: string;
  refs: Ref[];
  /** The page's main content as readable text -- the article rather than
      the menus around it -- whole, up to a generous cap. The model reads it
      a part at a time (see textParts). */
  text: string;
  /** Checkbox CAPTCHAs on the page. They live in cross-origin iframes the
      outline cannot see into, so they are found separately. */
  captchas: { kind: CaptchaKind; solved: boolean; challenge: boolean }[];
  /** The dialog open on top of the page, by name. */
  dialog?: string | null;
  scroll?: ScrollState;
  /** The site turned the sign-in away, in its own words. */
  blocked?: string | null;
  /** A Cloudflare interstitial instead of the page: there is nothing on it to
      click, and it decides on its own. */
  challenge?: string | null;
  /** What the action that produced this read did, field by field, or why
      it did nothing. */
  notes?: string[];
}

/**
 * Looking at the same thing again, which is where an agent gets stuck.
 *
 * The failure this exists for: a dialog whose buttons are not in the outline
 * -- a script-drawn prompt with no refs -- leaves reading as the only thing
 * that still "works". So the agent reads, and reads, and reads, and every
 * read comes back identical, and the identical read looks like progress
 * because it came back at all. Twenty calls went that way once.
 *
 * Two identical looks are enough. The third one is answered with a way out
 * instead of the page again: what to do instead, named, in the result the
 * model actually reads. A page that changes between looks is a new page and
 * starts again, so ordinary work is never interrupted.
 */
export class SameLook {
  /** What the last look was, and how many times in a row it has been served. */
  private key: string | null = null;
  private count = 0;

  /** Remember this look. Returns the way-out note on the third identical one,
      and null while the agent is still doing something that works. */
  seen(key: string, note: string): string | null {
    if (key === this.key) {
      this.count += 1;
      return this.count >= 3 ? note : null;
    }
    this.key = key;
    this.count = 1;
    return null;
  }
}

/** A stable key for "the page as it was read this time". The outline carries
    the elements and the scroll line carries the position, so an unchanged
    page keys the same however long the agent stares at it. */
export function lookKey(page: PageRead, part = 1): string {
  return `${page.url}\u0000${page.title}\u0000${part}\u0000${page.outline}`;
}

/**
 * The note that replaces a third look at an unchanged page.
 *
 * It says what to do rather than what not to do, because "stop" on its own is
 * what the loop-check already says into the same wind: the agent needs the
 * instrument it is missing. Here that is running JavaScript in the page --
 * the only way to reach a control the outline cannot see.
 */
export const SAME_PAGE_NOTE = (
  "NOTHING CHANGED: this is the third time you have read this same page, " +
  "unchanged, and reading or screenshotting it again will keep coming back " +
  "identical. Reading is not what is failing -- the elements you need are " +
  "not in the outline. Stop reading and use one of these instead:\n" +
  "  1. browser_eval: run JavaScript in the page. That reaches anything, " +
  "including buttons no outline lists. To click one by its own words: " +
  "`__autora.click(__autora.byText(\"Save as draft\"))`. To look first: " +
  "`__autora.all(\"button\").map((b) => b.innerText)`.\n" +
  "  2. keyboard-first, if the thing you want is the primary action of a " +
  "dialog that is showing: focus it and Tab to the primary button, then Enter. " +
  "Escape is never the key for a dialog you are trying to accept.\n" +
  "  3. browser_handoff: if neither reaches it, hand the page over and ask the " +
  "person to click it -- they can do in three seconds what twenty calls could not.\n" +
  "Do not read this page again: nothing about it has changed, so nothing about " +
  "the answer will either."
);

/** The same, for the fourth picture of a page that has not moved. */
export const SAME_PICTURE_NOTE = (
  "NOTHING CHANGED: you have already been given this exact picture twice -- " +
  "the page has not moved a pixel since. Another screenshot will be the same " +
  "picture again, so it is not taken. If something on the page is not in its " +
  "text, reach it with browser_eval (run JavaScript in the page), or hand the " +
  "page to the person with browser_handoff. Do not take this screenshot again."
);

/** One click the script made for the agent: where, and what it hit. */
interface ScriptHit {
  x?: number;
  y?: number;
  label?: string;
}

/** How long a script may run in the page before it is called a hang. A
    blocking loop hangs the renderer itself, which no timeout here can fix --
    it is here for scripts that await something that never comes back. */
const SCRIPT_TIMEOUT_MS = 8000;

/** Errors that mean "that was the wrong shape, try the next one" rather than
    "your script is broken". */
const WRONG_SHAPE =
  /SyntaxError|Unexpected token|Unexpected identifier|Unexpected end of input|is not a function|missing \) after argument list|Invalid or unexpected token|await is only valid/i;

/**
 * The script as the three shapes it might be, in the order that gets it right
 * most often: a function to call, an expression to evaluate, or statements
 * that use `return` themselves. The page's own error tells us which, because a
 * wrong shape throws a syntax error before any of the script runs.
 */
/**
 * The shapes a script may be written in -- tried in the order that cannot run
 * anything twice.
 *
 * The first version called whatever it was given: a one-line click came back
 * as a label, the call on the end of it threw "is not a function", the retry
 * in the next shape clicked a *second* time. On a "Discard" that is the post
 * gone. So the shape is decided before anything runs, by parsing in Node --
 * `new Function` touches no page. An expression is run as it stands; anything
 * else is wrapped in a function body, where `return` and `const` belong.
 */
export function scriptAttempts(script: string): string[] {
  const body = script.trim();
  const asExpression = `return (${body});`;
  let expression = true;
  try {
    new Function(asExpression);
  } catch {
    expression = false;
  }
  const wrapped = `(async () => {
  ${body}
})()`;
  return expression ? [body, wrapped] : [wrapped, body];
}

/**
 * A failed script, in the page's own words. Playwright wraps every error in
 * its own frame and a stack of internal file names -- four hundred characters
 * for "nothing here says that" -- and the first line is the one that tells the
 * agent what actually happened.
 */
export function plainScriptError(err: unknown): string {
  const raw = err && typeof err === "object" && "message" in err
    ? String((err as { message: unknown }).message)
    : String(err);
  const first = raw.split("\n")[0]!.trim();
  if (/^(SyntaxError|Unexpected token)/.test(first)) return "the script is not valid JavaScript: " + first;
  return first.replace(/^page\.evaluate: /, "").replace(/^Error: /, "");
}

/** What a script returned, as the model reads it. */
export function describeScriptValue(value: unknown): string {
  if (value === undefined) return "The script returned nothing (no return value).";
  if (typeof value === "string") return value.length > 4000 ? `${value.slice(0, 4000)}…` : value;
  try {
    const json = JSON.stringify(value, null, 1);
    if (json === undefined) return String(value);
    return json.length > 4000 ? `${json.slice(0, 4000)}…` : json;
  } catch {
    return String(value);
  }
}

function withTimeout<T>(promise: Promise<T>, ms: number): Promise<T> {
  return new Promise<T>((resolve, reject) => {
    const timer = setTimeout(() => reject(new Error(`the script was still running after ${ms / 1000}s (it may be waiting for something that never arrives)`)), ms);
    promise.then(
      (v) => {
        clearTimeout(timer);
        resolve(v);
      },
      (e) => {
        clearTimeout(timer);
        reject(e);
      },
    );
  });
}

/**
 * Injected into the page before any script runs, so the agent has a handle on
 * things the outline cannot see -- and so its clicks are announced the way the
 * other mouse actions are, with the pointer drawn where they land.
 */
const AUTORA_HELPER_SCRIPT = `(() => {
  /* What the page says an element is: its visible words, or failing those the
     attribute it is named by. The outline names things the same way, so what
     the agent reads and what it can click agree. */
  const label = (el) => ((el.getAttribute("aria-label") || el.innerText || el.value
    || el.getAttribute("title") || el.getAttribute("placeholder") || el.getAttribute("alt")
    || el.getAttribute("name") || el.tagName || "") + "").trim();
  const shown = (el) => { const r = el.getBoundingClientRect(); return r.width > 0 && r.height > 0; };
  const ALL = "button, a, [role=button], [role=menuitem], [role=tab], input, textarea, select, summary, label, li, span, div, p, td, th";
  window.__autora = {
    hit: [],
    all(selector) { return Array.from(document.querySelectorAll(selector)); },
    /* The thing that says these words. An exact match wins; failing that the
       shortest thing containing them, so a button is chosen rather than the
       card around it. Case and surrounding space are ignored. */
    byText(want, selector) {
      const wanted = String(want).trim().toLowerCase();
      const nodes = Array.from(document.querySelectorAll(selector || ALL)).filter(shown);
      const said = (el) => label(el).toLowerCase();
      const exact = nodes.find((el) => said(el) === wanted);
      if (exact) return exact;
      const inside = nodes.filter((el) => said(el).includes(wanted)).sort((a, b) => label(a).length - label(b).length);
      return inside[0] || null;
    },
    el(target) {
      if (target === null || target === undefined) {
        throw new Error("nothing to act on: byText() found no element saying that, and el() no element with that selector");
      }
      if (typeof target === "object") return target;
      const found = document.querySelector(String(target));
      if (!found) throw new Error("no element matches the selector " + JSON.stringify(String(target)));
      return found;
    },
    click(target) {
      const el = this.el(target);
      const r = el.getBoundingClientRect();
      if (r.width === 0 || r.height === 0) {
        throw new Error(JSON.stringify(label(el)) + " is in the page but not visible, so a click on it would do nothing");
      }
      this.hit.push({ x: r.x + r.width / 2, y: r.y + r.height / 2, label: label(el).slice(0, 60) });
      el.click();
      return label(el).slice(0, 60);
    },
  };
  return true;
})()`;

/** Where to scroll: by screens (or pixels), to the top or bottom, inside a
    numbered element, or to some text. */
interface ScrollRequest {
  screens?: number;
  dy?: number;
  to?: "top" | "bottom";
  ref?: number | null;
  text?: string;
}

export type CaptchaKind = "recaptcha" | "hcaptcha" | "turnstile" | "lookalike";

/** A checkbox CAPTCHA found on the page, with where its box is. */
interface CaptchaHit {
  kind: CaptchaKind;
  /** The checkbox itself, in page coordinates. */
  box: { x: number; y: number; w: number; h: number };
  solved: boolean;
  /** An image or puzzle challenge is showing -- the checkbox was not enough. */
  challenge: boolean;
}

interface CaptchaResult {
  outcome: "none" | "solved" | "challenge" | "pending";
  kind: CaptchaKind | null;
  page: PageRead;
  /** What the solver did about a picture challenge, and what stood in its
      way. Absent when there was no picture to answer. */
  detail?: string;
  /** Which backend answered it: local arithmetic, the vision model, or the
      person's own solver. */
  backend?: string;
}

interface BrowserHooks {
  /** A live frame: base64 JPEG, ephemeral, never stored. */
  onFrame: (jpegBase64: string) => void;
  /** A frame worth keeping in the transcript. */
  onKeyframe: (jpeg: Buffer, url: string, title: string) => void;
  onNav: (url: string, title: string) => void;
  /** Something the agent did, with where it did it when that is meaningful. */
  onAction: (action: string, at: { x: number; y: number } | null, url: string) => void;
  /** Whose pointer to draw: the agent of the Organization working in this chat, or null for Autora itself. */
  who?: () => { name: string; color: string; rgb: string; sides: number } | null;
  /** Visible work (Settings, and the switch beside Follow): false, the agent works at speed with no pointer drawn,
      no words beside it and no typing rhythm. Missing means on. */
  visible?: () => boolean;
  /** The typeable fields on the page moved, appeared or went. */
  onFields: () => void;
  /** The page wrote an error or a warning to its console. */
  onConsole?: () => void;
  /** The page downloaded a file. `bytes` is the whole of it, or empty with `error` saying why it was not kept. */
  onDownload?: (file: { name: string; bytes: Buffer; url: string; error?: string }) => void;
  /** Whether anyone is watching. The screencast is stopped while nobody is,
      because encoding JPEGs for an empty room is just heat. */
  watchers: () => number;
  /** Bytes queued to the slowest viewer. A phone on a bad link backs up
      first; the stream then thins and softens itself rather than lag. */
  backlog?: () => number;
}

/** The capture size. Frame pixels map 1:1 to page pixels so a click at
    640,400 really is the middle of the picture -- the transcript's marker and
    the element picker both depend on that. */
export const VIEWPORT = { width: 1280, height: 800 };

const num = (value: string | undefined, fallback: number) => {
  const parsed = Number((value ?? "").trim());
  return Number.isFinite(parsed) && parsed > 0 ? parsed : fallback;
};

/** How long typing has to stop before it is logged and a frame is kept. */
const TYPING_PAUSE_MS = 1200;
/** How often live frames go out. Chrome offers about sixty a second; a LAN is
    not a video codec, and ten is enough to follow the pointer travelling to
    what it is about to click. */
const LIVE_FPS = Math.min(num(process.env.AUTORA_BROWSER_FPS, 10), 30);
const LIVE_QUALITY = Math.min(num(process.env.AUTORA_BROWSER_QUALITY, 50), 100);
/** Frames are sent narrower than the page is rendered: the picture is for
    watching, not for reading nine-point text, and halving the width quarters
    the bytes. */
const LIVE_WIDTH = num(process.env.AUTORA_BROWSER_STREAM_WIDTH, 960);
/** How hard the stream squeezes: speed over resolution when the link is
    slow or a person is working the page, sharp when they stop. */
const TIERS = [
  { width: LIVE_WIDTH, quality: LIVE_QUALITY },
  { width: Math.round(LIVE_WIDTH * 0.75), quality: Math.max(LIVE_QUALITY - 12, 20) },
  { width: Math.round(LIVE_WIDTH * 0.55), quality: Math.max(LIVE_QUALITY - 20, 15) },
];
/** After the last frame, how long the page must sit still before it is sent
    again sharp. */
const SHARP_AFTER_MS = 650;
/** Tabs one session may hold open. */
const MAX_TABS = 12;

/**
 * Where Chrome is.
 *
 * Named outright by AUTORA_BROWSER_PATH; otherwise the usual system packages,
 * in the order a machine is likely to have them. Playwright's own downloaded
 * browsers are found by Playwright itself and need nothing here.
 */
const CANDIDATE_PATHS = [
  "/usr/bin/chromium-browser",
  "/usr/bin/chromium",
  "/usr/bin/google-chrome",
  "/usr/bin/google-chrome-stable",
  "/usr/bin/microsoft-edge",
  "/Applications/Google Chrome.app/Contents/MacOS/Google Chrome",
  "/Applications/Chromium.app/Contents/MacOS/Chromium",
];

/**
 * The flags that give a machine with no graphics card a WebGL context.
 *
 * A CAPTCHA that draws itself is often a WebGL canvas -- distorted letters
 * put through a shader, a 3D scene, a shape to drag -- and with no context
 * getContext("webgl") returns null, the page's own script gives up, and the
 * canvas stays empty for ever. That is not a page that has not drawn itself
 * yet; it is a page that never will. Hardware is not needed for this, only a
 * Vulkan driver: Mesa's software one (llvmpipe, the mesa-vulkan-swrast
 * package) draws it on the CPU, and ANGLE is pointed at it here. Without a
 * Vulkan driver on the machine both flags are left off, since asking for a
 * backend that is not there would take WebGL away from a browser that might
 * have had it.
 */
export function webglArgs(
  dirs: string[] = ["/usr/share/vulkan/icd.d", "/etc/vulkan/icd.d"],
): string[] {
  const somewhere = dirs.some((dir) => {
    try {
      return fs.readdirSync(dir).some((name) => name.endsWith(".json"));
    } catch {
      return false;
    }
  });
  return somewhere ? ["--use-angle=vulkan", "--ignore-gpu-blocklist"] : [];
}

export function systemBrowser(): string | null {
  const named = (process.env.AUTORA_BROWSER_PATH || "").trim();
  if (named) return named;
  for (const candidate of CANDIDATE_PATHS) {
    try {
      if (fs.existsSync(candidate)) return candidate;
    } catch {
      // Unreadable is the same as absent for this purpose.
    }
  }
  return null;
}

/**
 * What to open, for what was typed.
 *
 * Only a real scheme is taken as one. `localhost:3000` and `box.local:8817`
 * used to be read as URLs with the schemes "localhost" and "box.local", which
 * Chrome refused, so the two addresses people most often hand an agent
 * running on their own server could not be opened without spelling out
 * http://. Without a scheme, an address on this machine or the local network
 * is opened over http, which is what a dev server or a box on the LAN
 * speaks, and anything else over https.
 */
export function addressFor(raw: string): string {
  const text = raw.trim();
  if (/^[a-z][a-z0-9+.-]*:\/\//i.test(text)) return text;
  if (/^(about|data|blob|javascript|mailto|view-source|chrome):/i.test(text)) return text;
  const bare = text.replace(/^\/\//, "");
  const host = bare.split(/[/?#]/)[0].replace(/:\d+$/, "").replace(/^\[|\]$/g, "").toLowerCase();
  const local =
    host === "localhost" || host === "::1" || host === "0.0.0.0" ||
    /\.(localhost|local|lan|internal|home\.arpa)$/.test(host) ||
    /^(127|10)\./.test(host) || /^192\.168\./.test(host) || /^172\.(1[6-9]|2\d|3[01])\./.test(host) ||
    /^100\.(6[4-9]|[7-9]\d|1[01]\d|12[0-7])\./.test(host) ||
    (!host.includes(".") && !host.includes(":"));
  return `${local ? "http" : "https"}://${bare}`;
}

/**
 * Where the browser keeps its profile.
 *
 * Beside the settings file, so it lands in whatever directory this
 * installation already treats as the one worth keeping -- `/data` in the
 * container, `.autora/` beside the app otherwise. Cookies and logins are as
 * sensitive as the API keys next door, so the directory is owner-only for the
 * same reason that one is.
 */
function profileDir(): string {
  const dir = path.join(path.dirname(stateFilePath()), "browser-profile");
  try {
    fs.mkdirSync(dir, { recursive: true, mode: 0o700 });
  } catch {
    // Chrome will say so more precisely than we can guess at here.
  }
  return dir;
}

/**
 * What this browser says it is, told truthfully.
 *
 * The user agent was pinned to Chrome/126 while the browser underneath was
 * 152, whose own client hints -- Sec-CH-UA, navigator.userAgentData, the
 * full version list -- said so in the same request. Two versions of one
 * browser is the first thing a bot score reads, and it was ours. The version
 * now comes from the binary, so upgrading the browser carries the user agent
 * with it; "HeadlessChrome" is the one word in it that does have to go,
 * because that is the browser announcing itself as the headless one.
 */
let cachedVersion: string | null | undefined;

function browserVersion(): string | null {
  if (cachedVersion !== undefined) return cachedVersion;
  cachedVersion = null;
  const exe = systemBrowser();
  if (exe) {
    try {
      const out = spawnSync(exe, ["--version"], { encoding: "utf8", timeout: 15_000 });
      const found = /(\d+\.\d+\.\d+\.\d+)/.exec(`${out.stdout ?? ""} ${out.stderr ?? ""}`);
      if (found) cachedVersion = found[1];
    } catch {
      // No version to be had: the browser's own user agent is left alone,
      // which is still better than one that contradicts it.
    }
  }
  return cachedVersion;
}

/** The user agent to present: the real version, and never "Headless". */
function browserUserAgent(): string | undefined {
  const full = browserVersion();
  if (!full) return undefined;
  const platform =
    process.platform === "darwin"
      ? "Macintosh; Intel Mac OS X 10_15_7"
      : process.platform === "win32"
        ? "Windows NT 10.0; Win64; x64"
        : "X11; Linux x86_64";
  return `Mozilla/5.0 (${platform}) AppleWebKit/537.36 (KHTML, like Gecko) Chrome/${full.split(".")[0]}.0.0.0 Safari/537.36`;
}

/**
 * Where this machine's traffic appears to come from, for the clock and the
 * language the browser reports.
 *
 * A browser that says it is in New York while its address is in Calgary is
 * hours out against its own IP, and the timezone is one of the few things a
 * page can read that is genuinely hard to fake consistently -- so it should be
 * the true one rather than a guess. Looked up once and cached for a week beside
 * the profile: an address changes about never, and a network round trip does
 * not belong in the path of opening a page.
 */
interface BrowserGeo {
  tz?: string;
  locale?: string;
  at: number;
}

function geoFile(): string {
  return path.join(path.dirname(stateFilePath()), "browser-geo.json");
}

/** The language a browser in that country would most plausibly be running. */
function languageFor(country: string | undefined): string | undefined {
  const english: Record<string, string> = {
    US: "en-US", CA: "en-CA", GB: "en-GB", AU: "en-AU", NZ: "en-NZ", IE: "en-IE",
  };
  return english[(country || "").toUpperCase()];
}

async function browserGeo(): Promise<BrowserGeo> {
  const forcedTz = (process.env.AUTORA_BROWSER_TZ || "").trim();
  const forcedLocale = (process.env.AUTORA_BROWSER_LOCALE || "").trim();
  if (forcedTz || forcedLocale) {
    return { tz: forcedTz || undefined, locale: forcedLocale || undefined, at: Date.now() };
  }

  let cached: BrowserGeo | null = null;
  try {
    cached = JSON.parse(fs.readFileSync(geoFile(), "utf8")) as BrowserGeo;
  } catch {
    cached = null;
  }
  if (cached?.tz && Date.now() - (cached.at || 0) < 7 * 24 * 3600_000) return cached;

  for (const source of ["https://ipinfo.io/json", "https://ipapi.co/json/"]) {
    try {
      const res = await fetch(source, {
        signal: AbortSignal.timeout(4000),
        headers: { accept: "application/json" },
      });
      if (!res.ok) continue;
      const data = (await res.json()) as { timezone?: string; country?: string; country_code?: string; languages?: string };
      const tz = typeof data.timezone === "string" && data.timezone.includes("/") ? data.timezone : undefined;
      if (!tz) continue;
      const country = data.country || data.country_code;
      const locale =
        languageFor(country) ||
        (typeof data.languages === "string" ? data.languages.split(",")[0].trim() : undefined);
      const fresh: BrowserGeo = { tz, locale, at: Date.now() };
      try {
        fs.writeFileSync(geoFile(), JSON.stringify(fresh), { mode: 0o600 });
      } catch {
        // The cache is an optimisation, not a requirement.
      }
      return fresh;
    } catch {
      // Offline, or that lookup is blocked: try the next, then the clock.
    }
  }
  return cached ?? { at: 0 };
}

/**
 * The pointer, drawn into the page.
 *
 * A headless browser has no cursor, so a recording of one clicking is a
 * recording of a page changing for no visible reason. This paints one: the same
 * arrow and "Autora" tag the other windows' cursors wear (lib/pointer.ts, the editors' hands),
 * so the agent looks the same in every tool. It is driven by the real input, not
 * by a guess at it: the arrow follows each genuine mouse move, presses when the
 * button goes down and ripples at that moment, shows "typing" while keys are
 * really being struck and "scrolling" while the wheel really turns. It sits in a
 * shadow root so the page cannot restyle it and `pointer-events: none` so it
 * cannot intercept the click it is illustrating.
 *
 * Marked `data-autora` and skipped by the element scan below, so it never
 * appears in what the model reads -- a cursor that the agent could click on
 * would be a very funny bug to debug.
 */
export const CURSOR_SCRIPT = `
(() => {
  // Init scripts run in every frame; one pointer, drawn over the whole page,
  // is the one that belongs to the top frame.
  if (window.__autoraCursor || window.top !== window) return;
  const mount = () => {
    if (!document.body || document.getElementById("__autora_cursor")) return;
    const host = document.createElement("div");
    host.id = "__autora_cursor";
    host.setAttribute("data-autora", "cursor");
    host.setAttribute("aria-hidden", "true");
    host.style.cssText = "position:fixed;inset:0;pointer-events:none;z-index:2147483647";
    const root = host.attachShadow({ mode: "closed" });
    root.innerHTML =
      '<style>' +
      '.cur{position:fixed;left:0;top:0;will-change:transform;transition:transform .07s linear}' +
      /* It pops into being where it starts work (out of a blur, a little past full size) and, once it has been idle a
         moment or the person has the page, swells a touch and dissolves: never a cut. */
      '.pop{position:relative;transform-origin:1px 1px;opacity:0}' +
      '.cur.on .pop{animation:pin .4s cubic-bezier(.34,1.56,.64,1) both}' +
      '.cur.out .pop{animation:pout .4s cubic-bezier(.32,.72,0,1) both}' +
      '@keyframes pin{0%{opacity:0;transform:scale(.25);filter:blur(4px)}55%{opacity:1;filter:none}100%{opacity:1;transform:none;filter:none}}' +
      '@keyframes pout{0%{opacity:1;transform:none}35%{opacity:1;transform:scale(1.18)}100%{opacity:0;transform:scale(.2);filter:blur(5px)}}' +
      '.pop>svg{display:block;transform-origin:1px 1px;transition:transform .09s ease-out;' +
      'filter:drop-shadow(0 1px 2px rgba(0,0,0,.35))}' +
      '.pop>svg path{fill:var(--a,#7c5cff)}' +
      '.cur.down .pop>svg{transform:scale(.82)}' +
      '.tag{position:absolute;left:14px;top:14px;display:inline-flex;align-items:center;gap:4px;padding:1px 8px 1px 6px;' +
      'border-radius:999px;background:var(--a,#7c5cff);color:#fff;font:600 10.5px/15px Inter,system-ui,sans-serif;' +
      'white-space:nowrap;transition:background .15s}' +
      '.tag .g{width:10px;height:10px;flex:none;fill:currentColor}.tag i{font-style:normal}' +
      '.cur.typing .tag{background:color-mix(in srgb,var(--a,#7c5cff) 78%,black)}' +
      '.cur.typing .tag::after{content:"";display:inline-block;width:0;height:10px;margin-left:4px;vertical-align:-1px;' +
      'border-right:2px solid #fff;animation:blink .7s steps(1) infinite}' +
      '@keyframes blink{50%{opacity:0}}' +
      '.thought{position:absolute;left:14px;top:-24px;padding:2px 9px;border-radius:999px;background:rgba(21,24,36,.94);' +
      'color:#edeff5;border:1px solid rgba(var(--ar,124,92,255),.5);font:550 11px/15px Inter,system-ui,sans-serif;white-space:nowrap;' +
      'opacity:0;transform:translateY(3px);transition:opacity .15s,transform .15s;box-shadow:0 4px 14px -4px rgba(0,0,0,.5)}' +
      '.thought.on{opacity:1;transform:none}.thought.low{top:34px}.thought.flip{left:auto;right:6px}' +
      '.ring{position:fixed;width:28px;height:28px;margin:-14px 0 0 -14px;border-radius:50%;' +
      'border:2px solid var(--a,#7c5cff);opacity:0}' +
      '@keyframes tap{from{transform:scale(.4);opacity:1}to{transform:scale(1.8);opacity:0}}' +
      '.ring.go{animation:tap .42s ease-out forwards}' +
      // The person's own tap: a quiet neutral ring, never the agent's colour.
      '.ring.you{border-color:rgba(255,255,255,.9);box-shadow:0 0 0 1px rgba(0,0,0,.35)}' +
      '.mark{position:fixed;box-sizing:border-box;border:2px solid rgba(139,124,246,.95);border-radius:4px;' +
      'background:rgba(139,124,246,.14);box-shadow:0 0 0 4px rgba(139,124,246,.28);' +
      'animation:markin .22s ease-out,markout .4s ease-in 1.2s forwards}' +
      '.mark span{position:absolute;left:-2px;top:-22px;padding:0 7px;border-radius:9px;background:#8b7cf6;color:#fff;' +
      'font:600 11px/17px system-ui,sans-serif;white-space:nowrap}' +
      '.mark.low span{top:auto;bottom:-22px}' +
      '@keyframes markin{from{opacity:0;transform:scale(1.04)}to{opacity:1;transform:scale(1)}}' +
      '@keyframes markout{to{opacity:0}}' +
      '</style>' +
      '<div class="ring"></div>' +
      '<div class="cur"><span class="pop"><svg width="16" height="20" viewBox="0 0 16 20">' +
      '<path d="M1 1 L1 15 L5 11.5 L8 18 L10.5 17 L7.5 10.5 L13 10.5 Z" fill="#7c5cff" stroke="#fff" ' +
      'stroke-width="1.2" stroke-linejoin="round"/></svg><span class="tag"><svg class="g" viewBox="0 0 10 10"><polygon points="5,0 10,10 0,10"/></svg><b>Autora</b><i></i></span></span><span class="thought"></span></div>';
    const cur = root.querySelector(".cur");
    const tag = root.querySelector(".tag i");
    const nameEl = root.querySelector(".tag b");
    const glyph = root.querySelector(".tag polygon");
    const ring = root.querySelector(".ring");
    const thought = root.querySelector(".thought");
    let thinkTimer = null;
    let atX = 0;
    let atY = 0;
    document.body.appendChild(host);
    let ringAt = 0;
    let doing = null;
    /* Whose hand is on the page. "agent": the input is Autora's, and its pointer shows it. "you": the person is using
       the page (the server says so before it passes on their tap, key or scroll), so their input is never drawn as
       Autora's pointer; it lapses on its own a moment after their last input. "off": the agent is working at speed
       with nothing shown (Visible work is off), until it is told "agent" again. */
    let hand = "agent";
    let handUntil = 0;
    const agents = () => hand === "agent" || (hand === "you" && Date.now() > handUntil);
    let idle = null;
    const show = () => {
      cur.classList.remove("out");
      cur.classList.add("on");
      clearTimeout(idle);
      idle = setTimeout(hide, 2600);
    };
    const hide = () => {
      clearTimeout(idle);
      if (!cur.classList.contains("on")) return;
      cur.classList.remove("on");
      cur.classList.add("out");
      thought.classList.remove("on");
    };
    window.__autoraHand = (h) => {
      hand = h === "you" || h === "off" ? h : "agent";
      handUntil = hand === "you" ? Date.now() + 2500 : 0;
      if (hand !== "agent") hide();
    };
    const say = (cls, text, ms) => {
      tag.textContent = text;
      cur.classList.toggle("typing", cls === "typing");
      clearTimeout(doing);
      doing = setTimeout(() => { tag.textContent = ""; cur.classList.remove("typing"); }, ms);
    };
    const ripple = (x, y, you) => {
      // A press and the tap that announces it are one click: once.
      if (Date.now() - ringAt < 220) return;
      ringAt = Date.now();
      ring.style.left = x + "px";
      ring.style.top = y + "px";
      ring.classList.remove("go");
      ring.classList.toggle("you", !!you);
      void ring.offsetWidth;
      ring.classList.add("go");
    };
    /* A few words about what it is doing, beside the pointer, for a moment: said by the server from the action it is
       about to take, so it is only ever what the pointer is really doing. */
    window.__autoraThought = (text) => {
      if (!agents()) return;
      thought.textContent = String(text || "");
      thought.classList.toggle("low", atY < 40);
      thought.classList.toggle("flip", atX > innerWidth - 230);
      thought.classList.add("on");
      clearTimeout(thinkTimer);
      thinkTimer = setTimeout(() => thought.classList.remove("on"), 2600);
    };
    /* Whose pointer it is: the agent of the Organization working here, or Autora (src/lib/cursorWho.ts): its name, colour
       and the shape of its mark. Said by the server before it moves the pointer. */
    window.__autoraWho = (name, color, rgb, sides) => {
      nameEl.textContent = String(name || "Autora");
      host.style.setProperty("--a", color || "#7c5cff");
      host.style.setProperty("--ar", rgb || "124,92,255");
      const n = Math.max(3, Math.min(12, Number(sides) || 3));
      glyph.setAttribute("points", Array.from({ length: n }, (_, i) => {
        const a = -Math.PI / 2 + (i * 2 * Math.PI) / n;
        return (5 + 5 * Math.cos(a)).toFixed(2) + "," + (5 + 5 * Math.sin(a)).toFixed(2);
      }).join(" "));
    };
    window.__autoraCursor = (x, y, tap) => {
      if (!agents()) {
        // The person's tap shows as theirs: a neutral ring where they touched, and no Autora pointer.
        if (tap && hand === "you") ripple(x, y, true);
        return;
      }
      atX = x; atY = y;
      cur.style.transform = "translate(" + x + "px," + y + "px)";
      show();
      if (tap) ripple(x, y);
    };
    // An outline round something that just changed, named, gone after a moment.
    window.__autoraMark = (x, y, w, h, label) => {
      const box = document.createElement("div");
      box.className = "mark" + (y < 26 ? " low" : "");
      box.style.left = x + "px";
      box.style.top = y + "px";
      box.style.width = w + "px";
      box.style.height = h + "px";
      const chip = document.createElement("span");
      chip.textContent = String(label || "");
      box.appendChild(chip);
      root.appendChild(box);
      setTimeout(() => box.remove(), 1700);
    };
    /* Follow the real input. The agent moves the mouse, presses, types and
       scrolls with genuine input events, so the cursor shows each of them as
       it happens rather than a summary of them afterwards. */
    const opt = { capture: true, passive: true };
    window.addEventListener("mousemove", (e) => {
      if (e.isTrusted) window.__autoraCursor(e.clientX, e.clientY, false);
    }, opt);
    window.addEventListener("mousedown", (e) => {
      if (!e.isTrusted) return;
      if (!agents()) { if (hand === "you") ripple(e.clientX, e.clientY, true); return; }
      window.__autoraCursor(e.clientX, e.clientY, false);
      cur.classList.add("down");
      ripple(e.clientX, e.clientY);
    }, opt);
    window.addEventListener("mouseup", (e) => {
      if (e.isTrusted) cur.classList.remove("down");
    }, opt);
    window.addEventListener("keydown", (e) => {
      if (e.isTrusted && !e.metaKey && !e.ctrlKey && agents()) { show(); say("typing", "", 900); }
    }, opt);
    window.addEventListener("wheel", (e) => {
      if (e.isTrusted && agents()) { show(); say("scroll", " · scrolling", 700); }
    }, opt);
  };
  if (document.readyState === "loading") {
    document.addEventListener("DOMContentLoaded", mount);
  } else {
    mount();
  }
  window.__autoraCursorMount = mount;
})();
`;

/**
 * What is on the page, as a list that two looks can be compared by (see
 * server/domdiff.ts): each visible element that has words of its own, or is a
 * picture, a control or a drawn box -- what it is, how it looks, where it is.
 */
const DOM_MAP_SCRIPT = `
(() => {
  const SKIP = new Set(["SCRIPT", "STYLE", "NOSCRIPT", "META", "LINK", "HEAD", "TITLE", "BR", "HTML", "BODY"]);
  const CONTROL = new Set(["IMG", "INPUT", "TEXTAREA", "SELECT", "BUTTON", "CANVAS", "VIDEO", "HR", "IFRAME"]);
  const out = [];
  const all = document.body ? document.body.querySelectorAll("*") : [];
  const own = (el) => {
    let t = "";
    for (const n of el.childNodes) if (n.nodeType === 3) t += n.nodeValue;
    return t.replace(/\\s+/g, " ").trim();
  };
  for (let i = 0; i < all.length && out.length < 700; i++) {
    const el = all[i];
    if (SKIP.has(el.tagName) || el.closest("[data-autora]")) continue;
    const r = el.getBoundingClientRect();
    if (r.width < 1 || r.height < 1) continue;
    const cs = getComputedStyle(el);
    if (cs.display === "none" || cs.visibility === "hidden" || Number(cs.opacity) === 0) continue;
    const text = own(el);
    const bg = cs.backgroundColor;
    const boxed = bg && bg !== "rgba(0, 0, 0, 0)" && bg !== "transparent" && el.childElementCount === 0 && r.width * r.height >= 400;
    if (!text && !CONTROL.has(el.tagName) && !boxed) continue;
    const src = el.tagName === "IMG" ? String(el.getAttribute("src") || "").split("/").pop() : "";
    const k = el.tagName.toLowerCase() + "|" + text.slice(0, 60) + "|" + String(el.className && el.className.baseVal !== undefined ? el.className.baseVal : el.className || "").slice(0, 60) + "|" + src;
    const s = [cs.color, bg, cs.fontSize, cs.fontWeight, cs.borderTopColor, cs.borderRadius].join(";");
    out.push({ k, s, tag: el.tagName.toLowerCase(), x: Math.round(r.left), y: Math.round(r.top), w: Math.round(r.width), h: Math.round(r.height) });
  }
  return out;
})()
`;

/**
 * Find the thing the agent means on the page: a selector if it looks like one,
 * otherwise the best match for some words among what can be clicked or typed
 * into (its text, label, placeholder, title). Scrolls it into view and says
 * where it is, or says what there is to choose from.
 */
const FIND_SCRIPT = (target: string) => `
(() => {
  const target = ${JSON.stringify(target)};
  const norm = (s) => String(s || "").replace(/\\s+/g, " ").trim().toLowerCase();
  const visible = (el) => {
    if (!el || el.closest("[data-autora]")) return false;
    const r = el.getBoundingClientRect();
    if (r.width < 1 || r.height < 1) return false;
    const cs = getComputedStyle(el);
    return cs.display !== "none" && cs.visibility !== "hidden" && Number(cs.opacity) !== 0;
  };
  const label = (el) => String(el.getAttribute("aria-label") || el.innerText || el.value || el.placeholder || el.title || el.alt || el.name || el.id || "").replace(/\\s+/g, " ").trim().slice(0, 80);
  let list = [];
  if (/^[#.\\[]|[>~+]|^[a-z][a-z0-9-]*[.#\\[:]/i.test(target)) {
    try { list = [...document.querySelectorAll(target)].filter(visible); } catch (e) { list = []; }
  }
  if (!list.length) {
    const want = norm(target);
    const CLICK = new Set(["A", "BUTTON", "INPUT", "SELECT", "TEXTAREA", "SUMMARY", "LABEL"]);
    const scored = [];
    for (const el of document.querySelectorAll("a,button,input,select,textarea,summary,label,[role=button],[role=link],[role=tab],[role=menuitem],[onclick],h1,h2,h3,h4,li,p,span,div,img")) {
      if (!visible(el)) continue;
      const texts = [el.getAttribute("aria-label"), el.innerText, el.value, el.placeholder, el.title, el.alt, el.name, el.id].map(norm).filter(Boolean);
      let score = 0;
      for (const t of texts) {
        if (t === want) score = Math.max(score, 3);
        else if (t.startsWith(want)) score = Math.max(score, 2);
        else if (t.includes(want)) score = Math.max(score, 1);
      }
      if (!score) continue;
      const clickable = CLICK.has(el.tagName) || el.getAttribute("role") || el.onclick;
      // The tightest match wins: a button over the section that contains it.
      score += (clickable ? 0.5 : 0) - Math.min(0.4, norm(el.innerText).length / 800);
      scored.push({ el, score });
    }
    scored.sort((a, b) => b.score - a.score);
    list = scored.map((s) => s.el);
  }
  if (!list.length) {
    const options = [...document.querySelectorAll("a,button,input,select,textarea,[role=button],[role=link]")]
      .filter(visible).map(label).filter(Boolean).slice(0, 14);
    return { ok: false, error: "Nothing on the page matches " + JSON.stringify(target) + ".", options };
  }
  const el = list[0];
  el.scrollIntoView({ block: "center", inline: "center", behavior: "instant" });
  const r = el.getBoundingClientRect();
  return { ok: true, x: r.left, y: r.top, w: r.width, h: r.height, tag: el.tagName.toLowerCase(), label: label(el), count: list.length };
})()
`;

/**
 * Everything on the page you could act on, numbered, and described well
 * enough to act on correctly.
 *
 * The accessibility layer rather than the DOM, for the reason the README
 * gives: the DOM is wrapper soup, a button is six nested divs, and the a11y
 * role and name are what a person perceiving this page without looking at it
 * would be given. Elements are collected in document order so the numbers are
 * stable across a read that changed nothing, and each carries the centre of
 * its box, which is where a click goes.
 *
 * A name alone was not enough to fill a form with. A box labelled "Name" is a
 * first name, a last name or both, and the page says which -- in its
 * autocomplete hint, its input type, the section it sits in, the text beside
 * it -- so all of that is carried too: what the field is for, what kind of
 * value it takes, whether it is required, and what the page said was wrong
 * with it. Dropdowns list their choices. Open shadow roots and same-origin
 * frames are walked, because a modern site's sign-in form is as likely to be
 * inside one as not, and a div that is only clickable because of its cursor
 * is still something to click.
 */
/**
 * What is drawn over a point of an element, as page script.
 *
 * The outline lists everything that is visible, and a cookie bar or a
 * newsletter pop-up is visible on top of things that are still listed as if
 * they could be clicked -- so a click on one landed on the pop-up, did
 * nothing the agent could see, and the agent tried again. This is the hit
 * test a mouse would get: what is topmost at the element's centre, through
 * open shadow roots and frames, and whether that is the element, part of it,
 * or something holding it. It defines `coverOf(el, x, y)`, which is null for
 * an element that can be clicked and otherwise says what is in the way.
 */
const COVER_FN = `
  const coverUp = (n) => {
    if (!n) return null;
    if (n.nodeType === 9) { try { return n.defaultView && n.defaultView.frameElement; } catch (e) { return null; } }
    return n.parentNode || n.host || null;
  };
  const coverInside = (n, anc) => {
    for (let p = n, i = 0; p && i < 300; p = coverUp(p), i++) if (p === anc) return true;
    return false;
  };
  const coverOf = (el, cx, cy) => {
    const doc = el.ownerDocument;
    const view = doc.defaultView;
    try { if (view.getComputedStyle(el).pointerEvents === "none") return null; } catch (e) {}
    let top = null;
    try { top = doc.elementFromPoint(cx, cy); } catch (e) { return null; }
    for (let i = 0; top && top.shadowRoot && i < 8; i++) {
      const inner = top.shadowRoot.elementFromPoint(cx, cy);
      if (!inner || inner === top) break;
      top = inner;
    }
    if (!top) return null;
    if (coverInside(top, el) || coverInside(el, top)) return null;
    const words = (s) => String(s || "").replace(/\\s+/g, " ").trim();
    let block = top.closest ? top.closest("dialog,[role=dialog],[role=alertdialog],[aria-modal=true]") : null;
    if (!block) {
      block = top;
      for (let p = top, i = 0; p && p.nodeType === 1 && p !== doc.body && i < 14; p = p.parentElement, i++) {
        const pos = view.getComputedStyle(p).position;
        if (pos === "fixed" || pos === "sticky") block = p;
      }
    }
    const said = words(block.getAttribute && block.getAttribute("aria-label")) ||
      words(block.innerText !== undefined ? block.innerText : block.textContent);
    return { block, label: (said.length > 70 ? said.slice(0, 69) + "\\u2026" : said) || String(block.tagName || "something").toLowerCase() };
  };
`;

const SCAN_SCRIPT = `
(() => {
  ${COVER_FN}
  const SELECTOR = [
    "a[href]", "button", "input", "select", "textarea", "summary", "label",
    "[role=button]", "[role=link]", "[role=checkbox]", "[role=radio]",
    "[role=tab]", "[role=menuitem]", "[role=menuitemcheckbox]", "[role=menuitemradio]",
    "[role=switch]", "[role=option]", "[role=combobox]", "[role=textbox]",
    "[role=searchbox]", "[role=slider]", "[role=spinbutton]", "[role=treeitem]",
    "[contenteditable=true]", "[contenteditable='']", "[tabindex]:not([tabindex='-1'])",
  ].join(",");
  const FIELD_TAGS = { INPUT: 1, SELECT: 1, TEXTAREA: 1 };
  const clean = (s) => String(s || "").replace(/\\s+/g, " ").trim();
  const short = (s, n) => { s = clean(s); return s.length > n ? s.slice(0, n - 1) + "\\u2026" : s; };
  const textOf = (el) => clean(el.innerText !== undefined ? el.innerText : el.textContent);

  /* What an autocomplete token or a field's own name says it is for. The
     single most useful thing to know about a box labelled "Name". */
  const PURPOSES = {
    "given-name": "first name", "family-name": "last name", "additional-name": "middle name",
    "name": "full name", "nickname": "nickname", "honorific-prefix": "title (Mr, Ms...)",
    "email": "email", "tel": "phone", "tel-national": "phone", "tel-country-code": "phone country code",
    "street-address": "street address", "address-line1": "address line 1",
    "address-line2": "address line 2 (apt, suite)", "address-line3": "address line 3",
    "address-level2": "city", "address-level1": "state / province", "postal-code": "ZIP / postal code",
    "country": "country", "country-name": "country", "organization": "company",
    "organization-title": "job title", "bday": "date of birth", "bday-day": "birth day",
    "bday-month": "birth month", "bday-year": "birth year", "sex": "gender",
    "username": "username", "current-password": "current password",
    "new-password": "new password (being set)", "one-time-code": "one-time code",
    "cc-name": "name on card", "cc-number": "card number", "cc-exp": "card expiry",
    "cc-exp-month": "card expiry month", "cc-exp-year": "card expiry year",
    "cc-csc": "card security code", "url": "website",
  };
  const GUESSES = [
    [/first.?name|fname|given|forename/i, "first name"],
    [/last.?name|lname|surname|family.?name/i, "last name"],
    [/middle.?name|mname/i, "middle name"],
    [/full.?name/i, "full name"],
    [/e.?mail/i, "email"],
    [/phone|mobile|\\btel\\b|cell/i, "phone"],
    [/zip|postal|postcode/i, "ZIP / postal code"],
    [/\\bcity\\b|town|locality/i, "city"],
    [/\\bstate\\b|province|region|county/i, "state / province"],
    [/country/i, "country"],
    [/address.?(line)?.?2|apt|suite|unit/i, "address line 2 (apt, suite)"],
    [/address|street/i, "street address"],
    [/birth|\\bdob\\b|bday/i, "date of birth"],
    [/user.?name|login.?id/i, "username"],
    [/company|organi[sz]ation|employer/i, "company"],
    [/otp|one.?time|verification.?code|2fa|mfa/i, "one-time code"],
  ];
  const purposeOf = (el) => {
    const auto = (el.getAttribute("autocomplete") || "").toLowerCase().split(/\\s+/)
      .filter((t) => t && t !== "on" && t !== "off" && !t.startsWith("section-"));
    const scope = auto.find((t) => t === "shipping" || t === "billing");
    const token = auto.find((t) => PURPOSES[t]);
    if (token) return (scope ? scope + " " : "") + PURPOSES[token];
    const hint = (el.getAttribute("name") || "") + " " + (el.id || "");
    for (const [re, what] of GUESSES) if (re.test(hint)) return what;
    return "";
  };

  const rootOf = (el) => el.getRootNode ? el.getRootNode() : el.ownerDocument;
  const byIds = (el, ids) => {
    const root = rootOf(el);
    return clean(String(ids || "").split(/\\s+/).map((id) => {
      const n = (root.getElementById ? root.getElementById(id) : null) || el.ownerDocument.getElementById(id);
      return n ? textOf(n) : "";
    }).join(" "));
  };

  /* Text just before the element: the "First name" in
     <div><span>First name</span><input></div>, which is how a great many
     forms are labelled and which no attribute records. */
  const nearbyText = (el) => {
    let node = el;
    for (let depth = 0; depth < 3 && node; depth++) {
      let sib = node.previousElementSibling;
      for (let hops = 0; sib && hops < 3; hops++) {
        // Another field before this one: whatever is before that is its label.
        if (isField(sib) || sib.querySelector("input,select,textarea")) return "";
        if (!sib.matches(SELECTOR) || sib.tagName === "LABEL") {
          const t = textOf(sib);
          if (t && t.length <= 80) return t;
          if (t) return "";
        }
        sib = sib.previousElementSibling;
      }
      node = node.parentElement;
      if (node && node.querySelectorAll("input,select,textarea").length > 1) break;
    }
    return "";
  };

  /* A tile that is only a picture -- the squares of a picture CAPTCHA, the
     cells of a picker -- has no text of its own to name it, so the outline
     dropped it and there was no way to click it. Its name is in the picture:
     the alt, or failing that the file, which for a CAPTCHA grid is the whole
     answer (carrot.webp, stop-sign, the letter drawn on it). One image only,
     so a whole card of pictures is not mistaken for one tile. */
  const imageLabel = (el) => {
    let pics = [];
    try {
      pics = /^(IMG|IMAGE)$/.test(el.tagName || "") ? [el] : Array.from(el.querySelectorAll("img,svg image"));
    } catch (err) { return ""; }
    if (pics.length !== 1) return "";
    const pic = pics[0];
    const alt = clean(pic.getAttribute("alt") || pic.getAttribute("aria-label"));
    if (alt) return alt;
    const title = clean(pic.getAttribute("title"));
    if (title) return title;
    const src = pic.getAttribute("src") || pic.getAttribute("xlink:href") || pic.getAttribute("href") || "";
    const file = String(src).split(/[?#]/)[0].split("/").pop() || "";
    if (!file) return "";
    try {
      return clean(decodeURIComponent(file.replace(/[.][a-z0-9]{2,5}$/i, "")).replace(/[-_+]+/g, " "));
    } catch (err) { return clean(file.replace(/[.][a-z0-9]{2,5}$/i, "")); }
  };

  const isField = (el) => !!FIELD_TAGS[el.tagName];
  const named = (el) => {
    const label = el.getAttribute("aria-label");
    if (label && clean(label)) return clean(label);
    const by = el.getAttribute("aria-labelledby");
    if (by) { const t = byIds(el, by); if (t) return t; }
    if (el.labels && el.labels.length) {
      const t = clean(Array.from(el.labels).map(textOf).join(" "));
      if (t) return t;
    }
    const wrapping = el.closest("label");
    if (wrapping && textOf(wrapping)) return textOf(wrapping);
    if (isField(el) || el.isContentEditable) {
      const t = el.getAttribute("title") || nearbyText(el) || el.getAttribute("placeholder");
      if (t) return clean(t);
      const raw = el.getAttribute("name") || el.id || "";
      return clean(raw.replace(/([a-z])([A-Z])/g, "$1 $2").replace(/[_\\-\\[\\].]+/g, " "));
    }
    const img = el.querySelector && el.querySelector("img[alt]");
    return clean(textOf(el) || el.getAttribute("alt") || el.getAttribute("title")
      || (img && img.getAttribute("alt")) || el.value || "");
  };

  const roleOf = (el) => {
    const explicit = el.getAttribute("role");
    if (explicit) return explicit.split(/\\s+/)[0];
    const tag = el.tagName.toLowerCase();
    if (tag === "a") return "link";
    if (tag === "button" || tag === "summary") return "button";
    if (tag === "select") return el.multiple ? "listbox" : "combobox";
    if (tag === "textarea") return "textbox";
    if (tag === "label") return "label";
    if (el.isContentEditable) return "textbox";
    if (tag !== "input") return "clickable";
    const type = (el.getAttribute("type") || "text").toLowerCase();
    if (type === "checkbox" || type === "radio" || type === "range" || type === "file") return type === "range" ? "slider" : type;
    if (type === "submit" || type === "button" || type === "reset" || type === "image") return "button";
    if (type === "password") return "password";
    return "textbox";
  };

  /* The section a field belongs to: its fieldset's legend, a labelled group,
     or the nearest heading above it. "Name" under "Billing address" and
     "Name" under "Cardholder" are different fields. */
  // A legend names its own fieldset only, which closest() handles; in the
  // walk back it would name the neighbouring one.
  const HEADING = "h1,h2,h3,h4,h5,h6,[role=heading]";
  const sectionOf = (el) => {
    const set = el.closest("fieldset");
    if (set) { const legend = set.querySelector("legend"); if (legend && textOf(legend)) return short(textOf(legend), 60); }
    const group = el.closest("[role=group],[role=radiogroup]");
    if (group) {
      const t = group.getAttribute("aria-label") || byIds(group, group.getAttribute("aria-labelledby"));
      if (t) return short(t, 60);
    }
    let node = el;
    for (let steps = 0; node && steps < 60; steps++) {
      let prev = node.previousElementSibling;
      while (prev && steps < 60) {
        steps++;
        if (prev.matches(HEADING)) return short(textOf(prev), 60);
        const inner = prev.querySelectorAll(HEADING);
        if (inner.length) return short(textOf(inner[inner.length - 1]), 60);
        prev = prev.previousElementSibling;
      }
      node = node.parentElement;
      if (!node || node.tagName === "BODY" || node.tagName === "FORM" || node.tagName === "MAIN") break;
    }
    return "";
  };

  const dialogOf = (el) => {
    const d = el.closest("dialog[open],[role=dialog],[role=alertdialog],[aria-modal=true]");
    if (!d) return null;
    return d;
  };
  const dialogName = (d) => short(d.getAttribute("aria-label")
    || byIds(d, d.getAttribute("aria-labelledby"))
    || (d.querySelector(HEADING) ? textOf(d.querySelector(HEADING)) : "") || "dialog", 60);

  const visible = (el, box) => {
    if (box.width < 2 || box.height < 2) return false;
    const style = el.ownerDocument.defaultView.getComputedStyle(el);
    return !(style.visibility === "hidden" || style.display === "none" || style.opacity === "0");
  };

  /* Every candidate, in document order, through open shadow roots and into
     frames on this origin, with the offset of the frame each is in. */
  const found = [];
  const walk = (root, dx, dy, depth) => {
    for (const el of root.querySelectorAll("*")) {
      if (el.closest("[data-autora]")) continue;
      found.push([el, dx, dy]);
      if (el.shadowRoot && depth < 8) walk(el.shadowRoot, dx, dy, depth + 1);
      if ((el.tagName === "IFRAME" || el.tagName === "FRAME") && depth < 4) {
        let doc = null;
        try { doc = el.contentDocument; } catch (e) {}
        if (doc && doc.documentElement) {
          const r = el.getBoundingClientRect();
          walk(doc, dx + r.left + el.clientLeft, dy + r.top + el.clientTop, depth + 1);
        }
      }
    }
  };
  walk(document, 0, 0, 0);

  /* A modal makes the rest of the page inert: listing what is behind it
     only invites clicks that land on nothing. */
  let modal = null;
  for (const d of document.querySelectorAll("dialog,[aria-modal=true]")) {
    const isModal = d.tagName === "DIALOG" ? d.matches(":modal") : true;
    if (!isModal) continue;
    const b = d.getBoundingClientRect();
    if (visible(d, b)) { modal = d; break; }
  }

  const refs = [];
  const elements = [];
  const blockers = [];
  const taken = new Set();
  const within = (el) => { for (let p = el.parentElement; p; p = p.parentElement) if (taken.has(p)) return p; return null; };
  for (const [el, dx, dy] of found) {
    if (modal && el.ownerDocument === document && !modal.contains(el)) continue;
    let target = el;
    let matched = el.matches(SELECTOR);
    // A label is only worth listing when it stands in for a control that
    // has been hidden to be restyled -- the usual custom checkbox.
    if (matched && el.tagName === "LABEL") {
      const control = el.control;
      if (!control || !/^(checkbox|radio)$/i.test(control.type || "")) continue;
      const cbox = control.getBoundingClientRect();
      if (visible(control, cbox)) continue;
      target = control;
    }
    /* A div that is only clickable because a script says so still looks
       clickable to a person: a pointer cursor, a little text, and not inside
       something already listed. */
    if (!matched) {
      if (!el.parentElement || el.children.length > 6) continue;
      const style = el.ownerDocument.defaultView.getComputedStyle(el);
      if (style.cursor !== "pointer") continue;
      const parentStyle = el.ownerDocument.defaultView.getComputedStyle(el.parentElement);
      if (parentStyle.cursor === "pointer") continue;
      const t = textOf(el) || imageLabel(el);
      if (!t || t.length > 80) continue;
      if (within(el)) continue;
      matched = true;
    }
    const box = el.getBoundingClientRect();
    if (!visible(el, box)) continue;
    // A span with tabindex inside a link is the link.
    const outer = within(el);
    if (outer && outer.tagName === "A" && !isField(el)) continue;
    const role = roleOf(target);
    const name = short(named(target) || named(el) || imageLabel(el), 120);
    const field = isField(target) || role === "textbox" || role === "combobox" || role === "searchbox";
    if (!name && !field && role !== "password") continue;
    const ref = refs.length;
    const x = box.left + dx, y = box.top + dy;
    const inView = y + box.height > -40 && y < innerHeight + 40 && x + box.width > 0 && x < innerWidth;
    const type = target.tagName === "INPUT" ? (target.getAttribute("type") || "text").toLowerCase() : null;
    const info = {
      ref, role, name,
      value: null, x: Math.round(x + box.width / 2), y: Math.round(y + box.height / 2),
      w: Math.round(box.width), h: Math.round(box.height),
      href: el.tagName === "A" ? (el.getAttribute("href") || null) : null,
      checked: null, disabled: !!(target.disabled || target.getAttribute("aria-disabled") === "true"),
      inView,
    };
    if (target.tagName === "SELECT") {
      const opts = Array.from(target.options).map((o) => clean(o.text || o.value));
      const chosen = Array.from(target.selectedOptions || []).map((o) => clean(o.text || o.value));
      info.value = chosen.join(", ") || null;
      info.options = opts.filter(Boolean).slice(0, 15);
      info.optionCount = opts.filter(Boolean).length;
    } else if (typeof target.value === "string" && type !== "password" && role !== "button" && role !== "checkbox" && role !== "radio") {
      info.value = target.value.slice(0, 80) || null;
    } else if (target.isContentEditable || role === "textbox" || role === "combobox" || role === "searchbox") {
      info.value = short(textOf(target), 80) || null;
      if (info.value === name) info.value = null;
    }
    if (typeof target.checked === "boolean" && (type === "checkbox" || type === "radio")) info.checked = target.checked;
    else if (target.hasAttribute("aria-checked")) info.checked = target.getAttribute("aria-checked") === "true";
    else if (role === "switch" || role === "menuitemcheckbox") info.checked = target.getAttribute("aria-pressed") === "true";
    if (field || role === "checkbox" || role === "radio" || role === "password" || role === "switch") {
      if (type && !/^(text|checkbox|radio|submit|button|hidden|password)$/.test(type)) info.type = type;
      const purpose = purposeOf(target);
      if (purpose && purpose.toLowerCase() !== name.toLowerCase()) info.purpose = purpose;
      const ph = target.getAttribute("placeholder");
      if (ph && clean(ph) !== name && clean(ph) !== info.value) info.placeholder = short(ph, 60);
      if (target.required || target.getAttribute("aria-required") === "true") info.required = true;
      const max = Number(target.getAttribute("maxlength"));
      if (max > 0 && max <= 12) info.maxLength = max;
      if (type === "number" || type === "date" || type === "range") {
        const lo = target.getAttribute("min"), hi = target.getAttribute("max");
        if (lo || hi) info.range = (lo || "") + ".." + (hi || "");
      }
      const hint = byIds(target, target.getAttribute("aria-describedby"));
      const invalid = target.getAttribute("aria-invalid") === "true"
        || (target.validity && !target.validity.valid && (target.value || "") !== "");
      if (invalid) {
        info.invalid = short(byIds(target, target.getAttribute("aria-errormessage")) || hint
          || target.validationMessage || "the page marks this as invalid", 120);
      } else if (hint && hint !== name) {
        info.hint = short(hint, 100);
      }
      if (role === "radio" || role === "checkbox" || field) {
        const section = sectionOf(target);
        if (section && section !== name) info.section = section;
      }
    }
    const expanded = el.getAttribute("aria-expanded");
    if (expanded === "true" || expanded === "false") info.expanded = expanded === "true";
    if (el.getAttribute("aria-selected") === "true" && role !== "option") info.selected = true;
    if (role === "option" && el.getAttribute("aria-selected") === "true") info.selected = true;
    if (el.getAttribute("aria-current") && el.getAttribute("aria-current") !== "false") info.current = true;
    const dialog = dialogOf(el);
    if (dialog) info.dialog = dialogName(dialog);
    if (inView) {
      const hit = coverOf(el, box.left + box.width / 2, box.top + box.height / 2);
      if (hit) { info.covered = hit.label; blockers.push([info, hit.block]); }
    }
    refs.push(info);
    // The label, for a restyled checkbox: it is what is on screen to click.
    elements.push(el);
    taken.add(el);
  }
  window.__autoraRefs = elements;

  /* What would dismiss the thing in the way: its own listed controls. */
  for (const [info, block] of blockers) {
    const controls = [];
    for (let i = 0; i < elements.length && controls.length < 3; i++) {
      if (refs[i].covered || refs[i].disabled || !block.contains(elements[i])) continue;
      controls.push(i);
    }
    if (controls.length) info.coverRefs = controls;
  }

  /* An open dialog sits on top of the page: whatever it asks comes first,
     and clicks behind it tend to land on it instead. */
  let dialog = null;
  for (const d of document.querySelectorAll("dialog[open],[role=dialog],[role=alertdialog],[aria-modal=true]")) {
    const b = d.getBoundingClientRect();
    if (visible(d, b) && b.width > 100 && b.height > 60) { dialog = dialogName(d); break; }
  }

  /* Where the reader is on the page -- or in the pane that does the
     scrolling, on the many apps whose page itself never moves. */
  const scroller = (() => {
    const doc = document.scrollingElement || document.documentElement;
    if (doc.scrollHeight > innerHeight + 20) return doc;
    let best = null, area = 0;
    for (const el of document.querySelectorAll("body *")) {
      if (el.scrollHeight <= el.clientHeight + 20 || el.clientHeight < 150) continue;
      const oy = getComputedStyle(el).overflowY;
      if (oy !== "auto" && oy !== "scroll") continue;
      const b = el.getBoundingClientRect();
      const a = b.width * b.height;
      if (a > area) { area = a; best = el; }
    }
    return best || doc;
  })();
  const scroll = {
    y: Math.round(scroller.scrollTop),
    max: Math.max(0, Math.round(scroller.scrollHeight - scroller.clientHeight)),
    view: Math.round(scroller === (document.scrollingElement || document.documentElement) ? innerHeight : scroller.clientHeight),
    pane: scroller !== (document.scrollingElement || document.documentElement),
  };

  /* The main content rather than the whole body: a site's menus, header and
     footer are the same on every page and are most of the text on many. A
     <main> or <article> that holds a fair share of the page is taken as it
     is; otherwise the body with its navigation, header, footer and asides
     cut out -- unless that leaves almost nothing, when the body it is. */
  const body = document.body ? (document.body.innerText || "") : "";
  const MENU_WORDS = /(^|[\\s_-])(nav|navbar|navigation|menu|sidebar|breadcrumbs?|toc|lang|languages|footer|cookie|cookies|skip)([\\s_-]|$)/i;
  const menuish = (el, outside) =>
    el.tagName === "NAV" || el.tagName === "ASIDE" || el.tagName === "FOOTER" ||
    (outside && el.tagName === "HEADER") ||
    /^(navigation|banner|contentinfo|complementary|search)$/i.test(el.getAttribute("role") || "") ||
    MENU_WORDS.test((el.getAttribute("class") || "") + " " + (el.id || ""));
  /* The root's text with its menus, language lists, tables of contents and
     the like taken out -- each once, as its outermost element. */
  const withoutMenus = (root, outside) => {
    let text = root.innerText || "";
    const cut = new Set();
    for (const el of root.querySelectorAll("*")) {
      if (!menuish(el, outside)) continue;
      let up = el.parentElement, nested = false;
      while (up && up !== root) { if (cut.has(up)) { nested = true; break; } up = up.parentElement; }
      if (nested) continue;
      cut.add(el);
      const chunk = (el.innerText || "").trim();
      if (chunk) text = text.replace(chunk, "");
    }
    return text.trim().length >= 200 ? text : (root.innerText || "");
  };
  const mainText = (() => {
    if (!document.body) return "";
    const main = document.querySelector("main, [role=main]") || document.querySelector("article");
    const own = main ? (main.innerText || "") : "";
    if (main && own.trim().length >= Math.min(400, body.length * 0.3)) return withoutMenus(main, false);
    return withoutMenus(document.body, true);
  })();
  return {
    url: location.href,
    title: document.title,
    refs,
    dialog,
    scroll,
    text: mainText.replace(/[ \\t]+/g, " ").replace(/\\n{3,}/g, "\\n\\n").trim().slice(0, 150000),
  };
})();
`;

/**
 * Is there a browser to drive at all?
 *
 * Asked once and remembered. It cannot be answered synchronously -- the only
 * honest test that `playwright-core` is installed is importing it, and this
 * file is loaded as ESM in development and bundled to CJS in the container, so
 * `require.resolve` is available in exactly one of those. The probe therefore
 * runs at startup and everything afterwards reads the answer it left.
 */
let probed: { ok: boolean; detail: string | null } | null = null;

export async function probeBrowser(): Promise<{ ok: boolean; detail: string | null }> {
  if (probed) return probed;
  try {
    await import("playwright-core");
  } catch {
    probed = {
      ok: false,
      detail:
        "Browsing needs the optional `playwright-core` package, which is not installed here. " +
        "Run `npm install playwright-core` beside the app and restart.",
    };
    return probed;
  }
  if (!systemBrowser() && !process.env.PLAYWRIGHT_BROWSERS_PATH) {
    probed = {
      ok: false,
      detail:
        "No Chromium was found. Install one (apk add chromium, apt install chromium, or Chrome), " +
        "or point AUTORA_BROWSER_PATH at the binary.",
    };
    return probed;
  }
  probed = { ok: true, detail: null };
  return probed;
}

const STEALTH_SCRIPT = `
(() => {
  /* The functions this script replaces are marked, so that a page asking any
     of them what they are gets the answer a built-in gives: "[native code]".
     An overridden navigator property that still prints its own source is a
     louder tell than the property was. */
  const natives = new WeakMap();
  const mark = (fn, name) => {
    try { natives.set(fn, "function " + (name || "") + "() { [native code] }"); } catch {}
    return fn;
  };
  const define = (obj, prop, get) => {
    try { Object.defineProperty(obj, prop, { get, configurable: true }); } catch {}
  };

  /* -- the flag, and the globals a driven Chrome still has ---------------- */
  define(navigator, "webdriver", () => undefined);
  try {
    const c = window.chrome || (window.chrome = {});
    if (!c.runtime) {
      c.runtime = {
        id: undefined,
        connect: () => undefined,
        sendMessage: () => undefined,
        OnInstalledReason: { CHROME_UPDATE: "chrome_update", INSTALL: "install", SHARED_MODULE_UPDATE: "shared_module_update", UPDATE: "update" },
        PlatformArch: { ARM: "arm", ARM64: "arm64", MIPS: "mips", MIPS64: "mips64", X86_32: "x86-32", X86_64: "x86-64" },
        PlatformOs: { ANDROID: "android", CROS: "cros", LINUX: "linux", MAC: "mac", OPENBSD: "openbsd", WIN: "win" }
      };
    }
    if (!c.app) {
      c.app = {
        isInstalled: false,
        InstallState: { DISABLED: "disabled", INSTALLED: "installed", NOT_INSTALLED: "not_installed" },
        RunningState: { CANNOT_RUN: "cannot_run", READY_TO_RUN: "ready_to_run", RUNNING: "running" }
      };
    }
    if (!c.csi) c.csi = () => ({ onloadT: Date.now(), startE: Date.now(), pageT: 120, tran: 15 });
    if (!c.loadTimes) {
      const now = () => Date.now() / 1000;
      c.loadTimes = () => ({
        commitLoadTime: now(), connectionInfo: "h2", finishDocumentLoadTime: 0, finishLoadTime: 0,
        firstPaintTime: 0, firstPaintAfterLoadTime: 0, npnNegotiatedProtocol: "h2", navigationType: "Other",
        requestTime: now(), startLoadTime: now(), wasAlternateProtocolAvailable: false,
        wasFetchedViaSpdy: true, wasNpnNegotiated: true
      });
    }
  } catch {}

  /* -- the graphics card --------------------------------------------------
     This machine has no GPU, so WebGL is Chrome's software renderer and says
     so by name: "SwiftShader" in the unmasked renderer is one of the surest
     signs that nobody is sitting in front of the machine. Reported instead as
     the integrated Intel chip a Linux desktop of this age would have, which
     is the same story the platform and the user agent are telling. */
  const VENDOR = "Google Inc. (Intel)";
  const RENDERER = "ANGLE (Intel, Mesa Intel(R) UHD Graphics 630 (CFL GT2), OpenGL 4.6 (Core Profile) Mesa 23.1.4)";
  for (const name of ["WebGLRenderingContext", "WebGL2RenderingContext"]) {
    const proto = window[name] && window[name].prototype;
    if (!proto || !proto.getParameter) continue;
    const original = proto.getParameter;
    proto.getParameter = mark(function getParameter(parameter) {
      try {
        const info = this.getExtension && this.getExtension("WEBGL_debug_renderer_info");
        if (info) {
          if (parameter === info.UNMASKED_VENDOR_WEBGL) return VENDOR;
          if (parameter === info.UNMASKED_RENDERER_WEBGL) return RENDERER;
        }
      } catch {}
      return original.call(this, parameter);
    }, "getParameter");
  }

  /* -- a window with a browser around it ---------------------------------
     A headless browser draws no tabs and no address bar, so its window is
     exactly as tall as the page inside it -- a page can measure that, and the
     difference is around eighty pixels on a desktop. */
  define(window, "outerHeight", () => window.innerHeight + 87);
  define(window, "outerWidth", () => window.innerWidth + 16);

  /* -- what the page is allowed to ask ------------------------------------
     Chrome answers "prompt" for notifications until it is asked once; the
     driven one answers "default", which is not a state the API has. */
  try {
    const query = navigator.permissions && navigator.permissions.query;
    if (query) {
      navigator.permissions.query = mark(function query(parameters) {
        if (parameters && parameters.name === "notifications") {
          const known = typeof Notification !== "undefined" && Notification.permission !== "default";
          return Promise.resolve({
            name: "notifications",
            state: known ? Notification.permission : "prompt",
            onchange: null,
            addEventListener: () => undefined,
            removeEventListener: () => undefined,
            dispatchEvent: () => false
          });
        }
        return query.call(navigator.permissions, parameters);
      }, "query");
    }
  } catch {}

  /* -- the network ---------------------------------------------------------
     Every desktop Chrome has this; a browser without it is not a desktop
     Chrome. */
  try {
    if (!navigator.connection) {
      define(navigator, "connection", () => ({
        downlink: 10, downlinkMax: Infinity, effectiveType: "4g", rtt: 50, saveData: false,
        type: "wifi", onchange: null,
        addEventListener: () => undefined, removeEventListener: () => undefined
      }));
    }
  } catch {}

  /* -- and the last word on all of the above ------------------------------- */
  try {
    const original = Function.prototype.toString;
    const patched = function toString() {
      const fake = natives.get(this);
      return fake || original.call(this);
    };
    natives.set(patched, "function toString() { [native code] }");
    Function.prototype.toString = patched;
  } catch {}
})();
`;

/**
 * Clear a profile lock nobody is holding.
 *
 * Chrome marks a profile in use with `SingletonLock`, a symlink to
 * `<hostname>-<pid>`. A container that was restarted or recreated leaves that
 * behind with the old container's hostname, and Chrome then refuses the
 * profile outright ("in use by another Chromium process on another computer")
 * and exits. A browser left running by an earlier run of this server holds it
 * for real; that one is an orphan nobody can reach, so it is stopped. Either
 * way nothing else should be using this profile: it is Autora's.
 */
function clearStaleLock(dir: string) {
  const lock = path.join(dir, "SingletonLock");
  let target: string;
  try {
    target = fs.readlinkSync(lock);
  } catch {
    return; // No lock, or not a symlink: nothing to clear.
  }
  const dash = target.lastIndexOf("-");
  const host = dash > 0 ? target.slice(0, dash) : "";
  const pid = Number(target.slice(dash + 1));
  if (host === os.hostname() && Number.isInteger(pid) && pid > 0 && pid !== process.pid) {
    let alive = false;
    try {
      process.kill(pid, 0);
      alive = true;
    } catch {
      // Gone already.
    }
    if (alive) {
      let ours = false;
      try {
        ours = fs.readFileSync(`/proc/${pid}/cmdline`, "utf8").includes(dir);
      } catch {
        // No /proc (not Linux): leave a live process alone.
      }
      if (!ours) return;
      try {
        process.kill(pid, "SIGKILL");
      } catch {
        // Exited between the two calls.
      }
    }
  }
  for (const name of ["SingletonLock", "SingletonCookie", "SingletonSocket"]) {
    try {
      fs.rmSync(path.join(dir, name), { force: true });
    } catch {
      // Chrome will say so if it still minds.
    }
  }
}

/**
 * The one Chrome every session shares.
 *
 * A persistent profile can be open in one browser at a time, so a browser per
 * session meant the second conversation to open a page found the profile
 * locked by the first and failed. Instead there is one browser on the profile
 * -- one set of sign-ins -- and each session gets a tab of its own in it. It
 * stays up while any session has a tab and closes, flushing the profile, when
 * the last one lets go.
 */
let shared: { context: BrowserContext; users: number } | null = null;
let launching: Promise<BrowserContext> | null = null;
/** The chromium processes behind `shared`, recorded at launch so that closing
    it takes the whole tree. A browser is twenty-odd processes and the DevTools
    close only stops the top one; the rest are reparented to PID 1, which is
    the node server and reaps nothing, so they used to stay as zombies for the
    life of the container. See server/processes.ts. */
let browserTree: number[] = [];
/** Pages some session has taken, so the tab Chrome opens with is handed out
    once rather than to everyone. */
const claimed = new WeakSet<object>();

async function launchShared(): Promise<BrowserContext> {
  const { chromium } = await import("playwright-core");
  const executablePath = systemBrowser();
  const dir = profileDir();
  const geo = await browserGeo();
  const agent = browserUserAgent();
  const extensionArgs = launchArgs();
  const launch = () =>
    chromium.launchPersistentContext(dir, {
      // Extensions need Chrome's new headless mode, which is the whole
      // browser without a window; it is asked for by flag (see extensions.ts).
      headless: process.env.AUTORA_BROWSER_HEADED !== "1" && !extensionArgs.length,
      ...(executablePath ? { executablePath } : {}),
      viewport: VIEWPORT,
      deviceScaleFactor: 1,
      // The browser's own user agent, with "Headless" taken out of it and its
      // real version left in: see browserUserAgent.
      ...(agent ? { userAgent: agent } : {}),
      locale: geo.locale || "en-US",
      ...(geo.tz ? { timezoneId: geo.tz } : {}),
      ignoreDefaultArgs: extensionArgs.length ? ["--enable-automation", "--disable-extensions"] : ["--enable-automation"],
      args: [
        ...(process.env.AUTORA_BROWSER_HEADED === "1" ? extensionArgs.filter((a) => a !== "--headless=new") : extensionArgs),
        "--no-sandbox",
        "--disable-dev-shm-usage",
        "--hide-scrollbars",
        "--disable-blink-features=AutomationControlled",
        "--disable-features=IsolateOrigins,site-per-process",
        "--disable-infobars",
        "--force-color-profile=srgb",
        // A canvas the page draws needs a GL context: see webglArgs.
        ...webglArgs(),
        `--window-size=${VIEWPORT.width},${VIEWPORT.height}`,
      ],
    });
  clearStaleLock(dir);
  /* Whatever chromium this launch started, successful or not: a launch that
     throws halfway through can still leave a browser behind, and that one
     holds the profile lock and every one of its children is an orphan. */
  const launchTracked = async () => {
    const before = new Set(browserRoots());
    try {
      return await launch();
    } finally {
      const born = browserRoots().filter((pid) => !before.has(pid));
      if (born.length) browserTree = born;
    }
  };
  let context: BrowserContext;
  try {
    context = await launchTracked();
  } catch (err) {
    // Once more after clearing again: a browser that was still shutting down
    // a moment ago may have released the profile by now.
    await new Promise((resolve) => setTimeout(resolve, 500));
    clearStaleLock(dir);
    try {
      context = await launchTracked();
    } catch {
      retireTree();
      throw new Error(`The browser would not start: ${firstLine(err)}`);
    }
  }
  await restoreCookies(context);
  await context.addInitScript(STEALTH_SCRIPT);
  await context.addInitScript(CURSOR_SCRIPT);
  /* A passkey request -- Google's "Use your passkey", a site's "Sign in with
     a passkey" -- opens Chrome's own dialog, which a headless browser draws
     nowhere. It still holds the tab: every click on the page is dropped until
     it closes, so "Try another way" did nothing and the person had no dialog
     to close. With WebAuthn handed to the DevTools protocol there is no
     dialog; the request goes unanswered and the page stays clickable, so its
     other ways in (a code, a prompt on the phone, the password) can be
     chosen. A headed browser shows the real dialog, so it is left alone. */
  if (process.env.AUTORA_BROWSER_HEADED !== "1") {
    const noPasskeyDialog = (page: Page) => {
      void context
        .newCDPSession(page)
        .then((cdp: any) => cdp.send("WebAuthn.enable", { enableUI: false }))
        .catch(() => undefined);
    };
    context.pages().forEach(noPasskeyDialog);
    context.on("page", noPasskeyDialog);
  }
  context.on("close", () => {
    if (shared?.context === context) shared = null;
    retireTree();
  });
  return context;
}

/** Take down the tree behind the browser that has just been closed: wait a
    moment for it to exit by itself, then kill what is left, so nothing is
    reparented to PID 1 to become a zombie nobody can clear. */
function retireTree() {
  const tree = browserTree;
  browserTree = [];
  for (const pid of tree) void settleTree(pid);
}

/** A browser left running by an earlier run of this server in the same
    container is unreachable -- it holds the profile lock and nothing can close
    it -- and every child of it is waiting to be orphaned. Called once at
    startup. */
export function sweepLeftoverBrowsers(): number {
  let dir = "";
  try {
    dir = profileDir();
  } catch {
    // No profile configured yet: nothing to match on.
  }
  return sweepBrowsers([dir].filter(Boolean));
}

/** Playwright's launch errors carry the whole command line and browser log;
    the first line is the part worth reading. */
function firstLine(err: unknown): string {
  const text = err instanceof Error ? err.message : String(err);
  return text.split("\n")[0].trim();
}

async function acquireContext(): Promise<BrowserContext> {
  if (!shared) {
    if (!launching) {
      launching = launchShared()
        .then((context) => {
          shared = { context, users: 0 };
          return context;
        })
        .finally(() => {
          launching = null;
        });
    }
    await launching;
  }
  if (!shared) throw new Error("The browser closed while it was starting.");
  shared.users += 1;
  return shared.context;
}

async function releaseContext(context: BrowserContext, cookiesSaved = false) {
  if (!shared || shared.context !== context) return;
  shared.users -= 1;
  if (shared.users > 0) return;
  // The last tab is gone: closing the context is what stops Chrome and
  // flushes the profile to disk.
  shared = null;
  if (!cookiesSaved) await saveCookies(context);
  await context.close().catch(() => undefined);
  // The close event handles the happy path; this is for a close that threw
  // and so never fired one.
  if (browserTree.length) retireTree();
}

/** Whether letting go of `context` would stop the browser. */
function lastUser(context: BrowserContext): boolean {
  return shared !== null && shared.context === context && shared.users <= 1;
}

/**
 * Every sign-in the browser holds, kept beside the profile.
 *
 * The profile keeps cookies with an expiry date, but Chrome drops the ones
 * without -- "session" cookies, which is how a good many sites (and parts of
 * Google, LinkedIn and Microsoft sign-in) hold you signed in -- every time it
 * stops, and it stops whenever the last conversation lets go of it. It also
 * writes its cookie store to disk only now and then, so a container that is
 * stopped rather than shut down loses the last sign-in. Both meant being asked
 * to sign in again to something you had signed in to. So every cookie is
 * saved here after each page load and when the browser closes, and on the
 * next start any the profile has lost are put back. Only missing ones: a
 * cookie the profile still has is newer than this copy.
 */
function cookieFile(): string {
  return path.join(path.dirname(stateFilePath()), "browser-cookies.json");
}

async function saveCookies(context: BrowserContext) {
  try {
    const cookies = await context.cookies();
    const file = cookieFile();
    const tmp = `${file}.tmp`;
    fs.writeFileSync(tmp, JSON.stringify(cookies), { mode: 0o600 });
    fs.renameSync(tmp, file);
  } catch {
    // A browser mid-close, or a full disk: the profile still has most of it.
  }
}

async function restoreCookies(context: BrowserContext) {
  let saved: BrowserCookie[];
  try {
    const raw = JSON.parse(fs.readFileSync(cookieFile(), "utf8"));
    saved = Array.isArray(raw) ? raw : [];
  } catch {
    return;
  }
  const now = Date.now() / 1000;
  const key = (c: BrowserCookie) => `${c.name}\u0000${c.domain}\u0000${c.path}`;
  const have = new Set(((await context.cookies().catch(() => [])) as BrowserCookie[]).map(key));
  const missing = saved.filter((c) =>
    c && typeof c.name === "string" && typeof c.domain === "string" &&
    (c.expires === -1 || c.expires > now) && !have.has(key(c)));
  if (missing.length === 0) return;
  try {
    await context.addCookies(missing);
  } catch {
    for (const cookie of missing) await context.addCookies([cookie]).catch(() => undefined);
  }
}

let cookieSave: NodeJS.Timeout | null = null;

/** Save the sign-ins a moment after a page loads: a sign-in ends in a page
    load, and a moment later its cookies are all set. */
function cookiesChanged() {
  if (cookieSave) return;
  cookieSave = setTimeout(() => {
    cookieSave = null;
    if (shared) void saveCookies(shared.context);
  }, 3000);
}

/** One page, one screencast, one session's worth of browsing. */
export class LiveBrowser {
  /** The size this browser captures and renders at. The agent's browser is
      always VIEWPORT; the app preview changes it to show a phone, a tablet or
      a desktop (see resize). */
  private vp: { width: number; height: number } = { ...VIEWPORT };
  private context: BrowserContext | null = null;
  private page: Page | null = null;
  private cdp: CDPSession | null = null;
  private streaming = false;
  private lastFrameAt = 0;
  /** Which of TIERS the screencast runs at, and when it last changed. */
  private tier = 0;
  private tierAt = 0;
  private sharpTimer: NodeJS.Timeout | null = null;
  private sharpBusy = false;
  /** Until when a person is working the page (a tap, a scroll): frames come
      faster and rougher, then one sharp one when they stop. */
  private activeUntil = 0;
  /** The newest frame that arrived too soon after the last one sent. It goes
      out when the interval is up, so the feed always ends on the page as it
      finally is rather than one step before it. */
  private pendingFrame: string | null = null;
  private flushTimer: NodeJS.Timeout | null = null;
  /** Where the mouse is, so the next move starts from here rather than
      appearing out of nowhere. */
  private pointer: Point = {
    x: Math.round(this.vp.width * (0.3 + Math.random() * 0.4)),
    y: Math.round(this.vp.height * (0.3 + Math.random() * 0.4)),
  };
  private refs: Ref[] = [];
  private closing = false;
  /** A new tab's address being followed into this one. */
  private following: Promise<void> | null = null;
  /** The page as the agent was last shown it, so that an action can be told
      to have changed nothing. See sigOf. */
  private lastSig = "";
  /** The click held back because something covered its target. Asking for the
      same one again, on the same page, means it. */
  private heldClick: { ref: number; url: string } | null = null;
  private control: { holder: "agent" | "human" | "shared"; reason: string | null } = {
    holder: "agent",
    reason: null,
  };
  /** Serialises actions: two clicks racing on one page is a bug report that
      is impossible to read afterwards. */
  private queue: Promise<unknown> = Promise.resolve();

  constructor(
    private hooks: BrowserHooks,
    /** The app preview's differences from the agent's browser: its own size,
        and a sharper, wider stream, because it is for looking at a design. */
    private opts: { viewport?: { width: number; height: number }; fps?: number; quality?: number; sharp?: boolean } = {},
  ) {
    if (opts.viewport) this.vp = { ...opts.viewport };
    /* Whatever the browser says it is doing is also said, in a few words, beside its pointer in the page. */
    const said = hooks.onAction;
    this.hooks = { ...hooks, onAction: (action, at, url) => { said(action, at, url); void this.think(action); } };
  }

  /** The words beside the pointer for `action` (see src/lib/thought.ts); nothing for an act with nothing to say. */
  /** The call that tells the page whose pointer it draws (empty for Autora's own). */
  private signature(): string {
    const w = this.hooks.who?.();
    return w ? `if (window.__autoraWho) window.__autoraWho(${JSON.stringify(w.name)}, ${JSON.stringify(w.color)}, ${JSON.stringify(w.rgb)}, ${Number(w.sides) || 3});` : "";
  }

  private async think(action: string): Promise<void> {
    // The person's own act ("you clicked ...") is theirs, and is never said beside Autora's pointer.
    if (action.startsWith("you ") || !this.visible()) return;
    const words = thoughtFromAction(action);
    if (!words) return;
    await this.page?.evaluate(
      `(() => { if (window.__autoraCursorMount) window.__autoraCursorMount(); ${this.signature()} if (window.__autoraHand) window.__autoraHand("agent"); if (window.__autoraThought) window.__autoraThought(${JSON.stringify(words)}); })()`,
    ).catch(() => undefined);
  }

  /** Whether the agent's work is shown as it is done (see LiveBrowserHooks.visible). */
  private visible(): boolean {
    return this.hooks.visible?.() ?? true;
  }

  /** When the page was last told the person's hand is on it. */
  private youAt = 0;

  /** The person is using the page: their input is drawn as theirs, not as Autora's pointer (see __autoraHand in
      CURSOR_SCRIPT). Said at most once a second, since it lapses on its own. */
  private async personHand(): Promise<void> {
    if (Date.now() - this.youAt < 1000) return;
    this.youAt = Date.now();
    await this.page?.evaluate(`(() => { if (window.__autoraHand) window.__autoraHand("you"); })()`).catch(() => undefined);
  }

  // ------------------------------------------------------------- lifecycle --

  status(): BrowserStatus {
    return {
      available: probed?.ok ?? false,
      open: !!this.page,
      url: this.page ? (this.currentUrl ?? null) : null,
      title: this.currentTitle,
      detail: probed?.detail ?? null,
      fps: this.streaming ? this.opts.fps ?? LIVE_FPS : 0,
      viewport: this.vp,
      control: this.control,
      fields: this.page ? this.fields : [],
      tabs: this.tabList(),
    };
  }

  // ----------------------------------------------------------------- tabs --

  /** The pages this session has open, in the order they were opened. */
  private tabPages: Page[] = [];
  private tabIds = new WeakMap<object, number>();
  private tabNumber = 0;
  private tabInfo = new WeakMap<object, { url: string; title: string }>();
  /** Set while a tab is being closed on purpose, so that closing the last
      one leaves a blank tab rather than letting go of the browser. */
  private closingTab = false;

  private addTab(page: Page) {
    if (this.tabPages.includes(page)) return;
    this.tabIds.set(page, ++this.tabNumber);
    this.tabPages.push(page);
    // A tab left open in the background by a page that opens many is the
    // oldest idle one to go, never the one being watched or its opener.
    while (this.tabPages.length > MAX_TABS) {
      const old = this.tabPages.find((p) => p !== this.page && p !== page && !this.openers.includes(p));
      if (!old) break;
      void old.close().catch(() => undefined);
      this.tabPages.splice(this.tabPages.indexOf(old), 1);
    }
  }

  tabList(): BrowserTab[] {
    return this.tabPages.filter((p) => !p.isClosed()).map((p) => ({
      id: this.tabIds.get(p) ?? 0,
      url: p === this.page ? (this.currentUrl ?? p.url()) : this.tabInfo.get(p)?.url ?? p.url(),
      title: p === this.page ? (this.currentTitle ?? "") : this.tabInfo.get(p)?.title ?? "",
      active: p === this.page,
    }));
  }

  private tabById(id: number): Page | undefined {
    return this.tabPages.find((p) => this.tabIds.get(p) === id && !p.isClosed());
  }

  /** A new tab, opened and shown; with an address, loaded. */
  newTab(rawUrl?: string): Promise<PageRead | { tabs: BrowserTab[] }> {
    return this.run(async () => {
      await this.ensure();
      const context = this.context;
      if (!context) throw new Error("No browser is open.");
      const page = await context.newPage();
      claimed.add(page);
      this.wire(page);
      this.addTab(page);
      await this.show(page, null, "a new tab");
      if (rawUrl && rawUrl.trim()) {
        const url = addressFor(rawUrl);
        this.hooks.onAction(`open ${url}`, null, url);
        await page.goto(url, { waitUntil: "domcontentloaded", timeout: 30_000 }).catch(() => undefined);
        await this.settle();
        const read = await this.read();
        await this.keyframe();
        return read;
      }
      return { tabs: this.tabList() };
    });
  }

  switchTab(id: number): Promise<{ tabs: BrowserTab[] }> {
    return this.run(async () => {
      const page = this.tabById(id);
      if (!page) throw new Error(`There is no tab ${id}.`);
      if (page !== this.page) await this.show(page, null, "switched tab");
      return { tabs: this.tabList() };
    });
  }

  closeTab(id: number): Promise<{ tabs: BrowserTab[] }> {
    return this.run(async () => {
      const page = this.tabById(id);
      if (!page) throw new Error(`There is no tab ${id}.`);
      /* The last tab is replaced before it is closed: Chrome ends its
         browsing session, and drops the session cookies with it, the moment
         no tab is open. */
      if (this.tabPages.filter((p) => !p.isClosed()).length <= 1 && this.context) {
        const fresh = await this.context.newPage();
        claimed.add(fresh);
        this.wire(fresh);
        this.addTab(fresh);
        await this.show(fresh, null, "a new tab");
      }
      this.closingTab = true;
      try {
        await page.close().catch(() => undefined);
        // The page's own close handler picks the tab to show next.
        await this.following?.catch(() => undefined);
      } finally {
        this.closingTab = false;
      }
      return { tabs: this.tabList() };
    });
  }

  /** Find text on the page and select it, the way a browser's find bar
      does; the next call with the same text goes on to the next match. */
  find(text: string, backwards = false): Promise<boolean> {
    return this.run(async () => {
      const page = this.page;
      if (!page || !text) return false;
      // The browser's own window.find reports nothing in a headless page, so
      // the matches are walked here: the text nodes, case-insensitively, the
      // current one remembered so Next goes on from it.
      return !!(await page.evaluate(`(() => {
        const q = ${JSON.stringify(text.toLowerCase())};
        const back = ${backwards ? "true" : "false"};
        const hits = [];
        const walker = document.createTreeWalker(document.body, NodeFilter.SHOW_TEXT);
        for (let n = walker.nextNode(); n; n = walker.nextNode()) {
          const parent = n.parentElement;
          if (!parent || /^(SCRIPT|STYLE|NOSCRIPT)$/.test(parent.tagName)) continue;
          const hay = n.nodeValue.toLowerCase();
          for (let i = hay.indexOf(q); i >= 0; i = hay.indexOf(q, i + q.length)) hits.push([n, i]);
        }
        if (!hits.length) return false;
        const state = window.__autoraFind;
        let at = state && state.q === q ? state.at + (back ? -1 : 1) : (back ? hits.length - 1 : 0);
        at = (at + hits.length) % hits.length;
        window.__autoraFind = { q, at };
        const [node, i] = hits[at];
        const range = document.createRange();
        range.setStart(node, i);
        range.setEnd(node, i + q.length);
        const sel = getSelection();
        sel.removeAllRanges();
        sel.addRange(range);
        node.parentElement.scrollIntoView({ block: "center", inline: "nearest" });
        return true;
      })()`).catch(() => false));
    });
  }

  /** Forward in this tab's history. */
  goForward(): Promise<PageRead | null> {
    return this.run(async () => {
      const page = await this.ensure();
      this.hooks.onAction("navigated forward", null, this.currentUrl ?? "");
      await page.goForward({ waitUntil: "domcontentloaded", timeout: 15_000 }).catch(() => undefined);
      await this.settle();
      const read = await this.read();
      await this.keyframe();
      return read;
    });
  }

  getControl() {
    return this.control;
  }

  setControl(holder: "agent" | "human" | "shared", reason: string | null = null) {
    this.control = { holder, reason: reason ?? null };
  }

  private currentUrl: string | null = null;
  private currentTitle: string | null = null;

  /**
   * Start Chrome, if it is not already running.
   *
   * A persistent profile rather than a fresh one each time, because the
   * alternative is signing in to everything again on every restart -- and an
   * agent that cannot stay signed in to your mail is an agent that cannot
   * read your mail. The profile lives beside the settings file, which in the
   * container is the one directory that survives an update.
   *
   * Headed when asked: on a desktop that means a real window you can watch
   * beside the app, which is sometimes exactly what someone wants and costs
   * nothing to allow.
   */
  private async ensure(): Promise<Page> {
    if (this.page) return this.page;

    const { ok, detail } = await probeBrowser();
    if (!ok) throw new Error(detail ?? "No browser available.");

    const context = await acquireContext();
    this.context = context;
    // Chrome opens with a tab already in it; the first session to arrive
    // takes that one rather than leaving an orphan about:blank behind.
    const idle = context.pages().find((p: Page) => !claimed.has(p));
    try {
      this.page = idle ?? (await context.newPage());
    } catch (err) {
      this.context = null;
      await releaseContext(context);
      throw err;
    }
    claimed.add(this.page);
    this.wire(this.page);
    this.addTab(this.page);
    if (this.vp.width !== VIEWPORT.width || this.vp.height !== VIEWPORT.height) {
      await this.page.setViewportSize(this.vp).catch(() => undefined);
    }
    await this.startStream();
    return this.page;
  }

  /** Windows a sign-in opened, the newest last, over the tab that opened
      them: when one closes the page under it is the one watched again. */
  private openers: Page[] = [];
  private wired = new WeakSet<object>();

  /** The listeners every page this session shows needs, once per page. */
  private wire(page: Page) {
    if (this.wired.has(page)) return;
    this.wired.add(page);

    page.on("popup", (popup: Page) => {
      claimed.add(popup);
      this.wire(popup);
      this.addTab(popup);
      /* A link to a new tab opens one, as in any browser, and it is the tab
         shown; a sign-in window ("Sign in with Google", a bank's 2FA) is the
         same and closes itself when done, returning to the page that opened
         it, which is waiting for its answer. A popup from a tab that is not
         the one watched is kept in the background. */
      if (this.page !== page) return;
      this.following = (async () => {
        if (popup.isClosed()) return;
        await this.show(popup, page, "a new tab opened");
        await popup.waitForLoadState("domcontentloaded", { timeout: 8000 }).catch(() => undefined);
      })().finally(() => { this.following = null; });
    });

    /* What the page says to its own console, for whoever is building it: an
       error the page throws is the first thing a developer looks for, and
       the agent cannot see a console that only the screencast shows. */
    page.on("console", (m: any) => {
      const kind = String(m.type?.() ?? "log");
      const said = String(m.text?.() ?? "");
      this.noteDev(page, { kind: "console", level: kind === "warning" ? "warn" : kind, text: said.slice(0, 600) });
      // Chrome's own line for a failed fetch names no address; the response
      // listener below says which one, and skips the icon every page is
      // asked for and many do not have.
      if (/^Failed to load resource/i.test(said)) return;
      if (kind === "error" || kind === "warning" || kind === "warn") this.noteConsole(kind === "error" ? "error" : "warn", said);
    });
    page.on("download", (download: any) => {
      void (async () => {
        try {
          const tmp = await download.path();
          if (!tmp) return;
          const name = String(download.suggestedFilename?.() ?? "download");
          const url = String(download.url?.() ?? "");
          /* Looked at before it is read: a page can offer a download of any
             size, and reading it whole to find out it is too big is how the
             container runs out of memory. */
          if (fs.statSync(tmp).size > MAX_ARTIFACT_BYTES) {
            this.hooks.onDownload?.({ name, bytes: Buffer.alloc(0), url, error: `Too large: downloads are capped at ${MAX_ARTIFACT_BYTES / 1024 / 1024} MB.` });
            return;
          }
          this.hooks.onDownload?.({ name, bytes: fs.readFileSync(tmp), url });
        } catch {
          // Cancelled or failed; nothing to keep.
        }
      })();
    });
    page.on("pageerror", (err: any) => {
      this.noteDev(page, { kind: "console", level: "error", text: `Uncaught: ${String(err?.message ?? err).slice(0, 600)}` });
      this.noteConsole("error", `Uncaught: ${String(err?.message ?? err)}`);
    });
    const began = new WeakMap<object, number>();
    page.on("request", (req: any) => { began.set(req, Date.now()); });
    page.on("requestfinished", (req: any) => {
      void (async () => {
        const res = await req.response?.().catch(() => null);
        const length = Number(res?.headers?.()["content-length"] ?? 0);
        this.noteDev(page, {
          kind: "request", level: String(req.resourceType?.() ?? "other"), text: String(req.url?.() ?? "").slice(0, 400),
          method: String(req.method?.() ?? "GET"), status: Number(res?.status?.() ?? 0),
          ms: Date.now() - (began.get(req) ?? Date.now()), ...(length ? { bytes: length } : {}),
        });
      })();
    });
    page.on("response", (res: any) => {
      const status = Number(res.status?.() ?? 0);
      const where = String(res.url?.() ?? "");
      // Every page is asked for an icon it may not have; that is not its bug.
      if (status >= 400 && !/\/favicon\.ico(\?|$)/.test(where)) this.noteConsole("error", `${status} ${where.slice(0, 160)}`);
    });
    page.on("requestfailed", (req: any) => {
      this.noteDev(page, {
        kind: "request", level: String(req.resourceType?.() ?? "other"), text: String(req.url?.() ?? "").slice(0, 400),
        method: String(req.method?.() ?? "GET"), failed: String(req.failure?.()?.errorText ?? "failed"),
        ms: Date.now() - (began.get(req) ?? Date.now()),
      });
      this.noteConsole("error", `Request failed: ${String(req.url?.() ?? "").slice(0, 160)} (${String(req.failure?.()?.errorText ?? "")})`);
    });

    page.on("framenavigated", (frame: any) => {
      if (frame !== page.mainFrame()) return;
      const info = this.tabInfo.get(page) ?? { url: "", title: "" };
      info.url = frame.url();
      this.tabInfo.set(page, info);
      if (this.page !== page) { this.hooks.onFields(); return; }
      this.currentUrl = frame.url();
      void this.announceNav();
    });
    page.on("domcontentloaded", () => {
      void page.title().then((title: string) => {
        const info = this.tabInfo.get(page) ?? { url: page.url(), title: "" };
        if (info.title === title) return;
        info.title = title;
        this.tabInfo.set(page, info);
        if (this.page === page) this.currentTitle = title;
        this.hooks.onFields();
      }).catch(() => undefined);
    });
    page.on("close", () => {
      const waiting = this.openers.indexOf(page);
      if (waiting >= 0) this.openers.splice(waiting, 1);
      const at = this.tabPages.indexOf(page);
      if (at >= 0) this.tabPages.splice(at, 1);
      if (this.closing) return;
      if (this.page !== page) { this.hooks.onFields(); return; }
      // The tab being watched closed. A sign-in window that closed itself
      // goes back to the page it opened from, which now has the sign-in;
      // otherwise the tab beside it, or the one before.
      const back = this.openers.pop()
        ?? this.tabPages[Math.min(Math.max(at, 0), this.tabPages.length - 1)];
      if (back && !back.isClosed()) {
        this.following = this.show(back, null, "the tab closed; back to the page").finally(() => { this.following = null; });
        return;
      }
      if (this.closingTab && this.context) {
        // Closing the last tab leaves a blank one, as on a phone.
        const context = this.context;
        this.following = (async () => {
          const fresh = await context.newPage();
          claimed.add(fresh);
          this.wire(fresh);
          this.addTab(fresh);
          await this.show(fresh, null, "a new tab");
        })().catch(() => undefined).finally(() => { this.following = null; });
        return;
      }
      this.page = null;
      this.streaming = false;
      // The tab went on its own (Chrome crashed, or the page closed itself):
      // let go of the browser so it is not held open for nobody.
      const held = this.context;
      this.context = null;
      if (held) void releaseContext(held);
    });
  }

  /**
   * Make `next` the page this session shows and acts on: the screencast
   * moves to it, its elements are the ones numbered, and the person watching
   * sees it and can type into it. `from`, when given, is kept underneath to
   * come back to.
   */
  private async show(next: Page, from: Page | null, why = "a new tab opened") {
    if (from) this.openers.push(from);
    // Switched at once, so whatever reads the page next reads this one.
    const cdp = this.cdp;
    this.cdp = null;
    this.streaming = false;
    this.page = next;
    this.refs = [];
    this.wire(next);
    await cdp?.send("Page.stopScreencast").catch(() => undefined);
    await cdp?.detach().catch(() => undefined);
    await next.setViewportSize(this.vp).catch(() => undefined);
    await next.bringToFront().catch(() => undefined);
    this.currentUrl = next.url();
    this.currentTitle = this.tabInfo.get(next)?.title ?? this.currentTitle;
    this.hooks.onAction(why, null, this.currentUrl ?? "");
    await this.startStream().catch(() => undefined);
    await this.announceNav();
  }

  /** The last nav that was announced, so the several `framenavigated` events
      one navigation produces become the one line they describe. */
  private announced = "";

  private async announceNav() {
    if (!this.page) return;
    const title = await this.page.title().catch(() => "");
    this.currentTitle = title;
    const url = this.currentUrl ?? "";
    const signature = `${url}\u0000${title}`;
    if (signature === this.announced) return;
    this.announced = signature;
    cookiesChanged();
    this.hooks.onNav(url, title);
  }

  /**
   * Chrome's screencast, throttled.
   *
   * Every frame is acknowledged -- Chrome stops sending until it is -- but
   * only every so many are forwarded, and none at all while nobody is
   * watching. That keeps a browsing session at a few hundred kilobytes a
   * second on the wire and near nothing when the tab is closed.
   */
  private async startStream() {
    if (!this.page || !this.context || this.streaming) return;
    const cdp = await this.context.newCDPSession(this.page);
    this.cdp = cdp;
    this.cdp.on("Page.screencastFrame", (frame: any) => {
      // Acknowledged on the session it came from: after a switch to a
      // sign-in window, a late frame of the old page is not the new one's.
      cdp.send("Page.screencastFrameAck", { sessionId: frame.sessionId }).catch(() => undefined);
      if (this.hooks.watchers() === 0 || this.cdp !== cdp) return;
      this.forward(frame.data);
    });
    await cdp.send("Page.startScreencast", {
      format: "jpeg",
      quality: this.opts.quality ?? TIERS[this.tier].quality,
      maxWidth: this.opts.sharp ? Math.max(LIVE_WIDTH, this.vp.width) : TIERS[this.tier].width,
      maxHeight: this.opts.sharp
        ? Math.max(Math.round((LIVE_WIDTH / this.vp.width) * this.vp.height), this.vp.height)
        : Math.round((TIERS[this.tier].width / this.vp.width) * this.vp.height),
      everyNthFrame: 1,
    });
    this.streaming = true;
  }

  /** Someone is working the page: raise the frame rate for a moment. */
  touched() {
    this.activeUntil = Date.now() + 1800;
  }

  /** Step the screencast down a tier when a viewer is backing up, and back
      up when the link has been clear for a while. Rare, and never twice
      within three seconds: restarting the screencast costs a frame. */
  private adapt() {
    if (this.opts.sharp || !this.hooks.backlog || Date.now() - this.tierAt < 3000) return;
    const behind = this.hooks.backlog();
    let next = this.tier;
    if (behind > 256 * 1024 && this.tier < TIERS.length - 1) next = this.tier + 1;
    else if (behind < 16 * 1024 && this.tier > 0 && Date.now() - this.tierAt > 8000) next = this.tier - 1;
    if (next === this.tier) return;
    this.tier = next;
    this.tierAt = Date.now();
    const cdp = this.cdp;
    this.cdp = null;
    this.streaming = false;
    void (async () => {
      await cdp?.send("Page.stopScreencast").catch(() => undefined);
      await cdp?.detach().catch(() => undefined);
      await this.startStream().catch(() => undefined);
    })();
  }

  /** One crisp frame once the page has been still for a moment. Skipped
      while a viewer is behind: sharp is for a link that can afford it. */
  private armSharp() {
    if (this.opts.sharp) return;
    if (this.sharpTimer) clearTimeout(this.sharpTimer);
    this.sharpTimer = setTimeout(() => {
      this.sharpTimer = null;
      void this.sharpFrame();
    }, SHARP_AFTER_MS);
    this.sharpTimer.unref?.();
  }

  private async sharpFrame() {
    if (!this.page || this.sharpBusy || this.hooks.watchers() === 0) return;
    if (Date.now() - this.lastFrameAt < SHARP_AFTER_MS - 50) return;
    if ((this.hooks.backlog?.() ?? 0) > 32 * 1024) return;
    this.sharpBusy = true;
    try {
      const shot: Buffer = await this.page.screenshot({ type: "jpeg", quality: 82, scale: "css", timeout: 3000 });
      this.hooks.onFrame(shot.toString("base64"));
    } catch {
      // Mid-navigation; the next frame covers it.
    } finally {
      this.sharpBusy = false;
    }
  }

  /** Throttle with a trailing edge: a burst of frames is thinned to the
      frame rate, and the last one of the burst is always delivered. Dropping
      it left the feed parked on the page mid-change until something else
      happened to move. */
  private forward(data: string) {
    const rate = this.opts.fps ?? (Date.now() < this.activeUntil ? Math.min(LIVE_FPS * 2, 24) : LIVE_FPS);
    const wait = 1000 / rate - (Date.now() - this.lastFrameAt);
    if (wait <= 0) {
      this.lastFrameAt = Date.now();
      this.pendingFrame = null;
      this.adapt();
      // A viewer that is behind gets nothing new until it has caught up.
      if ((this.hooks.backlog?.() ?? 0) > 1024 * 1024) { this.armSharp(); return; }
      this.hooks.onFrame(data);
      this.armSharp();
      return;
    }
    this.pendingFrame = data;
    if (this.flushTimer) return;
    this.flushTimer = setTimeout(() => {
      this.flushTimer = null;
      const next = this.pendingFrame;
      if (next && this.hooks.watchers() > 0) this.forward(next);
    }, wait);
    this.flushTimer.unref?.();
  }

  /**
   * Send one frame right now, whether or not the page has moved.
   *
   * Chrome's screencast is change-driven: a page that is sitting still emits
   * nothing, which is the right behaviour for a video codec and the wrong one
   * for someone who has just opened the app. Without this, joining a session
   * whose browser is parked on a static page shows the last *stored*
   * screenshot and calls it live -- or shows nothing and waits for the page to
   * happen to move.
   */
  async nudge() {
    if (!this.page || this.hooks.watchers() === 0) return;
    try {
      const shot: Buffer = await this.page.screenshot({
        type: "jpeg",
        quality: this.opts.quality ?? LIVE_QUALITY,
        scale: "css",
      });
      this.hooks.onFrame(shot.toString("base64"));
    } catch {
      // Mid-navigation. The next real frame is a moment away.
    }
  }

  // ------------------------------------------------ app preview (see preview.ts) --

  /** Everything the pages said and asked for, newest last: DevTools' console
      and network panels, for the person and for the agent. */
  private dev: DevEntry[] = [];
  private devCount = 0;
  private noteDev(page: Page, entry: Omit<DevEntry, "n" | "tab" | "ts">) {
    this.dev.push({ n: ++this.devCount, tab: this.tabIds.get(page) ?? 0, ts: Date.now(), ...entry });
    if (this.dev.length > 400) this.dev.splice(0, this.dev.length - 400);
  }
  devtools(opts: { kind?: "console" | "request"; tab?: number; since?: number; errorsOnly?: boolean; limit?: number } = {}): DevEntry[] {
    const tab = opts.tab ?? (this.page ? this.tabIds.get(this.page) : undefined);
    return this.dev
      .filter((e) => (!opts.kind || e.kind === opts.kind) && (tab === undefined || e.tab === tab) && e.n > (opts.since ?? 0))
      .filter((e) => !opts.errorsOnly || e.failed || (e.kind === "console" && e.level === "error") || (e.status ?? 0) >= 400)
      .slice(-(opts.limit ?? 200));
  }
  clearDevtools() { this.dev = []; }

  /** The page's own console, newest last. */
  private consoleLog: Array<{ kind: "error" | "warn"; text: string; ts: number }> = [];
  private noteConsole(kind: "error" | "warn", text: string) {
    const line = text.replace(/\s+/g, " ").trim().slice(0, 400);
    if (!line) return;
    const last = this.consoleLog[this.consoleLog.length - 1];
    if (last && last.text === line && last.kind === kind) return;
    this.consoleLog.push({ kind, text: line, ts: Date.now() });
    if (this.consoleLog.length > 60) this.consoleLog.splice(0, this.consoleLog.length - 60);
    this.hooks.onConsole?.();
  }
  consoleTail(n = 20): Array<{ kind: "error" | "warn"; text: string; ts: number }> {
    return this.consoleLog.slice(-n);
  }
  clearConsole() { this.consoleLog = []; }

  /** The size of the window the page is rendered in. */
  viewport() { return { ...this.vp }; }

  /**
   * Render at another size -- a phone, a tablet, a desktop -- and carry on
   * streaming at it. The page re-lays itself out as it would on that screen.
   */
  resize(width: number, height: number): Promise<{ width: number; height: number }> {
    return this.run(async () => {
      const w = Math.max(240, Math.min(2560, Math.round(width)));
      const h = Math.max(240, Math.min(2560, Math.round(height)));
      this.vp = { width: w, height: h };
      this.pointer = { x: Math.round(w / 2), y: Math.round(h / 2) };
      if (this.page) {
        await this.page.setViewportSize(this.vp).catch(() => undefined);
        const cdp = this.cdp;
        this.cdp = null;
        this.streaming = false;
        await cdp?.send("Page.stopScreencast").catch(() => undefined);
        await cdp?.detach().catch(() => undefined);
        await this.startStream().catch(() => undefined);
        // The page re-laid itself out: its fields moved with it.
        await this.mapFields();
      }
      return { ...this.vp };
    });
  }

  /** Run one of the picker's operations in the page (see pick.ts). */
  pickOp(expression: string): Promise<any> {
    return this.run(async () => {
      const page = this.page;
      if (!page) return { ok: false, error: "No page is open." };
      // A page stuck in its own script would otherwise hold every later input behind this one.
      let timer: NodeJS.Timeout | undefined;
      const late = new Promise((resolve) => {
        timer = setTimeout(() => resolve({ ok: false, error: "The page is not responding." }), 4000);
      });
      try {
        return await Promise.race([page.evaluate(expression), late]);
      } finally {
        clearTimeout(timer);
      }
    });
  }

  /** The page as a list two looks can be compared by (server/domdiff.ts), or
      null when there is no page to look at. */
  domMap(): Promise<DomItem[] | null> {
    return this.run(async () => {
      const page = this.page;
      if (!page || page.isClosed()) return null;
      try {
        return (await Promise.race([
          page.evaluate(DOM_MAP_SCRIPT),
          new Promise((resolve) => setTimeout(() => resolve(null), 3000)),
        ])) as DomItem[] | null;
      } catch {
        return null;
      }
    });
  }

  /**
   * The pointer glides to a place and outlines it with a name, so a change to
   * the page is seen being found. Real mouse movement, so the dot in the page
   * follows every step of it, and a click is never sent.
   */
  async markAt(x: number, y: number, w: number, h: number, label: string): Promise<void> {
    if (!(await this.glideTo(x + Math.min(w, 28), y + h * 0.6))) return;
    await this.run(async () => {
      await this.page
        ?.evaluate(
          `(() => { if (window.__autoraCursorMount) window.__autoraCursorMount();
             if (window.__autoraMark) window.__autoraMark(${Math.round(x)}, ${Math.round(y)}, ${Math.round(w)}, ${Math.round(h)}, ${JSON.stringify(label)}); })()`,
        )
        .catch(() => undefined);
    });
  }

  /** The pointer travels to a place in real mouse movements, so the dot in the
      page is seen going there. False if the page went away on the way. */
  async glideTo(x: number, y: number): Promise<boolean> {
    const from = { ...this.pointer };
    const to = { x: Math.max(0, Math.min(this.vp.width, Math.round(x))), y: Math.max(0, Math.min(this.vp.height, Math.round(y))) };
    const steps = 14;
    for (let i = 1; i <= steps; i += 1) {
      // Eased: quick away from where it was, slow arriving.
      const t = 1 - (1 - i / steps) ** 3;
      const px = Math.round(from.x + (to.x - from.x) * t), py = Math.round(from.y + (to.y - from.y) * t);
      const moved = await this.run(async () => {
        const page = this.page;
        if (!page || page.isClosed()) return false;
        await page.mouse.move(px, py).catch(() => undefined);
        this.pointer = { x: px, y: py };
        return true;
      });
      if (!moved) return false;
      await new Promise((resolve) => setTimeout(resolve, 22));
    }
    return true;
  }

  /** Where the thing the agent means is on the page (scrolled into view), or
      what there is to choose from. See FIND_SCRIPT. */
  findTarget(target: string): Promise<
    | { ok: true; x: number; y: number; w: number; h: number; tag: string; label: string; count: number }
    | { ok: false; error: string; options: string[] }
  > {
    return this.run(async () => {
      const page = await this.ensure();
      try {
        return (await page.evaluate(FIND_SCRIPT(target))) as never;
      } catch (err) {
        return { ok: false as const, error: `Could not look for it: ${(err as Error).message.split("\n")[0]}`, options: [] };
      }
    });
  }

  /** Typing at a person's pace, so it is watched happening; long text is faster. */
  typeText(text: string): Promise<void> {
    return this.run(async () => {
      const page = await this.ensure();
      await page.keyboard.type(text, { delay: Math.max(4, Math.min(60, Math.floor(1400 / Math.max(1, text.length)))) });
      this.noteTyping(text.length, null);
    });
  }

  /** A picture of an element, or of a rectangle of the window. */
  cropShot(target: { selector: string } | { x: number; y: number; w: number; h: number }): Promise<Buffer | null> {
    return this.run(async () => {
      const page = this.page;
      if (!page) return null;
      try {
        if ("selector" in target) {
          return (await page.locator(target.selector).first().screenshot({ type: "png", timeout: 4000 })) as Buffer;
        }
        const x = Math.max(0, Math.min(this.vp.width - 2, Math.round(target.x)));
        const y = Math.max(0, Math.min(this.vp.height - 2, Math.round(target.y)));
        const width = Math.max(2, Math.min(this.vp.width - x, Math.round(target.w)));
        const height = Math.max(2, Math.min(this.vp.height - y, Math.round(target.h)));
        return (await page.screenshot({ type: "png", clip: { x, y, width, height } })) as Buffer;
      } catch {
        return null;
      }
    });
  }

  async close() {
    this.closing = true;
    // This session's tab, and its hold on the shared browser. The browser
    // itself stops when the last session lets go.
    const context = this.context;
    const page = this.page;
    const cdp = this.cdp;
    this.page = null;
    this.context = null;
    this.cdp = null;
    this.streaming = false;
    if (this.flushTimer) clearTimeout(this.flushTimer);
    this.flushTimer = null;
    this.pendingFrame = null;
    this.announced = "";
    this.currentUrl = null;
    this.currentTitle = null;
    this.refs = [];
    this.fields = [];
    if (this.typed.timer) clearTimeout(this.typed.timer);
    this.typed = { chars: 0, keys: [], timer: null };
    const openers = this.openers;
    this.openers = [];
    /* The sign-ins are saved while the tab is still open. Chrome launched
       without --enable-automation (see launchShared) ends its browsing
       session when the last tab closes, and newer Chrome drops session
       cookies right then, so saving after the tab closed saved none. */
    const saved = context !== null && lastUser(context);
    if (saved) await saveCookies(context);
    await cdp?.detach().catch(() => undefined);
    await page?.close().catch(() => undefined);
    for (const under of openers) await under.close().catch(() => undefined);
    const others = this.tabPages.filter((p) => p !== page);
    this.tabPages = [];
    for (const other of others) await other.close().catch(() => undefined);
    if (context) await releaseContext(context, saved);
    this.closing = false;
  }

  // ---------------------------------------------------------------- acting --

  /** One at a time, in the order asked. */
  private run<T>(job: () => Promise<T>): Promise<T> {
    const next = this.queue.then(job, job);
    this.queue = next.catch(() => undefined);
    return next;
  }

  /** A frame worth keeping: taken after the page has settled, so the log
      shows the result of an action rather than the middle of it. */
  private async keyframe() {
    if (!this.page || this.closing) return;
    try {
      const shot: Buffer = await this.page.screenshot({ type: "jpeg", quality: 70 });
      this.hooks.onKeyframe(shot, this.currentUrl ?? "", this.currentTitle ?? "");
    } catch {
      // A page that navigated out from under the shot is not an error worth
      // reporting; the next action takes another one.
    }
    await this.mapFields();
  }

  /** Last known typeable fields, for `status()`. */
  private fields: Array<[number, number, number, number]> = [];

  /** Find the fields you can type into, and tell the watchers if they moved.
      Taken alongside every kept frame, which is after every action. */
  private async mapFields() {
    if (!this.page || this.closing) return;
    // A string, because this file is compiled without the DOM's types.
    const found: Array<[number, number, number, number]> = await this.page
      .evaluate(`(() => {
        const skip = ["button", "submit", "reset", "checkbox", "radio", "range",
          "color", "file", "image", "hidden"];
        const out = [];
        const vw = window.innerWidth, vh = window.innerHeight;
        for (const el of document.querySelectorAll("input, textarea, [contenteditable], iframe")) {
          if (el.tagName === "INPUT" && skip.includes((el.type || "text").toLowerCase())) continue;
          if (el.hasAttribute("contenteditable") && !el.isContentEditable) continue;
          if (el.disabled || el.readOnly) continue;
          const r = el.getBoundingClientRect();
          if (r.width < 2 || r.height < 2) continue;
          if (r.bottom < 0 || r.right < 0 || r.top > vh || r.left > vw) continue;
          const style = getComputedStyle(el);
          if (style.visibility === "hidden" || style.display === "none") continue;
          out.push([Math.round(r.left), Math.round(r.top), Math.round(r.width), Math.round(r.height)]);
          if (out.length >= 400) break;
        }
        return out;
      })()`)
      .catch(() => null);
    if (!found) return;
    if (JSON.stringify(found) === JSON.stringify(this.fields)) return;
    this.fields = found;
    this.hooks.onFields();
  }

  /** Let whatever the action started finish painting before we photograph it.
      Short, because this sits in front of every action and a browser that
      feels like a slideshow is worse than one frame early. */
  private async settle(ms = 450) {
    await this.page?.waitForTimeout?.(ms).catch(() => undefined);
  }

  goto(rawUrl: string): Promise<PageRead> {
    return this.run(async () => {
      const page = await this.ensure();
      const url = addressFor(rawUrl);
      this.heldClick = null;
      this.hooks.onAction(`open ${url}`, null, url);
      await page.goto(url, { waitUntil: "domcontentloaded", timeout: 30_000 });
      await this.settle();
      // A page that draws itself with script is a blank one at this point:
      // give the network a moment, then give an empty page time to fill.
      await page.waitForLoadState("networkidle", { timeout: 2500 }).catch(() => undefined);
      await this.awaitContent(4500);
      const read = await this.read();
      await this.keyframe();
      return read;
    });
  }

  back(): Promise<PageRead> {
    return this.run(async () => {
      const page = await this.ensure();
      this.heldClick = null;
      this.hooks.onAction("back", null, this.currentUrl ?? "");
      await page.goBack({ waitUntil: "domcontentloaded" }).catch(() => undefined);
      await this.settle();
      await this.awaitContent(3000);
      const read = await this.read();
      await this.keyframe();
      return read;
    });
  }

  /**
   * Click the numbered thing, visibly.
   *
   * The pointer is drawn travelling to the target and a ring is played where
   * it lands, then the click is dispatched as a real mouse event at those
   * coordinates. The drawing is for the person watching; the event is the
   * actual click, at the actual place, so what the recording shows and what
   * the page received are the same thing.
   */
  click(ref: number): Promise<PageRead> {
    return this.run(async () => {
      await this.ensure();
      const target = this.refs.find((r) => r.ref === ref);
      if (!target) throw new Error(`No element [${ref}] on this page. Read it again.`);
      const before = this.lastSig;

      /* Where a mouse would land, checked before it does: a cookie bar or a
         pop-up over the element takes the click and the page does nothing the
         agent can see. A sticky header is cleared by centring the element; a
         real cover is named, and the click waits to be asked for again. */
      let box = await this.aim(target);
      let cover = await this.coverAt(ref);
      if (cover) {
        cover = await this.coverAt(ref, true);
        box = await this.aim(target);
      }
      const at = this.currentUrl ?? "";
      const held = this.heldClick;
      const meant = !!held && held.ref === ref && held.url === at;
      if (cover && !meant) {
        this.heldClick = { ref, url: at };
        const read = await this.read();
        const close = (target.coverRefs ?? []).map((k) => {
          const c = this.refs.find((x) => x.ref === k);
          return c ? `[${k}] ${JSON.stringify(c.name)}` : `[${k}]`;
        });
        read.notes = [
          `NOT CLICKED: [${ref}]${target.name ? ` "${target.name}"` : ""} is covered by "${cover.label}", ` +
            "so the click would have landed on that instead." +
            (close.length ? ` Dismiss it first with ${close.join(" or ")}.` : " Dismiss it first (its own button, or Escape).") +
            ` If you do want this click as it is, click [${ref}] again.`,
        ];
        return read;
      }
      this.heldClick = null;

      // Said before the pointer sets off, so the caption on the feed names
      // what it is heading for while you watch it travel there.
      this.hooks.onAction(
        `click [${ref}] ${target.role} "${target.name}"`.trim(),
        { x: target.x, y: target.y },
        at,
      );
      await this.humanClickAt(pointIn(box));
      await this.settle(700);
      await this.arrive();
      /* The page answers late as often as not: a search that fetches, a menu
         that animates open. Reading it the moment the click returned showed
         the page as it had been, which looked like a click that did nothing. */
      const changed = await this.awaitChange(before, 2200);
      await this.awaitContent(3500);
      const read = await this.read();
      if (!changed) {
        read.notes = [
          `Nothing on the page changed after this click (waited about 2 seconds). [${ref}] may not do ` +
            "anything, or the click did not take. Try a different element, press Enter with it focused " +
            "(browser_press), or browser_eval with __autora.click(__autora.byText(\"its words\")).",
        ];
      }
      await this.keyframe();
      return read;
    });
  }

  /**
   * What would be hit by a click on the numbered element, as it is now:
   * nothing in the way (null), or what is. `recenter` scrolls it to the middle
   * of the screen first, which is all a sticky header needs.
   */
  private async coverAt(ref: number, recenter = false): Promise<{ label: string } | null> {
    const page = this.page;
    if (!page) return null;
    const hit = await page.evaluate(`(() => {
      ${COVER_FN}
      const el = (window.__autoraRefs || [])[${Number(ref)}];
      if (!el || !el.isConnected) return null;
      if (${recenter ? "true" : "false"}) el.scrollIntoView({ block: "center", inline: "center" });
      const b = el.getBoundingClientRect();
      if (b.width < 1 || b.height < 1) return null;
      const hit = coverOf(el, b.left + b.width / 2, b.top + b.height / 2);
      return hit ? { label: hit.label } : null;
    })()`).catch(() => null);
    return hit && typeof (hit as { label?: unknown }).label === "string" ? (hit as { label: string }) : null;
  }

  /** The page in a form that changes when anything the agent could see does:
      where it is, what is on screen, how far down, and the text. */
  private sigOf(s: { url: string; title: string; refs: Ref[]; text: string; scroll?: ScrollState }): string {
    const text = String(s.text ?? "");
    return [
      s.url, s.title, s.scroll ? s.scroll.y : "",
      s.refs.filter((r) => r.inView !== false).map(refLine).join("\n"),
      text.length, text.slice(0, 160), text.slice(-160),
    ].join("\u0000");
  }

  /** The page as it is right now -- just enough to compare, without the rest
      of a read. Null while it is in the middle of navigating away. */
  private async peek(): Promise<{ sig: string; shown: number; text: string } | null> {
    const page = this.page;
    if (!page) return null;
    try {
      const s = await page.evaluate(SCAN_SCRIPT);
      return { sig: this.sigOf(s), shown: s.refs.filter((r: Ref) => r.inView).length, text: String(s.text ?? "") };
    } catch {
      return null;
    }
  }

  /** Wait, up to a limit, for the page to differ from what the agent last
      saw. True as soon as it does -- or is mid-navigation, which is a change. */
  private async awaitChange(before: string, maxMs: number): Promise<boolean> {
    const page = this.page;
    if (!page) return true;
    const until = Date.now() + maxMs;
    for (;;) {
      const now = await this.peek();
      if (!now || now.sig !== before) return true;
      if (Date.now() >= until) return false;
      await page.waitForTimeout(300).catch(() => undefined);
    }
  }

  /** A page with nothing on it, or only "Loading...", is one that has not
      drawn yet: wait for it, up to a limit, before it is read as empty. */
  private async awaitContent(maxMs: number) {
    const page = this.page;
    if (!page) return;
    const until = Date.now() + maxMs;
    for (;;) {
      const now = await this.peek();
      if (!now) return;
      const words = now.text.trim();
      const bare = now.shown === 0 && words.length < 200;
      const loading = words.length < 200 && /^\W*(loading|please wait|one moment)\b/i.test(words);
      if (!bare && !loading) return;
      if (Date.now() >= until) return;
      await page.waitForTimeout(400).catch(() => undefined);
    }
  }

  /**
   * Whatever a click or a key started, finished: a navigation (or the new
   * tab a link opened, which is followed in this one) given the moment it
   * needs to show its content, so the page read next is the page arrived at
   * rather than the one being left.
   */
  private async arrive() {
    const page = this.page;
    if (!page) return;
    if (this.following) await this.following.catch(() => undefined);
    await page.waitForLoadState("domcontentloaded", { timeout: 8000 }).catch(() => undefined);
  }

  /**
   * Fill fields by number, then optionally submit. A form is one round trip
   * rather than one per field, which is the difference between an agent that
   * fills in a login and one that spends six turns on it.
   *
   * "Fill" means whatever setting that field takes: typing into a box,
   * choosing a dropdown's option by its text, ticking or clearing a checkbox,
   * setting a date. Each field is read back afterwards and what it now holds
   * is reported, so a phone box that reformatted the number, a dropdown with
   * no such choice or a field the page rejected is seen at once rather than
   * three steps later.
   */
  fill(values: { ref: number; text: string }[], submit = false): Promise<PageRead> {
    return this.run(async () => {
      const page = await this.ensure();
      const notes: string[] = [];
      let lastKind = "text";
      for (const { ref, text } of values) {
        const target = this.refs.find((r) => r.ref === ref);
        if (!target) throw new Error(`No field [${ref}] on this page. Read it again.`);
        const kind: string = await page.evaluate(`(() => {
          const el0 = (window.__autoraRefs || [])[${Number(ref)}];
          if (!el0 || !el0.isConnected) return "gone";
          const el = el0.tagName === "LABEL" && el0.control ? el0.control : el0;
          if (el.tagName === "SELECT") return "select";
          const role = (el.getAttribute("role") || "").toLowerCase();
          const type = el.tagName === "INPUT" ? (el.type || "text").toLowerCase() : "";
          if (type === "checkbox" || role === "checkbox" || role === "switch" || role === "menuitemcheckbox") return "check";
          if (type === "radio" || role === "radio" || role === "menuitemradio") return "radio";
          if (type === "file") return "file";
          if (/^(date|time|month|week|datetime-local|color|range)$/.test(type)) return "native:" + type;
          return "text";
        })()`).catch(() => "gone");
        lastKind = kind;
        this.hooks.onAction(
          `fill [${ref}] "${target.name}"`,
          { x: target.x, y: target.y },
          this.currentUrl ?? "",
        );
        const label = `[${ref}]${target.name ? ` "${target.name}"` : ""}`;

        if (kind === "gone") {
          notes.push(`${label}: no longer on the page; read it again.`);
          continue;
        }
        if (kind === "file") {
          notes.push(`${label}: a file upload. Put a file in it with browser_upload and the file's artifact id.`);
          continue;
        }
        if (kind === "select") {
          const picked = await page.evaluate(SELECT_SCRIPT(ref, text)).catch(() => null);
          if (!picked?.ok) {
            const list = (picked?.options ?? []).slice(0, 30).map((o: string) => JSON.stringify(o)).join(", ");
            notes.push(`${label}: no option matches ${JSON.stringify(text)}. Its options: ${list || "(none)"}.`);
          } else {
            notes.push(`${label}: chose ${JSON.stringify(picked.chosen)}.`);
          }
          continue;
        }
        if (kind === "check" || kind === "radio") {
          const want = kind === "radio" || !/^(false|no|off|0|uncheck(ed)?|unticked?|clear(ed)?|unselect(ed)?|none)$/i.test(text.trim());
          const now = await this.checkedState(ref);
          if (now !== want) {
            await this.humanClickAt(pointIn(await this.aim(target)));
            await this.settle(200);
          }
          const after = await this.checkedState(ref);
          notes.push(`${label}: ${after === null ? "clicked" : after ? "checked" : "not checked"}${
            after !== null && after !== want ? " -- it did not take; look at the page" : ""}.`);
          continue;
        }
        if (kind.startsWith("native:")) {
          const value = normaliseNative(kind.slice(7), text);
          const held = await page.evaluate(SET_VALUE_SCRIPT(ref, value)).catch(() => null);
          notes.push(`${label}: ${held === value ? `set to ${JSON.stringify(value)}` : `wanted ${JSON.stringify(value)}, holds ${JSON.stringify(held ?? "")}`}.`);
          continue;
        }

        await this.humanClickAt(pointIn(await this.aim(target)));
        /* What is already in the field is selected so the typing replaces
           it -- selected by the field itself rather than with Ctrl+A, which
           on a click that did not land in the box selected the whole page. */
        await page.evaluate(SELECT_FIELD_SCRIPT(ref)).catch(() => undefined);
        // A person's typing rhythm for whoever is watching; nobody watching,
        // it is typed straight in.
        if (this.hooks.watchers() > 0 && this.visible()) await humanType(page, text, () => this.touched());
        else await page.keyboard.type(text);
        let held = await this.valueOf(ref);
        /* A field that swallowed the typing (a script that rebuilds it on
           focus, an input that ignores synthetic keys) gets its value set
           the way the page's own code would see it being set. */
        if (held !== null && !sameValue(held, text)) {
          const set = await page.evaluate(SET_VALUE_SCRIPT(ref, text)).catch(() => null);
          if (typeof set === "string") held = set;
        }
        if (target.role === "password" || held === null) notes.push(`${label}: filled.`);
        else if (sameValue(held, text)) notes.push(`${label}: holds ${JSON.stringify(held)}.`);
        else notes.push(`${label}: typed ${JSON.stringify(text)} but it holds ${JSON.stringify(held)} -- the page reformatted or rejected it.`);
      }
      if (submit) {
        /* Enter submits from a text box. From a dropdown or a checkbox it
           does not, so the form is asked to submit itself, the way its
           submit button would. */
        if (lastKind === "text") {
          await page.keyboard.press("Enter");
        } else {
          const last = values[values.length - 1];
          await page.evaluate(`(() => {
            const el0 = (window.__autoraRefs || [])[${Number(last?.ref)}];
            const el = el0 && el0.tagName === "LABEL" && el0.control ? el0.control : el0;
            const form = el && (el.form || el.closest("form"));
            if (form && form.requestSubmit) form.requestSubmit();
          })()`).catch(() => undefined);
        }
        this.hooks.onAction("submit", null, this.currentUrl ?? "");
        await this.settle(900);
        await this.arrive();
      } else {
        await this.settle();
      }
      const read = await this.read();
      read.notes = notes;
      await this.keyframe();
      return read;
    });
  }

  /**
   * Put files into a numbered upload field, the way choosing them in the
   * file picker would. The number can be the file input itself or the
   * button a site draws over a hidden one ("Upload CV", "Attach"): that is
   * clicked, and the file picker it opens is answered with the files
   * instead of being shown.
   */
  upload(ref: number, files: UploadFile[]): Promise<PageRead> {
    return this.run(async () => {
      const page = await this.ensure();
      const target = this.refs.find((r) => r.ref === ref);
      if (!target) throw new Error(`No element [${ref}] on this page. Read it again.`);
      const names = files.map((f) => f.name).join(", ");
      this.hooks.onAction(
        `upload ${names} to [${ref}] "${target.name}"`,
        { x: target.x, y: target.y },
        this.currentUrl ?? "",
      );
      const payload = files.map((f) => ({ name: f.name, mimeType: f.mimeType, buffer: f.buffer }));
      const notes: string[] = [];
      /* The ways a page takes a file, surest first: its file input (the one
         named, or a hidden one inside or near it, which is how most styled
         upload boxes are built); the file picker a click on it opens; the
         only file input on the page; and last, for a drag-and-drop box with
         no input at all, the files dropped onto it. */
      const inputNear = async (near: boolean) => {
        const handle = await page.evaluateHandle(`(() => {
          const el = ${REF_EL(ref)};
          if (!el || !el.isConnected) return null;
          const isFile = (n) => n && n.tagName === "INPUT" && (n.type || "").toLowerCase() === "file" && !n.disabled;
          if (isFile(el)) return el;
          if (${near ? "true" : "false"}) {
            // Inside it, or inside the few boxes around it.
            let box = el;
            for (let i = 0; box && i < 4; i++, box = box.parentElement) {
              const found = box.querySelectorAll ? [...box.querySelectorAll('input[type="file" i]')].filter(isFile) : [];
              if (found.length === 1) return found[0];
              if (found.length > 1) return null;
            }
            return null;
          }
          const all = [...el.ownerDocument.querySelectorAll('input[type="file" i]')].filter(isFile);
          return all.length === 1 ? all[0] : null;
        })()`).catch(() => null);
        return handle?.asElement?.() ?? null;
      };
      const into = async (input: any) =>
        input ? await input.setInputFiles(payload).then(() => true).catch(() => false) : false;

      let how = "attached";
      let done = await into(await inputNear(true));
      if (!done) {
        const chooser = page.waitForEvent("filechooser", { timeout: 3000 }).catch(() => null);
        await this.humanClickAt(pointIn(await this.aim(target)));
        const picker = await chooser;
        if (picker) {
          if (files.length > 1 && !picker.isMultiple()) {
            throw new Error(`[${ref}] takes one file; ${files.length} were given.`);
          }
          await picker.setFiles(payload);
          done = true;
        }
      }
      if (!done) done = await into(await inputNear(false));
      if (!done) {
        done = await page.evaluate(DROP_SCRIPT(ref, files)).catch(() => false);
        if (done) how = "dropped";
      }
      if (!done) {
        throw new Error(
          `[${ref}] would not take a file: it has no file input, opens no file picker and takes no ` +
          `dropped files. Give the number of the upload box or the button that opens the picker.`,
        );
      }
      notes.push(`[${ref}]${target.name ? ` "${target.name}"` : ""}: ${how} ${names}${
        how === "dropped" ? " onto it (it is a drag-and-drop box); check the page shows the file" : ""}.`);
      await this.settle(900);
      await this.arrive();
      const read = await this.read();
      read.notes = notes;
      await this.keyframe();
      return read;
    });
  }

  private async checkedState(ref: number): Promise<boolean | null> {
    return (await this.page?.evaluate(`(() => {
      const el0 = (window.__autoraRefs || [])[${Number(ref)}];
      if (!el0) return null;
      const el = el0.tagName === "LABEL" && el0.control ? el0.control : el0;
      if (typeof el.checked === "boolean") return el.checked;
      const aria = el.getAttribute("aria-checked") ?? el.getAttribute("aria-pressed");
      return aria === null ? null : aria === "true";
    })()`).catch(() => null)) ?? null;
  }

  private async valueOf(ref: number): Promise<string | null> {
    return (await this.page?.evaluate(`(() => {
      const el = (window.__autoraRefs || [])[${Number(ref)}];
      if (!el) return null;
      if (typeof el.value === "string") return el.value;
      if (el.isContentEditable) return el.innerText;
      return null;
    })()`).catch(() => null)) ?? null;
  }

  /**
   * Press a key, or a few, as a person would at the keyboard: Escape to
   * close a dialog, Tab to move on, the arrows to walk a suggestion list,
   * Enter to pick from it. With a field named, it is focused first.
   */
  press(keys: string[], ref: number | null = null): Promise<PageRead> {
    return this.run(async () => {
      const page = await this.ensure();
      if (ref !== null) {
        const target = this.refs.find((r) => r.ref === ref);
        if (!target) throw new Error(`No element [${ref}] on this page. Read it again.`);
        await page.evaluate(`(() => {
          const el = (window.__autoraRefs || [])[${Number(ref)}];
          if (el && el.focus) el.focus();
        })()`).catch(() => undefined);
      }
      for (const key of keys) {
        /* Select-all with the focus outside any field highlights the whole
           page and does nothing useful, so it is not pressed there. */
        if (SELECT_ALL_KEY.test(key) && !(await page.evaluate(FOCUS_TYPEABLE_SCRIPT).catch(() => true))) {
          continue;
        }
        this.hooks.onAction(`press ${key}`, null, this.currentUrl ?? "");
        await page.keyboard.press(key);
        await page.waitForTimeout(120).catch(() => undefined);
      }
      await this.settle(400);
      await this.arrive();
      const read = await this.read();
      await this.keyframe();
      return read;
    });
  }

  /**
   * Scroll to where something is.
   *
   * By screens rather than pixels, in whichever part of the page actually
   * scrolls -- the page, or on the many apps whose page never moves, the pane
   * that does -- or inside an element named by number, or straight to some
   * text. What it reports is where that left the reader and whether it moved
   * at all, because an agent told only "scrolled" scrolls a page that is
   * already at the bottom forever.
   */
  /** The last look at the page, and the last picture, for the notes above. */
  private lookSeen = new SameLook();
  private shotSeen = new SameLook();

  /** After serving a read: null, or the way-out note in place of a fourth
      identical one. Called by the tool that gives the model a read, not by
      every internal read, so the count is of what the model was shown. */
  lookNote(page: PageRead, part = 1): string | null {
    return this.lookSeen.seen(lookKey(page, part), SAME_PAGE_NOTE);
  }

  /** After taking a picture: null, or the note that stops a fourth identical
      one being taken and paid for. */
  shotNote(png: Buffer): string | null {
    return this.shotSeen.seen(createHash("sha1").update(png).digest("hex"), SAME_PICTURE_NOTE);
  }

  /**
   * Run JavaScript in the page.
   *
   * The instrument this console was missing. The outline only knows what the
   * page announces: a dialog drawn by script has no refs, a value that lives
   * only in the DOM has no element to click, and an iframe's own document is
   * not visible from here -- so reading was all the agent could do, over and
   * over. This is the DOM itself. A click made through `__autora.click()` is a
   * real click on a real element, and the pointer is drawn where it landed, so
   * the person still watches it happen.
   */
  runScript(script: string): Promise<{ page: PageRead; value: string; hits: ScriptHit[]; elapsed: number }> {
    return this.run(async () => {
      const page = await this.ensure();
      await page.evaluate(AUTORA_HELPER_SCRIPT).catch(() => undefined);
      const started = Date.now();
      let value: unknown;
      let failure: string | null = null;
      for (const attempt of scriptAttempts(script)) {
        try {
          value = await withTimeout(page.evaluate(attempt), SCRIPT_TIMEOUT_MS);
          failure = null;
          break;
        } catch (err: any) {
          failure = plainScriptError(err);
          // A syntax error or "not a function" means the script was the wrong
          // *shape* -- an expression where a function was wanted, or the other
          // way round. Anything else is the script's own failure, reported as
          // it stands rather than retried in another shape.
          // A syntax error or "not a function" means the script was the wrong
          // shape -- an expression where statements were wanted, or the other
          // way round. Anything else is the script's own failure, reported as
          // it stands rather than run again in another shape, which for a
          // click would mean doing it twice.
          if (!WRONG_SHAPE.test(failure)) break;
        }
      }
      const hits = (await page
        .evaluate("(() => { const h = (window.__autora && window.__autora.hit) || []; if (window.__autora) window.__autora.hit = []; return h; })()")
        .catch(() => [])) as ScriptHit[];
      /* The pointer goes to the last thing it clicked, so the recording shows
         where the click landed even though the click itself was the DOM's. */
      const last = [...hits].reverse().find((h) => typeof h.x === "number");
      if (last) await this.showCursor(Math.round(last.x!), Math.round(last.y!), true).catch(() => undefined);
      this.hooks.onAction(`eval${hits.length ? ` (clicked ${hits.map((h) => h.label || "an element").join(", ")})` : ""}`, null, this.currentUrl ?? "");
      const elapsed = Date.now() - started;
      await this.settle(300);
      await this.arrive();
      const read = await this.read();
      await this.keyframe();
      return { page: read, value: failure ? `The script failed: ${failure}` : describeScriptValue(value), hits, elapsed };
    });
  }

  scroll(how: ScrollRequest): Promise<PageRead> {
    return this.run(async () => {
      const page = await this.ensure();
      const notes: string[] = [];
      const moved = await page.evaluate(SCROLL_SCRIPT(how)).catch((err: unknown) => ({ error: String(err) }));
      const said = how.text
        ? `scroll to "${how.text}"`
        : how.to
          ? `scroll to ${how.to}`
          : `scroll ${(how.screens ?? how.dy ?? 1) < 0 ? "up" : "down"}`;
      this.hooks.onAction(said, null, this.currentUrl ?? "");
      if (moved?.error) {
        notes.push(`Could not scroll: ${moved.error}`);
      } else if (how.text) {
        notes.push(moved?.found
          ? `Found ${JSON.stringify(how.text)} and scrolled it to the middle of the screen: "${moved.found}".`
          : `${JSON.stringify(how.text)} is not in the page's text. It may be further down (not loaded yet), in a different wording, or not on this page.`);
      } else if (moved && moved.after === moved.before && moved.max !== undefined) {
        notes.push(moved.max <= 0
          ? "Nothing moved: there is nothing to scroll here."
          : moved.after <= 0
            ? "Nothing moved: already at the top."
            : "Nothing moved: already at the bottom.");
      }
      await this.settle(350);
      /* At the bottom of a feed, more is often loaded in as you arrive.
         Wait a moment for it and say so, or it looks like the end. */
      if (moved && moved.max !== undefined && moved.after >= moved.max - 2 && moved.max > 0) {
        await page.waitForTimeout(900).catch(() => undefined);
        const grown = await page.evaluate(SCROLL_SCRIPT({ screens: 0, ref: how.ref })).catch(() => null);
        if (grown && grown.max > moved.max + 50) notes.push("More content loaded in at the bottom; scroll down again to see it.");
      }
      const read = await this.read();
      read.notes = notes;
      await this.keyframe();
      return read;
    });
  }

  /**
   * Sign-ins brought over from the person's own browser (see ./cookies).
   * Into the shared profile, so every session is signed in from then on and
   * they survive a restart. Returns how many took; a cookie Chrome refuses
   * is skipped rather than taking the rest down with it.
   */
  importCookies(cookies: BrowserCookie[]): Promise<{ added: number; refused: number }> {
    return this.run(async () => {
      await this.ensure();
      const context = this.context;
      if (!context) throw new Error("The browser is not running.");
      try {
        await context.addCookies(cookies);
        await saveCookies(context);
        return { added: cookies.length, refused: 0 };
      } catch {
        let added = 0;
        for (const cookie of cookies) {
          try {
            await context.addCookies([cookie]);
            added += 1;
          } catch {
            // Malformed for Chrome: the rest still go in.
          }
        }
        await saveCookies(context);
        return { added, refused: cookies.length - added };
      }
    });
  }

  /** A picture of the page as it is, for the thread. The one case where the
      screenshot is the answer rather than the fallback. */
  capture(): Promise<Buffer> {
    return this.run(async () => {
      const page = await this.ensure();
      return (await page.screenshot({ type: "png", fullPage: false })) as Buffer;
    });
  }

  /** A picture to keep: the window, the whole page, or one element. Throws
      with Playwright's reason, which says what was wrong with a selector. */
  screenshot(opts: { fullPage?: boolean; selector?: string; ref?: number }): Promise<Buffer> {
    return this.run(async () => {
      const page = await this.ensure();
      if (opts.ref !== undefined) {
        const el = (await page.evaluateHandle(REF_EL(opts.ref))).asElement();
        if (!el) throw new Error(`there is no element [${opts.ref}] on the page now; read it again for the current numbers`);
        return (await el.screenshot({ type: "png", timeout: 5000 })) as Buffer;
      }
      if (opts.selector) {
        return (await page.locator(opts.selector).first().screenshot({ type: "png", timeout: 5000 })) as Buffer;
      }
      return (await page.screenshot({ type: "png", fullPage: !!opts.fullPage, timeout: 20_000 })) as Buffer;
    });
  }

  /** Read the page without touching it. Safe to call at any time; refreshes
      the numbering the actions above resolve against. */
  snapshot(): Promise<PageRead> {
    return this.run(async () => {
      await this.ensure();
      return this.read();
    });
  }

  /** Direct mouse click from user or agent at screen coordinates */
  mouseClick(
    x: number,
    y: number,
    button: "left" | "right" | "middle" = "left",
    double = false,
  ): Promise<PageRead> {
    return this.run(async () => {
      const page = await this.ensure();
      const clampedX = Math.max(0, Math.min(this.vp.width, Math.round(x)));
      const clampedY = Math.max(0, Math.min(this.vp.height, Math.round(y)));
      this.pointer = { x: clampedX, y: clampedY };
      await this.showCursor(clampedX, clampedY, true);
      this.hooks.onAction(
        `${double ? "double-click" : "click"} at ${clampedX},${clampedY}`,
        { x: clampedX, y: clampedY },
        this.currentUrl ?? "",
      );
      if (double) {
        await page.mouse.dblclick(clampedX, clampedY, { button });
      } else {
        await page.mouse.click(clampedX, clampedY, { button });
      }
      await this.settle(600);
      const read = await this.read();
      await this.keyframe();
      return read;
    });
  }

  /**
   * A click from the person's own hand, on the picture of the page.
   *
   * Lighter than the agent's click -- no page read, a short settle -- because
   * someone tapping through a sign-in feels every hundred milliseconds. Says
   * whether the tap landed in something you type into, so a phone knows
   * whether to keep its keyboard up.
   */
  userClick(
    x: number,
    y: number,
    button: "left" | "right" | "middle" = "left",
    double = false,
  ): Promise<{ editable: boolean; select: SelectInfo | null }> {
    return this.run(async () => {
      const page = await this.ensure();
      const cx = Math.max(0, Math.min(this.vp.width, Math.round(x)));
      const cy = Math.max(0, Math.min(this.vp.height, Math.round(y)));
      this.pointer = { x: cx, y: cy };
      await this.showCursor(cx, cy, true, true);
      // A native <select> opens a popup the browser draws outside the page,
      // and a screencast never paints it: the tap would look like a tap on
      // nothing. So a dropdown is not clicked at all -- its choices go back
      // with the click and the app offers them itself.
      const dropdown = await this.selectAt(cx, cy);
      if (dropdown) {
        this.hooks.onAction(`you opened a dropdown at ${cx},${cy}`, { x: cx, y: cy }, this.currentUrl ?? "");
        return { editable: false, select: dropdown };
      }
      this.hooks.onAction(`you clicked at ${cx},${cy}`, { x: cx, y: cy }, this.currentUrl ?? "");
      if (double) await page.mouse.dblclick(cx, cy, { button });
      else await page.mouse.click(cx, cy, { button });
      await this.settle(150);
      // A string, because this file is compiled without the DOM's types.
      const editable: boolean = await page
        .evaluate(`(() => {
          const el = document.activeElement;
          if (!el || el === document.body) return false;
          if (el.isContentEditable) return true;
          const tag = el.tagName;
          if (tag === "TEXTAREA" || tag === "IFRAME") return true;
          if (tag !== "INPUT") return false;
          const type = (el.type || "text").toLowerCase();
          return !["button", "submit", "reset", "checkbox", "radio", "range",
            "color", "file", "image", "hidden"].includes(type);
        })()`)
        .catch(() => false);
      await this.keyframe();
      return { editable, select: null };
    });
  }

  /**
   * The dropdown under a point, if the page has one there.
   *
   * The choices are read off the element itself, so what the app shows is
   * what the page would have shown -- the same options, in the same order,
   * with the selected one marked and the disabled ones unchoosable.
   */
  private async selectAt(x: number, y: number): Promise<SelectInfo | null> {
    const page = this.page;
    if (!page) return null;
    const read = await page
      .evaluate(`(() => {
        const el = document.elementFromPoint(${x}, ${y});
        const sel = el && el.closest ? el.closest("select") : null;
        if (!sel) return null;
        return {
          name: String(sel.getAttribute("aria-label") || sel.name || "").slice(0, 80),
          multiple: !!sel.multiple,
          options: Array.from(sel.options).map((o, i) => ({
            index: i,
            label: String(o.label || o.textContent || "").replace(/\\s+/g, " ").trim().slice(0, 120),
            selected: !!o.selected,
            disabled: !!o.disabled || !!o.parentElement && !!o.parentElement.disabled,
          })),
        };
      })()`)
      .catch(() => null);
    return (read && Array.isArray((read as SelectInfo).options)) ? (read as SelectInfo) : null;
  }

  /**
   * Set a dropdown to the choice the person made in the app's own list.
   *
   * No popup is involved: the element's own selectedIndex is set and the
   * change is announced the way a real choice is, so a page listening for it
   * (or a form that submits on it) behaves exactly as if it had been clicked.
   */
  chooseOption(x: number, y: number, index: number): Promise<{ ok: boolean; label: string | null }> {
    return this.run(async () => {
      const page = await this.ensure();
      const cx = Math.max(0, Math.min(this.vp.width, Math.round(x)));
      const cy = Math.max(0, Math.min(this.vp.height, Math.round(y)));
      const picked: string | null = await page
        .evaluate(`(() => {
          const el = document.elementFromPoint(${cx}, ${cy});
          const sel = el && el.closest ? el.closest("select") : null;
          if (!sel) return null;
          const opt = sel.options[${Math.round(index)}];
          if (!opt) return null;
          sel.selectedIndex = ${Math.round(index)};
          opt.selected = true;
          sel.dispatchEvent(new Event("input", { bubbles: true }));
          sel.dispatchEvent(new Event("change", { bubbles: true }));
          return String(opt.label || opt.textContent || "").replace(/\\s+/g, " ").trim();
        })()`)
        .catch(() => null);
      this.hooks.onAction(
        picked === null ? "a dropdown chose nothing" : `you chose "${picked}"`,
        { x: cx, y: cy },
        this.currentUrl ?? "",
      );
      await this.settle(150);
      await this.keyframe();
      return { ok: picked !== null, label: picked };
    });
  }

  /**
   * A drag from the person's own hand, in three parts.
   *
   * A slider, a canvas, a map or a drag handle only moves when the pointer
   * travels with the button held, and until now a drag on the picture did
   * nothing at all: the app treated every movement as a scroll of the page.
   * Start presses, move travels (as the pointer moves, not after it is let
   * go, so what is being dragged follows the hand), end releases.
   */
  userDrag(phase: "start" | "move" | "end", x: number, y: number): Promise<{ ok: boolean }> {
    return this.run(async () => {
      const page = await this.ensure();
      const cx = Math.max(0, Math.min(this.vp.width, Math.round(x)));
      const cy = Math.max(0, Math.min(this.vp.height, Math.round(y)));
      if (phase === "start") {
        this.pointer = { x: cx, y: cy };
        await this.showCursor(cx, cy, true, true);
        this.hooks.onAction(`you dragged from ${cx},${cy}`, { x: cx, y: cy }, this.currentUrl ?? "");
        await page.mouse.move(cx, cy);
        await page.mouse.down();
        return { ok: true };
      }
      if (phase === "move") {
        this.pointer = { x: cx, y: cy };
        await this.showCursor(cx, cy, true, true);
        await page.mouse.move(cx, cy);
        return { ok: true };
      }
      await page.mouse.move(cx, cy);
      await page.mouse.up();
      this.pointer = { x: cx, y: cy };
      await this.settle(180);
      await this.keyframe();
      return { ok: true };
    });
  }

  /** Direct typing from user into focused element.

      No per-letter delay, no settle and no screenshot: the live feed already
      shows each letter land, and waiting on any of those held up the next
      keys behind it, which is what made typing into the page lag. The log
      gets one entry and one kept frame once the typing stops. */
  keyboardType(text: string): Promise<void> {
    return this.run(async () => {
      const page = await this.ensure();
      await this.personHand();
      await page.keyboard.type(text);
      this.noteTyping(text.length, null);
    });
  }

  /** Direct keystroke from user (Enter, Tab, Escape, Backspace, etc.) */
  keyboardPress(key: string): Promise<void> {
    return this.run(async () => {
      const page = await this.ensure();
      await this.personHand();
      await page.keyboard.press(key);
      this.noteTyping(0, key);
    });
  }

  /** What a run of typing adds up to, logged once it pauses. */
  private typed = { chars: 0, keys: [] as string[], timer: null as NodeJS.Timeout | null };

  private noteTyping(chars: number, key: string | null) {
    this.typed.chars += chars;
    if (key) this.typed.keys.push(key);
    if (this.typed.timer) clearTimeout(this.typed.timer);
    this.typed.timer = setTimeout(() => {
      const { chars: count, keys } = this.typed;
      this.typed = { chars: 0, keys: [], timer: null };
      const parts: string[] = [];
      if (count > 0) parts.push(`typed text (${count} chars)`);
      const named = [...new Set(keys)];
      if (named.length > 0) parts.push(`pressed ${named.join(", ")}`);
      if (parts.length === 0) return;
      void this.run(async () => {
        if (!this.page || this.closing) return;
        this.hooks.onAction(parts.join("; "), null, this.currentUrl ?? "");
        await this.keyframe();
      });
    }, TYPING_PAUSE_MS);
    this.typed.timer.unref?.();
  }

  /** Direct mouse wheel scrolling from user */
  mouseWheel(deltaX: number, deltaY: number, person = true): Promise<void> {
    return this.run(async () => {
      const page = await this.ensure();
      if (person) await this.personHand();
      await page.mouse.wheel(deltaX, deltaY);
      await this.settle(150);
      await this.keyframe();
    });
  }

  /** Reload current page */
  reload(): Promise<PageRead> {
    return this.run(async () => {
      const page = await this.ensure();
      this.hooks.onAction("reloaded page", null, this.currentUrl ?? "");
      await page.reload({ waitUntil: "domcontentloaded", timeout: 30_000 }).catch(() => undefined);
      await this.settle();
      const read = await this.read();
      await this.keyframe();
      return read;
    });
  }

  /** Go back in browser history */
  goBack(): Promise<PageRead | null> {
    return this.run(async () => {
      const page = await this.ensure();
      this.hooks.onAction("navigated back", null, this.currentUrl ?? "");
      await page.goBack({ waitUntil: "domcontentloaded", timeout: 15_000 }).catch(() => undefined);
      await this.settle();
      const read = await this.read();
      await this.keyframe();
      return read;
    });
  }

  /**
   * Where an element is now, scrolled into view first if it is off screen.
   *
   * Elements keep their numbers wherever the page is scrolled, so the agent
   * can click one it saw several screens ago; the box recorded then is no
   * longer where it is. Falls back to that box if the element is gone.
   */
  private async aim(target: Ref): Promise<{ x: number; y: number; w: number; h: number }> {
    const page = this.page;
    const fresh = page && await page.evaluate(`(() => {
      const el = (window.__autoraRefs || [])[${Number(target.ref)}];
      if (!el || !el.isConnected) return null;
      // In a frame, its box is relative to the frame: add where each
      // enclosing frame sits, out to the page.
      const place = () => {
        const b = el.getBoundingClientRect();
        let x = b.left, y = b.top;
        for (let win = el.ownerDocument.defaultView; win && win.frameElement; win = win.parent) {
          const f = win.frameElement, fb = f.getBoundingClientRect();
          x += fb.left + f.clientLeft;
          y += fb.top + f.clientTop;
        }
        return { x, y, w: b.width, h: b.height };
      };
      let b = place();
      if (b.y < 0 || b.y + b.h > innerHeight || b.x < 0 || b.x + b.w > innerWidth) {
        el.scrollIntoView({ block: "center", inline: "center" });
        b = place();
      }
      return { ...b, moved: true };
    })()`).catch(() => null);
    if (!fresh || fresh.w < 1 || fresh.h < 1) return boxOf(target);
    return { x: fresh.x, y: fresh.y, w: fresh.w, h: fresh.h };
  }

  /** Travel to a point the way a hand would and click there, with the ring
      played at the moment the button goes down. With nobody watching there
      is no one to show the journey to, so the click goes straight there --
      unless `always` asks for the hand regardless, as a CAPTCHA does. */
  private async humanClickAt(to: Point, always = false) {
    const page = this.page;
    if (!page) return;
    try {
      // Nobody watching, or Visible work off: straight there and click, at speed.
      if (!always && (this.hooks.watchers() === 0 || !this.visible())) {
        await page.mouse.click(to.x, to.y);
        this.pointer = to;
        return;
      }
      await this.showCursor(this.pointer.x, this.pointer.y, false);
      // The ripple is played by the page when the button really goes down, not announced ahead of it.
      this.pointer = await humanClick(page, this.pointer, to, { tick: () => this.touched() });
    } catch (err) {
      /* A button that closes its own window -- "Approve" in a sign-in popup
         -- can take the page down before the mouse-up is acknowledged, and
         the click that did exactly what it should then reported "Target page
         closed". The page's close handler has already gone back to the
         opener; the caller reads that. Any other failure is real. */
      if (!page.isClosed()) throw err;
      this.pointer = to;
    }
  }

  /**
   * Cloudflare's "Just a moment..." interstitial, by name.
   *
   * It is not a CAPTCHA with a box to tick: it scores the browser and lets a
   * browser it likes through by itself, with nothing clicked. Worth naming,
   * because the page then looks empty and stuck, and the answer is to wait
   * rather than to reach for the captcha tool or the person.
   */
  private async cloudflareCheck(): Promise<string | null> {
    const page = this.page;
    if (!page) return null;
    return await page
      .evaluate(`(() => {
        const title = (document.title || "").trim();
        const markup = !!document.querySelector(
          '#challenge-stage, #cf-challenge-running, #challenge-form, #cf-wrapper, [src*="challenge-platform"]'
        );
        const words = /just a moment|checking your browser|verify you are human|ddos protection|enable javascript and cookies/i
          .test((document.body && document.body.innerText || "").slice(0, 600));
        if (markup || words || /just a moment/i.test(title)) return title || "a Cloudflare check";
        return null;
      })()`)
      .catch(() => null);
  }

  // --------------------------------------------------------------- captcha --

  /**
   * Checkbox CAPTCHAs on the page, found by the frames that carry them.
   *
   * reCAPTCHA, hCaptcha and Turnstile all put their checkbox in a cross-origin
   * iframe, which is exactly where the element scan cannot reach -- so without
   * this the agent was told about a page with nothing to click on it. The
   * frame's URL says which widget it is; its box says where to click.
   */
  private loadingCaptchas: CaptchaKind[] = [];

  private async findCaptchas(): Promise<CaptchaHit[]> {
    const page = this.page;
    if (!page) return [];
    const hits: CaptchaHit[] = [];
    let recaptchaChallenge = false;
    let hcaptchaChallenge = false;

    const visibleBox = async (frame: any) => {
      try {
        const el = await frame.frameElement();
        const box = await el.boundingBox();
        if (!box || box.width < 20 || box.height < 20) return null;
        return { el, box };
      } catch {
        return null;
      }
    };
    const boxIn = async (frame: any, selector: string) => {
      try {
        const handle = await frame.$(selector);
        const box = handle ? await handle.boundingBox() : null;
        const checked = handle ? await handle.getAttribute("aria-checked") : null;
        return { box, checked };
      } catch {
        return { box: null, checked: null };
      }
    };

    for (const frame of page.frames()) {
      if (frame === page.mainFrame()) continue;
      let url: string = frame.url();
      // A widget frame that has not finished loading reports no URL yet, but
      // the iframe already carries the address it is loading.
      if (!url || url === "about:blank") {
        url = await frame
          .frameElement()
          .then((el: any) => el.getAttribute("src"))
          .catch(() => null) ?? "";
      }

      if (/\/recaptcha\/(api2|enterprise)\/bframe/.test(url)) {
        const shown = await visibleBox(frame);
        if (shown && shown.box.height > 150 && shown.box.y > -1000) recaptchaChallenge = true;
        continue;
      }
      if (/hcaptcha\.com/.test(url) && /frame=challenge/.test(url)) {
        const shown = await visibleBox(frame);
        if (shown && shown.box.height > 150 && shown.box.y > -1000) hcaptchaChallenge = true;
        continue;
      }

      let kind: CaptchaKind | null = null;
      let selector = "";
      if (/\/recaptcha\/(api2|enterprise)\/anchor/.test(url)) {
        kind = "recaptcha";
        selector = "#recaptcha-anchor";
      } else if (/hcaptcha\.com/.test(url) && /frame=checkbox/.test(url)) {
        kind = "hcaptcha";
        selector = "#checkbox";
      } else if (/challenges\.cloudflare\.com/.test(url)) {
        kind = "turnstile";
        selector = "input[type=checkbox]";
      }
      if (!kind) continue;

      const shown = await visibleBox(frame);
      if (!shown) continue;
      await shown.el.scrollIntoViewIfNeeded?.().catch(() => undefined);
      const frameBox = (await shown.el.boundingBox().catch(() => null)) ?? shown.box;
      const inner = await boxIn(frame, selector);

      // Turnstile keeps its checkbox in a closed shadow root that nothing can
      // query, so when the lookup comes back empty the box is where the widget
      // always draws it: a small square near the left, vertically centred.
      const box = inner.box
        ? { x: inner.box.x, y: inner.box.y, w: inner.box.width, h: inner.box.height }
        : kind === "turnstile"
          ? { x: frameBox.x + 18, y: frameBox.y + frameBox.height / 2 - 12, w: 24, h: 24 }
          : { x: frameBox.x + 12, y: frameBox.y + frameBox.height / 2 - 14, w: 28, h: 28 };

      hits.push({ kind, box, solved: inner.checked === "true", challenge: false });
    }

    /* Nothing found, or nothing found that is still to be ticked: a page
       with no widget at all can still draw the box itself. */
    const drawn = hits.some((h) => !h.solved) ? null : await findPageCheckbox(page);
    if (drawn) hits.push({ kind: "lookalike", box: { x: drawn.x, y: drawn.y, w: drawn.w, h: drawn.h }, solved: drawn.checked, challenge: false });

    // A response token in the page is the widget's own word that it passed,
    // and the only one Turnstile gives.
    const found: { tokens: Record<string, boolean>; markup: Record<string, boolean> } = await page
      .evaluate(`(() => {
        const has = (sel) => [...document.querySelectorAll(sel)].some((el) => (el.value || "").length > 20);
        const on = (sel) => !!document.querySelector(sel);
        return {
          tokens: {
            recaptcha: has('textarea[name="g-recaptcha-response"]'),
            hcaptcha: has('textarea[name="h-captcha-response"]'),
            turnstile: has('input[name="cf-turnstile-response"]'),
          },
          markup: {
            recaptcha: on('.g-recaptcha, iframe[src*="/recaptcha/api2/anchor"], iframe[src*="/recaptcha/enterprise/anchor"]'),
            hcaptcha: on('.h-captcha, iframe[src*="hcaptcha.com"]'),
            turnstile: on('.cf-turnstile, iframe[src*="challenges.cloudflare.com"]'),
          },
        };
      })()`)
      .catch(() => ({ tokens: {}, markup: {} }));
    const tokens = found.tokens;
    /** Widgets declared in the page whose frame has not drawn yet. */
    this.loadingCaptchas = (Object.keys(found.markup) as CaptchaKind[]).filter(
      (kind) => found.markup[kind] && !tokens[kind] && !hits.some((h) => h.kind === kind),
    );

    for (const hit of hits) {
      if (tokens[hit.kind]) hit.solved = true;
      if (hit.kind === "recaptcha" && recaptchaChallenge && !hit.solved) hit.challenge = true;
      if (hit.kind === "hcaptcha" && hcaptchaChallenge && !hit.solved) hit.challenge = true;
    }
    return hits;
  }

  /**
   * Tick the "I'm not a robot" box, like a person would.
   *
   * The pointer drifts a little first -- these widgets watch the mouse from
   * the moment the page loads, and one that has never moved before the click
   * is the giveaway -- then travels to the box on a curved, uneven path, lands
   * off-centre, pauses and clicks. After that the widget decides: it ticks,
   * it throws up a picture puzzle, or it thinks about it. Each is reported as
   * what it is, because a picture puzzle is the person's to solve.
   */
  /**
   * Whether the page carries a CAPTCHA, and whether every one on it has passed.
   *
   * Read-only and deliberately outside the action queue: it is what watches a
   * page the person is working in, so it must neither wait behind their clicks
   * nor move anything on the page.
   */
  async captchaStatus(): Promise<{ present: boolean; passed: boolean; url: string | null }> {
    const hits = await this.findCaptchas().catch(() => [] as CaptchaHit[]);
    const loading = this.loadingCaptchas.length > 0;
    let url: string | null = null;
    try { url = this.page?.url?.() ?? null; } catch { /* closing */ }
    return {
      present: hits.length > 0 || loading,
      passed: hits.length > 0 && !loading && hits.every((h) => h.solved),
      url,
    };
  }

  private captchaSettings: (() => CaptchaSettings) | null = null;
  private vision: ((prompt: string, pngs: Buffer[]) => Promise<string>) | null = null;
  private visionModel: (() => string | null) | null = null;

  /** What the solver may do, read from the settings panel each time. */
  setCaptchaSettings(read: () => CaptchaSettings) {
    this.captchaSettings = read;
  }

  /** The model that reads pictures. Set by the server; null means that
      backend has nothing to answer with. */
  setVision(ask: (prompt: string, pngs: Buffer[]) => Promise<string>) {
    this.vision = ask;
  }

  setVisionModel(label: () => string | null) {
    this.visionModel = label;
  }

  /** The model that would read a challenge's picture, for the status line. */
  captchaVisionModel(): string | null {
    return this.visionModel?.() ?? null;
  }

  /**
   * Answer the picture a checkbox CAPTCHA escalated to.
   *
   * Everything the solver needs is here and nothing of the browser's own
   * state leaves: the settings, the model, a way to photograph part of the
   * page, the same humanlike pointer the rest of the browsing uses, and the
   * widget's own token as the judge of whether it worked.
   */
  private async solvePicture(): Promise<SolveReport> {
    const page = this.page;
    if (!page) return { outcome: "none", widget: null, backend: null, detail: "No page is open." };
    const settings = this.captchaSettings?.() ?? DEFAULT_CAPTCHA;
    return solveChallenge({
      page,
      settings,
      vision: this.vision,
      visionName: this.visionModel,
      // Whether this browser can draw a canvas at all: a blank picture says
      // something different when it cannot.
      webgl: await page
        .evaluate(() => {
          try {
            const doc = (globalThis as any).document;
            const c = doc.createElement("canvas");
            return !!(c.getContext("webgl") || c.getContext("experimental-webgl"));
          } catch {
            return null;
          }
        })
        .catch(() => null),
      shot: (box: { x: number; y: number; w: number; h: number }) =>
        page.screenshot({
          clip: {
            x: Math.max(0, Math.round(box.x)),
            y: Math.max(0, Math.round(box.y)),
            width: Math.max(2, Math.round(box.w)),
            height: Math.max(2, Math.round(box.h)),
          },
          type: "png",
        }),
      click: async (at: Point) => {
        this.pointer = await humanMove(page, this.pointer, at, () => this.touched());
        await this.humanClickAt(at, true);
      },
      // A text CAPTCHA is answered by typing into its box: click into it the
      // way a hand would, then type the characters at a human speed.
      type: async (text: string, at: Point) => {
        this.pointer = await humanMove(page, this.pointer, at, () => this.touched());
        await this.humanClickAt(at, true);
        await humanType(page, text, () => this.touched());
      },
      drag: (from: Point, to: Point) => this.dragAt(from, to),
      passed: async () => {
        // A puzzle still standing is not passed, whoever drew it: a page that
        // draws its own has no widget token here to ask, so the puzzle it drew
        // going away is the pass.
        if (await findChallenge(page).catch(() => null)) return false;
        const hits = await this.findCaptchas();
        return !this.loadingCaptchas.length && hits.every((h) => h.solved);
      },
      log: (what: string, at?: Point | null) => {
        this.hooks.onAction(what, at ?? null, this.currentUrl ?? "");
      },
      sleep: (ms: number) => page.waitForTimeout(ms).catch(() => undefined),
    });
  }

  /**
   * A drag, the way a hand does it: press, travel, release.
   *
   * Sliders watch the path and not just the two ends -- a piece that jumps
   * from one side to the other with nothing in between is the single easiest
   * thing to catch -- so the pointer follows the same curve a click does,
   * with the button held down and a pause between the points that a hand
   * would take.
   */
  private async dragAt(from: Point, to: Point) {
    const page = this.page;
    if (!page) return;
    await this.showCursor(this.pointer.x, this.pointer.y, false);
    this.pointer = await humanMove(page, this.pointer, from, () => this.touched());
    await this.showCursor(from.x, from.y, true);
    await page.mouse.move(from.x, from.y);
    await page.mouse.down();
    for (const at of humanPath(this.pointer, to)) {
      await page.mouse.move(at.x, at.y);
      await page.waitForTimeout(8 + Math.random() * 14);
    }
    this.pointer = await humanMove(page, this.pointer, to, () => this.touched());
    await page.mouse.up();
    await this.settle(140);
  }

    solveCaptcha(): Promise<CaptchaResult> {
    return this.run(async () => {
      const page = await this.ensure();

      /* A Cloudflare interstitial is not a checkbox: it clears by itself for a
         browser it trusts, and clicking it only delays that. Given the half
         minute it usually needs before anything else is tried, so the tool
         does not report "no CAPTCHA here" on a page that is one. */
      let checking = await this.cloudflareCheck();
      if (checking) {
        this.hooks.onAction(`cloudflare: "${checking}" -- waiting for it to clear`, null, this.currentUrl ?? "");
        for (let waited = 0; waited < 30_000 && checking; waited += 1000) {
          await page.waitForTimeout(1000).catch(() => undefined);
          checking = await this.cloudflareCheck();
        }
        if (checking) {
          return { outcome: "pending", kind: null, page: await this.read() };
        }
      }

      let hits = await this.findCaptchas();
      // The widget script loads after the page does; give a declared one a
      // few seconds to draw its checkbox before concluding there is none.
      for (let waited = 0; waited < 12_000 && this.loadingCaptchas.length; waited += 500) {
        await page.waitForTimeout(500).catch(() => undefined);
        hits = await this.findCaptchas();
      }
      const target = hits.find((h) => !h.solved);
      if (!target) {
        /* Nothing to tick -- but a puzzle can still be standing: the box may
           already be ticked, or the page may draw the puzzle and never draw a
           box at all. browser_captcha is the tool for a picture challenge too,
           so it answers that rather than reporting there is nothing here. */
        const standing = await findChallenge(page).catch(() => null);
        if (standing) {
          const report = await this.solvePicture();
          this.hooks.onAction(`captcha: ${standing.widget} -- ${report.detail}`, null, this.currentUrl ?? "");
          await this.settle(400);
          const read = await this.read();
          await this.keyframe();
          return {
            outcome: report.outcome === "solved" ? "solved" : "challenge",
            kind: hits[0]?.kind ?? null,
            page: read,
            detail: report.detail,
            ...(report.backend ? { backend: report.backend } : {}),
          };
        }
        const loading = this.loadingCaptchas[0] ?? null;
        const read = await this.read();
        return {
          outcome: loading ? "pending" : hits.length ? "solved" : "none",
          kind: loading ?? hits[0]?.kind ?? null,
          page: read,
        };
      }

      const aim = pointIn(target.box);
      this.hooks.onAction(`captcha: tick the ${labelOf(target.kind)} checkbox`, aim, this.currentUrl ?? "");
      await this.showCursor(this.pointer.x, this.pointer.y, false);
      this.pointer = await wander(page, this.pointer, this.vp);
      await this.humanClickAt(aim, true);

      // Give the widget time to decide. It usually does within a couple of
      // seconds; Turnstile and a slow connection can take longer.
      let outcome: CaptchaResult["outcome"] = "pending";
      for (let waited = 0; waited < 15_000; waited += 500) {
        await page.waitForTimeout(500).catch(() => undefined);
        hits = await this.findCaptchas();
        const same = hits.find((h) => h.kind === target.kind) ?? null;
        if (!same || same.solved) { outcome = "solved"; break; }
        if (same.challenge) { outcome = "challenge"; break; }
      }

      /* Still thinking. A widget that has not decided usually wants the click
         again, a moment later and a little to one side, rather than a harder
         one -- and a page whose box has been redrawn wants the new box. */
      if (outcome === "pending") {
        const again = hits.find((h) => h.kind === target.kind && !h.solved) ?? null;
        if (again) {
          await this.humanClickAt(pointIn(again.box), true);
          for (let waited = 0; waited < 12_000; waited += 500) {
            await page.waitForTimeout(500).catch(() => undefined);
            hits = await this.findCaptchas();
            const same = hits.find((h) => h.kind === target.kind) ?? null;
            if (!same || same.solved) { outcome = "solved"; break; }
            if (same.challenge) { outcome = "challenge"; break; }
          }
        }
      }

      // Rest the pointer somewhere nearby rather than leaving it parked on
      // the box -- people move off what they just clicked.
      this.pointer = await humanMove(page, this.pointer, {
        x: Math.min(this.vp.width - 10, Math.max(10, this.pointer.x + Math.round((Math.random() - 0.3) * 200))),
        y: Math.min(this.vp.height - 10, Math.max(10, this.pointer.y + Math.round((Math.random() - 0.5) * 120))),
      });

      /* A picture challenge is no longer the end of the road. The solver
         looks at it, answers it with whichever backend can, and asks the
         widget itself whether that passed; only when every backend has had
         its say and the widget still wants an answer does this come back as
         a challenge for the person. */
      let detail: string | null = null;
      let backend: string | null = null;
      if (outcome === "challenge") {
        const report = await this.solvePicture();
        detail = report.detail;
        backend = report.backend;
        this.hooks.onAction(`captcha: picture challenge -- ${report.detail}`, null, this.currentUrl ?? "");
        if (report.outcome === "solved") outcome = "solved";
      }

      this.hooks.onAction(`captcha: ${outcome}`, null, this.currentUrl ?? "");
      await this.settle(400);
      const read = await this.read();
      await this.keyframe();
      return {
        outcome,
        kind: target.kind,
        page: read,
        ...(detail ? { detail } : {}),
        ...(backend ? { backend } : {}),
      };
    });
  }

  /** Draw the pointer at a place. `you`: the person's own tap, drawn as theirs (a neutral ring), never as Autora's
      pointer. With Visible work off the agent's pointer is not drawn at all. */
  private async showCursor(x: number, y: number, tap: boolean, you = false) {
    // The pointer is on screen: frames come at the faster rate so it is seen travelling, not arriving.
    this.touched();
    const hand = you ? "you" : this.visible() ? "agent" : "off";
    if (you) this.youAt = Date.now();
    await this.page
      ?.evaluate(
        `(() => { if (window.__autoraCursorMount) window.__autoraCursorMount(); ${this.signature()}
           if (window.__autoraHand) window.__autoraHand(${JSON.stringify(hand)});
           if (window.__autoraCursor) window.__autoraCursor(${x}, ${y}, ${tap ? "true" : "false"}); })()`,
      )
      .catch(() => undefined);
    // Long enough for the dot's own transition to play, so the pointer is seen
    // arriving rather than teleporting.
    if (!tap && hand === "agent") await this.page?.waitForTimeout?.(200).catch(() => undefined);
  }

  /** The scan, folded into the shape the model is given. */
  private async read(): Promise<PageRead> {
    let page = this.page;
    if (!page) throw new Error("No page is open.");
    let scanned;
    try {
      scanned = await page.evaluate(SCAN_SCRIPT);
    } catch (err) {
      // A sign-in window that closed itself as it was being read: the page
      // under it is the one to read now.
      if (!page.isClosed()) throw err;
      await new Promise((resolve) => setTimeout(resolve, 50));
      if (this.following) await this.following.catch(() => undefined);
      if (!this.page || this.page === page) throw err;
      page = this.page;
      scanned = await page.evaluate(SCAN_SCRIPT);
    }
    this.refs = scanned.refs;
    this.lastSig = this.sigOf(scanned);
    this.currentUrl = scanned.url;
    this.currentTitle = scanned.title;
    const captchas = [
      ...(await this.findCaptchas().catch(() => [] as CaptchaHit[])).map(
        ({ kind, solved, challenge }) => ({ kind, solved, challenge }),
      ),
      ...this.loadingCaptchas.map((kind) => ({ kind, solved: false, challenge: false })),
    ];
    const blocked = signInRefusal(scanned.text);
    const challenge = await this.cloudflareCheck();
    return {
      url: scanned.url,
      title: scanned.title,
      refs: scanned.refs,
      text: scanned.text,
      outline: outlineOf(scanned.refs, 80, { dialog: scanned.dialog, scroll: scanned.scroll }),
      captchas,
      dialog: scanned.dialog ?? null,
      scroll: scanned.scroll,
      blocked,
      challenge,
    };
  }
}

/** The element a numbered ref stands for, as page script: a label that
    stands in for a hidden checkbox resolves to the checkbox. */
const REF_EL = (ref: number) => `(() => {
  const el0 = (window.__autoraRefs || [])[${Number(ref)}];
  return el0 && el0.tagName === "LABEL" && el0.control ? el0.control : el0;
})()`;

/**
 * Choose a dropdown's option by what it says. Exact text first, then the
 * option's value, then one that starts with or contains what was asked --
 * "Canada" finds "Canada (CA)" -- and the change is announced the way a
 * person's choice would be, so the page's own code sees it.
 */
const SELECT_SCRIPT = (ref: number, wanted: string) => `(() => {
  const el = ${REF_EL(ref)};
  if (!el || el.tagName !== "SELECT") return { ok: false, options: [] };
  const norm = (s) => String(s || "").replace(/\\s+/g, " ").trim().toLowerCase();
  const want = norm(${JSON.stringify(wanted)});
  const opts = Array.from(el.options);
  const texts = opts.map((o) => (o.text || "").replace(/\\s+/g, " ").trim());
  const pick =
    opts.find((o, i) => norm(texts[i]) === want) ||
    opts.find((o) => norm(o.value) === want) ||
    opts.find((o, i) => want && norm(texts[i]).startsWith(want)) ||
    opts.find((o, i) => want && norm(texts[i]).includes(want)) ||
    opts.find((o, i) => want.length > 2 && norm(texts[i]).length > 1 && want.includes(norm(texts[i])));
  if (!pick) return { ok: false, options: texts.filter(Boolean) };
  const set = Object.getOwnPropertyDescriptor(el.ownerDocument.defaultView.HTMLSelectElement.prototype, "value").set;
  set.call(el, pick.value);
  pick.selected = true;
  el.dispatchEvent(new Event("input", { bubbles: true }));
  el.dispatchEvent(new Event("change", { bubbles: true }));
  return { ok: true, chosen: (pick.text || pick.value).trim() };
})()`;

/**
 * Set a field's value through the setter the page's framework watches, then
 * announce it: what a date picker, a colour well or a field that ignores
 * typed keys needs, since there is nothing sensible to type into those.
 */
const SET_VALUE_SCRIPT = (ref: number, value: string) => `(() => {
  const el = ${REF_EL(ref)};
  if (!el) return null;
  const view = el.ownerDocument.defaultView;
  if (el.isContentEditable && typeof el.value !== "string") {
    el.focus();
    const sel = view.getSelection();
    const range = el.ownerDocument.createRange();
    range.selectNodeContents(el);
    sel.removeAllRanges();
    sel.addRange(range);
    el.ownerDocument.execCommand("insertText", false, ${JSON.stringify(value)});
    return el.innerText;
  }
  const proto = el.tagName === "TEXTAREA" ? view.HTMLTextAreaElement.prototype : view.HTMLInputElement.prototype;
  const desc = Object.getOwnPropertyDescriptor(proto, "value");
  if (!desc || !desc.set) return null;
  desc.set.call(el, ${JSON.stringify(value)});
  el.dispatchEvent(new Event("input", { bubbles: true }));
  el.dispatchEvent(new Event("change", { bubbles: true }));
  el.dispatchEvent(new Event("blur", { bubbles: true }));
  return el.value;
})()`;

/**
 * Select what a field holds, so what is typed next replaces it. The field
 * is the numbered element, or the box inside it the click put the caret in.
 * When neither is something that takes typing, whatever the click selected
 * is cleared and nothing is selected: select-all outside a field is the
 * whole page, highlighted, and that is what the person watching saw.
 */
const SELECT_FIELD_SCRIPT = (ref: number) => `(() => {
  const el0 = ${REF_EL(ref)};
  const doc = (el0 && el0.ownerDocument) || document;
  const view = doc.defaultView;
  const typeable = (el) => el && el.isConnected && !el.disabled && !el.readOnly &&
    ((el.tagName === "INPUT" || el.tagName === "TEXTAREA") || el.isContentEditable);
  const active = doc.activeElement;
  const el = typeable(el0) ? el0 : typeable(active) ? active : null;
  const sel = view.getSelection();
  if (!el) {
    if (sel) sel.removeAllRanges();
    return false;
  }
  if (doc.activeElement !== el) el.focus();
  if (el.tagName === "INPUT" || el.tagName === "TEXTAREA") {
    try { el.select(); } catch (e) {}
    return true;
  }
  const range = doc.createRange();
  range.selectNodeContents(el);
  sel.removeAllRanges();
  sel.addRange(range);
  return true;
})()`;

/**
 * Drop files onto an element the way dragging them from a desktop would: a
 * drag-and-drop upload box with no file input behind it takes files only
 * this way. The bytes travel into the page as base64.
 */
const DROP_SCRIPT = (ref: number, files: UploadFile[]) => `((files) => {
  const el = ${REF_EL(ref)};
  if (!el || !el.isConnected) return false;
  const view = el.ownerDocument.defaultView;
  const dt = new view.DataTransfer();
  for (const f of files) {
    const raw = view.atob(f.data);
    const bytes = new Uint8Array(raw.length);
    for (let i = 0; i < raw.length; i++) bytes[i] = raw.charCodeAt(i);
    dt.items.add(new view.File([bytes], f.name, { type: f.type }));
  }
  const b = el.getBoundingClientRect();
  const at = { clientX: b.left + b.width / 2, clientY: b.top + b.height / 2 };
  for (const type of ["dragenter", "dragover", "drop"]) {
    el.dispatchEvent(new view.DragEvent(type, { bubbles: true, cancelable: true, composed: true, dataTransfer: dt, ...at }));
  }
  return true;
})(${JSON.stringify(files.map((f) => ({ name: f.name, type: f.mimeType, data: f.buffer.toString("base64") })))})`;

/** Keys that select everything wherever the focus is. */
const SELECT_ALL_KEY = /^(control|meta|controlormeta)\+a$/i;

/** Whether the focus is somewhere typing goes, as page script. */
const FOCUS_TYPEABLE_SCRIPT = `(() => {
  let el = document.activeElement;
  while (el && el.tagName === "IFRAME") {
    try { el = el.contentDocument && el.contentDocument.activeElement; } catch (e) { return true; }
  }
  return !!el && (el.tagName === "INPUT" || el.tagName === "TEXTAREA" || el.isContentEditable);
})()`;

/** Scroll as asked and say where that left things; see LiveBrowser.scroll. */
const SCROLL_SCRIPT = (how: ScrollRequest) => `((o) => {
  const doc = document.scrollingElement || document.documentElement;
  const scrollable = (el) => {
    if (!el || el === doc) return false;
    if (el.scrollHeight <= el.clientHeight + 20) return false;
    const oy = getComputedStyle(el).overflowY;
    return oy === "auto" || oy === "scroll" || oy === "overlay";
  };
  const pane = () => {
    if (doc.scrollHeight > innerHeight + 20) return doc;
    let best = null, area = 0;
    for (const el of document.querySelectorAll("body *")) {
      if (el.clientHeight < 150 || !scrollable(el)) continue;
      const b = el.getBoundingClientRect();
      if (b.bottom < 0 || b.top > innerHeight) continue;
      if (b.width * b.height > area) { area = b.width * b.height; best = el; }
    }
    return best || doc;
  };
  if (o.text) {
    const want = o.text.toLowerCase();
    const walker = document.createTreeWalker(document.body, NodeFilter.SHOW_TEXT);
    let first = null, below = null;
    for (let n = walker.nextNode(); n; n = walker.nextNode()) {
      const t = n.nodeValue || "";
      if (!t.toLowerCase().includes(want)) continue;
      const el = n.parentElement;
      if (!el || el.closest("[data-autora]")) continue;
      const b = el.getBoundingClientRect();
      if (b.width < 1 || b.height < 1) continue;
      if (!first) first = el;
      // The next one further down, so asking again moves on.
      if (b.top > innerHeight * 0.55) { below = el; break; }
    }
    const hit = below || first;
    if (!hit) return { found: null };
    hit.scrollIntoView({ block: "center", inline: "nearest" });
    const text = (hit.innerText || hit.textContent || "").replace(/\\s+/g, " ").trim();
    return { found: text.length > 160 ? text.slice(0, 159) + "\\u2026" : text };
  }
  let target = pane();
  if (o.ref !== null && o.ref !== undefined) {
    const el0 = (window.__autoraRefs || [])[o.ref];
    if (!el0 || !el0.isConnected) return { error: "there is no element [" + o.ref + "] now; read the page again" };
    let up = el0;
    while (up && up !== document.body && !scrollable(up)) up = up.parentElement;
    if (up && up !== document.body && scrollable(up)) target = up;
    else if (!o.to && !o.screens && !o.dy) {
      el0.scrollIntoView({ block: "center", inline: "nearest" });
      return { into: true };
    }
  }
  const view = target === doc ? innerHeight : target.clientHeight;
  const max = Math.max(0, target.scrollHeight - (target === doc ? innerHeight : target.clientHeight));
  const before = Math.round(target.scrollTop);
  if (o.to === "top") target.scrollTop = 0;
  else if (o.to === "bottom") target.scrollTop = target.scrollHeight;
  else if (o.dy) target.scrollTop = before + o.dy;
  else if (o.screens) target.scrollTop = before + Math.round(o.screens * view * 0.85);
  return { before, after: Math.round(target.scrollTop), max, view };
})(${JSON.stringify(how)})`;

/** A date typed as a person would say it, as the value a date field holds. */
export function normaliseNative(type: string, text: string): string {
  const t = text.trim();
  if (type === "date" && !/^\d{4}-\d{2}-\d{2}$/.test(t)) {
    const d = new Date(t);
    if (!Number.isNaN(d.getTime())) {
      const pad = (n: number) => String(n).padStart(2, "0");
      return `${d.getFullYear()}-${pad(d.getMonth() + 1)}-${pad(d.getDate())}`;
    }
  }
  return t;
}

/** Whether a field holds what was typed, allowing for the reformatting a
    phone, card or date box does to it: "(555) 123-4567" is "5551234567". */
export function sameValue(held: string, typed: string): boolean {
  const loose = (s: string) => s.toLowerCase().replace(/[\s\-()./+,]/g, "");
  if (held === typed || loose(held) === loose(typed)) return true;
  const digits = (s: string) => s.replace(/\D/g, "");
  return digits(typed).length >= 4 && digits(held) === digits(typed) && !/[a-z]/i.test(typed);
}

/**
 * The site turning a sign-in away because of the browser it is in, found by
 * what those pages say. Each of these means the same thing -- trying again
 * here will not work -- and the agent needs to know that rather than retype
 * the password until the account is locked.
 */
const REFUSALS: RegExp[] = [
  /this browser or app may not be secure[^\n]*/i,
  /couldn[’']t sign you in[^\n]*/i,
  /try using a different browser[^\n]*/i,
  /our systems have detected unusual traffic[^\n]*/i,
  /(?:your )?browser is not supported[^\n]*/i,
  /we (?:couldn[’']t|could not) verify (?:that )?you(?:['’]re| are) (?:a )?(?:human|not a robot)[^\n]*/i,
  /access to this page has been denied[^\n]*/i,
  /automated (?:access|queries|requests) (?:is|are) not allowed[^\n]*/i,
];

export function signInRefusal(text: string): string | null {
  for (const re of REFUSALS) {
    const hit = re.exec(text);
    if (hit) return hit[0].trim().slice(0, 200);
  }
  return null;
}

export function labelOf(kind: CaptchaKind): string {
  if (kind === "lookalike") return "a look-alike";
  return kind === "recaptcha" ? "reCAPTCHA" : kind === "hcaptcha" ? "hCaptcha" : "Cloudflare Turnstile";
}

/** A ref's box, from the centre and size the scan recorded. */
function boxOf(r: Ref) {
  return { x: r.x - r.w / 2, y: r.y - r.h / 2, w: r.w, h: r.h };
}


/** The CAPTCHA line for the model, or nothing when there is none. */

const FIELD_ROLES = new Set([
  "textbox", "searchbox", "combobox", "listbox", "checkbox", "radio", "switch", "slider", "password", "spinbutton",
]);

/** One element, as the model reads it. */

/** Where the reader is, in words: how far down, and how much is left. */

/**
 * The numbered outline, as a screen reader would read it.
 *
 * Capped, because a search results page has four hundred links and the first
 * forty are the ones anybody acts on; the count is printed so the model knows
 * it is looking at the top of a list rather than all of it.
 */
export function outlineOf(
  refs: Ref[],
  limit = 80,
  around: { dialog?: string | null; scroll?: ScrollState } = {},
): string {
  // What is on screen, by the numbers every element keeps wherever the page
  // is scrolled. A read made before this was tracked shows everything.
  const shown = refs.some((r) => r.inView !== undefined) ? refs.filter((r) => r.inView) : refs;
  const firstShown = shown[0]?.ref ?? Infinity;
  const lastShown = shown[shown.length - 1]?.ref ?? -Infinity;
  const above = refs.filter((r) => !r.inView && r.ref < firstShown).length;
  const below = refs.filter((r) => !r.inView && r.ref > lastShown).length;
  const lines: string[] = [];
  if (around.dialog) {
    lines.push(
      `A dialog is open on top of the page: "${around.dialog}". Deal with it first ` +
        "(answer it, or close it with its button or Escape); what is behind it may not respond " +
        "and, while it blocks the page, is not listed.",
    );
  }
  /* Things drawn over the page, and so over what is listed under them. Said
     once per covering thing, with the way to close it. */
  const covering = new Map<string, Ref[]>();
  for (const r of shown) if (r.covered) covering.set(r.covered, [...(covering.get(r.covered) ?? []), r]);
  for (const [label, hit] of covering) {
    const close = (hit[0].coverRefs ?? []).map((k) => {
      const c = refs.find((x) => x.ref === k);
      return c ? `[${k}] ${JSON.stringify(c.name)}` : `[${k}]`;
    });
    lines.push(
      `${hit.length} element${hit.length === 1 ? " is" : "s are"} covered by "${label}": a click on ` +
        `${hit.length === 1 ? "it" : "them"} would land on that instead. ` +
        (close.length ? `Dismiss it first with ${close.join(" or ")}.` : "Dismiss it first (its own button, or Escape)."),
    );
  }
  /* Fields under a heading are introduced by it once, rather than each
     carrying it: "Shipping address" then the six fields in it. */
  let section = "";
  for (const r of shown.slice(0, limit)) {
    const under = r.dialog ? `in dialog "${r.dialog}"${r.section ? ` / ${r.section}` : ""}` : r.section ?? "";
    if (under && under !== section) lines.push(`-- ${under} --`);
    // A field outside the section closes it, so it is not read as part of it.
    else if (!under && section && FIELD_ROLES.has(r.role)) lines.push("-- (end of section) --");
    if (under || FIELD_ROLES.has(r.role)) section = under;
    lines.push(refLine(r));
  }
  if (shown.length > limit) {
    lines.push(`… ${shown.length - limit} more on screen after these.`);
  }
  if (above > 0 || below > 0) {
    lines.push(
      `(${above} more above and ${below} more below, off screen. Scroll to list them; ` +
        "every element keeps its number wherever the page is scrolled, and clicking " +
        "one you saw earlier scrolls it into view first.)",
    );
  }
  if (around.scroll) lines.push(scrollLine(around.scroll));
  return lines.join("\n");
}
