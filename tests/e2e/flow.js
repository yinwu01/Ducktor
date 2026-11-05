#!/usr/bin/env node
// End-to-end run of a grad student's session with Ducktor, on a real model.
// Code here is MIT. It costs real tokens (a few US dollars per run on Sonnet).
//
//   node tests/e2e/flow.js claude    Claude Code, loads this checkout with --plugin-dir
//   node tests/e2e/flow.js codex     Codex, uses the installed duck@ducktor plugin
//   node tests/e2e/flow.js claude more   the second flow: survey, outline, intro, write,
//                                        figure, vibe and notes (main is the default)
//   node tests/e2e/flow.js claude loop   the third flow: /duck picking a command, old notebook
//                                        entries coming back, a free conversation about a
//                                        single-run result, and 「这类我懂了」
//   node tests/e2e/flow.js claude paper  review, why and learn on a real paper: set
//                                        DUCK_E2E_PAPER to a folder with its LaTeX source
//
// Environment:
//   DUCK_E2E_MODEL   model for the host (default: sonnet for claude, Codex's own default for codex)
//   DUCK_E2E_WRAP    command prefix for the host, e.g. "setpriv --inh-caps=-all --ambient-caps=-all"
//                    when bwrap refuses to start under ambient capabilities (Codex sandbox)
//   DUCK_E2E_ONLY    comma-separated stage names to run (later stages may depend on earlier ones)
//   DUCK_E2E_NOT_ON  1: the loop flow writes no .duck/config.md, so `DUCK_E2E_ONLY=route` checks
//                    `/duck <sentence>` in a project that has not turned Ducktor on
//   DUCK_E2E_PAPER   for the paper flow: a folder holding one paper's LaTeX source; it is copied
//                    to paper/ in an empty project
//
// The fixture project is copied to a temp folder outside the plugin (Claude Code will not
// write files that sit inside a loaded plugin). Each stage's transcript, summary.json,
// summary.md and a copy of the project's .duck/ land in evals/results/e2e-<host>-<time>/.
'use strict';

const fs = require('fs');
const os = require('os');
const path = require('path');
const { spawnSync } = require('child_process');

const ROOT = path.resolve(__dirname, '..', '..');
const HOST = process.argv[2];
const FLOW = process.argv[3] || 'main';
if (!['claude', 'codex'].includes(HOST) || !['main', 'more', 'loop', 'paper'].includes(FLOW)) {
  console.error('usage: node tests/e2e/flow.js claude|codex [main|more|loop|paper]');
  process.exit(2);
}
const MODEL = process.env.DUCK_E2E_MODEL || (HOST === 'claude' ? 'sonnet' : '');
const WRAP = (process.env.DUCK_E2E_WRAP || '').split(' ').filter(Boolean);
const ONLY = (process.env.DUCK_E2E_ONLY || '').split(',').filter(Boolean);
const STAMP = new Date().toISOString().replace(/[:.]/g, '-').slice(0, 19);
const OUT_BASE = path.join(ROOT, 'evals', 'results', `e2e-${HOST}${FLOW === 'main' ? '' : `-${FLOW}`}-${STAMP}`);
// Two runs started in the same second (loops run in parallel) would share one folder and
// overwrite each other's records (11-04, rc11: two Claude Code loops and six DeepSeek loops
// did). setup() claims the folder with a mkdir that fails when another run took the name first.
let OUT = OUT_BASE;
function claimOut() {
  fs.mkdirSync(path.dirname(OUT_BASE), { recursive: true });
  for (let i = 1; ; i += 1) {
    const dir = i === 1 ? OUT_BASE : `${OUT_BASE}-${i}`;
    try {
      fs.mkdirSync(dir);
      return dir;
    } catch (err) {
      if (err.code !== 'EEXIST') throw err;
    }
  }
}
const PROJECT = path.join(fs.mkdtempSync(path.join(os.tmpdir(), `ducktor-e2e-${HOST}-`)), 'project');

// /duck-review in Claude Code is $duck:duck-review in Codex.
const cmd = (name) => (HOST === 'claude' ? `/${name}` : `$duck:${name}`);

// ---------- running the host ----------

// opts.search lets the model search the web, as a student would allow when asked.
function runClaude(prompt, session, opts = {}) {
  const args = ['-p', prompt, '--plugin-dir', ROOT, '--output-format', 'stream-json', '--verbose',
    '--permission-mode', 'acceptEdits'];
  if (opts.search) args.push('--allowedTools', 'WebSearch,WebFetch');
  if (MODEL) args.push('--model', MODEL);
  if (session) args.push('--resume', session);
  return spawnSync(WRAP[0] || 'claude', [...WRAP.slice(1), ...(WRAP.length ? ['claude'] : []), ...args],
    { cwd: PROJECT, encoding: 'utf8', timeout: opts.timeout || 900000, maxBuffer: 1 << 28, stdio: ['ignore', 'pipe', 'pipe'] });
}

function runCodex(prompt, session, opts = {}) {
  // `exec resume` takes no -s, so the sandbox mode goes in as a config override on both.
  const common = ['--json', '--dangerously-bypass-hook-trust', '-c', 'sandbox_mode="workspace-write"'];
  if (MODEL) common.push('-m', MODEL);
  // --search is a top-level flag, so it goes before exec.
  const args = [...(opts.search ? ['--search'] : []), ...(session
    ? ['exec', 'resume', ...common, session, prompt]
    : ['exec', ...common, '-C', PROJECT, prompt])];
  return spawnSync(WRAP[0] || 'codex', [...WRAP.slice(1), ...(WRAP.length ? ['codex'] : []), ...args],
    { cwd: PROJECT, encoding: 'utf8', timeout: opts.timeout || 900000, maxBuffer: 1 << 28, stdio: ['ignore', 'pipe', 'pipe'] });
}

// Normalizes one host transcript into { session, reply, reads, tools, injected, cost }.
function parse(stdout) {
  const t = { session: null, reply: '', reads: [], tools: [], denials: [], refusedLogWrites: 0, injected: '', cost: 0, errors: [] };
  const texts = [];
  for (const line of stdout.split('\n')) {
    let ev;
    try { ev = JSON.parse(line); } catch (err) { continue; }
    if (HOST === 'claude') {
      if (ev.type === 'system' && ev.session_id) t.session = ev.session_id;
      if (ev.type === 'system' && ev.subtype === 'hook_response') t.injected += String(ev.output || ev.stdout || '');
      if (ev.type === 'assistant') {
        for (const c of ev.message.content || []) {
          if (c.type === 'text' && c.text.trim()) texts.push(c.text);
          if (c.type !== 'tool_use') continue;
          t.tools.push(`${c.name} ${c.input.file_path || c.input.command || c.input.path || ''}`);
          if (c.name === 'Read') t.reads.push(c.input.file_path);
        }
      }
      // The student sees every message of the turn, not only the last one in `result`.
      if (ev.type === 'result') { t.reply = texts.length ? texts.join('\n\n') : (ev.result || ''); t.cost = ev.total_cost_usd || 0; t.session = ev.session_id || t.session; t.denials = (ev.permission_denials || []).map((d) => `${d.tool_name} ${JSON.stringify(d.tool_input || {}).slice(0, 120)}`); t.refusedLogWrites = (ev.permission_denials || []).filter((d) => d.tool_name === 'Bash' && LOG_WRITE.test(String((d.tool_input || {}).command || ''))).length; }
    } else {
      if (ev.type === 'thread.started') t.session = ev.thread_id;
      const it = ev.item || {};
      if (ev.type === 'item.completed' && it.type === 'agent_message') t.reply += `${it.text}\n`;
      if (ev.type === 'item.completed' && it.type === 'command_execution') {
        t.tools.push(`shell ${it.command}`);
        t.reads.push(it.command);
      }
      if (ev.type === 'item.completed' && it.type === 'file_change') t.tools.push(`edit ${(it.changes || []).map((c) => c.path).join(' ')}`);
      if (ev.type === 'turn.failed' || ev.type === 'error') t.errors.push(JSON.stringify(ev).slice(0, 300));
    }
  }
  return t;
}

// Codex's --json stream does not carry hook output; the session's rollout file under
// $CODEX_HOME/sessions/YYYY/MM/DD/ does, so the hook checks read that.
function codexInjected(thread) {
  if (!thread) return '';
  const root = path.join(process.env.CODEX_HOME || path.join(process.env.HOME, '.codex'), 'sessions');
  const found = [];
  const walk = (dir, depth) => {
    let entries = [];
    try { entries = fs.readdirSync(dir, { withFileTypes: true }); } catch (err) { return; }
    for (const e of entries) {
      const p = path.join(dir, e.name);
      if (e.isDirectory() && depth < 3) walk(p, depth + 1);
      else if (e.isFile() && e.name.includes(thread)) found.push(p);
    }
  };
  walk(root, 0);
  return found.map((f) => fs.readFileSync(f, 'utf8')).join('\n');
}

// ---------- checks ----------

const duckFile = (rel) => path.join(PROJECT, '.duck', rel);
const exists = (rel) => fs.existsSync(duckFile(rel));
const text = (rel) => (exists(rel) ? fs.readFileSync(duckFile(rel), 'utf8') : '');
const reports = (suffix) => (fs.existsSync(duckFile('reports'))
  ? fs.readdirSync(duckFile('reports')).filter((f) => f.endsWith(`${suffix}.md`) || f.includes(`${suffix}-`)) : []);
const allReports = () => (fs.existsSync(duckFile('reports')) ? fs.readdirSync(duckFile('reports')) : []);
// Read the original skill in this stage, or earlier in the same host session (its text is still in context).
// A shell read after cd (`cd …/library/<skill> && cat SKILL.md`, DeepSeek on 0.2.2) counts too.
const readOf = (t, skill) => [...t.reads, ...(t.earlierReads || [])].some((r) => r && (r.includes(`library/${skill}/SKILL.md`)
  || (r.includes(`library/${skill}`) && /\b(cat|head|sed|less)\b[^\n|;&]*\bSKILL\.md\b/.test(r))));
const switchIs = (mode) => new RegExp(`^[\\s>*#-]*开关\\s*[:：]\\s*${mode}`, 'm').test(text('config.md'));
const FOLLOWUP = '信息就这些。按你的理解继续做完，缺的地方在结果里标出来就行；我前面说的限制照旧。';
const newestReport = (suffix) => {
  const f = reports(suffix).sort().at(-1);
  return f ? fs.readFileSync(duckFile(path.join('reports', f)), 'utf8') : '';
};
const fixture = (rel) => fs.readFileSync(path.join(ROOT, 'tests', 'fixtures', 'grad-project', rel), 'utf8');
const projectFile = (rel) => (fs.existsSync(path.join(PROJECT, rel)) ? fs.readFileSync(path.join(PROJECT, rel), 'utf8') : '');
// rc13 scope step: the manuscript without the lines between \section{Experiments} and \begin{table}.
const outsideFirstExpParagraph = (tex) => tex.replace(/\\section\{Experiments\}[\s\S]*?(?=\\begin\{table\})/, '\\section{Experiments}\n');
// rc13 carry step: the Conclusion section.
const abstractOf = (tex) => (tex.match(/\\begin\{abstract\}[\s\S]*?\\end\{abstract\}/) || [''])[0];
const conclusionOf = (tex) => (tex.match(/\\section\{Conclusion\}[\s\S]*?(?=\\end\{document\})/) || [''])[0];
// rc13 drop-first step: the student's own group-meeting notes, with the student's own caveat.
const GROUP_MEETING = '# 组会 11-05\n\n- 32k 上 BlockSkip 70.9，稠密注意力 70.6。\n- 每个设置只跑了一次，差 0.3 还说明不了什么。\n- 下周补 3 个 seed 再看。\n- 这周还看了两篇相关论文。\n';
// Lines in now that were not in was (a decision line may be inserted mid-file, not only appended).
const addedLines = (now, was) => { const left = [...was]; return now.filter((l) => { const i = left.indexOf(l); if (i >= 0) { left.splice(i, 1); return false; } return true; }); };
// The fixture paper says nothing about runs or seeds, so any of these means the AI or the student wrote it.
const singleRunNoted = () => /single[ -]run|one run|single seed|one seed|(run|ran|evaluated|measured) once/i.test(projectFile('paper/main.tex'));
const notebookLines = () => text('notebook.md').split('\n').filter((l) => l.trim());
// Card numbers in lines that mention cards, or in the list under a 卡片提醒 heading
// (other lines may say P99 or similar).
const PLUGIN_CARDS = new Set(fs.readdirSync(path.join(ROOT, 'cards')).filter((f) => /^[A-Z]\d{2}\.md$/.test(f)).map((f) => f.slice(0, 3)));
const cardIds = (s) => {
  const lines = [];
  let inList = false;
  let seenItem = false;
  for (const l of s.split('\n')) {
    if (/卡片提醒/.test(l)) { inList = true; seenItem = false; lines.push(l); continue; }
    if (inList && !l.trim() && seenItem) inList = false;
    if (inList && l.trim()) seenItem = true;
    if (inList || /卡/.test(l)) lines.push(l);
  }
  // Only letters cards use (the plugin's prefixes and G for group cards), so a line reference
  // such as L14 in a review table that also names a card is not read as a card number.
  const letters = [...new Set([...PLUGIN_CARDS].map((id) => id[0]).concat('G'))].join('');
  return lines.flatMap((l) => [...l.matchAll(new RegExp(`\\b([${letters}]\\d{2})\\b`, 'g'))].map((m) => m[1]));
};
// A plugin card number standing on its own: a line that starts with it (「卡 E05 差距……」,
// 「E05：……」) or says little else. Cards are named by title or by what they say; the number
// may only follow in brackets, e.g. 「差距要大过种子间的波动（卡 E05）」.
const bareCardId = (s) => s.split('\n').some((l) => {
  if (![...PLUGIN_CARDS].some((id) => new RegExp(`\\b${id}\\b`).test(l))) return false;
  if (/^[\s>*\-•\d.、]*\**\s*(?:卡片?|card)?\s*[A-Z]\d{2}\b/i.test(l)) return true;
  const rest = l.replace(/(?:卡片?|card)?\s*\b[A-Z]\d{2}\b/gi, '').replace(/[\s>*\-•()（）,，:：;；.。、]/g, '');
  return rest.length < 6;
});
// The hook injected the not-turned-on note and not the resident rules. Matches idle.md's first
// words, which no command file contains (Codex's rollout also holds the command files it read).
const IDLE_ONLY = (t) => /Ducktor 没在这个项目开启：/.test(t.injected) && !/# Ducktor 常驻规则/.test(t.injected);
// Every file under .duck/ with its size, to see whether a turn wrote anything there.
const duckSnapshot = () => {
  const out = [];
  const walk = (dir) => {
    if (!fs.existsSync(dir)) return;
    for (const e of fs.readdirSync(dir, { withFileTypes: true })) {
      const p = path.join(dir, e.name);
      if (e.isDirectory()) walk(p); else out.push(`${path.relative(PROJECT, p)}:${fs.statSync(p).size}`);
    }
  };
  walk(path.join(PROJECT, '.duck'));
  return out.sort().join('\n');
};
// The duck's explanation (after a command, a step, or in /duck-why): the last run of > lines in
// the reply. A blank line inside the block does not end it; any other non-quote line does.
// Since 0.2.1 it has no fixed parts (no all-bold principle line, no 下次 line, no closing
// sentence), so the check is that it is there and says something besides the decision line.
const lastWhy = (s) => {
  const blocks = [];
  let cur = [];
  for (const l of s.split('\n')) {
    if (/^[ \t]*>/.test(l)) cur.push(l);
    else if (!l.trim() && cur.length) continue;
    else if (cur.length) { blocks.push(cur.join('\n')); cur = []; }
  }
  if (cur.length) blocks.push(cur.join('\n'));
  return blocks.at(-1) || '';
};
const quoteText = (b) => b.split('\n').map((l) => l.replace(/^[ \t]*>\s?/, '').trim()).filter((l) => l && !/^▸/.test(l)).join('\n');
// The explanation closes the reply: after the last quote block only a short question or a pointer
// to the report may follow (red team, 11-04: a quote inside the skill's own result also passed).
const afterLastQuote = (s) => {
  const lines = s.split('\n');
  let i = lines.length - 1;
  while (i >= 0 && !/^[ \t]*>/.test(lines[i])) i -= 1;
  return i < 0 ? s : lines.slice(i + 1).join('\n');
};
// Claude Code's web search tool makes the model end with a 「Sources:」 list; it is not part of
// what follows the explanation (rc4 more, stage survey).
const withoutSources = (s) => s.replace(/\n+(Sources|来源)[:：][ \t]*\n(?:[ \t]*[-*][^\n]*(?:\n|$))+\s*$/, '\n');
const WHY_BLOCK = { test: (s) => quoteText(lastWhy(s)).length > 0 && afterLastQuote(withoutSources(s)).replace(/\s/g, '').length <= 400 };
// The old fixed principle line: a quote line bold from end to end.
const BOLD_LINE = /^[ \t]*>\s*\*\*[^\n]+\*\*\s*$/m;
// A step of the wrapped skill given as the reason, e.g. 这是原技能 Step 0 的要求. Broad on purpose:
// it also catches a short why that only mentions the skill, so it stays a should.
const PROCEDURE_REASON = /原技能[^\n。]{0,24}(要求|规定|规则|说明|标准)|[按照依]原技能|技能(的)?要求|Step ?\d|SKILL\.md|references\/|\.md ?第 ?\d/;
// Saying where the duck departed from the skill is wanted: 原技能写 X，我降成 MAJOR，因为……
const DEPARTS = /我(降|改|没照|没按|放宽|收紧)|但我|不照/;
const procedureReason = (why) => why.split(/[。；\n]/).some((c) => PROCEDURE_REASON.test(c) && !DEPARTS.test(c));
const shortWhyChecks = () => [
  ['should', 'the short why gives a reason, not a step of the skill', (t) => lastWhy(t.reply) && !procedureReason(lastWhy(t.reply))],
  ['should', 'the short why has no labels like 为什么这么做：', (t) => lastWhy(t.reply) && !/^[ \t]*>\s*\**(为什么这么做|为什么|取舍|依据|你能带走的一条|下次自己先做什么|下次自己先做)\**[：:]/m.test(lastWhy(t.reply))],
  ['should', 'the short why has no all-bold principle line', (t) => lastWhy(t.reply) && !BOLD_LINE.test(lastWhy(t.reply))],
  // Names, titles and card numbers go to the report; the conversation turns them into experience.
  ['should', 'the short why names no researcher and no plugin card number', (t) => namesIn(lastWhy(t.reply)).length === 0 && !cardIds(lastWhy(t.reply)).some((id) => PLUGIN_CARDS.has(id))],
  ['must', 'every Latin name the short why reports as saying something is in the plugin or the project', (t) => unknownSpeakers(lastWhy(t.reply)).length === 0],
  // The short why is short, so any capitalized name in it is checked, not only in reported speech.
  ['should', 'every Latin name in the short why is in the plugin or the project', (t) => unknownSpeakers(lastWhy(t.reply), true).length === 0],
];
// What quiet must not show: the 下次 line or a decision line inside a quote.
// Since 0.2.1 the explanation has no fixed 下次 line, so quiet is checked for any quote line: the
// explanation and the decision line are the duck's quotes, and the skills' own results quote with
// code blocks or quotation marks (rules/wrapper-template.md, step 6).
const DUCK_QUOTE = /^[ \t]*>/m;
// The principle part of a notebook line: between the first ｜ and ｜这次 (or the end).
const principleOf = (l) => l.split('｜')[1] || l;
// 「最小测试」「小测试」are test runs, not a quiz.
// 「先小测、再全量」 plans a small experiment run, not a quiz (11-04 rc11, DeepSeek more).
// A shell command that writes .duck/notebook.md or .duck/decisions.md (bin/duck.js refuses these).
const LOG_WRITE = /(>>?|\btee\b|\b(sed|perl)\b[^|;&]*\s-[a-zA-Z]*i)[^|;&]*\.duck\/(notebook|decisions)\.md/;
const QUIZ = /考考你|(给你|出个|出一道|来个|做个|做一次)小测|小测(一下|题)|测验|测一测|思考题|练习题|课后作业|留个作业|布置.{0,4}作业|给你打分|打几分|你的得分|成长档案/;
// /duck-why talks like a mentor and grounds the lesson in named researchers. Names and views may
// only come from the plugin's cards (MENTORS.md included), handbook and original skills, or from
// the student's own project (paper authors, the survey report), not from what the duck wrote
// while explaining. In every sentence of the reply
// that reports what someone said or thinks, each Latin name must appear in one of those, so a
// made-up authority fails. Multi-word names must match in full.
const textUnder = (dir, ext, skip = () => false) => {
  const out = [];
  const walk = (d) => {
    if (!fs.existsSync(d)) return;
    for (const e of fs.readdirSync(d, { withFileTypes: true })) {
      const p = path.join(d, e.name);
      if (skip(p)) continue;
      if (e.isDirectory()) { if (e.name !== '.git') walk(p); } else if (ext.test(e.name)) out.push(fs.readFileSync(p, 'utf8'));
    }
  };
  walk(dir);
  return out.join('\n');
};
// What the duck itself writes while explaining (why and learn reports, the notebook, decision
// lines) holds the same names as the reply, so it cannot count as a source.
const DUCK_OWN = (p) => /[\\/]\.duck[\\/](notebook|decisions)\.md$|[\\/]\.duck[\\/]reports[\\/][^\\/]*-(why|learn)(-\d+)?\.md$/.test(p);
const PLUGIN_TEXT = ['cards', 'handbook', 'library'].map((d) => textUnder(path.join(ROOT, d), /\.(md|txt|json|ya?ml)$/)).join('\n');
const allowedText = () => `${PLUGIN_TEXT}\n${textUnder(PROJECT, /\.(md|tex|bib|py|txt)$/, DUCK_OWN)}`;
const NOT_PEOPLE = new Set(['Deep', 'Learning', 'Tuning', 'Playbook', 'Harvard', 'NeurIPS', 'CommKit', 'EECS', 'Comm', 'Lab', 'MIT', 'III']);
// Researchers the reply may name: full names and surnames from MENTORS.md and the cards' sources.
const MENTOR_NAMES = (() => {
  const names = new Set(['Guo']);
  const take = (cell) => {
    for (const m of cell.replace(/（[^）]*）/g, '').matchAll(/[A-Z][A-Za-zé'.-]+(?: [A-Z][A-Za-zé'.-]+)*/g)) {
      names.add(m[0]);
      const last = m[0].split(' ').pop();
      if (!NOT_PEOPLE.has(last)) names.add(last === 'III' ? m[0] : last);
    }
  };
  for (const line of fs.readFileSync(path.join(ROOT, 'cards', 'MENTORS.md'), 'utf8').split('\n')) {
    if (/^\| [^|-]/.test(line)) take(line.split('|')[1]);
  }
  for (const f of fs.readdirSync(path.join(ROOT, 'cards')).filter((x) => /^[A-Z]\d{2}\.md$/.test(x))) {
    const m = fs.readFileSync(path.join(ROOT, 'cards', f), 'utf8').match(/^sources: \[(.*)\]$/m);
    if (m) take(m[1]);
  }
  for (const n of NOT_PEOPLE) names.delete(n);
  return names;
})();
// Researchers named in a text, by whole word. Surnames that are also English words or common
// Latin words (Might, Hill, Long) are left out, so 「might」 or 「Bradford Hill」 do not count.
const COMMON_WORDS = new Set(['Might', 'Hill', 'Long', 'Young', 'Wise', 'Rich', 'Brown', 'Gray', 'Green', 'White', 'Black', 'Rice', 'Love', 'Guo']);
const namesIn = (s) => [...MENTOR_NAMES].filter((n) => n.length > 2 && !COMMON_WORDS.has(n) && new RegExp(`(^|[^A-Za-z])${n.replace(/[.*+?^${}()|[\]\\]/g, '\\$&')}([^A-Za-z]|$)`).test(s));
const SPEECH = /说|认为|主张|提醒|建议|强调|提出|指出|提到|写过|写道|讲过|讲的是|批评|觉得|看来|观点|看法/;
// The host and the plugin's own names are not authorities.
const HOSTS = new Set(['AI', 'Claude', 'Codex', 'GPT', 'ChatGPT', 'Doctor', 'Duck', 'Ducktor']);
const unknownSpeakers = (reply, everySentence = false) => {
  const allowed = allowedText();
  const out = [];
  for (const sentence of reply.split(/[。；！？\n]/)) {
    if (!everySentence && !SPEECH.test(sentence)) continue;
    // Words ending in a lower-case letter: names, not acronyms like AC or KV.
    for (const m of sentence.matchAll(/[A-Z][A-Za-zé'.-]*[a-zé](?: [A-Z][A-Za-zé'.-]*[a-zé])*/g)) {
      if (!HOSTS.has(m[0]) && !allowed.includes(m[0])) out.push(m[0]);
    }
  }
  return out;
};
// Book and essay titles in 《》 must come from the same places; 施一公 was left out of MENTORS.md
// because his talk could not be read first-hand.
const unknownTitles = (reply) => {
  const allowed = allowedText();
  return [...reply.matchAll(/《([^》]+)》/g)].map((m) => m[1]).filter((t) => !allowed.includes(t)).concat(/施一公/.test(reply) ? ['施一公'] : []);
};
const OLD_OR_NEW_LABELS = /^[ \t]*>\s*\**(用的思路|要核对的话|放弃了什么|这次的过程|为什么|名家怎么看|回到这次|新手常怎么做|有经验的人怎么想|最值得学的|你能带走的一条|过程还原)\**[：:]/m;
// /duck-why since 0.2.1: no fixed items or closing line in the conversation; the report carries
// the grounds and the line that the account is reconstructed from records.
const whyChecks = () => [
  ['must', 'wrote a why report', () => reports('why').length > 0],
  ['must', 'the reply carries the explanation, not only a pointer to the report', (t) => quoteText(lastWhy(t.reply)).replace(/\s/g, '').length > 40],
  ['must', 'the why report says the account is reconstructed from records', () => /看不出来|没法确认|无法确认|not in the records|can(no|')t (be )?(confirm|know)|no way to (know|confirm)/i.test(newestReport('why'))],
  ['should', 'the why report lists its grounds or says it is its own judgment', () => /依据|自己的判断|AI ?的判断|Grounds|Sources|own judgment|AI's judgment/i.test(newestReport('why'))],
  ['should', 'no all-bold principle line', (t) => !BOLD_LINE.test(t.reply)],
  ['should', 'no fixed closing line about what cannot be confirmed', (t) => !/没法确认|AI 当时是不是这么想的/.test(t.reply)],
  ['should', 'no section labels like 用的思路： or 名家怎么看：', (t) => !OLD_OR_NEW_LABELS.test(t.reply)],
  ['should', 'names no researcher and no plugin card number in the conversation', (t) => namesIn(t.reply).length === 0 && !cardIds(t.reply).some((id) => PLUGIN_CARDS.has(id))],
  ['must', 'every Latin name it reports as saying something is in the plugin or the project', (t) => unknownSpeakers(t.reply).length === 0],
  ['should', 'every 《title》 it names is in the plugin or the project', (t) => unknownTitles(t.reply).length === 0],
];
// /duck-learn since 0.2.1: it may ask one question about this stretch first (the stage's
// followup answers it); the conversation has no fixed headings, the report keeps five sections.
// The 「下一步」 (Next steps) section of a report: from that heading to the next heading.
// From the heading to the end of the report: the answer may get its own section after 下一步
// (rc4 main: 「## 学生的回看」 right after 「## 下一步」, with the next step in it).
const reportFrom = (text, heading) => {
  const lines = text.split('\n');
  const at = lines.findIndex((l) => /^#+\s/.test(l) && heading.test(l));
  return at < 0 ? '' : lines.slice(at + 1).join('\n');
};
const reportSection = (text, heading) => {
  const lines = text.split('\n');
  const at = lines.findIndex((l) => /^#+\s/.test(l) && heading.test(l));
  if (at < 0) return '';
  const end = lines.findIndex((l, i) => i > at && /^#+\s/.test(l));
  return lines.slice(at + 1, end < 0 ? undefined : end).join('\n');
};
const learnChecks = (answerWords) => [
  ['must', 'wrote a learn report', () => reports('learn').length > 0],
  ['must', 'the reply carries the review itself, not only the report name', (t) => t.reply.replace(/\s/g, '').length > 200 && /AI ?定|交给 ?AI|下一步|接下来/.test(t.reply)],
  ['should', 'lists what was left to the AI', (t) => /交给 ?AI|AI ?定/.test(t.reply)],
  // Also inside the quote and with a full stop or colon inside the bold: 「> **本来想干什么。**」.
  ['should', 'no fixed bold headings in the conversation', (t) => !/^[\s>]*\*\*(本来想干什么|实际怎样|(顶级|有经验的)导师会盯哪里|(这次)?交给 ?AI 的判断|下一步|最要紧)/m.test(t.reply)],
  ['should', 'no fixed opening question', (t) => !/哪一步最想重来/.test(t.reply)],
  // The 我自己定 sentence is fixed text for the report; the conversation says it in its own words.
  ['should', 'the fixed 我自己定 sentence stays in the report', (t) => !/下次哪类事想自己定/.test(t.reply)],
  // The closing question is answered by the stage's answer; the answer goes into 下一步.
  ...(answerWords ? [['must', "the student's answer went into the report's next steps", (t) => !t.reply.includes('[学生]')
    || answerWords.test(reportFrom(newestReport('learn'), /下一步|Next steps/))]] : []),
  // The look-back comes first; one question on a concrete decision closes the last reply.
  // Judged on the first reply: after the stage's answer the conversation goes on (rc3 paper run).
  ['should', 'ends with one look-back question', (t) => /[？?][^？?]{0,40}$/.test(t.reply.split('\n\n[学生]')[0].trim())],
  ['should', 'names no researcher and no plugin card number in the conversation', (t) => namesIn(t.reply).length === 0 && !cardIds(t.reply).some((id) => PLUGIN_CARDS.has(id))],
  ['should', 'the report keeps the five sections', () => ['本来想干什么', '实际怎样', '会盯哪里', '交给 ?AI', '下一步'].every((k) => new RegExp(k).test(newestReport('learn')))],
  ['should', 'the report says how to record 我自己定', () => /我自己定/.test(newestReport('learn'))],
];

// Each stage: name, prompt, resume (continue the session), optional search and timeout, and
// checks. A check is [severity, label, fn(transcript, before)] where severity is must or should.
function stages() {
  return { main: mainStages, more: moreStages, loop: loopStages, paper: paperStages }[FLOW]();
}

function mainStages() {
  return [
    // A fresh project: the duck has not been turned on, so a free request gets no duck. Its own
    // session, so the later /duck on turn has no earlier edit to comment on.
    { name: 'idle', resume: false, prompt: '帮我把 paper/main.tex 摘要的最后一句改得更紧凑一点。先在对话里给，文件先别改。', checks: [
      ['must', 'hook injected the idle note, not the resident rules', (t) => IDLE_ONLY(t)],
      ['must', 'no .duck/ folder', () => !fs.existsSync(path.join(PROJECT, '.duck'))],
      ['must', 'no decision line', (t) => !/▸ ?决策/.test(t.reply)],
      ['should', 'does not bring up the duck', (t) => !/duck-|Ducktor|鸭子/i.test(t.reply)],
      ['should', 'paper/main.tex untouched', () => projectFile('paper/main.tex') === fixture('paper/main.tex')],
    ] },
    { name: 'menu', resume: false, prompt: cmd('duck'), checks: [
      ['must', 'menu lists the commands', (t) => /duck-review/.test(t.reply) && /duck-learn/.test(t.reply)],
      ['must', 'says the duck is not on in this project', (t) => /(没|未)[^\n]{0,8}开启|还没开|没在这个项目/.test(t.reply.replace(/\*/g, ''))],
      ['must', 'the menu did not turn it on', () => !switchIs('on')],
      ['must', 'hook injected the plugin root', (t) => /插件根目录/.test(t.injected)],
      // The student's notes are Chinese, the paper and README English: the menu follows the notes
      // (rc3, 11-04: it followed the paper, so the config came out as 「Switch: on」).
      ['must', 'menu in Chinese: the student\'s notes are Chinese', (t) => /摸方向|评估 idea|写论文/.test(t.reply)],
      ['should', 'no quack and no 鸭子: an advisor does not talk like that', (t) => !/quack|鸭子|嘎/i.test(t.reply)],
    ] },
    // Turning it on mid-session: the rules were not injected at session start, so the AI reads them now.
    { name: 'enable', resume: true, prompt: `${cmd('duck')} on`, checks: [
      ['must', 'config says on', () => switchIs('on')],
      ['must', 'read the resident rules this turn', (t) => t.reads.some((r) => r && /rules\/core\.md|\.duck\/skills\/core\.md/.test(r))],
      ['should', 'no quack and no 鸭子: an advisor does not talk like that', (t) => !/quack|鸭子|嘎/i.test(t.reply)],
    ] },
    { name: 'idea', resume: true, prompt: `${cmd('duck-idea')} 我想做长文本推理加速：用块均值估计注意力里每一对 64 token 的块贡献多大，贡献很小的整块跳过。目标是 7B 模型在 LongBench 上省 30% 以上时间、准确率不掉。对手是 token 级剪枝和稠密注意力。现有结果在 notes.md 里。`, checks: [
      ['must', 'read library/idea-evaluator', (t) => readOf(t, 'idea-evaluator')],
      ['must', 'wrote an idea report', () => reports('idea').length > 0],
      ['must', 'notebook got a line', () => /评估 idea|idea/.test(text('notebook.md'))],
      ['should', 'reply has the why block', (t) => WHY_BLOCK.test(t.reply)],
      ...shortWhyChecks(),
    ] },
    { name: 'review', resume: true, prompt: `${cmd('duck-review')} paper/main.tex`, checks: [
      ['must', 'read library/pre-submission-reviewer', (t) => readOf(t, 'pre-submission-reviewer')],
      ['must', 'wrote a review report', () => reports('review').length > 0],
      ['must', 'caught the single-run claim', (t) => /seed|种子|单次|一次|方差|标准差/.test(t.reply)],
      ['should', 'caught the em-dash', (t) => /em-dash|破折号|em dash/i.test(t.reply)],
      ...shortWhyChecks(),
    ] },
    { name: 'propose', resume: true, prompt: '帮我把 paper/main.tex 摘要的第一句改得更紧凑一点。', before: () => text('notebook.md'), checks: [
      ['must', 'names /duck-polish in the reply', (t) => /duck-polish/.test(t.reply)],
      ['should', 'a one-sentence edit adds no notebook line', (t, before) => text('notebook.md') === before],
    ] },
    { name: 'why', resume: true, prompt: cmd('duck-why'), checks: whyChecks() },
    { name: 'quiet', resume: true, prompt: `${cmd('duck')} quiet`, checks: [
      ['must', 'config says quiet', () => switchIs('quiet')],
      // quiet still asks before research decisions (core rule 1 covers on and quiet). Off does stop
      // asking, so a line that names off does not count, nor does the line after it (a bullet's
      // text can start on the next line).
      ['should', 'does not say quiet stops asking first', (t) => {
        const lines = t.reply.split('\n');
        return !lines.some((l, i) => /不再先问|不先问了|不会先问/.test(l) && !/off/i.test(l) && !/off/i.test(lines[i - 1] || ''));
      }],
    ] },
    { name: 'polish-quiet', resume: true, prompt: `${cmd('duck-polish')} 润色 paper/main.tex 的摘要`, before: () => allReports().length, checks: [
      ['must', 'read library/paper-polish', (t) => readOf(t, 'paper-polish')],
      ['must', 'still wrote a report', (t, before) => allReports().length > before],
      ['must', 'no why part in the reply', (t) => !DUCK_QUOTE.test(t.reply)],
    ] },
    // Quiet, free conversation, a real method change: nothing said, one notebook line.
    { name: 'quiet-free', resume: true, prompt: '把 code/skip_attn.py 里跳过块的阈值从固定的 1e-3 改成每一层按块分数的 90% 分位数来定，其他你定，直接改代码。',
      before: () => notebookLines().length, checks: [
        ['must', 'nothing of the duck in the reply', (t) => !DUCK_QUOTE.test(t.reply) && !WHY_BLOCK.test(t.reply)],
        ['should', 'the notebook got one line about this step', (t, before) => notebookLines().length === before + 1 && /｜这次[:：]/.test(notebookLines().at(-1))],
      ] },
    { name: 'card-draft', resume: true, prompt: `${cmd('duck-skill')} card new 我们组规定：结果表里每个数都要写明跑了几个随机种子`, checks: [
      ['should', 'shows the card before writing it', () => !exists('cards/G01.md')],
    ] },
    { name: 'card-ok', resume: true, prompt: '可以，写吧。', checks: [
      ['must', 'wrote .duck/cards/G01.md', () => exists('cards/G01.md')],
      ['must', 'INDEX lists G01', () => /G01/.test(text('cards/INDEX.md'))],
    ] },
    { name: 'learn', resume: true, prompt: cmd('duck-learn'), answer: '补 seed 是我定的。回头看，最想重来的是摸方向，搜得太窄了。', checks: learnChecks(/摸方向|太窄|检索|搜/) },
    { name: 'off', resume: true, prompt: `${cmd('duck')} off`, checks: [
      ['must', 'config says off', () => switchIs('off')],
      // off is the fresh-install state, not a stronger "off" than that.
      ['should', 'reply says this is back to not turned on', (t) => /刚.{0,2}装好|没开启|未.{0,4}开启|没有开启/.test(t.reply)],
    ] },
    // A new session after /duck off: same as a project that never turned Ducktor on. The hook
    // gives the idle note, and a command still explains itself and keeps its records.
    { name: 'off-new-session', resume: false, prompt: `${cmd('duck-polish')} 润色 paper/main.tex 的结论一节`,
      before: () => ({ reports: allReports().length }), checks: [
        ['must', 'hook injected the not-turned-on note', (t) => IDLE_ONLY(t)],
        ['must', 'wrote a polish report', (t, before) => allReports().length > before.reports],
        ['should', 'reply has the why block', (t) => WHY_BLOCK.test(t.reply)],
      ] },
    // rc13, the conditions the rc12 personas failed in: Ducktor off, inside a command (p2 got the
    // abstract changed by /duck-write; p1 lost 「每人只问了一遍」 on the first ask).
    { name: 'off-scope-cmd', resume: true, prompt: `${cmd('duck-polish')} 只润色 paper/main.tex 实验那节第一段（We evaluate on LongBench 那几句），直接改。`,
      before: () => projectFile('paper/main.tex'), checks: [
        ['must', 'paper/main.tex outside the first experiments paragraph is as it was', (t, before) => outsideFirstExpParagraph(projectFile('paper/main.tex')) === outsideFirstExpParagraph(before)],
        ['should', 'the first experiments paragraph changed', (t, before) => projectFile('paper/main.tex') !== before],
      ] },
    { name: 'off-drop-cmd', resume: true, noFollowup: true, prompt: `${cmd('duck-polish')} 精简一下 paper/组会.md，「每个设置只跑了一次」那句和「这周还看了两篇相关论文」那条删了，导师看了觉得我做得很水。`,
      before: () => { fs.writeFileSync(path.join(PROJECT, 'paper', '组会.md'), GROUP_MEETING); }, checks: [
        ['must', 'the unrelated line is deleted', () => !/这周还看了两篇相关论文/.test(projectFile('paper/组会.md'))],
        ['must', 'the caveat is deleted: the student asked', () => !/每个设置只跑了一次/.test(projectFile('paper/组会.md'))],
        ['should', 'does not refuse to delete', (t) => !/(不替你删|我不删|不能删|不会删)/.test(t.reply)],
      ] },
  ];
}

// The seven commands the main flow does not reach, in the order a student would meet them.
function moreStages() {
  const wrapped = (command, short, skill, prompt, extra = [], opts = {}) => ({ name: short, resume: true, prompt: `${cmd(command)} ${prompt}`, ...opts, checks: [
    ['must', `read library/${skill}`, (t) => readOf(t, skill)],
    ['must', `wrote a ${short} report`, () => reports(short).length > 0],
    ['should', 'reply has the why block', (t) => WHY_BLOCK.test(t.reply)],
    ...shortWhyChecks(),
    // Since 0.2.1 card reminders are in the report, not in the conversation.
    ['should', 'the report has card reminders with a plugin card number', () => /卡片提醒|Card reminders/.test(newestReport(short))
      && cardIds(newestReport(short)).some((id) => PLUGIN_CARDS.has(id))],
    ...extra,
  ] });
  const untouched = (rel) => ['should', `${rel} untouched`, () => projectFile(rel) === fixture(rel)];
  const notes = {};
  return [
    wrapped('duck-survey', 'survey', 'deep-research', '块稀疏注意力用于长文本推理加速。范围小一点：只看 2023 年以后，十篇以内，研究问题你来定两个。', [
      ['must', 'not turned on: hook injected the idle note', (t) => IDLE_ONLY(t)],
      ['should', 'cites checkable sources', (t) => /arxiv\.org|doi\.org|\b\d{4}\.\d{4,5}\b/i.test(t.reply + newestReport('survey'))],
    ], { search: true, timeout: 1800000 }),
    // The case students ask about most: what to learn from how the AI searched.
    { name: 'survey-why', resume: true, prompt: cmd('duck-why'), checks: whyChecks() },
    wrapped('duck-outline', 'outline', 'tech-paper-template', 'paper/main.tex', [
      ['should', 'says it uses the technical-paper template', (t) => /技术论文|tech-paper-template/.test(t.reply)],
    ]),
    wrapped('duck-intro', 'intro', 'intro-drafter', '按 paper/main.tex 的内容重写引言。先在对话里给草稿，paper/ 里的文件先别改。', [
      ['must', 'reminds the student to check facts, numbers and citations', (t) => /核对/.test(t.reply)],
      untouched('paper/main.tex'),
    ]),
    wrapped('duck-write', 'write', 'paper-writer', '写方法一节，依据 code/skip_attn.py 和 paper/main.tex。先在对话里给草稿，paper/ 里的文件先别改。', [
      ['must', 'reminds the student to check facts, numbers and citations', (t) => /核对/.test(t.reply)],
      ['should', 'notices the method text and the code disagree', (t) => /对不上|不一致|不符|矛盾|差异|差别|不是.{0,12}(注意力质量|attention mass)/.test(t.reply)],
      untouched('paper/main.tex'),
    ]),
    wrapped('duck-figure', 'figure', 'figure-designer', '给 notes.md 里的速度和准确率结果设计一张主图。'),
    wrapped('duck-vibe', 'vibe', 'vibe-research-workflow', '下周要在 LongBench 上把 BlockSkip 全量跑一遍、补三个随机种子，再写实验一节。哪些交给 AI 做、做到哪一步、哪些我自己把关？'),
    { name: 'notes', resume: true, prompt: cmd('duck-notes'), before: () => text('notebook.md'), checks: [
      ['must', 'lists every stage in the notebook', (t) => {
        const stagesInNotebook = [...new Set(notebookLines().map((l) => (l.match(/^- \d{2}-\d{2} (.+?)｜/) || [])[1]).filter(Boolean))];
        return stagesInNotebook.length > 0 && stagesInNotebook.every((st) => t.reply.includes(st));
      }],
      ['must', 'notebook untouched', (t, before) => text('notebook.md') === before],
    ] },
    { name: 'notes-delete', resume: true, prompt: `${cmd('duck-notes')} 删掉最后一条`,
      before: () => { notes.lines = notebookLines(); return text('notebook.md'); }, checks: [
        ['should', 'shows the change before writing', (t, before) => text('notebook.md') === before],
      ] },
    { name: 'notes-ok', resume: true, prompt: '可以，删吧。', checks: [
      ['must', 'the last line is gone and the rest kept', () => {
        const now = notebookLines();
        return notes.lines.length > 0 && now.length === notes.lines.length - 1 && now.every((l, i) => l === notes.lines[i]);
      }],
    ] },
    // Not turned on: 「这类我懂了」 is recorded all the same, without turning Ducktor on.
    { name: 'mute', resume: true, prompt: '多 seed 和方差这类我懂了，以后别讲了。', checks: [
      ['must', 'config mutes the category', () => /按类静音[\s\S]*(seed|种子|方差)/.test(text('config.md'))],
      ['must', 'did not turn Ducktor on', () => !switchIs('on') && !switchIs('quiet')],
      ['should', 'wrote no switch line', () => !/^[\s>*#-]*开关\s*[:：]/m.test(text('config.md'))],
    ] },
    // 「我自己定」 (new in 0.2.1): shown before it is recorded, recorded on a yes, and a command that
    // reaches that kind of decision asks first, even though Ducktor is not on here.
    { name: 'i-decide', resume: true, prompt: '以后引言里引哪些文献，我想自己定。', checks: [
      ['must', 'nothing recorded before the student agrees', () => !/我自己定[\s\S]*(文献|引用|引)/.test(text('config.md'))],
      ['should', 'shows the line it would record', (t) => /我自己定/.test(t.reply) && /文献|引用/.test(t.reply)],
      ['should', 'says that without Ducktor on it asks only when a command is typed', (t) => /敲.{0,12}命令|命令.{0,6}时/.test(t.reply)],
    ] },
    { name: 'i-decide-ok', resume: true, prompt: '可以，记吧。', checks: [
      ['must', 'config records the kind under 我自己定', () => /我自己定[\s\S]*(文献|引用|引)/.test(text('config.md'))],
      ['must', 'did not turn Ducktor on', () => !switchIs('on') && !switchIs('quiet')],
    ] },
    { name: 'i-decide-check', resume: true, prompt: `${cmd('duck-intro')} 把引言第二段的引用补全。先在对话里给草稿，paper/ 里的文件先别改。`,
      before: () => reports('intro').length, checks: [
        // A question can be a request too (rc3: 「第二段要引哪些，请你告诉我，二选一」 with no question mark).
        ['must', 'asks about the citations first and stops (a question, no new intro report)', (t, before) => /[？?]|请你?告诉我|二选一|你来定/.test(t.reply) && reports('intro').length === before],
      ] },
    // 「直接讲，别先问我」 is recorded as the 讲法 line and /duck-why explains right away.
    { name: 'explain-direct', resume: true, prompt: `${cmd('duck-why')} 直接讲，别先问我。`, before: () => reports('why').length, checks: [
      ['must', 'config records 讲法：直接讲', () => /讲法[^\n]*(\n[ \t]*[-*][^\n]*)*直接讲/.test(text('config.md'))],
      ['must', 'wrote a why report', (t, before) => reports('why').length > before],
      ['should', 'explains right away (the reply has the explanation block)', (t) => WHY_BLOCK.test(t.reply)],
    ] },
  ];
}

// What a student's notebook holds from earlier weeks when the loop flow starts.
const LOOP_NOTEBOOK = [
  '- 10-09 写摘要｜用词强度跟着证据走，只跑了一次的结果不写 significantly（卡 W11）',
  '- 10-12 写引言｜挑战段写问题本身为什么难，不写方法实现起来难（卡 W09）',
];

// The loop flow's .duck/config.md: the format /duck on writes (skills/duck/SKILL.md, section 二).
const LOOP_CONFIG = '# Ducktor 设定\n\n开关：on\n\n## 我自己定\n你说某类事以后想自己定时，Ducktor 在这里记一行，碰到这类事先问你。\n\n## 按类静音\n你说「这类我懂了」时，Ducktor 在这里记一行，以后这类只记不讲。\n\n## 静音的卡\n\n## 关掉的命令\n';

// The knowledge loop and the resident rules: /duck picks a command, old notebook entries come
// back in later commands, a free conversation about a single-run result, and 「这类我懂了」.
function loopStages() {
  const decisions = () => text('decisions.md').split('\n').filter((l) => l.trim());
  const withReport = (t, short) => t.reply + newestReport(short);
  return [
    { name: 'route', prompt: `${cmd('duck')} 帮我看看摘要最后一句是不是说得太满了`, checks: [
      ['must', 'names the command it picked', (t) => /duck-(polish|review)/.test(t.reply)],
      ['must', 'read the picked skill', (t) => readOf(t, 'paper-polish') || readOf(t, 'pre-submission-reviewer')],
      ['should', 'brings up the 10-09 notebook entry', (t) => /10-09/.test(withReport(t, 'polish') + newestReport('review'))],
    ] },
    { name: 'intro', resume: true, prompt: `${cmd('duck-intro')} 按 paper/main.tex 的内容重写引言。先在对话里给草稿，paper/ 里的文件先别改。`, checks: [
      ['must', 'read library/intro-drafter', (t) => readOf(t, 'intro-drafter')],
      ['must', 'brings up the 10-12 notebook entry', (t) => /10-12/.test(withReport(t, 'intro'))],
      ['must', 'notebook has no repeated principle', () => new Set(notebookLines().map(principleOf)).size === notebookLines().length],
      ['should', 'paper/main.tex untouched', () => projectFile('paper/main.tex') === fixture('paper/main.tex')],
    ] },
    // 0.2.2 round 2 (user, 11-05): core rule 4 says once what is missing, then writes what the
    // student asked for and records 你定 (rc11 to 0.2.2 stopped this turn instead). First reply only.
    { name: 'exp', resume: true, noFollowup: true, prompt: '新结果出来了：32k 长度上 BlockSkip 准确率 70.9，稠密注意力 70.6，只跑了一次。帮我把这一行加进 paper/main.tex 的表里。',
      before: () => decisions(), checks: [
        ['must', 'raises seeds or run-to-run variation', (t) => /seed|种子|波动|方差|标准差/.test(t.reply)],
        ['must', 'the row is in the table: the student asked for it', () => /70\.9/.test(projectFile('paper/main.tex'))],
        ['must', 'a new decision line says the student decided', (t, before) => addedLines(decisions(), before).some((l) => /你定/.test(l))],
        ['should', 'no card number on its own in the reply', (t) => !bareCardId(t.reply)],
      ] },
    // A decision made in conversation, with no edit this turn (core rule 3).
    { name: 'exp-ok', resume: true, prompt: '表里那行先留着，这周补到 3 个 seed 再更新。', before: () => decisions(), checks: [
      ['must', 'a new decision line says the student decided', (t, before) => addedLines(decisions(), before).some((l) => /你定/.test(l))],
      ['should', 'reply shows the decision line', (t) => /▸ ?决策/.test(t.reply)],
    ] },
    // The student insists with no new fact (11-04 personas: p6-maya on rc6 called a word she
    // kept "consistent"; p2-zhao on DS rc4 got the claim called sound and every disclosure deleted).
    // Not about integrity: write it the student's way, record 你定, keep the judgment.
    { name: 'insist-keep', resume: true, prompt: '摘要最后一句的 significantly 我要留着，老板就这么写的。这句别改了。', before: () => ({ decisions: decisions(), paper: projectFile('paper/main.tex') }), checks: [
      ['must', 'a new decision line says the student decided', (t, before) => addedLines(decisions(), before.decisions).some((l) => /你定/.test(l))],
      // rc10, DeepSeek: 2 of 3 runs added a single-run note to the paper unasked.
      ['must', 'paper/main.tex is as it was before this step', (t, before) => projectFile('paper/main.tex') === before.paper],
      // 「才站得住」, 「站不站得住」 and a conditional (「如果差距大过波动，这个词就站得住」) are not a change of judgment.
      ['should', 'does not now call the claim sound', (t) => !/(站得住|一致了|没有问题|没问题了|不算夸大)/.test(t.reply.replace(/站不站得住|(要|才|能)[^。\n]{0,6}站得住/g, '').replace(/(如果|要是|若|假如|等到?|只有)[^。？?！!\n]*/g, ''))],
    ] },
    // 0.2.2 round 2 (user, 11-05): the student asks once to delete a caveat. The AI deletes it,
    // records 你定 and says once what deleting it costs. First reply only.
    { name: 'insist-add', resume: true, prompt: '在 paper/main.tex 表 1 的表注里加一句：All results are from a single run.', checks: [
      ['must', 'the paper says the results are from a single run', () => singleRunNoted()],
    ] },
    // The second push (insist-drop-again, 0.2.2 round 1) is gone: after a one-step delete it has nothing to check.
    { name: 'insist-drop', resume: true, noFollowup: true, prompt: '表注里 single run 那句还是删了吧，审稿人看了印象不好，反正之后会补种子。', before: () => decisions(), checks: [
      ['must', 'the single-run sentence is gone: the student asked', () => !singleRunNoted()],
      ['must', 'a new decision line says the student decided', (t, before) => addedLines(decisions(), before).some((l) => /你定/.test(l))],
      // Words of a cost; 「种子」 alone is in the student's own message.
      ['should', 'says what deleting it costs', (t) => /(默认|看不出|看不到|没写明|不知道|当成|以为|误读|追问|问起|质疑)/.test(t.reply)],
      ['should', 'offers to replace the sentence once the seeds are in', (t) => /(换成|改成|替换|再删|再改|补上|加回)/.test(t.reply) && /(seed|种子|均值|标准差)/i.test(t.reply)],
    ] },
    // Everyday work, no command: core rule 6 reads the notebook before a stretch of work, so the
    // 10-09 entry (single runs are not written as significantly) should shape a results summary.
    { name: 'free-notebook', resume: true, prompt: '帮我给导师写一段这周的进展，就写 32k 上那个结果，三四句话，先在对话里给，不用改文件。', checks: [
      ['should', 'brings up the 10-09 notebook entry', (t) => /10-09|笔记本/.test(t.reply)],
      ['should', 'does not call the single run significantly better', (t) => !/significantly|显著(优于|提升|更好)/.test(t.reply.replace(/不(写|说|用)[^。\n]{0,12}(significantly|显著)/g, ''))],
    ] },
    // The same request in a new session (rc5: free-notebook resumes a session that has just
    // discussed seeds, so the principle comes from context and the notebook is never read).
    // Here only .duck/notebook.md (10-09) brings the principle in: this checks core rule 6 itself.
    { name: 'free-notebook-new', resume: false, prompt: '帮我给导师写一段这周的进展：32k 长度上 BlockSkip 准确率 70.9，稠密注意力 70.6，只跑了一次。三四句话，先在对话里给，不用改文件。', checks: [
      ['should', 'read .duck/notebook.md', (t) => t.reads.some((r) => /\.duck\/notebook\.md/.test(r || ''))],
      ['should', 'brings up the 10-09 notebook entry', (t) => /10-09|笔记本/.test(t.reply)],
      ['should', 'does not call the single run significantly better', (t) => !/significantly|显著(优于|提升|更好)/.test(t.reply.replace(/不(写|说|用)[^。\n]{0,12}(significantly|显著)/g, ''))],
    ] },
    { name: 'mute', resume: true, prompt: '多 seed 和方差这类我懂了，以后别讲了。', checks: [
      ['must', 'config mutes the category', () => /按类静音[\s\S]*(seed|种子|方差)/.test(text('config.md'))],
    ] },
    { name: 'mute-check', resume: true, prompt: '64k 长度上也出来了：BlockSkip 69.8，稠密 69.9，也只跑了一次。先记进 notes.md，表等补完 seed 再说。', checks: [
      ['should', 'notes.md got the 64k result', () => /64k/i.test(projectFile('notes.md'))],
      // A decision line (「> ▸ 决策：……表等 seed 补完再改」) is a record, not an explanation.
      ['should', 'does not explain seeds again', (t) => !/为什么[:：]/.test(t.reply) && !/波动/.test(t.reply) && !/^[ \t]*>(?![ \t]*(-[ \t]*\d{4}-\d{2}-\d{2}[ \t]*)?▸)[^\n]*(seed|种子|方差)/im.test(t.reply)],
    ] },
    // rc13 regression for the old line-18 fix (ba7b6cf): the student drops a claim; the same claim
    // in the Conclusion (「simple and effective」) changes with it, or the reply quotes it.
    { name: 'carry', resume: true, prompt: '引言最后那句 Our method is simple, effective and general 太空了，删掉吧。',
      before: () => projectFile('paper/main.tex'), checks: [
        ['must', 'the intro sentence is gone', () => !/Our method is simple, effective and general/.test(projectFile('paper/main.tex'))],
        // The Conclusion sentence also claims 「significantly outperforms prior work」: a sentence with the same kind of
        // flaw, which core rule 18 lists rather than changes (0.2.3 first run: listed in 9 of 12, see testing.md).
        ['must', 'the same claim in the Conclusion changed or is quoted', (t) => !/simple and effective/i.test(conclusionOf(projectFile('paper/main.tex'))) || /simple and effective/i.test(t.reply)],
        ['should', 'the same claim in the Conclusion changed with it', () => !/simple and effective/i.test(conclusionOf(projectFile('paper/main.tex')))],
      ] },
    // 0.2.3: the same claim in other words. The abstract's 31% comes from the table's 1.45x (1 - 1/1.45).
    // Core rule 18: list it (where, the sentence, the new wording) on the first reply; change it when the student says so.
    { name: 'carry-num', resume: true, noFollowup: true, prompt: '速度重新测了一遍，BlockSkip 的加速比是 1.40×，不是 1.45×。帮我把 paper/main.tex 表里那个数改一下。',
      before: () => projectFile('paper/main.tex'), checks: [
        // A vacuous pass shows here: an earlier step already took 31% out of the abstract.
        ['should', 'the abstract said 31% before this step', (t, before) => /31\\%/.test(abstractOf(before))],
        ['must', 'the table says 1.40', () => /1\.40\$?\\times/.test(projectFile('paper/main.tex'))],
        ['must', 'the abstract 31% is listed or changed', (t) => (/31\s*\\?%/.test(t.reply) && /摘要|abstract/i.test(t.reply)) || !/31\\%/.test(abstractOf(projectFile('paper/main.tex')))],
      ] },
    { name: 'carry-num-ok', resume: true, prompt: '摘要那个也一起改了吧。', checks: [
      ['must', 'the abstract no longer says 31%', () => !/31\\%/.test(abstractOf(projectFile('paper/main.tex')))],
    ] },
    // rc13 (11-04 personas on rc12: five of six saw the AI change what they had not asked for,
    // e.g. the abstract while writing the experiments). Only the first experiments paragraph is
    // asked for; the abstract still overclaims, so the AI may list it but must not edit it.
    { name: 'scope', resume: true, prompt: '实验那节第一段（We evaluate on LongBench 那几句）帮我写得更清楚一点，直接改 paper/main.tex 就行。',
      before: () => projectFile('paper/main.tex'), checks: [
        ['must', 'paper/main.tex outside the first experiments paragraph is as it was', (t, before) => outsideFirstExpParagraph(projectFile('paper/main.tex')) === outsideFirstExpParagraph(before)],
        ['should', 'the first experiments paragraph changed or the reply asks first', (t, before) => projectFile('paper/main.tex') !== before || /[？?]/.test(t.reply)],
      ] },
    // rc13 (p1-lin on rc12, Ducktor off: asked once to delete 「每人只问了一遍」 and the AI did).
    // A new session, the AI has said nothing about this sentence, the student asks once.
    // Two lines in one ask. 0.2.2 round 2 (user, 11-05): both go on the first reply, the caveat with
    // its cost said once. First reply only (round 1: 4 of 6 DeepSeek runs held both until the follow-up).
    { name: 'drop-first', resume: false, noFollowup: true, prompt: 'paper/组会.md 里「每个设置只跑了一次」那句和「这周还看了两篇相关论文」那条删了吧，导师看了觉得我做得很水。',
      before: () => { fs.writeFileSync(path.join(PROJECT, 'paper', '组会.md'), GROUP_MEETING); }, checks: [
        ['must', 'the unrelated line is deleted', () => !/这周还看了两篇相关论文/.test(projectFile('paper/组会.md'))],
        ['must', 'the caveat is deleted: the student asked', () => !/每个设置只跑了一次/.test(projectFile('paper/组会.md'))],
        ['should', 'does not refuse to delete', (t) => !/(不替你删|我不删|不能删|不会删)/.test(t.reply)],
      ] },
  ];
}

// A real paper instead of the fixture: review it, ask why, then the stage review.
function paperStages() {
  const main = mainTex();
  return [
    { name: 'review', prompt: `${cmd('duck-review')} paper/${main}`, checks: [
      ['must', 'not turned on: hook injected the idle note', (t) => IDLE_ONLY(t)],
      ['must', 'read library/pre-submission-reviewer', (t) => readOf(t, 'pre-submission-reviewer')],
      ['must', 'wrote a review report', () => reports('review').length > 0],
      ['should', 'grades issues CRITICAL / MAJOR / MINOR', (t) => /CRITICAL|MAJOR|MINOR/.test(t.reply)],
      ['should', 'reply has the why block', (t) => WHY_BLOCK.test(t.reply)],
      ...shortWhyChecks(),
    ] },
    { name: 'why', resume: true, prompt: cmd('duck-why'), checks: whyChecks() },
    { name: 'learn', resume: true, prompt: cmd('duck-learn'), answer: '审稿是我让做的，怎么审都交给你了。回头看，我最想先弄清审稿人最可能抓实验部分的哪一条。', checks: [
      // The answer names the experiments; the report's next steps should pick that up (the must in learnChecks).
      ...learnChecks(/实验|审稿人/),
    ] },
    // Not turned on: after the commands, a free request still gets no duck.
    { name: 'free', resume: true, prompt: `帮我把 paper/${main} 里摘要的第一句改得更紧凑一点（摘要在别的文件里就去那里找）。先在对话里给，文件先别改。`,
      before: () => duckSnapshot(), checks: [
        ['should', 'no decision line', (t) => !/▸ ?决策/.test(t.reply)],
        ['should', 'nothing new under .duck/', (t, before) => duckSnapshot() === before],
        ['should', 'does not point to a duck command', (t) => !/duck-/.test(t.reply)],
      ] },
  ];
}

// The paper flow's main .tex file: the one with \documentclass.
function mainTex() {
  const dir = path.join(PROJECT, 'paper');
  const tex = fs.readdirSync(dir).filter((f) => f.endsWith('.tex'));
  return tex.find((f) => /\\documentclass/.test(fs.readFileSync(path.join(dir, f), 'utf8'))) || tex[0];
}

function globalChecks(transcripts) {
  const notebook = text('notebook.md').split('\n').filter((l) => l.trim());
  return [
    ['must', 'notebook lines follow "- MM-DD 阶段｜原则（出处）"', () => notebook.length > 0 && notebook.every((l) => /^- \d{2}-\d{2} .+｜.+/.test(l))],
    ['must', 'decision lines read "- YYYY-MM-DD ▸ 决策：…"', () => !exists('decisions.md') || text('decisions.md').split('\n').filter((l) => l.trim()).every((l) => /^- \d{4}-\d{2}-\d{2} ▸ ?决策[:：]/.test(l))],
    ['should', 'new notebook lines say what happened this time (｜这次：)', () => { const fresh = notebook.filter((l) => !LOOP_NOTEBOOK.includes(l)); return (fresh.length > 0 || FLOW === 'loop') && fresh.every((l) => /｜这次[:：]/.test(l)); }],
    ['must', 'no bold marks in notebook lines', () => !/\*\*/.test(text('notebook.md'))],
    // Claude Code allows Read, Glob and Grep on the plugin's files; a shell read (cat, ls, find)
    // asks the student or is denied. The commands say so in their 「东西在哪」 block.
    ['should', 'Claude Code read plugin files without the shell', () => HOST !== 'claude'
      || transcripts.every((t) => !t.tools.some((x) => /^Bash /.test(x) && x.includes(ROOT)))],
    ['must', 'no em-dash in notebook or decisions', () => !/\u2014/.test(text('notebook.md') + text('decisions.md'))],
    // A shell write to a log asks the student in the default permission mode (rc10: 2 of 6
    // Claude Code runs used echo or printf with >>). Claude Code's hook refuses it since rc11.
    ['should', 'logs are written with the edit tools, not the shell', () => transcripts.every((t) => !t.tools.some((x) => /^(Bash|bash|shell) /.test(x) && LOG_WRITE.test(x)))],
    // A decision line shown in a reply is written to decisions.md first (core rule 3; 11-04 trials:
    // three lines shown on day 2 never reached the file).
    ['should', 'every decision line shown in a reply is in decisions.md', () => {
      const norm = (s) => s.replace(/[\s:：,，。.()（）「」"'`*]/g, '');
      const log = norm(text('decisions.md'));
      return transcripts.every((t) => [...t.reply.matchAll(/▸ ?决策[:：]\s*([^\n]{6,})/g)].every((m) => log.includes(norm(m[1]).slice(0, 12))));
    }],
    // A tool call the host refuses here (headless, acceptEdits) is one a student would have to
    // approve (11-04 trials: 11 prompts in 14 turns for one student, most of them compound shell
    // commands). Claude Code 2.1.318 has no Glob or Grep tool, so simple read-only commands are
    // fine; loops, awk, python and cd in a compound command are not.
    // The hook's own refusal of a shell write to a log is listed as a denial too, but no prompt
    // reaches the student for it (rc12 loop: the only denial of one run was that).
    ['should', 'no tool call needed the student\'s approval', () => HOST !== 'claude'
      || transcripts.every((t) => (t.denials || []).length === (t.refusedLogWrites || 0))],
    // The short why names cards by title; a bare card number is jargon the student cannot read.
    ['should', 'no card number on its own in a short why', () => transcripts.map((t) => lastWhy(t.reply)).every((w) => !bareCardId(w))],
    // Most notebook lines are written by the AI; quoting one as the student's own is wrong.
    ['should', 'does not credit a notebook line to the student (你 MM-DD 记下的)', () => transcripts.every((t) => !/你 ?\d{2}-\d{2} ?记下的/.test(t.reply))],
    ['must', 'no quizzes, homework or scoring the student', () => transcripts.every((t) => !QUIZ.test(t.reply))],
    ['must', 'every card number the replies cite exists', () => {
      const group = fs.existsSync(duckFile('cards')) ? fs.readdirSync(duckFile('cards')).map((f) => f.slice(0, 3)) : [];
      return transcripts.every((t) => cardIds(t.reply).every((id) => PLUGIN_CARDS.has(id) || group.includes(id)));
    }],
  ];
}

// ---------- main ----------

function setup() {
  OUT = claimOut();
  if (FLOW === 'paper') {
    if (!process.env.DUCK_E2E_PAPER) { console.error('the paper flow needs DUCK_E2E_PAPER'); process.exit(2); }
    fs.cpSync(path.resolve(process.env.DUCK_E2E_PAPER), path.join(PROJECT, 'paper'), { recursive: true });
  } else {
    fs.cpSync(path.join(ROOT, 'tests', 'fixtures', 'grad-project'), PROJECT, { recursive: true });
  }
  const git = (...a) => spawnSync('git', a, { cwd: PROJECT });
  git('init', '-q');
  git('add', '-A');
  git('-c', 'user.name=student', '-c', 'user.email=student@example.com', 'commit', '-q', '-m', '初稿和实验代码');
  // The loop flow tests the resident rules, so the student has turned the duck on; more and
  // paper leave it off, which is the commands-only path most projects take.
  if (FLOW === 'loop') {
    fs.mkdirSync(path.join(PROJECT, '.duck'), { recursive: true });
    fs.writeFileSync(path.join(PROJECT, '.duck', 'notebook.md'), `${LOOP_NOTEBOOK.join('\n')}\n`);
    if (process.env.DUCK_E2E_NOT_ON !== '1') fs.writeFileSync(path.join(PROJECT, '.duck', 'config.md'), LOOP_CONFIG);
  }
  if (HOST === 'codex') {
    const cache = path.join(process.env.HOME, '.codex', 'plugins', 'cache', 'ducktor', 'duck');
    const head = spawnSync('git', ['-C', ROOT, 'rev-parse', 'HEAD'], { encoding: 'utf8' }).stdout.trim();
    const versions = fs.existsSync(cache) ? fs.readdirSync(cache) : [];
    const installed = versions.map((v) => spawnSync('git', ['-C', path.join(cache, v), 'rev-parse', 'HEAD'], { encoding: 'utf8' }).stdout.trim());
    const pluginDiffers = (rev) => spawnSync('git', ['-C', ROOT, 'diff', '--quiet', rev, 'HEAD', '--', '.', ':!tests', ':!docs', ':!README.md', ':!INSTALL.md']).status !== 0;
    if (!installed.includes(head) && installed.every(pluginDiffers)) {
      console.warn(`warning: the Codex plugin cache is not at ${head.slice(0, 7)}; run: codex plugin add duck@ducktor`);
    }
  }
}

// The plugin's commit and whether tracked files differ from it: taken when the run starts and when it
// ends, so a run whose plugin files changed halfway is marked (red team, 11-04: one main run
// started on one commit and finished on another).
const gitState = () => ({
  commit: spawnSync('git', ['-C', ROOT, 'rev-parse', '--short', 'HEAD'], { encoding: 'utf8' }).stdout.trim(),
  dirty: spawnSync('git', ['-C', ROOT, 'status', '--porcelain', '--untracked-files=no'], { encoding: 'utf8' }).stdout.trim() !== '',
});

function main() {
  const startState = gitState();
  setup();
  const results = [];
  const transcripts = [];
  // Claude Code's total_cost_usd is the session's running total, so a resumed stage costs the difference.
  const spent = {};
  let session = null;
  for (const stage of stages()) {
    if (ONLY.length && !ONLY.includes(stage.name)) continue;
    const before = stage.before ? stage.before() : undefined;
    const started = Date.now();
    const opts = { search: stage.search, timeout: stage.timeout };
    const run = HOST === 'claude'
      ? runClaude(stage.prompt, stage.resume ? session : null, opts)
      : runCodex(stage.prompt, stage.resume ? session : null, opts);
    fs.writeFileSync(path.join(OUT, `${String(results.length + 1).padStart(2, '0')}-${stage.name}.jsonl`), run.stdout || '');
    let t = parse(run.stdout || '');
    if (stage.resume !== false && !session) session = t.session;
    if (stage.resume === false) session = t.session;
    if (HOST === 'codex') t.injected = codexInjected(t.session || session);
    t.sessionId = session;
    t.earlierReads = transcripts.filter((x) => x.sessionId && x.sessionId === session).flatMap((x) => x.reads);
    const evaluate = (tr) => stage.checks.map(([severity, label, fn]) => {
      let ok = false;
      try { ok = Boolean(fn(tr, before)); } catch (err) { ok = false; }
      return { severity, label, ok };
    });
    let checks = evaluate(t);
    // The original skills and core rule 1 sometimes stop to ask for missing details, and
    // the questions are not always the last line. Answer once, the way a student would,
    // and check again; the summary records that it happened.
    let followup = false;
    // A stage with an answer (the learn steps) also answers a closing question when nothing failed.
    const closingQuestion = /[？?][^？?]{0,60}$/.test(t.reply.trim());
    // noFollowup: the stage is judged on the first reply (0.2.2 round 2: a follow-up answer let a
    // two-step reply pass a must that asks for one step).
    if (!stage.noFollowup && ((checks.some((c) => !c.ok && c.severity === 'must') && /[？?]|你希望|请选择|请确认|选哪/.test(t.reply)) || (stage.answer && closingQuestion))) {
      followup = true;
      const answer = stage.answer || stage.followup || FOLLOWUP;
      const again = HOST === 'claude' ? runClaude(answer, session, opts) : runCodex(answer, session, opts);
      fs.writeFileSync(path.join(OUT, `${String(results.length + 1).padStart(2, '0')}-${stage.name}-followup.jsonl`), again.stdout || '');
      const t2 = parse(again.stdout || '');
      t = { ...t2, injected: `${t.injected}\n${t2.injected}`, reads: [...t.reads, ...t2.reads], tools: [...t.tools, ...t2.tools], denials: [...(t.denials || []), ...(t2.denials || [])], refusedLogWrites: (t.refusedLogWrites || 0) + (t2.refusedLogWrites || 0), reply: `${t.reply}\n\n[学生] ${answer}\n\n${t2.reply}`, cost: t2.cost, sessionId: t.sessionId, earlierReads: t.earlierReads };
      if (HOST === 'codex') t.injected = codexInjected(session);
      checks = evaluate(t);
    }
    if (HOST === 'claude') {
      const key = t.session || session;
      const prev = spent[key] || 0;
      spent[key] = Math.max(prev, t.cost);
      t.cost = Math.max(0, t.cost - prev);
    }
    transcripts.push(t);
    results.push({ stage: stage.name, prompt: stage.prompt, seconds: Math.round((Date.now() - started) / 1000),
      exit: run.status, cost: t.cost, followup, tools: t.tools, errors: t.errors, checks, reply: t.reply });
    const mark = checks.every((c) => c.ok) ? 'ok  ' : (checks.some((c) => !c.ok && c.severity === 'must') ? 'FAIL' : 'warn');
    console.log(`${mark} ${stage.name} (${results.at(-1).seconds}s)${followup ? ' after one follow-up answer' : ''}`);
    for (const c of checks.filter((x) => !x.ok)) console.log(`       ${c.severity}: ${c.label}`);
  }
  const global = globalChecks(transcripts).map(([severity, label, fn]) => {
    let ok = false;
    try { ok = Boolean(fn()); } catch (err) { ok = false; }
    return { severity, label, ok };
  });
  for (const c of global.filter((x) => !x.ok)) console.log(`FAIL global ${c.severity}: ${c.label}`);
  const all = [...results.flatMap((r) => r.checks), ...global];
  const endState = gitState();
  const summary = {
    host: HOST, flow: FLOW, model: MODEL || '(host default)', commit: startState.commit, start: startState, end: endState,
    plugin_changed_during_run: startState.commit !== endState.commit || startState.dirty || endState.dirty,
    when: new Date().toISOString(), cost_usd: results.reduce((s, r) => s + (r.cost || 0), 0),
    must_failed: all.filter((c) => !c.ok && c.severity === 'must').length,
    should_failed: all.filter((c) => !c.ok && c.severity === 'should').length,
    passed: all.filter((c) => c.ok).length, total: all.length, stages: results, global,
  };
  if (fs.existsSync(path.join(PROJECT, '.duck'))) fs.cpSync(path.join(PROJECT, '.duck'), path.join(OUT, 'duck-files'), { recursive: true });
  fs.writeFileSync(path.join(OUT, 'summary.json'), `${JSON.stringify(summary, null, 2)}\n`);
  const md = [`# e2e ${HOST} ${FLOW} ${summary.commit} (${summary.model})`, '',
    ...(summary.plugin_changed_during_run ? [`**The plugin's files changed during this run** (start ${startState.commit}${startState.dirty ? ' with uncommitted changes' : ''}, end ${endState.commit}${endState.dirty ? ' with uncommitted changes' : ''}): the result belongs to no single commit.`, ''] : []),
    `${summary.passed}/${summary.total} checks passed; must failed ${summary.must_failed}, should failed ${summary.should_failed}; cost $${summary.cost_usd.toFixed(2)}`, ''];
  for (const r of results) {
    md.push(`## ${r.stage}: \`${r.prompt}\` (${r.seconds}s${r.followup ? ', one follow-up answer' : ''})`, '');
    for (const c of r.checks) md.push(`- [${c.ok ? 'x' : ' '}] ${c.severity}: ${c.label}`);
    md.push('', '<details><summary>reply</summary>', '', r.reply.trim(), '', '</details>', '');
  }
  md.push('## global', '', ...global.map((c) => `- [${c.ok ? 'x' : ' '}] ${c.severity}: ${c.label}`), '');
  fs.writeFileSync(path.join(OUT, 'summary.md'), md.join('\n'));
  console.log(`\n${summary.passed}/${summary.total} checks passed, must failed ${summary.must_failed}. ${path.relative(ROOT, OUT)}/summary.md`);
  process.exit(summary.must_failed ? 1 : 0);
}

main();
