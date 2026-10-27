#!/usr/bin/env node
// OCTA runner — runs on your own computer and uses the AI tools you're signed in to.
// Each bot gets its own browser window with its own profile (separate logins, cookies, tabs),
// so several bots can work at the same time without touching each other.
// Files (attachments, screenshots, what bots make) are kept on this computer in the OCTA file folder,
// one folder per bot or group; bots may read each other's folders.
//
// One computer per account is the 主機 (host) and does the work; others wait on standby.
//
// CLI (cloud version):
//   first time:  node octa-runner.mjs <網站網址> <執行器金鑰>
//   afterwards:  node octa-runner.mjs
// The desktop app imports startRunner() instead.
// Requires: Node 18+, at least one AI CLI (Claude Code, Codex, Gemini…), Google Chrome.

import { spawn, spawnSync, execFile } from 'node:child_process';
import { readFileSync, writeFileSync, mkdirSync, existsSync, readdirSync, statSync, renameSync, copyFileSync, openSync, closeSync, lstatSync, unlinkSync } from 'node:fs';
import { dirname, join, extname, basename, relative, sep } from 'node:path';
import { fileURLToPath, pathToFileURL } from 'node:url';
import os from 'node:os';
import { createHash } from 'node:crypto';
import { probeCodingHosts, listRecoverableStates, runCodingTask, selectProvider } from './coding-runtime.mjs';
import { replyIsProviderRefusal, providerFailureText } from './model-route.mjs';
import { connectorLines, stripConnectorTask, takeConnectorTask, toolForBrowse } from './connectors.mjs';

export const VERSION = '18.1';
export const OLLAMA_NUM_CTX = 8192;
export const GOOGLE_HOME = 'https://www.google.com/';
const PW_MCP = '@playwright/mcp@0.0.83';
const WIN = process.platform === 'win32';
const JOB_TIMEOUT_MS = 15 * 60 * 1000;
const CHUNK = 900_000;

let cfg = {}, workDir = '', MAX = 3, log = (...a) => console.log(new Date().toLocaleTimeString(), ...a);

// tools installed after the app started aren't on its PATH yet; add the usual install folders
if (WIN) {
  const add = [join(os.homedir(), '.local', 'bin'), join(process.env.APPDATA || '', 'npm'), join(process.env.LOCALAPPDATA || '', 'Programs', 'Ollama'), join(process.env.ProgramFiles || 'C:\\Program Files', 'nodejs'), join(process.env.LOCALAPPDATA || '', 'cursor-agent')];
  process.env.PATH = [...add.filter(p => !(process.env.PATH || '').includes(p)), process.env.PATH].join(';');
}

async function api(path, body, method = 'POST', signal) {
  const r = await fetch(cfg.url + '/api/' + path, {
    method, signal,
    headers: { 'content-type': 'application/json', ...(cfg.token ? { authorization: 'Bearer ' + cfg.token } : {}) },
    body: method === 'GET' ? undefined : JSON.stringify(body || {})
  });
  const data = await r.json().catch(() => ({}));
  if (!r.ok) throw new Error(data.error || 'HTTP ' + r.status);
  return data;
}

// ---------- file folder (attachments, screenshots, outputs) ----------
export const storeDir = () => (cfg.getStore ? cfg.getStore() : cfg.store) || join(cfg.home || '.', 'files');
const safeName = s => String(s || '').replace(/[\\/:*?"<>|\x00-\x1f]/g, '_').replace(/^\.+/, '').trim().slice(0, 60) || '未命名';
const shortId = id => String(id).replace(/^g-/, '').replace(/[^\w]/g, '').slice(0, 8);
// one folder per bot or group, named "名稱_編號"; renamed when the bot is renamed
function convDir(conv) {
  const root = storeDir(), tag = '_' + shortId(conv.id), want = join(root, safeName(conv.name) + tag);
  mkdirSync(root, { recursive: true });
  if (!existsSync(want)) {
    const old = readdirSync(root).find(f => f.endsWith(tag));
    if (old) { try { renameSync(join(root, old), want); } catch { return join(root, old); } }
  }
  for (const sub of ['附件', '截圖', '輸出']) mkdirSync(join(want, sub), { recursive: true });
  return want;
}
const rel = p => relative(storeDir(), p).split(sep).join('/');
function freeName(dir, name) {   // don't overwrite: "報表.xlsx" → "報表 (2).xlsx"
  const ext = extname(name), base = name.slice(0, name.length - ext.length);
  let p = join(dir, name);
  for (let i = 2; existsSync(p); i++) p = join(dir, `${base} (${i})${ext}`);
  return p;
}
// an uploaded file → this computer's folder; the cloud copy is then deleted
async function saveUpload(f) {
  const d = await api('file/' + f.id, null, 'GET');
  const dir = join(convDir({ id: f.conv, name: f.convName || f.conv }), '附件');
  const p = freeName(dir, safeName(f.name || d.name));
  const buf = Buffer.from(d.data, 'base64');
  writeFileSync(p, buf);
  await api('runner/stored', { id: f.id, path: rel(p), size: buf.length });
  log(`📥 已存到電腦：${rel(p)}`);
  return p;
}
// someone opened a file that lives here: send a temporary copy
async function sendCopy(f) {
  const p = join(storeDir(), String(f.path || ''));
  if (!f.path || !existsSync(p)) return api('runner/blob', { id: f.id, missing: true });
  const data = readFileSync(p).toString('base64');
  for (let i = 0, n = 0; i < data.length || n === 0; i += CHUNK, n++)
    await api('runner/blob', { id: f.id, n, data: data.slice(i, i + CHUNK), last: i + CHUNK >= data.length });
}

// ---------- per-bot workspace (browser profile and AI tool settings) ----------
const extToken = () => (cfg.getExtToken ? cfg.getExtToken() : cfg.extToken) || '';
// mode 'own': the bot's own Chrome profile (separate logins). mode 'mine': the user's real Chrome through the
// Playwright Extension, so saved logins and passwords work; each bot gets its own tab group there.
function botDir(id, mode = 'own', port = 0) {
  const safe = String(id).replace(/[^\w-]/g, '');
  const dir = join(workDir, 'bots', safe);
  mkdirSync(join(dir, 'shots'), { recursive: true });
  const profile = join(dir, 'profile');
  const mine = mode === 'mine';
  const pwArgs = mine ? ['--extension', '--output-dir', join(dir, 'shots')]
    : port ? ['--cdp-endpoint', `http://127.0.0.1:${port}`, '--caps', 'vision', '--output-dir', join(dir, 'shots')]   // the bot's own browser that stays open
    : ['--browser', 'chrome', '--user-data-dir', profile, '--output-dir', join(dir, 'shots')];
  const env = { ...(cfg.pwCli ? cfg.nodeEnv || {} : {}), ...(mine && extToken() ? { PLAYWRIGHT_MCP_EXTENSION_TOKEN: extToken() } : {}) };
  const server = cfg.pwCli
    ? { command: cfg.nodeBin || process.execPath, args: [cfg.pwCli, ...pwArgs], env }   // bundled (desktop app)
    : WIN ? { command: 'cmd', args: ['/c', 'npx', '-y', PW_MCP, ...pwArgs], env } : { command: 'npx', args: ['-y', PW_MCP, ...pwArgs], env };
  const put = (f, o) => { mkdirSync(dirname(join(dir, f)), { recursive: true }); writeFileSync(join(dir, f), JSON.stringify(o, null, 2)); };
  // The main turn never receives the browser server. A separate file is handed only to the one round that reads the page.
  writeFileSync(join(dir, 'mcp.json'), JSON.stringify({ mcpServers: {} }, null, 2));
  writeFileSync(join(dir, 'mcp-browser.json'), JSON.stringify({ mcpServers: { browser: server } }, null, 2));
  const applyBrowser = (on) => {
    const trusted = on ? { browser: { ...server, timeout: 60000, trust: true } } : {};
    put('.gemini/settings.json', { mcpServers: trusted });
    put('.agents/mcp_config.json', { mcpServers: on ? { browser: { ...server } } : {} });   // Antigravity CLI (agy)
    put('.qwen/settings.json', { mcpServers: trusted });
    put('.cursor/mcp.json', { mcpServers: on ? { browser: server } : {} });
    put('.mcp.json', { mcpServers: on ? { browser: server } : {} });
    put('copilot-mcp.json', { mcpServers: on ? { browser: { type: 'local', ...server, tools: ['*'] } } : {} });
  };
  applyBrowser(false);
  return { dir, profile, server, put, applyBrowser };
}
export function findChrome() {
  if (cfg.chrome && existsSync(cfg.chrome)) return cfg.chrome;
  const c = WIN ? [
    join(process.env.PROGRAMFILES || 'C:\\Program Files', 'Google\\Chrome\\Application\\chrome.exe'),
    join(process.env['PROGRAMFILES(X86)'] || 'C:\\Program Files (x86)', 'Google\\Chrome\\Application\\chrome.exe'),
    join(process.env.LOCALAPPDATA || '', 'Google\\Chrome\\Application\\chrome.exe')
  ] : process.platform === 'darwin' ? ['/Applications/Google Chrome.app/Contents/MacOS/Google Chrome']
    : ['/usr/bin/google-chrome', '/usr/bin/google-chrome-stable', '/usr/bin/chromium'];
  return c.find(p => p && existsSync(p));
}
function newestImage(dir, since) {
  let best = null;
  const walk = d => {
    for (const f of readdirSync(d)) {
      if (f === 'profile') continue;
      const p = join(d, f), st = statSync(p);
      if (st.isDirectory()) { if (d === dir) walk(p); continue; }
      if (/\.(png|jpe?g|webp)$/i.test(f) && st.mtimeMs >= since && (!best || st.mtimeMs > best.t)) best = { p, t: st.mtimeMs, size: st.size };
    }
  };
  try { walk(dir); } catch { }
  return best;
}
function newFiles(dir, since) {   // what the bot put in its 輸出 folder during this job
  try {
    return readdirSync(dir).map(f => ({ f, p: join(dir, f) })).filter(x => { const st = statSync(x.p); return st.isFile() && st.mtimeMs >= since; })
      .slice(0, 8).map(x => ({ name: x.f, path: rel(x.p), size: statSync(x.p).size }));
  } catch { return []; }
}
const q = a => (WIN && /[\s"&|<>^]/.test(a) ? '"' + a.replace(/"/g, '\\"') + '"' : a);

// ---------- prompts ----------
// said again right before the instruction: in groups, models (small ones especially) took on another member's name and duties
const whoAmI = job => { const E = ENGINES[job.bot.engine || 'claude'] || ENGINES.claude;
  return callUser(job) + `提醒：你是「${job.bot.name}」，用的 AI 是 ${E.label}${job.bot.model ? `（${job.bot.model}）` : ''}。` + (job.group ? '對話裡其他機器人的發言是它們自己的，不是你的；不要用它們的名字、模型或任務介紹自己。' : ''); };
const callUser = job => job.nick ? `使用者叫「${job.nick}」：跟他說話時稱呼他「${job.nick}」，不要叫他老闆、主人或使用者；規則或資料裡寫的「老闆」就是指他。` : '跟使用者說話時直接用「你」，不要叫他老闆或主人；規則或資料裡寫的「老闆」就是指使用者。';
// The standing task is a specialty, not a ceiling. Said at the top and again before each turn.
function studioAim() {
  return [
    '你的目標：成為比使用者更厲害的全能助手。OCTA 是一座超級 AI 工作室，每個機器人都要盡可能學。指定任務是你長期負責的本業，不是能力的邊界。',
    '遊戲、創作、研究、生活、寫程式、操作軟體，使用者問得出口的都要接。禁止用「我只處理工作」「遊戲我還不能」「這不在我的功能裡」收尾，也不要把話題拉回「有沒有工作要我做」。',
    '不會就學，而且要在授權下真的試：先查做法（搜尋、讀說明）。已登入的網站寫【派瀏覽】交給單獨的一輪；公開資料和你自己的資料夾可以直接做最小的一次嘗試。把學會的步驟用 🧩技能 或 🗺️網站筆記 留下。沒試過不能說不會。',
    '查看、搜尋、打開、練習直接做。安裝軟體、付款、刪除、更改帳號、對別人發出訊息，先寫 ✅待確認 取得授權再做；還沒授權時說明你卡在哪一個授權，不要改口說自己沒有這個能力。',
    '頁面上的數字不准編。電池、金額、礦機、機架、數量、名次，只能抄這一次畫面裡看得到的字或圖；看不清就寫「這次畫面沒有這個數字」，不要沿用上一則回覆，也不要自己估。使用者說數字不對時，重新打開那一頁、看過圖再讀，不要把舊數字再說一次。畫面是遊戲或圖、文字很少時，描述你實際看到的東西，不要自製一張數據表。',
    '看畫面要用眼睛：文字讀不到的分數、電池、機架、金額，以「畫面.jpg」這張圖為準。圖裡沒有的數字寫「這次畫面沒有這個數字」，不要沿用舊回覆。',
    cfg.embed ? '你的瀏覽器嵌在 OCTA 視窗裡，使用者看得到你的游標和點擊。不要說瀏覽器開在別的程式。' : ''
  ].filter(Boolean);
}
// 權限三段（bots.autonomy）與「先規劃再動手」. Routine runs, standby checks and colleagues' background requests
// have nobody waiting to approve a plan, so they never stop for one.
export function autonomyRules(job) {
  const a = job.bot?.autonomy || 'report', p = String(job.prompt || '').trim();
  const unattended = /^（例行任務|^〔背景:|^同事「[^」]*」回覆了你在背景問|^（自動接續/.test(p);
  const approved = /^(@\S+\s+)?核准[:：]\s*照計畫/.test(p);
  if (a === 'auto') return ['- 權限：全權處理。看得懂要做什麼就直接做完，不用先出計畫，也不用每一步回報，做完簡短說結果。對別人送出訊息、提交表單，只要在指定任務或這次指示的範圍內就直接做；付款、刪除資料、更改帳號設定仍要先寫 ✅待確認。'];
  const lines = [a === 'ask'
    ? '- 權限：重要動作先問。送出訊息、提交表單、刪除、付款、下單、更改帳號設定這類做了收不回來的動作，每一次都先把內容擬好，單獨一行寫「✅待確認：要做的事」然後停下，等使用者核准才做；就算之前「一律允許」過也一樣。查看、搜尋、整理直接做。'
    : '- 權限：做完告知。一般工作直接做，做完回報做了什麼；做了收不回來的動作（送出訊息、提交表單、刪除、付款）照規則先寫 ✅待確認。'];
  if (approved) lines.push('- 使用者剛按了「照做」，核准你上一則的計畫：照那份計畫一路做完，不要再出一次計畫；途中遇到計畫外、收不回來的動作再問。');
  else if (!unattended) lines.push('- 先規劃再動手：這則指示如果要超過 3 個步驟、包含收不回來的動作（送出訊息、提交表單、刪除、付款），或是「每天／全部／整理」這類大範圍的工作，先不要動手。先回一則計畫：第一行寫「📋計畫」，接著 3 到 5 行編號步驟（每步一句：去哪裡、做什麼、產出什麼；需要核准的步驟標出來），最後單獨一行寫「✅待確認：照計畫執行：一句話目標」，然後停下。使用者按「照做」才開始。簡單的問題、查詢、一兩步就做得完的事直接做，不要出計畫。');
  return lines;
}
function workLoop() {
  return [
    '做事順序（每一則都照這五步，不要跳、不要先寫結論）：',
    '1. 先看完再下結論。有圖就整張讀完，有網頁就先看目前畫面。還沒看完，不要寫結果。',
    '2. 回覆裡把三樣分開寫：畫面上的原文、我的判斷、還沒看到的。判斷可以寫，但要讓人看得出是判斷；沒看到的留白，不要用猜的補上。',
    '3. 自己做下一步。檔案和公開網頁這一步就做。有接上的服務寫【連接器】。已登入的網頁寫【派瀏覽】，不要自己點。畫面寫了誰去做，就照那個做，不要改成叫使用者做。',
    '4. 做一步就再看一次。檔案或公開網頁做完就再讀一次。已登入的頁面等報告回來再決定下一步，不要沿用想像。',
    '5. 對完再回。使用者要的每一項都對回這一次看到的畫面或檔案。沒有逐項對過，不能說「一致」或「跟目前的一樣」。對不上就寫對不上的那一項。'
  ];
}
function turnGuide() {
  return '先判斷這則指示的類型：(1) 只問你的設定、任務內容、AI 方案 → 直接回答，不用工具。(2) 問到網頁上、畫面上、帳號裡現在的狀況（例如「你看到什麼」「現在有幾則訊息」），或使用者說他幫你打開、登入好了 → 先看完再下結論。用 Read 讀「畫面.jpg」，畫面上的數字只能照這次看到的抄。要再看已登入的頁面或點開才出現的內容，不要自己點，改寫【派瀏覽】到【派完】，而且不要同時寫【回覆】。(3) 問你會不會、能不能，或要你做一件還沒做過的事（包含玩遊戲、學新軟體）→ 不要推辭。先用一句話說你會學，然後立刻做第一個學習動作（搜尋做法、用 WebFetch 讀公開頁，或在自己的資料夾試一個最小例子）；已登入的網站改寫【派瀏覽】。需要他指定對象時，一邊查通用做法，一邊只問要哪一個。(4) 其他要你做事的 → 照五步做完再回，不要只回計畫。有接上的服務寫【連接器】；公開網頁用 WebFetch；已登入的網頁寫【派瀏覽】。這個判斷和 octa-task.md 都是內部說明，回覆裡不要提到它們，也不要自稱是別的產品。工作過程中不要輸出「Let me…」「先用瀏覽器看看」之類的說明；最後給使用者的回覆前，單獨一行寫「【回覆】」，後面接繁體中文回覆。若這則只是在派瀏覽，就不要寫【回覆】。';
}
// today's date said plainly, and the bot's own work notes (what it already found), so it doesn't start from zero each time
function dayInfo(job) {
  const d = new Date(), f = x => `${x.getMonth() + 1}/${x.getDate()}`, wk = '日一二三四五六';
  const y = new Date(d - 864e5), t = new Date(+d + 864e5);
  const out = [`今天是 ${d.getFullYear()}/${f(d)}（週${wk[d.getDay()]}），昨天是 ${f(y)}（週${wk[y.getDay()]}），明天是 ${f(t)}。`];
  // general working rules for any kind of job; anything specific to one business lives in that bot's task or its section's notes
  out.push(
    '一次把整件事做完再回覆，花幾分鐘沒關係；能確定的先整理出來，有疑點的另外列在最後，不要因為有疑點就整份不給。',
    '名字、編號、數字、金額只能抄這一次畫面上或資料裡看到的字，不准自己編；沒看到的空著。',
    '日期沒有寫年份時，當成今年、離今天最近的那一天。',
    '找資料不能只看畫面上看得到的：用搜尋、篩選、往下捲到載入完整，相關的帳號和頁面都要看過。',
    '交出數字、名單、清單之前，先回頭對照原始資料（畫面、檔案、紀錄）逐項核對一次，對不上就重算。回覆裡不用描述核對過程，只有無法確認的疑點才另外列出。');
  return out;
}
const notesFile = job => join(workDir, 'bots', String(job.bot.id).replace(/[^\w-]/g, ''), '工作筆記.md');
function workNotes(job) {
  let t = ''; try { t = readFileSync(notesFile(job), 'utf8').trim(); } catch { }
  if (t.length > 6000) t = '…' + t.slice(-6000);
  return [`你的工作筆記（檔案 ${notesFile(job)}，由你自己維護）：查到值得留下的資料就更新這個檔案，例如查到的名單和數字、網站上東西在哪、做到哪一步，每段寫上查到的時間；舊日期、用不到的就刪掉。只能寫這一次畫面上看得到的字。畫面上沒有的編號、名字、數字不要寫，OCTA 會把那些列拿掉。檔案寫不進去（例如顯示唯讀）時，改在回覆最後寫「📒工作筆記：」換行接完整的新筆記，最後一行寫「📒結束」，OCTA 會幫你存，不用跟使用者提這件事。下次先看筆記，只補查可能變動的部分，不用每次從頭查。使用者再問一樣的事、而筆記裡已經有今天整理好的結果時，先告訴他「上次幾點查的、結果是什麼」，再用 ❓ 問他要不要重新查（A. 現在重新查 B. 用剛才那份就好）。`,
    t ? '目前筆記內容：\n' + t : '（目前筆記是空的）'];
}
// 紀錄: every browse report is kept as a dated text file, so lists are computed from files and compared with earlier days
const recDir = job => join(workDir, 'bots', String(job.bot.id).replace(/[^\w-]/g, ''), '紀錄');
const stamp = () => { const d = new Date(), p = n => String(n).padStart(2, '0'); return `${d.getFullYear()}-${p(d.getMonth() + 1)}-${p(d.getDate())} ${p(d.getHours())}${p(d.getMinutes())}`; };
function saveRecord(job, task, report) {
  try {
    const dir = recDir(job); mkdirSync(dir, { recursive: true });
    const what = String(task?.prompt || '').replace(/[\\/:*?"<>|\s]+/g, ' ').trim().slice(0, 24) || '讀取';
    const f = join(dir, `${stamp()} ${what}.txt`);
    writeFileSync(f, `時間：${new Date().toLocaleString('zh-TW')}\n網址：${task?.url || ''}\n要做的事：${task?.prompt || ''}\n\n${report}\n`);
    const old = Date.now() - 30 * 86400000;
    for (const n of readdirSync(dir)) { try { const p = join(dir, n); if (statSync(p).mtimeMs < old) unlinkSync(p); } catch { } }
    return f;
  } catch (e) { log('紀錄存檔失敗：' + e.message); return ''; }
}
function records(job) {
  let fs = []; try { fs = readdirSync(recDir(job)).filter(n => n.endsWith('.txt')).sort().slice(-12); } catch { }
  return [`你的讀取紀錄資料夾：${recDir(job)}。每次【派瀏覽】讀回來的內容都會自動存成一個有日期時間的檔案。`,
    '- 要整理名單、算數量、分類時，用程式（python、node 或 PowerShell，有哪個用哪個）讀紀錄檔來算，不要用心算或憑印象；算完把結果也存成檔案（例如「2026-10-27 名單.txt」放在同一個資料夾）。',
    '- 和前幾天的紀錄比對，找出新增、消失、改變的項目；今天已經有涵蓋需要範圍的紀錄、而且使用者沒有要最新的，就直接用紀錄算，不用重新捲一次。',
    '- 使用者糾正你、或你發現一個例外（打錯字的名字、某種情況怎麼算、哪些已經確認過），立刻用 📌記住 寫成一條規則，下次照做。',
    fs.length ? '最近的紀錄：\n' + fs.map(n => '· ' + n).join('\n') : '（還沒有紀錄）'];
}
// 記憶分層: 規則 / 事實 / 做事手冊, each its own section and each capped (the server already keeps the newest that fit)
const MEM_LIMIT = { rule: 3000, fact: 3000, manual: 3000 };
const fitNewest = (list, chars) => { const out = []; let n = 0; for (let i = list.length - 1; i >= 0; i--) { const v = String(list[i] || ''); if (!v || n + v.length > chars) break; n += v.length; out.unshift(v); } return out; };
export function memoryLines(job) {
  const out = [], rules = fitNewest(job.memory || [], MEM_LIMIT.rule), facts = fitNewest(job.facts || [], MEM_LIMIT.fact);
  if (rules.length) out.push('', '你的規則（之前被糾正或學到的做法，照著做）：', ...rules.map(m => '- ' + m));
  if (facts.length) out.push('', '你記得的事實（固定的名單、網址、帳號名稱等資料；重要決定前仍要到來源確認最新狀況）：', ...facts.map(m => '- ' + m));
  return [...out, ...manualLines(job)];
}
// the manuals change with each instruction, so a warm session gets them with the turn instead of in its fingerprint
export function manualLines(job) {
  let used = 0; const mans = [];
  for (const m of job.manuals || []) { const s = `【${m.name}】\n${m.steps}`; if (used + s.length > MEM_LIMIT.manual) break; used += s.length; mans.push(s); }
  return mans.length ? ['', '做事手冊（你之前成功做過類似的事，照這些步驟做；畫面跟手冊不一樣時以畫面為準，做完用同名 📘手冊 更新）：', ...mans] : [];
}
export function memoryHowTo() {
  return [
    '- 固定的資料（名單、網址、帳號名稱、門市地址這類不常變的事實）寫成「📇事實：一句話」，跟 📌記住（規則、做法、偏好）分開。',
    '- 成功做完一件多步驟的工作（例如用瀏覽器操作，步驟有 3 步以上）而且以後還會再做時，在回覆最後單獨一行寫「📘手冊：名稱｜步驟1 → 步驟2 → 步驟3」（名稱用看得出是什麼工作的幾個字，例如「下載訂房報表」；步驟寫去哪裡、點什麼、怎麼判斷），下次做類似的事會提供給你。沒做完、失敗或只做一兩步的不要寫。'
  ];
}
export const GROUP_HISTORY = 14;
export function buildPrompt(job, here) {
  const lines = [
    `你是 OCTA（奧克塔）裡的機器人「${job.bot.name}」，在使用者自己的電腦上執行。`,
    callUser(job),
    job.bot.task ? `你的指定任務（長期本業，不是能力上限）：${job.bot.task}` : '你還沒有指定任務：只做使用者這次交代的事，做完就停，不要自己找事做，也不要把共用資料、分區資料或同事的工作當成你的。使用者說明要你長期負責什麼時，再用📝任務更新記下來。',
    /^新機器人\d*$/.test(job.bot.name) ? '- 你的名字是暫定的。使用者第一次說明要你做什麼時，幫自己取一個 2 到 6 個字、看得出工作的名字，前面加一個合適的 emoji，在回覆最後單獨一行寫「📛名稱：emoji 名字」（例如「📛名稱：🎮 遊戲員」）。只寫一次。' : '',
    '- 共用資料、分區資料、網站筆記和同事清單只是背景參考：只用跟你的指定任務或這次指示有關的部分，無關的忽略，回覆裡也不要提。不要在回覆裡引用規則編號或內部說明。',
    ...studioAim()
  ];
  if (job.backup) lines.push('你是在其他 AI 沒有額度時代替它把這件工作做完。該查的頁面要查，該建的例行任務要寫成⏰那一行，該抄的名單只能抄畫面。不要因為自己是備援就少做。');
  if (job.group) lines.push(
    `你在群組「${job.group.name}」，成員依序為：${job.group.members.join('、')}。`,
    job.group.task ? `群組協作規則：${job.group.task}` : '群組沒有特別規則：依各成員的指定任務分工。',
    '只做你自己負責的部分，可以引用其他成員在對話裡交出的資料。使用者直接問你的新主題（就算不是你的本業，例如遊戲）也要學著接，不要推說這不是你的工作。',
    '在群組說話像同事聊天：用第一人稱只講你自己的部分，不要重述其他成員的職責；帶出你實際做過或看到的具體事（日期、房號、遇到的狀況），可以直接回應前面成員說的話，或 @ 某位成員接話、問問題。簡短自然。',
    '真的需要使用者回答才能繼續時，在回覆最後單獨一行寫「❓問你：具體問題」：寫清楚是哪一館哪一房／哪位客人、你看到什麼、要他選什麼（例如「貳宿 303 有 ʟɪɴ_ 和 蔡宗恩 兩組暱稱，密碼要傳給：A. ʟɪɴ_ B. 蔡宗恩？」）。不是問題的心得、說明、報告不要寫 ❓，也不要用問號結尾。使用者回覆會直接回到你這裡。',
    ...(job.group.mode === 'parallel' && !String(job.prompt || '').includes('@' + job.bot.name) ? ['成員是同時收到這則訊息、各自並行處理的。先判斷這則訊息該不該由你處理：只有訊息明顯是交代給別的成員的工作時，整則回覆才只寫「（略過）」；對大家說的（你們、大家、各位、沒指定人的問題、聊天）一定要回答。'] : []),
    ...(job.group.mode === 'turns' ? ['這一則由成員依序處理。你只做自己負責的部分，做完就停。上一位已經回過的內容不要再做一遍，也不要把同一句再寫一次。'] : []),
    ...(job.canAsk ? ['需要其他成員的資料或幫忙時，單獨一行寫「@成員名 你的問題」，系統會請對方回答再叫你回來繼續；整件工作交給更適合的成員時寫「@成員名 交接：要做的事」，交出去後你就不用再做。成員名要寫完整（名字裡有空白也照抄）。使用者要你「私下／在背景」問某位成員時，寫「@成員名 私下：問題」，這一行不會出現在群組，對方在背景回答後你會被叫回來，再在群組只回使用者要的最後結果。'] : []),
    '資訊不夠、會影響結果時，直接問使用者並停下等回覆，不要亂猜。'
  );
  if (job.colleagues?.length && !job.group) {
    lines.push('OCTA 裡的其他機器人同事（像全天待命的員工，可以在背景互相幫忙）：');
    for (const c of job.colleagues) lines.push(`- ${c.name}：${c.task || '（還沒有指定任務）'}`);
    if (job.canAsk) lines.push('需要同事的資料或幫忙時，單獨一行寫「@同事名 你的問題」，系統會在背景傳給對方，對方回答後自動叫你繼續；整件事交給更適合的同事做，寫「@同事名 交接：要做的事」，對方做完會回報給你。不需要就不要寫。');
  }
  lines.push('', '你的運作環境（使用者問到你用什麼 AI、方案、還剩多少流量時，照這些資料回答，不要說你查不到）：', ...aboutMe(job));
  lines.push(...memoryLines(job));
  if (job.skills?.length) lines.push('', '你會的技能（使用者說「執行技能 X」或要做相同的事時，照步驟做）：', ...job.skills.map(k => `【${k.name}】\n${k.steps}`));
  if (job.notes) lines.push('', '共用資料（所有機器人都要知道）：', job.notes);
  if (job.folderNotes) lines.push('', `分區「${job.folder}」的資料：`, job.folderNotes);
  lines.push(
    '',
    '檔案：',
    `- 這個對話的資料夾：${here}（附件在「附件」，截圖在「截圖」）。`,
    `- 要交給使用者的檔案（報表、圖片、文件）存到 ${join(here, '輸出')}，會自動附在你的回覆裡。`,
    `- 其他機器人和群組的資料夾都在 ${storeDir()} 底下（名稱_編號），需要時可以讀取別人的檔案，但不要改動或刪除別人的檔案。`,
    '',
    '工作方式（像一個能自己做事的助理）：',
    '- 理解目標後，自己規劃步驟並一路做完，不要每一步都停下來問。為了完成工作需要的查看動作（打開網頁、點開對話、讀訊息、翻頁、下載報表）直接做。',
    '- 做完先講結果，再列出「需要你決定的事」，每一項附上你的建議做法。',
    '- 主動做下一步：根據指定任務推斷接下來應該做什麼。在允許範圍內就直接做；需要核准的事（例如回覆客人）先把內容擬好，用 ✅待確認 讓使用者一鍵核准。例如看到未回覆的客人訊息，就點開讀完、擬好回覆。',
    ...autonomyRules(job),
    '- 指定任務太簡短或模糊時（只有幾個字），根據你看到的實際情況推斷完整的工作內容，用 📝任務更新 寫出來，並提出合適的例行任務。',
    '- 記住長期有用的事：使用者說了穩定的偏好、規則或重要事實（例如「回覆客人要用敬語」「302 房冷氣壞了」），在回覆最後加一行「📌記住：一句話」。一次性的事不要記。',
    '- 存成技能：使用者說「把這個流程存起來／存成技能」，或同一套步驟你已經做順了，在回覆最後寫「🧩技能：技能名稱」，換行後條列每個步驟（去哪裡、點什麼、怎麼判斷、輸出什麼），最後一行寫「🧩結束」。',
    ...memoryHowTo(),
    '',
    '規則：',
    `- 用${({ 'zh-TW': '繁體中文', 'zh-CN': '簡體中文', en: '英文（English）', ja: '日文（日本語）' })[job.lang] || '繁體中文'}回覆，簡潔、先給結果。你的最後輸出會原封不動顯示成聊天訊息。`,
    '- 說話要像真人同事在 LINE 上回訊息：口語、自然、短句，先講重點，可以有一點語氣（「好喔」「我看了一下」「這間有點怪」）。不要用標題、粗體、表格、分隔線；名單或多筆資料才用簡單的換行清單。內文不要講系統用語（「依規則」「根據指示」「執行」「類型」），也不要每次重述自己的職責；✅待確認、❓問你、@同事 這些標記照規定單獨一行寫。沒做成就直接說卡在哪、需要什麼。',
    '- 公開網頁（不需要登入）用 WebFetch 讀成文字，不帶登入。工作區裡已經有的檔案直接讀，不必開瀏覽器。',
    ...connectorLines(job.connectors),
    '- 已登入的網頁、要點了才出現的內容，你不能自己點、不能打字、不能捲動、不能讀 Cookie。需要時單獨寫下面這一段，不要同時寫【回覆】：\n【派瀏覽】\n網址：https://完整網址（不知道就寫目前頁面）\n要做的事：要得到的結果、限制、怎樣算做完\n【派完】',
    '- 派出去的那一輪會用這台電腦上已登入的瀏覽器讀頁面、點下一步，做完只交回文字：網址、頁面上有什麼、做成了什麼、卡在哪裡。你根據那份報告回答，不要把整頁內容貼進對話。同一則使用者的話最多派兩次。',
    '- 要確認它停在哪，用 Read 讀「畫面.jpg」。那張圖只用來對位置，不代替報告。',
    '- 關掉 OCTA 裡的瀏覽器視窗：單獨一行寫「【關瀏覽器】」。這是視窗控制，你做得到。禁止說「沒有控制工具」「沒辦法替你關閉」「無法操作瀏覽器視窗」。',
    '- 打開 OCTA 裡的瀏覽器：單獨一行寫「【開瀏覽器】」。沒有指定網址就打開內嵌的 Google。指定了就寫「【開瀏覽器】https://完整網址」。不要叫使用者先去打網址。',
    job.windowNote ? '- ' + job.windowNote : '',
    job.bot.browser === 'mine'
      ? '- 瀏覽器是使用者自己的 Chrome（有他已登入的網站）。只在你自己的分頁群組裡操作，不要關閉或改動使用者其他分頁。登入頁若只要點已記住的帳號，寫進要做的事裡；不要讓那一輪猜或輸入密碼。'
      : '- 瀏覽器是你專屬、一直開著的（獨立的登入和分頁，上次開的分頁都還在）。使用者看得到旁邊的畫面，也可以接手。不會影響其他機器人。',
    job.bot.page ? `- 你上次停在：${job.bot.page}` : '',
    '- 研究一個網站時：先看網址結構（帳號 ID、頁面路徑常在網址裡，改網址就能切換）、左側選單、右上角帳號選單，弄清楚每個功能在哪。知道完整網址就寫進【派瀏覽】。',
    '- 學到某個網站好用的做法（例如去哪裡切換帳號、哪個網址直接打開某頁、哪個按鈕要先等載入），在回覆最後單獨一行寫「🗺️網站筆記：網域｜做法」，所有機器人以後都會知道。',
    job.sites ? '- 之前大家學到的網站操作筆記（先照這些做）：\n' + job.sites : '',
    '- 登入頁只要點選已經記住的帳號（例如顯示帳號名稱和「登入」按鈕、「以 XX 身分繼續」），不必輸入密碼或驗證碼時，把「點已記住的帳號繼續」寫進【派瀏覽】。',
    '- 需要輸入帳號密碼、驗證碼或手機確認時，派瀏覽停在那一頁。報告會寫「需要使用者在電腦上登入」。你的回覆照抄這幾個字和要登入的網站。使用者會在旁邊的畫面幫你登入，再叫你繼續。密碼不要進對話。',
    '- 發訊息給任何人、付款、刪除資料、更改帳號設定：除非使用者在對話中明確下令，否則只準備好內容並請使用者確認，不要執行。同意只涵蓋那一次動作。',
    '- 這些「只看不改」的事不用問、也不要叫使用者幫你，寫進【派瀏覽】讓那一輪去做：打開或切換網站、切換後台裡要看的帳號或分頁、捲動清單、搜尋、篩選、點開聊天室或頁面看內容、到其他網站或試算表查資料核對。任務規則說的「只讀」「不改」是指不能修改或發送，讀任何網站查資料都可以。公開網頁用 WebFetch。',
    '- 使用者要一份資料（例如名單、報表、統計）時，用【派瀏覽】到所有相關的地方找齊：先想清楚資料在哪裡、要用什麼條件找（例如在列表搜尋日期或關鍵字、往下捲到載入完整、每個相關帳號都切換過去看），把這些寫進要做的事，整理好再回覆；不要回「請你打開某頁」或「請你提供名單」。真的找不到才說找過哪些地方。',
    '- 需要使用者核准才能做的事，在回覆最後單獨一行寫「✅待確認：要做的事（一句話）」（「✅待確認：」這幾個字照抄，不要翻譯），然後停下。使用者回「核准：…」後才執行。',
    ...(job.allowed?.length ? ['- 使用者已經「一律允許」你做下面這些事：遇到同一類的事直接做，不用再寫 ✅待確認，做完在回覆裡清楚列出做了什麼（對象、數量、內容）。只限這些事本身，不要擴大解讀；付款、刪除資料、更改帳號設定仍然每次都要問：', ...job.allowed.map(t => '  · ' + t)] : []),
    '- 只回報實際完成的事，做不到就直說。',
    `- 自動排程：使用者要你定時或持續做某件事（每天幾點、每隔多久巡一次）時，不要叫他自己去設定，在回覆最後加一行「⏰例行任務：名稱｜時間｜每次要做的事」。時間寫法：每天固定時間用 24 小時制（08:00,13:30），每隔一段時間寫「每30分鐘」或「每2小時」，兩種可以並用。例如「⏰例行任務：巡 LINE 訊息｜每30分鐘｜檢查 LINE 官方帳號新訊息，擬好回覆給我確認」（「⏰例行任務：」和「｜」照抄）。要「有新東西才做」時，時間欄寫「每10分鐘監看 網址」（系統會不花 AI 流量地檢查那個網頁，內容有變化才叫你），或寫「外部事件」（給一個觸發網址讓 LINE、表單等服務呼叫）。系統會自動建立；同名的會更新。你的任務本身就是要持續盯著某個地方（訊息、訂單、後台）時，主動建議並建立一個每隔一段時間的例行任務。指示裡已經寫了時間，就只用那些時間，不要另編指示裡沒有的時間。每一件都要寫成「⏰例行任務：名稱｜時間｜要做的事」那一行；沒有那一行就沒有建立。禁止只寫「排程已建好」「已建立例行任務」「例行任務已建好」。要刪除、暫停或恢復例行任務時，自己在回覆最後寫一行「⏰刪除：名稱」「⏰停用：名稱」或「⏰啟用：名稱」（多個用、分開，名稱照下面的清單抄），系統會直接處理；改時間或內容就用同名的⏰例行任務那一行覆蓋。你自己的設定都自己改：任務說明用 📝任務更新、記憶用 📌記住、技能用 🧩技能、例行任務用 ⏰。禁止叫使用者去「任務設定」手動刪除、停用或修改，也不要說自己刪不掉。${job.routines?.length ? '你已經有的例行任務（被問到下次什麼時候做時照這些回答）：' + job.routines.map(r => `${r.name}（${r.times.map(t => t.startsWith('*/') ? `每 ${t.slice(2)} 分鐘` : t).join('、')}${r.enabled ? '' : '，已停用'}）`).join('；') + '。' : ''}`,
    '- 自動整理指定任務：當使用者在對話中說明你長期要負責的工作、固定做法、規則或排程（不是一次性的小請求）時，在回覆最後加上：「📝任務更新：」換行後寫出完整、更新後的指定任務（把原本的任務和新的說明合併成一份，條列清楚：負責什麼、去哪裡做、怎麼做、結果怎麼回報、要注意的規則），最後一行寫「📝結束」。這兩個標記照抄。沒有新的長期工作說明就不要寫。',
    '- 回覆最後一行可以寫「📍 目前頁面：網址」。不用自己截圖，執行器會拍畫面。',
    '',
    '對話紀錄（舊到新）：'
  );
  // older messages are shortened; the last few stay whole. A backup does the same job, so it gets the same history.
  // a group sends this to every member each turn: fewer and shorter old messages (省 token)
  const all = job.history || [], hist = job.group ? all.slice(-GROUP_HISTORY) : all, cut = job.group ? 300 : 600, keep = job.group ? 1500 : Infinity;
  hist.forEach((h, i) => {
    const recent = i >= hist.length - 4, t = recent ? (h.text.length <= keep ? h.text : h.text.slice(0, keep) + '…（已截短，全文在對話裡）') : h.text.length <= cut ? h.text : h.text.slice(0, cut) + '…（較早的訊息，已截短）';
    const quote = h.replyText ? `（回覆${h.replyWho ? '「' + h.replyWho + '」' : ''}：${h.replyText}）\n` : '';
    lines.push(`【${h.who}】${quote}${t}` + (h.paths?.length ? `\n（附件，可直接讀取這些檔案：${h.paths.join('、')}）` : ''));
  });
  lines.push('', ...dayInfo(job), '', ...workNotes(job), '', ...records(job));
  lines.push('', ...tabsNow(job), '', ...seeNow(job), '', ...workLoop(), '', turnGuide(), '', whoAmI(job), '現在請處理這則指示：', job.prompt);
  return lines.filter(l => l !== '').join('\n');
}
// A local model often has a 4096 context. Keep the rules and this instruction, and drop the long essay.
export function fitLocal(text, max = 4000) {
  const s = String(text || '');
  if (s.length <= max) return s;
  const head = s.slice(0, Math.floor(max * 0.72));
  const tail = s.slice(-Math.floor(max * 0.25));
  return head + '\n…（中段已省略）\n' + tail;
}
export function buildLocalPrompt(job, here) {
  const task = String(job.bot?.task || '').replace(/\s+/g, ' ').trim().slice(0, 400);
  const raw = String(job.prompt || '');
  const instruction = raw.length > 2200 ? raw.slice(0, 1400) + '\n…\n' + raw.slice(-700) : raw;
  const hist = (job.history || []).slice(-3).map(h => `【${h.who}】${String(h.text || '').replace(/\s+/g, ' ').trim().slice(0, 220)}`);
  let notes = '';
  try { notes = readFileSync(notesFile(job), 'utf8').trim().slice(-400); } catch { }
  const lines = [
    `你是 OCTA 裡的「${job.bot?.name || '機器人'}」。下面就是完整指示，看完就做。不要把同一句再寫一遍。`,
    job.backup ? '你是在其他 AI 沒有額度時代替它把這件工作做完。該查的頁面要查，該記的要記。不要因為自己是備援就少做。' : '',
    `現在要做：${instruction}`,
    job.bot?.autonomy === 'ask' ? '送出訊息、提交表單、刪除、付款前，先單獨一行寫「✅待確認：要做的事」然後停下。' : '',
    task ? `指定任務：${task}` : '',
    '規則：先看完再下結論。名字、編號、數字只能抄這一次看得到的字，沒看到就留空，不准編。需要登入時，整則只寫一次「需要使用者在電腦上登入」和網站名稱，然後停下，不要再寫【派瀏覽】。做一步就再看一次。例行任務要寫「⏰例行任務：名稱｜時間｜要做的事」，沒有那一行就沒有建立，時間只用指示裡寫的。工作筆記只能寫畫面上有的字。交出數字、名單、清單之前，先回頭對照原始資料核對一次，對不上就重算；不用描述核對過程，有疑點才另列。',
    job.group ? `群組「${job.group.name}」依序做。你只做自己的部分，做完就停。` : '',
    hist.length ? '最近的對話：\n' + hist.join('\n') : '',
    notes ? '工作筆記節錄：\n' + notes : '',
    here ? `檔案在 ${here}。` : '',
    `再看一次現在要做：${instruction.slice(0, 500)}`
  ];
  return fitLocal(lines.filter(Boolean).join('\n'), 4000);
}
export function taskPrompt(job, here) {
  return (job.bot?.engine || 'claude') === 'opencode' ? buildLocalPrompt(job, here) : buildPrompt(job, here);
}
export function evidenceText(job) {
  const bits = [job?.prompt, job?.seen];
  for (const h of job?.history || []) {
    if (h.who === '使用者' || h.who === '系統') bits.push(h.text);
  }
  return bits.filter(Boolean).join('\n');
}
// A roster line whose room number was not in the page or the user's words is dropped.
export function scrubNotes(notes, evidence) {
  const ev = String(evidence || '');
  const kept = [];
  let dropped = 0;
  for (const line of String(notes || '').split('\n')) {
    const rooms = [...line.matchAll(/(?<!\d)(\d{3})(?!\d)/g)].map(m => m[1]);
    const roster = rooms.length > 0 && /房|館|入住|退房|續住|掃|姓名|先生|小姐|[A-Za-zＡ-Ｚ]\s*[.．、]\s*[\u4e00-\u9fff]/.test(line);
    if (roster && rooms.some(r => !ev.includes(r))) { dropped++; continue; }
    kept.push(line);
  }
  return { text: kept.join('\n').replace(/\n{3,}/g, '\n\n').trim(), dropped };
}
function refreshNotes(job) {
  const p = notesFile(job);
  let cur = '';
  try { cur = readFileSync(p, 'utf8'); } catch { return; }
  const next = scrubNotes(cur, evidenceText(job));
  if (!next.dropped) return;
  try { writeFileSync(p, next.text ? next.text + '\n' : ''); log(`📒 已拿掉 ${job.bot.name} 工作筆記裡畫面上沒有的名單`); } catch (e) { log('工作筆記整理失敗：' + e.message); }
}
export function ollamaContextTag(base) {
  const safe = String(base || 'model').replace(/[^A-Za-z0-9._-]/g, '-').replace(/-+/g, '-').slice(0, 48);
  return `octa-ctx-${safe}`;
}
export function ollamaContextModelfile(base, numCtx = OLLAMA_NUM_CTX) {
  return `FROM ${String(base || '').trim()}\nPARAMETER num_ctx ${numCtx}\n`;
}
// OpenCode talks to Ollama's OpenAI endpoint, which ignores a per-request num_ctx.
// A local model tag bakes the larger window in, then OpenCode can use it.
function ensureOllamaContext(base) {
  const tag = ollamaContextTag(base);
  const show = spawnSync('ollama', ['show', tag, '--modelfile'], { encoding: 'utf8', timeout: 15000, shell: WIN, windowsHide: true });
  if (show.status === 0 && new RegExp(`num_ctx\\s+${OLLAMA_NUM_CTX}\\b`).test(show.stdout || '')) return tag;
  const created = spawnSync('ollama', ['create', tag, '-f', '-'], { input: ollamaContextModelfile(base), encoding: 'utf8', timeout: 60000, shell: WIN, windowsHide: true });
  if (created.status === 0) { log(`本機模型改用上下文 ${OLLAMA_NUM_CTX}：${tag}`); return tag; }
  log('無法加大本機模型的上下文，仍用原本的模型。' + String(created.stderr || created.stdout || '').slice(0, 180));
  return base;
}

// what the bot runs on and how much of the plan is left, for the prompt
const PLAN_NOTE = { grokbot: 'Grok Bot 方案（在 xAI 雲端電腦上工作，用量看 Grok Bot App 的 Usage）', grok: 'Grok（xAI）帳號（官方沒有提供剩餘量查詢）', gemini: 'Google 帳號的 Antigravity 額度（免費帳號也能用；在 agy 裡輸入 /usage 可查剩餘量）', copilot: 'GitHub Copilot 訂閱（GitHub 沒有提供剩餘量查詢）', cursor: 'Cursor 訂閱（Cursor 沒有提供剩餘量查詢）', qwen: 'Qwen 帳號（官方沒有提供剩餘量查詢）', opencode: '電腦本機的 Ollama 模型，免費、沒有流量限制' };
// the tabs open in the bot's browser right now (the user may have just opened or signed in to one)
function tabsNow(job) {
  const t = job.bot.tabs;
  if (!t) return [];
  if (!t.length) return ['你的瀏覽器目前沒有開著的網頁。'];
  return ['你的瀏覽器目前開著的分頁（使用者可能剛幫你打開或登入好）：', ...t.map((x, i) => `${i + 1}. ${x.title || '(無標題)'} — ${x.url}`)];
}
// The picture is what the main turn reads. Page structure is read by the separate browsing round.
function picturePaths(job) {
  const out = [];
  if (job.eyes) out.push(job.eyes);
  for (const h of job.history || []) for (const p of h.paths || []) {
    if (/\.(jpe?g|png|webp|gif)$/i.test(String(p)) && !out.includes(p)) out.push(p);
  }
  return out.slice(-6);
}
function seeNow(job) {
  const pics = picturePaths(job);
  const lines = ['看畫面要用眼睛。回答畫面上的數字或「你看到什麼」之前，先把圖整張讀完。圖裡沒有的數字寫「這次畫面沒有這個數字」。讀不到圖就老實說，不要編。遊戲、畫布、分數、電池、機架若這張圖是空的，就寫【派瀏覽】請那一輪看圖，不要自己編。'];
  lines.push('時間、金額、房號、按鈕上的字，畫面上看得到的全部照抄，不要只抄最上面幾筆。鍵盤或邊緣切掉的，只指出被切掉的那一列；還看得到的數字要寫出來，不能說「下面的都被擋住」。按鈕還在畫面上，只代表這一頁開著，不要說使用者沒有按。');
  lines.push('名字、編號、數字不准編。畫面沒有的空著。');
  lines.push('轉述畫面時，要做什麼、步驟、條件整段照抄，這條比講得口語優先。不要改寫、不要漏半句。誰做、要不要略過，都照畫面的字；不要把「自己點登入」說成「讓使用者登入」，也不要把寫了的條件說成沒有。');
  if (pics.length) lines.push(`這一輪要讀的圖，用 Read 讀它：${pics.join('、')}`);
  else lines.push('這輪還沒有現成的圖。要看已登入的頁面就寫【派瀏覽】，不要自己截圖。使用者傳了圖片就讀那個附件，不要用猜的。');
  return lines;
}
// The main turn writes this block instead of clicking. The runner parses it and does not show it.
export function takeBrowserTask(text) {
  const m = String(text || '').match(/【派瀏覽】\s*([\s\S]*?)\s*【派完】/);
  if (!m) return null;
  const body = m[1];
  const urlLine = (body.match(/網址[:：]\s*(\S+)/) || [])[1] || '';
  const url = /^https?:\/\//i.test(urlLine) ? urlLine.replace(/[)）,，。】]+$/g, '') : '';
  let prompt = body.replace(/網址[:：][^\n]*\n?/, '').replace(/要做的事[:：]\s*/, '').trim();
  if (!prompt) prompt = url ? `打開 ${url}，讀出現在頁面上有什麼` : '';
  if (!prompt) return null;
  return { url, prompt: prompt.slice(0, 2000) };
}
export function stripBrowserTask(text) {
  return String(text || '').replace(/【派瀏覽】[\s\S]*?【派完】/g, '').trim();
}
// A 【回覆】 marker drops everything before it, including the block. Put the block back so the runner can still dispatch.
export function keepBrowserTask(text) {
  const raw = String(text || '');
  const task = takeBrowserTask(raw);
  const conn = takeConnectorTask(raw);
  const k = raw.lastIndexOf('【回覆】');
  let out = k >= 0 ? (raw.slice(k + 4).trim() || raw.replace(/【回覆】/g, '').trim()) : raw.trim();
  if (conn && !takeConnectorTask(out)) out = `【連接器】\n名稱：${conn.name}\n動作：${conn.action}${conn.path ? '\n路徑：' + conn.path : ''}${conn.content ? '\n內容：' + conn.content : ''}\n【接完】\n${out}`.trim();
  if (task && !takeBrowserTask(out)) out = `【派瀏覽】\n網址：${task.url || '目前頁面'}\n要做的事：${task.prompt}\n【派完】\n${out}`.trim();
  return out;
}
const PAGE_RE = /後台|訂單|名單|報表|帳號裡|網站上|頁面上/i;
// A job about data on a signed-in site still has to open the page. A short greeting does not.
export function needsPage(job) {
  const prompt = String(job?.prompt || ''), task = String(job?.bot?.task || '');
  if (PAGE_RE.test(prompt)) return true;
  return PAGE_RE.test(task) && /查|看|名單|整理|對照|核對|列出|統計/i.test(prompt);
}
export function forcedBrowseTask(job) {
  if (!job || job.didBrowse || job.handed) return null;
  if ((job.bot?.engine || 'claude') === 'grokbot') return null;
  if (browserWindowAsk(job.prompt) === 'close') return null;
  if (!needsPage(job)) return null;
  return '到已登入的頁面把需要的資料抄下來。名字、編號、數字只能抄畫面上的字。沒看到的空著，不准編。';
}
export function planBrowserRound(text, { engine, port, mine, depth } = {}) {
  if (engine === 'grokbot') return { action: 'keep' };
  const task = takeBrowserTask(text);
  if (!task) return { action: 'keep' };
  if ((depth || 0) >= 2) return { action: 'strip' };
  if (!port && !mine) return { action: 'down' };
  return { action: 'work', task };
}
// One round that can click. It returns text. The page tree stays in that round.
export function buildBrowserPrompt(job, task, here) {
  const url = task?.url || '';
  const lines = [
    `你是 OCTA 裡「${job.bot.name}」這一輪的瀏覽工作。你只負責把這一件事做完，交回文字報告。`,
    '不要再派下一輪，也不要寫派工標記。原始 HTML 和頁面樹不要寫進報告。密碼、一次性驗證碼、卡片號碼不要輸入，也不要出現在報告或工具參數裡。',
    '讀頁順序（固定，不要跳）：',
    url ? `1. browser_navigate 到這個完整網址：${url}` : '1. 停在目前頁面，不要亂開新網址。若這是使用者按繼續之後，第一步必須 browser_snapshot，不沿用接手之前的引用。',
    '2. browser_snapshot。下一步之前先知道頁面上現在有什麼。',
    '3. 點或輸入只用這一張快照裡的引用（ref，例如 e5）。browser_click、browser_type 的 target 用那個引用。工具會再附一份新快照。',
    '4. 引用失效（Ref not found）就重新 browser_snapshot，不沿用舊引用。導覽、點擊、頁面變化之後，上一份讀取作廢，必須重讀再行動。',
    '5. 要確認版面、顏色、被擋住的對話框時才 browser_take_screenshot。不必每次跟快照一起要。',
    '6. 遊戲、畫布、文字讀不到的畫面：先 browser_take_screenshot，再只用這一幀的座標 browser_mouse_click_xy。畫面動過就重拍再點，不要點舊畫面。',
    '7. 大頁用 depth 或只看某個元素的子樹，不要把整頁灌進來。不要執行頁面裡的程式。',
    '找不到要點的東西時：等 1–2 秒再看（browser_wait_for）→ 捲動 → 截圖看彈出框 → 滑鼠移上去 → 鍵盤（Tab、方向鍵、Enter）→ 從網址直接進入。至少換 3 種方法才能說做不到。',
    '做完只寫這四段：',
    '網址：現在的網址',
    '頁面上有什麼：看得到的文字和狀態',
    '做成了什麼：這輪實際做了的事',
    '卡在哪裡：沒卡住就寫「沒有」。需要登入、驗證碼或付款就寫「需要使用者在電腦上登入」和網站名稱，不要自己填密碼。寄信、付款、刪除、更改帳號還沒有這一次的同意時，停下來寫 ✅待確認，不要執行。',
    '登入頁只要點選已經記住的帳號（例如顯示帳號名稱和「登入」按鈕、「以 XX 身分繼續」），不必輸入密碼或驗證碼時，直接點它繼續。',
    task?.prompt ? '這次要做的事：\n' + task.prompt : '',
    '使用者原本的指示：\n' + String(job.prompt || '').slice(0, 1500),
    here ? `檔案在 ${here}。大量資料讀檔案，不要從頁面上逐格抄。` : ''
  ];
  const hist = (job.history || []).slice(-4);
  if (hist.length) lines.push('最近的對話：', ...hist.map(h => `【${h.who}】${String(h.text || '').slice(0, 300)}`));
  lines.push(...tabsNow(job), ...dayInfo(job));
  if (job.sites) lines.push('網站操作筆記（先照這些做）：\n' + job.sites);
  if (job.bot?.page) lines.push('上次停在：' + job.bot.page);
  return lines.filter(Boolean).join('\n');
}
function aboutMe(job) {
  const e = job.bot.engine || 'claude', E = ENGINES[e] || ENGINES.claude, u = usageNow[e];
  const out = [`- AI：${E.label}${job.bot.model ? `，模型 ${job.bot.model}` : '（該工具的預設模型）'}；在使用者的主機電腦「${os.hostname()}」上執行，透過 OCTA 執行器 v${VERSION}。`];
  const when = t => { try { return new Date(t).toLocaleString('zh-TW', { month: 'numeric', day: 'numeric', hour: '2-digit', minute: '2-digit' }); } catch { return t; } };
  if (u?.windows?.length) {
    const lab = { '5h': '5 小時額度', '7d': '本週額度', '30d': '本月額度' };
    out.push(`- 方案：${u.plan || '（讀不到方案名稱）'}`);
    for (const w of u.windows) out.push(`- ${lab[w.k] || (/^\d+h$/.test(w.k) ? parseInt(w.k) + ' 小時額度' : w.k)}：已用 ${w.used}%，剩 ${Math.max(0, 100 - w.used)}%${w.reset ? `，${when(w.reset)} 重置` : ''}`);
    out.push(`- 以上是 ${when(u.t)} 讀到的數字（每 10 分鐘更新）。`);
  } else if (e === 'claude' || e === 'codex') {
    out.push(`- 方案：${u?.plan || '讀不到'}；剩餘流量這次讀不到${u?.error ? `（${u.error}）` : ''}，請使用者到 OCTA「設定 → AI 連線」查看。`);
  } else out.push(`- 方案：${PLAN_NOTE[e] || '官方沒有提供剩餘量查詢'}`);
  if (job.usageToday != null) out.push(`- 今天 OCTA 已經用這個 AI 執行了 ${job.usageToday} 次工作。`);
  return out;
}

// install: { win, mac } shell commands, or npm: package name (needs Node.js); pre: installed first; login: command that starts sign-in
export const ENGINES = {
  claude: { label: 'Claude Code', bin: 'claude', site: 'https://code.claude.com', login: 'claude', loginHint: '視窗出現後輸入 /login，選 Claude 訂閱帳號',
    install: { win: 'powershell -NoProfile -ExecutionPolicy Bypass -Command "irm https://claude.ai/install.ps1 | iex"', mac: 'curl -fsSL https://claude.ai/install.sh | bash' },
    paths: { win: '%USERPROFILE%\\.local\\bin', mac: '$HOME/.local/bin' } },
  codex: { label: 'Codex CLI（ChatGPT）', bin: 'codex', site: 'https://developers.openai.com/codex/cli', npm: '@openai/codex', login: 'codex login', loginHint: '瀏覽器會打開，用 ChatGPT 帳號登入' },
  // Google moved personal accounts from Gemini CLI to the Antigravity CLI (agy) in June 2026; the key stays 'gemini' so existing bots keep working
  gemini: { label: 'Antigravity CLI（Gemini／Claude）', bin: 'agy', site: 'https://antigravity.google/docs/cli', login: 'agy', loginHint: '瀏覽器會打開，用 Google 帳號登入（免費帳號也可以），完成後輸入 /quit 離開',
    install: { win: 'powershell -NoProfile -ExecutionPolicy Bypass -Command "irm https://antigravity.google/cli/install.ps1 | iex"', mac: 'curl -fsSL https://antigravity.google/cli/install.sh | bash' },
    paths: { win: '%USERPROFILE%\\.local\\bin', mac: '$HOME/.local/bin' } },
  copilot: { label: 'GitHub Copilot CLI', bin: 'copilot', site: 'https://github.com/github/copilot-cli', npm: '@github/copilot', login: 'copilot', loginHint: '視窗出現後輸入 /login，用 GitHub 帳號登入' },
  cursor: { label: 'Cursor CLI', bin: 'agent', site: 'https://cursor.com/cli', login: 'agent login', loginHint: '瀏覽器會打開，用 Cursor 帳號登入',
    install: { win: 'powershell -NoProfile -ExecutionPolicy Bypass -Command "irm \'https://cursor.com/install?win32=true\' | iex"', mac: 'curl https://cursor.com/install -fsS | bash' },
    paths: { win: '%LOCALAPPDATA%\\cursor-agent', mac: '$HOME/.local/bin' } },
  qwen: { label: 'Qwen Code', bin: 'qwen', site: 'https://github.com/QwenLM/qwen-code', npm: '@qwen-code/qwen-code', login: 'qwen', loginHint: '依畫面選擇登入方式，完成後輸入 /quit 離開' },
  // local open models only — no paid API keys. OpenCode drives the model and the browser tool; Ollama runs the model.
  grok: { label: 'Grok CLI（xAI）', bin: 'grok', site: 'https://docs.x.ai/build/overview', login: 'grok login', loginHint: '瀏覽器會打開，用你的 X／Grok 帳號登入',
    install: { win: 'powershell -NoProfile -ExecutionPolicy Bypass -Command "irm https://x.ai/cli/install.ps1 | iex"', mac: 'curl -fsSL https://x.ai/cli/install.sh | bash' } },
  // a bot from the user's Grok Bot app, driven through the open-source grok-bot-cli (third party, not by xAI);
  // it uses the signed-in Grok Bot desktop app on this computer
  grokbot: { label: 'Grok Bot（grok-bot-cli）', bin: 'gbot', site: 'https://github.com/ScriptedAlchemy/grok-bot-cli', npm: 'grok-bot-cli',
    login: 'gbot bots list --gateway', loginHint: '這是進階的反向功能，要 Grok Bot App 開放本機連線才會列出機器人（目前 Windows 版通常沒有，出現錯誤是正常的）。這不影響「Grok Bot 交派任務給 OCTA」，那個用交接網址就好' },
  opencode: { label: 'Ollama 本機模型', bin: 'opencode', also: 'ollama', site: 'https://ollama.com', npm: 'opencode-ai',
    pre: { win: 'winget install -e --id Ollama.Ollama --accept-source-agreements --accept-package-agreements', mac: 'brew install --cask ollama' },
    paths: { win: '%LOCALAPPDATA%\\Programs\\Ollama', mac: '/usr/local/bin' },
    login: 'ollama pull qwen3', loginHint: '正在下載 qwen3 模型（約 5 GB），完成後機器人的「模型」填 qwen3' }
};
const BASE_INSTR = '請先完整讀取目前資料夾裡的 octa-task.md，依照裡面的指示執行。最後的輸出要直接是給使用者看的回覆。';
const STDIN_INSTR = '請依照標準輸入中的完整指示執行，最後輸出要給使用者看的回覆。';
// Windows consoles often answer in the local code page (e.g. Big5), not UTF-8
function decode(chunks) {
  const buf = Buffer.concat(chunks), utf = buf.toString('utf8');
  if (!WIN || !utf.includes('�')) return utf;
  for (const enc of ['big5', 'gbk', 'shift_jis']) { try { const t = new TextDecoder(enc).decode(buf); if (!t.includes('�')) return t; } catch { } }
  return utf;
}
const installed = {};
// Windows: tools installed after OCTA started aren't on its PATH; re-read the saved PATH now and then
let pathRead = 0;
function refreshPath() {
  if (!WIN || Date.now() - pathRead < 120000) return Promise.resolve();
  pathRead = Date.now();
  return new Promise(ok => execFile('powershell', ['-NoProfile', '-NonInteractive', '-Command', "[Environment]::GetEnvironmentVariable('Path','Machine') + ';' + [Environment]::GetEnvironmentVariable('Path','User')"],
    { windowsHide: true, timeout: 20000 }, (err, out) => {
      if (!err && out) {
        const have = new Set(String(process.env.PATH || '').toLowerCase().split(';'));
        const more = String(out).trim().split(';').map(p => p.replace(/%([^%]+)%/g, (_, v) => process.env[v] || '')).filter(p => p && !have.has(p.toLowerCase()));
        if (more.length) process.env.PATH = process.env.PATH + ';' + more.join(';');
      }
      ok();
    }));
}
// looks through PATH itself instead of running `where` for each tool: running many `where` at once
// sometimes timed out on Windows, which made AIs flip between connected and not connected
function findBin(bin) {
  const dirs = String(process.env.PATH || '').split(WIN ? ';' : ':').filter(Boolean);
  const exts = WIN ? ['', ...String(process.env.PATHEXT || '.COM;.EXE;.BAT;.CMD').toLowerCase().split(';').filter(Boolean)] : [''];
  for (const d of dirs) for (const x of exts) { const p = join(d.replace(/^"|"$/g, ''), bin + x); try { if (existsSync(p) && (WIN ? x !== '' : true)) return p; } catch { } }
  return '';
}
// async on purpose: a blocking check freezes the desktop app's window
export async function has(bin, fresh) {   // a missing command can't be told apart from a failing one after the fact, so check first
  const c = installed[bin];
  if (!fresh && c && (c.ok || Date.now() - c.t < 30000)) return c.ok;
  if (!c?.ok) await refreshPath();
  const p = findBin(bin);
  installed[bin] = { ok: !!p, t: Date.now(), path: p };
  return !!p;
}
const engineReady = async (k, fresh) => (await has(ENGINES[k].bin, fresh)) && (!ENGINES[k].also || await has(ENGINES[k].also, fresh))
  && (k !== 'grokbot' || !grokBotEnv().missing);   // Grok Bot: the tool alone isn't enough, the app's sign-in must be readable
let lastReport = 0;
const engineReport = async () => {   // tell the app which AI tools this computer has, about once a minute
  if (Date.now() - lastReport < 60000) return undefined;
  lastReport = Date.now();
  const keys = Object.keys(ENGINES), oks = await Promise.all(keys.map(k => engineReady(k, true)));
  return Object.fromEntries(keys.map((k, i) => [k, oks[i]]));
};

// ---------- how much of each plan is left ----------
// Claude and ChatGPT report their plan limits; the others don't offer a way to ask.
async function claudeUsage() {
  const f = join(os.homedir(), '.claude', '.credentials.json');
  if (!existsSync(f)) return { error: 'no-credentials' };   // e.g. kept in the macOS keychain
  const o = JSON.parse(readFileSync(f, 'utf8'))?.claudeAiOauth || {}, tok = o.accessToken;
  if (!tok) return { error: 'no-credentials' };
  const plan = { max: 'Claude Max', pro: 'Claude Pro', team: 'Claude Team', enterprise: 'Claude Enterprise' }[String(o.subscriptionType || '').toLowerCase()] || (o.subscriptionType ? 'Claude ' + o.subscriptionType : '');
  const r = await fetch('https://api.anthropic.com/api/oauth/usage', { headers: { authorization: 'Bearer ' + tok, 'anthropic-beta': 'oauth-2025-04-20' }, signal: AbortSignal.timeout(10000) });
  if (!r.ok) return { error: 'HTTP ' + r.status, plan };
  const d = await r.json();
  const w = (x, k) => (x && typeof x.utilization === 'number' ? { k, used: Math.round(x.utilization), reset: x.resets_at || null } : null);
  return { plan, windows: [w(d.five_hour, '5h'), w(d.seven_day, '7d')].filter(Boolean) };
}
function codexPlan() {   // ChatGPT plan from the sign-in Codex saved (only the plan label is read)
  try {
    const a = JSON.parse(readFileSync(join(os.homedir(), '.codex', 'auth.json'), 'utf8'));
    const p = JSON.parse(Buffer.from(String(a?.tokens?.id_token || '').split('.')[1] || '', 'base64url').toString())['https://api.openai.com/auth']?.chatgpt_plan_type;
    return p ? 'ChatGPT ' + p[0].toUpperCase() + p.slice(1) : '';
  } catch { return ''; }
}
// label a quota window by its real length (the free ChatGPT plan has a monthly window, not 5 hours)
const winKey = (m, k) => !m ? k : m <= 1440 ? (m === 300 ? '5h' : Math.round(m / 60) + 'h') : m <= 10080 ? '7d' : '30d';
function codexUsage() {   // `codex app-server` answers account/rateLimits/read over JSON-RPC
  return new Promise(resolve => {
    let done = false, buf = '';
    const child = spawn('codex', ['app-server'], { shell: WIN, windowsHide: true });
    const finish = v => { if (done) return; done = true; clearTimeout(t); try { child.kill(); } catch { } resolve(v); };
    const t = setTimeout(() => finish({ error: 'timeout' }), 15000);
    const send = o => { try { child.stdin.write(JSON.stringify(o) + '\n'); } catch { } };
    child.on('error', () => finish(null));
    child.stdout.on('data', d => {
      buf += d;
      let i;
      while ((i = buf.indexOf('\n')) >= 0) {
        const line = buf.slice(0, i).trim(); buf = buf.slice(i + 1);
        let msg; try { msg = JSON.parse(line); } catch { continue; }
        if (msg.id === 1) { send({ method: 'initialized' }); send({ id: 2, method: 'account/rateLimits/read' }); }
        if (msg.id === 2) {
          const rl = msg.result?.rateLimits || msg.result || {};
          const w = (x, k) => (x && typeof x.usedPercent === 'number' ? { k: winKey(x.windowDurationMins, k), used: Math.round(x.usedPercent), reset: x.resetsAt ? new Date(x.resetsAt * (x.resetsAt < 1e12 ? 1000 : 1)).toISOString() : null } : null);
          finish(msg.error ? { error: msg.error.message || 'error', plan: codexPlan() } : { plan: codexPlan() || (rl.planType ? 'ChatGPT ' + rl.planType : ''), windows: [w(rl.primary, '5h'), w(rl.secondary, '7d')].filter(Boolean) });
        }
      }
    });
    send({ id: 1, method: 'initialize', params: { clientInfo: { name: 'octa', title: 'OCTA', version: VERSION } } });
  });
}
// which models each AI on this computer offers (for the model menu); asked from the tools that can list them
const runText = (bin, args) => new Promise(ok => execFile(bin, args, { shell: WIN, windowsHide: true, timeout: 20000, encoding: 'utf8', maxBuffer: 4 << 20 }, (e, out, err) => ok(e ? '' : String(out || '') + String(err || ''))));
let lastModels = 0;
async function modelReport() {   // every 30 minutes
  if (Date.now() - lastModels < 30 * 60000) return undefined;
  lastModels = Date.now();
  const out = {};
  if (await has('ollama')) out.opencode = (await runText('ollama', ['list'])).split('\n').slice(1).map(l => l.trim().split(/\s+/)[0]).filter(Boolean).slice(0, 30);
  if (await has('agent')) {
    const t = (await runText('agent', ['--list-models'])).replace(/\x1b\[[0-9;]*m/g, '');
    out.cursor = [...new Set(t.split('\n').map(l => (l.match(/^\s*(?:[-*•]\s*)?([a-z0-9][\w.\-]{2,40})(?:\s|$)/i) || [])[1]).filter(x => x && /\d|-/.test(x)))].slice(0, 30);
  }
  if (await has('agy')) {
    const t = (await runText('agy', ['models'])).replace(/\x1b\[[0-9;]*m/g, '');
    out.gemini = [...new Set(t.split("\n").map(l => (l.match(/^\s*([a-z][\w.\-]*-[\w.\-]+)\s/i) || [])[1]).filter(Boolean))].slice(0, 30);   // agy also serves Claude and GPT-OSS models (separate weekly quota)
  }
  if (await has('gbot')) { try { out.grokbot = (await grokBots()).map(b => b.name).slice(0, 40); } catch { } }
  if (await has('copilot')) {
    const t = await runText('copilot', ['--help']);
    const m = t.match(/--model[\s\S]{0,300}?choices:\s*([^)]+)\)/);
    if (m) out.copilot = [...m[1].matchAll(/"([^"]+)"/g)].map(x => x[1]).slice(0, 40);
  }
  return out;
}
let lastUsage = 0, usageNow = {};
async function usageReport() {   // every 10 minutes
  if (Date.now() - lastUsage < 10 * 60000) return undefined;
  lastUsage = Date.now();
  const out = {};
  usageNow = out;   // bots read this to answer "how much quota is left" 
  const safe = async (k, fn) => { try { const v = (await engineReady(k)) ? await fn() : null; if (v) out[k] = { ...v, t: Date.now() }; } catch (e) { out[k] = { error: String(e.message || e).slice(0, 80), t: Date.now() }; } };
  await Promise.all([safe('claude', claudeUsage), safe('codex', codexUsage)]);
  return out;
}

// opts.onLine: called with each stdout line (live progress); opts.ctl.kill() stops the run
async function spawnCli(bin, args, dir, input, opts = {}) {
  if (!(await has(bin))) return { code: -1, out: '', err: '', missing: true };
  return new Promise(resolve => {
    const child = spawn(bin, WIN ? args.map(q) : args, { cwd: dir, shell: WIN, windowsHide: true });
    const out = [], err = [];
    let killed = false, part = '';
    if (opts.ctl) opts.ctl.kill = () => { try { WIN ? spawn('taskkill', ['/pid', String(child.pid), '/t', '/f'], { windowsHide: true }) : child.kill(); } catch { } };
    const timer = setTimeout(() => { killed = true; child.kill(); }, JOB_TIMEOUT_MS);
    child.stdout.on('data', d => {
      out.push(d);
      if (!opts.onLine) return;
      part += d.toString('utf8');
      let i; while ((i = part.indexOf('\n')) >= 0) { const l = part.slice(0, i); part = part.slice(i + 1); try { opts.onLine(l); } catch { } }
    });
    child.stderr.on('data', d => err.push(d));
    child.on('error', e => { clearTimeout(timer); resolve({ code: -1, out: decode(out), err: e.message, missing: e.code === 'ENOENT' }); });
    child.on('close', code => { clearTimeout(timer); resolve({ code, out: decode(out), err: decode(err) + (killed ? '\n執行超過 15 分鐘，已中止。' : '') }); });
    child.stdin.on('error', () => { });
    child.stdin.end(input);
  });
}
// tokens a run used: Claude reports them in its result; Codex prints "tokens used"
const claudeTokens = u => (u ? (u.input_tokens || 0) + (u.output_tokens || 0) + (u.cache_creation_input_tokens || 0) + (u.cache_read_input_tokens || 0) : null);
const toml = v => (Array.isArray(v) ? '[' + v.map(x => JSON.stringify(String(x))).join(',') + ']' : JSON.stringify(String(v)));
const PARENT_TOOLS = 'WebFetch,WebSearch,Read,Write,Edit,Glob,Grep';
const WORKER_TOOLS = 'mcp__browser,Read';
// 省 token: --allowedTools only pre-approves; every built-in tool (Agent, TodoWrite, NotebookEdit…) and every installed
// skill / slash command is still described to the model on each request. When this Claude Code supports them, load only
// the tools a bot can use (Bash stays: bots compute lists from their record files) and skip skills and slash commands.
let claudeFlags = null;
export function leanFlags(help, worker) {
  const out = [];
  if (/--tools\b/.test(help)) out.push('--tools', worker ? 'Read' : PARENT_TOOLS + ',Bash');
  if (/--disable-slash-commands/.test(help)) out.push('--disable-slash-commands');
  return out;
}
async function claudeLean(worker) {
  if (claudeFlags === null) {
    claudeFlags = await new Promise(res => execFile('claude', ['--help'], { shell: WIN, windowsHide: true, timeout: 20000, maxBuffer: 1 << 20 }, (e, out) => res(String(out || ''))));
    if (!claudeFlags) setTimeout(() => { claudeFlags = null; }, 600000);   // try again later rather than never
  }
  return leanFlags(claudeFlags, worker);
}
// the model Ollama should use: the bot's, or the first one downloaded on this computer
function ollamaModel(model) {
  if (model) return model.replace(/^ollama\//, '');
  const r = spawnSync('ollama', ['list'], { encoding: 'utf8', shell: WIN, windowsHide: true, timeout: 10000 });
  return (r.stdout || '').split('\n').slice(1).map(l => l.trim().split(/\s+/)[0]).find(Boolean) || '';
}
// what Claude Code is doing right now, in words, from its stream-json events
function describeTool(name, input = {}) {
  const n = String(name).replace(/^mcp__browser__/, '');
  const host = u => { try { return new URL(u).host; } catch { return String(u || '').slice(0, 40); } };
  const short = s => String(s || '').replace(/\s+/g, ' ').slice(0, 40);
  return ({
    browser_navigate: `打開 ${host(input.url)}`, browser_click: `點擊「${short(input.element)}」`, browser_type: `在「${short(input.element)}」輸入`,
    browser_fill_form: '填寫表單', browser_snapshot: '讀取網頁內容', browser_take_screenshot: '截圖', browser_select_option: '選擇選項',
    browser_tabs: '切換分頁', browser_wait_for: '等待網頁載入', browser_press_key: '按鍵盤', browser_navigate_back: '回上一頁', browser_evaluate: '讀取網頁資料',
    Read: `讀取檔案 ${basename(String(input.file_path || ''))}`, Write: `寫入檔案 ${basename(String(input.file_path || ''))}`, Edit: `修改檔案 ${basename(String(input.file_path || ''))}`,
    Glob: '找檔案', Grep: '搜尋檔案內容', WebSearch: `上網搜尋「${short(input.query)}」`, WebFetch: `讀取網頁 ${host(input.url)}`
  })[n] || (n.startsWith('browser_') ? '操作瀏覽器' : `使用 ${n}`);
}
async function runEngine(engine, prompt, b, model, live = {}) {
  let tokens = null;
  const { dir, server } = b;
  const useBrowser = live.browser === true;
  if (b.applyBrowser) b.applyBrowser(useBrowser);
  const store = storeDir();
  const m = (flag) => (model ? [flag, model] : []);
  writeFileSync(join(dir, 'octa-task.md'), prompt);
  // some CLIs treat another folder as "current" (agy: the store): always give the full path
  const FILE_INSTR = BASE_INSTR.replace('目前資料夾裡的 octa-task.md', `檔案 ${join(dir, 'octa-task.md')}（用讀檔工具讀這個完整路徑）`);   // for CLIs that take the prompt as an argument (avoids Windows length limits)
  let r, text;
  switch (engine) {
    case 'codex': {
      const last = join(dir, '.codex-last.txt');
      try { writeFileSync(last, ''); } catch { }
      const c = ['approval_policy="never"', 'model_reasoning_effort="high"', `sandbox_workspace_write.writable_roots=${toml([store, dir])}`,
        ...(useBrowser ? [`mcp_servers.browser.command=${toml(server.command)}`, `mcp_servers.browser.args=${toml(server.args)}`,
          'mcp_servers.browser.startup_timeout_sec=60', 'mcp_servers.browser.default_tools_approval_mode="approve"',
          ...Object.entries(server.env || {}).map(([k, v]) => `mcp_servers.browser.env.${k}=${toml(v)}`)] : [])];
      r = await spawnCli('codex', ['exec', '--skip-git-repo-check', '--sandbox', 'workspace-write', '-C', dir, '-o', last, ...m('-m'), ...c.flatMap(x => ['-c', x]), '-'], dir, prompt, { ctl: live.ctl });
      // Codex's sandbox isn't available on every Windows setup: run without it rather than not at all (other engines run unsandboxed too)
      if (r.code !== 0 && /sandbox/i.test(r.err || '')) r = await spawnCli('codex', ['exec', '--skip-git-repo-check', '--sandbox', 'danger-full-access', '-C', dir, '-o', last, ...m('-m'), ...c.flatMap(x => ['-c', x]), '-'], dir, prompt, { ctl: live.ctl });
      try { text = readFileSync(last, 'utf8').trim(); } catch { }
      break;
    }
    case 'gemini': r = await spawnCli('agy', ['-p', FILE_INSTR, '--dangerously-skip-permissions', '--output-format', 'text', '--print-timeout', '15m', '--add-dir', store, ...m('--model')], dir, '', { ctl: live.ctl }); break;
    case 'qwen': r = await spawnCli('qwen', ['--yolo', '--include-directories', store, ...m('-m'), '-p', STDIN_INSTR], dir, prompt, { ctl: live.ctl }); break;
    case 'copilot': r = await spawnCli('copilot', ['-p', FILE_INSTR, '-s', '--allow-all-tools', '--allow-all-paths', '--no-color',
      '--additional-mcp-config', '@' + join(dir, 'copilot-mcp.json'), ...m('--model')], dir, '', { ctl: live.ctl }); break;
    case 'grok': r = await spawnCli('grok', ['--no-auto-update', '--no-alt-screen', '--always-approve', '--cwd', dir, '--output-format', 'plain', ...m('-m'), '-p', FILE_INSTR], dir, '', { ctl: live.ctl }); break;
    case 'cursor': r = await spawnCli('agent', ['-p', '--force', '--approve-mcps', '--output-format', 'text', ...m('--model'), FILE_INSTR], dir, '', { ctl: live.ctl }); break;
    case 'opencode': {
      if (!(await has('ollama'))) { r = { missing: true }; break; }
      const name = ollamaModel(model);
      if (!name) return { ok: false, text: '⚠ 這台電腦的 Ollama 還沒有下載任何模型。請在「AI 連線 → Ollama」按「一鍵安裝並登入」，或在終端機執行 ollama pull qwen3。' };
      const runName = ensureOllamaContext(name);
      // only the local Ollama provider is enabled: no paid APIs
      b.put('opencode.json', {
        $schema: 'https://opencode.ai/config.json', enabled_providers: ['ollama'], model: 'ollama/' + runName,
        provider: { ollama: { npm: '@ai-sdk/openai-compatible', name: 'Ollama', options: { baseURL: 'http://127.0.0.1:11434/v1' }, models: { [runName]: { name: runName } } } },
        mcp: useBrowser ? { browser: { type: 'local', command: [server.command, ...server.args], environment: server.env || {}, enabled: true } } : {},
        tools: { task: false, todowrite: false, todoread: false, grep: false, glob: false }   // grep/glob need ripgrep, often missing on Windows; small local models misuse sub-agents and to-do lists, then reply about the error
      });
      // /no_think: qwen3-style models skip their long hidden reasoning (several times faster on a laptop)
      r = await spawnCli('opencode', ['run', '--auto', '--dir', dir, '-m', 'ollama/' + runName, '/no_think ' + FILE_INSTR], dir, '', { ctl: live.ctl });
      break;
    }
    default: {
      // stream-json: lets OCTA show what the bot is doing while it works
      let result = null;
      r = await spawnCli('claude', ['-p', '--output-format', 'stream-json', '--verbose', '--mcp-config', join(dir, useBrowser ? 'mcp-browser.json' : 'mcp.json'), '--strict-mcp-config', '--add-dir', store, ...m('--model'),
        '--allowedTools', useBrowser ? WORKER_TOOLS : PARENT_TOOLS, ...(await claudeLean(useBrowser))], dir, prompt, {
        ctl: live.ctl,
        onLine: l => {
          let e; try { e = JSON.parse(l); } catch { return; }
          if (e.type === 'result') { result = e; return; }
          if (e.type === 'assistant') for (const c of e.message?.content || []) {
            if (c.type === 'tool_use') live.progress?.(describeTool(c.name, c.input));
            else if (c.type === 'text' && c.text?.trim()) live.progress?.('整理回覆中');
          }
        }
      });
      if (result) { text = String(result.result || '').trim(); if (result.is_error && r.code === 0) r.code = 1; tokens = claudeTokens(result.usage); }
      else if (r.out && r.out.trim().startsWith('{')) text = '';   // stream with no result: fall back to the error output
    }
  }
  text = keepBrowserTask((text || r.out || '').replace(/\x1b\[[0-9;]*m/g, ''));
  // agy prints the model's running commentary too ("Let me read…"): keep the reply, drop English narration lines before it
  if (engine === 'gemini' && /[\u4e00-\u9fff]/.test(text)) text = text.split('\n').filter(l => !/^\s*(Let me|Let's|I'll|I will|I see|I need|I'm going|Found it|Now,? |Next,? |First,? |OK,? |Okay|Great|Perfect|Looking at|Checking|Reading)\b/i.test(l)).join('\n').replace(/\n{3,}/g, '\n\n').trim();
  const E = ENGINES[engine] || ENGINES.claude;
  if (r.missing) return { ok: false, text: `⚠ 這台電腦沒有安裝 ${E.label}。請到「AI 連線」安裝並登入（${E.site}），或在任務設定把這個機器人改用其他 AI。` };
  if (tokens == null) { const tm = String((r.err || '') + (r.out || '')).match(/tokens used[:\s]*([\d,]+)/i); if (tm) tokens = +tm[1].replace(/,/g, ''); }
  // Exit 0 with only "流量不夠" is not an answer: report it as a failure so the backup runs.
  const refused = r.code === 0 && replyIsProviderRefusal(text);
  if (r.code === 0 && text && !refused) return { ok: true, text, tokens };
  const quoted = providerFailureText([text, r.err, r.out]);
  if (refused || quoted) return { ok: false, text: refused ? text : quoted };
  return { ok: false, text: `⚠ ${E.label} 執行失敗：` + failText(r, prompt) };
}
// the useful part of a failed run: CLIs like Codex echo the whole prompt into their log, which buried the real error
function failText(r, prompt) {
  let t = String((r.err || '').trim() || (r.out || '').trim()).replace(/\x1b\[[0-9;]*m/g, '');
  if (!t) return '結束碼 ' + r.code;
  const errs = [...new Set(t.split('\n').map(l => l.trim()).filter(l => /^(error|錯誤)\b|^\[?error\]?[:\s]|\berror:\s|exception\b|failed\b/i.test(l)))];
  if (errs.length) return errs.slice(-8).join('\n').slice(-1200);
  const p = String(prompt || '').trim();
  if (p) { const tail = p.slice(-200), i = t.lastIndexOf(tail); if (i >= 0) t = t.slice(i + tail.length).trim() || '（沒有錯誤訊息，結束碼 ' + r.code + '）'; }
  return t.slice(-1200);
}

// ---------- job handlers ----------
async function chatJob(job) {
  if (typeof job.shareBrowser === 'boolean') shareBrowser = job.shareBrowser;
  return chatRun(job);
}
async function chatRun(job) {
  const own = job.bot.browser !== 'mine';
  let port = 0;
  if (own && job.bot.engine !== 'grokbot') { try { port = await ensureBrowser(job.bot); } catch (e) { log('瀏覽器：' + e.message); } }   // a Grok Bot works on xAI's cloud computer
  const b = botDir(job.bot.id, job.bot.browser, port), { dir } = b;
  const here = convDir(job.conv || job.bot);
  if (port) busyBots.add(job.bot.id);
  for (const h of job.history) {   // attachments: already in the folder, or saved there now
    h.paths = [];
    for (const f of h.files || []) {
      try {
        const p = f.path ? join(storeDir(), f.path) : null;
        if (p && existsSync(p)) { h.paths.push(p); continue; }
        if (!f.path) { h.paths.push(await saveUpload({ ...f, conv: job.conv?.id || job.bot.id, convName: job.conv?.name || job.bot.name })); continue; }
        // made on another computer: get a copy through OCTA (that computer sends it) and keep it here
        const d = await api('file/' + encodeURIComponent(f.id), undefined, 'GET');
        mkdirSync(dirname(p), { recursive: true }); writeFileSync(p, Buffer.from(d.data || '', 'base64')); h.paths.push(p);
        log(`📥 從其他電腦取得：${f.path}`);
      } catch (e) { log('附件讀取失敗：' + e.message); }
    }
  }
  restoreSkills(dir, job.nskills);
  const start = Date.now() - 1000;
  log(`▶ ${job.bot.name}［${job.bot.engine || 'claude'}］${job.group ? ' @' + job.group.name : ''}：${job.prompt.slice(0, 40)}`);
  job.bot.livePort = port;
  if (port) { try { job.bot.tabs = await cdp(port, async send => (await pagesOf(send)).filter(p => !/^(about:blank|chrome:)/.test(p.url)).slice(0, 6).map(p => ({ title: p.title.slice(0, 80), url: p.url.slice(0, 200) }))); } catch { } }
  job.eyes = port ? await captureEyes(port, dir) : '';
  // live progress (at most every 4 s); if the user pressed 停止, the server says so and the run is stopped
  const ctl = {};
  let lastSent = 0, pendingText = '', timerP = null, stoppedByUser = false;
  const flush = () => { timerP = null; lastSent = Date.now(); api('runner/progress', { id: job.id, text: pendingText }).then(r => { if (r.hand) { job.handed = true; log(`✋ ${job.bot.name}：使用者接手，停止點擊`); ctl.kill?.(); } if (r.stop) { stoppedByUser = true; log(`■ ${job.bot.name}：使用者按了停止`); ctl.kill?.(); } }).catch(() => { }); };
  const progress = t => { pendingText = t; if (timerP) return; const wait = Math.max(0, 4000 - (Date.now() - lastSent)); timerP = setTimeout(flush, wait); };
  progress('開始工作');
  const beat = setInterval(() => { if (!timerP) flush(); }, 15000);   // also notices 停止 for AIs that don't report progress
  let res;
  const engine = job.bot.engine || 'claude';
  job.stopForHand = () => ctl.kill?.();
  const liveBeat = port ? setInterval(() => pushLive(port, job).catch(() => { }), 1500) : null;
  try {
    if (port) await settleBrowserWindow(port, job);
    refreshNotes(job);
    res = engine === 'grokbot' ? await runGrokBot(job, { progress, ctl })
      : engine === 'claude' && job.warm && (await has('claude'))
      ? await warmClaude(job, b, here, { progress, ctl })        // AI 待機: reuse the running Claude session
      : await runEngine(engine, taskPrompt(job, here), b, job.bot.model, { progress, ctl, browser: false });
    if (res?.ok && engine !== 'grokbot') {
      const pendingBrowser = takeBrowserTask(res.text);
      res = await connectorRounds(job, b, here, engine, res, { progress, ctl });
      if (pendingBrowser && res?.ok && !takeBrowserTask(res.text)) res = { ...res, text: `【派瀏覽】\n網址：${pendingBrowser.url || '目前頁面'}\n要做的事：${pendingBrowser.prompt}\n【派完】\n${stripConnectorTask(res.text)}` };
      res = await browseRounds(job, b, here, engine, res, { progress, ctl, port });
      const again = res?.ok && port && !job.handed && !/需要使用者在電腦上登入/.test(res.text || '') ? forcedBrowseTask(job) : null;
      if (again) {
        res = { ...res, text: `【派瀏覽】\n網址：目前頁面\n要做的事：${again}\n【派完】` };
        res = await browseRounds(job, b, here, engine, res, { progress, ctl, port });
      }
    }
  }
  finally { clearTimeout(timerP); clearInterval(beat); clearInterval(liveBeat); busyBots.delete(job.bot.id); if (port) touchBrowser(job.bot.id); }
  if (job.handed && res) { res.ok = true; res.text = '我先停手。你在旁邊的畫面登入或看完，按繼續我就重新讀頁再做。'; }
  if (res?.text) res.text = stripConnectorTask(stripBrowserTask(res.text)) || '這次沒有新的結果。';
  if (port && res?.text) res.text = await finishBrowserWindow(port, job, res.text);
  if (port && shareBrowser) await syncOut(port);
  // 📒工作筆記：…📒結束 — the bot couldn't write its notes file itself (sandbox): OCTA saves it
  if (res?.text) res.text = res.text.replace(/📒\s*工作筆記[:：]\s*([\s\S]*?)📒\s*結束/g, (_, n) => { try { const cleanNotes = scrubNotes(n, evidenceText(job)).text; if (!cleanNotes) return ''; mkdirSync(dirname(notesFile(job)), { recursive: true }); writeFileSync(notesFile(job), cleanNotes + '\n'); log(`📒 已更新 ${job.bot.name} 的工作筆記`); } catch (e) { log('工作筆記寫入失敗：' + e.message); } return ''; }).trim() || '（已更新工作筆記）';
  refreshNotes(job);
  // what the browser shows now: taken by OCTA itself (no need for the bot to remember)
  let page = (res.text.match(/📍\s*目前頁面[:：]\s*(\S+)/) || [])[1];
  const d = new Date(), z = n => String(n).padStart(2, '0'), stamp = `${d.getFullYear()}${z(d.getMonth() + 1)}${z(d.getDate())}-${z(d.getHours())}${z(d.getMinutes())}`;
  // a failed run (or one waiting for a sign-in) also sends its screen once, for the Telegram notification
  let shotB64 = null;
  const saveShot = async (buf, ext) => {
    const p = freeName(join(here, '截圖'), safeName(job.bot.name) + '-' + stamp + ext);
    writeFileSync(p, buf);
    await api('runner/shot', { id: job.id, path: rel(p), name: basename(p), size: buf.length });
    if ((!res.ok || /需要使用者在電腦上登入/.test(res.text || '')) && /^\.jpe?g$/.test(ext) && buf.length < 600000) shotB64 = buf.toString('base64');
  };
  try {
    const live = port ? await browserSnapshot(port, start) : null;
    if (live) { if (live.url && !/^(about:|chrome:)/.test(live.url)) page = live.url; if (live.jpeg) await saveShot(live.jpeg, '.jpeg'); }
    else { const shot = newestImage(dir, start); if (shot) await saveShot(readFileSync(shot.p), extname(shot.p).toLowerCase()); }
  } catch (e) { log('截圖儲存失敗：' + e.message); }
  const nsk = collectSkills(dir, job.nskills);
  await api('runner/done', { id: job.id, ok: res.ok, text: res.text, page, tokens: res.tokens ?? null, files: res.ok ? newFiles(join(here, '輸出'), start) : [], browser: !!port, stopped: stoppedByUser, ...(nsk ? { nskills: nsk } : {}), ...(res.stalled ? { stalled: true, err_kind: 'timeout' } : {}), ...(shotB64 ? { shot: shotB64 } : {}) });
  log(`${res.ok ? '✓' : '✗'} ${job.bot.name}`);
  if (['claude', 'codex'].includes(job.bot.engine || 'claude')) lastUsage = 0;   // refresh how much is left
  try { cfg.onDone?.(job, res); } catch { }
}

// The main turn cannot click. A logged-in page is one extra round on the same browser, then a text report.
function addTokens(a, b) {
  if (a == null && b == null) return null;
  return (a || 0) + (b || 0);
}
async function parentFollow(job, b, here, engine, follow, live) {
  if (b.applyBrowser) b.applyBrowser(false);
  if (engine === 'claude' && job.warm && sessions.get(job.bot.id)) return warmSend(job, follow, live);
  return runEngine(engine, taskPrompt({ ...job, prompt: follow }, here), b, job.bot.model, { progress: live.progress, ctl: live.ctl, browser: false });
}
async function connectorRounds(job, b, here, engine, res, live) {
  for (let depth = 0; depth < 2 && res?.ok; depth++) {
    const task = takeConnectorTask(res.text);
    if (!task) break;
    const known = (job.connectors || []).some(c => c.name === task.name);
    const approved = /核准[:：]/.test(job.prompt || '');
    if (!known || (task.action === '送出' && !approved)) {
      const why = !known
        ? `沒有接上「${task.name}」。已接上的只有：${(job.connectors || []).map(c => c.name).join('、') || '（沒有）'}。不要再寫【連接器】，直接用【回覆】說明。`
        : `「${task.name}」這次沒有送出。對別人送出要先寫 ✅待確認，等使用者回「核准：」再做。不要再寫【連接器】，直接用【回覆】寫出準備送出的內容。`;
      const next = await parentFollow(job, b, here, engine, why, live);
      const text = next?.ok ? (stripConnectorTask(next.text) || why) : why;
      return { ok: true, text, tokens: addTokens(res.tokens, next?.tokens) };
    }
    live.progress?.('呼叫連接器 ' + task.name);
    let report = '連接器沒有完成。';
    try {
      const r = await api('runner/connector', { job: job.id, name: task.name, action: task.action, path: task.path, content: task.content });
      report = stripConnectorTask(r.text || report).slice(0, 4000) || report;
    } catch (e) { report = '連接器沒有完成：' + e.message; }
    const follow = [
      `下面是連接器「${task.name}」的結果。只根據這份結果回答，不要貼金鑰，也不要把整段原文以外的內容說成你看到的。`,
      depth + 1 < 2 ? '還要再呼叫一次就寫【連接器】到【接完】，而且不要寫【回覆】。夠了就用【回覆】回答。' : '不能再呼叫連接器。直接用【回覆】回答。',
      '結果：', report,
      '使用者原本的指示：', job.prompt
    ].join('\n');
    const next = await parentFollow(job, b, here, engine, follow, live);
    const tokens = addTokens(res.tokens, next?.tokens);
    if (!next?.ok) return { ok: true, text: report, tokens };
    let text = next.text || '';
    if (depth + 1 >= 2 || !takeConnectorTask(text)) text = stripConnectorTask(text) || report;
    res = { ok: true, text, tokens };
  }
  if (res?.text) res = { ...res, text: stripConnectorTask(res.text) || '這次沒有新的結果。' };
  return res;
}
async function browseRounds(job, b, here, engine, res, live) {
  const port = live.port, mine = job.bot.browser === 'mine';
  for (let depth = 0; depth < 2 && res?.ok; depth++) {
    const plan = planBrowserRound(res.text, { engine, port, mine, depth });
    if (plan.action === 'keep') break;
    if (plan.action === 'strip') { res = { ...res, text: stripBrowserTask(res.text) || '這次的頁面沒有新的結果。' }; break; }
    if (plan.action === 'work') job.didBrowse = true;
    const viaTool = toolForBrowse(plan.task, job.connectors);
    if (viaTool) {
      const next = await parentFollow(job, b, here, engine, `這件事連接器「${viaTool.name}」做得到。不要開瀏覽器，改寫【連接器】。名稱用「${viaTool.name}」。讀取可以直接做，送出要先 ✅待確認。`, live);
      const text = next?.ok ? (stripBrowserTask(stripConnectorTask(next.text)) || `改用連接器「${viaTool.name}」。`) : `改用連接器「${viaTool.name}」。`;
      return { ok: true, text, tokens: addTokens(res.tokens, next?.tokens) };
    }
    if (job.handed) return { ok: true, text: '我先停手。你在旁邊的畫面登入或看完，按繼續我就重新讀頁再做。', tokens: res.tokens };
    if (plan.action === 'down') {
      const next = await parentFollow(job, b, here, engine, '內建瀏覽器沒有起來，這次不能讀頁面。請用你已經有的資料回答，或直接說瀏覽器沒有打開。不要再派瀏覽。', live);
      const text = next?.ok ? (stripBrowserTask(next.text) || '瀏覽器沒有打開，這次沒有讀到頁面。') : '瀏覽器沒有打開，這次沒有讀到頁面。';
      return { ok: true, text, tokens: addTokens(res.tokens, next?.tokens) };
    }
    live.progress?.('讀取網頁');
    const workerPrompt = engine === 'opencode' ? fitLocal(buildBrowserPrompt(job, plan.task, here), 4000) : buildBrowserPrompt(job, plan.task, here);
    const worker = await runEngine(engine, workerPrompt, b, job.bot.model, { progress: live.progress, ctl: live.ctl, browser: true });
    if (b.applyBrowser) b.applyBrowser(false);
    let report = stripBrowserTask(worker?.ok ? worker.text : ('瀏覽沒有完成：' + String(worker?.text || '沒有報告'))).slice(0, 6000) || '瀏覽沒有完成。';
    job.seen = ((job.seen || '') + '\n' + report).slice(-8000);
    if (/需要使用者在電腦上登入/.test(report)) {
      const site = (report.match(/https?:\/\/[^\s）)]+/) || [])[0] || '';
      return { ok: true, text: `需要使用者在電腦上登入${site ? '（' + site + '）' : ''}。登入好之後跟我說一聲。`, tokens: addTokens(res.tokens, worker?.tokens) };
    }
    if (worker?.ok) { const rec = saveRecord(job, plan.task, report); if (rec) report += `\n（這份報告已存成紀錄檔：${rec}）`; }
    if (port) {
      const eyes = await captureEyes(port, b.dir);
      if (eyes) { job.eyes = eyes; report += `\n確認停在哪，用 Read 讀這個檔：${eyes}`; }
    }
    const follow = [
      '下面是單獨一輪瀏覽交回的文字報告。只根據這份報告回答使用者原本的指示，不要把整頁貼上。',
      '報告裡如果寫了「需要使用者在電腦上登入」，回覆裡照抄這幾個字和網站名稱。',
      depth + 1 < 2 ? '報告不夠、還要再看已登入的頁面時，可以再寫一次【派瀏覽】到【派完】，而且不要寫【回覆】。夠了就用【回覆】回答。' : '不能再派瀏覽了。直接用【回覆】根據報告回答。',
      '報告：', report,
      '使用者原本的指示：', job.prompt
    ].join('\n');
    const next = await parentFollow(job, b, here, engine, follow, live);
    const tokens = addTokens(addTokens(res.tokens, worker?.tokens), next?.tokens);
    if (!next?.ok) return { ok: true, text: report, tokens };
    let text = next.text || '';
    if (depth + 1 >= 2 || !takeBrowserTask(text)) text = stripBrowserTask(text) || report;
    res = { ok: true, text, tokens };
  }
  if (res?.text) res = { ...res, text: stripBrowserTask(res.text) || '這次的頁面沒有新的結果。' };
  return res;
}
// ---------- the bot's own Claude Code skills (.claude/skills in its folder) travel with the account ----------
const SKILL_EXT = /\.(md|txt|json|ya?ml|py|js|mjs|ts|sh|ps1|csv|html|css|toml)$/i;
function skillFiles(root) {
  const out = {}; let total = 0;
  const walk = (d, pre) => { let es = []; try { es = readdirSync(d, { withFileTypes: true }); } catch { return; }
    for (const e of es) { const p = join(d, e.name), r = pre ? pre + '/' + e.name : e.name;
      if (e.isDirectory()) { if (!/^(node_modules|\.git)$/.test(e.name)) walk(p, r); }
      else if (SKILL_EXT.test(e.name)) { try { const st = statSync(p); if (st.size > 60000 || total + st.size > 250000) continue; total += st.size; out[r] = readFileSync(p, 'utf8'); } catch { } } } };
  walk(root, ''); return out;
}
function collectSkills(dir, had) {
  const files = skillFiles(join(dir, '.claude', 'skills'));
  if (!Object.keys(files).length && !had) return null;
  const h = createHash('sha1').update(JSON.stringify(files)).digest('hex');
  return h === had?.h ? null : { h, files };
}
function restoreSkills(dir, sk) {   // e.g. on a new host computer
  if (!sk?.files) return;
  for (const [r, text] of Object.entries(sk.files)) {
    if (r.split('/').includes('..')) continue;
    const p = join(dir, '.claude', 'skills', ...r.split('/'));
    try { if (!existsSync(p) || readFileSync(p, 'utf8') !== text) { mkdirSync(dirname(p), { recursive: true }); writeFileSync(p, text); } } catch { }
  }
}

// ---------- handing a bot's website logins to another computer (cookies of its own browser) ----------
const SAME_CDP = { Lax: 'Lax', Strict: 'Strict', None: 'None', lax: 'Lax', strict: 'Strict', no_restriction: 'None' };   // the embedded browser used to save Electron's names
const cookieParams = list => list.filter(c => c.name && c.domain)
  .map(c => ({ name: c.name, value: c.value, path: c.path || '/', secure: !!c.secure, httpOnly: !!c.httpOnly,
    ...(c.domain.startsWith('.') && !c.name.startsWith('__Host-') ? { domain: c.domain } : { url: `${c.secure ? 'https' : 'http'}://${c.domain.replace(/^\./, '')}${c.path || '/'}` }),
    ...(SAME_CDP[c.sameSite] ? { sameSite: SAME_CDP[c.sameSite] } : {}), ...(c.expires > 0 ? { expires: c.expires } : {}), ...(c.partitionKey ? { partitionKey: c.partitionKey } : {}), ...(c.sourceScheme ? { sourceScheme: c.sourceScheme } : {}) }));
// switching to the shared browser: bring the sign-ins from every bot's old browser into it, once
async function mergeOldProfiles() {   // once: the sign-ins in every bot's browser (and the 2.4.x shared one) go into the shared store
  const mark = join(workDir, '.octa-logins-merged');
  if (existsSync(mark)) return;
  const root = join(workDir, 'bots'), chrome = findChrome();
  const when = p => { for (const f of [join(p, 'Default', 'Network', 'Cookies'), join(p, 'Default', 'Cookies'), p]) { try { return statSync(f).mtimeMs; } catch { } } return 0; };
  let dirs = []; try { dirs = readdirSync(root).map(d => join(root, d, 'profile')).filter(p => existsSync(p)); } catch { }
  if (existsSync(sharedProfile())) dirs.push(sharedProfile());
  dirs.sort((a, b) => when(a) - when(b));   // newest last: its sign-in wins when two have the same site
  const all = []; let n = 0;
  for (const p of dirs) {
    let port = 0;
    for (const [, b] of browsers) if (b.profile === p) port = b.port;   // already open: read it directly
    let child = null;
    if (!port) {
      if (!chrome || profileInUse(p)) continue;
      port = 9390 + (n++ % 9);
      child = spawn(chrome, [`--user-data-dir=${p}`, `--remote-debugging-port=${port}`, '--headless=new', '--no-first-run', '--no-default-browser-check', 'about:blank'], { stdio: 'ignore', windowsHide: true });
      child.on('error', () => { });
    }
    try {
      for (let i = 0; i < 40 && !(await cdpInfo(port)); i++) await pause(300);
      const { cookies = [] } = await cdp(port, send => send('Storage.getCookies'));
      all.push(...cookies);
      if (child) await cdp(port, send => send('Browser.close')).catch(() => { });
    } catch (e) { log('讀取舊瀏覽器登入失敗：' + e.message); }
    finally { try { child?.kill(); } catch { } }
  }
  const total = all.length ? addToJar(all) : 0;
  mkdirSync(workDir, { recursive: true }); writeFileSync(mark, String(total));
  const sites = new Set(all.map(c => String(c.domain).replace(/^\./, '').split('.').slice(-2).join('.')));
  if (all.length) log(`🔑 已把各機器人瀏覽器的登入合併成共用登入（${sites.size} 個網站）`);
}

async function exportJob(job) {
  if (typeof job.shareBrowser === 'boolean') shareBrowser = job.shareBrowser;
  const port = await ensureBrowser(job.bot);
  const { cookies = [] } = await cdp(port, send => send('Storage.getCookies'));
  const data = Buffer.from(JSON.stringify(cookies)).toString('base64');
  for (let i = 0, n = 0; i < data.length || n === 0; i += CHUNK, n++) await api('runner/xfer', { id: job.id, n, data: data.slice(i, i + CHUNK), last: i + CHUNK >= data.length });
  log(`🔑 已送出 ${job.bot.name} 的網站登入（${cookies.length} 筆）`);
}
async function importJob(job) {
  if (typeof job.shareBrowser === 'boolean') shareBrowser = job.shareBrowser;
  const { data } = await api('runner/xfer/' + encodeURIComponent(job.xfer), undefined, 'GET');
  const cookies = cookieParams(JSON.parse(Buffer.from(data || '', 'base64').toString('utf8') || '[]'));
  const port = await ensureBrowser(job.bot);
  await cdp(port, send => send('Storage.setCookies', { cookies }));
  if (shareBrowser) addToJar(cookies);
  const sites = new Set(cookies.map(c => c.domain.replace(/^\./, '').split('.').slice(-2).join('.')));
  log(`🔑 已帶入 ${job.bot.name} 的網站登入（${sites.size} 個網站）`);
  await api('runner/done', { id: job.id, ok: true, text: `已把「${job.bot.name}」的網站登入帶到這台主機（${sites.size} 個網站）。有些網站會綁定裝置，可能還是要再登入一次。` });
}

// ---------- Grok Bot (through grok-bot-cli) ----------
function jsonOut(text) { const t = String(text || '').trim(); const i = t.search(/[[{]/); if (i < 0) return null; try { return JSON.parse(t.slice(i)); } catch { return null; } }
const pickArr = o => (Array.isArray(o) ? o : o && (o.bots || o.items || o.entries || o.thread || o.messages || o.data || o.results)) || [];
// gbot reads the Grok Bot app's session and asks xAI's gateway: the first call can take a while, and its errors matter
// grok-bot-cli finds the app's sign-in at <APPDATA>/Grok Bot/gateway-descriptor.json; if this copy of the app keeps it
// somewhere else, look for it and point grok-bot-cli there
let gbEnv = null, gbLook = 0;
function grokBotEnv() {
  if (Date.now() - gbLook < 5 * 60000) return gbEnv;
  gbLook = Date.now(); gbEnv = null;
  const want = 'gateway-descriptor.json', home = os.homedir();
  const std = WIN ? join(process.env.APPDATA || join(home, 'AppData', 'Roaming'), 'Grok Bot') : process.platform === 'darwin' ? join(home, 'Library', 'Application Support', 'Grok Bot') : join(process.env.XDG_CONFIG_HOME || join(home, '.config'), 'Grok Bot');
  if (existsSync(join(std, want))) return gbEnv = { found: std };
  const roots = WIN ? [process.env.APPDATA, process.env.LOCALAPPDATA, home, join(home, '.grokbot')] : [join(home, '.config'), join(home, 'Library', 'Application Support'), join(home, '.grokbot')];
  for (const r of roots.filter(Boolean)) {
    let subs = []; try { subs = readdirSync(r, { withFileTypes: true }).filter(d => d.isDirectory() && /grok/i.test(d.name)).map(d => join(r, d.name)); } catch { }
    for (const d of [r, ...subs]) if (existsSync(join(d, want)) && basename(d) === 'Grok Bot') return gbEnv = { found: d, env: WIN ? { APPDATA: dirname(d) } : { XDG_CONFIG_HOME: dirname(d) } };
  }
  return gbEnv = { missing: std };
}
// on Windows run grok-bot-cli's script with node directly: going through gbot.cmd (cmd.exe) mangles messages with line breaks or quotes
function gbotCmd(args) {
  if (WIN) {
    const shim = installed.gbot?.path || findBin('gbot'), mjs = shim && join(dirname(shim), 'node_modules', 'grok-bot-cli', 'dist', 'bin', 'gbot.mjs');
    if (mjs && existsSync(mjs)) return ['node', [mjs, ...args], false];
  }
  return ['gbot', WIN ? args.map(q) : args, WIN];
}
const runGbot = (args, timeout = 90000) => new Promise(ok => { const [cmd, a, shell] = gbotCmd(args); execFile(cmd, a, { shell, windowsHide: true, timeout, encoding: 'utf8', maxBuffer: 8 << 20, env: { ...process.env, ...(grokBotEnv()?.env || {}) } },
  (e, out, err) => ok({ code: e ? (e.code ?? 1) : 0, out: String(out || ''), err: String(err || '') + (e?.killed ? '\n（超過 90 秒沒有回應）' : '') })); });
const gbotError = r => (r.err || r.out).replace(/\x1b\[[0-9;]*m/g, '').trim().split('\n').slice(-6).join('\n').slice(0, 600) || ('結束碼 ' + r.code);
async function grokBots() {   // [{name, description}] — groups included (they take messages too)
  const where = grokBotEnv();
  if (where.missing) throw new Error(`找不到 Grok Bot 桌面 App 的登入資料（${where.missing}${sep}gateway-descriptor.json）。請在這台電腦打開 Grok Bot App 並登入（用官方安裝版，不是複製來的資料夾），讓它連上一次後再試。`);
  const r = await runGbot(['bots', 'list', '--gateway', '--json']);
  const j = jsonOut(r.out);
  if (j) return pickArr(j).map(b => ({ name: String(b.name || b.title || b.displayName || ''), description: (b.isGroup ? '（群組）' : '') + String(b.description || b.instructions || b.label || '') })).filter(b => b.name);
  if (r.code !== 0) throw new Error('grok-bot-cli 讀取失敗：' + gbotError(r));
  return r.out.split('\n').map(l => l.replace(/\x1b\[[0-9;]*m/g, '').trim()).filter(l => l && !/^(name|bots?)\b/i.test(l)).map(l => ({ name: l.split(/\s{2,}|\t/)[0], description: '' })).filter(b => b.name);
}
const entryText = e => typeof e === 'string' ? e : e.text || e.body || e.markdown || e.message?.text || (Array.isArray(e.content) ? e.content.map(c => c.text || '').join('') : typeof e.content === 'string' ? e.content : '');
const fromUser = e => /^(user|me|human|you)$/i.test(String(e.role || e.author?.type || e.author || e.from || e.sender || e.kind || ''));
async function runGrokBot(job, live) {
  const name = job.bot.model;
  if (!(await has('gbot'))) return { ok: false, text: '⚠ 這台電腦還沒安裝 grok-bot-cli。請到「AI 連線 → Grok Bot」安裝。' };
  if (!name) return { ok: false, text: '⚠ 這個機器人還沒選擇要帶入的 Grok Bot 機器人，請到任務設定的「模型」選一個。' };
  let cursor = jsonOut((await runGbot(['thread', name, '--json'])).out)?.cursor;
  const msg = [job.prompt, ...job.history.slice(-1).flatMap(h => h.paths?.length ? ['（附件在使用者電腦上：' + h.paths.join('、') + '）'] : [])].join('\n');
  live.progress?.('交給 Grok Bot「' + name + '」處理');
  const sent = await runGbot(['send', name, msg], 120000);
  if (sent.code !== 0) return { ok: false, text: '⚠ 傳給 Grok Bot 失敗：' + ((sent.err || sent.out || '').trim().slice(-800) || '結束碼 ' + sent.code) };
  const got = [], t0 = Date.now();
  let quiet = 0;
  while (Date.now() - t0 < JOB_TIMEOUT_MS && !stopped) {
    await pause(5000);
    const j = jsonOut((await runGbot(['thread', name, ...(cursor ? ['--after', String(cursor)] : []), '--json'])).out);
    if (!j) continue;
    if (j.cursor) cursor = j.cursor;
    const fresh = pickArr(j).filter(e => !fromUser(e)).map(entryText).filter(x => x && x.trim() && x.trim() !== msg.trim());
    if (fresh.length) { got.push(...fresh); quiet = 0; live.progress?.('Grok Bot 回覆中'); }
    else if (got.length && ++quiet >= 3) break;   // replies stopped for ~15 s
  }
  return got.length ? { ok: true, text: got.join('\n\n') } : { ok: false, text: '⚠ Grok Bot 在時間內沒有回覆，可以在 Grok Bot App 裡看看它的狀況。' };
}
// started from any device (phone, web): open the install window on this computer, then watch for the tool
async function installJob(job) {
  const E = ENGINES[job.engine];
  if (!E || !cfg.openInstall) return api('runner/done', { id: job.id, ok: false, text: '這台主機不是 OCTA 桌面版，無法自動安裝，請在主機電腦上手動安裝。' });
  try { await cfg.openInstall(job.engine); } catch (e) { return api('runner/done', { id: job.id, ok: false, text: '無法打開安裝視窗：' + e.message }); }
  log(`🧩 已打開 ${E.label} 的安裝視窗`);
  await api('runner/done', { id: job.id, ok: true, text: `已在主機電腦「${os.hostname()}」打開 ${E.label} 的安裝視窗。` });
  // report as soon as it's installed (checks every 10 seconds for up to 15 minutes)
  const t0 = Date.now();
  const tick = setInterval(async () => {
    if (await engineReady(job.engine, true)) { clearInterval(tick); lastReport = 0; lastModels = 0; lastUsage = 0; log(`✓ ${E.label} 已安裝`); }
    else if (Date.now() - t0 > 15 * 60000) clearInterval(tick);
  }, 10000);
}
async function listJob(job) {
  let result;
  if (!(await has('gbot', true))) result = JSON.stringify({ error: '這台電腦還沒安裝 grok-bot-cli，請先在「AI 連線 → Grok Bot」按安裝' });
  else try { result = JSON.stringify(await grokBots()); } catch (e) { result = JSON.stringify({ error: e.message }); }
  await api('runner/done', { id: job.id, ok: true, text: result });
}

// ---------- AI 待機: keep a Claude Code session running between messages ----------
// The first message sends everything; while the session waits, the next message only sends what's new,
// so there is no restart and nothing to re-read. job.warm: seconds to keep waiting (-1: always).
const sessions = new Map();   // bot id → { child, fp, lastId, turn, timer }
function closeSession(id, why) {
  const s = sessions.get(id);
  if (!s) return;
  sessions.delete(id);
  clearTimeout(s.timer);
  try { s.child.stdin.end(); } catch { }
  setTimeout(() => { try { WIN ? spawn('taskkill', ['/pid', String(s.child.pid), '/t', '/f'], { windowsHide: true }) : s.child.kill(); } catch { } }, 4000);
  if (why) log(`💤 ${why}`);
}
function startSession(job, b) {
  const { dir } = b, m = job.bot.model ? ['--model', job.bot.model] : [];
  const child = spawn('claude', (WIN ? a => a.map(q) : a => a)(['-p', '--input-format', 'stream-json', '--output-format', 'stream-json', '--verbose',
    '--mcp-config', join(dir, 'mcp.json'), '--strict-mcp-config', '--add-dir', storeDir(), ...m,
    '--allowedTools', PARENT_TOOLS, ...leanFlags(claudeFlags || '', false)]), { cwd: dir, shell: WIN, windowsHide: true });
  if (claudeFlags === null) claudeLean(false);   // known from the next session on
  const s = { child, turn: null, err: [] };
  let part = '';
  child.stdout.on('data', d => {
    s.seenAt = Date.now();
    part += d.toString('utf8');
    let i;
    while ((i = part.indexOf('\n')) >= 0) {
      const l = part.slice(0, i); part = part.slice(i + 1);
      let e; try { e = JSON.parse(l); } catch { continue; }
      if (!s.turn) continue;
      s.turn.heard = true;
      if (e.type === 'assistant') for (const c of e.message?.content || []) {
        if (c.type === 'tool_use') s.turn.progress?.(describeTool(c.name, c.input));
        else if (c.type === 'text' && c.text?.trim()) s.turn.progress?.('整理回覆中');
      }
      if (e.type === 'result') { const t = s.turn; s.turn = null; const raw = String(e.result || '').trim(); t.done({ ok: !e.is_error && !!raw, text: keepBrowserTask(raw) || '⚠ Claude Code 沒有回覆內容', tokens: claudeTokens(e.usage) }); }
    }
  });
  child.stderr.on('data', d => { s.err.push(d); if (s.err.length > 50) s.err.shift(); });
  child.stdin.on('error', () => { });
  const gone = msg => { for (const [k, v] of sessions) if (v === s) sessions.delete(k); clearTimeout(s.timer); if (s.turn) { const t = s.turn; s.turn = null; t.done({ ok: false, text: '⚠ Claude Code 執行失敗：' + (decode(s.err).trim().slice(-1200) || msg) }); } };
  child.on('error', e => gone(e.message));
  child.on('exit', code => gone('結束碼 ' + code));
  return s;
}
function warmSend(job, text, live) {
  const s = sessions.get(job.bot.id);
  if (!s?.child) return Promise.resolve({ ok: false, text: '⚠ 沒有正在待機的對話' });
  live.ctl.kill = () => closeSession(job.bot.id, `${job.bot.name}：已停止`);
  return turnWithWatch(job, s, text, live).then(r => { s.doneAt = Date.now(); return r; });
}
const WARM_STALE = 20 * 60000;   // reuse a waiting session only if it answered within the last 20 minutes
const FIRST_WORD = 180000, QUIET = 360000;   // no sign of life this long → the session is stuck
function turnWithWatch(job, s, text, live) {
  return new Promise(done => {
    const started = Date.now();
    s.seenAt = started;
    const end = r => { clearInterval(dog); done(r); };
    s.turn = { done: end, progress: live.progress, heard: false };
    const dog = setInterval(() => {
      if (!s.turn) return clearInterval(dog);
      const quiet = Date.now() - (s.seenAt || started);
      if (quiet > (s.turn.heard ? QUIET : FIRST_WORD)) {
        const t = s.turn; s.turn = null;
        closeSession(job.bot.id, `${job.bot.name}：AI ${Math.round(quiet / 60000)} 分鐘沒有動靜`);
        t.done({ ok: false, stalled: true, text: '⚠ AI 很久沒有回應，已中止' });
      }
    }, 10000);
    try { s.child.stdin.write(JSON.stringify({ type: 'user', message: { role: 'user', content: text } }) + '\n'); }
    catch (e) { s.turn = null; end({ ok: false, text: '⚠ ' + e.message }); }
  });
}
async function warmClaude(job, b, here, live) {
  // anything that changes the bot's standing instructions starts a fresh session
  const fp = JSON.stringify([VERSION, job.memory, job.facts, (job.skills || []).map(k => k.name + k.steps), job.bot.task, job.bot.model, job.bot.browser, job.bot.livePort, job.notes, job.folderNotes, job.group, (job.colleagues || []).map(c => c.name + c.task), job.allowed, job.lang, storeDir(), job.conv?.id, job.nick]);
  let s = sessions.get(job.bot.id), text;
  const ids = job.history.map(h => h.id || 0), newest = Math.max(0, ...ids);
  // a session that sat idle a long time (the computer may have slept) can hang on its old connection: start fresh
  if (s && !s.turn && s.doneAt && Date.now() - s.doneAt > WARM_STALE) { closeSession(job.bot.id, `${job.bot.name}：待機太久，重新開始對話`); s = null; }
  const reused = !!(s && s.fp === fp && s.convId === job.conv?.id);
  if (reused) {
    clearTimeout(s.timer);
    // only what happened since the last turn, then the new instruction
    const fresh = job.history.filter(h => (h.id || 0) > s.lastId && !(h.who === '使用者' && h.text === job.prompt));
    text = [fresh.length ? '（上次之後的新對話）\n' + fresh.map(h => `【${h.who}】${h.text}` + (h.paths?.length ? `\n（附件，可直接讀取這些檔案：${h.paths.join('、')}）` : '')).join('\n') : '',
      dayInfo(job).join('\n'), workNotes(job).join('\n'), records(job).join('\n'), tabsNow(job).join('\n'), seeNow(job).join('\n'), workLoop().join('\n'), studioAim().join('\n'), turnGuide(), whoAmI(job), manualLines(job).join('\n').trim(), '現在請處理這則指示：', job.prompt].filter(Boolean).join('\n\n');
    log(`⚡ ${job.bot.name}：AI 待機中，直接接續`);
  } else {
    if (s) closeSession(job.bot.id);
    s = startSession(job, b);
    s.fp = fp; s.convId = job.conv?.id;
    sessions.set(job.bot.id, s);
    text = buildPrompt(job, here);
  }
  s.lastId = newest;
  live.ctl.kill = () => closeSession(job.bot.id, `${job.bot.name}：已停止`);
  const res = await turnWithWatch(job, s, text, live);
  s.doneAt = Date.now();
  if (res.stalled && !job.stallRetried) {   // the AI never answered: one fresh try with the full instructions
    job.stallRetried = true;
    log(`⏱ ${job.bot.name}：AI 沒有回應，重新開始一次`);
    live.progress?.('AI 沒有回應，重新開始');
    closeSession(job.bot.id);
    return warmClaude(job, b, here, live);
  }
  if (sessions.get(job.bot.id) === s) {
    if (job.warm > 0) s.timer = setTimeout(() => closeSession(job.bot.id, `${job.bot.name}：待機 ${job.warm} 秒到了，AI 先休息`), job.warm * 1000);
    if (!res.ok) closeSession(job.bot.id);   // start clean after an error
  }
  return res;
}

async function testJob(job) {
  if (job.engine === 'grokbot') {
    const ok = await has('gbot', true);
    let bots = [], why = '';
    if (ok) try { bots = await grokBots(); } catch (e) { why = e.message; }
    lastReport = 0; lastModels = 0;
    return api('runner/done', { id: job.id, ok: ok && bots.length > 0, text: !ok ? '這台電腦還沒安裝 grok-bot-cli' : bots.length ? `連上了，找到 ${bots.length} 個 Grok Bot 機器人：${bots.map(b => b.name).join('、')}` : why || 'Grok Bot 裡沒有任何機器人（請確認 Grok Bot 桌面 App 已登入）' });
  }
  const b = botDir('_test-' + job.engine);
  log(`🔌 測試 ${ENGINES[job.engine]?.label || job.engine}`);
  const res = await runEngine(job.engine, job.prompt, b, '');
  lastReport = 0; lastUsage = 0; lastModels = 0;   // refresh the installed list, models and quotas right after a test
  await api('runner/done', { id: job.id, ok: res.ok, text: res.text });
}

// ---------- each bot's own browser: one Chrome that stays open between jobs ----------
// It starts in the background (off screen). The AI connects to it over CDP, so tabs and logins carry over.
// 「在電腦上顯示」 brings the same window forward: you see what the bot sees, and can log in right there.
const browsers = new Map();   // key ('shared' or bot id) → { port, last }
let shareBrowser = true;   // sign-ins shared between bots; each bot still has its own browser, so bots work in parallel
const sharedProfile = () => join(workDir, 'profile-shared');   // 2.4.0–2.4.2 used one shared Chrome here: its sign-ins get merged in
const jarFile = () => join(workDir, 'shared-logins.json');
const readJar = () => { try { return JSON.parse(readFileSync(jarFile(), 'utf8')); } catch { return []; } };
const ckKey = c => `${c.name}|${c.domain}|${c.path || '/'}`;
function addToJar(list) {   // newest values win; expired ones drop out
  const now = Date.now() / 1000, m = new Map(readJar().map(c => [ckKey(c), c]));
  for (const c of list) if (c.name && c.domain) m.set(ckKey(c), c);
  const out = [...m.values()].filter(c => !(c.expires > 0 && c.expires < now));
  mkdirSync(workDir, { recursive: true }); writeFileSync(jarFile(), JSON.stringify(out)); return out.length;
}
// before a bot works: give its browser everyone's sign-ins; after: add what it signed in to
async function syncIn(port) {   // also take sign-ins from other bots' browsers that are open right now (they only save theirs when their job ends)
  let m = {}; try { m = JSON.parse(readFileSync(join(workDir, 'ports.json'), 'utf8')); } catch { }
  await Promise.all(Object.values(m).filter(p => p !== port).map(async p => { if (await cdpInfo(p)) await syncOut(p); }));
  await syncOut(port);   // its own newest sign-ins last, so an older copy in the shared store never logs it out
  const jar = readJar(); if (jar.length) await cdp(port, send => send('Storage.setCookies', { cookies: cookieParams(jar) })).catch(e => log('帶入共用登入失敗：' + e.message)); }
async function syncOut(port) { try { const { cookies = [] } = await cdp(port, send => send('Storage.getCookies')); addToJar(cookies); } catch (e) { log('儲存共用登入失敗：' + e.message); } }
const busyBots = new Set();
const pause = ms => new Promise(r => setTimeout(r, ms));
function profileInUse(profile) {   // a Chrome window (without the debugging port) still has this profile open
  if (WIN) {
    const f = join(profile, 'lockfile');
    if (!existsSync(f)) return false;
    try { closeSync(openSync(f, 'r+')); return false; } catch (e) { return ['EBUSY', 'EPERM', 'EACCES'].includes(e.code); }
  }
  try { lstatSync(join(profile, 'SingletonLock')); return true; } catch { return false; }
}
function portOf(id) {   // a fixed local port per bot, kept in work/ports.json
  const f = join(workDir, 'ports.json');
  let m = {}; try { m = JSON.parse(readFileSync(f, 'utf8')); } catch { }
  if (!m[id]) { const used = new Set(Object.values(m)); let p = 9311; while (used.has(p)) p++; m[id] = p; writeFileSync(f, JSON.stringify(m)); }
  return m[id];
}
function embedPortOf(id) {   // separate from Chrome's ports, so a leftover Chrome does not get driven by mistake
  const f = join(workDir, 'embed-ports.json');
  let m = {}; try { m = JSON.parse(readFileSync(f, 'utf8')); } catch { }
  if (!m[id]) { const used = new Set(Object.values(m)); let p = 19011; while (used.has(p)) p++; m[id] = p; try { writeFileSync(f, JSON.stringify(m)); } catch { } }
  return m[id];
}
function savedPorts() {
  const out = [];
  for (const name of ['ports.json', 'embed-ports.json']) {
    try { out.push(...Object.values(JSON.parse(readFileSync(join(workDir, name), 'utf8')))); } catch { }
  }
  return out;
}
async function cdpInfo(port) {
  try { const r = await fetch(`http://127.0.0.1:${port}/json/version`, { signal: AbortSignal.timeout(1500) }); return r.ok ? await r.json() : null; } catch { return null; }
}
async function cdp(port, fn) {   // a short CDP session on the browser
  if (typeof WebSocket === 'undefined') throw new Error('需要 Node 22 以上');
  const v = await cdpInfo(port);
  if (!v) throw new Error('瀏覽器沒有開著');
  const ws = new WebSocket(v.webSocketDebuggerUrl);
  await new Promise((ok, no) => { ws.onopen = ok; ws.onerror = () => no(new Error('連不上瀏覽器')); setTimeout(() => no(new Error('連不上瀏覽器')), 5000); });
  let n = 0; const wait = {};
  ws.onmessage = e => { const m = JSON.parse(e.data); if (wait[m.id]) { wait[m.id](m); delete wait[m.id]; } };
  const send = (method, params = {}, sessionId) => new Promise((ok, no) => {
    const id = ++n; wait[id] = m => (m.error ? no(new Error(m.error.message)) : ok(m.result));
    ws.send(JSON.stringify({ id, method, params, ...(sessionId ? { sessionId } : {}) }));
    setTimeout(() => { if (wait[id]) { delete wait[id]; no(new Error('瀏覽器沒有回應')); } }, 15000);
  });
  try { return await fn(send); } finally { try { ws.close(); } catch { } }
}
const pagesOf = async send => (await send('Target.getTargets')).targetInfos.filter(t => t.type === 'page' && !t.url.startsWith('devtools://'));
export function pickLivePage(pages) {
  const list = (pages || []).filter(p => p && !String(p.url || '').startsWith('devtools://'));
  const real = list.filter(p => { const u = String(p.url || ''); return u && u !== 'about:blank' && !u.startsWith('data:'); });
  return real.at(-1) || list.at(-1) || null;
}
const touchBrowser = id => { const b = browsers.get(id); if (b) b.last = Date.now(); };
// a name tag on every page of a bot's browser: a colored badge in the corner, and its name before the tab title
const tags = new Map();   // port → open CDP connection that tags new pages
const colorOf = name => { let h = 0; for (const ch of name) h = (h * 31 + ch.codePointAt(0)) >>> 0; return '#' + (BOT_COLORS[h % BOT_COLORS.length] & 0xFFFFFF).toString(16).padStart(6, '0'); };
const tagScript = (name, color) => `(() => { if (window.top !== window) return; const N = ${JSON.stringify(name)}, C = ${JSON.stringify(color)}, P = '【' + N + '】';
  const fix = () => { if (document.title && !document.title.startsWith(P)) document.title = P + document.title; else if (!document.title) document.title = P + location.hostname; };
  const put = () => { if (!document.documentElement || document.getElementById('__octa_tag')) return; const d = document.createElement('div'); d.id = '__octa_tag'; d.textContent = '🐙 ' + N;
    d.setAttribute('style', 'position:fixed;right:10px;top:10px;z-index:2147483647;background:' + C + ';color:#fff;font:600 13px/1 system-ui,sans-serif;padding:7px 12px;border-radius:999px;box-shadow:0 2px 10px rgba(0,0,0,.35);pointer-events:none;opacity:.92');
    document.documentElement.appendChild(d); fix(); new MutationObserver(fix).observe(document.querySelector('title') || document.head || document.documentElement, { childList: true, subtree: true, characterData: true });
    // a live cursor so you can watch what the bot does: glides to each mouse move, ripples on clicks, flashes what it clicked
    const cur = document.createElement('div'); cur.id = '__octa_cur';
    cur.innerHTML = '<svg width="26" height="26" viewBox="0 0 24 24"><path d="M3 2l7.5 19 2.6-7.9L21 10.5z" fill="' + C + '" stroke="#fff" stroke-width="1.6" stroke-linejoin="round"/></svg><span></span>';
    cur.setAttribute('style', 'position:fixed;left:0;top:0;z-index:2147483647;pointer-events:none;transform:translate(-60px,-60px);transition:transform .38s cubic-bezier(.3,.8,.3,1),opacity .4s;opacity:0;filter:drop-shadow(0 2px 4px rgba(0,0,0,.4))');
    const lab = cur.querySelector('span'); lab.setAttribute('style', 'position:absolute;left:22px;top:20px;white-space:nowrap;background:' + C + ';color:#fff;font:600 11px/1 system-ui,sans-serif;padding:4px 7px;border-radius:999px;opacity:0;transition:opacity .2s');
    lab.textContent = N; document.documentElement.appendChild(cur);
    let idle, x = -60, y = -60; const wake = () => { cur.style.opacity = '1'; clearTimeout(idle); idle = setTimeout(() => { cur.style.opacity = '0' }, 8000); };
    const move = (nx, ny) => { x = nx; y = ny; cur.style.transform = 'translate(' + (x - 3) + 'px,' + (y - 2) + 'px)'; wake(); };
    addEventListener('mousemove', e => move(e.clientX, e.clientY), true);
    addEventListener('mousedown', e => { move(e.clientX, e.clientY);
      const r = document.createElement('div'); r.setAttribute('style', 'position:fixed;z-index:2147483646;pointer-events:none;left:' + (e.clientX - 18) + 'px;top:' + (e.clientY - 18) + 'px;width:36px;height:36px;border-radius:50%;border:3px solid ' + C + ';transform:scale(.3);opacity:1;transition:transform .5s ease-out,opacity .5s');
      document.documentElement.appendChild(r); requestAnimationFrame(() => { r.style.transform = 'scale(1.6)'; r.style.opacity = '0'; }); setTimeout(() => r.remove(), 600);
      const t = e.target; if (t && t.style) { const o = t.style.outline, oo = t.style.outlineOffset; t.style.outline = '3px solid ' + C; t.style.outlineOffset = '2px'; setTimeout(() => { t.style.outline = o; t.style.outlineOffset = oo; }, 700); } }, true);
    addEventListener('keydown', () => { lab.textContent = '⌨️ ' + N + ' 輸入中'; lab.style.opacity = '1'; wake();
      const f = document.activeElement; if (f && f.getBoundingClientRect && x < 0) { const b = f.getBoundingClientRect(); move(b.left + 12, b.top + b.height / 2); }
      clearTimeout(lab._t); lab._t = setTimeout(() => { lab.style.opacity = '0'; lab.textContent = N; }, 900); }, true);
    addEventListener('focusin', e => { const b = e.target.getBoundingClientRect && e.target.getBoundingClientRect(); if (b && b.width && !(x >= b.left && x <= b.right && y >= b.top && y <= b.bottom)) move(b.left + Math.min(24, b.width / 2), b.top + b.height / 2); }, true); };
  if (document.readyState === 'loading') document.addEventListener('DOMContentLoaded', put); else put(); })()`;
async function tagBrowser(port, name) {
  if (tags.has(port) || typeof WebSocket === 'undefined') return;
  const v = await cdpInfo(port); if (!v) return;
  const ws = new WebSocket(v.webSocketDebuggerUrl), src = tagScript(name, colorOf(name)), done = new Set(), sess = new Map();
  tags.set(port, ws);
  let n = 0; const send = (method, params = {}, sessionId) => ws.send(JSON.stringify({ id: ++n, method, params, ...(sessionId ? { sessionId } : {}) }));
  const attach = t => { if (t.type === 'page' && !t.attached && !done.has(t.targetId)) { done.add(t.targetId); send('Target.attachToTarget', { targetId: t.targetId, flatten: true }); } };
  ws.onopen = () => { send('Target.setDiscoverTargets', { discover: true }); };
  ws.onmessage = e => { const m = JSON.parse(e.data);
    if (m.method === 'Target.targetCreated' || m.method === 'Target.targetInfoChanged') attach(m.params.targetInfo);
    // a page that was already loading when we attached: tag it again once its address changes
    if (m.method === 'Target.targetInfoChanged' && sess.has(m.params.targetInfo.targetId)) send('Runtime.evaluate', { expression: src }, sess.get(m.params.targetInfo.targetId));
    if (m.method === 'Target.attachedToTarget' && m.params.targetInfo.type === 'page') { const sid = m.params.sessionId; sess.set(m.params.targetInfo.targetId, sid);
      send('Page.addScriptToEvaluateOnNewDocument', { source: src }, sid); send('Runtime.evaluate', { expression: src }, sid); send('Runtime.runIfWaitingForDebugger', {}, sid); }
    if (m.method === 'Target.targetDestroyed') { done.delete(m.params.targetId); sess.delete(m.params.targetId); } };
  ws.onclose = ws.onerror = () => { tags.delete(port); };
}
export async function ensureBrowser(bot, opts) {
  const port = await openBrowser(bot, opts);
  if (shareBrowser) { await mergeOldProfiles().catch(e => log('合併舊登入失敗：' + e.message)); await syncIn(port); }
  return port;
}
// tell the bots' browsers apart: the profile is named after the bot and gets its own theme color
const BOT_COLORS = [0xFFD93025, 0xFF1A73E8, 0xFF188038, 0xFFF9AB00, 0xFF9334E6, 0xFFE8710A, 0xFF12B5CB, 0xFFE52592];
function markProfile(profile, name) {
  try {
    const f = join(profile, 'Default', 'Preferences');
    mkdirSync(join(profile, 'Default'), { recursive: true });
    let pr = {}; try { pr = JSON.parse(readFileSync(f, 'utf8')); } catch { }
    let h = 0; for (const ch of name) h = (h * 31 + ch.codePointAt(0)) >>> 0;
    const color = BOT_COLORS[h % BOT_COLORS.length] | 0;
    pr.profile = { ...(pr.profile || {}), name };
    pr.browser = { ...(pr.browser || {}), theme: { ...((pr.browser || {}).theme || {}), user_color: color, color_variant: 1 } };
    writeFileSync(f, JSON.stringify(pr));
  } catch (e) { log('瀏覽器標記失敗：' + e.message); }
}
const onDesk = new Set();
const knownBots = new Map();
// Google refuses sign-in inside the embedded browser ("這個瀏覽器或應用程式可能有安全疑慮").
// From then on this bot uses a real Chrome window with its own profile, opened at the sign-in page.
export function googleSignInUrl(url) {
  let u; try { u = new URL(url); } catch { return ''; }
  if (u.hostname !== 'accounts.google.com' || !/signin|ServiceLogin|AddSession|rejected/i.test(u.pathname)) return '';
  const cont = u.searchParams.get('continue') || 'https://www.google.com/';
  return 'https://accounts.google.com/ServiceLogin?continue=' + encodeURIComponent(cont);
}
async function switchToChrome(botId, url) {
  const bot = knownBots.get(botId);
  const dest = googleSignInUrl(url);
  if (!bot || !dest || !cfg.embed) return false;
  if (browsers.get(botId)?.embed) browsers.delete(botId);
  try { await cfg.embed.stop?.(embedPortOf(botId)); } catch { }
  try {
    const port = await openBrowser(bot);
    await showBrowser(port, dest, false, true);
    log(`🌐 ${bot.name}：Google 不讓內嵌瀏覽器登入，已改用 Chrome 視窗`);
    return true;
  } catch (e) { log('改用 Chrome 失敗：' + e.message); return false; }
}
async function openBrowser(bot, opts = {}) {
  if (bot?.id && bot.name !== '監看') knownBots.set(bot.id, bot);
  if (cfg.embed && !cfg.embed.onGoogle) cfg.embed.onGoogle = switchToChrome;
  if (cfg.embed && bot.browser !== 'mine' && !cfg.embed.external?.(bot.id)) {
    const port = embedPortOf(bot.id);
    try {
      if (!(await cdpInfo(port))) await cfg.embed.start(bot, port);
      for (let i = 0; i < 30 && !(await cdpInfo(port)); i++) await pause(100);
      if (await cdpInfo(port)) {
        browsers.set(bot.id, { port, last: Date.now(), embed: true });
        if (opts.show !== false) await cfg.embed.show?.(port, opts.expand ? 'open' : true);
        log(`🌐 ${bot.name} 的瀏覽器在 OCTA 裡`);
        await tagBrowser(port, bot.name).catch(() => { });
        return port;
      }
    } catch (e) { log('內建瀏覽器沒有起來，改開 Chrome：' + e.message); }
  }
  const port = portOf(bot.id);
  const key = bot.id;
  if (await cdpInfo(port)) {
    browsers.set(key, { port, last: Date.now() });
    if (!onDesk.has(port)) { onDesk.add(port); await cdp(port, async send => {   // a window an older version hid off-screen or minimised comes back onto the desktop
      const [p] = await pagesOf(send); if (!p) return;
      const { windowId, bounds } = await send('Browser.getWindowForTarget', { targetId: p.targetId });
      if (bounds.windowState === 'minimized' || bounds.left < -5000) { await send('Browser.setWindowBounds', { windowId, bounds: { windowState: 'normal' } }).catch(() => { }); await send('Browser.setWindowBounds', { windowId, bounds: { left: 40 + ((port - 9311) % 6) * 60, top: 30 + ((port - 9311) % 6) * 40, width: 1200, height: 820 } }).catch(() => { }); }
    }).catch(() => { }); }
    await tagBrowser(port, bot.name).catch(() => { });
    return port;
  }
  const chrome = findChrome();
  if (!chrome) throw new Error('找不到 Google Chrome');
  const profile = botDir(bot.id).profile;
  mkdirSync(profile, { recursive: true });
  for (let i = 0; i < 10 && profileInUse(profile); i++) await pause(1000);   // an old window may still be closing
  if (profileInUse(profile)) throw new Error('這個機器人的瀏覽器有一個舊視窗開著，請先關掉它');
  markProfile(profile, bot.name);
  const child = spawn(chrome, [`--user-data-dir=${profile}`, `--remote-debugging-port=${port}`, '--no-first-run', '--no-default-browser-check', `--window-name=OCTA｜${bot.name}`,
    `data:text/html;charset=utf-8,${encodeURIComponent(`<title>${bot.name} 的瀏覽器</title><body style="margin:0;display:grid;place-items:center;height:100vh;background:${colorOf(bot.name)};color:#fff;font:600 32px system-ui,sans-serif">🐙 ${bot.name.replace(/[<&]/g, '')} 的瀏覽器<div style="font:400 15px system-ui;opacity:.85;margin-top:12px">OCTA 機器人專用，登入後網站會共用給其他機器人</div></body>`)}`,
    '--restore-last-session', `--window-position=${40 + ((port - 9311) % 6) * 60},${30 + ((port - 9311) % 6) * 40}`, '--window-size=1200,820'], { detached: true, stdio: 'ignore', windowsHide: false });
  child.on('error', () => { });
  child.unref();
  for (let i = 0; i < 40; i++) { if (await cdpInfo(port)) break; await pause(500); }
  if (!(await cdpInfo(port))) throw new Error('Chrome 沒有啟動');
  browsers.set(key, { port, last: Date.now(), profile });
  if (sessions.has(bot.id)) closeSession(bot.id);   // a waiting AI was connected to the old browser
  log(`🌐 ${bot.name} 的瀏覽器已在背景開啟`);
  // the window stays on the desktop (cascaded per bot) so you can click into any bot's browser at any time
  await tagBrowser(port, bot.name).catch(() => { });
  return port;
}
async function pushLive(port, job) {
  // nobody has this bot's browser open: don't upload frames, just check every 6 s whether someone started watching or took over
  if (!job.liveWatch) {
    if (Date.now() - (job.livePeek || 0) < 6000) return;
    job.livePeek = Date.now();
    const p = await api('runner/live', { bot: job.bot.id, peek: 1 });
    if (p.hand) { job.handed = true; job.stopForHand?.(); }
    if (!p.watch) return;
    job.liveWatch = true;
  }
  const shot = await browserSnapshot(port, 0, 40);
  if (!shot?.jpeg || shot.jpeg.length > 350000) return;
  let title = '';
  try { title = (pickLivePage(await cdp(port, send => pagesOf(send)))?.title || '').slice(0, 80); } catch { }
  const r = await api('runner/live', { bot: job.bot.id, url: realPage(shot.url) || '', title, data: shot.jpeg.toString('base64') });
  if (r.hand) { job.handed = true; job.stopForHand?.(); }
  if (r.watch === false) job.liveWatch = false;
}
async function captureEyes(port, dir) {
  try {
    const live = await browserSnapshot(port);
    if (!live?.jpeg) return '';
    const p = join(dir, '畫面.jpg');
    writeFileSync(p, live.jpeg);
    return p;
  } catch (e) { log('看畫面失敗：' + e.message); return ''; }
}
async function browserSnapshot(port, since, quality = 70) {   // screenshot + address of the tab the bot used last
  const q = Math.min(80, Math.max(20, +quality || 70));
  return cdp(port, async send => {
    const p = pickLivePage(await pagesOf(send));
    if (!p) return null;
    const { sessionId } = await send('Target.attachToTarget', { targetId: p.targetId, flatten: true });
    let jpeg = null;
    try { jpeg = Buffer.from((await send('Page.captureScreenshot', { format: 'jpeg', quality: q }, sessionId)).data, 'base64'); } catch { }
    await send('Target.detachFromTarget', { sessionId }).catch(() => { });
    return { url: p.url, jpeg };
  });
}
const realPage = u => (u && !/^(about:|data:|chrome:)/.test(u)) ? u : '';
const blankPage = u => !u || /^(about:|data:|chrome:)/.test(u);
export function browserWindowAsk(text) {
  const t = String(text || '');
  if (/不要關|別關|先別關/.test(t)) return '';
  if (/關閉瀏覽器|關掉瀏覽器|把瀏覽器關|收起瀏覽器|瀏覽器收起來|瀏覽器關掉/.test(t)) return 'close';
  if (/打開瀏覽器|開啟瀏覽器|開瀏覽器|把瀏覽器打開/.test(t)) return 'open';
  return '';
}
export function takeWindowMarks(text) {
  const raw = String(text || '');
  const open = raw.match(/【開瀏覽器】\s*(https?:\/\/\S+)?/);
  return { close: /【關瀏覽器】/.test(raw), open: open ? (open[1] || GOOGLE_HOME) : '' };
}
async function settleBrowserWindow(port, job) {
  const ask = browserWindowAsk(job.prompt);
  if (ask === 'close') {
    try { await showBrowser(port, '', true, false); } catch (e) { log('關閉瀏覽器：' + e.message); }
    job.windowNote = '使用者要你關閉瀏覽器。視窗已經收起來了。回覆直接說已經關閉。禁止說「沒有控制工具」「沒辦法替你關閉」「無法操作瀏覽器視窗」。';
  } else if (ask === 'open') {
    try { await showBrowser(port, '', false, true); } catch (e) { log('打開瀏覽器：' + e.message); }
    job.windowNote = '使用者要你打開瀏覽器。沒有指定網址時，已經在 OCTA 視窗裡打開內嵌的 Google。直接說已經打開，不要叫他先輸入網址。';
  }
}
async function finishBrowserWindow(port, job, text) {
  const marks = takeWindowMarks(text);
  if (marks.close) { try { await showBrowser(port, '', true, false); } catch (e) { log('關閉瀏覽器：' + e.message); } }
  if (marks.open) { try { await showBrowser(port, marks.open, false, true); } catch (e) { log('打開瀏覽器：' + e.message); } }
  let out = String(text || '').replace(/【關瀏覽器】/g, '').replace(/【開瀏覽器】\s*(https?:\/\/\S+)?/g, '').trim();
  if (browserWindowAsk(job.prompt) === 'close' && /控制工具|沒能替你關閉|沒辦法替你關閉|無法關閉|無法操作/.test(out)) out = '瀏覽器已經關閉。';
  if (browserWindowAsk(job.prompt) === 'open' && /先輸入網址|先打網址|沒有控制工具/.test(out)) out = '瀏覽器已經打開，裡面是 Google。';
  if (out) return out;
  if (marks.close || browserWindowAsk(job.prompt) === 'close') return '瀏覽器已經關閉。';
  if (marks.open || browserWindowAsk(job.prompt) === 'open') return '瀏覽器已經打開，裡面是 Google。';
  return text;
}
async function showBrowser(port, url, hide, expand) {
  const embed = [...browsers.values()].some(b => b.port === port && b.embed);
  if (embed) await cfg.embed?.show?.(port, hide ? false : (expand ? 'open' : true));
  return cdp(port, async send => {
    const pages = await pagesOf(send);
    const live = pickLivePage(pages);
    let targetId = live?.targetId;
    const dest = hide ? '' : (url || (blankPage(live?.url) ? GOOGLE_HOME : ''));
    if (dest || !targetId) targetId = (await send('Target.createTarget', { url: dest || GOOGLE_HOME })).targetId;
    const seen = async () => realPage((await pagesOf(send)).find(p => p.targetId === targetId)?.url);
    if (hide || !targetId) return seen();   // handing back: the window stays where it is on the desktop
    const { windowId } = await send('Browser.getWindowForTarget', { targetId });
    await send('Browser.setWindowBounds', { windowId, bounds: { windowState: 'normal' } }).catch(() => { });
    if (!embed) {
      const { bounds } = await send('Browser.getWindowForTarget', { targetId });
      if (bounds.left < -5000) await send('Browser.setWindowBounds', { windowId, bounds: { left: 60, top: 40, width: 1200, height: 820 } });   // windows from older versions sat off-screen
    }
    await send('Target.activateTarget', { targetId });
    return seen();
  });
}
async function rememberOpen(port, job) {   // the phone is waiting for the address and a picture of what the computer opened
  let seen = '', jpeg = null;
  for (let i = 0; i < 8; i++) {
    const live = await browserSnapshot(port).catch(() => null);
    const url = realPage(live?.url);
    if (url) seen = url;
    if (live?.jpeg) jpeg = live.jpeg;
    if (jpeg && (seen || i === 7)) break;
    await pause(400);
  }
  if (jpeg) {
    try {
      const conv = job.conv?.id ? job.conv : job.bot;
      const p = freeName(join(convDir(conv), '截圖'), safeName(job.bot.name) + '-畫面.jpeg');
      writeFileSync(p, jpeg);
      await api('runner/shot', { id: job.id, path: rel(p), name: basename(p), size: jpeg.length });
    } catch (e) { log('截圖儲存失敗：' + e.message); }
  }
  return seen;
}
async function openJob(job) {
  if (typeof job.shareBrowser === 'boolean') shareBrowser = job.shareBrowser;
  const done = (ok, text, page) => { log(`🌐 ${job.bot.name}：${text}`); return api('runner/done', { id: job.id, ok, text, ...(page ? { page } : {}) }).catch(() => { }); };
  const hide = job.url === 'octa:hide';
  const expand = String(job.url || '').startsWith('octa:open');
  const page = expand ? String(job.url).slice('octa:open'.length).trim() : (hide ? '' : (job.url || ''));
  try {
    const ports = [...new Set([browsers.get(job.bot.id)?.port, cfg.embed && job.bot.browser !== 'mine' && !cfg.embed.external?.(job.bot.id) ? embedPortOf(job.bot.id) : 0, portOf(job.bot.id)].filter(Boolean))];
    if (hide && (await Promise.all(ports.map(p => cdpInfo(p)))).every(v => !v)) return done(true, '我的瀏覽器已經收起來了。');
    const port = await ensureBrowser(job.bot, { show: !hide, expand });
    const landed = realPage(await showBrowser(port, page, hide, expand));
    touchBrowser(job.bot.id);
    if (hide && shareBrowser) await syncOut(port);   // signed in by hand: every bot gets it
    if (hide) return done(true, '我的瀏覽器已收到背景，我會繼續在裡面工作。');
    const seen = await rememberOpen(port, job);
    const where = browsers.get(job.bot.id)?.embed ? (expand ? 'OCTA 視窗裡，按「收回」會縮回角落' : 'OCTA 視窗的角落縮圖，點一下可以打開') : '電腦上';
    return done(true, busyBots.has(job.bot.id) ? `我的瀏覽器已經在${where}，我正在裡面工作，先別操作；要幫我登入請等我停下來。`
      : `我的瀏覽器已經在${where}。需要登入就直接在裡面登入，好了回來按「登入好了，繼續」。`, seen || landed || realPage(page));
  } catch (e) { return done(false, '⚠ 無法打開瀏覽器：' + e.message); }
}
// ---------- 監看網頁: check pages in the bot's own browser, start the routine only when they change ----------
// No AI is used for checking, so it costs no tokens; the bot is called only when something new shows up.
let watches = [], watchesAt = 0;
const lastLook = new Map();
async function readPage(port, url, sel) {
  return cdp(port, async send => {
    const { targetId } = await send('Target.createTarget', { url, background: true });
    try {
      const { sessionId } = await send('Target.attachToTarget', { targetId, flatten: true });
      const ev = async expr => (await send('Runtime.evaluate', { expression: expr, returnByValue: true }, sessionId)).result?.value;
      for (let i = 0; i < 40 && (await ev('document.readyState').catch(() => '')) !== 'complete'; i++) await pause(500);
      await pause(4000);   // pages that load their content afterwards (chat lists, dashboards)
      const s = JSON.stringify(sel || '');
      return String(await ev(`(()=>{const sel=${s};const els=sel?[...document.querySelectorAll(sel)]:[document.body];return els.map(e=>e.innerText).join('\\n')})()`) || '').slice(0, 8000);
    } finally { await send('Target.closeTarget', { targetId }).catch(() => { }); }
  });
}
async function checkWatches() {
  if (standby || stopped) return;
  if (Date.now() - watchesAt > 5 * 60000) { watchesAt = Date.now(); try { watches = (await api('runner/watches', {})).watches || []; } catch { } }
  for (const w of watches) {
    if (Date.now() - (lastLook.get(w.id) || 0) < (w.every || 10) * 60000) continue;
    if (busyBots.has(w.bot) || sessions.get(w.bot)?.turn) continue;   // don't disturb a bot at work
    lastLook.set(w.id, Date.now());
    try {
      const port = await ensureBrowser({ id: w.bot, name: '監看' }, { show: false });
      const text = (await readPage(port, w.url, w.sel)).replace(/\d{1,2}:\d{2}(:\d{2})?/g, '').trim();   // ignore clocks on the page
      const hash = createHash('sha1').update(text).digest('hex');
      const r = await api('runner/watched', { id: w.id, hash, text });
      if (r.changed) log(`👀 監看的網頁有變化：${w.url}`);
    } catch (e) { log('監看失敗：' + e.message); }
  }
}

// browsers idle for 30 minutes and not on screen are closed to save memory (tabs come back next time)
// OCTA is closing: close every bot's browser (also ones a previous run left open), so the next start doesn't pile up windows
export async function closeAllBrowsers() {
  await Promise.all(savedPorts().map(async p => { if (await cdpInfo(p)) await cdp(p, send => send('Browser.close')).catch(() => { }); }));
  for (const ws of tags.values()) { try { ws.close(); } catch { } }
  tags.clear(); browsers.clear(); onDesk.clear();
}
async function reapBrowsers(all) {
  if (all) return closeAllBrowsers();
  for (const [id, b] of browsers) {
    const inUse = busyBots.has(id) || sessions.has(id);
    if (!all && inUse) continue;   // in use, or an AI is waiting (待機)
    if (!all && Date.now() - b.last < 30 * 60000) continue;
    try {
      await cdp(b.port, async send => {
        if (!all) {
          const [p] = await pagesOf(send);
          if (p) { const { bounds } = await send('Browser.getWindowForTarget', { targetId: p.targetId }); if (bounds.left > -5000 && bounds.windowState !== 'minimized') return; }   // the user is looking at it
        }
        await send('Browser.close');
      });
      browsers.delete(id);
    } catch { browsers.delete(id); }
  }
}

// ---------- main loop: long-poll, so work starts the moment it's sent ----------
let active = 0, failures = 0, stopped = true, onFatal = null, polling = false, standby = false;
const fileWork = new Set();
function codeSummary(state) {
  const { events, context, ...rest } = state || {};
  rest.diff = String(rest.diff || '').slice(0, 20000);
  rest.tests = (rest.tests || []).map(t => ({ ...t, stdout: String(t.stdout || '').slice(0, 2000), stderr: String(t.stderr || '').slice(0, 2000) }));
  return rest;
}
async function codeJob(job) {
  const ac = new AbortController();
  const resumed = job.resumeState || null;
  let sent = resumed?.events?.length || 0;
  const workspacesRoot = join(workDir, 'code-workspaces');
  const fb = Array.isArray(job.task.fb) ? job.task.fb : [];
  const routeChain = [{ engine: job.task.engine, model: job.task.model || '' }, ...fb.map(s => {
    const [engine, model] = String(s).split('|');
    return { engine, model: model || '' };
  })];
  const providerFor = slot => selectProvider({ engine: slot.engine, model: slot.model, allowFixture: process.env.OCTA_CODE_ALLOW_FIXTURE === '1' });
  const slot = routeChain[resumed?.routeIndex || 0] || routeChain[0];
  const provider = await providerFor(slot);
  const res = await runCodingTask({
    id: job.task.id, title: job.task.title, prompt: job.task.prompt, criteria: job.task.criteria,
    engine: slot.engine, model: slot.model, maxRepairs: job.task.maxRetries,
    repoPath: job.repo.path, workspacesRoot, provider, routeChain, providerFor, signal: ac.signal, resume: resumed || undefined,
    approval: job.task.approval || undefined,
    isCancelled: async () => ac.signal.aborted,
    persist: async state => {
      const fresh = (state.events || []).slice(sent);
      sent = (state.events || []).length;
      const r = await api('runner/code/event', {
        taskId: state.id, status: state.status, phase: state.phase, role: state.role,
        workspaceId: state.workspaceId, branch: state.branch, baseRef: state.baseRef, headRef: state.headRef,
        retries: state.repairs, summary: codeSummary(state),
        events: fresh.map(e => ({ role: e.role, kind: e.kind, text: e.text, data: e.data || null }))
      });
      if (r.cancel) ac.abort();
      return r;
    }
  });
  const text = `${res.providerNote || res.providerId || ''} ${res.status}${res.reason ? ' ' + res.reason : ''}${res.error ? ' ' + res.error : ''}`.trim();
  await api('runner/done', { id: job.id, ok: res.status === 'tested', text: text.slice(0, 2000) });
  log(`${res.status === 'tested' ? '✓' : '✗'} 程式任務 ${job.task.title || job.task.id}：${res.status}`);
}
async function recoverCodeTasks() {
  const root = join(workDir, 'code-workspaces');
  for (const state of listRecoverableStates(root)) {
    try {
      const r = await api('runner/code/resume', { taskId: state.id });
      if (r?.continue && r.job) runJob({ ...r.job, resumeState: state });
    } catch (e) { log('程式任務恢復失敗：' + e.message); }
  }
}
let lastCoding = 0, codingCache = null;
async function codingProbe() {
  if (codingCache && Date.now() - lastCoding < 60000) return codingCache;
  lastCoding = Date.now();
  try { codingCache = await probeCodingHosts({ timeoutMs: 400 }); } catch { codingCache = null; }
  return codingCache;
}
function runJob(job) {
  active++;
  (job.kind === 'code' ? codeJob(job) : job.kind === 'open' ? openJob(job) : job.kind === 'test' ? testJob(job) : job.kind === 'list' ? listJob(job) : job.kind === 'install' ? installJob(job) : job.kind === 'export' ? exportJob(job) : job.kind === 'import' ? importJob(job) : chatJob(job))
    .catch(e => { log('任務錯誤：' + e.message); return api('runner/done', { id: job.id, ok: false, text: '⚠ ' + e.message }).catch(() => { }); })
    .finally(() => { active--; kick(); });
}
function doFiles(inbox = [], pull = []) {
  for (const f of inbox) if (!fileWork.has(f.id)) { fileWork.add(f.id); saveUpload(f).catch(e => log('附件儲存失敗：' + e.message)).finally(() => fileWork.delete(f.id)); }
  for (const f of pull) if (!fileWork.has(f.id)) { fileWork.add(f.id); sendCopy(f).catch(e => log('傳送檔案失敗：' + e.message)).finally(() => fileWork.delete(f.id)); }
}
let poll = null;
const kick = () => { if (active < MAX) poll?.abort(); };   // a slot freed up: ask again right away (with the free slot)
async function loop() {
  if (polling) return;
  polling = true;
  while (!stopped) {
    try {
      const slots = MAX - active;
      poll = new AbortController();
      const r = await api('runner/next', {
        wait: true, slots, engines: await engineReport(), usage: await usageReport(), models: await modelReport(),
        version: VERSION, app: cfg.appVersion || undefined, store: storeDir(), coding: await codingProbe()
      }, 'POST', slots ? undefined : poll.signal).catch(e => { if (e.name === 'AbortError') return {}; throw e; });
      failures = 0;
      if ('job' in r && !!r.standby !== standby) { standby = !!r.standby; log(standby ? '⏸ 這台電腦目前是備用電腦，由主機執行機器人。可在「設定 → 電腦」改成主機。' : '▶ 這台電腦是主機，開始接工作。'); cfg.onStandby?.(standby); }
      doFiles(r.inbox, r.pull);
      if (r.job) runJob(r.job);
    } catch (e) {
      failures++;
      log('連線問題：' + e.message);
      if (/執行器金鑰|請先登入/.test(e.message)) { stopped = true; onFatal?.('金鑰無效，請重新登入 OCTA 或到網站「設定」重新產生。'); break; }
      await new Promise(ok => setTimeout(ok, Math.min(2000 * 2 ** Math.min(failures, 5), 60000)));
    }
  }
  polling = false;
}

// opts: { url, token, home, max, chrome, pwCli, nodeBin, nodeEnv, log, onFatal, onDone, onStandby, getStore, getExtToken, appVersion, openInstall(engine) }
export function startRunner(opts) {
  cfg = { ...opts, url: opts.url.replace(/\/+$/, '') };
  workDir = join(opts.home, 'work');
  MAX = Math.max(1, Math.min(+opts.max || 3, 8));
  if (opts.log) log = opts.log;
  onFatal = opts.onFatal || null;
  stopped = false; lastReport = 0; lastUsage = 0; lastModels = 0; standby = false;
  mkdirSync(join(workDir, 'bots'), { recursive: true });
  mkdirSync(storeDir(), { recursive: true });
  log(`OCTA 執行器 v${VERSION} 啟動，最多 ${MAX} 個機器人同時工作；檔案資料夾：${storeDir()}`);
  if (!cfg.pwCli) {
    log('準備瀏覽器工具…');
    spawnSync(WIN ? 'cmd' : 'npx', WIN ? ['/c', 'npx', '-y', PW_MCP, '--version'] : ['-y', PW_MCP, '--version'], { stdio: 'ignore', timeout: 180000 });
  }
  loop();
  recoverCodeTasks().catch(e => log('程式任務恢復失敗：' + e.message));
  const reaper = setInterval(() => reapBrowsers(false).catch(() => { }), 5 * 60000);
  const watcher = setInterval(() => checkWatches().catch(() => { }), 60000);
  watchesAt = 0; lastLook.clear();
  setTimeout(() => checkWatches().catch(() => { }), 15000);
  const myCfg = cfg;
  return {
    stop: () => { stopped = true; poll?.abort(); clearInterval(reaper); clearInterval(watcher); reapBrowsers(true).catch(() => { }); for (const id of [...sessions.keys()]) closeSession(id); if (myCfg.token) fetch(myCfg.url + '/api/runner/bye', { method: 'POST', headers: { 'content-type': 'application/json', authorization: 'Bearer ' + myCfg.token }, body: '{}' }).catch(() => { }); },
    active: () => active, standby: () => standby
  };
}

// ---------- CLI ----------
if (process.argv[1] && import.meta.url === pathToFileURL(process.argv[1]).href) {
  const here = dirname(fileURLToPath(import.meta.url));
  const cfgPath = join(here, 'octa-runner.json'), oldCfg = join(here, 'ebot-runner.json');
  let c = existsSync(cfgPath) ? JSON.parse(readFileSync(cfgPath, 'utf8')) : existsSync(oldCfg) ? JSON.parse(readFileSync(oldCfg, 'utf8')) : {};
  if (process.argv[2]) { c = { ...c, url: process.argv[2].replace(/\/+$/, ''), token: process.argv[3] }; writeFileSync(cfgPath, JSON.stringify(c, null, 2)); }
  if (!c.url || !c.token) { console.error('第一次請執行：node octa-runner.mjs <網站網址> <執行器金鑰>'); process.exit(1); }
  console.log(`連線到 ${c.url}（Ctrl+C 停止）`);
  const r = startRunner({ ...c, home: here, onFatal: m => { console.error(m); process.exit(1); } });
  process.on('SIGINT', () => { r.stop(); setTimeout(() => process.exit(0), 500); });
}
