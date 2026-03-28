# Jarvis Build Progress

## Current Phase
Jarvis architecture restructure complete. Slack skill operational.

## Last Session (2026-03-28)
- Restructured repo from flat CHITRA layout to Jarvis agent/skill hierarchy
- Renamed workspace: Tax Strategies -> Jarvis
- Renamed GitHub repo: chitragupta -> jarvis
- Moved 29 git-tracked files to new locations (core/, skills/, agents/chitra/)
- Moved gitignored files (knowledge-base JSON, scripts/personal/, 2025/ data)
- Updated imports in all 8 scripts (sys.path bootstrap + core.config_loader)
- Created Jarvis coordinator rule (.cursor/rules/jarvis.md)
- Created Slack skill (skills/slack/adapter.py) with send_message, read_replies, request_otp
- Stored Slack bot token in macOS Keychain (service: jarvis)
- Added Slack MCP to user-level ~/.cursor/mcp.json
- Tested Slack connection: DM sent successfully to workspace owner
- Updated all configs (config.template.yaml, config.yaml, .gitignore, .cursor/mcp.json)
- Fixed Playwright MCP config (`--profile` -> `--user-data-dir`, explicit nvm PATH)
- Moved Playwright MCP to user-level `~/.cursor/mcp.json`
- Installed Chromium for Playwright MCP
- Added stronger session continuity rules so new chats resume from files, not chat history
- Verified direct Google Drive API access via local config/token refresh path
- Added local Drive parity tooling: reusable inventory command + shadow diff script
- Added direct Google Drive folder-creation helper for shadow-folder setup
- Cleaned up document-registry.json: normalized all drivePaths to numbered convention, deduplicated IDs (30-33 → 34-37), removed status suffixes from folder names, removed incorrect Expenses Partnership folder, updated emptyFolders
- Queried Google Sheet — confirms 31 documents tracked, all match registry
- Upgraded chitra-playbook.md: prior-year return is now the primary bootstrap input (not manual registry maintenance)
- Added "Handling User Design Feedback" protocol to jarvis.md
- Rewrote create_shadow_folders.py to be registry-driven (no hardcoded folder names) — works for any CHITRA user
- Refreshed benchmark inventory at `extracted/drive-2025-inventory.json`
- Improved derive_registry_from_return.py fuzzy matching (6.5% → 48.4% match rate)
  - Added issuer normalization (strip EINs, account numbers, legal suffixes)
  - Added docType aliasing (Consolidated 1099 → 1099, Form 1098 → 1098, etc.)
  - Generic issuer matching (Property Manager, County Tax Assessor → matches actual names)
- Created return-profile.schema.md — canonical JSON schema for tax return profiles
  - CHITRA uses this schema when parsing any user's tax return text
  - Covers all standard forms: 1040, Schedules A-E, 8889, 8949, 8582, K-1s
- Created generate_questionnaire.py — produces 35 friendly layperson questions
  - 19 Confirmation questions (did prior-year items change?)
  - 16 Discovery questions (life events the return can't predict)
  - Categories: Jobs, Investments, Rental, Partnerships, Business, Charitable, Health, Home, Life Events, Retirement, Education, Tax Payments
  - Each question explains WHY it's asked and WHAT to do if the answer is yes/no
- Created onboard_from_return.py — full new-user pipeline
  - Input: PDF (local or Drive ID) or existing profile JSON
  - Step 1: Extract text via pdfplumber
  - Step 2: Print parsing prompt + schema for CHITRA to produce profile JSON
  - Step 3: Derive registry + questionnaire from profile
  - Works for ANY user — no hardcoded names or entities
- Current match analysis: 15/31 registry docs derived from prior-year return alone (48.4%)
  - Remaining 16 are genuinely new-year events (new home, new CPA, DONUM note, employer payroll docs, retirement accounts, homestead exemption, etc.)
  - These are exactly the questions the questionnaire asks

### Prior Sessions (2026-03-27)
- Completed CHITRA v1: Phases A-D (git init, knowledge capture, browser automation, README)
- CPA email drafting and Homebase document handling
- Uploaded Palmetto employer tax docs (W-2, W-3, Form 941, Form 940) to Drive

## What's Next (v2 backlog)
1. ~~Add channels:join scope~~ DONE — bot invited to #all-jarvis manually
2. Install Playwright MCP and test with Fort Bend County (public, no login) — IN PROGRESS
   - Fixed: `--profile` → `--user-data-dir`, added env PATH for nvm, moved to user-level MCP config
   - Chromium browser binary installed
   - Remaining issue: Playwright MCP descriptors appear on disk, but runtime MCP tool list has not exposed `user-playwright` yet
3. Populate credentials/portals.yaml and Keychain entries for each portal
4. Test full OTP flow: Playwright login -> Slack OTP request -> continue
5. Fix validation gaps (docType normalization, Sheet tab names, estimates field names)
6. **Shadow folder validation (BLIND PARITY mode)**: Build `Taxes/2025-test` entirely from CHITRA's knowledge, automation, and user conversations — never look inside real `Taxes/2025`
   - Real folder is sealed; only opened for a final scored comparison
   - Derive folder structure from `drive-folder-convention.md` + `document-registry.json`
   - Derive filenames from naming conventions + document metadata
   - Ask user for any missing input data, configs, or credentials
   - Done: benchmark inventory captured (sealed), diff tooling ready, folder-creation helper ready
   - Next: create `2025-test` root folder, then derive and build subfolder structure from knowledge base
7. **New-user onboarding pipeline**: PDF → extracted text → CHITRA parsing → profile JSON → registry + questionnaire
   - Schema: `agents/chitra/knowledge-base/schema/return-profile.schema.md`
   - Questionnaire: `agents/chitra/scripts/generate_questionnaire.py`
   - Pipeline: `agents/chitra/scripts/onboard_from_return.py`
   - Tested: 35 questions generated, 22 docs derived, 8 folder categories

## North Star Vision
CHITRA's goal is fully autonomous tax document collection for ANY user:
1. User hands CHITRA their prior-year tax return PDF
2. CHITRA parses it into a structured profile (CHITRA-the-AI is the parser)
3. CHITRA derives 60-70% of the expected documents from the return
4. CHITRA asks ~35 friendly questions to fill the remaining 30-40% (life events, changes)
5. From answers, CHITRA autonomously figures out WHERE to get each document:
   - County property tax sites (derived from address → county lookup)
   - Broker portals (credentials in Keychain)
   - Employer HR portals
   - Insurance company sites
6. CHITRA navigates those sites (Playwright), downloads documents, uploads to Drive
7. User only provides: the PDF, answers to plain-English questions, and occasional permissions
8. End result: 100% populated Drive folder structure matching what a human would build

Current state: steps 1-4 are built and tested. Steps 5-8 require Playwright MCP + portal automation.

## Live Questionnaire Exercise Results (2026-03-28)
Simulated new-user onboarding using only `profile-2024.json` + user Q&A (no peeking at real registry).

**Starting point:** 22 docs derived from 2024 return alone (48.4% of real 31-doc registry)
**After 6 questions + answers:** 34 docs identified (~97% coverage of real registry)
  - 13 from return alone (no questions needed)
  - 10 from user answers (6 questions total)
  - 11 CHITRA would fetch autonomously via Playwright (zero user questions)

**Key learnings persisted to chitra-playbook.md:**
1. Check-yourself-first principle: never ask what you can check via portal/bank/public site
2. Question triage table: self-check vs bank-derived vs address-derived vs must-ask vs user-provides
3. Smart follow-ups: address → county → portal URL → homestead (auto-derive chain)
4. Employer HR portals = user provides (too much SSO friction)
5. Match user's tone, use names not "taxpayer/spouse"
6. Gmail is a document source — CPA correspondence + charitable docs (priority skill)
7. Bank transactions reveal insurance providers and property managers
8. Status reports > more questions ("Downloaded X, Y. Z isn't available yet — want me to email?")

**Portal registry created:** `credentials/portals.yaml.template` with 20+ portals mapped:
  - 8 Playwright-automatable (brokers, banks, county sites, insurance, payroll)
  - 4 Playwright+OTP (brokers with MFA)
  - 2 user-provides (employer HR with SSO)
  - 3 email-based (CPA, charitable, K-1 notifications)
  - Gmail skill identified as high priority (came up 2x in exercise)

## Immediate Next Steps (prioritized by impact)
1. **Populate portals.yaml** from template + store credentials in Keychain for each portal
2. **Get Playwright MCP working reliably** — this unlocks autonomous document collection
3. **Test first portal automation**: Fort Bend County property tax (public, no login) as proof of concept
4. **Build Gmail skill** — high priority, came up twice in questionnaire exercise (DONUM docs, CPA correspondence)
5. **Wire answer-processing logic** — take questionnaire answers → auto-update derived registry → auto-derive portal list
6. **Score against real registry** — run final diff of exercise-built registry vs actual document-registry.json

## Blockers
- Playwright MCP is configured and Chromium is installed, but runtime MCP tool availability is inconsistent (`user-playwright` appears on disk but not in callable server list)
- Portal credentials not yet populated — template created, need user to provide creds for Keychain storage
- Google Drive MCP read-only auth path is failing with a Google 403, so Drive work is currently using the repo's direct Google API helpers instead

## Completed Steps
- [x] CHITRA v1 — Phases A-D (commits 7cea51d → fa1e88c)
- [x] Jarvis architecture restructure
  - Workspace renamed: Tax Strategies -> Jarvis
  - GitHub repo renamed: chitragupta -> jarvis
  - Directory hierarchy: core/, skills/, agents/chitra/
  - 29 files moved via git mv
  - All imports updated
  - jarvis.md coordinator rule created
  - Slack skill created and tested
  - Config templates updated with slack section

## Decisions Log
- 2026-03-27: Public repo (open-source the framework)
- 2026-03-27: Passwords via macOS Keychain, never plaintext
- 2026-03-27: Playwright MCP for browser automation, Slack MCP for OTP
- 2026-03-27: No PII in any git commit
- 2026-03-28: Restructure to Jarvis coordinator + agent/skill hierarchy
- 2026-03-28: jarvis/ folder conflict resolved by renaming old to jarvis-legacy/
- 2026-03-28: Slack MCP in user-level ~/.cursor/mcp.json (not workspace — secrets)
- 2026-03-28: Portal playbooks under agents/chitra/ (domain knowledge, not generic skill)
- 2026-03-28: sys.path bootstrapping for imports (pyproject.toml deferred to v3)
- 2026-03-28: Shadow-folder validation is a BLIND test — never look inside real `Taxes/2025`, build everything from CHITRA's own knowledge + user input
- 2026-03-28: If mirror validation hits unresolved discrepancies, pause and ask the user instead of guessing
- 2026-03-28: Mirror-validation diffs should continuously drive Jarvis's next-step prioritization
- 2026-03-28: CHITRA's primary input for bootstrapping a tax year should be the prior-year federal/state returns — parse every schedule/form/issuer, derive the document checklist and folder structure from it, then pull docs autonomously using saved credentials. The registry is derived output, not manual input.
- 2026-03-28: Expenses Partnership folder was a misread of 2024 return — removed
- 2026-03-28: Auburn CA is a passive RE investment waiting on K-1 (reference 2024 return for context)
- 2026-03-28: No estimated tax payment docs for 2025; filing extensions in 2026
- 2026-03-28: Questionnaire exercise proved ~97% coverage achievable with 6 user questions + autonomous portal checks
- 2026-03-28: Check-yourself-first principle — CHITRA should attempt portal/site checks before asking the user
- 2026-03-28: Employer HR portals (DoorDash, Texas Children's) are user-provides — too much SSO friction to automate
- 2026-03-28: Gmail skill is high priority — CPA correspondence and charitable docs both live in email
- 2026-03-28: Portal credential registry uses Keychain for secrets, portals.yaml.template for portal metadata (URLs, auth methods, doc types)

## Git State
- Branch: `main`
- Remote: `git@github.com-personal:aditya2kx/jarvis.git`
- Public URL: https://github.com/aditya2kx/jarvis
- Local config: user.email=aditya.2ky@gmail.com, user.name=adi2ky
