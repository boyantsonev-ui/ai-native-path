// Lesson 14 — The course that teaches itself

function Lesson14() {
  return (
    <div>

      <HeroCard
        eyebrow="Meta"
        title="The course that teaches itself"
        lede="Every rating you submitted, every question you asked — this system processed it. Here's the architecture running underneath."
        meta={["4 min read", "Orchestrator pattern", "Live example"]}
      />

      <p style={{ color: "var(--ink-2)", marginTop: 8, marginBottom: 0 }}>
        This is the capstone: a real orchestrator pattern running live on this course. You'll see the architecture, understand how each node maps to a pattern you've already learned, and get the setup checklist to wire it yourself.
      </p>

      <section>
        <h3 className="eyebrow" style={{ marginBottom: 4 }}>Part 1 — The architecture</h3>
        <h2>This isn't a demo</h2>
        <p>
          Most courses talk about AI-native architectures. This one runs on one. The feedback panel at the bottom of each lesson doesn't just collect stars — it feeds a live learning loop that proposes content improvements and can open a GitHub PR to apply them.
        </p>
        <p>
          Everything in this architecture is a pattern you've already seen in the course. The diagram below cross-references each node back to the lesson that introduced it.
        </p>
      </section>

      <section>
        <h2>The orchestrator diagram</h2>
        <AgentDiagram kind="course-orchestrator" />
      </section>

      <section>
        <h2>How each node maps to a pattern</h2>

        <div className="cheat-card" style={{ marginTop: 16 }}>

          <div className="cc-item">
            <div className="eyebrow">Augmented LLM · Agents — what the term means</div>
            <h4>Supabase + /api/synthesize</h4>
            <p>
              The synthesis function is an LLM (Claude API) augmented with external memory — Supabase stores the feedback it reads and the proposals it writes. That's the Augmented LLM pattern: model + retrieval + memory + tools.
            </p>
          </div>

          <div className="cc-item">
            <div className="eyebrow">Evaluator-Optimizer · Sub-agents &amp; orchestrators</div>
            <h4>Feedback → proposals → revisions</h4>
            <p>
              Each synthesis run evaluates the course against learner feedback and generates graded improvement proposals. Approved proposals close the loop — the course is the generator, synthesis is the evaluator, the HITL review is the optimizer step.
            </p>
          </div>

          <div className="cc-item">
            <div className="eyebrow">Human-in-the-Loop · Autonomous agents</div>
            <h4>The HITL proposals tab</h4>
            <p>
              Trivial proposals can be auto-applied via PR; minor and major ones require human review. This is the HITL checkpoint pattern: the agent proposes, a human decides, the system acts. Nothing major ships without approval.
            </p>
          </div>

          <div className="cc-item">
            <div className="eyebrow">Orchestrator + sub-agent · Sub-agents &amp; orchestrators</div>
            <h4>/api/apply → GitHub → Vercel</h4>
            <p>
              The admin dashboard is the orchestrator: it receives an approved proposal and delegates to the <code>/api/apply</code> sub-agent, which fetches the file, makes a targeted edit via Claude, opens a branch, and creates a PR. The orchestrator never touches the file directly.
            </p>
          </div>

        </div>
      </section>

      <section>
        <h3 className="eyebrow" style={{ marginBottom: 4 }}>Part 2 — The infrastructure</h3>
        <h2>The three infrastructure pieces</h2>
        <CodeTabs files={[
          {
            name: "vercel.json",
            lang: "json",
            code: `{
  "crons": [
    {
      "path": "/api/synthesize",
      "schedule": "0 9 * * MON"
    }
  ]
}`,
          },
          {
            name: "api/synthesize.js (shape)",
            lang: "js",
            code: `// 1. Guard — reject if already running
// 2. Fetch feedback WHERE synthesized = false
// 3. If count < threshold, skip
// 4. Call Claude API with the synthesis prompt
// 5. Bulk-insert proposals to hitl_proposals
// 6. Mark feedback synthesized = true
// 7. Update syntheses row to status = 'complete'`,
          },
          {
            name: "Supabase schema (key tables)",
            lang: "sql",
            code: `-- Learner feedback (written directly from browser)
feedback (id, lesson_id, type, rating, content,
          sentiment, synthesized, session_id)

-- One row per synthesis run
syntheses (id, feedback_count, trigger, status, error)

-- Improvement proposals from each synthesis
hitl_proposals (id, synthesis_id, lesson_id, severity,
                type, title, problem, proposal, reasoning,
                feedback_count, status, admin_note, pr_url)`,
          },
        ]} />
      </section>

      <section>
        <h2>The upgrade path — Hermes</h2>

        <Callout kind="note" title="When to consider Hermes by Nous Research">
          <p>
            The current loop is a single-shot synthesis: one LLM call, structured output, done. That's the right starting point. When your loop becomes multi-step — synthesis → draft revision → review → commit — you need an agent framework that handles persistent memory, skill reuse, and multi-backend orchestration.
          </p>
          <p style={{ marginBottom: 0 }}>
            <strong>Hermes</strong> (MIT license, self-hosted) is built for exactly that. It adds: cross-session memory with FTS5 search, autonomous skill creation from successful runs, and 20+ messaging platform integrations so the agent is reachable without direct server access. Wire it in as the synthesis orchestrator when your loop outgrows a single function call.
          </p>
        </Callout>
      </section>

      <section>
        <h3 className="eyebrow" style={{ marginBottom: 4 }}>Part 3 — Set it up</h3>
        <h2>Setup checklist</h2>
        <p>
          The architecture is live when you complete these six steps. Until then the system falls back gracefully to localStorage and local synthesis via <code>window.claude.complete</code>.
        </p>

        <Steps items={[
          {
            label: "Create a Supabase project & run the schema",
            body: (<>
              <p>Go to <strong>supabase.com → New project</strong>. Once it's provisioned, open the <strong>SQL Editor</strong> and run these three tables in order:</p>
              <CodeTabs files={[
                {
                  name: "feedback",
                  lang: "sql",
                  code: `CREATE TABLE feedback (
  id           UUID PRIMARY KEY DEFAULT gen_random_uuid(),
  lesson_id    INT,
  lesson_title TEXT,
  type         TEXT,        -- 'rating' or 'chat'
  rating       INT,         -- 1–5 (null for chat entries)
  content      TEXT,
  sentiment    TEXT,        -- 'positive' | 'neutral' | 'negative'
  synthesized  BOOLEAN DEFAULT false,
  session_id   TEXT,
  created_at   TIMESTAMP DEFAULT now()
);

-- Allow anonymous browser inserts (RLS must be enabled)
ALTER TABLE feedback ENABLE ROW LEVEL SECURITY;
CREATE POLICY "anon insert" ON feedback
  FOR INSERT TO anon WITH CHECK (true);`,
                },
                {
                  name: "syntheses",
                  lang: "sql",
                  code: `CREATE TABLE syntheses (
  id             UUID PRIMARY KEY DEFAULT gen_random_uuid(),
  feedback_count INT,
  trigger        TEXT,   -- 'threshold' | 'manual' | 'cron'
  status         TEXT,   -- 'running' | 'complete' | 'failed'
  error          TEXT,
  created_at     TIMESTAMP DEFAULT now()
);

-- Only service_role (server-side) can read or write
ALTER TABLE syntheses ENABLE ROW LEVEL SECURITY;`,
                },
                {
                  name: "hitl_proposals",
                  lang: "sql",
                  code: `CREATE TABLE hitl_proposals (
  id            UUID PRIMARY KEY DEFAULT gen_random_uuid(),
  synthesis_id  UUID REFERENCES syntheses(id),
  lesson_id     INT,
  lesson_title  TEXT,
  severity      TEXT,   -- 'trivial' | 'minor' | 'major'
  type          TEXT,   -- 'typo' | 'accuracy' | 'clarification' | 'example' | 'structure'
  title         TEXT,
  problem       TEXT,
  proposal      TEXT,
  reasoning     TEXT,
  feedback_count INT,
  status        TEXT DEFAULT 'pending',
  admin_note    TEXT,
  pr_url        TEXT,
  reviewed_at   TIMESTAMP,
  created_at    TIMESTAMP DEFAULT now()
);

ALTER TABLE hitl_proposals ENABLE ROW LEVEL SECURITY;`,
                },
              ]} />
              <Callout kind="tip" title="Where to find your keys">
                <p>In Supabase: <strong>Settings → API</strong>. Copy three things: <strong>Project URL</strong>, <strong>anon / public key</strong> (goes into <code>app.jsx</code>), and <strong>service_role key</strong> (goes into Vercel — never commit it). The anon key is safe in client code because RLS prevents browsers from reading proposals.</p>
              </Callout>
            </>),
          },
          {
            label: "Create a GitHub fine-grained token",
            body: (<>
              <p>Go to <strong>GitHub → Settings → Developer settings → Fine-grained personal access tokens → Generate new token</strong>. Scope it to your course repo only, with these repository permissions:</p>
              <CodeBlock lang="text" filename="Required token permissions">
{`Contents       → Read and write   (fetch files, commit edits)
Pull requests  → Read and write   (open auto-fix PRs)
Metadata       → Read-only        (required by GitHub for all tokens)`}
              </CodeBlock>
              <Callout kind="warn" title="Scope it to one repo">
                The token only needs access to your course repo. Granting access to all repositories gives the auto-apply sub-agent unnecessary reach — scope it narrowly.
              </Callout>
            </>),
          },
          {
            label: "Add environment variables in Vercel",
            body: (<>
              <p>Go to <strong>Vercel project → Settings → Environment Variables</strong>. Add all seven — they apply to all environments (Production, Preview, Development):</p>
              <CodeBlock lang="bash" filename="Vercel environment variables">
{`ANTHROPIC_API_KEY          # sk-ant-... from console.anthropic.com
SUPABASE_URL               # https://xxxx.supabase.co
SUPABASE_SERVICE_ROLE_KEY  # from Supabase Settings → API → service_role
GITHUB_TOKEN               # fine-grained PAT from Step 2
GITHUB_OWNER               # your GitHub username or org name
GITHUB_REPO                # repo name only — not the full URL
SYNTHESIS_THRESHOLD        # optional — omit to use the default of 15`}
              </CodeBlock>
              <Callout kind="note" title="SUPABASE_ANON_KEY is different">
                The anon key lives in <code>app.jsx</code> as a client-side constant — it is not a Vercel env var. The service_role key above is the elevated server-side key used by <code>/api/synthesize</code> and <code>/api/apply</code>. Do not mix them up.
              </Callout>
            </>),
          },
          {
            label: "Update app.jsx with your Supabase client credentials",
            body: (<>
              <p>At the top of <code>app.jsx</code>, replace the two placeholder constants with the values from your Supabase project:</p>
              <CodeBlock lang="js" filename="app.jsx — lines 3–4">
{`const SUPABASE_URL      = "https://your-project-id.supabase.co";
const SUPABASE_ANON_KEY = "eyJhbGci...your-anon-key-here";`}
              </CodeBlock>
              <Callout kind="tip" title="Safe to commit">
                The anon key is designed to be public. Supabase RLS ensures browsers can only INSERT rows into <code>feedback</code> — they cannot read proposals or syntheses. Commit it freely.
              </Callout>
            </>),
          },
          {
            label: "Push to GitHub — Vercel does the rest",
            body: (<>
              <p>Vercel auto-detects the <code>/api</code> folder as serverless functions and <code>vercel.json</code> as the cron schedule. One push wires everything:</p>
              <Terminal
                label="git — course repo"
                lines={[
                  { kind: "cmd",  text: "git add app.jsx" },
                  { kind: "cmd",  text: 'git commit -m "wire Supabase credentials"' },
                  { kind: "cmd",  text: "git push origin main" },
                  { kind: "blank" },
                  { kind: "out",  text: "Vercel detects push → builds..." },
                  { kind: "ok",   text: "✓ Serverless functions: /api/synthesize, /api/apply" },
                  { kind: "ok",   text: "✓ Cron job registered: 0 12 * * 4 (Thu 12:00 UTC)" },
                  { kind: "ok",   text: "✓ Deployment live" },
                ]}
              />
              <Callout kind="do" title="Verify in Vercel dashboard">
                After deploy: <strong>Project → Functions tab</strong> should list <code>synthesize</code> and <code>apply</code>. <strong>Project → Cron Jobs tab</strong> should show Thursday 12:00 UTC. If Cron Jobs tab is missing, check that <code>vercel.json</code> is at the repo root.
              </Callout>
            </>),
          },
          {
            label: "Test the full loop end-to-end",
            body: (<>
              <p>Submit a test rating, confirm the Supabase write, then trigger your first synthesis manually:</p>
              <ol style={{ paddingLeft: 18, color: "var(--ink-2)", display: "flex", flexDirection: "column", gap: 12, marginTop: 12 }}>
                <li><strong>Submit feedback</strong> — Rate any lesson. Open <strong>Supabase → Table Editor → feedback</strong>. A new row should appear with <code>synthesized = false</code>. If it doesn't, check that <code>SUPABASE_URL</code> and <code>SUPABASE_ANON_KEY</code> in <code>app.jsx</code> match your project.</li>
                <li><strong>Unlock the admin dashboard</strong> — Click the <strong>"AI-Native Builder"</strong> brand logo in the sidebar <strong>five times in quick succession</strong> → enter your admin password → you're in.</li>
                <li><strong>Run synthesis</strong> — Go to the <strong>Automations</strong> tab → click <strong>"Run synthesis now"</strong>. The manual trigger bypasses the 15-item threshold. A proposal should appear in the <strong>HITL Proposals</strong> tab within 10–15 seconds.</li>
                <li><strong>Approve & auto-apply</strong> — Find a <strong>trivial</strong> proposal (moss-coloured badge) → click <strong>Approve</strong> → <strong>Apply automatically</strong>. A branch named <code>auto-fix/…</code> and a PR should appear in GitHub within 30 seconds.</li>
              </ol>
              <Callout kind="tip" title="Cron will take over from here">
                After the initial test, the system runs itself. The Thursday noon cron fires automatically once you have enough real learner feedback. The threshold (default 15) also auto-triggers synthesis mid-week if the course gets traffic.
              </Callout>
            </>),
          },
        ]} />

      </section>

      <QuizTiered tiers={[
        {
          label: "Beginner",
          question: "What does HITL mean in the course feedback loop?",
          options: [
            "A type of analytics dashboard",
            "A programming language for AI agents",
            "A checkpoint where a human reviews and approves AI-generated changes",
            "The name of the Supabase database",
          ],
          correct: 2,
          explain: "HITL — Human in the Loop — is a deliberate pause before the AI takes an irreversible action. A human reviews synthesis proposals before they become GitHub PRs, preventing the course from auto-editing in wrong directions.",
        },
        {
          label: "Intermediate",
          question: "Which pattern best describes the /api/synthesize function in this architecture?",
          options: [
            "Prompt chaining — it passes output from one step to the next in sequence",
            "Routing — it classifies feedback and sends it to different handlers",
            "Augmented LLM — it uses external memory (Supabase) and produces structured output",
            "Parallelization — it runs multiple LLM calls simultaneously",
          ],
          correct: 2,
          explain: "The synthesis function is an LLM augmented with retrieval (reads feedback from Supabase) and memory (writes proposals back). That's the Augmented LLM building block — same pattern as the Agents diagram.",
        },
        {
          label: "Advanced",
          question: "Synthesis proposals are often too vague to act on. What architectural change would most improve proposal specificity?",
          options: [
            "Increase the feedback item count before triggering synthesis",
            "Add a second LLM pass that grounds each proposal in a specific file and line range",
            "Use a larger model for synthesis",
            "Ask learners to write more detailed feedback",
          ],
          correct: 1,
          explain: "Vague proposals come from vague grounding. A two-pass pattern — cluster semantically, then locate specifically — maps each proposal to the exact file and line the change would affect. That's the diff the auto-apply agent needs.",
        },
      ]} />

    </div>
  );
}

function Lesson15() {
  return (
    <div>

      <HeroCard
        eyebrow="Foundations · Lesson 15"
        title="Context & cost"
        lede="Every message costs more than the one before it — not because you asked something harder, but because Claude re-reads every prior turn first. Here's how to work with that constraint instead of against it."
        meta={["6 min read", "Context management", "Cost optimisation"]}
      />

      <section>
        <h2>Why message 50 costs more than message 5</h2>
        <p>
          The single biggest cost driver in a Claude Code session isn't the complexity of your request — it's the size of the conversation Claude has to re-read before it can answer. Every message Claude sends requires processing the entire conversation from the top: your system prompt, every tool call, every file Claude read, every MCP response. Message 50 is expensive because Claude reads 49 prior turns before generating a single token of reply.
        </p>
        <p>
          This also means that every file read, every tool result, and every subagent output you pull into the main session stays there for the rest of the session. The context window fills up not from hard questions — but from accumulated history.
        </p>
        <Callout kind="note" title="The cost unit isn't the message">
          You're not paying per question. You're paying for the full context Claude processes to answer it. A short question at turn 80 of a heavy session costs more than a complex question at turn 3.
        </Callout>
      </section>

      <section>
        <h2>Diagnose before you optimise</h2>
        <p>
          Before tuning anything, find out where your tokens are actually going. Run <code>/context</code> — it shows a breakdown of your context window: system prompt, tools definitions, memory files, skills, and conversation history. If memory files are eating 15% of your window before the first task, that's fixable. If tool definitions are the culprit, you can disable unused MCP servers.
        </p>
        <CodeBlock lang="bash" filename="Claude Code">
{`/context`}
        </CodeBlock>
        <p>
          The status bar at the bottom of the terminal also shows token percentage in real time. Build the habit of glancing at it before starting each new task — it tells you how much working room you have left before things start getting expensive or before Claude starts dropping earlier context.
        </p>
        <Callout kind="tip" title="Red flags to watch for">
          Memory files consuming more than 10% before you've started, tool definitions from MCP servers you're not using this session, and conversation history that includes large file reads you no longer need. Each is independently fixable.
        </Callout>
      </section>

      <section>
        <h2>CLAUDE.md — signal, not noise</h2>
        <p>
          CLAUDE.md loads before Claude reads your code, before it reads your task, before anything. It persists in the context window for the entire session and is never lazy-loaded or evicted. Whatever you put there, Claude pays for on every single turn.
        </p>
        <CodeBlock lang="md" filename="CLAUDE.md — what belongs">
{`# Project: [name]

## Commands
- Install: npm install
- Dev: npm run dev
- Test: npm test
- Lint: npm run lint

## Conventions
- Use pnpm, not npm
- Tailwind utility classes only — no inline styles
- No default exports

## Architecture
- /src/components — presentational only
- /src/features — domain logic
- /api — serverless functions (Vercel)

## Directories to avoid
- /legacy — deprecated, do not read or edit
- /vendor — third-party, do not modify`}
        </CodeBlock>
        <Callout kind="warn" title="5,000 tokens, every turn">
          A 5,000-token CLAUDE.md costs 5,000 tokens on every single message — whether you send 2 or 200. Meeting notes, design history, and implementation guides do not belong there. Put only what Claude needs to work correctly in this repo: how to run things, what to avoid, and non-obvious constraints.
        </Callout>
        <p>
          You can also use CLAUDE.md to explicitly list which files are safe to read and which directories are off-limits. This prevents Claude from pulling in large irrelevant files during exploration.
        </p>
      </section>

      <section>
        <h2>Compact early, clear cleanly</h2>
        <p>
          <code>/compact</code> summarises the conversation history into a condensed snapshot, then continues from there. It dramatically shrinks the re-reading cost on all future turns. The key is timing: don't wait until you're near the context limit. Compact after completing a discrete sub-task, before starting the next one — think of it as checkpointing.
        </p>
        <Terminal
          label="Claude Code — /compact workflow"
          lines={[
            { kind: "cmd",  text: "Before we compact — note that we chose optimistic locking for the cart merge, and the API is at /api/cart/merge." },
            { kind: "out",  text: "Got it. I'll preserve that decision in the summary." },
            { kind: "blank" },
            { kind: "cmd",  text: "/compact" },
            { kind: "out",  text: "Compacting conversation..." },
            { kind: "ok",   text: "✓ Condensed 47 turns → 1 summary block" },
            { kind: "ok",   text: "✓ Preserved: optimistic locking decision, /api/cart/merge endpoint" },
            { kind: "out",  text: "Context window: 68% → 8%" },
          ]}
        />
        <p>
          Before running <code>/compact</code>, tell Claude which decisions matter: <em>"Note that we chose to use optimistic locking for the cart merge..."</em> This shapes what the compaction summary captures, so critical context doesn't get silently dropped.
        </p>
        <p>
          Use <code>/clear</code> when switching to completely unrelated work. It starts a fresh session with no history — cheaper than compacting when the prior context has zero bearing on the next task.
        </p>
      </section>

      <section>
        <h2>Explore in a separate window</h2>
        <p>
          When Claude researches an unfamiliar codebase, it reads lots of files. Every one of those reads lands in your main context and stays there. The fix: delegate exploration to a subagent with a phrase like <em>"use subagents to investigate X."</em> The subagent explores in its own context window, reads what it needs, and reports back a summary. Your main session gets the findings without inheriting the file contents.
        </p>
        <Callout kind="do" title="Subagents are context firewalls">
          Use subagents whenever you're about to pull in a large volume of read-only information — codebase archaeology, documentation research, dependency audits. The subagent pays the file-read cost; your session only pays for the summary it returns.
        </Callout>
      </section>

      <section>
        <h2>Right model for the job</h2>
        <p>
          On API billing, Opus costs roughly 5× more per token than Sonnet. Defaulting to Opus for everything isn't just expensive — it's slower for tasks that don't need deep reasoning.
        </p>

        <div className="two-col" style={{ marginTop: 16 }}>
          <div className="cheat-card">
            <h5>Claude Sonnet</h5>
            <p>Default for everything. Code generation, refactoring, content writing, most implementation work. The right starting point for every session.</p>
          </div>
          <div className="cheat-card">
            <h5>Claude Haiku</h5>
            <p>Quick lookups, renaming, formatting, and anything repetitive. Fastest and cheapest — use it whenever depth isn't required.</p>
          </div>
          <div className="cheat-card">
            <h5>Claude Opus</h5>
            <p>Complex architecture decisions, deep multi-file analysis, and reasoning-heavy refactors. Switch here deliberately, not by default.</p>
          </div>
          <div className="cheat-card">
            <h5>opusplan alias</h5>
            <p>Uses Opus during plan mode for complex reasoning, then automatically switches to Sonnet for implementation. Best of both without paying Opus rates throughout.</p>
          </div>
        </div>
      </section>

      <section>
        <h2>Hygiene: MCP, files, and sessions</h2>
        <p>
          <strong>MCP servers.</strong> Each enabled MCP server adds tool definitions to your context window — before any work begins. Keep fewer than 10 enabled per project. Where possible, prefer CLI equivalents: <code>gh</code> instead of the GitHub MCP, <code>aws</code> instead of the AWS MCP. Use <code>/mcp</code> to disable servers you don't need for the current task.
        </p>
        <p>
          <strong>File reads.</strong> A common context sink is pulling a 500-line file when you only need 20 lines. Scope reads narrowly. Filter test output to failures only. Avoid reformatting requests ("rewrite this as bullets") that burn tokens without changing meaning. If a directory is irrelevant to the current task, add it to <code>.claudeignore</code> — Claude won't touch it.
        </p>
        <p>
          <strong>Sessions.</strong> Name sessions with <code>/rename</code> and treat them like branches — one session per workstream. Use <code>claude --continue</code> to pick up the most recent session, or <code>claude --resume</code> to choose from a list. Mixing unrelated tasks in one session inflates context without benefit.
        </p>
        <p>
          <strong>The last 20% rule.</strong> Never start complex, multi-file work when the context window is more than 80% full. Memory-intensive operations — refactoring, feature implementation, debugging across components — require headroom. When you're running low, compact first.
        </p>
        <Callout kind="note" title="Prompt caching is on by default">
          Claude Code uses prompt caching to reduce costs and latency on repeated context. Leave it enabled. Only disable it (<code>DISABLE_PROMPT_CACHING=1</code>) when benchmarking or debugging cache behaviour — it meaningfully cuts costs in production use.
        </Callout>
      </section>

      <section>
        <h2>Quick reference</h2>

        <div className="cheat-card" style={{ marginTop: 16 }}>

          <div className="cc-item">
            <div className="eyebrow">Diagnose</div>
            <h4>Don't know where tokens are going</h4>
            <p>Run <code>/context</code> for a full breakdown by category: system prompt, tools, memory, skills, conversation.</p>
          </div>

          <div className="cc-item">
            <div className="eyebrow">Compact</div>
            <h4>Context growing mid-task</h4>
            <p>Run <code>/compact</code> at task breakpoints — after completing a sub-task, before starting the next. Tell Claude what to preserve first.</p>
          </div>

          <div className="cc-item">
            <div className="eyebrow">Clear</div>
            <h4>Switching to unrelated work</h4>
            <p>Use <code>/clear</code> to start fresh. Don't compact history that has zero relevance to the next task.</p>
          </div>

          <div className="cc-item">
            <div className="eyebrow">Subagents</div>
            <h4>Researching a large codebase</h4>
            <p>"Use subagents to investigate X." The subagent reads; your session gets only the summary.</p>
          </div>

          <div className="cc-item">
            <div className="eyebrow">Model selection</div>
            <h4>Over-paying per token</h4>
            <p>Default to Sonnet. Use Haiku for quick tasks. Switch to Opus only for deep analysis or complex reasoning.</p>
          </div>

          <div className="cc-item">
            <div className="eyebrow">MCP</div>
            <h4>Tool definitions eating context</h4>
            <p>Disable unused servers with <code>/mcp</code>. Prefer CLI tools (<code>gh</code>, <code>aws</code>) over MCP equivalents where available.</p>
          </div>

          <div className="cc-item">
            <div className="eyebrow">CLAUDE.md</div>
            <h4>Repeated re-explanation</h4>
            <p>Move stable context (commands, conventions, forbidden dirs) to CLAUDE.md. Keep it lean — it loads on every turn.</p>
          </div>

          <div className="cc-item">
            <div className="eyebrow">File reads</div>
            <h4>Reads eating context</h4>
            <p>Scope reads narrowly. Add irrelevant directories to <code>.claudeignore</code>. Filter test output to failures only.</p>
          </div>

        </div>
      </section>

      <QuizTiered tiers={[
        {
          label: "Beginner",
          question: "What does /compact do in a Claude Code session?",
          options: [
            "Deletes all files Claude has read to free up disk space",
            "Summarises conversation history into a condensed snapshot, shrinking the context Claude re-reads on future turns",
            "Switches to a smaller, cheaper model for the rest of the session",
            "Clears the terminal output without affecting the conversation",
          ],
          correct: 1,
          explain: "/compact condenses your conversation history into a summary block. Claude continues from that summary, so every subsequent turn re-reads far less — cutting cost and latency without losing the thread of what you were working on.",
        },
        {
          label: "Intermediate",
          question: "Why does message 50 in a session cost more tokens to process than message 5?",
          options: [
            "Claude uses a larger model automatically as sessions get longer",
            "Token prices increase with session length on the Anthropic API",
            "Claude re-reads the entire conversation — all 49 prior turns — before generating each new reply",
            "The system prompt grows larger as Claude learns your preferences",
          ],
          correct: 2,
          explain: "Claude doesn't maintain state between turns — it re-processes the full context from the top every time. Message 50 is expensive because it includes 49 prior messages, all tool outputs, and every file that was read during the session.",
        },
        {
          label: "Advanced",
          question: "You need to explore an unfamiliar 200-file codebase before writing any code. Which approach best preserves your main session's context budget?",
          options: [
            "Read each file one at a time in the main session, using /compact between each read",
            "Ask Claude to summarise the repo structure from git log and file names only",
            "Delegate exploration to a subagent — it reads files in a separate context window and returns a summary",
            "Use /clear before exploring so the reads don't accumulate with earlier context",
          ],
          correct: 2,
          explain: "Subagents are context firewalls. The subagent pays the file-read cost in its own window; your main session only receives the summary. /compact helps but doesn't prevent the initial file-read bloat. /clear throws away useful earlier context unnecessarily.",
        },
      ]} />

    </div>
  );
}

Object.assign(window, { Lesson14, Lesson15 });
