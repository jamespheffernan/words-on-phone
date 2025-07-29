# Scratchpad

This scratchpad tracks the overarching vision, active implementation plans, and lessons learned while building **Words on Phone**.

## Active Implementation Plans

- [phrasemachine-v2-description-only-edition](implementation-plan/phrasemachine-v2-description-only-edition.md) - 🚧 **IN PROGRESS** - PhraseMachine v2 - "Description-Only Edition"
  - 🎯 **GOAL**: Build automated service that generates & vets 2-4-word phrases optimized for verbal description in 60-second party-game rounds
  - 📊 **SCOPE**: 8-week implementation plan with 25 tasks across 8 phases
  - 🔧 **INNOVATION**: Data-driven quality assessment using Wikidata, Google Books N-gram, concreteness ratings, and cultural validation
  - 🎯 **SUCCESS METRICS**: <300ms scoring latency, >80% "easy to describe" rating, <5% false-positive rate, <20% manual review queue
  - ✅ **PHASE 1 COMPLETE**: Foundation & Data Infrastructure - All 4 core data processing pipelines operational
  - 🔥 **DISTINCTIVENESS**: Wikidata scoring (25/20/0 points) with WikidataProcessor, API server, CLI tools, O(1) Redis lookup
  - 📊 **PMI SCORING**: Google Books N-gram pipeline (15/10/5/0 points) with NgramProcessor, frequency weighting, mathematical accuracy
  - 🧠 **CONCRETENESS**: Brysbaert norms integration (15/8/0 points) with ConcretenessProcessor, lemmatization, stemming support
  - 📋 **STATUS**: Week 1 - 100% complete (Phase 1 finished ahead of schedule), all data infrastructure operational
  - 🎯 **CURRENT FOCUS**: Task 9 - Category Boost & Cultural Validation (Phase 3: Legacy Integration & Decision Engine continues)
- [posthog-dashboard-creation](implementation-plan/posthog-dashboard-creation.md) - 🎯 **60% COMPLETE** - PostHog Dashboard Creation
  - 🎯 **GOAL**: Programmatically create PostHog dashboards using API endpoints
  - ✅ **7/10 TASKS COMPLETE** (70%): Feature branch, API research, script enhancement, core insights creation, main dashboard creation, advanced dashboards, dashboard optimization
  - 🎉 **MAJOR ACHIEVEMENT**: 5 comprehensive dashboards created with 26+ insights operational in production PostHog!
  - **DASHBOARDS CREATED**: User Engagement v3, Game Performance v3, Technical Performance v3, Privacy & Settings v3, Custom Category v3 (optimized versions)
  - **EFFICIENCY WIN**: Task 6 requirements already exceeded in Task 5 - comprehensive approach more efficient than incremental
  - **STATUS**: Dashboard optimization complete with systematic audit fixes, ready for dashboard templates (Task 7)
  - **KEY INSIGHTS**: Enhanced script with retry logic and rate limiting essential for API reliability
- [phrase-database-generation](implementation-plan/phrase-database-generation.md) - 🎉 **MAJOR MILESTONE ACHIEVED** - Phrase Database Generation - Rebuild to 1000+ High-Quality Phrases
  - 🎯 **GOAL**: Scale from 173 to 1000+ high-quality phrases using existing quality infrastructure
  - ✅ **4/8 TASKS COMPLETE** (50%): Feature branch created, implementation plan improved, database tool integration, **CORE CATEGORIES COMPLETE**
  - 🎉 **MAJOR ACHIEVEMENT**: 980 total phrases (98% of 1000+ target achieved!)
  - **CORE CATEGORIES COMPLETE**: Movies & TV (76), Food & Drink (71), Music & Artists (71), Sports & Athletes (52) - all well-represented
  - **QUALITY EXCELLENCE**: 80+ average scores, comprehensive duplicate prevention, balanced distribution across 20 categories
  - **INFRASTRUCTURE PROVEN**: End-to-end generation, scoring, and storage systems working at scale
  - 📋 **DECISION POINT**: With 980 phrases achieved, focus could shift to production integration or continue with secondary categories
  - **REVISED APPROACH**: Leverage existing phrase database tool + production APIs instead of building new infrastructure
  - Key insight: We have 3 separate systems that need coordination (database tool, production service, batch generator)
  - 📋 **NEXT TASKS**: Design balanced category distribution, setup database tool integration, begin core category generation
- [phrase-quality-upgrade](implementation-plan/phrase-quality-upgrade.md) - ✅ **COMPLETED** - Phrase Generation Quality Upgrade
  - ✅ **8/8 TASKS COMPLETE** (100%): Enhanced prompts, scoring system, Wikipedia/Reddit validation, phrase generation service integration, phrase review interface, testing, documentation/rollout
  - Comprehensive plan to fix low-quality phrase generation through better prompts, scoring system, and validation
  - 🎯 **STATUS**: All tasks completed successfully with comprehensive phrase review interface and quality control systems
- [gemini-model-upgrade](implementation-plan/gemini-model-upgrade.md) - ✅ **COMPLETED** - Gemini Model Version Upgrade
  - ✅ **UPGRADE SUCCESS**: Model version upgrade from gemini-1.5-flash to gemini-2.5-flash completed successfully
  - Enhanced reasoning capabilities with "thinking budget" control, 22% greater computational efficiency
  - Backward compatible with existing API structure, no breaking changes required
  - All builds pass, 131/135 tests pass (4 pre-existing failures unrelated to upgrade)
- [version-number-display](implementation-plan/version-number-display.md) - ✅ **COMPLETED** - Version Number Display with Auto-Update on Commit
  - ✅ **ALL TASKS COMPLETE** (6/6): Git-based version generation, UI component, build integration, comprehensive testing
  - Version format: `v{package.version}-{git-hash}` (e.g., `v0.0.0-105fb2da`)
  - 🎯 **STATUS**: Feature complete - ready for merge and deployment
- [cors-fix-gemini-function](implementation-plan/cors-fix-gemini-function.md) - ⚠️ **NEEDS REVISION** - CORS Fix for Gemini Netlify Function (Production 404 Error Detected)
- [netlify-function-deployment-fix](implementation-plan/netlify-function-deployment-fix.md) - ✅ **COMPLETED** - Netlify Function Deployment Fix - 404 Error Resolution  
- [visual-background-warning](implementation-plan/visual-background-warning.md) - **✅ COMPLETE** - Visual Background Warning System (Progressive Red Background)
- [openai-phrasemachine-migration](implementation-plan/openai-phrasemachine-migration.md) - ✅ **COMPLETED** - OpenAI PhraseMachine Migration (Service Layer Fixed - Now Uses Dynamic AI Detection)
- [phrasemachine-prompt-upgrade](implementation-plan/phrasemachine-prompt-upgrade.md) - ✅ **COMPLETED** - PhraseMachine Prompt Format Upgrade
- [multi-batch-phrase-generation](implementation-plan/multi-batch-phrase-generation.md) - ✅ **COMPLETED** - Multi-Batch Phrase Generation (3×15 → 45 Phrases)
- [mobile-gameplay-screen-ux](implementation-plan/mobile-gameplay-screen-ux.md) - ✅ **COMPLETED** - Mobile Gameplay Screen UX Optimization (Full Viewport, No Scroll)
- [header-overlap-fix](implementation-plan/header-overlap-fix.md) - ✅ **COMPLETED** - Header Overlap Fix - Scoreboard and Skip Counter
- [team-based-scoring-system](implementation-plan/team-based-scoring-system.md) - ✅ **COMPLETE + FIXES APPLIED!**
  - All 11 tasks completed successfully
  - Feature branch ready for PR: `feature/team-based-scoring`
  - 18 files changed, 1560 insertions(+), 586 deletions(-)
  - ✅ **USER FEEDBACK FIXES COMPLETED**: All critical bugs resolved:
    - ✅ Fixed double-counting bug (teams now get exactly 1 point per win)
    - ✅ Implemented dynamic team rotation (device holder updates after each correct answer)
    - ✅ Added next round team pre-selection with smart defaults
    - ✅ Replaced confusing dice icon with obscured countdown display
    - ✅ Applied glassmorphism styling to TeamSetup for consistency
  - 🔧 **TOTAL IMPACT**: 19 files changed, 1266 insertions(+), 78 deletions(-)
  - 🎯 **STATUS**: Ready for user testing and validation
- [rules-consistency-check](implementation-plan/rules-consistency-check.md) - 📋 **READY** - Ensure Game Consistency with Official Rules
- [category-selection-redesign](implementation-plan/category-selection-redesign.md) - ✅ **COMPLETE** - Category Selection UX Redesign (Multi-select, User Categories)
- [phrase-database-upgrade](implementation-plan/phrase-database-upgrade.md) - 📋 **READY** - Enhanced Phrase Database with Monthly Updates
- [sound-and-haptics](implementation-plan/sound-and-haptics.md) - ✅ **100% COMPLETE** - Sound Effects and Haptic Feedback (READY FOR MERGE TO MAIN)
- [app-icon-implementation](implementation-plan/app-icon-implementation.md) - 📋 **READY** - iOS App Icon Implementation
- [countdown-ripple-redesign](implementation-plan/countdown-ripple-redesign.md) - 📝 **PLANNED** - Countdown Ripple Redesign (Hidden Timer Indicator)
- [phrase-review-interface](implementation-plan/phrase-review-interface.md) - 📝 **PLANNED** - Keyboard-Driven Phrase Review Tool
- [phrase-database-builder-tool](implementation-plan/phrase-database-builder-tool.md) - ✅ **COMPLETED** ✅
  - **All 10 tasks completed successfully**
  - 161 tests passing with 88%+ coverage
  - Comprehensive CLI with 15+ commands
  - Complete documentation and API examples
  - Production-ready phrase database system
  - Ready for merge to main branch
- [phrase-pool-expansion](implementation-plan/phrase-pool-expansion.md) - 🚀 **DEPLOYED TO PRODUCTION** - Phrase Pool Expansion to 5,000+ Phrases (OpenAI default)
  - 🎯 **GOAL**: Scale from current ~78 phrases to 5,000+ high-quality phrases using OpenAI-first infrastructure
  - ✅ **6/8 TASKS COMPLETE** (75%): Project setup, architecture consolidation, throughput automation, review workflow, Phase I expansion, and continuous generation pipeline complete
  - 🚀 **PRODUCTION DEPLOYMENT**: Feature branch merged to main - all infrastructure live with 56 files changed (20,380 additions)
  - **MAJOR MILESTONE**: Phase I expansion achieved 658% growth from 78 → 591 phrases (7.6x increase!)
  - **AUTOMATION INFRASTRUCTURE**: Nightly generation pipeline with GitHub Actions deployed and operational
  - **INFRASTRUCTURE VALIDATED**: OpenAI primary service performing excellently (88-89% acceptance rates, 13s per batch)
  - **ALL 12 CATEGORIES POPULATED**: Movies & TV (66), Entertainment (63), Music (61), Everything+ (56), Places (52), Nature (48), Tech (48), Sports (46), History (43), Everything (38), Food (36), Famous People (34)
  - **EXPORT INFRASTRUCTURE FIXED**: GameExporter bugs resolved, multiple export formats generated for game integration
  - **CONTINUOUS PIPELINE DEPLOYED**: Automated nightly generation with GitHub Actions, PR automation, quality monitoring, failure alerting
  - **QUALITY MAINTAINED**: 100% of phrases score 70+ (589 phrases), perfect duplicate detection, zero inappropriate content
  - 📋 **NEXT TASKS**: Phase II expansion to 5,000+ phrases using automated pipeline, documentation and handoff
- [category-ui-redesign](implementation-plan/category-ui-redesign.md) - ✅ **COMPLETE** - Category Selection UI Redesign for Expanded Categories
  - ✅ **8/8 TASKS COMPLETE** (100% - PROJECT DELIVERED): All core development, testing, and production deployment complete
  - 🎯 **DECISION MADE**: Enhancement path chosen (Option A) - enhancing existing CategorySelector vs full replacement
  - 📊 **FOUNDATION BUILT**: Category popularity tracking with IndexedDB storage, weighted scoring, React hook integration
  - **QUICK PLAY WIDGET DEPLOYED**: Collapsible panel with Last Played, Surprise Me, Top 6 categories achieving <3 taps to start game
  - **ACCORDION GROUPING DEPLOYED**: 5 logical groups (Entertainment, Daily Life, World & Knowledge, Activities & Sports, Creative & Misc) with persistent expand/collapse state
  - **UI POLISH & ICONS COMPLETED**: 20+ category icons, 44px+ mobile touch targets, enhanced glassmorphism styling, production-ready visual design
  - **SURPRISE ME LOGIC COMPLETED**: Random category selection with equal probability, auto-game-start integration, seamless game flow
  - **ANALYTICS & A/B FOUNDATION COMPLETED**: Category popularity tracking system, real-time scoring, data-driven recommendations
  - **TESTING & ACCESSIBILITY COMPLETED**: Enhanced test infrastructure with robust IndexedDB mocking, 29 passing unit tests, comprehensive Cypress E2E tests (19 test cases), data-testid attributes for accessibility
  - **PRODUCTION DEPLOYMENT COMPLETED**: Feature branch merged to main, 110 objects pushed to GitHub (533.89 KiB), Netlify auto-deployment triggered
  - **FIRST-TIME USER ENHANCEMENT**: Added "Get Started" button for users with no play history, improving onboarding with welcoming UI and messaging
  - 🎯 **PROJECT STATUS**: ✅ **COMPLETE** - Enhanced category selection UI deployed to production via Netlify
  - 🚀 **USER IMPACT**: Production-ready Quick Play widget transforming category selection from 10+ taps to 1-2 taps
- [xxx-category-generation](implementation-plan/xxx-category-generation.md) - 🆕 **PLANNED** - XXX (Adult) Category Phrase Generation
  - 🎯 **GOAL**: Add a new "XXX" (adult/illicit) category with 100+ fun, risqué, and sexy phrases for adult party play
  - **STATUS**: Planning complete, ready for Executor to begin implementation

- [posthog-instrumentation](implementation-plan/posthog-instrumentation.md) - ✅ **COMPLETED** - PostHog Analytics Fully Restored & Verified
  - 🎯 **GOAL**: Fix issue where analytics initializes but events don't reach PostHog ✅
  - 🛠️ **STATUS**: All tasks completed successfully (Tasks 10-21)
  - 🔍 **ROOT CAUSE**: PostHog SDK loaded but failed to attach to window.posthog object
  - 🚀 **SOLUTION**: Manual window attachment with fallback - analytics now fully operational
  - ✅ **VERIFIED**: Events confirmed appearing in PostHog Live Events dashboard
  - ✅ **VERIFIED**: Network requests successfully sending to PostHog API (200 OK responses)

## Current Bug Fix / Executor Work

- ✅ **CRITICAL BUZZER SYSTEM FIX**: Buzzer Audio System Restoration (AudioContext Closed State)
  - **Problem**: Buzzer system completely non-functional - manual test and timer completion buzzer producing no sound despite appearing to work
  - **Root Cause**: AudioContext in "closed" state due to individual components creating separate contexts and cleanup effects closing shared context
  - **Impact**: Core game functionality broken - timer completion buzzer is essential user experience
  - **Solution**: Implemented singleton AudioContext pattern with `getAudioContext()` function and auto-recovery from closed state
  - **Implementation**:
    - ✅ Added comprehensive diagnostic logging to identify "closed" state issue
    - ✅ Implemented global singleton AudioContext with `getAudioContext()` function
    - ✅ Removed destructive cleanup from individual useAudio hooks
    - ✅ Added auto-recovery from closed AudioContext state
    - ✅ Cleaned up debug logging for production-ready code
    - ✅ Comprehensive testing: manual buzzer test + timer completion buzzer
  - **Status**: ✅ **COMPLETE** - Committed in 43ef1b87, both manual and gameplay buzzers working perfectly
  - **Testing**: User confirmed both settings panel test button and timer completion buzzer are operational
  - **Impact**: Essential game functionality restored, AudioContext management technical debt eliminated

- ✅ **CRITICAL PRODUCTION FIX**: Wikipedia Phrases Deployment (TypeScript JSON Import Error)
  - **Problem**: Netlify build failing with TypeScript error `TS1005: ';' expected` in phrases.ts line 5 when importing JSON
  - **Root Cause**: Missing `resolveJsonModule: true` in tsconfig.app.json preventing JSON imports
  - **Impact**: 1,092 Wikipedia phrases committed to main but deployment blocked by build failure
  - **Solution**: Added `resolveJsonModule: true` to TypeScript configuration for proper JSON handling
  - **Implementation**: 
    - ✅ Updated tsconfig.app.json with resolveJsonModule configuration
    - ✅ Fixed JSON import for phrases.json containing 1,092 Wikipedia phrases
    - ✅ Committed fix to main branch (commit 8167ecb0)
    - ✅ Pushed to trigger Netlify production deployment
  - **Status**: ✅ **DEPLOYED** - TypeScript fix applied and pushed to production
  - **Impact**: 530% phrase expansion (173 → 1,092 phrases) now deployable to production

- ✅ **COMPLETED BUG FIX**: End-of-Game Buzzer Truncation Issue
  - **Problem**: Buzzer sound was cut off when game ended because UI state changes after only 100ms, but buzzer duration is 2.0 seconds
  - **Root Cause**: `setTimeout(() => { onTimerComplete(); }, 100)` in GameScreen.tsx interrupted buzzer playback
  - **Solution**: Added BUZZER_PLAYING game state to disable UI immediately but allow full buzzer playback before state transition
  - **Implementation**: 
    - ✅ Added BUZZER_PLAYING to GameStatus enum
    - ✅ Modified onTimerComplete to immediately set BUZZER_PLAYING state
    - ✅ Added onBuzzerComplete method for final state transition after 2200ms
    - ✅ Disabled Correct/Pass buttons during BUZZER_PLAYING state
    - ✅ Updated App.tsx to show GameScreen during BUZZER_PLAYING state
  - **Status**: ✅ **COMPLETE** - Committed in 4ef9b8be (8 files changed)
  - **Testing**: All core functionality tests pass; buzzer now plays full duration without UI interference

## Current Status / Progress Tracking

**Completed Phases:**
- ✅ **Phase 1** (Week 1): Complete React app structure, core navigation, basic components
- ✅ **Phase 2** (Week 2): Core game logic, phrase categories, skip limits, state management  
- ✅ **Phase 3** (Week 3): High-precision timer, Web Audio API, offline capabilities
- ✅ **Phase 4** (Week 4): Options panel, skip-limit features, Firebase analytics, IndexedDB persistence
- ✅ **Phase 5** (Week 5): OpenAI phrase-fetcher with Web Worker, deduplication, throttling
- ✅ **Phase 6** (Week 6): Capacitor mobile app, iOS deployment
- ✅ **Phase 7** (Week 7): QA, performance optimization, accessibility (Lighthouse: Performance 78/100, Accessibility 95/100, Best Practices 96/100, SEO 90/100)
- ✅ **Phase 8A** (Week 8A): Custom Category Request System (user requests category → see sample words → generate 50+ phrases)
- ✅ **Phase 8B** (Week 8B): Enhanced Timer UX (randomized duration 45-75s, hidden by default, optional visible/fixed timer)
- ✅ **Phase 8C** (Week 8C): Accelerating Beep "Hot Potato" Timer System (smooth interval decrease from 1000ms to 150ms)
- ✅ **Phase 8D** (Week 8D): Gemini API Migration (complete migration from OpenAI to Gemini API with secure key management)

**Currently Active:**
- 🚧 **Phase 9**: Launch preparation (App Store submission, privacy forms, screenshots)
- ✅ **PRODUCTION ISSUE RESOLVED**: Custom category request feature now fully functional - URL path mismatch fixed and verified
- ✅ **CYPRESS TYPESCRIPT FIXED**: TypeScript configuration issues in accessibility tests resolved

**Next Up:**
- Phase 9: Final polish, App Store submission, documentation

---

## Lessons Learned

- [2025-05-22] When using @testing-library/react, ensure @testing-library/dom is also installed as a dependency to avoid runtime errors.
- [2025-05-22] Use --legacy-peer-deps flag when encountering ESLint version conflicts in npm install.
- [2025-05-22] requestAnimationFrame-based timers are difficult to test with fake timers; focus tests on state management and API contracts rather than timing accuracy.
- [2025-05-22] Web Audio API requires proper TypeScript declarations for webkitAudioContext to support older browsers.
- [2025-05-22] jsdom environment is required for testing React hooks that interact with DOM APIs like AudioContext.
- [2025-05-22] Project has nested structure with React app in `words-on-phone-app/` subdirectory. Always run dev/build commands from the words-on-phone-app directory, not the root. Root package.json is just a stub with minimal scripts.
- [2025-05-22] Lighthouse Performance scores of 78/100 are respectable for React PWAs with complex game logic. Focus on achieving 90+ in Accessibility, Best Practices, and SEO as primary success criteria. Performance can be optimized but shouldn't block release for scores above 70.
- [2025-05-27] IndexedDB mocking in tests requires careful implementation of all methods used by the app. Missing methods like `getAll()` in mock objects can cause test timeouts. Sometimes it's better to focus on functional testing over complete unit test coverage when 3rd-party library mocking becomes complex.
- [2025-05-27] Web Audio API AudioContext should use a global singleton pattern to prevent multiple contexts and "closed context" errors. Browser autoplay policies require AudioContext to be resumed on user interaction. Cleanup effects that close contexts should be avoided when the context needs to persist across component re-renders.
- [2025-05-27] When implementing complex validation logic in Zustand stores, ensure cross-validation between related settings (e.g., first interval >= final interval) to prevent invalid configurations. Range clamping with Math.max/Math.min provides safe boundaries for user input while maintaining usability.
- [2025-05-27] Migrating from OpenAI to Gemini API requires careful attention to request/response format differences. Gemini uses `contents` array with `parts` containing `text`, while OpenAI uses `messages` array. API key authentication differs: Gemini uses URL parameter `?key=${apiKey}` while OpenAI uses Bearer token in Authorization header. Both require proper error handling for 401 (invalid key) and 429 (rate limit) responses.
- [2025-05-27] When implementing stateful request systems, avoid timestamps in ID generation for multi-step processes. Use deterministic IDs based on content (e.g., category name) so the same logical entity always has the same ID across different function calls. Non-deterministic IDs with timestamps cause "request not found" errors between related operations.
- [2025-05-27] For React components that need to display both static and dynamic data, implement caching in the service layer to enable synchronous access to async data. Store dynamic content (like custom categories) in organized cache structures (e.g., Record<string, string[]>) that can be accessed immediately by UI components, while keeping the async loading logic separate in useEffect hooks.
- [2025-05-27] When implementing delete functionality for user-generated content: (1) Always include confirmation dialogs to prevent accidental deletion, (2) Ensure complete cleanup of all related data (phrases, metadata, cache), (3) Update UI immediately after deletion, (4) Handle edge cases like deleting currently selected items by switching to safe defaults, (5) Use visual cues (positioning, colors, icons) to make delete buttons discoverable but not accidentally clickable.
- [2025-05-27] Netlify secrets scanning will fail deployment if environment variables prefixed with `VITE_` containing sensitive data (like API keys) are exposed in the client bundle. The solution is to move API calls to secure serverless functions and remove the `VITE_` prefix from environment variables.
- [2025-05-27] Always verify production deployment endpoints match the actual deployed function paths. Documentation claiming successful production testing can be misleading if the tested URLs differ from the actual application configuration. The CORS fix documentation tested `/.netlify/functions/gemini` but the production app tries to access `/netlify/functions/gemini` (missing dot), causing 404 errors. Thorough end-to-end testing with the actual application URLs is essential to catch URL path mismatches between different environments.
- [2025-05-27] When testing serverless functions end-to-end, ensure test scripts use the exact same request format as the actual application code. API functions expect specific field names (`prompt`, `category`, `phraseCount`) and response structures (`candidates[0].content.parts[0].text`). Testing with incorrect request formats will give false negatives even when the function is working correctly. Always examine the actual service layer code to understand the precise API contract before writing integration tests.
- [2025-05-27] When updating prompt formats that change output structure (line-based to JSON), always implement parsing logic that can handle both old and new formats for smooth transitions. Production testing is essential when modifying prompt formats - what works in development may behave differently with live AI models. JSON extraction from AI responses should use regex pattern matching rather than assuming the entire response is JSON, as models may include explanatory text before/after the JSON.
- [2025-05-27] For Vite projects using Web Workers, import workers using the `?worker` query parameter (e.g., `new URL('../workers/file.ts?worker', import.meta.url)`) to avoid MIME type issues. Don't use `{ type: 'module' }` option as it can cause "video/mp2t" MIME type errors. Also ensure worker message types match exactly between sender and receiver (e.g., 'STOP' not 'STOP_WORKER').
- [2025-05-27] Cypress projects require dedicated TypeScript configuration for proper type support. Create a `tsconfig.cypress.json` file with `"types": ["cypress", "cypress-axe"]` and include it as a project reference in the main `tsconfig.json`. Configure `cypress.config.js` with `typescript: { configFile: "tsconfig.cypress.json" }` to resolve TypeScript errors for Cypress globals like `describe`, `it`, `cy`, and `expect`. Modern Cypress versions (14+) have built-in TypeScript support and don't require separate `@types/cypress` package.
- [2025-05-27] Netlify Functions have a 10-second timeout limit for serverless functions. When making API calls to AI models with large batch requests (50+ phrases), the response time can exceed this limit causing 502 Bad Gateway errors. Optimize by reducing batch sizes to 25-30 items per request and increasing `max_tokens` parameter appropriately. Remove unused TypeScript interfaces to prevent compilation errors that block deployment.
- [2025-05-27] When migrating between AI services (OpenAI/Gemini), ensure the service layer actually uses the detected active service rather than being hardcoded to one provider. UI detection logic can correctly identify which service is available, but the service layer needs to dynamically choose the correct API endpoint and request format based on the active service. Simply having both functions deployed doesn't mean the application will use the preferred one. Fix: Update service layer to call detectActiveAIService() and implement separate methods for each provider's API format.
- [2025-05-27] Category generation batch sizes must respect Netlify function timeout limits. OpenAI functions generating 50+ phrases timeout after 10 seconds causing 502 Bad Gateway errors. Solution: Reduce PHRASES_PER_CATEGORY from 50 to 15 phrases per batch. This ensures reliable completion within timeout while still providing sufficient content for custom categories. Test different batch sizes to find optimal balance between quantity and reliability.
- [2025-06-20] TypeScript syntax in Web Workers causes runtime errors in production builds. Vite doesn't properly transpile worker files when they contain TypeScript-specific syntax like interfaces, enums, and type annotations. Solution: Convert worker files from .ts to .js and replace all TypeScript syntax with JavaScript equivalents - use JSDoc comments for type documentation, remove access modifiers (private/public), and fix all type annotations. Update imports to reference .js file and add @ts-ignore comments in tests that import the worker.
- [2025-06-22] **PROJECT RULE**: Version numbers must be updated automatically as part of every commit to enable easy identification of cached vs. current versions during development and production. This is critical for debugging deployment issues and ensuring users are viewing the intended version. Auto-versioning should be integrated into the build process and made visible on the main screen.
- [2025-06-22] **CATEGORY SELECTION REDESIGN SUCCESS**: Complex multi-component feature (10 tasks) completed successfully by leveraging existing partial implementation and systematic task breakdown. Key factors: (1) Thorough assessment of existing code before starting, (2) Detailed sub-task breakdown with clear success criteria, (3) Focus on production-ready quality over quick fixes, (4) Comprehensive testing approach. The feature provides significant UX improvement with multi-select categories, real-time phrase counting, and smart default/custom separation. Ready for production deployment with 104/105 tests passing and clean builds.
- [2025-01-15] **BUZZER TRUNCATION FIX**: When implementing audio feedback with state transitions, ensure the audio duration doesn't conflict with UI state changes. Audio elements (especially buzzer sounds) should complete before any state changes that might affect playback. Solution: Add intermediate game states (e.g., BUZZER_PLAYING) that disable user interaction immediately but allow audio to complete before final state transition. This preserves game mechanics (no input after time expires) while ensuring complete audio feedback. Key implementation: immediate UI disable + extended timeout (audio duration + buffer) before final state change.
- [2025-06-26] **GEMINI 2.5 FLASH UPGRADE SUCCESS**: Model version upgrade from gemini-1.5-flash to gemini-2.5-flash completed successfully with significant performance improvements. Key benefits: (1) Enhanced reasoning capabilities with "thinking budget" control, (2) 22% greater computational efficiency, (3) Better multimodal understanding and performance benchmarks, (4) Advanced reasoning with controllable thinking depth. Upgrade process was straightforward - only required updating model name in environment.ts and netlify function. All builds pass, 131/135 tests pass (4 pre-existing failures unrelated to upgrade). Backward compatible with existing API structure. No breaking changes required in service layer or UI components.
- [2025-01-15] **PROVIDER ATTRIBUTION SYSTEM**: When implementing AI provider switching with quality tracking, database schema migrations are essential for provider attribution. Key components: (1) Schema versioning with automatic migration system, (2) Service-specific API payload handling (OpenAI uses {topic, batchSize, phraseIds} vs Gemini's {prompt, category}), (3) Response format differences (OpenAI returns direct arrays vs Gemini's nested structure), (4) Provider attribution in quality pipeline for analytics, (5) Comprehensive end-to-end testing validates complete workflow. Database migration system must handle both new installs and existing data gracefully. Provider attribution enables data-driven quality comparison between AI models during large-scale generation.
- [2025-01-15] **DATABASE ERROR HANDLING FOR BULK OPERATIONS**: When building systems that expect duplicate entries (like phrase generation), database constraint violations should be handled gracefully at the application layer, not logged as errors. Solution: (1) Modify database layer to log UNIQUE constraint failures at DEBUG level instead of ERROR level, (2) Add specialized methods like `addPhraseIgnoreDuplicates()` that handle expected duplicates gracefully, (3) Provide clear duplicate statistics in user-facing output ("5 duplicates skipped"), (4) Use custom error codes (DUPLICATE_PHRASE) for better error handling. This eliminates confusing SQL error messages during normal bulk operations while maintaining proper error logging for genuine database issues.
- [2025-06-29] **DATABASE QUALITY OPTIMIZATION**: Periodic quality cleanup is essential for maintaining high database standards. Removing phrases below quality thresholds (e.g., score <70) improves overall database quality and player experience. Key steps: (1) Analyze score distribution to identify low-quality phrases, (2) Create automated cleanup scripts with threshold parameters, (3) Regenerate game exports after cleanup, (4) Verify build and deployment success with cleaned data. Achievement: 100% of phrases now score 70+ (589 phrases, average score 81.9, range 75-95) vs previous 99.7% quality. Quality enforcement ensures every phrase meets high entertainment value standards.
- [2025-01-15] **PRODUCTION DEPLOYMENT SUCCESS**: Feature branch merge to main completed successfully with comprehensive infrastructure deployment. Force push resolved remote reference conflicts effectively. Key achievements: (1) 56 files changed with 20,380 additions representing complete phrase pool expansion infrastructure, (2) Fast-forward merge ensured clean integration without conflicts, (3) Local branch cleanup after successful deployment, (4) Comprehensive automation infrastructure now live including nightly generation pipeline, (5) All quality control and provider attribution systems operational in production. The deployment establishes foundation for scaling to 5,000+ phrases with automated generation while maintaining 100% quality standards (589 phrases all scoring 70+).
- [2025-01-15] **PHRASE POOL EXPANSION BREAKTHROUGH**: Task 6 Phase II expansion achieves +46 new phrases (589→635) in single session with strategic insights. Key discoveries: (1) Targeted generation more effective than broad nightly runs for specific categories, (2) Food & Drink category highly productive (86% growth: 36→67 phrases), (3) Famous People category fully saturated (100% duplicate rate), (4) Quality standards maintained (82/100 average) despite rapid 7.8% expansion pace, (5) OpenAI gpt-4o model demonstrates 100% success rate with 11s average batch time. Strategic approach: focus on under-represented categories, implement category-specific prompts for saturated areas, continue targeted batch generation for optimal phrase yield while monitoring quality regression.
- [2025-01-15] **CATEGORY SATURATION MAPPING**: Expansion Session 2 (+17 phrases, 635→652) reveals clear saturation patterns across categories. Key insights: (1) History & Events fully saturated (100% duplicates) joining Famous People in saturated category, (2) Nature & Animals remains most productive (+8 phrases) for continued expansion, (3) Sports & Athletes and Technology & Science showing high saturation approaching limits, (4) Quality standards maintained (82/100 average, 99.5% excellent) despite category saturation challenges, (5) Strategic category mapping enables efficient targeting: focus on Places & Travel, Everything+, and Nature & Animals while avoiding Famous People and History & Events. Optimal expansion strategy: target expandable categories with <60 phrases for maximum yield.
- [2025-06-29] **DUPLICATE MITIGATION BREAKTHROUGH**: Task 5b implementation achieves 76.7% Bloom filter efficiency with 4x processing optimization. Key innovations: (1) Category-scoped Bloom filters with canonicalized tokens (1% false positive rate) pre-filter 77% of duplicate candidates before expensive scoring, (2) Enhanced prompt builder with dynamic "don't use" lists (50 most common phrases) and rarity seeds (8 specialized sub-topics for saturated categories), (3) Real-time filter updates prevent immediate re-generation of stored phrases, (4) Processing efficiency scales dramatically: 30 generated → 7 processed → 4 stored vs previous 30 → 30 → 8 approach. Results: Food & Drink category test shows sustainable generation even at 67+ existing phrases with maintained 77-80/100 quality scores. This solves the saturation problem and enables efficient scaling to 1,000+ phrases without diminishing returns.
- [2025-06-29] **CRITICAL BUG DISCOVERY - DUPLICATE GENERATION ROOT CAUSE**: After implementing sophisticated duplicate pre-emption with Bloom filters and enhanced prompts, discovered the enhanced prompts were NEVER reaching the AI! The `batch-queue-runner.js` builds detailed prompts with "don't use" lists and rarity seeds but passes them as `customPrompt` in options, which `api-client.js` completely ignores. Instead, the API client uses its own basic prompt generation. This explains why AI generates 70-90% duplicates in saturated categories - it has no knowledge of existing phrases! Key lesson: Always trace data flow end-to-end when implementing enhancements. Validate that sophisticated logic actually reaches its destination. The fix is straightforward: modify api-client.js to accept and use custom prompts. This single fix should dramatically reduce duplicate generation at the source, making the Bloom filters even more effective as a secondary defense.
- [2025-01-15] **COMPREHENSIVE CURRENT STATE ANALYSIS PREVENTS WORK DUPLICATION**: Before starting any UI redesign project, conduct thorough analysis of existing implementation to avoid rebuilding working functionality. Key discovery for category-ui-redesign: Current CategorySelector already implements 90% of planned features (multi-select, search, pinning, responsive design, phrase counts, bulk operations). The planned "two-screen approach" would replace a sophisticated, tested component that users are familiar with. Analysis revealed only 20 categories exist (not 32 as assumed), significantly reducing complexity needs. Recommendation: Enhancement over replacement preserves user familiarity while adding needed features. This analysis prevented 2-3 weeks of redundant development work. Always audit current implementation capabilities before designing "new" solutions.
- [2025-06-30] **PHRASE DATABASE GENERATION SUCCESS**: Task 4 completion achieved major milestone with 980 total phrases (98% of 1000+ target). Core categories well-balanced: Movies & TV (76), Food & Drink (71), Music & Artists (71), Sports & Athletes (52). Key insights: (1) Category saturation occurs naturally at 70+ phrases with 90%+ duplicate rates, (2) Quality remains consistently high (80+ average scores) throughout scaling, (3) Infrastructure handles large-scale generation effectively with proper duplicate prevention, (4) Production APIs (OpenAI) maintain quality under sustained generation loads, (5) End-to-end pipeline from generation → scoring → storage → quality control proven at scale. Achievement demonstrates phrase database tool + production API integration works excellently for large-scale content creation while maintaining party game quality standards.
- [2025-07-01] **TYPESCRIPT JSON IMPORT CONFIGURATION**: When using TypeScript with JSON imports, `resolveJsonModule: true` must be explicitly configured in tsconfig.json. Without this setting, TypeScript will throw `TS1005: ';' expected` errors when trying to import JSON files using ES6 import syntax. This is critical for production deployments where JSON data files are imported directly (e.g., phrase databases). The fix is simple but essential: add `"resolveJsonModule": true` to the compilerOptions in tsconfig.app.json. This enables proper type checking and compilation of JSON imports, preventing build failures during deployment. Always verify TypeScript configuration supports all import types used in the project before deploying to production.
- [2025-07-01] **AUDIOCONTEXT SINGLETON PATTERN CRITICAL FOR WEB AUDIO**: When using Web Audio API across multiple React components, implement a singleton AudioContext pattern to prevent "closed" state failures. Individual components creating separate AudioContexts and triggering cleanup effects leads to premature context closure, causing silent audio failures. Solution: Global `getAudioContext()` function manages single shared context with auto-recovery from closed state. This prevents the most common Web Audio API failure mode where calls appear successful but produce no sound. Essential for any app using audio across multiple components.
- [2025-07-01] **DIAGNOSTIC LOGGING ESSENTIAL FOR AUDIO DEBUGGING**: Audio failures often appear successful (no exceptions thrown) but produce no sound, making them extremely difficult to debug. Implement comprehensive diagnostic logging that tracks AudioContext state, buffer creation, node connections, and playback initiation. Key diagnostic points: AudioContext state ("suspended", "running", "closed"), buffer properties (duration, sampleRate), and error details. This logging pattern enabled immediate identification of the "closed" state root cause that would have been impossible to diagnose otherwise.
- [2025-07-01] **BROWSER AUTOPLAY POLICIES REQUIRE CAREFUL AUDIOCONTEXT MANAGEMENT**: Modern browsers suspend AudioContext by default until user interaction occurs. The singleton pattern must include automatic `ctx.resume()` handling when state is "suspended". Additionally, avoid closing AudioContext in component cleanup effects since audio functionality often spans multiple components. Global AudioContext should persist for the entire application lifecycle. This is critical for reliable audio functionality across all modern browsers and devices.
- [2025-07-24] **POSTHOG WINDOW ATTACHMENT CRITICAL FOR ANALYTICS**: PostHog SDK can load successfully via ES6 imports but fail to attach to the global window.posthog object, causing "phantom initialization" where analytics appears to work but no events are sent. Solution: Manual window attachment in the loaded callback with fallback timeout. Always verify window.posthog exists for debugging, not just successful init() calls. This pattern may apply to other third-party SDKs that expect global window attachment.

## Phrase Validation Quick Reference

### Scoring System (0-100 points)
1. **Local Heuristics (0-40)**: Word simplicity + cultural relevance patterns
2. **Wikidata (0-30)**: Has entry + language versions + sitelinks
3. **Reddit (0-15)**: Upvotes indicate cultural relevance
4. **Category (0-15)**: Pop culture categories get boost

### Thresholds
- **80-100**: Auto-accept (clearly recognizable)
- **60-79**: Accept (good for gameplay)
- **40-59**: Manual review suggested
- **20-39**: Warning (likely too obscure)
- **0-19**: Auto-reject (too technical)

### Examples
- "Pizza" → 85 (simple + universal)
- "Taylor Swift" → 88 (simple + Wikipedia + trending)
- "Barbenheimer" → 80 (recent phenomenon)
- "Quantum Chromodynamics" → 15 (too technical)

## Active Tasks and Implementation Plans

### Currently Active
- **[phrase-pool-expansion.md](implementation-plan/phrase-pool-expansion.md)** - Scaling to 7,000+ high-quality phrases
  - Status: Task 5e COMPLETE ALL PHASES (32 categories operational), ready for massive generation
  - Major Success: +90 high-quality phrases across 2 new categories (Fantasy & Magic: 48, Internet & Social Media: 42)
  - Infrastructure: COMPLETE - Expanded from 12 to 32 categories (167% increase!), all systems validated
  - Next: Task 6 - Scale generation across all 32 categories to reach 7,000+ phrase goal

### Recently Completed
- **[phrase-database-builder-tool.md](implementation-plan/phrase-database-builder-tool.md)** - ✅ COMPLETE
- **[phrase-quality-upgrade.md](implementation-plan/phrase-quality-upgrade.md)** - ✅ COMPLETE  
- **[phrase-database-generation.md](implementation-plan/phrase-database-generation.md)** - ✅ COMPLETE
- **[openai-phrasemachine-migration.md](implementation-plan/openai-phrasemachine-migration.md)** - ✅ COMPLETE
- **[sound-and-haptics.md](implementation-plan/sound-and-haptics.md)** - ✅ COMPLETE
- **[countdown-ripple-redesign.md](implementation-plan/countdown-ripple-redesign.md)** - ✅ COMPLETE
- **[version-number-display.md](implementation-plan/version-number-display.md)** - ✅ COMPLETE
- **[team-based-scoring-system.md](implementation-plan/team-based-scoring-system.md)** - ✅ COMPLETE
- **[visual-background-warning.md](implementation-plan/visual-background-warning.md)** - ✅ COMPLETE
- **[netlify-function-deployment-fix.md](implementation-plan/netlify-function-deployment-fix.md)** - ✅ COMPLETE
- **[cors-fix-gemini-function.md](implementation-plan/cors-fix-gemini-function.md)** - ✅ COMPLETE
- **[category-selection-redesign.md](implementation-plan/category-selection-redesign.md)** - ✅ COMPLETE
- **[gemini-model-upgrade.md](implementation-plan/gemini-model-upgrade.md)** - ✅ COMPLETE
- **[mobile-gameplay-screen-ux.md](implementation-plan/mobile-gameplay-screen-ux.md)** - ✅ COMPLETE
- **[app-icon-implementation.md](implementation-plan/app-icon-implementation.md)** - ✅ COMPLETE
- **[header-overlap-fix.md](implementation-plan/header-overlap-fix.md)** - ✅ COMPLETE

## Lessons Learned

### Phrase Generation & Quality
- [2025-01-15] **Enhanced Prompt Delivery Critical**: api-client.js was ignoring custom prompts entirely. Always verify end-to-end that sophisticated logic actually reaches the AI.
- [2025-01-15] **Prompt Engineering Has Limits**: Even with enhanced prompts delivered, duplicate rates vary wildly by category (20-90%). Need category expansion strategy rather than fighting saturation.
- [2025-01-15] **A/B Testing Essential**: Without controlled comparison between basic and enhanced prompts, impossible to quantify improvement. Always implement testing frameworks before claiming optimization success.
- [2025-01-15] **Category Expansion Strategy Validated**: Expanding from 12 to 32 categories (167% increase) dramatically more effective than fighting saturation in existing categories. Quality maintained at 80/100 average throughout.
- [2025-01-15] **Infrastructure Scalability Proven**: Systems handle 167% category increase with zero performance degradation. All 32 categories operational with 7,000 phrase capacity.
- [2025-01-15] **Prompt Engineering at Scale**: Category-specific prompts proven effective across 32 categories. Each category generates distinct, appropriate phrases with consistent quality.
