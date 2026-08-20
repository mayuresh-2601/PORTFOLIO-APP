# FIXES.md — Full Audit & Fix Log

Everything below was actually found by inspecting your real code and actually verified
(hadolint run, YAML parsed, `node --check` on every server file, real `npm run build`,
real server boot test) — not guessed or assumed.

---

## 🔴 Critical — found this round (round 4)

### 7. `schema.sql` created tables in the wrong database
**What was wrong:** the init script explicitly ran:
```sql
CREATE DATABASE IF NOT EXISTS portfolio_db ...
USE portfolio_db;
```
before creating any tables. But nothing else in the project uses a database literally
named `portfolio_db` — the actual database name is whatever `DB_NAME` is set to (e.g.
`portfolio_ci` in CI, or your real TiDB Cloud database name in production). Docker's
MySQL entrypoint already creates and switches into the `MYSQL_DATABASE`-named database
automatically before running any `/docker-entrypoint-initdb.d/` script — this file was
overriding that with its own, different, hardcoded database. Result: all 5 tables got
created in an empty, unused `portfolio_db` database, while the actual `portfolio_ci`
database the app queries stayed completely empty — exactly matching your log's
`Table 'portfolio_ci.projects' doesn't exist`.

**Fix:** removed the `CREATE DATABASE` + `USE` lines entirely. The script now creates
tables directly in whatever database MySQL's entrypoint already selected — correct in
every environment (CI, local Docker, or if ever pointed at a fresh instance) without any
hardcoded name.

*(Your live production TiDB Cloud database already has its own real tables and data,
provisioned separately/manually before this session — this bug specifically affects the
CI docker-compose smoke test's fresh, ephemeral database, not your live site.)*

---

### 8. CI's dummy `ADMIN_PASSWORD_HASH` broke Docker Compose's env-file interpolation
**What was wrong:** the placeholder value mimicked real bcrypt hash formatting
(`$2a$10$...`), which is exactly the syntax Docker Compose's `.env`-parsing engine reads
as variable-substitution syntax (`$VARNAME`). Your log's odd warnings —
`The "CIu8lY1uRz...XXXX" variable is not set. Defaulting to a blank string` — are Compose
literally trying to substitute a variable named after the tail end of that fake hash,
and silently blanking it out.

**Fix:** replaced it with a plain placeholder string containing no `$` characters at
all — the CI smoke test never actually validates this hash against a real login, so it
doesn't need to look like a real bcrypt hash, just be present and non-empty.

**Verified:** re-extracted the exact generated bash script from the YAML and re-ran it —
confirmed the value written to `server/.env` now contains zero `$` characters.

---

## 🔴 Critical — found this round (round 3)

### 6. `gemini-2.5-flash` was also closed off — Google retired two model lines in one week
**What happened:** after fixing round 2 (retiring `gemini-1.5-flash` → `gemini-2.5-flash`)
and confirming via your Render logs that the fix *did* deploy correctly, Google closed
the entire **2.5 line** to new API keys/projects too — a separate, more recent change.
The error was specific: `"This model models/gemini-2.5-flash is no longer available to
new users."`

**Fix:** switched to `gemini-3.5-flash-lite` — confirmed via multiple current sources
(Google's own docs, third-party API proxies, dev guides, all dated within the last few
weeks) to be a currently GA, low-cost model accessible to new projects.

**Two related fixes bundled in, found while researching this:**
- Removed the `temperature` sampling parameter — deprecated on all Gemini 3.x models as
  of this generation
- Fixed response parsing: Gemini 3.x models can attach a `thoughtSignature`-only part
  with no `text` field *before* the actual answer in the `parts` array. The old code read
  `parts[0].text` only, which could silently return `undefined` even on a fully successful
  API call. Now joins every part that has a `text` field, matching Google's own documented
  parsing pattern for 3.x responses.

**Verified:** `node --check` passes. **Not verified:** an actual live call with your real
key (still don't have it) — but this is now the third round tracing the exact real error
message from your Render logs each time, so confidence is high. If Google closes this
model too, the fix pattern is now well-established: check
https://ai.google.dev/gemini-api/docs/models, swap the `GEMINI_MODEL` string, redeploy.

---

## 🔴 Critical — found this round (round 2)

### 5. Gemini model `gemini-1.5-flash` was retired by Google
**What was wrong:** `aiService.js` called `gemini-1.5-flash`, which Google fully retired
sometime after this project's AI feature was first built. The API returned:
```
404: models/gemini-1.5-flash is not found for API version v1beta,
or is not supported for generateContent.
```

**Fix:** switched to `gemini-2.5-flash` — confirmed via Google's current official docs
and code samples (checked live, not from training data, since Gemini's model lineup has
moved through several generations recently) to be a currently supported model on the
same `v1beta/generateContent` endpoint already in use.

**Note:** I don't have your real `GEMINI_API_KEY`, so I could not make a live end-to-end
call to 100% confirm the response — only confirm the model name is current per Google's
own documentation. Test this after redeploying; if Google retires this model too in the
future, check https://ai.google.dev/gemini-api/docs/models for the current list.

---

## 🔴 Critical — found this round (round 1)

### 1. `server/Dockerfile` was not a Dockerfile
**What was wrong:** the file's entire contents had been overwritten with a copy of
`docker-compose.yml` (pure YAML, no `FROM` instruction). This alone would break the
"Lint Dockerfiles" job and any `docker build` of the backend image completely.

**Fix:** restored the correct Dockerfile content (multi-stage-free Node 20 Alpine build,
non-root user, `HEALTHCHECK` against `/api/health`).

**Verified:** ran the real `hadolint` binary against it → **0 warnings, 0 errors.**

---

### 2. Strict SSL was blocking every CI database connection
**What was wrong:** `server/Dockerfile` hardcodes `ENV NODE_ENV=production`. Your DB
config (`config/db.js`) enabled strict TLS (`rejectUnauthorized: true`) whenever
`NODE_ENV === "production"`. That's correct for real TiDB Cloud, but in CI the "database"
is a plain local MySQL container with a self-signed cert — which **fails strict TLS
validation every time.** This is almost certainly the real reason
`portfolio_server_container` was going straight to `Error` status in your earlier CI run,
more fundamentally than the healthcheck-target mismatch fixed previously.

**Fix:**
- `config/db.js` now reads an explicit `DB_SSL` variable. If unset, it falls back to the
  old `NODE_ENV`-based behavior — **your real Render/TiDB Cloud deployment is unaffected.**
- The CI workflow (`docker-ci.yml`) now sets `DB_SSL=false` in the generated
  `server/.env`, so the CI smoke test connects to its local MySQL container without TLS.

**Verified:** re-extracted the exact generated bash script from the YAML and ran it —
confirmed `DB_SSL=false` appears correctly in the generated file. Re-ran `node --check`
on `db.js` — no syntax errors introduced.

---

### 3. Live site: "Route not found: POST /api/ai/explain-skill"
**This is not a code bug in this zip.** `server.js` in your uploaded project correctly
imports and mounts `aiRoutes` and `systemRoutes` at `/api/ai` and `/api/system`. The
exact error message in your screenshot is generated by your own `notFound` middleware,
which only fires when a route genuinely doesn't exist **on whichever server actually
received the request.**

**What this means:** your Render deployment is running an older build of `server.js` —
one from before the AI/System features were added — and hasn't picked up the latest
code yet.

**Fix (deployment step, not a code change):**
1. Push this updated code to your `main` branch
2. On Render, either wait for auto-deploy to trigger, or go to your service → **Manual
   Deploy** → **Deploy latest commit**
3. Watch the Render logs for `🚀 Server running on http://localhost:5000`
4. Confirm `GEMINI_API_KEY` is set in Render's environment variables (separate from your
   local `.env`, which is never pushed to git)
5. Re-test the live site — the skill/certificate AI-explain buttons should work once
   Render is serving current code

---

## 🟡 Cleanup — found this round

### 4. Duplicate `CLIENT_URL` in `server/.env`
Two `CLIENT_URL=` lines existed in your local `server/.env` (one `localhost:5173`, one
the Vercel URL). Since Node's `dotenv` uses the **first** match, the Vercel line was
silently ignored locally. Removed the duplicate, kept the local dev value active, and
added a comment noting the production value belongs in Render's dashboard instead.

*(This didn't necessarily affect your live Render deployment, since Render's actual env
vars are configured separately in its dashboard, not from this file — but it was
confusing and worth fixing for local dev clarity.)*

---

## ✅ Re-confirmed still correct from earlier fixes

These were fixed in earlier turns and verified again this round to make sure nothing
regressed:

| Item | Status |
|---|---|
| `client/Dockerfile` — consolidated `RUN` + `hadolint ignore` for `apk add` | ✅ Still passes hadolint clean |
| `docker-compose.yml` — obsolete `version:` key removed | ✅ Confirmed absent |
| `docker-compose.yml` — server healthcheck targets `/api/health` (not DB-dependent) | ✅ Confirmed, `start_period: 20s` present |
| `docker-ci.yml` — generates `server/.env` + root `.env` before `docker compose config` | ✅ Confirmed, script re-extracted and re-run |
| AI routes (`/api/ai/*`) and System routes (`/api/system`) mounted in `server.js` | ✅ Confirmed |
| `client/src/api/axios.js` — correctly builds `${VITE_API_BASE_URL}/api` | ✅ Confirmed, matches server route mounts exactly |
| `vercel.json` — SPA rewrite rule present | ✅ Confirmed |
| `.gitignore` (root + client) — `.env` properly excluded everywhere | ✅ Confirmed |
| `nginx.conf` — reverse proxy to `server:5000` correct for docker-compose network | ✅ Confirmed |

---

## Full verification checklist run this round

- [x] `hadolint` (real binary, v2.12.0) against both Dockerfiles → 0 issues
- [x] `node --check` against every `.js` file in `server/` → 0 syntax errors
- [x] `docker-compose.yml` parsed with PyYAML → valid, 3 services, no `version` key
- [x] `docker-ci.yml` parsed with PyYAML → valid, heredoc script extracted and actually
      executed to confirm real output (no indentation bugs, `DB_SSL=false` present)
- [x] `client/`: clean `npm install` + `npm run build` → succeeded, 0 errors
- [x] `server/`: clean `npm install` + real `node server.js` boot → all modules loaded,
      no crash (hung on DB connection as expected — this sandbox has no network path to
      your real TiDB Cloud instance)

## What I could NOT verify in this sandbox

- Full `docker compose up --build` end-to-end (no Docker daemon available here)
- A real connection to your TiDB Cloud database
- The actual Gemini API call succeeding with your real key
- Your live Render deployment picking up this code (that step is on you — see item #3)

After you push and redeploy, re-run the GitHub Actions workflow and check the live
`/system` and `/skills` pages. If anything still fails, send me the new log/screenshot —
same as before, I'll trace the exact cause rather than guessing.
