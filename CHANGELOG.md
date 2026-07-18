# Changelog

All notable changes to **idea-to-deploy** are documented here.

The format is based on [Keep a Changelog](https://keepachangelog.com/en/1.1.0/),
and this project adheres to [Semantic Versioning](https://semver.org/spec/v2.0.0.html).

---

## [Unreleased]

## [1.91.1] - 2026-07-18

**Честное model-neutral позиционирование Idea to Deploy как реализации Harness
Engineering без заявления недоказанной универсальности**:

### Changed
- README на английском и русском теперь различают продукт **Idea to Deploy**,
  категорию методологии **Harness Engineering**, model-neutral ядро контрактов,
  состояния и verification rules и host-specific adapter/transport слой.
- Quick start, архитектура и support matrix описывают два проверенных host-а —
  Claude Code и OpenAI Codex. Все остальные hosts и providers явно помечены как
  невалидированные, без обещания одинакового поведения или out-of-box поддержки.
- Документы contracts, model routing, Harness Engineering map и ADR приведены к
  той же границе переносимости; остаточные `CLAUDE.md`, `CLAUDE_CODE_GUIDE.md`,
  Claude model tiers и известные transport degradations раскрыты явно.
- Версии Claude Code и Codex adapter manifests и публичные badges синхронизированы
  на v1.91.1. Production skills, hooks, contracts и adapter semantics не
  менялись; conformance evidence заново получен на текущем content-pinned tree.

### Fixed
- Live-model runner больше не считает один недетерминированный model turn
  атомарным: при успешном, но неполном первом проходе допускается ровно одно
  продолжение в том же adopted project. Попытки делят исходный deadline и
  Anthropic budget; независимый snapshot oracle не ослаблен.
- PASS и FAIL evidence теперь сохраняют per-attempt terminal events,
  byte-boundaries и transcript hashes. Реальный FAIL архивирует только transcript
  и присутствующие oracle-required outputs, поэтому причина воспроизводима и не
  превращается в ложный H4 PASS.
- Headless Codex явно использует no-escalation policy
  `never + workspace-write`. Windows-bridge transport нормализует host temp и
  `-C` path, а WSL write benchmark проверен через native Linux Codex без
  full-access bypass и без API key.

### Verification
- Host-adapter parity, documentation freshness, methodology meta-review and the
  repository quick regression suite are required to pass on the release tree.
- Fresh native Codex live evidence is resolved through the content-pinned
  `tests/fixtures/live-model-evidence/latest.json` pointer; independent
  fail-closed verifier and archived snapshot replay: 81/81 PASS.

## [1.91.0] - 2026-07-16

**Рабочий SLA-профиль: один verified unit за ход, proportional verification
и exact-context safety gates без снижения Harness Engineering / Practical
Effectiveness**:

### Added
- **Default-off `working_deadline` mode** — отдельный 45-минутный профиль для
  повседневной работы ограничивает ход одним unit, требует bounded scope и
  2–4 проверяемых критерия, а на 30-й минуте возвращает готовое, blocker,
  остаток и оценку времени вместо бесконтрольного расширения задачи.
- **Два verification-профиля** — host-neutral selector выбирает targeted
  contours для low/medium daily work, но fail-closed переводит high/unknown
  risk, release candidate и security signals в strict release. Диагностический
  прогон собирает ошибки пакетом; неблокирующие находки уходят в backlog.
- **Frozen A/B benchmark рабочего режима** — sealed corpus сравнивает один и
  тот же набор cases с always-full baseline через реальный selector. Quality
  определяется покрытием capabilities; candidate hash включает base `HEAD`,
  binary diff и non-ignored untracked files. Mutation guards запрещают stale
  binding, high-risk bypass, false completion и synthetic external evidence.
- **Exact external-write boundary** — внешняя запись требует preview точных
  targets, полного payload и attachments и возвращает host-native `ask`.
  Локальный forgeable approval ledger удалён; изменение адресата или payload
  создаёт новое подтверждение.

### Changed
- `/goal` хранит deadline/handoff evidence, выдаёт результат после каждого
  verified unit и не активирует следующий unit до нового пользовательского
  хода. Schema и state validators сохраняют WIP=1 и проверяют elapsed evidence.
- `/review` и `/security-audit` записывают verdict только по полному context key:
  repository, base/tree, binary diff, scope/acceptance contracts,
  rubric/version и risk tier. `BLOCKED`/`UNVERIFIED` не удовлетворяют gate.
- Risk budget разделён на general/security buckets; успешный bound verdict
  сбрасывает только свой bucket и начинает новый post-gate delta window.
- Model/effort routing разрешает low reasoning только для ограниченной
  mechanical работы; high/unknown risk и release остаются strict независимо от
  запрошенного рабочего профиля.
- Full benchmark зарегистрирован в Linux/Windows CI и full `run-all`; повседневный
  targeted путь не запускает release matrix после каждого изменения.

### Fixed
- Security DoD gate больше не принимает поддельный, чужой или устаревший
  sentinel: он проверяет accepted `records.security` для текущего staged
  candidate. Изменение staged diff и `BLOCKED` verdict снова закрывают gate.
- Explicit session id изолирует test/migrate markers между сессиями; legacy
  fresh fallback сохраняется только для hosts без session id, устраняя
  order-dependent full-suite false green.
- Тип и текст subagent больше не могут сами выдать review/security success:
  status-aware evidence создаёт только явный producer соответствующего
  workflow после принятия независимого machine-readable verdict.
- Codex transport сохраняет native `ask` parity, корректно классифицирует
  реальные `mcp__codex_apps__...`, локальный `mcp__node_repl__...`, compound
  read-only commands и fail-closed обрабатывает malformed/external payloads
  без обхода PII/egress boundary.

### Verification
- PE5-010…PE5-016: **verified**; финальный immutable oracle завершён с
  `DONE fails:none` (Harness Conformance, пять внутренних Practical
  Effectiveness axes, host adapters, meta-review, quick и full regression).
- Frozen A/B: 0 quality regressions, 0 high-risk bypasses, 0 critical false
  completions; eligible contour calls снизились с 15 до 6.
- PE5-008/009 остаются **UNVERIFIED** до отдельно одобренного opt-in pilot и
  реального external outcome evidence. Режим остаётся default-off; этот релиз
  не заявляет внешний Practical Effectiveness 5,0/5,0.

## [1.90.0] - 2026-07-15

**Модель-нейтральный Harness Engineering 5/5: Codex adapter, доказуемые
completion boundaries, host-neutral continuity и live-model verification**:

### Added
- **Машинный контур практической эффективности по шести осям** — frozen
  `PRACTICAL_EFFECTIVENESS_CONTRACT.json` и fail-closed evaluator принимают
  только свежие независимые evidence-команды. Adversarial completion corpus,
  proportionality/cost attribution, operational cold start, cross-platform
  runtime и learning-loop fixtures довели пять внутренних осей до
  воспроизводимого 5/5 без подмены внешнего результата.
- **Privacy-safe внешний pilot kit** — zero-dependency collectors ведут
  псевдонимный paired baseline/follow-up ledger локально у оператора,
  агрегируют только числовые outcomes и SHA-256 provenance и требуют явные
  consent/independence/accuracy attestations. Реальный
  `docs/evidence/external-outcomes/INDEX.json` намеренно отсутствует до
  отдельно одобренного пилота; fixtures и self-report не могут сделать ось
  зелёной.
- **Поведенческие benchmark-корпуса практической эффективности** — отдельные
  sealed-наборы проверяют ложное завершение, proportionality, обходы при
  cold-start adoption, Windows/WSL parity и human-gated learning loop; corpus
  hashes не позволяют реализации незаметно ослабить собственный экзамен.
- **Замороженная H1–H5 рубрика и доказанный итог 5/5** — sealed
  `HARNESS_CONFORMANCE_CONTRACT.json`, fail-closed evaluator, русскоязычный
  аналитический отчёт и freshness state не позволяют narrative-документам
  выставлять себе балл или принимать missing/stale/self-referential evidence.
- **Настоящий ITD live-model benchmark** — изолированный adopted-проект
  вызывает repository-local `$idea-to-deploy:blueprint --full`, сохраняет
  bounded transcript/artifact hashes и принимает PASS только после независимого
  replayable snapshot oracle; свежий pinned run: `20260715T160657Z-f0da33ea`.
- **Host-neutral continuity и полный hard-gate parity** — project-local
  `.itd-memory` восстанавливает unit/evidence/blockers/next action между Claude
  Code и Codex, а все 10 computational hard gates проверяются на обоих host
  adapters реальными allow/deny сценариями.
- **Evidence-efficient `/goal` 5/5 path** — adaptive checker routing is sealed
  per unit (`low/medium/high` → machine-only/targeted/full), compact handoff
  checkpoints are capped at 4 KiB, and `itd_goal_score.py` awards five binary
  points only from ≥5 parity-matched A/B pairs with frozen-oracle quality,
  time/token, memory, immediate+24h understanding, and stop-integrity evidence.
  Thresholds are fixed in code; contaminated controls or missed criticals fail
  closed with actionable `path + WHY + FIX` output.
- **Opt-in bounded autonomy for `/goal`** — an approved `runPolicy` can seal the
  verification oracle, cap attempts/wall-clock/host-observed token budgets,
  require an explicit approach and independent-review evidence, and persist an
  append-only attempt ledger with typed stop reasons. Resume after exhaustion
  requires a human reason and a strict increase of exactly the exhausted limit;
  host-native continuation remains transport and cannot bypass `/task`, `/test`,
  `/review`, deployment, or external-write gates.
- **Реальный внешний scheduler** — read-only GitHub Actions cron запускает
  weekly cleanup + objective quality scoring каждый понедельник и monthly
  reversible ablation первого числа месяца; evidence сохраняется Actions
  artifact даже при красном результате. Для принятых проектов добавлен
  opt-in workflow template, который `/adopt` не включает без согласия.
- **Objective quality scorecard** — пять содержательных измерений получают
  weighted score из исполняемых probes; stability может требовать повторных
  попыток, minimum score и завышенная declared grade дают fail-closed, а полный
  per-attempt evidence пишется в `.itd-memory/hygiene/quality-score-*.json`.
- **Практический retro-proof** — `RETRO-2026-07-14.md`: пять последовательных
  session-close прогонов поймали 5/5 классов нарушений; на 10 фиксированных
  задачах strict harness сохранил final completion 100%, но снизил leaked-task
  rate с 70% до 0%; ablation `completion-stop` дала 6/6 → 3/6 и решение KEEP.
- **Codex host adapter** — `.codex-plugin/plugin.json`, нативная регистрация
  хуков, `codex-dispatch.py` для нормализации `apply_patch`, host-adapter
  registry/contract и Codex-specific setup guide. Общие skills, hooks, `.itd/`
  contracts и `.itd-memory/` state остаются единым методологическим ядром.
- **Явный session-close contract** — `/session-save --close` запускает
  `itd_hygiene.py close` и требует одновременно зелёные verification/startup
  checks, свежий quality ledger, отсутствие debug-маркеров, manifest cleanup и
  чистый Git. Обычный Stop остаётся мягким сигналом.
- **Двухрежимная очистка** — безопасная немедленная manifest-cleanup и
  периодический weekly-runner; операции повторяемы, не удаляют tracked-файлы,
  отклоняют absolute/escaping paths и не маскируют ошибки.
- **Quality и ablation ledgers** — `QUALITY.json` ранжирует модули и направляет
  `/task` к худшему модулю по умолчанию; `HARNESS_ABLATION.json` хранит
  ежемесячные baseline/disabled эксперименты и решение человека о судьбе
  компонента. Добавлен воспроизводимый benchmark completion-stop.
- **Поведенческий proof-suite** — `verify_session_hygiene_quality.py` проверяет
  fail-closed close, dirty/debug/verification failures, freshness quality,
  weekly cleanup, monthly ablation и идемпотентность. Отдельный
  `verify_host_adapters.py` фиксирует parity Claude Code/Codex.

### Changed
- `cost-tracker.sh` повышен из soft telemetry до двухфазного cost boundary:
  PostToolUse по-прежнему учитывает observed/estimated usage, а PreToolUse
  fail-closed запрещает только следующую дорогую попытку, которая пересечёт
  настроенный ceiling. Дешёвые inspection/checkpoint операции остаются
  доступными; hard-gate taxonomy теперь 11/18/29 с behavioural parity на
  Claude Code и Codex.
- `/task`, `/adopt` и `/retro` получили исполняемые proportionality,
  cross-platform и feedback-loop контракты; CI запускает соответствующие
  проверки на Linux и Windows, а learning proposals остаются human-gated и не
  изменяют методологию автоматически.
- **Strict completion теперь авторизуется исполняемым baseline-verifier** —
  workspace-writable signal ledger остаётся telemetry, а source commit и
  explicit close повторно исполняют канонический
  `.itd/VERIFICATION_CONTRACT.json`, неизменный с последнего source checkpoint.
  Закрыты staged/committed oracle weakening, split policy/close verifier,
  `env`/`command`/`sudo` wrappers, source→non-source rename и timeout nesting
  720/840/900; human bypass остаётся явным и аудитируемым.
- **Live evidence pinning исключает только собственные generated artifacts** —
  exact path filtering сохраняет mixed rename и похожие вложенные source paths,
  поэтому benchmark не инвалидирует себя и не скрывает изменение методологии.
- Bounded token stops now require a numeric host observation meeting the sealed
  limit; `enforceObservedTokens` can require the meter on every verification.
  Weekly hygiene timeout is 30 minutes, covering its 24-minute worst-case probe
  budget instead of timing out structurally at 15 minutes.
- `/adopt` устанавливает полный набор `.itd`-шаблонов и создаёт консервативные
  стартовые quality/ablation/session-artifact contracts для обоих host adapters.
- `/task`, `/session-save` и `/retro` связаны с quality queue, явной границей
  закрытия, weekly hygiene и monthly ablation; CI запускает новые поведенческие
  проверки на Linux и Windows.
- Destructive/external-write skills используют vendor-neutral
  `metadata.explicit_invocation` и host-native запрет implicit invocation вместо
  Claude-only frontmatter как источника политики.

### Fixed
- Windows cold-start verifier больше не смешивает `cmd.exe`-quoting для
  adoption/bootstrap команд с POSIX-sh контрактом goal
  `verificationCommand`; Python под профилем с не-ASCII именем запускается без
  ручного исправления пути.
- `check-skill-completeness.sh` нормализует Windows `\` только для
  contract-path matching, поэтому Write и Codex `apply_patch` снова получают
  одинаковый deny на неполный `skills/<name>/SKILL.md`.
- Native Windows runtime probe не принимает доступный через
  `\\wsl.localhost` foreign `/proc` за доказательство WSL kernel; OS identity
  проверяется до kernel marker, сохраняя раздельные native/PowerShell/Git Bash
  launch paths.

### Assessment
- Чистое состояние как требование завершения: **5,0/5**.
- Немедленная + периодическая очистка: **4,9/5** — weekly cron материализован;
  первый scheduled evidence появится после merge workflow в default branch.
- Активный документ качества: **4,8/5** — weighted executable probes, stability
  repeats, minimum score и overstatement gate автоматизированы; выбор смысловых
  probes и повышение tracked grade намеренно остаются human-reviewed.
- Периодическое упрощение harness: **4,9/5** — monthly cron и реальная ablation
  6/6 → 3/6 работают fail-closed; удаление компонента остаётся human decision.
- Идемпотентные операции очистки: **5,0/5**.

Средняя оценка после полного набора изменений: **4,9/5**.

Отдельная цель практической эффективности закрыта на **7/9 verified units**.
Внешняя adoption/outcome-валидация и итоговый all-axis evaluator остаются
**UNVERIFIED**: recruitment приостановлен до нового явного решения человека,
реальных consented pilot records не собрано. Это не блокирует выпуск tooling,
но запрещает заявлять внешний или общий practical-effectiveness результат
5,0/5,0.

## [1.89.0] - 2026-07-12

**10 параметров наблюдаемости/качества → 5/5 на обеих машинах (цель v1.89.0, GO-001…GO-007; сет-4 старт 4/2/2/3/3/4/1/4/2/3, RE-AUDIT-OBS: PASS)**:

### Added
- **Двухфазный execution-tracer (GO-001)** — PostToolUse-фаза дописывает исход
  (`outcome` ok/fail/empty/unknown + exit/error) для ВСЕХ tool
  (Bash/PowerShell/Edit/Write/Agent/Skill) парно к PreToolUse-интенту. Закрывает
  «трейс из намерений, не результатов» (сет-4: 0/228 событий несли исход).
  Agent пустой финал → `outcome empty`. Тест (10) + run-all.
- **ОТК-сигнал верификации (GO-003)** — `itd_goal_verify.py` пишет `verify`-сигнал
  (L2, unit-атрибуция) при каждом прогоне verificationCommand: состояние
  «верифицирован ↔ ничего не проверялось» стало различимо (было 44 verified / 0
  сигналов). Плюс `agent_result_signal` (пустой финал субагента) и `find_stalls`
  (зависший фон по (tool,target)). Тест (6).
- **Дефолтная deployment-планка /task (GO-005)** — Step 3f несёт deployment-floor
  (exit-семантика, diff-scoped/no-op, actionable WHY+FIX, тихий успех, zero-dep,
  самопроба), применяемый БЕЗ явного Sprint Contract. A/B: безконтрактный агент
  6/6 требований (было 3.5/6). Тест (8).

### Changed
- **Классификация сигналов (GO-002)** — `unwrap_shell` снимает `wsl/sh -c`-обёртки
  перед классификацией: commit-в-обёртке больше не `test_run` (live-FP сет-4
  «commit=test»). `SUPPRESS_PATH_RE` подавляет ТОЛЬКО корпус методологии
  (`benchmarks/review-evalset`, `.itd/benchmarks`) — чужие `tests/fixtures/` не
  глушатся. `append_signal` проставляет `sig.unit` из `GOAL.currentUnitId`. Тест (12).
- **OTel-экспортёр (GO-004)** — сигнал цепляется к span юнита ПО ПОЛЮ `unit`
  (не по времени; orphan<10% на тест-леджере); semconv-атрибуты
  `gen_ai.operation.name`/`gen_ai.usage.*`, `process.command_line`/`exit_code`,
  `test.case.result.status`; `validate_semconv`. Тест (9).
- **meta_review M-C10** — поддержка двухфазных телеметрия-хуков (Pre+Post),
  распознавание по обоим строковым литералам события.

---

## [1.88.0] - 2026-07-12

**4 практики runtime-наблюдаемости → 5/5 на обеих машинах (цель v1.88.0, GP-001…GP-007; стартовые оценки 4.0/4.0/4.5/2.0, RE-AUDIT-4P: PASS)**:

### Added
- **PowerShell-канал runtime-сигналов (GP-001)** — `completion-signals.sh` принимает
  `tool_name: PowerShell` (симметрия со state-guard v1.78.1); `completion_lib`:
  `Invoke-Pester` → L2, `Invoke-ScriptAnalyzer` → L1, `Invoke-WebRequest`/`irm` на
  localhost → L3; регистрация под matcher `PowerShell` в **PostToolUse** (не PreToolUse —
  там нет `tool_response`). Тест: `tests/verify_completion_signals_powershell.py` (8).
- **Классы сигналов (GP-002)** — поле `class` (verification / lifecycle / data_flow /
  resource) на каждом сигнале; `phase` startup/ready/shutdown для app_start по маркерам
  вывода; `RESOURCE_ANOMALY_RE` (OOM / max_memory_restart → `anomaly: memory`, никогда
  pass; неклассифицируемая команда с OOM-выводом → resource-сигнал L0); `error_tail`
  на fail — полный контекст ошибки, не только сообщение. Поля аддитивны — verdict-логика
  не тронута. Тест: `tests/verify_completion_signal_classes.py` (13).
- **Sprint Contract per-задача (GP-003)** — шаблон `docs/templates/itd/TASK_CONTRACT.md`
  (Scope / Verification Standards / Exclusions, один экран); `/task` Step 3f-1b: контракт
  в `.itd-memory/contracts/<unit-id>.md` ДО первой правки кода; DoD-гейт: advisory-строка
  на `git commit` при активном юните без контракта (НЕ deny — анти-ceremonial, opt-in по
  `.itd-memory/`). Тест: `tests/verify_task_contract_advisory.py` (6).
- **Eval-set рубрики /review (GP-004)** — `benchmarks/review-evalset/`: 10 посеянных
  дефектов (категории из живого review-findings ledger: sql-performance ×3,
  BigInt-сериализация, migration-numbers, секреты, SQL-инъекция, floating promise,
  tz-date, empty catch) + 2 чистые фикстуры (false positives);
  `tests/verify_review_evalset.py` — detection rate, порог ≥80% и 0 FP (exit 1 ниже),
  `RESULTS.json`; `itd_retro_scan` отдаёт секцию `reviewEvalset`.
- **OTel-экспортёр (GP-005)** — `scripts/itd_otel_export.py` (stdlib): `events.jsonl` +
  `signals.jsonl` → OTLP/HTTP JSON; trace = сессия, span = юнит/задача, sub-span = шаг
  верификации и runtime-сигнал; детерминированные trace/span id (idempotent re-export);
  офлайн-валидатор; `--out` / `--endpoint`. Смоук: Jaeger 1.57 принял трейс реального
  леджера (145 spans, HTTP 200). **Инвариант best-effort**: JSONL остаётся каноном,
  экспортёр — транспорт, ни один гейт на OTLP не завязан. Раскатка: `sync-to-active`
  копирует в `~/.claude/scripts/`. Тест: `tests/verify_otel_export.py` (13).

---

## [1.87.0] - 2026-07-11

**Сет-3 упражнений Harness Engineering → 5.0 по всем трём (цель exercise-5s, GX-001…GX-005; повторная проверка живыми пробами: 4.2 → 5.0)**:

- **GX-001 (кросс-компонентные дефекты 3.8 → 5.0)**: ОТК `itd_goal_verify.py` исполняет verificationCommand через `[\"sh\",\"-c\"]` — POSIX-семантика на обеих ОС; тихий false-pass cmd.exe (live-репро: verified с нераскрытым `$HOME` при exit 0) убит; без sh — громкий rc=127, не деградация. Контракт-тест `tests/verify_goal_verify_shell.py` проверяет СЕМАНТИКУ ($VAR раскрыт, одинарные кавычки сняты, ненулевой exit доходит), не только exit-код.
- **GX-002 (автоматизация арх-правил, слот)**: first-class слот project-level проверок — `skills/_shared/itd_project_checks.sh` (`.itd/checks/*`, диспатч sh/node/py, `ITD_CHANGED_FILES`, agent-oriented вывод), DoD-хук гоняет раннер на staged-файлах при наличии каталога (deny с WHY/FIX, обход штатным SKILL_BYPASS), `docs/project-checks.md`, тест `verify_project_checks.py` (7 контрактов, включая hook-deny/pass).
- **GX-004 (продвижение review-фидбека 4.5 → 5.0)**: импортёр внешних GitHub-ревью `skills/retro/scripts/itd_review_import.py` → review-findings.jsonl (схема v1.86, verdict=EXTERNAL_REVIEW, dedup по id комментария, эвристический классификатор); шаг 1a-ext в /retro. Live: 7 записей из OneOfS, retro-майнинг сразу поднял новый повторяющийся класс `sql-performance ×4` — петля «партнёрское ревью → леджер → майнинг → кандидат-автопроверка» замкнута end-to-end.
- Пример model-aware project-проверки (BigInt-сериализация из parsing schema.prisma + `--files`) живёт в целевом проекте (`.itd/checks/`, вне git методологии) — контракт описан в docs/project-checks.md.

## [1.86.0] - 2026-07-11

**Три quick-win'а по итогам внешней оценки Harness Engineering (4.5/5.0/4.5/4.5 → цель 5): FIX_HINTS из инцидент-корпуса, review-findings ledger + retro-майнинг, P6 pre-wire.**

- **Пункт 3 (FIX_HINTS)**: +9 классов ошибок из реального инцидент-корпуса (retro 2026-07-11 + прод-инциденты OneOfS): cp1251/UnicodeEncodeError → `PYTHONIOENCODING`/`itd_py.sh`; Prisma P1001 (БД недоступна); unique/duplicate key (идемпотентность); FK-нарушение; PG 42703 (несуществующая колонка — сверять с information_schema); 42P08 (NULL-параметр без `::type`); heap out of memory (лимиты/батчи); ECONNRESET/EPIPE (таймауты прокси, не код); 413 (лимит тела запроса). Специфичные классы стоят до generic-хвоста — «P1001 … timed out» получает подсказку про БД, а не про таймаут (order pin в тесте). +11 проверок в `verify_completion_gate.py`.
- **Пункт 4 (review → автопроверки)**: связка «находка /review → кандидат-автопроверка» замкнута машинно. (1) `verdict-contract.sh` при ВАЛИДНОМ вердикте персистит findings в `.itd-memory/review-findings.jsonl` (fallback — глобальный tmp-леджер; bounded 64K, content-дедуп, best-effort — block/silent-решение хука не меняется); (2) схема вердикта /review — опциональное поле `category` (kebab-case класс дефекта); (3) `itd_retro_scan.py` — новая секция FACTS «Находки /review»: повторяющиеся классы (category, либо `~фингерпринт` по summary) с count ≥2 = кандидаты в автопроверки для PROPOSALS. +5 проверок в `verify_verdict_contract.py`, +3 в `verify_retro_scan.py` (фикстуры зеркалят реального продюсера — урок v1.46.0).
- **Пункт 1 (P6 pre-wire)**: в OneOfS `.claude/completion/config.json` предзаведён L2-паттерн `sql-ro\.sh` для отчётного класса работ (правка идемпотентна и не даёт ложных сигналов, пока серверного канала нет); серверная часть (`/opt/mgmt/scripts/sql-ro.sh`, роль ai_readonly) по-прежнему ждёт ОК Максима — P6 остаётся открытым до смоука канала.

## [1.85.0] - 2026-07-11

**Дорога к 4.9-5.0 по пятёрке Harness Engineering (цель harness-layers-4.9, юниты G-001…G-005; независимая перепроверка живыми пробами: 4.4 → 4.92/5)**:

- **G-001 (инструменты/среда 4.0 → 5.0)**: `itd_py.sh` форсирует `PYTHONIOENCODING=utf-8` + `PYTHONUTF8=1` (уважая значения вызывающего) — live-провал итер-4 диагностической петли: cp1251-консоль роняла `print(\"→\")` UnicodeEncodeError при корректно выбранном интерпретаторе. Контракт-тест `tests/verify_py_launcher_encoding.py` (static/default/override/smoke) в run-all + meta-review.
- **G-002 (инструкции 4.0 → 4.9)**: `skills/_shared/subagent-contract.md` — канонический субагентский контракт; env-преамбула транспортирует env-нормы в промпты субагентов (live: субагент сжёг 2 попытки на WindowsApps-шиме при закрытом в v1.84.0 слое основного цикла — защиты main-loop не наследуются). Подключён в Rules blueprint/discover/perf/review.
- **G-003 (evidence 4.5 → 4.9)**: секция 2 контракта «evidence-gate» — сдача субагента принимается только с evidence либо явной пометкой «НЕ ПРОВЕРЕНО» (live: процессный gap 60% на микрозадачах); калибровка: на микрозадачах полную лестницу не требовать (фактический gap там 0%).
- **G-004 (петля/телеметрия 4.5 → 4.9)**: `skills/task/scripts/itd_unit_log.py` — harness-писатель unit-бухгалтерии /task Step 3.5 (инструкция → инструмент): пары activated/verified fail-closed, WIP=1, verified без evidence отклоняется, `backfill-activation --note` для реконсиляции истории. Диагноз: ручная JSON-запись моделью теряла activation-события (4 юнита U-2…U-5 → «Аномалия учёта», слепой VCR). Тест `tests/verify_unit_log.py` (8 проверок) в run-all + meta-review; история OneOfS реконсилирована (скан: 0 аномалий).
- **G-005 (калибровка 4.5 → 4.9)**: P4-final в RETRO-2026-07-11-followup — независимая сессия: bypass 573.5/сессию → 0, ceremonial 0.
- **Независимая перепроверка (G-006)**: три слепые пробы sonnet-субагентами — транспорт контракта (1-я попытка), кодировка end-to-end без env-префикса (1-я попытка, 0 UnicodeEncodeError), evidence-приёмка (полный протокол + скрытый тест 8/8). Отчёт: память OneOfS session_2026-07-11_8.
- Попутная находка (бэклог): `itd_goal_verify.py` исполняет verificationCommand через cmd.exe на Windows — `sh -c` с одинарными кавычками/`$VAR` ломается; юнит-команды следует писать плоскими, долгосрочный фикс — явный `["sh","-c",…]` без shell=True.

## [1.84.0] - 2026-07-11

**Вторая волна бэклога ретро 2026-07-11 (P4, P8, W1, слабые сигналы №2/№3/№6, T1, minors ревью #155) — всё, кроме P6 (прод-доступ, решение человека) и gemini-логина (внешний блокер)**:

- **P4 (трение гейтов)**: ceremonial SKILL_BYPASS (265 привычных аннотаций при
  открытом гейте за 2 сессии) → `check-tool-skill.sh` учит агента одноразовым
  (per session) hint'ом «окно уже открыто — аннотация не обязательна»;
  формулировка в шаблоне глобального CLAUDE.md. Hard-gated классы
  (push/migration/deploy) не затронуты — их явный bypass остаётся единственным
  in-band escape.
- **P8 (коллизии памяти)**: `state-guard.sh` — soft-guard файлов памяти сессий:
  Write/`mv`/`cp`/redirect поверх СУЩЕСТВУЮЩЕГО и СВЕЖЕГО (<6 ч)
  `memory/session_*.md` → предупреждение о параллельной сессии (live-инцидент:
  mv затёр чужую хронику, восстанавливали из JSONL-транскрипта). Warn, не deny
  (ownership файла памяти неатрибутируем); один раз per (session, file).
- **W1 (WSL-мост)**: `skills/_shared/itd_wsl.sh` — команды уезжают в WSL
  base64-строкой (MSYS-конверсия путей/`$(...)`/wildcard больше не мнут inline;
  грабли воспроизводились ×3 за день) + правило helpers §13.
- **Слабый сигнал №2**: `careful.sh` вырезает цитируемую прозу `-m '…'`
  перед матчингом (FP «GIT BRANCH -D» в теле коммита).
- **№3/№6 → helpers §14/§15**: «гейт-статусы грепай точной строкой
  `FINAL STATUS: PASSED`»; «границы вместо человеческих чекпоинтов» (D3).
- **T1**: `AGENTS.md`-алиас в корне репо (указатель на CLAUDE.md) + `/adopt`
  предлагает такой же алиас проекту; карта T1 обновлена. Промо-драфт: счётчик
  скиллов 23→40.
- **Minors ревью #155**: verify_no_bare_python3 — trailing-комментарии не
  матчятся, version-pinned `python3.11` ловится; ENV_PROBE_RE понимает
  `import x as y`; I10-сниппет review-checklist самодостаточен.
- **№5 (narration-финалы) — сознательно БЕЗ кода**: регекс УЖЕ матчит
  сегодняшние обрывы («Now let's check…»), хук читает транскрипт — вопрос в
  wiring SubagentStop у Agent-tool клиента; переведён в диагностический
  кандидат (слепое расширение регекса было бы Гудхартом).

Тесты: +9 кейсов (bypass_friction hint ×2, state_hardening P8 ×6, v147 careful
×2, init_contracts s5, no_bare_python3 ужесточён). `run-all` fails:none.

## [1.83.0] - 2026-07-11

**«Дорога к 5/5»: закрытие вычетов аудита Harness Engineering (RETRO-2026-07-11, принято пользователем)**:

- **U1 (Инструменты, P2)**: `itd_py.sh` переехал в `skills/_shared/` и раскатан
  на ВСЕ bash-сниппеты скиллов с голым `python3` (18 файлов: /goal, /kickstart,
  /session-save, /handoff, /review, /adopt и др. — на Windows Git Bash они
  ломались о WindowsApps-шим); осознанные исключения помечены `win-ok`
  (fallback-цепочки, probes, команды окружения пользователя). Новый positional-
  гейт `tests/verify_no_bare_python3.py` (fenced bash/sh-блоки skills/**/*.md)
  + правило в `skills/_shared/helpers.md` §12.
- **U2 (Обратная связь, P3)**: VCR>1 невозможен — retro-скан выровнен с
  `itd_metrics.py` (union verified⊆activated), потерянные активации репортятся
  отдельным фактом «Аномалия учёта» (live: OneOfS 16/13=1.231, юниты U-2..U-5);
  `itd_goal_verify.py` бэкфиллит отсутствующее activation-событие ДО verified.
- **U3 (Обратная связь, P5)**: `ENV_PROBE_RE` в `completion_lib.py` — проба
  окружения (`python -c "import X"`, голый import) не классифицируется как
  сигнал слоя (live-FP: ModuleNotFoundError пробы pytest = FAILED test_run).
- **U4 (Обратная связь, P9)**: M-C12 не сканирует `docs/retros/` (FP ×2:
  «N субагентов» в ретро — счётчик прогонов эксперимента, не ростера агентов).
- **U5 (Модель)**: 29-й хук `model-policy.sh` (PreToolUse Task|Agent, advisory)
  — хинт при спавне субагента с моделью СЛАБЕЕ frontmatter (risk-tier ⇒ model,
  G-003, теперь и в runtime, не только в CI); `cost-tracker.sh` атрибуцирует
  РЕАЛЬНЫЕ subagent-токены per agent(model) (`by_agent`), retro-скан показывает
  топ. Taxonomy 10 hard / 19 soft; все счётчики и карта §8.1/§8.2 обновлены.
- Новые гейты зарегистрированы в `tests/run-all.sh` и meta-review.yml
  (verify_no_bare_python3, verify_model_policy_hint); verify_cost_tracker,
  verify_retro_scan, verify_goal_tools, verify_init_contracts расширены
  кейсами. Локально: `run-all` fails:none.

## [1.82.0] - 2026-07-11

**Кросс-платформенный python-резолвер для inline-сниппетов скиллов + RETRO-2026-07-11 (упражнения Harness Engineering)**:

- **`skills/retro/scripts/itd_py.sh`** — запускатель python-скриптов для сниппетов
  (`sh itd_py.sh script.py …`; выбор: `$ITD_WIN_PYTHON` → python вне WindowsApps →
  `py -3` → `python3` fail loud; exec с кавычками — пути с пробелами вроде
  `C:/Program Files/...` безопасны, major-находка ревью #154; без аргументов —
  диагностика выбора).
  Live-инцидент 2026-07-11: канонический Step 1 `/retro` (`python3 …`) на
  Windows Git Bash уходил в WindowsApps-шим и печатал мусор вместо скана.
  Голый `python3` остаётся в 18 skill-файлах — расширение резолвера на них
  занесено в бэклог (P2 ретро).
- **/retro SKILL.md**: сниппеты Step 1/1b через резолвер + Troubleshooting-пункт
  «на Windows скан печатает мусор».
- **`docs/retros/RETRO-2026-07-11.md`** — упражнения Harness Engineering:
  аудит по пятёрке компонентов (итог 4.3/5; слабейшее — инструменты/среда),
  абляция C0–C3 при фиксированной модели (полный харнес 10/10, ценность
  харнеса — в хвостах и длинных горизонтах), affordance-анализ OneOfS
  (Gulf of Execution: нет read-only SQL-канала к прод-БД; Gulf of Evaluation:
  L2-паттерны не знают класс отчётных шаблонов), предложения P1–P7.

Проверено: WSL → `/usr/bin/python3` (поведение прежнее); Windows → `py -3`,
скан печатает полный отчёт. Тесты: `run-all` fails:none.

## [1.81.0] - 2026-07-11

**Follow-up финальной ACID-пересдачи (кандидаты (а)+(б)) — путь к 9.0+**:

- **(а) Удаление леджера — deny-достойно**: `rm`/`del`/`Remove-Item` с явным
  путём леджера ИЛИ самого каталога `.itd-memory` — hard-гейт при чужом
  свежем локе (топ-пробел пересдачи: раньше проходило молча). Плюс дыры
  soft-детекта с FP~0: `perl -i`, `sponge`, `install`, `rsync`,
  `Copy-Item`/`New-Item`, запуск скриптов (`python x.py`/`node x.js`),
  rm-класс; `git stash`/`git clean` — в GIT_REWRITE_RE (безусловная
  ревалидация). Исчезнувший после rm-класса STATE.json теперь красная
  пометка (раньше отсутствующий файл молча пропускался; guard по классу
  команды — проект без STATE.json не шумит).
- **(б) Heartbeat на shell-каналах**: чисто Bash/PowerShell-сессия больше не
  протухает свой `.active-session.lock` за 10 минут (вторая сессия могла
  легитимно забрать single-writer посреди работы первой). Внутренний
  rate-limit 60с держит IO ~нулевым.
- Тесты: +7 → verify_state_hardening 72/72 WSL.

## [1.80.1] - 2026-07-11

**Последняя минорка RUNBOOK-кандидатов** (мандат):

- **Bound на events.jsonl в реконсиляции**: `_last_unit_events` читает не
  больше хвоста `EVENTS_TAIL_BYTES` (512KB) — очень большой журнал +
  hook-timeout 5с раньше молча скипал бы валидацию целиком. Хвост —
  безопасная деградация: «последнее решение по юниту» tail-biased по
  построению, а юнит со всеми событиями старше окна выглядит как «нет
  события» → это WARNING-ветка (absence), не ложный fail.
- **`.gitignore`**: `.itd-memory/` и `tests/fixtures/*/output/` —
  dogfood-артефакты больше не шумят в git status (minor ревью v1.78.1).
- Тесты: +2 (свежее решение в хвосте огромного журнала реконсилируется;
  проход ограничен по времени) — verify_state_hardening 65/65.
  Список RUNBOOK-кандидатов пуст.

## [1.80.0] - 2026-07-10

**Два последних RUNBOOK-кандидата state-хардeнинга закрыты** (мандат):

- **git-перезапись леджера**: `git checkout/restore` с ЯВНЫМ путём
  `.itd-memory/STATE.json|GOAL*.json` — hard-гейт при чужом свежем локе
  (намеренная перезапись файла старой версией = та же гонка писателей);
  `git checkout <ветка>` / `reset --hard` БЕЗ пути леджера сознательно НЕ
  гейтятся hard'ом (false-deny на обычном переключении веток дороже) — их
  накрывает soft-нога с БЕЗУСЛОВНЫМ триггером `GIT_REWRITE_RE`: любая
  git-перезапись рабочего дерева перевалидирует леджеры, где протухание
  относительно events.jsonl ловит реконсиляция (git-откат даёт валидный по
  схеме, но устаревший леджер). Important ревью релиза: первая версия вешала
  git-токены в co-occurrence-регэксп — нога была мертва для голого checkout
  (путь леджера в команде не упоминается); исправлено на безусловный триггер
  + 2 регресс-теста (bare checkout → FAILED; git status/log → тишина).
- **POSIX flock симметризован с msvcrt**: `LOCK_EX|LOCK_NB` с bounded-
  ретраями (~2с) вместо блокирующего `LOCK_EX` — под экстремальной
  контенцией блокирующий лок держал хук дольше hook-timeout 5с (харнес
  убивал mid-write, сигнал терялся молча).
- Тесты: +5 (git-deny явного пути / allow переключения ветки / soft-детект
  git restore; held-lock → False за <4с, POSIX-only) —
  verify_state_hardening 61/61 WSL, 56 актуальных на Windows cp1251.

## [1.79.1] - 2026-07-10

**Дрифт-гард `tests/run-all.sh` ↔ workflow-файлы** (кандидат из
RELEASE_RUNBOOK, мандат пользователя): зеркало «прогнать всё локально»,
синхронизируемое руками, протухает молча — тест добавили в CI, а локальный
«DONE fails:none» перестал означать зелёный CI.

- `tests/verify_runall_drift.py`: каждая verify-проверка из обоих workflow
  обязана присутствовать в run-all.sh (строго CI ⊆ run-all; обратное —
  «локально строже» — лишь репортится). Anti-rot: минимальные счётчики
  распарсенного зашиты assert'ами (пустой парс = false-green); самореференс —
  гард требует собственной регистрации в CI и в run-all.
- Гард окупился первым же прогоном: нашёл ОБРАТНЫЙ дрейф — 4 проверки были
  local-only и не гонялись в CI вовсе (`verify_gate_taxonomy`,
  `verify_harness_map_fixtures` (G-003!), `verify_completion_gate`,
  `verify_completion_ledger`) — добавлены в meta-review workflow.

## [1.79.0] - 2026-07-10

**Cold-start гэпы закрыты** (упражнение «5 вопросов новичка»: свежий агент
без контекста отвечал по репо на «что это/как устроено/как запускать»
уверенно, на «как проверять» и «каков прогресс» — по крохам):

- **`tests/run-all.sh`** — одна команда «прогнать всё локально» (зеркалит
  оба CI-workflow; `--quick` — быстрый статический костяк). До этого полный
  набор проверок жил только внутри `.github/workflows/*.yml`, а «локальный
  минимум» из docs/CI.md (2 команды из ~22) не гарантировал зелёный CI —
  docs/CI.md теперь указывает на раннер.
- **`docs/RELEASE_RUNBOOK.md`** — экстернализация процедуры релиза и её
  граблей из session-memory оператора (свежий main перед бампом версии —
  урок коллизии v1.77.0; ревью-финалы и resume при обрыве; sed/backticks
  через двойной шелл; ASCII-safe вывод хуков; Store-заглушка python;
  munging раскладки ~/.claude/projects; раскатка на оба инсталла; открытые
  кандидаты след. релизов). Снижает knowledge visibility gap — знания,
  нужные для разработки методологии, теперь в репо.
- **Указатели прогресса**: README — «текущий прогресс = CHANGELOG.md,
  roadmap-файлы исторические»; баннер в `ROADMAP_v1.21.md` (последний
  roadmap датирован апрелем при фактической v1.78.1 — новичок считал его
  актуальным статусом).

## [1.78.1] - 2026-07-10

**Follow-up'ы фокусной пересдачи оси I** (оба minor-finding'а закрыты):

- **PowerShell-tool = тот же канал мутаций**: state-guard получил отдельные
  matcher-блоки `PowerShell` на PreToolUse (hard-гейт цели записи, включая
  `Set-Content`/`Out-File`/`Add-Content`) и PostToolUse (soft-ревалидация) —
  в `sync-to-active.sh` и `/adopt`-шаблоне; в хуке `SHELL_TOOLS = {Bash,
  PowerShell}`. До этого Windows-инсталл с PowerShell-tool не гейтился вовсе.
- **Интерпретаторные записи** (`python -c` / `py -c` / `node -e`) добавлены в
  soft-детект `BASH_MUTATION_RE` — co-occurrence с путём леджера уже
  требуется, цена FP ~0 (молчит на валидном леджере). Hard-гейт для них
  сознательно не строится (парсить код интерпретатора — вне best-effort).
- Тесты: +4 проверки (PowerShell deny/read-allow; python -c детект /
  python без -c молчит) — verify_state_hardening 56/56.

## [1.78.0] - 2026-07-10

**Bash-канал гейтится pre-write — Isolation до 9** (important-finding финальной
пересдачи ACID v1.76.x: параллельная сессия через `jq … > STATE.json` всё ещё
была last-writer-wins — deny-гейт покрывал только Write/Edit-инструменты).

- `state-guard.sh` зарегистрирован и на **PreToolUse Bash** (4-я регистрация):
  команда, где леджер `.itd-memory/STATE.json|GOAL*.json` — ЦЕЛЬ записи, при
  чужом свежем owned-локе отклоняется тем же решением (общий deny-бюджет ≤2
  per сессия+проект, ownerless не гейтится, ITD_STATE_GUARD=0).
- Регэксп гейта **target-anchored** (редирект/`tee`/`sed -i`/`mv`/`cp`/
  `truncate`/`dd of=`/PowerShell `Set-Content` прямо В леджер) — широкое
  со-вхождение (`git diff .itd-memory/STATE.json > out.txt`) сознательно НЕ
  гейтится: цена false-deny у hard-гейта выше, такие случаи остаются на
  soft-ревалидации PostToolUse-ноги (v1.76.0).
- Тесты: +4 проверки (deny редиректа в леджер и `sed -i`; allow со-вхождения
  и read-only pipe) — verify_state_hardening 50/50 (WSL + Windows cp1251).

## [1.77.0] - 2026-07-10

**Declared-source read contract: субагент, не прочитавший заявленный источник,
отвечает READ_FAILED — молчаливая подмена источника запрещена** (кандидат №2
ретро 2026-07-10, реализован по явному мандату пользователя; evidence: в
замере lost-in-the-middle 6 из 21 субагентов, не сумев прочитать заявленный
файл инструкций, молча выполнили задачу из других источников без критического
правила; с отказ-инструкцией в промпте — 0 подмен на 6 прогонов).

- `skills/_shared/helpers.md` §11 — двусторонний контракт: subagent-side
  (обязательный источник не читается → `READ_FAILED: <путь>` + «что пробовал»,
  задачу из других источников не выполнять); dispatcher-side (помечать
  обязательность источника, диктовать отказ дословно, на READ_FAILED — чинить
  доступ и перезапускать, ответ из незаявленных источников не принимать).
- §8 (Delegation Intent Template) — кросс-ссылка «Declared-source contract».
- Новый doc-contract тест `tests/verify_source_read_contract.py` (8 проверок),
  прописан в CI (meta-review workflow).
- Номер релиза v1.77.0: v1.75–v1.76 заняты параллельной линией ACID-хардeнинга
  (#143–#145), вышедшей тем же днём.

## [1.76.1] - 2026-07-10

**Hotfix: локатор memory-dir не находил реальную раскладку ~/.claude/projects**
— live-смоук deny-гейта v1.76.0 на боевом Windows-инсталле показал allow там,
где должен быть deny. Root cause НЕ в гейте: `find_project_memory_dir`
(pre-flight-check.sh и его копия в state-guard.sh) строил имя каталога только
заменой `/`→`-`, а реальный munging Claude Code заменяет КАЖДЫЙ не-alnum
символ (`C:\Users\Дмитрий\AI\OneOfS_tmp` → `C--Users---------AI-OneOfS-tmp`;
подчёркивания и не-ASCII включительно, на Windows без ведущего дефиса). На
таких путях молча превращались в no-op: memory-index и parallel-session
warning pre-flight (баг ПРЕ-существующий, задолго до v1.75), heartbeat лока и
single-writer гейт state-guard.

- Оба локатора: кандидаты = {настоящий munging, легаси-вариант} + suffix-
  фолбэк теперь матчит и munged-суффиксы; ведущий дефис больше не обязателен
  (Windows-имена начинаются с буквы диска).
- Регресс-тест: гейт доводится до deny через раскладку с underscore-путём и
  настоящим munging (46-я проверка verify_state_hardening).

## [1.76.0] - 2026-07-10

**ACID до 9: остаточные капы пересдачи аудита закрыты** — по findings
адверсариальной переоценки v1.75.0 (A 7.5 / C 8 / I 6.5 / D 8, итог ~7.6).

- **A: durable rename** — `atomic_write_text` теперь fsync'ает данные ПЕРЕД
  `os.replace` (без этого rename мог пережить данные при крэше ядра/питания —
  пустой-но-существующий файл) + dir-fsync на POSIX; tmp-сирота убирается и
  при падении самой записи, не только replace. То же в чекпоинте
  `crash-recovery.sh`.
- **C: реконсиляция GOAL.json ↔ events.jsonl** — та же семантика, что для
  STATE (v1.75.0), per unit долгой цели: открытый юнит при записанном
  terminal-событии = ERROR, verified без события = WARNING (cap 3). Один
  проход по журналу (`_last_unit_events`).
- **C: Bash-bypass закрыт** — `state-guard.sh` зарегистрирован и на
  PostToolUse Bash: мутация леджера в обход Write/Edit (редиректы, `sed -i`,
  `tee`, `jq`, `mv`/`cp`, PowerShell `Set-Content`) детектится по команде →
  леджеры проекта перевалидируются, нарушение — та же красная пометка.
- **I: single-writer гейт леджера (state-guard стал 10-м HARD-гейтом)** —
  PreToolUse на Write|Edit|MultiEdit|NotebookEdit: запись
  `.itd-memory/STATE.json`/`GOAL*.json` при СВЕЖЕМ `.active-session.lock`
  ДРУГОЙ сессии отклоняется (`permissionDecision: "deny"`, exit 2) — ровно
  класс инцидента NeuroExpert 2026-04-11 (last-writer-wins). ≤2 deny на
  сессию, третья попытка проходит с warning (escape-hatch как у
  narration-final); ownerless-локи (легаси /session-save) не гейтятся —
  атрибуция невозможна. Таксономия: 10 hard / 18 soft из 28;
  behavioural-proof добавлен в грид G-003 (`verify_harness_map_fixtures`).
- **I: изоляция деградирует наблюдаемо** — отказ взятия лока
  `signals.jsonl.lock` логируется в errors.log (once per process), а
  Windows-путь лока переведён на неблокирующий `LK_NBLCK` с bounded-ретраями
  (~2с): блокирующий `LK_LOCK` ждал до 10с — дольше hook-timeout 5с, под
  контенцией харнес убивал бы хук mid-write.
- **D: у errors.log появился читатель** — `pre-flight-check.sh` всплывает
  непустые persist-error-логи (`.claude/completion/errors.log` проекта +
  `<tmp>/claude-checkpoint-errors.log`) на старте промпта: счётчик +
  последняя запись, rate-limited 4ч. v1.75.0 сделал сбои персиста
  наблюдаемыми — v1.76.0 делает их УВИДЕННЫМИ (human-in-loop работает,
  только если сигнал доходит).
- Тесты: `verify_state_hardening.py` 27→45 проверок (deny-proof гейта —
  реальный subprocess до exit 2, auto-allow третьей попытки, ownerless-,
  stale- и no-memdir-кейсы, Bash-детект, GOAL-реконсиляция, fsync-сирота,
  наблюдаемый отказ лока, rate-limit потребителя errors.log).
- По ревью релиза: deny-бюджет гейта скоуплен per (сессия, проект) — не
  утекает между проектами одной сессии; вывод хука `ensure_ascii=True`
  (cp1251-пайп Windows глотал эмодзи и превращал warn-allow в молчание);
  латентный тест G-005 `verify_hook_table_completeness.py` (протух ещё на
  v1.75.0: заголовок §8.1 «(27)») починен вместе с квадрантами §8.1/§8.2
  карты и добавлен в meta-review CI.

## [1.75.0] - 2026-07-10

**ACID-хардeнинг управления состоянием** — по итогам адверсариального
ACID-аудита (A=4, C=6.5, I=3.5, D=7): пять самых дешёвых фиксов, закрывающих
все наблюдённые классы инцидентов персиста без покупки полной транзакционности
(дизайн остаётся single-writer + human-in-loop + дешёвый откат из git).

- **Fix #1 (Atomicity): атомарные записи** — `atomic_write_text` (tmp +
  `os.replace`) в `hooks/completion_lib.py`; применено к `write_verdict`
  (раньше голый `write_text` — обрыв mid-write = усечённый вердикт), к триму
  `signals.jsonl` и к чекпоинту `crash-recovery.sh`. Читатель больше никогда
  не видит полуфайл.
- **Fix #2 (Isolation): лок на append+trim леджера** — `append_signal`
  сериализуется через ВЫДЕЛЕННЫЙ lock-файл `signals.jsonl.lock` (fcntl на
  POSIX / msvcrt на Windows, best-effort). Лок именно на отдельном файле:
  атомарный трим подменяет inode леджера, и лок на самом леджере не пережил
  бы `os.replace` — конкурентный писатель дописывал бы в unlinked-файл
  (ровно та cross-session гонка потери строк, что нашёл аудит).
- **Fix #3 (Durability): сбои персиста наблюдаемы** — `log_persist_error`
  пишет в bounded `.claude/completion/errors.log` (64KB, хвост);
  `except: pass` в триме/вердикте заменён на логирование; crash-recovery
  логирует в `<tmp>/claude-checkpoint-errors.log`. Вся recovery-стратегия
  human-in-loop — невидимый сбой персиста был единственным классом, который
  человек не мог починить в принципе.
- **Fix #4 (Consistency+Isolation): новый хук `state-guard.sh`** (PostToolUse
  на Write|Edit|MultiEdit|NotebookEdit, 28-й хук, soft): (а) правка
  `.itd-memory/STATE.json`/`GOAL*.json` валидируется НЕМЕДЛЕННО (та же
  логика, что CLI) — нарушение возвращается красной пометкой
  FAILED/WHY/FIX через additionalContext; consistency сдвигается из «на
  старте следующей сессии» в «после каждой мутации»; (б) heartbeat
  `.active-session.lock` на каждом Write/Edit — лок больше не протухает
  между `/session-save` (инцидент NeuroExpert 2026-04-11: параллельные
  сессии не видели друг друга); ЧУЖОЙ свежий лок не перетирается.
  Отключение: `ITD_STATE_GUARD=0`. Зарегистрирован в `sync-to-active.sh` и
  в `/adopt`-шаблоне project-settings.
- **Fix #5 (Consistency): инвариант реконсиляции STATE ↔ events.jsonl** —
  валидатор проверяет, что хвост STATE не ПРОТИВОРЕЧИТ хвосту журнала:
  активный unit при уже записанном `verified`-событии = ERROR (fail-closed);
  отсутствие события (легаси-проекты до конвенции events) = WARNING, не fail.
  Заявленный «event sourcing» стал проверяемым, а не декларативным.
- Рефактор: логика валидации вынесена в `hooks/validate_state_core.py`
  (единый источник для CLI и хука, схемы резолвятся из repo- и
  install-раскладки с fallback'ом на встроенный список — best-effort
  invariant); `scripts/validate_state.py` — тонкий CLI-враппер, контракт
  сохранён (ERROR/OK, exit 0/1; новое: строки `WARNING:` без влияния на код
  выхода).
- Тесты: `tests/verify_state_hardening.py` (27 проверок, stdlib,
  кросс-платформенный) в обоих workflow (meta-review + windows-verify);
  taxonomy обновлена (9 hard / 19 soft = 28), счётчики хуков — во всех
  доках/манифестах.

## [1.74.0] - 2026-07-10

**Retro 2026-07-10: best-effort invariant — rationale в topic-док, entry ещё
легче** (кандидат №1 ретро `docs/retros/RETRO-2026-07-10.md`; два внешних
сигнала: SNR-аудит — секция релевантна 1 из 5 типов задач, A/B-замер сжатия —
20/20 паритет поведения; третий замер (6/21 тихих продолжений при недоступном
файле) зафиксировал правило «поведенчески-критичное остаётся в entry»).

- Секция «Harness-native features» в `docs/templates/global-claude-md.md`
  ужата 19→17 строк с указателем на новый topic-док
  `docs/harness-best-effort.md` (полный контракт + rationale + связи с
  FEATURE_LEDGER/completion-gate). Сжатие скромнее плана — и это находка
  ретро: doc-contract тесты (`verify_fable_snippets`,
  `verify_feature_ledger_completeness`) машинно парсят из секции
  frontier-перечень фич и контрактные фразы — секция почти целиком
  поведенческий контракт, а не rationale; шум для не-методологических задач
  ограничен её плотностью, дальше не сжимается без потери контракта.
  Entry-шаблон 150→148 строк.
- Реестр инструкций: запись пересмотрена (notes + свежий `review_by`
  2027-01-10) — первый живой цикл lifecycle-механики v1.73.0.
- Ретро-отчёт `docs/retros/RETRO-2026-07-10.md` (скан as-is + замеры +
  таблица кандидатов); кандидат №2 (агентный контракт «не читается заявленный
  источник инструкций → скажи явно, не продолжай молча») — в бэклог до
  второго сигнала.

## [1.73.1] - 2026-07-10

**Hotfix раскатки на Windows-инсталл: sync больше не затирает python-wrapper
регистрацию хуков POSIX-формой** (живой инцидент 2026-07-10 при раскатке
v1.73.0: `CLAUDE_HOME=/mnt/c/... bash scripts/sync-to-active.sh` из WSL
резолвил target OS по `uname` хоста → 'unix' → записал голые
`~/.claude/hooks/*.sh` в Windows settings.json → Git-Bash исполнял
python-телые хуки как shell (syntax error, exit 2) → PreToolUse-хук с
matcher'ом `*` блокировал КАЖДЫЙ вызов инструмента, а сломанный Stop-хук —
завершение хода; восстановление — ручной откат settings.json из .bak).

- **Авто-детект Windows-таргета по ПУТИ** (`scripts/sync-to-active.sh`):
  target OS — свойство целевого пути, не хоста; `CLAUDE_HOME` на
  `/mnt/<диск>/…` или `<диск>:/…` → `windows` без ручного `ITD_TARGET_OS`
  (env-переменная остаётся override'ом).
- **Интерпретатор — из существующей wrapper-регистрации**: до PATH-discovery
  python.exe добывается из текущего settings.json таргета (на WSL-хосте
  `command -v python` находит Linux-интерпретатор — обёртка из него так же
  сломана; Linux-пути теперь отбрасываются с предупреждением).
- **Fail-closed guard от даунгрейда**: если существующая регистрация —
  Windows-wrapper, а target OS резолвнулся не-windows, Step 5 ОТКАЗЫВАЕТСЯ
  перезаписывать hooks (ошибка с инструкцией оператору) — рабочая
  регистрация не трогается ни при какой ошибке резолюции.
- Верификация вживую: repro-команда инцидента теперь даёт «hooks already
  up-to-date» (wrapper-форма, интерпретатор harvested); guard-тест —
  REFUSING + settings байт-в-байт нетронуты; WSL-инсталл — без
  false-positive.

## [1.73.0] - 2026-07-10

**«Принцип чемодана» доведён до конца: entry-файлы — роутинговые, инструкции —
с lifecycle, проза не дублирует код** (реализация 4 фиксов аудита «suitcase»
2026-07-10: методология держала СВОЙ entry-файл коротким, но не экспортировала
принцип на проектные CLAUDE.md; lifecycle без срока пересмотра; Completion Gate
жил и в прозе, и в хуках; толстые скиллы грузились целиком).

- **/adopt Step 3.8 — роутинговый слой для проектных `CLAUDE.md`** (главный
  гэп: реальный кейс — проект с ~1500-строчным CLAUDE.md, грузящимся каждый
  ход). Файл > 300 строк → предлагается сплит: entry ≤200 строк (обзор,
  quick start, ≤15 жёстких ограничений, индекс тем со строками-условиями
  «когда читать») + тематические `docs/claude/*.md` по 50–150 строк. Гайд и
  шаблон — `skills/adopt/references/claude-md-router.md`. Approval-gated
  (единственный шаг /adopt, реорганизующий пользовательский контент: перенос
  дословный, удаления — видимым списком, без явного «да» — только план);
  идемпотентность — маркер `<!-- itd:claude-router -->`.
- **Lifecycle-реестр стоячих инструкций** — `docs/instruction-registry.json`:
  у каждой секции глобального CLAUDE.md-блока источник (`since`), исполнитель
  (`enforced_by` — код, который правило enforce'ит; `[]` = prose-only
  watch-list) и срок пересмотра (`review_by`: vX.Y или ISO-дата). Метаданные —
  вне entry-файла (entry не тяжелеет). `itd_retro_scan.py` сверяет реестр с
  шаблоном на каждом /retro: незарегистрированные секции, осиротевшие записи,
  битые enforced_by-пути, просроченные review_by — каждая строка = готовый
  PROPOSAL-кандидат «перечитать против кода → обновить или удалить»
  (инструкции управляются как зависимости). +4 функциональных теста
  (`tests/verify_retro_scan.py`, 18/18).
- **Дедуп прозы и кода Completion Gate**: секция в
  `docs/templates/global-claude-md.md` сжата 60→18 строк (остались правила,
  которые агент обязан соблюдать: лестница L1→L2→L3, «тесты зелёные — иначе не
  done», bypass, деградация); полная механика (сигналы, WHY+FIX, FIX_HINTS,
  env-выключатели) — в новый topic-док `docs/completion-gate.md`. Entry-шаблон
  191→150 строк — внутри коридора 50–200.
- **Progressive disclosure в толстых скиллах**: session-save 492→407
  (lockfile-формат и wrap-up-скрипты → `references/lockfile-format.md`,
  `references/wrapup-scripts.md`), review 461→396 (обоснования runner'а,
  контракт report-файла, belt-and-suspenders, rationale маркера →
  `references/runner-and-recovery.md`). Правила остались в SKILL.md,
  приложения читаются по требованию.

## [1.72.0] - 2026-07-09

**Ревью-прогоны переживают обрыв харнеса: report-файл + класс «finish-line
interruption»** (реализация фикс-кандидатов 1–2 из
`ROOT_CAUSE-empty-review-finals-2026-07-09`: три длинных (9–15 мин) ревью за
день были убиты mid-stream и отрапортованы «completed» с пустым финалом;
готовый отчёт жил только в транскрипте).

- **Finish-line interruption ≠ true stall** (helpers §9 + `/review` Step 2.7):
  пустой/обрубленный финал после долгого «completed»-прогона со здоровой
  tool-цепочкой — обрыв на финальной миле, результат уже вычислен в контексте
  субагента. Первый ход — ОДИН дешёвый resume re-ping (3/3 живых
  восстановления 2026-07-09, одно с нулём доп. tool-вызовов); правило §9
  «fresh narrow, never resume» остаётся для TRUE stalls (no-progress /
  autocompact) — прежнее evidence (§8: resume 600s vs fresh 84s) относится
  именно к ним.
- **Report-файл ревью** (`agents/code-reviewer.md` + `/review` dispatch):
  диспетчер передаёт путь `claude-review-<slug>.md` в thin-промпте; ревьюер
  создаёт файл в начале, дописывает findings после каждой dimension и кладёт
  вердикт+```json-блок в файл до финального сообщения (финал — прежний полный
  deliverable + строка `Report file: <path>`). Убитый прогон оставляет каждую
  завершённую dimension на диске: file = contract, final message = transport
  (best-effort invariant). `Write` добавлен в allowed-tools агента с жёстким
  ограничением «писать можно ТОЛЬКО report-файл» — само ревью остаётся
  read-only.
- Порядок восстановления при обрыве: report-файл → Step 2.7 re-ping → fresh
  narrow (§9).
- Гейт: `tests/verify_review_report_file.py` (13 checks) — в обеих CI-ногах.
- Версии: review 1.17.0.

---

## [1.71.1] - 2026-07-09

**Follow-up по ретро-ревью #136** (ревью-агент перед мержем v1.70.0 умер, не
выдав отчёта; ретроспективное ревью: Critical 0, Important 3, Minor 1 — все
закрыты этим патчем).

- `/handoff` Step 3 + `/session-save` Step 3.3: вызов `itd_progress.py` — с
  интерпретаторным фолбэком `python3 || python || py -3 || true` (на Windows
  `python3` бывает Store-заглушкой — класс, уже описанный в
  `sync-to-active.sh`); ни одного интерпретатора → шаг тихо пропускается,
  опционально `ITD_WIN_PYTHON`.
- `itd_progress.py`: из тела `PROGRESS.md` убран wall-clock-таймстамп —
  перегенерация без содержательных изменений больше не даёт git-diff; в шапке
  вью и в `docs/CONTRACTS.md` зафиксировано: `PROGRESS.md` — кандидат в
  `.gitignore` целевого проекта (derived).
- `/obsidian-export`: `.itd/DECISIONS.md` добавлен в Source-артефакты —
  vault-заметка `DECISIONS.md` теперь прямая производная канонического
  журнала, а не пересинтез из session-файлов.
- `docs/CONTRACTS.md`: строка `itd_progress.py` явно помечена «utility, NOT
  counted in the 14 contract templates» (граница «14» была неоднозначна).
- Версии: handoff 1.22.1, session-save 1.10.1, obsidian-export 1.21.1.

---

## [1.71.0] - 2026-07-09

**Retro 2026-07-09 (amnesia-lab, 14 сессий-агентов): закрыты оба замеренных
потолка v1.70.0.** Отчёт — `docs/retros/RETRO-2026-07-09.md`; все три
предложения подкреплены боевыми инцидентами эксперимента.

- **P1 — cost-tracker: леджер per-агент** (боевой инцидент: субагент с ~183k
  собственных токенов остановлен HARD-ASK «2,0M — 100% потолка», накрученным
  параллельными соседями через общий day-anchor): ключ леджера теперь
  `payload["session_id"]` (стабилен per агент; тот же класс фикса, что
  v1.69.1) → env `CLAUDE_SESSION_ID` → day-anchor (fallback сохранён). Имя
  файла санитайзится.
- **P2 — датчик 60% контекста для /handoff** (частичный флип абстенции F-18;
  внешний сигнал — единственная long-session стратегия эксперимента прервана
  лимитом харнеса на полпути): cost-tracker оценивает занятость окна по
  размеру транскрипта (`transcript_path`, байты/4) и при
  ≥`ITD_CONTEXT_HANDOFF_PCT` (default 60%) от `ITD_CONTEXT_WINDOW_TOKENS`
  (default 200k) один раз на леджер инжектит hint «подготовь /handoff /
  session-save до авто-компакции». Best-effort ТРАНСПОРТ текстового правила
  v1.70.0 (контракт остаётся вендор-нейтральным текстом; сенсор исчез —
  ничего не ломается). Ограничение документировано: после первой компакции
  оценка завышает — задача сенсора именно первый подход к 60%.
- **P3 — микро-путь артефактов непрерывности** (замер: +2–8 вызовов и +5–15k
  токенов/сессию не окупаются на микро-задачах — recovery-разрыв Σ14 vs Σ9
  вызовов на 3-файловом проекте): `/session-save` Steps 3.2/3.3 пропускаются
  для micro-сессий (≤1–2 юнита, нет durable-решений; критерий helpers §6);
  есть durable-решение — журнал обязателен независимо от размера.
- Регрессия: `tests/verify_cost_tracker.py` (10 checks; t1/t2 red на
  pre-v1.71.0 коде — проверено против HEAD-версии хука) — в CI.
- Версии: session-save 1.10.0; hooks/cost-tracker.sh v1.71.0.

---

## [1.70.0] - 2026-07-09

**«Инженер с амнезией»: закрыты 3 гэпа непрерывности** (внешняя оценка подхода
PROGRESS.md / DECISIONS.md / git-чекпоинты / clock-in-out дала 9/10 — минус
балл ровно за эти три пункта).

- **DECISIONS.md — первоклассный контракт** (гэп: решения были размазаны по
  session-файлам памяти и ADR, единого журнала «какое/почему/когда» не было):
  - новый 14-й шаблон `docs/templates/itd/DECISIONS.md` — append-only журнал
    решений (формат: решение / Почему / Отвергнуто / Ограничение / Ссылки);
    отмена решения = новая запись, старые не переписываются;
  - `/adopt` Step 3.5 копирует его в `.itd/` вместе с остальными контрактами;
  - `/session-save` Step 3.2 дописывает durable-решения сессии в журнал
    (session-файл ссылается, а не дублирует); нет `.itd/` — шаг молчит (opt-in);
  - `/handoff` Step 1 читает журнал как источник поля 4 «Финальные решения».
- **PROGRESS view — единая glance-точка** (гэп: роль PROGRESS.md делили
  STATE.json / GOAL.json / MEMORY.md / session-файлы — машиночитаемо, но
  человеку «одним взглядом» не охватить):
  - новый `docs/templates/itd/itd_progress.py` — рендерит
    `.itd-memory/PROGRESS.md` из STATE.json + GOAL.json + events.jsonl + git +
    DECISIONS.md (+ вердикт Completion Gate, если есть); per-section
    деградация на битых/отсутствующих входах, всегда exit 0 (best-effort);
  - в шапке вью и в скиллах явно: PROGRESS.md — DERIVED, канон остаётся в
    JSON, гейты на вью не завязываются (best-effort invariant соблюдён);
  - перегенерация: `/session-save` Step 3.3 и `/handoff` Step 3.
- **Порог контекста 60% → `/handoff` кодифицирован** (гэп: момент вызова
  оставался на суждении агента): задача требует >60% окна → handoff
  закладывается с самого старта; израсходовано ~60% и конец не виден →
  `HANDOFF.md` пишется немедленно, до авто-компакции. Правило — в
  `/handoff` «Когда вызывать», в `references/handoff-checklist.md` и в
  global-claude-md блоке («Memory is the continuity backbone»).
- Версии скиллов: adopt 1.23.0, handoff 1.22.0, session-save 1.9.0.

---

## [1.69.1] - 2026-07-08

**Hotfix: checkpoint fragmentation on Windows — session id now comes from the
hook payload.** Found by the post-restart live smoke of v1.69.0: the phantom
banners' DEEPER root cause was not the missing SubagentStop leg alone.

- Root cause: `CLAUDE_SESSION_ID` is absent from the hook environment on
  Windows, so `session_id()` fell back to `pid{os.getppid()}` — which is
  UNSTABLE across hook invocations. A subagent's tool calls and its
  Stop/SubagentStop mark landed in DIFFERENT checkpoint files (369 fragments
  observed for one project); the clean mark missed, phantoms returned.
- Fix: `crash-recovery.sh` and `pre-flight-check.sh` prefer
  `payload["session_id"]` — Claude Code puts it in the stdin JSON of every
  hook event — over the env var; the pid fallback remains last resort. One
  agent = one checkpoint file across PostToolUse/Stop/SubagentStop, and
  pre-flight's own-checkpoint exclusion uses the same key.
- Regression: `verify_init_contracts.py` t11 (suite 27 → 31 checks) — red on
  the old code exactly at "checkpoint keyed by payload session_id".

---

## [1.69.0] - 2026-07-08

**Fix: phantom "Crash recovery" banners from background subagents** — the one
remaining positive-ROI item from the init-audit close-out (found live by
exercise 2: ×5 phantom banners in a single session).

- Root cause: subagents write crash checkpoints too (PostToolUse fires in
  their context with their own session id), but they finish via
  **SubagentStop**, which the hook was not registered on — their checkpoints
  stayed `clean_exit: false` forever and pre-flight surfaced them to the MAIN
  session as crashes.
- Fix: `crash-recovery.sh` accepts SubagentStop as a clean-exit marker and
  `sync-to-active.sh` registers it on SubagentStop (now 3 hooks there). A
  subagent that dies mid-work still surfaces — that signal is real and kept.
- Regression: `verify_init_contracts.py` t10 (suite 24 → 27 checks) — the
  registration assertion was red on the old code, green now; the functional
  leg proves SubagentStop flips `clean_exit` and pre-flight stays silent.

---

## [1.68.1] - 2026-07-08

**Hotfix: init validator on Windows with non-ASCII repo paths.** Found by
actually running the init-audit exercises (exercise 1: fresh-session bootstrap
test) — the validator failed on a real Cyrillic-path repo
(`C:/Users/Дмитрий/…`) with `WinError 267`. Two defects of the same class:

- `itd_init_validate.py` `run()`: `text=True` without `encoding` decoded git's
  UTF-8 output with the Windows locale codepage — the repo root path turned to
  mojibake and the next `subprocess` got a nonexistent `cwd`. Fixed with
  explicit `encoding="utf-8", errors="replace"`.
- Both template utilities crashed with `UnicodeEncodeError` when printing
  `⚠`/Cyrillic marks to a legacy console (cp866/cp1252) — `sys.stdout`/`stderr`
  are now reconfigured to UTF-8 with `errors="replace"` (best-effort).
- Regression: `tests/verify_init_contracts.py` t9 runs the validator in a
  Cyrillic-named repo (suite now 24 checks); `windows-verify.yml` gains a step
  running the suite with **`PYTHONUTF8=0`** — the job-level UTF-8 env was
  masking exactly this bug class. The test harness's own subprocess reader
  fixed the same way.
- The new CI step immediately caught three more Windows defects of the same
  family (each fixed + covered):
  - `crash-recovery.sh` stored `os.getcwd()` verbatim — an 8.3 short path
    (`RUNNER~1`) never matched the consumer's resolved path, so the crash
    section silently failed to surface. Both sides now compare **resolved**
    paths; checkpoint file I/O got explicit UTF-8.
  - `pre-flight-check.sh` crashed with `UnicodeEncodeError` emitting Cyrillic
    advisories to a cp1252 console — stdout/stderr now reconfigured to UTF-8
    (production invokes hooks with `-X utf8`; this is the belt for CI/legacy).
  - `sync-to-active.sh` PYBIN discovery trusted `command -v python` — on
    Windows that can be the Microsoft Store STUB which prints "Python" and
    exits non-zero. Candidates (`ITD_WIN_PYTHON`, python3, python, py) are now
    validated by executing `-c "print(1)"`.
  - Test-side: Git-Bash bash.exe preferred over the System32 WSL stub when
    running the sync step on Windows.

---

## [1.68.0] - 2026-07-08

**Init-hardening round 2: the four residual gaps from the post-v1.67.0
re-audit (44/50), closed C1–C4.** Round 1 gave every init element an
executable sensor; this round moves the sensor TRIGGERS from skill prompts to
the harness where cheap, and fixes the one distribution gap found while
verifying the rollout.

- **C1 — init validator is now a completion-gate signal**
  (`hooks/completion_lib.py` TEST_RE): a run of `itd_init_validate.py`
  (path-prefixed forms included) classifies as a `test_run`/L2 signal — its
  exit 0 is a real test execution in a clean clone, so the commit veto sees
  it like any other test run. The `commit ≠ test` VCS guard still wins:
  `git commit -m itd_init_validate` is not a signal.
- **C2 — `--filled` check in the pre-flight hook**
  (`hooks/pre-flight-check.sh`): the 4-hourly `.itd/` advisory now also
  mirrors `check_contract_drift.py --filled` inline (placeholder prose /
  empty `commands[]` / broken JSON / missing key contract) — template-prose
  contracts surface at session start, not only when `/review` happens to
  run. Filledness is pure file reading, so unlike drift it does not require
  git.
- **C3 — plan-without-mirror detector** (`hooks/pre-flight-check.sh`):
  when `IMPLEMENTATION_PLAN.md` exists (root or `docs/`) but
  `.itd-memory/GOAL.json` does not, pre-flight says so once per 4h — a
  project resuming "from prose" is now visible instead of silent.
- **C4 — templates ship with sync installs** (`scripts/sync-to-active.sh`
  new Step 4/6, steps renumbered to /6): `docs/templates/{itd,itd-memory}`
  are mirrored to `~/.claude/templates/` — a sync-based install on a machine
  without the repo checkout (e.g. the Windows side) can now scaffold `.itd/`;
  `/adopt` Step 3.5 and `/kickstart` Phase 3 resolve `~/.claude/templates/itd/`
  as a fallback.
- **Tests/CI**: `tests/verify_init_contracts.py` extended 14 → 23 checks
  (classifier L2 + VCS guard, pre-flight red/green for C2+C3 on throwaway
  git projects, full `sync-to-active.sh` run into a fresh `CLAUDE_HOME`
  asserting bit-identical mirrored templates).

---

## [1.67.0] - 2026-07-08

**Init-hardening release: the five gaps from the 2026-07-08 initialization
audit (advisor + devils-advocate, scored 36/50), closed P1–P5.** The audit's
calibration lens — "a skill prompt is not enforcement" — drove every item:
each fix lands as an executable script/hook with a functional test
(`tests/verify_init_contracts.py`, wired into CI), not as more prose.

- **P1 — init validator, executable instead of self-asserted**
  (`docs/templates/itd/itd_init_validate.py`, new): clones the repo into an
  isolated temp dir (`git clone --local --no-hardlinks` — committed state
  only) and actually runs the bootstrap and test commands there, with
  WHY+FIX failure marks and the failed clone kept for inspection;
  `--selftest` exercises the positive and negative paths on a throwaway git
  repo. `/kickstart` Phase 3 Initialization Acceptance Checklist now requires
  the validator's exit 0 as the ONLY acceptable evidence for its first two
  boxes ("green in words" is gone); `/adopt` gains Step 3.7 — an advisory
  runnability check for legacy projects (a brownfield repo that cannot
  bootstrap from a clean clone is surfaced on day one, adoption not rolled
  back).
- **P2 — `/adopt` example test ("the pillar holds weight" for brownfield)**:
  new Step 3.6 — when the project has NO tests, offer to create ONE smoke
  test on a ZERO-dependency built-in runner (stdlib `unittest` / `node:test`
  / `go test` / `cargo test`) and actually run it; a red run is reported as
  the finding, never deleted to look green. No new dependencies ever — the
  non-scope carve-out is explicit; stacks without a built-in runner are
  skipped with a pointer to `/test`.
- **P3 — contract health: drift + filledness gate in `/review`**:
  `check_contract_drift.py` gains a `--filled` mode (template placeholders /
  empty `commands[]` => TMPL — a scaffold of template prose is decoration,
  not a contract; selftest extended, 11 cases). New Important rubric check
  **I10** (`references/review-checklist.md`, Important tier now 10 checks) +
  Stage A.5 in `/review` run both modes when `.itd/` exists, with a
  read-only Grep fallback for projects whose `.itd/` copy predates the flag.
  Complements the v1.65.0 pre-flight drift advisory — now the review gate
  sees it too, and emptiness (not just staleness) is finally detected.
- **P4 — unified verification substrate: `/kickstart` mirrors the plan into
  GOAL.json** (new Phase 3 step 7.5): one unit per IMPLEMENTATION_PLAN.md
  step (criterion = the step's acceptance criterion, verificationCommand =
  its verify command), validated by `scripts/validate_state.py` before the
  init checkpoint commit; Phase 4 drives each step through
  `itd_goal_verify.py` (`--activate` -> implement -> verify with evidence).
  Resumability and the WIP=1 + evidence-gated `verified` mechanics no longer
  depend on the entry point — kickstarted projects get the same
  machine-readable resume surface `/goal` projects had.
- **P5 — crash checkpoints are now consumed, not just written**
  (`hooks/crash-recovery.sh` + `hooks/pre-flight-check.sh`): the checkpoint
  records `cwd`; every significant tool call flips `clean_exit: false`, a
  Stop registration (added to `sync-to-active.sh`) flips it back to true on
  a normal turn end — so a checkpoint left `clean_exit: false` means "died
  mid-work". `pre-flight-check.sh` surfaces such a checkpoint ONCE to the
  next session in the same project (last tool calls + branch + "check git
  status before redoing work") and marks it consumed. Closes the
  "written but not automatically consumed" gap documented in the hook's own
  docstring since v1.19.2.
- **Tests/CI**: `tests/verify_init_contracts.py` (14 checks: both selftests,
  functional `--filled` red->green, the full crash-checkpoint pipe-test
  surface-once/consume/clean-stop, GOAL.json mirror shape vs
  `validate_state.py`) added to `meta-review.yml`.

---

## [1.66.0] - 2026-07-08

**Retro-2026-07-08 release: friction cut + tail-quality (P1–P4).** All four
candidates from `docs/retros/RETRO-2026-07-08.md` (evidence: telemetry scan —
864 SKILL_BYPASS / 2 sessions, 432/session, all Bash — plus a measured A/B
WIP=1 experiment and a completion-evidence audit), accepted by the user as one
release, implemented in order:

- **P1 — skill-gate friction cut** (`hooks/check-tool-skill.sh`):
  - **Sliding grace window** — allowed skill work refreshes the sentinel, so a
    long skill flow no longer lapses mid-flight; an idle gap > TTL still
    expires it (never-block-forever guard regression-tested).
  - **Hard-gated mutation classes** — `git push`, migration appliers
    (`psql -f` / `prisma migrate` / `alembic upgrade|downgrade` /
    `flyway migrate|clean`) and deploy scripts (`deploy.sh`) never ride the
    grace window or the read-only fast-path; explicit SKILL_BYPASS stays their
    only in-band escape and is always ledgered.
  - **Honest ledger** — a bypass that arrives while the gate was open anyway
    (fresh window / read-only command) is logged `"ceremonial": true`;
    `itd_retro_scan.py` now reports ceremonial vs real separately
    (`bypassCeremonialTotal`).
  - **wsl unwrap** now also matches the bare `--` separator form
    (`wsl.exe -- bash -lc "…"`) — the dominant live-session spelling that
    silently never unwrapped.
  - +7 FP-corpus cases in `tests/verify_skill_enforcement.py` (17 total).
- **P2 — negative scenarios are verified, not merely written**: new rubric item
  `I-code-12` in `skills/review/references/review-checklist.md` + an
  advisory-only tail on the completion-gate green path (`completion_lib.py`
  sets `verdict.advisory` when L2 is pass; never a veto — best-effort
  invariant). Evidence: A/B run shipped a truthful "6/6 done" with 87% branch
  coverage and unverified error branches.
- **P3 — scope audit of the diff**: new rubric item `I-code-13` — public
  API/behavior introduced by the diff must map to a requirement or a test;
  flagged as a question, not a block. Evidence: a 100%-passing run still
  shipped a dead public method and +14% src of scope drift.
- **P4 — micro-path regression cadence**: `/task` Step 1b +
  `skills/_shared/helpers.md` §6 — for standard-tier tasks of ≤1–2 units the
  cumulative regression suite runs once as a final full pass; per-unit
  verification stays mandatory. Evidence: after-every-unit regression on a
  micro-task cost ×3.5 wall-clock / ×7 tool calls at zero difference in
  verified-completion rate.

Core stays untouched on purpose: WIP=1, the L1→L3 ladder and the
completion-gate proved their lower-bound-guarantee role in the same retro.

---

## [1.65.0] - 2026-07-08

**Contract-drift detection goes automatic.** `pre-flight-check.sh` gains an
inline advisory: if the project has `.itd/` and CLAUDE.md, the `snapshot @ <sha>`
markers in derived `.itd/*.md` docs are compared against the last commit that
touched CLAUDE.md. On drift, one warning line enters the pre-flight context
(with a pointer to `.itd/check_contract_drift.py` for details). Rate-limited to
once per 4h per project; advisory-only; any error (no git, not a repo) is a
silent skip. The logic is implemented INLINE — a user-level hook never executes
code from the project directory (reads data, does not run scripts).

---

## [1.64.0] - 2026-07-08

**/session-save: methodology-memory auto-push.** New Step 4.7b — when
`~/.claude/methodology-memory/` is a git repo with a remote (private
`idea-to-deploy-memory`), every `/session-save` commits and pushes the memory
checkpoint. Best-effort: a network/auth failure never blocks the save (the
local commit still preserves state). Scope guard: only methodology notes live
there; secret VALUES never go into memory files; the remote must stay private.

---

## [1.63.0] - 2026-07-08

**Completion Gate hardening + contract-drift detector + WIP=1 cross-check.**
Follow-up to 1.62.0 closing three defects found by auditing the gate on a live
project.

### Fixed (completion_lib.py classifier)

- `outcome_from` now reads an echoed exit code (`EXIT: 0` / `TSC_EXIT=0` /
  `exit: 1`). Commands that pipe through `head`/`tail` mask `$?` and the host
  tool-response often omits a structured exit code, so every signal landed as
  `unknown` and L1 never turned `pass`.
- VCS/submission commands (`git`/`gh`/`hg`/`svn`/`jj`) are excluded from signal
  classification. A `git commit ... && git log` was classified as an L2
  `test_run` - the act of submitting masqueraded as proof (violated the gate's
  own "commit != test").
- PASS text heuristic tightened to strong signals only (test/build summaries).
  Weak phrases (`clean`, `no errors`, bare `PASS`, `ok N`) no longer yield a
  false `pass` on arbitrary output - they degrade to `unknown` (safe). A false
  `pass` is a dangerous false-green; a false `unknown` is a safe advisory.
- Projects with declared `l2_evidence_patterns` (no unit tests) no longer
  hard-block every commit on an incidental test-file scan match: the generic
  scan is suppressed, hard block only for real unit tests, otherwise advisory.

### Added

- `scripts/validate_state.py`: WIP=1 cross-ledger check. `STATE.currentUnit`
  (ad-hoc /task unit) and `GOAL.json` (long goal) may not be active at the same
  time - removes the dual source of "current unit" (fail-closed).
- `docs/templates/itd/check_contract_drift.py`: detector for silent drift of
  derived `.itd/*` contract copies from CLAUDE.md. Compares a `snapshot @ <sha>`
  marker against the last commit touching CLAUDE.md; `--strict` for a gate,
  `--selftest` for the compare logic.

---

## [1.62.0] - 2026-07-06

**Completion Gate — a harness subsystem against premature "done".** Closes the
gap where completion was judged by agent confidence, not runtime signals: an
independent gate now vetoes a `git commit` when the three-layer completion
ladder (L1 static → L2 tests → L3 e2e) is unproven, judging from an objective
signal ledger rather than the model's say-so. Vendor-neutral contract (JSON in
`.claude/completion/` + a "Определение завершения" section in the global
CLAUDE.md template); the hooks only transport it and degrade to advisory when no
ledger exists (best-effort invariant). Hook count **24 → 27**; hard gates
**8 → 9**.

### Hooks (3 new)

- `completion-signals.sh` (PostToolUse · Bash, soft) — classifies each Bash call
  into a layer signal (`static`/`test_run`/`app_start`/`side_effect`/`cleanup`)
  and appends it to `.claude/completion/signals.jsonl`; returns a teacher-style
  `FAILED | WHY | FIX` mark the moment a test/build fails (self-correction).
- `completion-gate.sh` (PreToolUse · Bash, **hard gate**) — on a commit touching
  source code: **deny** when a layer is FAIL or tests exist but were not run this
  session; **degrade** to advisory when there are no signals; pass when green.
  Bypass: `COMPLETION_BYPASS:` in the commit's Bash `description`.
- `completion-stop.sh` (Stop, soft) — reminds, without blocking, when a turn ends
  with a dirty code tree and a non-green verdict.
- `completion_lib.py` (library) — signal classification, three-layer
  `compute_verdict` (latest-per-command so a fix+rerun supersedes an old fail),
  `red_mark` + `FIX_HINTS`. Projects without unit tests declare an L2 equivalent
  via `.claude/completion/config.json` (`l2_evidence_patterns`).

### Registration, contract & docs

- `scripts/sync-to-active.sh` registers the 3 hooks (PostToolUse Bash → signals,
  PreToolUse Bash → gate, Stop → stop) with `-X utf8` on Windows targets.
- `docs/templates/global-claude-md.md` — new "Определение завершения" section
  (the vendor-neutral completion contract).
- Count/taxonomy synced to 27 hooks / 9 hard / 18 soft across `plugin.json`,
  `marketplace.json`, `HARNESS_ENGINEERING_MAP.md` (§8.1/§8.2), the global
  CLAUDE.md template and `README.md`.

### Tests

- `tests/verify_completion_gate.py` (new, behavioural) — spawns the gate and
  asserts real `deny`/exit-2 on a failed-L2 ledger, plus degradation/pass/bypass.
- `tests/verify_harness_map_fixtures.py` — `GATE_TESTS` gains the completion-gate
  mapping so hard-gate coverage stays 9/9.

---

## [1.61.0] - 2026-07-06

**Ось 3 — Fable 5 absorption (multi-unit; goal `.itd-memory/GOAL.json`).** A push to raise the Fable-5-absorption axis from a self-graded ~7.0 toward **~9 — explicitly NOT 10**: literal "absorbed EVERY harness feature" would be 10 and is *not the goal*. The value is a verifiably-complete, consciously-decided registry, not breadth. What was name-dropped across the invariant block, CHANGELOG, and DESIGN_SPACE is now consolidated into one proven ledger, its fallbacks are fixture-proven (not just declared), abstentions get a periodic re-review, and two measured adoptions land. Every unit is backed by a section-scoped, mutation-tested CI gate. Counts stay **40/10/24** throughout.

### G-001 — one consolidated harness-native feature ledger

`docs/FABLE5_FEATURE_LEDGER.md` — one row per harness-native feature (20 rows) with **adopt/abstain + evidence (a real repo path) + a vendor-neutral fallback**. Consolidates the previously-scattered invariant block (`global-claude-md.md`), Fable releases A–D in `CHANGELOG.md`, and DESIGN_SPACE overlaps. All five features named in the invariant (typed tool-calls, chips, artifacts, background agents, transcript search) appear as rows. The "~9, not 10" ceiling is stated in the doc.

**Tests** — `tests/verify_feature_ledger.py` (new, structural + mutation-proven: empty cell / bogus decision / non-existent evidence path / stripped disclaimer all fail).

### G-002 — verifiable completeness (drift-guard)

`tests/verify_feature_ledger_completeness.py` proves the ledger COVERS the frontier, turning "scattered" into "provably consolidated". Mechanism A LIVE-parses the invariant's feature sentence — add a noun there without a ledger row and it FAILS. Mechanism B holds a curated set of adopted CHANGELOG tokens, each required to stay grounded in `CHANGELOG.md` and covered by an actual table row.

### G-003 — fixture-proof of fallbacks (proven, not declared)

`tests/verify_feature_ledger_fallbacks.py` SIMULATES a feature being absent and asserts the exact vendor-neutral path engages: it imports `hooks/cross-review-precommit.sh`, forces both engines absent (`resolve_engine → None`), and asserts the honest "UNAVAILABLE … run `/cross-review`" degrade with **no fabricated "Findings" green** (a positive control proves the absent-branch is not vacuous); and it shows the worktree precondition genuinely fails in a non-git dir so `freeze.sh` is the real fallback. The best-effort invariant is now PROVEN for two adopted features.

### G-004 — periodic re-review of abstentions via `/retro`

`skills/retro/scripts/itd_ledger_abstentions.py` (new FACTS producer) surfaces the ledger's `abstain` rows + their fallback; `/retro` Step 1b raises them ("has a safe use appeared?") under the same anti-Goodhart gate (a flip needs an EXTERNAL signal). Non-fatal outside the methodology repo. **Test** — `tests/verify_retro_abstention_review.py` (SKILL wiring + helper faithfulness vs an independent ledger parse + non-fatal-on-absent).

### G-005 — two measured, invariant-safe adoptions (not breadth)

`F-21` scheduled **read-only** nudge (`ScheduleWakeup`/cron) for the abstention re-review — makes "periodic" real; the scheduled agent stays a read-only reporter. `F-16` flips `abstain → adopt (complement only)`: a `spawn_task` chip *transports* an out-of-scope finding to the UI while `BACKLOG.md` stays the contract (chips AS the backlog stays rejected) — wired into `skills/_shared/helpers.md` §10. **Test** — `tests/verify_feature_ledger_adoptions.py` (each adoption is really wired, evidence path exists, fallback preserved, invariant guard stated).

### G-006 — release v1.61.0

Version bumped across `plugin.json`, `marketplace.json`, both README badges; this CHANGELOG entry; the five new gates wired into `meta-review.yml` and `windows-verify.yml`. Self-assessment: **~9/10, deliberately not 10** — the last point is external evidence / red-team, not more code.

## [1.60.0] - 2026-07-06

**Ось 2 — Agentic engineering (multi-unit; goal `.itd-memory/GOAL.json`).** A push to raise the agentic-engineering axis from a self-graded ~7.5 toward ~9: make subagent recovery mechanical (never a manual ping), extend the adversarial refute discipline across the whole verify fleet, lock the risk-tier⇒model ordering, make the skill Definition-of-Done machine-readable, and turn stall recovery into an automatic fallback. Every unit is backed by a section-scoped, mutation-tested CI gate. Counts stay **40/10/24** throughout.

### G-001 — caller-side auto-ping-for-verdict in `/review`

The #1 agentic drag was a subagent ending its final message on process narration instead of a verdict, recovered only by a human ping. `/review` gains **Step 2.7**: after each Agent-tool dispatch, the conductor detects a verdict-less return by the **absence of the verdict marker** (not by regex-guessing the prose — strictly less reliable) and **auto-re-pings once, without asking the user**, bounded by `ITD_AUTOPING_MAX` (default 2). `/cross-review` gets the symmetric step 3a. The two SubagentStop hooks (`narration-final.sh`, `verdict-contract.sh`) are the *suspenders* to this caller-side *belt*; the layers degrade independently (harness best-effort invariant).

**Tests** — `tests/verify_review_autoping.py` (new, 12 checks, section-scoped to Step 2.7 / 3a).

### G-002 — refute pass across the whole verify fleet

The `/review` Step 2.6 adversarial refute is extended to the rest of the verify fleet: `/security-audit` **Step 2.5** (refute exploitability of each Critical/Important vuln; security tie-break — vague doubt is not a refutation), `/perf` **Step 2.5** (refute each HIGH/MEDIUM bottleneck; must be measured on the hot path), `/test` **Step 5.5** (mutation-check each behavior-asserting test — green under a mutation = vacuous coverage). Shared invariant: the refute pass can only REMOVE findings, never invent one; minor/low findings are exempt.

**Tests** — `tests/verify_refute_fleet.py` (new, 19 checks, section-scoped per skill).

### G-003 — risk-tier ⇒ model monotonicity invariant

A machine-checked invariant: the `security-reviewer`'s model tier is never below the `code-reviewer`'s (security is the higher-risk verify class). `MODEL-ROUTING-POLICY.md` is reconciled with the actual frontmatter (its table previously said code-review→opus while the `code-reviewer` subagent runs sonnet+high) — the interactive `/review` conductor row (opus) and the thin `code-reviewer` subagent row (sonnet+high) are now split and consistent.

**Tests** — `tests/verify_model_risk_monotonic.py` (new) parses the `model:` frontmatter (tier-normalized, tolerant of a pinned full id) and pins both doc tables to it; a future inversion or doc-drift fails CI.

### G-004 — machine-readable skill Definition-of-Done

`VERIFICATION_CONTRACT.json` gains a `skillDefinitionOfDone` registry: each verify/impl skill's DoD is expressed as ≥1 **structured** done-signal (sentinel / command / artifact / json_field / evidence), not only prose. Anti-fabrication: every `sentinel` done-signal must actually be **written** by its skill (a redirection/`tee` line, not a prose mention).

**Tests** — `tests/verify_dod_coverage.py` (new) counts coverage of the required verify/impl set (==100%) and grounds every sentinel ref.

### G-005 — mechanical stall-resilience fresh-narrow fallback

`skills/_shared/helpers.md` gains **§9**: on ANY subagent stall (watchdog timeout / autocompact death / empty return), the recovery is a fresh narrow agent spawned **automatically** — the default procedure, not a manual «resume or retry?» decision — generalizing §8's post-BLOCKED rule. Bounded by `ITD_STALL_MAX_RESPAWNS` (default 2), then escalates a visible blocker. Referenced from `/review` Step 0 and `/task` Step 3f.

**Tests** — `tests/verify_stall_fallback.py` (new, 8 checks, section-scoped to §9).

All five gates wired into `.github/workflows/meta-review.yml`. Live dogfood: during G-005's own review the `code-reviewer` ended on narration without a verdict — Step 2.7's caller-side auto-re-ping recovered the verdict in one message, zero manual pings.

---

## [1.59.0] - 2026-07-06

**Ось 1 — Harness engineering (multi-unit; goal `.itd-memory/GOAL.json`).** A push to raise the harness-engineering axis from a self-graded ~7.5 toward ~9.5: diff-bind the review gate, make the self-grading honest and behaviourally fixture-proofed, split hard vs soft gates explicitly, cut ceremony friction, and prove hook-inheritance + gate-robustness empirically. Counts stay **40/10/24** throughout.

### G-001 — diff-bound review-sentinel

The review commit gate (`check-review-before-commit.sh`) previously unblocked a >2-file `git commit` on *any* fresh `claude-review-done-*` sentinel (bare timestamp), so a stale review (content edited since) or a sentinel from an unrelated project wildcarded the gate. It is now **bound to `tree:<git-write-tree>`** — the SHA of the exact staged content — and unblocks only a commit whose staged tree matches. Closes the wildcard hole; fails **closed** when git cannot fingerprint the tree (no re-opened bypass).

**Changed**

- **`hooks/check-review-before-commit.sh`** — `review_was_done()` now requires the sentinel content to equal `tree:<current-staged-tree>` (via new `staged_tree_hash()` → `git write-tree`). Bare-timestamp / malformed sentinels are rejected (no wildcard). Fail-closed on git fault (deny, re-require /review) — a foreign `tree:` token can no longer slip through on a git error.
- **`hooks/record-agent-skill.sh`** — writes the review sentinel for the delegated `code-reviewer` subagent as `tree:<hash>` (bound), matching what the gate computes at commit time; other skills keep the plain timestamp (they feed existence-based gates).
- **`skills/review/SKILL.md`** — Step 5 writes `tree:$(git write-tree)` instead of a bare timestamp (timestamp fallback only on genuine git error).

**Tests**

- **`tests/verify_review_sentinel_diffbind.py`** (new, 12 checks) — real deny(exit 2)/allow(exit 0) exercises: foreign/stale/legacy sentinels denied, matching tree allowed, staleness re-block, end-to-end via the recorder, and a fail-closed regression guard (git-fault + foreign sentinel → not done).
- **`tests/verify_agent_review_sentinel.py`** — `run_record` gained `cwd` so the end-to-end case binds to the test repo's tree (models runtime: delegated review + commit share the repo). Still 10/10; DoD gate 19/19 (existence-based, unaffected).

### G-002 — hard/soft gate taxonomy + hard-gate coverage metric

The "24 hooks" count conflated enforcement strength with hook count. README now splits it explicitly: **8 hard gates** (can `deny`/`block` — `check-review-before-commit`, `check-dod-before-commit`, `check-commit-completeness`, `check-skill-completeness`, `check-tool-skill`, `pii-egress-guard`, `narration-final`, `verdict-contract`) vs **16 soft** (reminders/context/observability, always exit 0). Introduces the **hard-gate coverage** metric — the fraction of hard gates backed by a behavioural deny/block test (target 8/8).

**Changed**

- **`README.md` / `README.ru.md`** — new "Hook taxonomy — 8 hard gates vs 16 soft" table + hard-gate coverage definition; the bare "24 hooks" oversell is gone. Fixed a stale line that described the escalating `check-tool-skill.sh` as "Soft reminder — never blocks" (it denies on the 3rd ignored skill decision).

**Tests**

- **`tests/verify_gate_taxonomy.py`** (new, 9 checks) — derives the hard/soft split from `hooks/*.sh` by a strict blocking-decision regex (8/16/24), then asserts the README table and prose stay in sync with the derived sets (a 9th hard gate forces a doc update). Reports current hard-gate coverage.

### G-003 — fixture-proof self-grading grid (doc-vs-enforcement gap closed)

The HARNESS_MAP's H1/H3 enforcement ✅ rested on "the hook exists." Two hard gates — `check-commit-completeness` and `check-skill-completeness` — had **no test that actually drove them to `deny`** (referenced only structurally), so their ✅ was unproven. Now every hard gate is behaviourally fixture-proofed.

**Added**

- **`tests/verify_commit_completeness_gate.py`** (new, 3 checks) — spawns `check-commit-completeness.sh` against a temp methodology repo and asserts a real exit-2 deny for an incomplete skill commit (+ allow when complete, + no-op outside a methodology repo).
- **`tests/verify_skill_completeness_gate.py`** (new, 4 checks) — spawns `check-skill-completeness.sh` on a Write payload and asserts exit-2 deny for a `SKILL.md` referencing a missing `references/` (+ allow paths).
- **`tests/verify_harness_map_fixtures.py`** (new, 27 checks) — the grid: derives the 8 hard gates (same regex as the taxonomy test), maps each to a behavioural proof test, statically checks each proof spawns the hook + asserts block/deny, **runs each and requires it to pass**, and asserts **hard-gate coverage == 8/8**. A 9th hard gate without a passing proof fails the grid — a gate can never be ✅ without a proven block/deny.

**Changed**

- **`docs/HARNESS_ENGINEERING_MAP.md`** — the ✅ enforcement marks now cite the fixture-proof grid (8/8 behavioural coverage), not hook existence.

### G-004 — skill-gate friction cut + bypass/session metric

The skill-enforcement gate had two dead-ends that produced ceremony `SKILL_BYPASS` records (the live ledger's dominant reason class was read-only recon and "skill active but the hook can't see the Skill call").

**Fixed**

- **`hooks/check-tool-skill.sh`** — the `SKILL_BYPASS` check now runs **before** the read-only fast-path. Previously a read-only Bash carrying `SKILL_BYPASS:` was swallowed by the read-only short-circuit, so the natural `true` + `SKILL_BYPASS:` gesture used to open a grace window did nothing (no reset, no window, no log). It now reliably opens the window — the only in-band escape Edit/Write (no `description` field) have.
- **`hooks/check-tool-skill.sh`** — the block message no longer tells Edit/Write users to "add SKILL_BYPASS to the description" (impossible — they have no such field); it now points them to the correct escape (a one-off harmless Bash with `SKILL_BYPASS:` in its description opens a grace window covering the following Edit/Write burst).

**Changed**

- **`hooks/check-tool-skill.sh`** — evidence-driven read-only allowlist additions from the bypass ledger: `tsc --noEmit` (type-check, read-only) and `node --test` (built-in test runner). Bare `tsc` (emits) and `node app.js` stay gated.
- **`skills/retro/scripts/itd_retro_scan.py`** — new **bypass/session** friction metric (`bypassSessionCount`, `bypassPerSession`) rendered in the retro report and exposed in `--json`; it must trend down release to release.

**Tests**

- **`tests/verify_bypass_friction.py`** (new, 17 checks) — drives the real hook: readonly+bypass now resets/opens-window/logs (Bug 1); readonly-without-bypass stays exempt; end-to-end Edit dead-end → blocked, then one-off bypass opens the window, next Edit allowed (Bug 2 escape); allowlist additions classified read-only.
- **`tests/verify_retro_scan.py`** — asserts the new per-session metric in markdown and `--json`.

### G-005 — hook-table drift-guard + empirical context:fork inheritance

**Added**

- **`tests/verify_hook_table_completeness.py`** (new, 7 checks) — a drift-guard that asserts the HARNESS_MAP §8.2 per-hook table lists exactly `hooks/*.sh`, the §8.1 matrix mentions every hook, the §8.2 **blocking** rows equal the 8 hard gates (classifier), and the README taxonomy union equals the disk hook set. It caught real drift on arrival (see below).

**Fixed (drift the guard exposed)**

- **`docs/HARNESS_ENGINEERING_MAP.md` §8** — the §8.2 per-hook table was missing `narration-final.sh` and `verdict-contract.sh` (the two SubagentStop hard gates), and §8.1/§8.2 mislabelled `careful.sh`/`freeze.sh` as "blocking" though both self-declare `exit 0, permissionDecision: allow`. Reconciled: 24 hooks; **8 hard = 6 feedforward `deny` + 2 SubagentStop `block`**; 16 soft (careful/freeze are soft detectors). §8.1 header 22→24; §8.3 "8 blocking = feedforward" → "computational; 6 FF + 2 SubagentStop".

**Verified empirically**

- **`skills/autopilot/SKILL.md`** — the hedged `context: fork` caveat ("if a forked context does not inherit the enforcement hooks…") is replaced with evidence: a probe subagent in a forked context ran two Bash calls and the parent `settings.json` `PreToolUse` hooks BOTH fired (`careful`, `check-tool-skill`), delivered as `PreToolUse:Bash hook additional context`. So mechanical gates DO apply inside a fork. Recorded in HARNESS_MAP §8.4. (Separate mechanism: a fork does not inherit the parent `SKILL.md` — instruction inheritance, not hook firing.)

### G-006 — adversarial red-team + multi-host proof

**Added**

- **`tests/verify_redteam_multihost.py`** (new, 8 checks) — the ceiling unit. Part A red-team: the fixture grid proves all 8 hard gates deny/block, and targeted circumvention attempts must FAIL — a foreign/fresh `tree:` review sentinel is rejected, a legacy bare-timestamp wildcard is rejected, a `SKILL_BYPASS` smuggled in the Bash *command* (not the audited `description`) is not honoured, and read-only smuggles (`ls && rm -rf x`, `cat x > y`, `git status && curl …`) are not classified read-only. Part B multi-host: hooks are spawned with `sys.executable`, and the red-team is proven green on **two distinct OS/interpreter hosts** — WSL-Linux (py3.12.3) and Windows (py3.12.10) — with per-host evidence committed under `tests/redteam-hosts/`. The comprehensive fixture grid stays WSL-canonical (skippable on a secondary host whose git/temp harness differs); the cross-host robustness proof rests on the targeted adversarial cases, which run identically everywhere.

### G-007 — HARNESS_MAP re-score + axis close

- **`docs/HARNESS_ENGINEERING_MAP.md` §6** — records the honest post-Ось-1 self-assessment of the Harness-engineering axis: **~9.5/10**, up from ~7.5, with the systemic holes closed (diff-bound sentinel, 8/8 behavioural gate coverage, hard/soft split, friction cut, drift-guard, empirical fork inheritance, cross-host red-team). The last 0.5 to 10 is explicitly **external**: an independent red-team and multi-*OS* confirmation beyond Win+WSL — evidence a methodology cannot grant itself. Not scored as 10 for exactly that reason.
- **`tests/redteam-hosts/`** — moved out of `tests/fixtures/` (host evidence is data, not a snapshot fixture) so `verify_snapshot.py --all` stays green.
- Rolled out to `~/.claude` (WSL + Windows) via `scripts/sync-to-active.sh`.

## [1.58.0] - 2026-07-05

**Release D3 — `/autopilot` re-evaluation (audit graded it C, worst value/risk).** The plan's D3 item. Re-evaluated and **hardened, harness-aligned** (not deprecated, and not with per-phase human checkpoints — those would duplicate the mechanical harness and defeat the autonomy that is autopilot's whole point). The deciding fact: autopilot is already `disable-model-invocation: true`, so it is never auto-routed — a pure opt-in command. That removes most of the "redundant routing footgun" case for deprecation, leaving only a misleading description and a `context: fork` safety question, both fixed here. No new/removed skill — counts stay 40/10/24.

### Changed

- **`skills/autopilot/SKILL.md` — safety model reframed in harness terms; honest description; explicit boundary.** The old description ("minimal human intervention") oversold hands-free autonomy and understated the gates. Rewrote it around the actual safety model: autopilot auto-advances (that autonomy is the point and is harness-legitimate), and safety comes from the methodology's **mechanical gates** (`check-review-before-commit`, `check-dod-before-commit`, `careful`, `permission-ask`, `pii-egress-guard`) which fire on every tool call regardless of the orchestrating skill — **not** from human "да/нет" between phases. Autopilot owns exactly one hard **boundary**: it never performs an outward/irreversible action itself (no deploy, no `git push`, no `gh pr create`) — it stops at a local commit and hands those to the user. Added an explicit `context: fork` caveat: if a forked context does not inherit the enforcement hooks, the boundary still keeps the worst case to a local commit. Added a "prefer `/kickstart`" steer at the top (same lifecycle, main context, gates always apply; autopilot only for a deliberate hands-free greenfield spike) — turning the redundancy into a clear human choice instead of a trap. `/review` stays a hard gate (mechanically backstopped). Docs-only; no behavior/count change.

---

## [1.57.0] - 2026-07-05

**Release D2 — routing eval + CI gate for the de-prescribed skills.** Wave 2, next plan item after D1's two de-prescriptions. The audit's "evals for skills with false-match history" made concrete: D1's fixes were measured only *locally* — `verify_routing.py` was **not wired into any CI workflow**, so a re-broadened trigger would keep 100% accuracy while silently re-introducing the ambiguity the de-prescription removed. D2 closes that gap. No new hook/agent/skill — counts stay 40/10/24.

### Added

- **`exclusive` benchmark flag + exclusivity assertion in `verify_routing.py`.** A prompt tagged `"exclusive": true` must route to the expected skill **and nothing else** (`routed == [expected]`), not merely reach it. This is the regression guard for a de-prescribed skill: an over-broad trigger that co-fires again fails the benchmark instead of passing silently on accuracy. Proven to have teeth (a synthetic co-firing prompt tagged exclusive fails). Tagged the two D1 de-prescriptions — `advisor-1` (advisor↔blueprint) and `obsidian-export-2` (harden↔obsidian) — locking them against silent regression.
- **`verify_routing.py` wired into CI** (`windows-verify.yml`). The routing-accuracy benchmark (68 prompts, `--min-accuracy 1.0`) and the new exclusivity eval now run on every push/PR. Previously the whole routing benchmark was ungated — the D1 A/B measurements lived only in local runs.

### Fixed

- **`verify_triggers.load_hook_triggers` — hardcoded `/tmp` → `tempfile.gettempdir()`.** Wiring `verify_routing.py` (which imports this loader) into `windows-verify` immediately surfaced a latent "/tmp on Windows" bug: the loader copied `check-skills.sh` to `Path("/tmp")/...`, which fails on the native-Windows CI leg (`\tmp\...` does not exist). `verify_triggers` had only ever run on Ubuntu, so the bug was invisible until D2 exercised the shared loader on Windows — exactly the bug class `windows-verify.yml` exists to catch.

---

## [1.56.0] - 2026-07-05

**Release D1 — second measured A/B (advisor↔blueprint was the first).** Continuing wave 2 one A/B at a time. After D1's first change, the remaining 9 routing ambiguities were classified bug-vs-by-design: most are broad-gate co-fires that route correctly and are intentional (`/review` co-firing on the literal word "review"/"audit"; `migrate`⊂`migrate-prod` substring, already handled). This release fixes the one clean, non-by-design case. No new hook/agent/skill — counts stay 40/10/24.

### Changed

- **`check-skills.sh` — harden's bare `vault` trigger no longer matches "obsidian vault".** `\bvault\b` (the secrets-manager Vault, a canonical harden phrase alongside "doppler"/"secrets management") also matched "obsidian vault", so `/harden` co-fired on `obsidian-export-2` ("Export this to my Obsidian vault as linked notes"). Added a fixed-width negative-lookbehind — `(?<!obsidian )\bvault\b` — that excludes ONLY "obsidian vault"; the canonical "vault" phrase and "secrets vault"/"hashicorp vault" still match (so `verify_triggers.py` stays green), and the obsidian-export trigger already owns `obsidian\s+vault`. **A/B measured:** routing accuracy 100.0% → 100.0% (no degradation); ambiguous prompts 9 → 8 (`obsidian-export-2` now routes to `/obsidian-export` alone); no trigger drift.

---

## [1.55.0] - 2026-07-05

**Release D1 — skill-overlap de-prescription (wave 2, strictly one A/B at a time).** The 2026-07-05 `/advisor` audit flagged conceptual overlaps between skills; Release D resolves them one *measured* A/B at a time (baseline → change → `verify_routing.py` re-measure → rollback on any accuracy drop). Of the three pairs the audit named (project↔task, blueprint↔strategy, advisor↔grill-me), the routing benchmark showed **none** as a measurable ambiguity — the router is already 100% accurate. D1 therefore targets the only overlap that *did* surface as measurable routing ambiguity, `advisor`↔`blueprint`, chosen on evidence rather than the plan's assumed pairs. No new hook/agent/skill — counts stay 40/10/24.

### Changed

- **`check-skills.sh` — blueprint's bare `архитект` trigger narrowed to architecture-of-a-thing.** The bare stem matched "варианты архитектуры" in the analysis-only benchmark prompt `advisor-1` ("Только анализ, без кода: сравни варианты архитектуры"), so `/blueprint` co-fired and stole `/advisor`'s routing (ambiguous). Narrowed to `архитектур\w*\s+(?:проект|приложени|систем|продукт|сервис)` — still matches the canonical "архитектура проекта" phrase (so `verify_triggers.py` stays green) and genuine design prompts, and design-verb prompts ("спроектируй архитектуру") still route via `спроектируй`; it no longer fires on "сравни варианты архитектуры". **A/B measured:** routing accuracy 100.0% → 100.0% (no degradation); ambiguous prompts 10 → 9 (`advisor-1` now routes to `/advisor` alone); `verify_triggers.py` reports no drift.

---

## [1.54.0] - 2026-07-05

**Release E — usability fix-pack (wave 1 of the 2026-07-05 `/advisor` effectiveness audit, grade A−).** Three evidence-backed items: E1 shrinks the biggest ceremony source (691 SKILL_BYPASS this session), E2 makes two subagent contracts honest about their tools, E3 records a keep-with-justification decision for the three "silent" hooks and closes a hook-doc gap the drift-guard never caught. No new hook/agent/skill — counts stay 40/10/24.

### Changed

- **E1 — `check-tool-skill.sh` read-only allowlist now exempts test-runners and `git -C <dir>`.** Evidence: **691 SKILL_BYPASS records this session, all Bash**, dominated by verification/recon; a forked `/advisor` was blocked 3/3 on read-only work. Running a suite is verification recon, not entering a new task — so `pytest`, `python[3] -m pytest` / `python[3] tests/…`, `npm test` / `npm run test`, and `go test` are now exempt, while product-code runs (`python app.py`, `npm run build`/`dev`) stay gated. `git -C <path> <read-only-sub>` (status/log/…) joins the git allowlist; a mutation after `-C` (push/commit) stays gated. Pipe-safe recon (`grep`/`find`/`ls … | head/wc/sort`, `pytest | tail`) is regression-locked, and a read-only leader still cannot smuggle a mutation through a pipe (`grep … | xargs rm` stays gated). Test: `verify_v147_fixes.py` (+21 cases, 47 total).

### Fixed

- **E3 (doc-gap) — 6 of 24 hooks were missing from the `hooks/README.md` table though the count claimed 24.** The table documented only 18; three of the missing six are **wired by default in the `/adopt` template** (`risk-score.sh`, `cost-tracker.sh`, `pii-egress-guard.sh`) yet were undiscoverable. Added all six — `pii-egress-guard.sh` to the safety-guardrails table, and a new "Budget, observability & session-management" table for `cost-tracker`/`risk-score`/`crash-recovery`/`context-aware`/`stuck-detection`. The `24 hooks` claim now matches the table. (The numeric drift-guard passed on `24` — it never asserted table-completeness; that assertion is a backlog candidate, deferred as a new mechanism.)

### Contracts

- **E2 — `ux-reviewer` and `researcher` agent contracts reconciled with their tools (audit Important).** Both forks carry `allowed-tools: Read Grep Glob`, but their contracts implied they gather browser/web evidence themselves. Both now state explicitly that **the caller supplies the evidence** — `ux-reviewer` reviews `/browser-check` Playwright output (screenshots, a11y snapshots); `researcher` synthesizes `/market-scan` (last30days) / `/mcp-docs` (Context7) output — and if the needed evidence is absent, the agent must say so under "Unverified" (never fabricate) and recommend the caller run the tool and re-invoke. Tools now match responsibilities; the description frontmatter was updated to match.

### Decided (evidence-backed, E3)

- **Keep all three "silent" hooks — evidence attached, none deregistered.** `context-budget.sh`: fired live this session on real `cat`/recon commands → proven value, keep (opt-in). `execution-trace.sh`: injects **nothing** into context (zero context-budget cost by construction) → keep as opt-in observability. `risk-score.sh`: wired by default, conservative (escalates once per `ITD_RISK_THRESHOLD`=12 worth of accrued risk), catches the "death by a thousand edits" drift binary gates miss → keep, and now documented (it was the doc-gap above).

---

## [1.53.0] - 2026-07-05

**The first live `/retro` cycle, implemented.** `/retro` ran over the harness telemetry (SKILL_BYPASS ledger, cost, VCR) plus this session's external signals (real review findings, a reviewer stall, drift-guard holes) and produced `docs/retros/RETRO-2026-07-05.md`. The human accepted all four evidence-backed candidates; this release implements them. No new hook/agent — counts stay 40/10/24.

### Changed

- **P1 — `check-tool-skill.sh` read-only Bash exemption now fires for `wsl -e`.** Evidence: **691 SKILL_BYPASS records this session, all Bash**, reasons dominated by read-only/verification/staging. Reading the code (not memory) refined the fix: the read-only allowlist + `wsl … bash -lc` unwrap already existed (v1.35.0/v1.47.0), but the unwrap regex only matched the long `--exec` — the far more common short `-e` form (`wsl -e bash -lc …`) never unwrapped, so a whole session of read-only recon produced ceremony bypasses. Added `-e` to the unwrap; mutations inside `wsl -e` stay gated (verified). Test: `verify_v147_fixes.py` (+3 cases).
- **P2 — M-C15 hook-count check now parses teens + twenties (compounds).** Evidence: «семнадцать хуков» (17) sat stale in README.ru through v1.49/v1.50 (parser knew only 1-9), and «двадцать четыре хука» was misread as «четыре»=4, a false BLOCK in v1.51.0. The spelled-number parser (`num_ru`/`num_en`, now module-level in `meta_review.py`) covers 1..39 with compound parsing. New regression test `tests/verify_hook_count_words.py`, wired into CI. Residual (documented, no evidence yet): loose non-adjacent forms like «их N хуков» stay uncovered — over-match risk too high without a second signal.
- **P3 — `narration-final.sh` widened (cautiously, pruned to evidence).** Evidence: a reviewer ended on «Now I have full coverage. Time to refute my own findings before reporting.» — the narration was in the LAST sentence, not the paragraph start, so start-only matching missed it. Added the `time to …` opener, the single evidenced verb `refute` (+ RU `опроверг`), and a last-sentence probe. The review of this very release flagged an over-widening in the first draft: `report`/`finalize`/`summarize`/`wrap` double as user-facing instructions («Now report back to the team», «Now wrap up») and false-blocked benign non-review finals — pruned to the evidenced minimum, re-expand only on a second concrete incident. Safety nets: the verdict-marker exemption (a review that issued its verdict is never blocked) + the ≤2 ping cap; `verify_narration_final.py` adds positive + false-block-guard cases (+7, including the pruned-verb guards).

### Added

- **P4 — helper rule: re-verify after BLOCKED with a fresh narrow agent, not a resume** (`skills/_shared/helpers.md` §8). Evidence: a resumed re-check stalled (600s watchdog) while a fresh narrow agent returned PASSED in 84s. A fresh agent starts thin (cheaper, less stall-prone) and its verdict is independent of the finder's reasoning.
- **`docs/retros/RETRO-2026-07-05.md`** — the retro report (scan as-is + the evidence-ranked candidate table + the human decision).

### Decided (not implemented — backlog with triggers)

- Release D — strictly retro-evidence-gated (skill de-prescription A/B one at a time; SendMessage fix→re-review within one session, advice-only; evals for 2-3 skills with false-match history).

---

## [1.52.0] - 2026-07-05

**Fable 5 adoption, release B — safety + calibration** (order A→C→B→D). Three changes: stronger isolation for large refactors, the data-sensitive gate applied to memory consolidation, and effort-tier calibration across the subagents. No new hook — the hook count stays 24.

### Added

- **`skills/refactor/references/worktree-isolation.md` + `/refactor` Step 0.5 — opt-in git-worktree isolation** for large, file-only refactors: do the whole refactor in a throwaway worktree, verify green there, merge back only on success — the main working tree is never touched until then. **Opt-in, not the default**; graceful fallback to the existing `freeze.sh` scope guard when a worktree can't be created (not a git repo, old git, dirty tree, user declines). Worktree isolation transports the "don't corrupt the working tree" intent — it is not the contract (harness best-effort invariant).
- **Hook path-assumption audit (precondition, documented in the same reference).** All 24 hooks are worktree-safe: repo-root detection walks up to `.claude-plugin/plugin.json` (a worktree checks it out), and sentinels are keyed on `session_id`, not path. Two benign path-coupled cases (`execution-trace.sh` traces land in the transient worktree; `handoff-readiness.sh` may soft-nag on the dirty worktree) degrade, never break.
- **`tests/verify_worktree_hook_safety.py` — audit invariant test**, wired into windows-verify CI. Drives the commit gate's actual `find_repo_root(start)` against a REAL git worktree (fidelity), asserting the repo root resolves from inside the worktree and from a nested dir, with a non-repo control. SKIPs gracefully if git is unavailable (falls back to a simulated checkout for the walk-up assertions).
- **`docs/AGENT_EFFORT_TIERS.md`** — the per-role effort-tier framework (role class → effort), the durable rationale for the calibration below.

### Changed

- **Per-role effort tiers across the 10 subagents.** Before: almost every agent at `high` (no cost differentiation). After: verify/judge/design/deep-analysis (`code-reviewer`, `security-reviewer`, `devils-advocate`, `architect`, `perf-analyzer`, `test-generator`) stay `high`; gather/advise (`researcher` high→medium, `business-analyst` high→medium) drop to `medium`; mechanical `doc-writer` medium→low. `test-generator` stays `high` on purpose — its output gates everything else. `effort` is a per-call override via the Agent tool, so the frontmatter value is a default, not a floor.
- **`skills/session-save/SKILL.md` — memory consolidation is now approval-diff-only.** `MEMORY.md` and the session files are durable state, so running `anthropic-skills:consolidate-memory` follows the data-sensitive gate (harness best-effort invariant): model changes read-only → show the before/after diff of which facts are dropped/merged → explicit human approval → only then write. Never a blind rewrite, never an out-of-band writer. The gate is ITD's, not optional.
- **`plugin.json` / `marketplace.json` / README badges → 1.52.0.**

### Decided (not implemented — backlog with triggers)

- Release D — strictly retro-evidence-gated (skill de-prescription A/B one at a time; SendMessage fix→re-review within one session, advice-only; evals for 2–3 skills with false-match history).
- Drift-guard hardening (from the C review): `verify_registration_and_counts.py` / M-C15 miss loose/spelled-out count mentions in README prose — fold into a retro fix.

---

## [1.51.0] - 2026-07-05

**Fable 5 adoption, release C — the review pack.** Three coupled upgrades to the review gate, taken before B/D flow through it (order A→C→B→D, decided 2026-07-05). The gate now collects findings for recall, filters them adversarially, and hands downstream a machine-readable verdict — with a mechanical stop-gate so the machine-readable part is never silently dropped. Battle-tested on this release's own review cycle.

### Added

- **`hooks/verdict-contract.sh` — 24th hook, SubagentStop (part c).** A review subagent must emit its verdict as a vendor-neutral fenced ```json block (`{verdict, findings[], unverified[]}`). The hook blocks the subagent's stop (≤2 pings) when the final message declares a review verdict in prose (`FINAL STATUS:`, `Вердикт:`/`Verdict:`, or `PASSED_WITH_WARNINGS`) but ships no valid JSON block. Deliberately narrow — bare "PASSED"/"BLOCKED" don't trip it, so test-generator/researcher finals pass through. Complementary to `narration-final.sh` on the same event (missing verdict vs verdict-missing-its-block); no loop. Kill switch `ITD_VERDICT_CONTRACT=0`, fail-open on any parse/IO error. The native `ReportFindings` tool-call is only an optional transport — the load-bearing contract is the text block (harness best-effort invariant).
- **`tests/verify_verdict_contract.py` — 15 functional checks** (positives / valid-contract negatives / non-review pass-through / guards / ping-cap), both transcript layouts, wired into CI alongside the other hook suites.
- **`skills/review/SKILL.md` Step 2.6 — refute pass (part b).** Every Critical/Important candidate finding is put through an independent **fresh-context** `code-reviewer` subagent prompted to REFUTE it (default `refuted: true` under uncertainty); a finding that survives refutation escalates, a refuted one drops to observations. Fresh context is load-bearing — the refuter must not inherit the finder's reasoning. Never turns a rubric-Critical FAIL into a pass (Rule 4).

### Changed

- **Coverage-first finder (part a)** in `skills/review/SKILL.md` (Step 2) and `agents/code-reviewer.md`: the finding stage optimises for **recall, not precision** — surface every candidate, incl. uncertain/low-severity, each tagged `severity` + `confidence`; filtering happens downstream (refute pass + tiering), not by self-censoring. The binary rubric and the deterministic gate are untouched — coverage-first only widens the candidate list.
- **`agents/code-reviewer.md`** — findings now carry `severity` + `confidence`; the final message must end with the vendor-neutral JSON verdict block; new refute-mode section for when the agent is dispatched to disprove a single finding.
- **`.claude-plugin/plugin.json` version → 1.51.0** (was stale at 1.49.0 — the v1.50.0 doc-only release did not bump it; the count triple gated, the semver did not). Hook count 23→24 propagated across plugin.json, marketplace.json, `docs/HARNESS_ENGINEERING_MAP.md`, the global CLAUDE.md template, README.md, and hooks/README.md; `verdict-contract.sh` registered in `scripts/sync-to-active.sh` (DESIRED_HOOKS + SubagentStop block).

### Decided (not implemented — backlog with triggers)

- Release B (worktree isolation for file-only `/refactor` after a hook path-assumption audit; consolidate-memory in approval-diff mode only; per-role effort tiers) — next.
- Release D — strictly retro-evidence-gated (skill de-prescription A/B one at a time; SendMessage fix→re-review within one session, advice-only; evals for 2–3 skills with false-match history).

---

## [1.50.0] - 2026-07-05

**Fable 5 adoption, release A — vendor-canonical snippets + the harness best-effort invariant.** External signal (model-generation change), routed through /advisor (ROI panel) + red-team stress-test on 2026-07-05: four zero-risk snippet adoptions from Anthropic's official Fable 5 migration guidance, plus the cross-cutting invariant the red team demanded as a precondition for every later harness-feature adoption (releases B/C/D stay in the backlog, gated on retro evidence).

### Added

- **`docs/templates/global-claude-md.md` — Always #7 «Grounded progress claims».** Vendor-canonical snippet: every progress claim must be auditable against a tool result from the session; unverified work is declared as such. Global — applies to all skills, not just `/goal` (which already lived by it via the ОТК-verifier).
- **`docs/templates/global-claude-md.md` — «Harness-native features — best-effort invariant» section** (inside the ITD:BEGIN/END managed block, so it rolls out with sync). Two rules: (1) a harness-native feature may transport a methodology contract, never be it — no gate/`verified`/handoff depends on a specific tool-call, contracts stay vendor-neutral; (2) egress goes through the cross-review-grade scrubber + human confirmation, durable-state mutation follows the data-sensitive gate, background harness agents are read-only reporters. This is the red-team's cross-cutting blocker, now standing policy.
- **`skills/goal/SKILL.md` — autonomous-run reminder (Step 2)** for headless/AFK unit driving: proceed on reversible in-scope actions without asking, self-check the last paragraph for narration-finals before ending a turn. Prevention-side twin of `hooks/narration-final.sh` (which stays as the postfactum detector); data-sensitive boundary explicitly preserved.
- **`skills/_shared/helpers.md` §8 «Delegation Intent Template».** Every subagent spawn carries three intent lines (what larger task, for whom, what the result unblocks) — Fable 5-era models measurably improve with intent context; plus two companion rules: prescriptive WHEN-triggers for tools/skills, and the report-back contract (outcome first, evidence attached, «Не успел проверить» tail).
- **`tests/verify_fable_snippets.py` — 28 structural checks**, wired into windows-verify CI. Positional, not substring-only: grounded-claims must be a numbered item inside `## Always`; the invariant section must sit inside the managed ITD block (sync only propagates that block); the goal reminder must live between Step 2 and Step 3; caveman's Fable note must precede Auto-Clarity and keep lite as default.

### Changed

- **`skills/caveman/SKILL.md` — Fable 5-class note in Intensity.** On Fable 5-era models, `full`/`ultra`/`wenyan-*` stay acceptable for working inter-tool-call messages but never for the final summary of a long task (vendor guidance bans arrow chains / invented abbreviations there — fighting the training degrades quality). Final summary auto-drops to `lite`, treated as an Auto-Clarity case.

### Decided (not implemented — backlog with triggers)

- Release C (review pack: coverage-first finder + refute-verifier + vendor-neutral JSON verdict contract) — next unit, goes through its own battle-test cycle.
- Release B (worktree isolation for file-only `/refactor` after a hook path-assumption audit; consolidate-memory in approval-diff mode only; per-role effort tiers) — after C.
- Release D (skill de-prescription A/B one at a time; SendMessage fix→re-review within one session, advice-only; evals for 2–3 skills with false-match history) — strictly retro-evidence-gated.
- Rejected outright (red team): Artifact publishing of review/retro reports (secret egress), background harness agents with mutation rights, spawn_task chips as a BACKLOG.md replacement.

---

## [1.49.0] - 2026-07-04

**The narration-final anti-pattern gets a mechanical detector — prompt-level contracts demonstrably don't hold.** Retro signal #1 (evidence ×5): during the single v1.48.0 release review, the code-reviewer subagent ended its message on «Now check…»/«Далее проверю…» five times — AFTER the named anti-pattern was written into the agent contract in v1.47.0. Same class of fix as `handoff-readiness.sh`: computational detect, minimal intervention, never a prompt plea.

### Added

- **`hooks/narration-final.sh` — SubagentStop hook, the 23rd hook.** When a subagent stops with a final message whose last paragraph STARTS with a narration opener (Now / Next / Let's / Let me / Далее / Теперь / Сейчас + a check/verify/test/run verb) and the message carries NO verdict marker anywhere (PASSED / BLOCKED / FAILED / PASSED_WITH_WARNINGS / FINAL STATUS / Verdict / Вердикт / Итог), the hook blocks the stop (`{"decision":"block"}`) and feeds a «finish with the deliverable in one message» instruction back to the subagent — the auto-resume that callers previously did by hand («выдай итог одним сообщением»). Verdict-finals are NEVER blocked, including the valid «Не успел проверить: …» tail; long final paragraphs (content, not announcements) pass through. Rails: at most `ITD_NARRATION_MAX_PINGS` (default 2) blocks per subagent transcript, `stop_hook_active` loop guard, `ITD_NARRATION_FINAL=0` kill switch, fail-open (exit 0) on any parse/IO error. Transcript resolution covers both harness layouts observed live: transcript_path = the subagent's own `subagents/agent-*.jsonl` (isSidechain entries) and transcript_path = the main session file (fallback to the newest `<session-stem>/subagents/agent-*.jsonl`).
- **`tests/verify_narration_final.py` — 13 functional checks**, both transcript layouts, positives (EN/RU/markdown-bold narration-finals block) and the negative space that matters more (verdict-final never blocked; narration opener mid-message + verdict final silent; «Не успел проверить» tail silent; long content paragraph silent; stop_hook_active / kill-switch / missing transcript / garbage stdin silent; ping cap 2 then pass-through; `ITD_NARRATION_MAX_PINGS=1` honored). Wired into windows-verify CI.

### Changed

- **`scripts/sync-to-active.sh`** — canonical registration now includes the `SubagentStop` event (DESIRED_HOOKS + the ITD-managed keys tuple), so both machines pick the hook up on the next sync; hook count 22 → 23 across README.md, hooks/README.md, docs/HARNESS_ENGINEERING_MAP.md, plugin.json, marketplace.json and the global CLAUDE.md template (P5 drift-guard stays green).
- **`agents/code-reviewer.md`** — the final-message contract now names the mechanical backstop and keeps the burden on the agent: the hook bounces a narration-final back at most twice, and it cannot see a verdict that was never written.

---

## [1.48.0] - 2026-07-04

**The two critical items of the 2026-07-04 battle-readiness audit: no hook is silently dead, no fixture is a stub.** The audit scored the arsenal 9/10 with two honest gaps — 9 hooks had only smoke coverage (the «silently dead safety layer» class /retro already caught twice), and 24 of 32 fixtures were pending stubs (claimed↔verified gap). Both closed.

### Added

- **`tests/verify_hook_depth.py` — 19 semantic checks for the 9 previously smoke-only hooks** (stuck-detection, crash-recovery, context-aware, context-budget, execution-trace, session-open-diagnostic, freeze, record-agent-skill, check-commit-completeness). Each hook is pinned on BOTH sides of its contract: fires on the trigger condition (3rd identical command; checkpoint after the interval; long-session warning; unbounded dump; out-of-scope edit under freeze; subagent gate-sentinel; BLOCK of an incomplete skill commit in a synthetic repo) and stays silent otherwise. Isolated per-test session ids, state cleanup, cross-platform; wired into windows-verify CI. Result of the first run: all 9 hooks are semantically alive — zero dead layers found.
- **Phase-2 fixture validation — `status: "contract"`** in `verify_snapshot.py`: for stdout/dialog/orchestrator skills whose behaviour is not file-shaped, the snapshot now machine-pins the DOCUMENTED contract — anchors quoted in the fixture's notes.md must exist verbatim in `skills/<name>/SKILL.md` (+ required sections, + harness-suite existence and CI wiring for goal/retro, + multi-skill support for scenario fixtures). Honest framing: this is a DRIFT GUARD (green at adoption, fails when a later SKILL.md edit drops a documented guarantee), not a live-behaviour test — live behaviour stays with battle/headless runs. New `--all` mode validates every fixture by status (absent Phase-1 outputs are SKIP, not failure) and is wired into CI.
- **`tests/gen_phase2_contracts.py`** — regeneration tool: harvests backtick/bold anchors from notes.md, keeps only those verbatim-present in SKILL.md, converts the fixture; fixtures with too few anchors stay pending for manual curation (it converted 20/24 automatically; doc, session-save, mcp-docs and the multi-skill daily-work fixture were curated by hand).

### Changed

- **All 24 pending fixture stubs are now active Phase-2 contracts** — `verify_snapshot.py --all`: contract_pass=24, pending=0, active_pass=1 (fixture-01 with its committed live output). The «заявлено↔проверено» gap for the skill arsenal is closed at the contract layer: 100% of fixtures are now machine-validated (25 validated vs 8 before).

---

## [1.47.0] - 2026-07-04

**The first live /retro run, implemented — the self-improvement loop pays for itself in one day.** Every item below traces to evidence in `docs/retros/RETRO-2026-07-04.md` (committed with this release): three live incidents and three telemetry signals from the v1.44–v1.46 release marathon, turned into fixes through the ordinary pipeline — exactly the FACTS → PROPOSALS → human-MERGE contract v1.46.0 shipped.

### Fixed

- **#1 `careful.sh` — `git branch -D` false positives (live ×3/day).** The file-global `re.IGNORECASE` made the case-sensitive force flag `-D` swallow the harmless soft `-d` (deleting an already-merged branch in the release pipeline) and even gh's `--delete-branch`. The pattern now runs in a case-sensitive inline group `(?-i:…)` and additionally covers `-df`/`-fd`/`--delete --force`; soft deletes stay silent.
- **#2 `check-tool-skill.sh` — the read-only Bash exemption never fired on a Windows+WSL setup (628 ceremony SKILL_BYPASS records, top reason «read-only lookup»; one hard block mid-approved-release).** `is_readonly_bash` now unwraps `wsl.exe [-d X] [--exec] bash -lc "…"` and judges the INNER command; the allowlist gains `cd`/`sleep`/`true`/`diff`/checksums and gh's read-only subcommands (`gh pr|run|issue|release view|list|checks|status|diff`). Hardened while there: `git branch`/`git remote` with mutating flags (`-d/-D/-m/-f`, `add/remove/set-url`) are no longer «read-only»; redirects still force the gate; `gh pr merge` and any wrapped mutation stay gated.
- **#6 `cost-tracker.sh` — a new ledger per hook spawn (500 stale files averaging ~1.3k tokens).** `session_id()` derived from `getppid()`, which differs on every spawn; it now reuses the shared per-day anchor (`claude-skill-session-anchor`, same convention as the enforcement hooks), so a working session accumulates ONE ledger; `CLAUDE_SESSION_ID` still wins. **Semantic shift, deliberate and documented (review I2):** without `CLAUDE_SESSION_ID` the budget ceiling now gates the DAILY aggregate across all sessions of the day («runaway day»), not a single session — the old per-spawn key made the ceiling dead entirely, which is worse. Plus daily-throttled rotation: ledgers older than 14 days are deleted (marker-guarded, best-effort).

### Added

- **#3 blind-telemetry warning** — `pre-flight-check.sh` warns once per session-start when `.itd-memory/` is in use but `events.jsonl` is missing/empty (the live project had 10+ PRs/week and ZERO unit events — VCR and /retro were blind); `/task` Step 3.5 now says to create the missing `events.jsonl` and write events.
- **#4 named reviewer anti-pattern** — `agents/code-reviewer.md` Final-message contract: a closing paragraph that starts with «Now check…»/«Далее проверю…» is process narration by definition (three more live incidents — every marathon release review needed a resume ping); the agent must either do that check immediately or write the verdict from what it has.
- **#5 producer-first rule** — `/task` Step 3f and a new `code-reviewer` check: a consumer of an existing file/ledger/format must be written (and reviewed) against the PRODUCER's actual code, with tests seeded from real producer samples — the exact class that produced 2 Important findings in one v1.46.0 review.
- **`tests/verify_v147_fixes.py`** — 19 functional checks pinning all of the above (careful case-sensitivity ± gh flag, wsl-unwrap exemption vs gated mutations/redirects, pre-flight hint on/off, stable session id + ledger rotation); wired into the windows-verify CI leg. `docs/retros/RETRO-2026-07-04.md` committed as the evidence trail.

---

## [1.46.0] - 2026-07-03

**The methodology closes its own feedback loop — /retro, a self-proposing improvement cycle that never eats the merge gate.** Self-diagnosis existed (meta-review, drift-guards, CI); the missing piece was turning the telemetry the harness already collects into concrete release candidates without waiting for a human to notice the signals. The loop is deliberately split three ways: FACTS from a script, PROPOSALS from the model (evidence-required), MERGE from the human via the ordinary release pipeline. Full autonomy (self-merge) is explicitly rejected: the approve/review gates are the very mechanism that keeps every release provably non-regressive. Skill count 39 → 40.

### Added

- **`/retro` skill (40th)** — Step 1 runs the scanner and pastes its output verbatim (facts come from the harness, never from conversation memory); Step 2 turns facts into RANKED proposals where every proposal carries {signal quoted from the scan, concrete change, effort S/M/L, risk + the suite that pins it}; Step 3 writes `docs/retros/RETRO-YYYY-MM-DD.md` and STOPS — the user decides what enters the backlog. Selection rules: no evidence — no proposal; anti-Goodhart (a change justified only by improving the methodology's own metric — VCR, meta-review pass-rate — is rejected; signals must be external: live failures, trigger false positives, bypass reasons, cost anomalies); ROADMAP signal-gating (one weak signal → backlog note, a release candidate needs two signals or one live incident); an EMPTY scan is itself a finding («телеметрия не пишется — почему?»), never a licence to invent signals.
- **`itd_retro_scan.py`** (`skills/retro/scripts/`, delivered by both sync-to-active and the plugin install) — deterministic stdlib aggregation of: unit events (`*/.itd-memory/events.jsonl` → per-project and global VCR, regressions, failed verifications), active goals (`GOAL.json` → N/M verified, backpressure with `blocked` counted as open, blocked reasons), pending gates/blockers (`STATE.json`), `SKILL_BYPASS` ledger grouped by TOOL with a reasons tail (the real `check-tool-skill.sh` records carry `tool`, not `skill` — review finding), and cost-tracker ledgers (USD derived from the persisted `total_tokens` with the hook's own rate — the ledger never stores USD; review finding). Markdown + `--json`; `--tmp-dir` override; malformed sources are skipped, never fatal; pipe-escaping and utf-8/replace decoding from day one (both are pinned regression classes from v1.45.0).
- **`tests/verify_retro_scan.py`** — 12 functional checks (mixed workspace with malformed sources, VCR math, blocked-in-backpressure, ledger aggregation, cost summing, markdown↔`--json` consistency, empty-workspace honesty, usage errors) on BOTH interpreters + a windows-verify CI step.
- **Routing + anchors** — `/retro` trigger block in `check-skills.sh` (методология-anchored phrases only: «ретроспектива методологии», «что улучшить в методологии», methodology/itd retro — bare «ретроспектива спринта», «sprint retro report», «retro style» do NOT fire), `tests/fixtures/fixture-32-retro/` (pending stub documenting the facts/proposals/merge contract), `/goal` + `/retro` rows added to the global CLAUDE.md template trigger map, `docs/retros/` home with a README.

### Changed

- Counts 39 → 40 skills across `plugin.json` (+ retro capability phrase), `marketplace.json`, both READMEs (Workflow table 4 → 5, I/O and model tables), `docs/templates/global-claude-md.md`, `docs/HARNESS_ENGINEERING_MAP.md` (recount at v1.46.0) and promotion-doc prose.

---

## [1.45.0] - 2026-07-03

**The /goal harness grows hands: transitions and handoff reports are made by scripts, not by the agent.** v1.44.0 shipped the persistent ledger; the remaining walkinglabs feature-list principles — «переходами управляет harness, а не агент» and the script-generated handoff reporter — land here as two stdlib tools INSIDE the skill folder (`skills/goal/scripts/`), so both `sync-to-active.sh` and the plugin install deliver them to target projects. Simulated end-to-end in a sandbox (activate → verify green → verify red stays → block → report → pre-flight) before release.

### Added

- **`itd_goal_verify.py` («ОТК»)** — the ONLY writer of `verified`: executes the unit's `verificationCommand` itself and records `evidence` from the actual run. Enforces the course's state machine: `--activate` (pending/blocked → in_progress, WIP=1 refused while another unit is open), verify only from `in_progress` (gate on passing; `pending` is refused with "activate first"), failure keeps `in_progress`, `--recheck` demotes a regressed `verified` back to `in_progress` (deliberate delta from the course's irreversible passing — the ledger reflects VERIFIED reality), `--block --reason` is fail-closed. Every transition appends a unit event with `actor: "harness"` to `events.jsonl` — VCR counts them automatically.
- **`itd_goal_report.py` (handoff reporter)** — deterministic session summary generated FROM the ledger (+ event tail): goal, N/M verified, backpressure (open units; 0 = done), state distribution, per-unit table with evidence, the receiving session's first action. `/handoff` and `/session-save` now paste its output verbatim (prose around, never numbers-by-memory); `--json` for machine use.
- **`blocked` unit state** in `goal.schema.json` (full course automaton: pending / in_progress / blocked / verified, plus `skipped`): `blockedReason` fail-closed in `validate_state.py`, blocked count surfaced in the pre-flight goal line, unblock via `--activate`.
- **«ставлю цель» trigger** — `check-skills.sh` `поставь\s+цель` widened to `(?<![а-яё])(?:постав\w*|став(?:лю|им))\s+цель` (covers «ставлю/ставим/поставь/поставим/поставил цель»; the lookbehind keeps «сопоставь/составь/приставлю…» silent — review finding), phrase added to `/goal` SKILL.md + fixture-31 sample prompts (user-confirmed backlog item).
- **`tests/verify_goal_tools.py`** — 20 functional checks of both tools (WIP=1, gate on passing, evidence, regression demote, fail-closed block, reporter consistency, ledger validity, blocked-only backpressure, pipe escaping), cross-platform by construction; wired into the windows-verify CI leg. The Windows run immediately caught a real cp125x decode bug (em-dash 0x97 from a child process kills a utf-8 reader) — both tools now pin `encoding="utf-8", errors="replace"` on subprocess capture and reconfigure their own stdout/stderr.
- **Review findings fixed pre-merge** (code-reviewer PASSED_WITH_WARNINGS): both tools were blocked-blind in their "no open units / закрыть цель" messages (a blocked unit IS open — now the verifier lists blockers after the last actionable unit and the reporter says «все открытые юниты заблокированы» instead of suggesting closure); Markdown-pipe escaping in report table cells; explicit shell=True trust-model + `--recheck` asymmetry notes in the verifier docstring; a hand-corrupted ledger with >1 `in_progress` now prints a WIP=1 violation warning.

### Changed

- `/goal` SKILL.md — new «Инструменты харнеса» section + Step 2 rewritten: activation/verification go through the ОТК script (manual fallback only without python3, and it must be said aloud); Self-validation and Rules extended («Харнес, не агент»). `/handoff` Step 1 and `/session-save` Step 1 call the reporter and embed its output as-is. `HARNESS_ENGINEERING_MAP.md` §4.4: the last feature-list principle marked closed, with the one deliberate delta (reversible passing) recorded honestly.

---

## [1.44.0] - 2026-07-03

**Long-goal mode (`/goal`) — the persistent unit ledger a brownfield goal was missing.** For greenfield the "one phrase → whole pipeline" mode already existed (`/autopilot`); in brownfield a goal spanning multiple sessions lived in prose (`session_*.md`) and in the model's head — a dead session was resumed by re-reading text, not programmatically. This release activates the deferred T2 candidate ("persistent multi-feature ledger", HARNESS map §4.2/§5.4/§7) on its second signal, per the ROADMAP's own criteria — as a thin layer over the existing v1.41 unit mechanics, not an orchestrator (ADR-001). Skill count 38 → 39.

### Added

- **`/goal` skill (39th)** — decomposes a multi-session goal into ORDERED verifiable units (binary `criterion` + executable `verificationCommand`), shows the decomposition and **waits for explicit user approval** before writing anything; then drives units ONE at a time (WIP=1) through the standard `/task` pipeline (scope → plan → code → `/test` → `/review`), flips a unit to `verified` only with evidence from an actual `verificationCommand` run, and logs unit events to `events.jsonl` — the VCR metric counts goal work automatically. **Resume, never recreate:** with an active `GOAL.json` present, `/goal` continues from the first non-verified unit. NOT a gate — never bypasses `/review`, `/test`, the DoD, or any hook; brownfield-first (deliberately absent from the `_GREENFIELD_SKILLS` suppression list).
- **`.itd-memory/GOAL.json` ledger** — `docs/templates/itd-memory/GOAL.example.json` + `goal.schema.json` (goal statuses `active|done|abandoned`; unit statuses `pending|in_progress|verified|skipped`). `scripts/validate_state.py` now dispatches on the `GOAL` filename and validates the ledger fail-closed: empty goal/criterion/verificationCommand, a `skipped` unit without `skippedReason`, duplicate/dangling unit ids, or a `done` goal with open units are FAILURES.
- **Pre-flight goal injection** — `hooks/pre-flight-check.sh` `itd_state_context` also reads `GOAL.json` (works even without `STATE.json`) and injects "Цель (/goal): X — N/M юнитов verified, текущий `G-k`" plus a resume hint, so a fresh session picks the goal up on entry instead of re-deriving it.
- **Routing + regression anchors** — `/goal` trigger block in `hooks/check-skills.sh` (долгая цель / режим цели / поставь цель / продолжай цель / goal mode / resume the goal / …), `tests/fixtures/fixture-31-goal/` (pending stub in the memory-write bucket of fixture-09/18; the GOAL.json artifact itself is machine-checkable via `validate_state.py` today), `/handoff` + `/session-save` checklists now carry `GOAL.json` (durable artifact to read/refresh; a verified goal unit is an incremental checkpoint trigger).

### Changed

- Counts 38 → 39 skills across `plugin.json`, `marketplace.json`, both READMEs (incl. Workflow table 3 → 4 skills, I/O and model-recommendation tables), `docs/templates/global-claude-md.md`, `docs/HARNESS_ENGINEERING_MAP.md` (recount at v1.44.0; T2 row and the §4.4 "honest remainder" updated — the multi-unit persistent ledger is now implemented as `GOAL.json`).

---

## [1.43.1] - 2026-07-03

### Fixed

- **`tests/verify_snapshot.py` `_API_ENDPOINT_RE`** — counts the fourth legitimate endpoint shape: method in its OWN markdown-table cell, path in the next (`| GET | /api/v1/... |`). Caught by the first live headless run of fixture-01 (the generated architecture doc's API section held 40+ endpoints in exactly this shape yet scored 0 against the `min_api_endpoints: 15` contract → false FAIL); same output re-validates 33/33 after the fix. Regression pinned by the new `tests/verify_endpoint_regex.py` (4 positive shapes + 5 negative cases: table headers, separator rows, prose with method words).

### Added

- **`docs/greenfield-live-run-2026-07-03.md`** — the act of the first live greenfield run: kickstart Phase 1–2 via the standard headless fixture runner (33/33, $1.02) + a headless probe of the v1.40.0 initialization phase (Phase 3 steps 1–8): `PHASE3-PROBE-DONE 6/6`, independently verified by hand (pytest 1 passed in the project venv, 13 `.itd/` contracts, `validate_state.py` OK, 2 git checkpoint commits). Operational notes: headless claude from Windows requires a login shell (`wsl.exe --exec bash -lc`); Phases 4–5 remain signal-gated ($10–25/run). Greenfield score on the audit scale: 8 → 9.

## [1.43.0] - 2026-07-03

**The model council, done the ITD way: one external seat at decision points.** Answers the "council of models" request (second signal for the v1.21-rejected "adversarial debates" candidate) without building an orchestrator: role diversity already exists (10 subagents; /advisor and /blueprint 2.5 already synthesize multi-perspective output), so the only un-captured win is a genuinely DIFFERENT model family at the table. Same-model persona ensembles buy little for 3-4× tokens; a foreign model has foreign blind spots.

### Added

- **`skills/_shared/external-seat.md`** — the shared protocol: scrubbed 30–60-line decision synopsis (context, chosen variant, rejected alternatives, internal skeptic's top challenges) → codex → gemini → **skip** (deliberately NO native fallback — the internal adversarial is already in the room; the seat's value is the foreign model). Same invariants as /cross-review: egress opt-in (`CROSS_REVIEW_EGRESS_OK=1` / `.cross-review-egress-ok`), scrub-before-send, fail-open (never a gate), mandatory provenance, advisory-only (no veto). Reuses the verified CLI adapters from cross-review (stdin-from-file, config-error retry, timeout).
- **`/grill-me` Step 3.5** — for MAJOR decisions only (architecture, prod migration, strategic pivot): after the internal axes, offer the external seat; findings merge with `[external: codex|gemini]` tags; agreement between families elevates priority, disagreement is surfaced as a user fork, never resolved silently. Step 4 now names who sat at the table.
- **`/blueprint` Step 2.5 sub-step 2.5** — the external seat alongside Devil's Advocate (Full mode): both-families challenges get elevated priority in the ADR; forks go to the user with provenance.

Scope note: /strategy and /migrate-prod are named as next candidates in the protocol doc, signal-gated — not wired in this release. Docs-only; no hook/count changes; the on-demand `/cross-review` and its pre-commit hook are untouched.

## [1.42.0] - 2026-07-03

**Platform symmetry + the top-10 of the deep effectiveness audit.** A full audit (pipe-tests of every hook, all verify suites, live-session evidence) scored the methodology ~8.5/10 on WSL but ~6.5/10 on Windows: ten hooks and four skill snippets exchanged sentinels through a literal `/tmp` that means three different directories across Windows-python / Git-Bash / WSL. This release makes the two platforms symmetric and lands every item of the audit's top-10.

### Fixed

- **The "/tmp on Windows" bug class (audit #1).** All state/sentinel paths in `pre-flight-check`, `crash-recovery`, `context-aware`, `risk-score`, `session-open-diagnostic`, `cost-tracker`, `stuck-detection` now build from `tempfile.gettempdir()`; cross-component READERS (`check-review-before-commit`, `risk-score`, `freeze`, `careful`) scan BOTH the platform temp dir and literal `/tmp`; skill snippets that WRITE sentinels (`/review`, `/test`, `/security-audit`, `/migrate`) and freeze-state writers (`/bugfix`, `/refactor`, `/perf`) dual-write to both. Result: the review-gate sees a real `/review` on Windows, cost-tracker's ledger reaches session-save Step 4.6, risk/stuck/crash/context-aware come alive on the Windows machine.
- **Session-restart tolerance (audit #2).** `risk-score` gains the same fresh-mtime glob fallback the review/DoD gates already had — pid-based session ids no longer zero out review/security credit after a restart.
- **`careful.sh` precision (audit #10).** `rm -f file` is no longer mislabeled "rm -rf": recursive delete and plain force delete are separate patterns with honest labels (live false-positives 2026-07-03, twice in one session).
- **`freeze.sh` de-phantomed (audit #9).** Registered in the canonical set (no-op until a scope state file exists, so always-on registration is free); hooks/README no longer promises a non-existent `/freeze` skill — the state file is the interface; `verify-sync-to-active.sh` EXEMPT list and the registration drift-guard updated accordingly.

### Added

- **`/task` Step 3f — feature pipeline for brownfield (audit #3).** The main daily case (new feature in an existing project) finally has a route: scope (SCOPE_LOCK/unit) → short plan + approval → surgical implementation → `/test` (fail-closed) → `/review` → commit per repo rules. New routing-matrix row + trigger phrases (SKILL.md + `check-skills.sh`, no trigger drift).
- **`.github/workflows/windows-verify.yml` (audit #4)** — windows-latest CI leg running the platform-sensitive suites; the exact channel that would have caught the `/tmp` class before it shipped.
- **`/review` Step 0.4 — honest target-path resolution (audit #5).** A path in `$ARGUMENTS` is resolved and used (`cd`/`git -C`), unreachable targets are delegated to the `code-reviewer` agent with the explicit path — never a silent review of cwd (live incident 2026-07-02).
- **Final-message contract in all 10 agents (audit #6)** — the last message must BE the structured deliverable; ending on process narration is a contract violation; unverified items go under an explicit "Не успел проверить" list (two live truncated reviews 2026-07-02).
- **`/adopt` Step 2.0 — user-level install detect (audit #7):** when ITD hooks are already registered in `~/.claude/settings.json`, project-level hook duplication is skipped (only `permissions` merge) — no double-firing, no dead bare-`.sh` commands on Windows.
- **`tests/verify_platform_tmp_and_new_hooks.py` (audit #8)** — static regression guard for the literal-`/tmp` class + functional pipe-tests for `wip-gate.sh` and `handoff-readiness.sh` (the only two hooks that lacked automated coverage). Cross-platform by construction; wired into the Windows CI leg.
- **`scripts/itd_trace_summary.py`** — a reader for `execution-trace.sh` telemetry (per-tool breakdown, top targets, idle gaps >60s): observability nobody reads is a ritual, now it feeds session wrap-ups and harness debugging.
- **Depth upgrades:** `agents/architect.md` Required-coverage contract (7 mandatory sections incl. alternatives/risks/non-goals); `agents/business-analyst.md` gets the missing `model: opus` pin; fail-closed gates added to `/perf` (no before/after measurement → UNVERIFIED), `/doc` (every claim traced to code; unverified commands marked), `/strategy` (plans stay `draft` until explicit user approval).

Verified: full verify-suite matrix on WSL + functional pipe-tests of the touched hooks on BOTH interpreters (WSL python3 and Windows python.exe); code-reviewer review before commit. MINOR — additive + bug-class fix.

## [1.42.0] - 2026-07-03

**Platform symmetry: the Windows half of the sentinel chain lives again, /task gets the missing feature route, and every audit top-10 item ships.** The 2026-07-02 deep audit scored the methodology 8.5/10 on WSL but 6.5/10 on Windows — the real work machine — because ~10 hooks and 7 skill snippets exchanged sentinels through three mismatched temp dirs (literal `/tmp` under Windows python = `C:\tmp`; Git-Bash `/tmp` = `%TEMP%`; `gettempdir()` = `%TEMP%`). This release closes all ten audit findings.

### Fixed

- **The "/tmp on Windows" bug class (audit #1/#2).** Hook-owned state now writes to `tempfile.gettempdir()` (pre-flight cwd-history, crash-recovery, context-aware, risk-score state, session-open-diagnostic sentinel, cost-tracker ledger, stuck-detection); cross-component readers scan BOTH temp dirs (check-review-before-commit marker+glob, risk-score sentinels, freeze, careful); skill snippets dual-write via `tee` (review/test/security-audit/migrate sentinels; bugfix/refactor/perf freeze state). Session-restart tolerance rides the existing mtime-window fallbacks; risk-score deliberately keeps NO cross-session glob (its stricter contract, verify_risk_score case 9, is preserved and documented in-code).
- **`careful.sh` precision (audit #10):** `rm -r`/`rm -rf` (recursive) and `rm -f` (force, non-recursive) are now separate patterns with honest labels — live false-positive "rm -f flagged as rm -rf" eliminated.
- **`freeze.sh` de-phantomed (audit #9):** registered in the canonical set (no-op until a scope state file exists; matcher `Write|Edit|MultiEdit|NotebookEdit`), `OPT_IN_HOOKS`/`EXEMPT` emptied, hooks/README no longer promises a non-existent `/freeze` skill — the state file is the interface.

### Added

- **`/task` Step 3f — feature pipeline for brownfield (audit #3):** the main daily case (new feature in an existing project) now has a route — scope (SCOPE_LOCK/unit) → short plan + approval → surgical implementation → `/test` → `/review`; option 13 in the routing question, matrix row, trigger phrases (SKILL.md + check-skills.sh, no trigger drift).
- **`.github/workflows/windows-verify.yml` (audit #4):** windows-latest CI leg running the platform test + registration/count guards + skill profiles + meta-review — the class of bug this release fixes can no longer ship unnoticed.
- **`tests/verify_platform_tmp_and_new_hooks.py` (audit #8):** T1 static guard (no hook may build paths from literal `/tmp/claude-`), T2 wip-gate functional (hint / in-scope silence / kill-switch), T3 handoff-readiness functional (dirty / clean / kill-switch). 7/7 green on BOTH interpreters (WSL python3 and Windows python.exe; the run itself caught and fixed a cp1251-decode trap in subprocess capture).
- **`/review` Step 0.4 — honest target-path resolution (audit #5):** args naming another repo are resolved (cd/`git -C`), unreachable targets are delegated to the code-reviewer agent instead of silently reviewing cwd; the resolved target is named in the report header.
- **Final-message contract in all 10 agents (audit #6):** the final message must BE the structured deliverable; ending on process narration is a contract violation (two live truncations 2026-07-02); callers bounce a missing verdict with one ping. Plus: `architect` gains a 7-point Required-coverage depth contract, `business-analyst` gets its missing `model: opus` pin.
- **`/adopt` Step 2.0 (audit #7):** detects an existing user-level hook registration and skips project-level duplicates (live OneOfS case — double-firing hooks + bare `.sh` on Windows).
- **Fail-closed gates for the three gate-less skills:** `/perf` (no before/after measurement → UNVERIFIED, never "optimized"), `/doc` (every claim traced to code; unverified marked), `/strategy` (plans are `draft` until explicit user approval).
- **`scripts/itd_trace_summary.py`:** a reader for execution-trace telemetry (span, per-tool counts, top targets, idle gaps >60s) — the trace stops being write-only observability.

Verified: platform tests 7/7 on both interpreters; registration 9/9; skill-enforcement 10/10; brownfield 24/24; DoD 19/19; risk 9/9; cost 7/7; pii PASS; agent-sentinel 10/10; cross-review 10/10; triggers no drift; profiles 38 OK; meta_review PASSED; verify-sync OK (22 registered + 0 exempt); py_compile all hooks. Review: code-reviewer PASSED_WITH_WARNINGS — both Importants fixed pre-commit (freeze-snippet mkdir parity; NotebookEdit restored to the freeze/wip-gate matcher group). MINOR — additive + behavior-preserving fixes.

## [1.41.1] - 2026-07-02

### Fixed

- **`skills/cross-review/references/cli-adapters.md` — hardened by a live end-to-end probe of the degradation chain.** (1) The argv fallback (`codex exec "$PROMPT"`) now carries an explicit `ARG_MAX` warning — on a ~3.7k-line diff it dies with "Argument list too long" (rc=126, reproduced live); for big diffs the recipe is stdin from a file (`codex exec - < "$PROMPT_FILE"`). (2) Documented two real "unavailable" shapes with their handling: a startup config error (`unknown variant 'priority'` in `service_tier` after a CLI version change — one retry with `codex -c 'service_tier="flex"' exec …`, then degrade) and a cloud handshake timeout (`timed out waiting for cloud requirements after 15s` — no retry, fall through). The pre-commit hook (`cross-review-precommit.sh`) was already stdin-based and needs no change. Docs-only; no code or count change.

## [1.41.0] - 2026-07-02

**Scope control & verified completion: WIP=1, the state surface reaches the session, VCR is measured, and a soft activation gate watches the scope.** Closes the four findings of the /advisor check against the scope-control principle (WIP=1 / explicit completion evidence / externalized scope surface / VCR).

### Added

- **Explicit WIP=1 rule** in both CLAUDE.md templates (`skills/adopt/references/claude-md-template.md` Step 1.5, `docs/templates/global-claude-md.md` Always #6): one active unit at a time; the next starts only after the current one passes end-to-end verification; "also refactor B while doing A" goes to the backlog, not the diff.
- **`hooks/wip-gate.sh` — 22nd hook (PreToolUse Write|Edit|MultiEdit, soft).** Computational detect: `currentUnit.status` ∈ `verifying`/`recovery_required` AND the edited path is outside `SCOPE_LOCK.md → Allowed Change Areas` → additionalContext hint to finish the current unit's verification or explicitly reclassify. Silent without `.itd-memory/` or without a real declared scope; rate-limited (`ITD_WIP_GATE_RATE_MIN`, 30 min), kill-switch `ITD_WIP_GATE=0`. A hard "VCR<1.0 → deny activation" is deliberately NOT built: unit activation has no tool-call signature, and "is this a new task?" is semantic (map §8.3 — hint, not deny). Registered in `sync-to-active.sh` + `/adopt` settings template.
- **`pre-flight-check.sh` reads `.itd-memory/STATE.json`** — injects `currentUnit` (id/goal/status + WIP=1 reminder), `nextAction`, blockers, and unfinished gates at session start. The machine-readable scope surface existed but no session-entry hook ever read it; now a fresh session knows the active unit without /handoff.
- **VCR (Verified Completion Rate) in `scripts/itd_metrics.py`** — `vcr = unitsVerified / unitsActivated`, counted by distinct unit names from `events.jsonl` `type:"unit"` events (`activated`/`verified`; convention documented in `docs/templates/itd-memory/events.example.jsonl`, which now carries both example events).
- **`/task` Step 3.5 — unit bookkeeping** (only when `.itd-memory/` exists): before activation, an unfinished `currentUnit` forces an explicit user choice (finish verification vs reclassify); on activation/verified completion `/task` updates `currentUnit` and appends the unit events that feed VCR and `wip-gate.sh`.

### Changed

- **Hook counts 21 → 22** across all asserted surfaces (`plugin.json` + version 1.41.0, `marketplace.json`, map §3/§4.1/§8, `global-claude-md.md`, `README.md`/`README.ru.md` + badges, `hooks/README.md` + new table row).
- **`docs/HARNESS_ENGINEERING_MAP.md`** — §4.4 gains the v1.41.0 addendum (WIP=1 / state-at-entry / VCR, with the honest note on why hard activation-deny is not implementable); §8.1 quadrant gets the `wip-gate`*** soft-exception footnote; §8.2 new row; soft-hook count 13 → 14.

## [1.40.0] - 2026-07-02

**The Anthropic long-running-agents port: initialization is now a real phase, and sessions are nudged to end handoff-ready.** An /advisor audit against the Anthropic research ("Effective harnesses for long-running agents") found the proactive half of the init/handoff discipline existed only as templates and norms — no skill scaffolded the `.itd/` contracts, nothing enforced session-end readiness, and the harness map was structurally blind to the axis. This release closes all five findings.

### Added

- **`hooks/handoff-readiness.sh` — 21st hook, first on the `Stop` event.** Computational detect (dirty git tree AND no fresh `session_*.md` in the project memory dir) → soft `systemMessage` hint to run `/session-save` or `/handoff` and leave a clean checkpoint. Rate-limited (`ITD_HANDOFF_RATE_MIN`, default 45 min), freshness window `ITD_HANDOFF_FRESH_MIN` (default 120 min), kill-switch `ITD_HANDOFF_READINESS=0`, fail-safe exit 0. Per map §8.3 the "am I done?" decision is semantic, so this is a hint, never a deny. Registered in `sync-to-active.sh` `DESIRED_HOOKS` (new `Stop` event key, also added to the drift-compare `KEYS`) and in `/adopt`'s project-settings template.
- **`/kickstart` Phase 3 is now the dedicated initialization phase** (steps 7–8): scaffolds `.itd/` (13 contracts) + `.itd-memory/STATE.json` + empty `events.jsonl`, requires the test framework to land **with one passing example test**, and gates exit from the phase on a new **Initialization Acceptance Checklist** (bootstrap-from-scratch works; ≥1 passing test; "how to run/test" answerable from repo contents alone; IMPLEMENTATION_PLAN.md with ≥3 steps; everything committed as the init checkpoint).
- **`/adopt` Step 3.5 — optional `.itd/` + `.itd-memory/STATE.json` scaffold for brownfield** (recommended, user may decline with «без .itd» — the v1.39.0 opt-in tradeoff stands). Idempotent: never overwrites an existing `.itd/`. Closes the "templates without a creator" gap for adopted projects; `docs/CONTRACTS.md` now names the creators instead of declaring a scaffold no skill performed.
- **`starters/` env-boot norm — mandatory `commands.bootstrap`** in every `STARTER.json` (all 5 starters updated): one non-interactive command that brings the environment up from a cold clone. Documented in `starters/README.md`; verified by the `/kickstart` Phase 3 checklist. Deliberately no separate mechanism — the norm lives in starters.
- **`docs/HARNESS_ENGINEERING_MAP.md` §4.4 — new axis "I: Initialization phase & handoff-readiness"** (I1–I7, per the Anthropic source), with the honest residual (persistent `feature_list.json`) linked to §5.4/§7. §6 summary and the §8 hook classification (21 hooks, new feedback×computational row) updated; §7/§5.4 T2 trigger extended with the autopilot/AFK scenario (progress must survive session death programmatically).
- **`docs/HARNESS_ENGINEERING_MAP.md` §4.1/§6 — two-layer framing.** Records that ITD realizes harness engineering on two layers: *operating* (ITD is itself a harness over Claude Code) and *output* (the Day-3/5 ports added врезки that teach/audit building the harness of the user's own product — memory/context, eval loops, zero-trust guardrails). Docs-only; no code or count change.
- **`docs/competitive-analysis.md` §9 — external validation via the Google whitepaper *The New SDLC With Vibe Coding*** (Osmani, Saboo, Kartakis, 2026). Maps the paper's framework (structure > vibes, skills as dynamic context, hooks as guardrails, tests + evals, harness engineering, the "last 20%", model routing, context engineering as OpEx lever) onto concrete idea-to-deploy mechanisms — positioning the methodology as the plugin-form realization of the new SDLC, with the v1.31.0 enrichments closing the previously-honest gaps. Marketing/positioning only; no code or count change.

### Changed

- **Hook counts 20 → 21** across all asserted surfaces: `plugin.json`, `marketplace.json`, `docs/HARNESS_ENGINEERING_MAP.md` §3/§8, `docs/templates/global-claude-md.md`, `README.md`/`README.ru.md`, `hooks/README.md` (+ new table row for `handoff-readiness.sh`). The v1.39.0 count drift-guard (`verify_registration_and_counts.py`) enforces the new value.
- **`sync-to-active.sh`** — ITD-managed settings events now include `Stop` (drift-compare `KEYS` + merge comment); the platform-aware Windows rewrite applies to the new hook automatically.
- **`/adopt` self-validation** — hook checklist now lists all 7 PreToolUse commands (including the previously-missing `cross-review-precommit`) and the `Stop` hook.

Verified: `verify_registration_and_counts.py`, `verify-sync-to-active.sh`, `meta_review.py`, `python3 -m py_compile hooks/handoff-readiness.sh`, JSON validity of all touched manifests/starters. MINOR — additive.

## [1.39.0] - 2026-07-01

**CLAUDE.md methodology block now syncs across machines, and two drift-guards lock the wins in place.** Closes the audit's most valuable remaining items (points 3/4/5 — the ones worth chasing); points 1/2/6 are deliberate design tradeoffs (advisory complexity routing, commit-count brownfield detect, opt-in `.itd/` contracts) where forcing "10/10" would reduce effectiveness, so they're left as-is.

### Added

- **`docs/templates/global-claude-md.md` + `sync-to-active.sh` Step 5/5 — the global CLAUDE.md methodology block now syncs (point 3).** The repo owns the MANDATORY methodology block between `<!-- ITD:BEGIN -->`/`<!-- ITD:END -->` markers; sync replaces ONLY that marked region in the active `~/.claude/CLAUDE.md`, preserving everything outside (personal sections like token-efficiency prefs). Backup + dry-run aware + idempotent. Closes the "CLAUDE.md can silently drift between machines" gap — both installs are now kept in lockstep by the same mechanism as skills/hooks.
- **`tests/verify_registration_and_counts.py` — two drift-guards (points 4 + 5).** (4) Every hook file must be in the canonical registration set (`DESIRED_HOOKS`) OR the explicit opt-in allowlist (`freeze`) — turns the exact v1.37.0 root-cause (hooks shipped but silently unregistered) into a failing test. (5) The skill/agent/hook counts asserted in `plugin.json`, `marketplace.json`, `HARNESS_ENGINEERING_MAP.md`, and the CLAUDE.md template must all equal the actual on-disk counts — stops stale "34 skills / 16 hooks"-style docs.

### Fixed

- **`docs/HARNESS_ENGINEERING_MAP.md` — version label v1.37.0 → v1.38.0.** Independent audit flagged the map self-stamping v1.37.0 while `plugin.json` was v1.38.0; counts already correct, label aligned. Docs-only.

### Changed

- **`sync-to-active.sh` — step count 4 → 5**; backup cleanup now also prunes `CLAUDE.md.bak-*`.

Verified: Step 5 sandbox (up-to-date / update / prepend / create — personal section preserved in every case); `verify_registration_and_counts` 9/9; `verify_brownfield_and_gate` 24/24; `verify_skill_enforcement` 10/10; `meta_review` PASSED; `bash -n` clean. MINOR — additive.

## [1.38.0] - 2026-07-01

**`sync-to-active.sh` is now platform-aware — a Windows `~/.claude` can be synced from WSL, no more hand-editing.** Closes the last piece of the v1.37.0 audit's "default-on Win+WSL" gap: the sync script previously emitted only bare `~/.claude/hooks/X.sh` commands (correct on WSL, which runs them via shebang), so the Windows install had to be hand-maintained — Windows invokes `.sh` hooks through `python.exe`, not a shebang.

### Changed

- **`scripts/sync-to-active.sh` — platform-aware hook-command emission.** On a Windows target each `~/.claude/hooks/X.sh` is rewritten to `"<python.exe>" -X utf8 "<C:/…/.claude>/hooks/X.sh"`. Target detection: auto (Git-Bash / MSYS / Cygwin host) or explicit `ITD_TARGET_OS=windows` (for the WSL → `/mnt/c` case). The interpreter comes from `ITD_WIN_PYTHON` (or is discovered on PATH); `/mnt/c/…` and `/c/…` normalise to `C:/…`. Unix/WSL behaviour is unchanged (bare shebang paths). The foreign-key merge (SessionStart) and the ITD-only drift check both run on the platform-effective set, so re-runs are idempotent on either OS. Added a `python3`→`python` launcher fallback so the script also runs under Git-Bash. Example: `ITD_TARGET_OS=windows ITD_WIN_PYTHON="C:/…/python.exe" CLAUDE_HOME=/mnt/c/Users/<you>/.claude bash scripts/sync-to-active.sh`.

Verified: Windows wrapper form + `/mnt/c`→`C:` conversion + SessionStart preserved + idempotent 2nd run; unix mode unchanged; `bash -n` clean. MINOR — additive, backward-compatible.

## [1.37.0] - 2026-07-01

**Close the "orphan hook" gap — self-correction and observability hooks are now actually wired, and the two machines converge.** A 6-dimension methodology audit (effectiveness across project types, greenfield/brownfield, default-on Win+WSL, component wiring, Harness Engineering, Agentic Engineering) found that `careful`, `execution-trace`, `stuck-detection`, `crash-recovery`, and `context-aware` shipped into `~/.claude/hooks/` but were **not in the canonical registration set** — so they silently never fired, while `HARNESS_ENGINEERING_MAP.md` counted them as active (declaration ≠ reality). `careful` worked on one machine only because it had been added by hand.

### Changed

- **`scripts/sync-to-active.sh` — canonical hook registration now includes the always-on self-correction / observability / guardrail hooks.** Added to `DESIRED_HOOKS`: `context-aware` (UserPromptSubmit), `execution-trace` (PreToolUse `*`), `careful` (PreToolUse `Bash`), `stuck-detection` + `crash-recovery` (PostToolUse `*`). `freeze` stays opt-in by design. Registered ITD hooks 14 → 19 (of 20 files).
- **`scripts/sync-to-active.sh` — the settings.json patch is now a MERGE, not a full replace.** It updates only the ITD-managed event keys (UserPromptSubmit / PreToolUse / PostToolUse) and **preserves foreign event keys** (e.g. a SessionStart hook registered by another plugin such as context-mode), which the old full-replace silently clobbered. The drift check compares only the ITD keys, so a foreign key no longer reads as perpetual drift.
- **`docs/HARNESS_ENGINEERING_MAP.md` — updated to v1.37.0.** Counts 33→38 skills / 16→20 hooks; `careful` reclassified opt-in → always-on; the 4 previously-missing hooks (`pii-egress-guard`, `record-agent-skill`, `risk-score`, `cross-review-precommit`) added to §8.2; §8.3 recount 7→8 blocking / 9→12 soft; a v1.37.0 note records the declaration↔reality fix.

### Added

- **`docs/project-profiles.md` — "Recommended skill sets by scenario" matrix + complexity axis.** Formalizes project-kind/complexity → skill-set, removing the last heuristic gap for point 1 of the audit (projects of different kind/complexity).

Deploy-time config facts fixed outside the repo (per-machine): WSL was missing `careful` + `CAREFUL_MODE=1` and both machines' `settings.json` diverged — resolved by re-syncing both to the new canonical set + adding the env var on WSL. MINOR — additive registration + docs; no skill/agent count change.

## [1.36.0] - 2026-07-01

**Brownfield profile is now auto-detected — no per-project marker required.** Follow-up to v1.35.0: `itd-profile` no longer needs a hand-placed marker in each project. `hooks/check-skills.sh` resolves it from repo maturity, with an explicit marker overriding in either direction.

### Changed

- **`hooks/check-skills.sh` — `itd-profile` auto-detection.** Resolution order: (1) an explicit `itd-profile: brownfield|greenfield` (or `<!-- itd:… -->`) in the project's `CLAUDE.md` wins in either direction; (2) otherwise auto-detect by repo maturity — an established git history (`git rev-list --count HEAD` ≥ `ITD_BROWNFIELD_MIN_COMMITS`, default 25) is brownfield, a fresh/empty project (fewer commits, or no git) is greenfield. A mature repo (e.g. a 900-commit line-of-business app) becomes brownfield with zero configuration; a new project keeps the greenfield pipeline. The git call runs only when a greenfield hint actually fired, so ordinary prompts pay nothing.
- **`hooks/check-skills.sh` — suppression matches a hint's primary skill.** A greenfield hint is filtered by its own `/skill` (the one after `используй`), never by a greenfield skill merely referenced in the prose — fixes the `/adopt` hint (which mentions `/blueprint`) being wrongly suppressed on a brownfield project (latent since v1.35.0, exposed by auto-detection).

### Added

- `tests/verify_brownfield_and_gate.py` — 5 new cases for auto-detection (mature repo → brownfield, fresh repo → greenfield, explicit greenfield/brownfield override, non-git dir → greenfield); 24/24 total.

Escape hatch: a mature repo that still wants the greenfield pipeline for a big new feature sets `itd-profile: greenfield`. See `docs/project-profiles.md`. MINOR — backward-compatible; explicit v1.35.0 markers keep working.

## [1.35.0] - 2026-07-01

**Methodology fits brownfield feature-work, not just greenfield builds — plus two false-positive fixes to the skill gate.** Five opt-in/additive changes that make the methodology effective on a mature existing codebase (feature/maintenance work, where the project's own `CLAUDE.md` is the real source of truth) without weakening the greenfield pipeline, which stays the default. Motivated by an honest self-audit on a large brownfield accounting project (OneOfS payment calendar): the greenfield pipeline was ceremony there, the skill-decision line was ~90% "не нужен" noise, and keyword triggers mis-fired (the word *deploy* inside "idea to deploy"; bare *переписать* on a letter edit).

### Added

- **Project profile marker `itd-profile: brownfield`** (`hooks/check-skills.sh`, `docs/project-profiles.md`). When a project's own `CLAUDE.md` declares it, greenfield-pipeline hints (`/project`, `/blueprint`, `/discover`, `/kickstart`, `/guide`, `/strategy`, `/market-scan`, `/autopilot`) stop firing on day-to-day feature work; `/task`, `/bugfix`, `/refactor`, `/review`, `/test`, `/doc`, `/perf`, `/session-save`, `/migrate`, `/security-audit` stay active. Opt-in only — unset projects are unchanged. `/adopt` can stamp it when onboarding a legacy project.
- **Domain marker `itd-domain: data-sensitive`** (`docs/project-profiles.md`). Declares a project that mutates production/financial/irreplaceable data; standing convention = model the change read-only first, show before/after, get explicit confirmation, then mutate — never a data-mutating op straight from an ad-hoc command. Reinforces the existing `careful.sh`/`risk-score.sh` guardrails; opt-in.
- **Memory as continuity backbone** (`skills/session-save/SKILL.md` → v1.8.0). Explicit auto-checkpoint triggers on every meaningful state change — a subphase/roadmap item done, a migration applied to a test/prod DB, *before* a risky/irreversible op (deploy, force-push, mass re-post), after an external artifact (letter/report/PR) is sent — framed as cheap incremental checkpoints, not one big end-of-session save.

### Changed

- **`hooks/check-tool-skill.sh` — read-only Bash no longer demands a skill decision.** Pure inspection commands (`ls`/`cat`/`grep`/`find`/`git status|log|diff|show` …) skip the gate silently. The command is split on `; | && ||` and *every* segment must be read-only; any redirection (`>`, `>>`, `tee`) or unrecognised segment falls through to enforcement, so a read-only prefix can't smuggle a mutation. The ignore counter and grace window are untouched — recon is neither skill work nor an ignore. Mutations (Edit/Write/NotebookEdit) and state-changing Bash still enforce.
- **`hooks/check-skills.sh` — the methodology's own name no longer self-triggers.** A casual mention like "методология idea to deploy" used to fire the `/deploy` hint (the substring *deploy* inside "idea to deploy"); the name is now neutralised before keyword matching, while the `/adopt` trigger — which legitimately keys on the name — still matches the raw prompt. Real deploy phrases ("задеплой на прод", "deploy to aws") are unaffected.
- **`hooks/check-skills.sh` — `/refactor` trigger tightened.** Bare "переписать" no longer fires on prose/letters; it now requires a code object (код/модуль/функция/класс/метод/компонент).

All changes are opt-in or additive: a greenfield project with no markers behaves exactly as before. No skill/agent/hook count change. MINOR bump per SemVer (new backward-compatible capability).

## [1.34.5] - 2026-06-29

**Real cross-vendor review from inside WSL — reach the Windows Codex desktop binary over /mnt interop.** The standalone codex CLI inside WSL can be broken behind a fake-ip VPN (model-refresh timeout / Node crash), so a WSL-launched Claude Code session degraded cross-review to the native fallback. `resolve_engine` now, on WSL/Linux, also discovers the OpenAI Codex *desktop* `codex.exe` via the Windows mount (`/mnt/<drive>/Users/*/AppData/Local/OpenAI/Codex/bin/*/codex.exe`) and runs it through WSL interop — it executes as a Windows process and therefore uses the working Windows network stack. On a plain Linux box (no Windows mount) the glob matches nothing and resolution falls through to `PATH`, so nothing changes there. PATCH — no API/count change.

### Fixed

- **`hooks/cross-review-precommit.sh`** — `resolve_engine` gains a WSL→Windows-desktop-codex path (newest by mtime, survives desktop auto-updates), extracted a `_newest()` helper. The standalone CLI being unusable under a VPN no longer means "no cross-vendor review" in WSL.
- **`tests/verify_cross_review_precommit.py`** — inject a dummy engine via `CROSS_REVIEW_{CODEX,GEMINI}_BIN=/bin/false` so the detached worker never fires a real (paid) call during testing now that resolution can find a real binary off `PATH`.
- **Version 1.34.4 -> 1.34.5** across `.claude-plugin/plugin.json`, `.claude-plugin/marketplace.json`, and the Version badge in `README.md` / `README.ru.md`.

### Verified

- **Live WSL run behind the user's active VPN**: `resolve_engine("codex")` resolved the Windows desktop `codex.exe` via `/mnt`, and `run_engine` returned **three real codex findings** (overdraft, input validation, money-precision) on a buggy `charge()` diff in 42.9s — the same module path the detached worker uses. (The full dispatch→detached-worker→notes chain was separately verified on Windows in v1.34.4.)
- `tests/verify_cross_review_precommit.py` -> 10/10 (deterministic, no external call); `tests/meta_review.py` -> PASSED; all 6 CI checks green; `py_compile` clean.

## [1.34.4] - 2026-06-29

**Engine resolution prefers a working binary — fixes codex on Windows behind a flaky VPN.** The hook resolved `codex` purely via `PATH`, which on a typical Windows box is the npm `codex.CMD` shim — and that can be a stale version that fails to even start (rejects a newer `config.toml`'s `service_tier`, or times out refreshing its model list under a fake-ip VPN) while the user's *OpenAI Codex desktop* bundle (a newer, network-capable `codex.exe`) works fine. New `resolve_engine()` picks, in order: an explicit `CROSS_REVIEW_CODEX_BIN` / `CROSS_REVIEW_GEMINI_BIN` override; for codex on Windows, the **newest** `%LOCALAPPDATA%\OpenAI\Codex\bin\<hash>\codex.exe` (auto-tracks desktop auto-updates); then `PATH`. PATCH — no API/count change.

### Fixed

- **`hooks/cross-review-precommit.sh`** — `resolve_engine()` selects a working engine binary instead of blindly trusting `PATH`. Adds the `CROSS_REVIEW_<NAME>_BIN` override and a Windows OpenAI-Codex-desktop fallback. `run_engine` now runs an already-resolved full-path argv.

### Verified

- **Live Windows e2e behind the user's active VPN**: the hook resolved the desktop `codex.exe` (v0.142) and the detached worker wrote **three real codex findings** (overdraft, input validation, money-precision) on a staged `app/billing/charge.py` diff — genuine cross-vendor output, non-blocking, working tree untouched.
- `tests/verify_cross_review_precommit.py` -> 10/10; `tests/meta_review.py` -> PASSED; all 6 CI checks green; `py_compile` clean.
- **Version 1.34.3 -> 1.34.4** across `.claude-plugin/plugin.json`, `.claude-plugin/marketplace.json`, and the Version badge in `README.md` / `README.ru.md`.

## [1.34.3] - 2026-06-29

**Actually launch the external CLI on Windows (`run_engine` full-path resolution).** The hook invoked `subprocess.run(["codex", ...])` by bare name. On Windows, npm installs `codex`/`gemini` as `.CMD` shims that `CreateProcess` cannot launch by bare name — `subprocess.run` raises `FileNotFoundError`, so the worker always fell through to "unavailable" even when codex was installed and on `PATH`. `run_engine` now resolves the CLI to its full path via `shutil.which()` (e.g. `...\codex.CMD`), which launches correctly on Windows and is a harmless no-op on POSIX. Also pass `codex exec --skip-git-repo-check` so a fresh clone / CI checkout (a directory codex does not yet "trust") does not hard-error. PATCH — no API/count change.

### Fixed

- **`hooks/cross-review-precommit.sh`** — `run_engine` resolves the engine binary via `shutil.which()` and invokes the full path, so the external review actually runs on Windows (where the CLI is a `.CMD` shim). Added `--skip-git-repo-check` to the codex invocation for untrusted/fresh repos.
- **Version 1.34.2 -> 1.34.3** across `.claude-plugin/plugin.json`, `.claude-plugin/marketplace.json`, and the Version badge in `README.md` / `README.ru.md`.

> Note: this fix makes the methodology *invoke* codex/gemini correctly. Whether the external model then returns findings still depends on the user's CLI being healthy (authenticated, network-reachable, and — for codex — a `config.toml` the installed version accepts). The hook remains fail-open: any CLI error degrades to an honest "unavailable" note and never blocks the commit.

## [1.34.2] - 2026-06-29

**Overridable Agent Teams auto-disable for `cross-review-precommit.sh`.** v1.34.0 disabled the background review whenever `CLAUDE_CODE_EXPERIMENTAL_AGENT_TEAMS=1` was set. On a machine that runs Agent Teams as its *default*, that disabled the hook permanently — the background review could never fire. Split the guard: the **concrete** hazard (a linked/secondary worktree, where the index may hold another agent's staged work) remains an **unconditional** skip; the bare Agent Teams **flag** is now overridable with an explicit `CROSS_REVIEW_ALLOW_AGENT_TEAMS=1` (you thereby accept that an in-process parallel agent's staged change could ride along in the egressed diff). Safe-by-default is preserved; Agent-Teams-by-default users can now opt the hook back on. PATCH — no API/count change.

### Fixed

- **`hooks/cross-review-precommit.sh`** — the Agent Teams auto-disable is now overridable (`CROSS_REVIEW_ALLOW_AGENT_TEAMS=1`); the unconditional linked-worktree skip is unchanged. Verified on Windows (Agent Teams on): silent skip without the override, correct background dispatch with it.
- **`tests/verify_cross_review_precommit.py`** — added an "Agent Teams + override -> DISPATCH" case (now 10 cases).
- **Version 1.34.1 -> 1.34.2** across `.claude-plugin/plugin.json`, `.claude-plugin/marketplace.json`, and the Version badge in `README.md` / `README.ru.md`.

## [1.34.1] - 2026-06-29

**Cross-platform background dispatch for `cross-review-precommit.sh`.** The v1.34.0 hook detached its background worker with `os.fork` + `os.setsid`, which do not exist on Windows Python — there the worker silently no-op'd (fail-open, but the cross-vendor review never ran). Replaced with a portable `subprocess.Popen` that re-invokes the hook in a new `--worker` mode, using `start_new_session=True` on POSIX and `DETACHED_PROCESS | CREATE_NEW_PROCESS_GROUP` on Windows. The hook now actually dispatches on macOS/Linux/WSL **and** Windows. Behaviour, opt-in gating, scrubbing, and the never-a-gate invariant are unchanged; the 9-case test still passes and a live e2e confirms the detached worker writes its notes file. PATCH — no API/count change (still 20 hooks).

### Fixed

- **`hooks/cross-review-precommit.sh`** — background review now runs on Windows too (was a no-op there because `os.fork` is POSIX-only). Detach is now via `subprocess.Popen` with platform-appropriate flags; added a `--worker` self-invocation entry point.
- **Version 1.34.0 -> 1.34.1** across `.claude-plugin/plugin.json`, `.claude-plugin/marketplace.json`, and the Version badge in `README.md` / `README.ru.md`.

## [1.34.0] - 2026-06-29

**Opt-in cross-vendor pre-commit review — continuous second opinion without the always-on tax.** A two-perspective advisory pass (business-analyst + devils-advocate) evaluated making `/cross-review` continuous/automatic. The verdict: keep it on-demand by default, and add a continuous variant ONLY as an opt-in pre-commit hook, never an always-on per-edit (`PostToolUse`) or per-turn (`Stop`) layer. Rationale (privacy/governance of third-party egress, latency under a flaky VPN, multi-agent shared-worktree hazard, and non-duplication of the in-vendor `/security-guidance-setup` continuous layer) is recorded in the new `docs/adr/ADR-002-cross-review-opt-in-precommit.md`. Hook count 19 -> 20; skill/agent counts unchanged (38 / 10).

### Added

- **`hooks/cross-review-precommit.sh` (v1.34.0) — opt-in, fail-open, NON-BLOCKING cross-vendor review on `git commit`.** The deliberate opposite of the DoD gate it sits beside: it only ADVISES, never blocks. DEFAULT-OFF — egress to a third-party model (OpenAI Codex -> Google Gemini) happens only on explicit opt-in via env `CROSS_REVIEW_EGRESS_OK=1` (per-machine) or a `.cross-review-egress-ok` marker file at the repo root (detected by presence in the working tree, so it can be local/untracked and never enters a commit/PR; committing it is reserved for a team-wide opt-in). Scoped to sensitive staged paths only (migration/money/auth — the same signals as `check-dod-before-commit.sh`). Scrubs secrets/PII (same coverage as `pii-egress-guard.sh`) and refuses to egress if a high-confidence secret survives. Dispatches the slow external call as a detached background worker (`os.fork` + `setsid`) and returns well under its 5s timeout, writing findings to a `claude-cross-review-*.md` notes file with an honest "engine: codex/gemini/unavailable" provenance line. Auto-disables in Agent Teams / linked-worktree mode. Never writes the `/tmp/claude-review-done-*` sentinel — `/review` remains the mandatory floor. Hard off-switch: `ITD_CROSS_REVIEW=0`. Registered in `skills/adopt/references/project-settings-template.json` under the `PreToolUse`/`Bash` group.
- **`tests/verify_cross_review_precommit.py` — behavioural unit test (9 cases).** Asserts the egress DECISION (dispatch vs silent) rather than an exit code, since the hook is always non-blocking: default-off, env opt-in, marker opt-in, sensitive-path scoping, non-commit no-op, `ITD_CROSS_REVIEW=0` off-switch, Agent Teams auto-disable, and `&&`-chained commits. Runs with codex excluded from `PATH` so no real (paid) external call fires.
- **`docs/adr/ADR-002-cross-review-opt-in-precommit.md`** — records the decision and its boundary conditions, and is referenced from the `/cross-review` skill and the hook header. Consistent with ADR-001 (the hook is code on the existing hook engine; it ships no service).

### Changed

- **`skills/cross-review/SKILL.md`** gains a "Continuous mode — opt-in pre-commit hook" section documenting the companion hook and pointing to ADR-002; the fail-open / never-a-gate invariant is preserved.
- **Version 1.33.0 -> 1.34.0** across `.claude-plugin/plugin.json`, `.claude-plugin/marketplace.json`, and the Version badge in `README.md` / `README.ru.md` (MINOR — additive, zero breaking). Hook count propagated 19 -> 20 in `plugin.json`/`marketplace.json` descriptions, `hooks/README.md` (table row + "twenty hooks" prose), and the README hook narratives; a stale "семнадцать хуков" (17) in `README.ru.md` was corrected to 20 in passing.

### Verified

- `tests/verify_cross_review_precommit.py` -> 9 passed, 0 failed; plus a live end-to-end (opt-in + sensitive diff, codex excluded) confirming the background worker writes the notes file with the honest "unavailable" degradation line and cleans up its prompt temp file, non-blocking, with the working tree untouched.
- `python3 -m py_compile hooks/cross-review-precommit.sh` clean.
- `tests/verify_dod_gate.py` -> 19 passed, 0 failed (unchanged — DoD gate not modified).
- `tests/meta_review.py` -> FINAL STATUS PASSED (badge=1.34.0, CHANGELOG [1.34.0], marketplace=plugin version, hook-count narrative consistency).



**Day-5 Spec-Driven Production enrichment — Zero-Trust agent guardrails + spec-as-source, all as врезки, no new runtime.** Final study in the Google *New SDLC With Vibe Coding* series (Day 5, *Spec-Driven Production* — Boonstra et al., 2026). A two-lens review (business-analyst + devils-advocate) found ~70% of the paper already covered by the methodology (evals, prompt-injection, agent-memory, cross-vendor review, cost/model-routing — from the Day-1 and Day-3 ports). The real delta is **Zero-Trust Development** (policy server, sandboxing, human-in-the-loop, semantic gating, context hygiene) — for which the canon had zero coverage — plus the **spec-driven culture shift** (spec as durable source of truth, single `AGENTS.md`, Conditional LGTM). All land as opt-in врезки the methodology emits when designing/auditing a stateful, tool-calling agent. The paper's `agents-cli scaffold/eval/deploy` runtime is explicitly iceboxed (ADR-001). Zero new skills, zero new hook files; counts unchanged (38 skills / 19 hooks). Scope recorded in the new Day-5 note in `docs/adr/ADR-001-no-own-runtime.md`.

### Added

- **`/harden` Tier-3 `ZT-1` — Zero-Trust guardrail layer.** Informational, scoped to LLM/agent services that call tools or act: a deterministic policy server (allow/deny by role+env), sandboxing of agent-invoked code/tools (`GEMINI_SANDBOX=docker`-style), human-in-the-loop on irreversible/ambiguous actions, and optional semantic gating wired as an **ASK/advisory signal only, never a hard block** (a hook cannot pause the model loop — ADR-001, the retired score-gate lesson). N/A for non-agent services.
- **`/security-audit` `MEM-7` — context hygiene & tool-call sanitization.** Tool/function-call arguments (and downstream-prompt interpolations) are sanitized and policy-checked before execution — a resolver substitutes trusted values for placeholders and a tool-policy middleware vets the call, rather than passing model-produced strings straight to a side-effecting tool. Complements `MEM-1` (MEM-1 guards what enters context; MEM-7 guards what leaves it as an action).
- **`/blueprint` Step 1.6 point 8 + spec-as-source pointer.** Step 1.6 (opt-in, stateful-agent) gains a zero-trust guardrail-layer design item (policy + sandbox + HITL + advisory semantic gating). The 6-document section gains a **spec-as-source (SDD)** note: treat PRD + acceptance criteria as the durable source of truth (code is comparatively disposable), keep agent instructions in a single `CLAUDE.md` (the `AGENTS.md` equivalent), change the spec then regenerate code — not the reverse.
- **`/adopt` consolidation pointer.** When a legacy project scatters agent instructions across many files, `/adopt` flags *instructional fragmentation* in its report and suggests consolidating into a single `CLAUDE.md` (no auto-merge).
- **`/review` high-velocity report add-ons (optional, not new checks).** The report may surface a **Bundled Summary + Risk Assessment** and a **Conditional LGTM** ("approve provided X is fixed") — reporting formats over the same binary rubric; they never turn a Critical `BLOCKED` into a pass.
- **`docs/adr/ADR-001-no-own-runtime.md` — Day-5 note.** Iceboxes `agents-cli`/owned agent-runtime; frames Zero-Trust Development as product design the methodology teaches and audits (not its own engine); records that semantic gating is ASK/advisory only, never a hard inferential gate.

### Changed

- **Version 1.32.0 → 1.33.0** across `.claude-plugin/plugin.json`, `.claude-plugin/marketplace.json`, and the Version badge in `README.md` / `README.ru.md` (MINOR — additive врезки, zero breaking). Per-skill frontmatter versions bumped on edited skills: `/blueprint` 1.3.1 → 1.4.0, `/harden` 1.20.0 → 1.21.0, `/security-audit` 1.19.0 → 1.20.0, `/adopt` 1.21.0 → 1.22.0, `/review` 1.15.0 → 1.16.0. **Skill count (38) and hook count (19) unchanged** — all changes are врезки into existing skills + an ADR note, so no count cascade (M-C7/M-C12/M-C15/M-C16 unaffected).

### Verified

- `tests/meta_review.py --verbose` → FINAL STATUS PASSED (Critical 0), including M-C5 (badge=1.33.0), M-C6 (CHANGELOG [1.33.0] entry), M-C13 (marketplace=plugin version).
- `scripts/verify_skill_profiles.py` clean (edited skills keep valid `effort`/`side_effect`/`explicit_invocation` frontmatter).
- `tests/verify_dod_gate.py` → 19 passed, 0 failed (unchanged — no DoD-hook change this release).
- `/review --self` run before commit.

## [1.32.0] - 2026-06-28

**Day-3 Context Engineering enrichment — memory & context discipline for stateful agents, all as врезки + one new review check, no new runtime.** Second study in the Google *New SDLC With Vibe Coding* series (Day 3, *Context Engineering: Sessions, Memory* — Milam, Gulli, Nawalgaria, 2026). A two-lens review (business-analyst + devils-advocate) found ~80% of the paper is **product-design** guidance (how the agent the *user* builds should manage its context/memory), not methodology process — so it lands mostly as **opt-in врезки the methodology emits when designing a stateful agent**, plus the one place it is genuinely a guardrail for the money portfolio: provenance/freshness of remembered facts before an irreversible action. Zero new skills, zero new hook *files*, counts unchanged (38 skills / 19 hooks). Scope recorded in the new Day-3 note appended to `docs/adr/ADR-001-no-own-runtime.md`.

### Added

- **`/blueprint` Step 1.6 — Memory & context architecture (opt-in, stateful-agent / LLM products).** Triggered only when the product is a stateful AI agent / LLM app; emits a `## Memory & context architecture` section into `PROJECT_ARCHITECTURE.md` deciding memory scopes, storage-as-ADR (not a reflexive vector DB), extraction/consolidation/pruning policy, provenance & freshness, memory-as-tool vs auto-inject, sync vs async writes, and the trust boundary / tenant isolation. Skipped entirely for stateless apps.
- **`/discover` Step 7.5 — statefulness flag.** When discovery reveals a stateful agent, records a `Product class: stateful-agent` marker in DISCOVERY.md so `/blueprint` runs Step 1.6. Opt-in; omitted for stateless products.
- **`/security-audit` context & memory integrity checks (`MEM-1…MEM-6` in `references/security-checklist.md`).** Agent-memory threat model — prompt-injection trust boundary, memory poisoning via unvalidated writes, cross-tenant memory isolation, secrets/PII in context or store, memory/context exfiltration, and unreviewed async memory writers. N/A for non-AI targets. The most differentiated point of the release: the memory store treated as a first-class attack surface.
- **`/review` `C-code-7` (Critical) — context integrity.** Untrusted input (user/tool/web/RAG/docs) must not flow into the model context, system prompt, or long-term memory without a sanitization / trust-boundary step: retrieved text is data not instructions, memory writes are validated and attributable, async memory writers are gated. The agentic analogue of SQL injection; complements `C-code-6` (the irreversible action a poisoned memory would steer). `/review` SKILL.md tier ranges updated to C-code-1…7.
- **`MEMORY_RE` risk signal in the DoD pre-commit hook (`hooks/check-dod-before-commit.sh`).** Narrowly scoped to agent-memory / context artifacts (agent_memory, long-term memory, memory/vector store, system-prompt files); when such a path is staged it requires `/security-audit` before commit, via the same fail-open / `SKILL_BYPASS` machinery as the existing money/migration signals. No new hook *file* — counts unchanged. Covered by 5 new cases in `tests/verify_dod_gate.py` (19 passed, 0 failed).
- **`/harden` Tier-3 `MEM-1` check.** Informational, scoped to AI services with durable memory: retention/TTL or consolidation job, per-tenant isolation in the live query path, and async / out-of-band memory writers behind a validation gate (not a blind upsert). N/A for non-AI services.
- **`/test` Step 3.5 — memory-quality eval dimension.** For stateful agents, adds recall / freshness / consolidation-correctness / no-poisoning criteria to the eval rubric. Eval signal, not a unit test; rides the existing opt-in eval branch, never a global gate.
- **`/session-save` — memory-hygiene pointer.** One-line delegation to `anthropic-skills:consolidate-memory` for periodic dedup/prune of `MEMORY.md`; explicitly in-session and reviewed, never an out-of-band writer (ADR-001).
- **`docs/adr/ADR-001-no-own-runtime.md` — Day-3 note.** Extends the no-runtime decision to context engineering: context/memory design is work performed *into the user's product*; the plugin's own cross-session memory stays synchronous / in-session; async memory is a product pattern we help design and gate, not a methodology feature.

### Changed

- **Version 1.31.0 → 1.32.0** across `.claude-plugin/plugin.json`, `.claude-plugin/marketplace.json`, and the Version badge in `README.md` / `README.ru.md` (MINOR — additive врезки + one review check, zero breaking). Per-skill frontmatter versions bumped on edited skills: `/review` 1.14.0 → 1.15.0, `/security-audit` 1.18.0 → 1.19.0, `/harden` 1.19.0 → 1.20.0, `/test` 1.4.0 → 1.5.0, `/session-save` 1.6.0 → 1.7.0. `/blueprint` and `/discover` carry no version frontmatter (field set unchanged). **Skill count (38) and hook count (19) unchanged** — all changes are врезки into existing skills + one new review check + one new in-hook signal, so no count cascade (M-C7/M-C12/M-C15/M-C16 unaffected).

### Verified

- `tests/verify_dod_gate.py` → 19 passed, 0 failed (5 new agent-memory cases).
- `tests/meta_review.py --verbose` → FINAL STATUS PASSED (Critical 0), including M-C5 (badge=1.32.0), M-C6 (CHANGELOG [1.32.0] entry), M-C13 (marketplace=plugin version).
- `scripts/verify_skill_profiles.py` clean (edited skills keep valid `effort`/`side_effect`/`explicit_invocation` frontmatter).
- `/review --self` run before commit.

## [1.31.0] - 2026-06-28

**New-SDLC / Vibe-Coding enrichment — four points, all as врезки into existing skills, no new runtime.** A study of the Google whitepaper *The New SDLC With Vibe Coding* (Osmani, Saboo, Kartakis, 2026) found the methodology already implements most of the paper's "should" (skills = dynamic context, hooks = guardrails, test/review gates, harness map). This release closes the honest gaps it flagged — **without** new skills (avoids the ~4-artifact + doc-cascade cost) and **without** building any runtime of our own (see new `docs/adr/ADR-001-no-own-runtime.md`). Four blocks: **(A)** an opt-in/scoped **eval-suite branch** in `/test` (+ a Tier-3 `EVAL-1` in `/harden`) for AI/LLM/agent code — rubric + LM-judge + trajectory check, the non-deterministic counterpart to tests; **(D)** a **"80%-problem" checklist** in `/review` — hallucinated/slopsquatting deps, irreversible-action human-gate, business invariants, edge-case completeness; **(C)** lightweight **token/OpEx cost-accounting** врезки riding the existing `cost-tracker.sh` ledger + `ctx-stats` (no new hook); **(B)** a transparent **model-routing policy** (`docs/MODEL-ROUTING-POLICY.md`) applied via native `/model` + per-agent frontmatter (not an auto-router). Eval (A) is deliberately opt-in/scoped, never a global gate (the acceptance-gate false-block lesson). Skill count 38 → 38, hook count 19 → 19 (no count cascade).

### Added

- **`/test` Step 3.5 — eval-suite branch (opt-in, scoped).** When the code under test calls an LLM/agent or emits non-deterministic output (or the user asks), `/test` generates an eval-suite into the user's `evals/`: a **rubric** (`<feature>.rubric.md`), an **LM-judge stub** (`<feature>.judge.py`), and a **trajectory-eval scaffold** (`<feature>.trajectory.json`) for multi-step agents. Tests assert deterministic contracts; evals assert quality of non-deterministic output — both are needed for AI features. Explicitly **not a global gate** (would false-block ordinary work — same failure mode as the retired score≥7 and acceptance gates); never runs for non-AI projects. Fail-closed: an eval `passed` requires an actual judge run. Full patterns in `skills/test/references/test-frameworks.md` → "LLM / agent eval patterns".
- **`/harden` Tier-3 `EVAL-1` check.** Informational (never blocking): an LLM/agent service should ship an eval-suite + regression threshold alongside its tests. N/A (passes) for services with no AI component. Scoped to AI products, generated via `/test` Step 3.5.
- **`/review` "80%-problem" checks (`references/review-checklist.md`).** Targeting the failure-prone last 20% of vibe-coded output: `C-code-5` (Critical) hallucinated / slopsquatting dependencies — every import must resolve to a declared, real package; `C-code-6` (Critical) irreversible external actions (orders, money movement, FX/treasury, payouts, unrecoverable deletes) must be human-gated, not auto-executed; `I-code-10` (Important) business invariants enforced (price ≥ cost, quantity ≥ 0, …); `I-code-11` (Important) edge-case completeness on AI-generated logic. `C-code-6` maps to the trajectory-eval `human_gate` checkpoint in `/test` Step 3.5. `/review` SKILL.md tier ranges updated to C-code-1…6 / I-code-1…11.
- **Token/OpEx cost-accounting врезки (Block C — no new hook).** `/session-save` Step 4.6 attaches a per-session cost snapshot read from the existing `hooks/cost-tracker.sh` ledger; `/task` Step 1b adds a cost-awareness nudge (`ITD_COST_CEILING_TOKENS`) for high-risk/heavy targets; `/context-mode-setup` gains a "Cost visibility" section tying `ctx-stats` savings to the cost ledger. Lightweight accounting on existing runtime — explicitly not an observability platform (ADR-001).
- **`docs/MODEL-ROUTING-POLICY.md` (Block B).** Phase → model-tier → rationale table (expensive tiers on reasoning-heavy phases, cheap on mechanical, to control OpEx), applied via native `/model` + per-agent `model:` frontmatter. A transparent policy, **not** an auto-router / daemon. Linked from the Recommended Models section of `README.md` and `README.ru.md`.
- **`docs/adr/ADR-001-no-own-runtime.md`.** Records the decision to build no runtime of our own — delegate lifecycle/cost/model-selection to the existing substrate (Claude Code hook engine, context-mode, native `/model` + permissions, `cost-tracker.sh`); the real production runtime lives in the user's products, the methodology helps *design* it. Review date 2026-09-28.
- **`LAUNCH_PLAN.md`.** Strategic plan for the four-block enrichment (A+D → C → B), portfolio rationale, backlog (Day 3/5 analysis), and the gates/release checklist per merge.

### Changed

- **Version 1.30.0 → 1.31.0** across `plugin.json`, `marketplace.json`, and the Version badge in `README.md` / `README.ru.md` (MINOR — additive врезки, zero breaking). Per-skill frontmatter versions bumped on the edited skills: `/test` 1.3.1 → 1.4.0, `/review` 1.13.0 → 1.14.0, `/harden` 1.18.0 → 1.19.0, `/session-save` 1.5.0 → 1.6.0, `/task` 1.18.0 → 1.19.0, `/context-mode-setup` 1.0.0 → 1.1.0. **Skill count (38) and hook count (19) unchanged** — all changes are врезки into existing skills + new `docs/`, so no count cascade (M-C7/M-C12/M-C15/M-C16 unaffected).

### Verified

- `tests/meta_review.py --verbose` → FINAL STATUS PASSED (Critical 0), including M-C5 (badge=1.31.0), M-C6 (CHANGELOG [1.31.0] entry), M-C13 (marketplace=plugin version). `scripts/verify_skill_profiles.py` clean (edited skills keep valid `effort`/`side_effect`/`explicit_invocation` frontmatter). `/review --self` run before commit.

## [1.30.0] - 2026-06-28

**Five omnigent-inspired guardrail ports — outcomes, not abstractions.** A study of [`omnigent-ai/omnigent`](https://github.com/omnigent-ai/omnigent) found that its valuable concepts are server/control-plane *properties* that can't be lifted into a prompt+hook plugin — but their *outcomes* can. This release ports five of them onto idea-to-deploy's existing substrate (hooks + native Claude Code permissions), never a custom policy engine: (1) a **cost/budget hard-ceiling ASK** on the cost tracker, (2) a cumulative **risk-score escalation** ("death by a thousand edits" → forced `/review` or `/security-audit`), (3) **PII/secret deny-before-egress** (hybrid deny-secrets / ask-PII), (4) the **`/cross-review`** cross-vendor second-opinion skill (fail-open codex → gemini → native red-team, never a gate), and (5) **OS-tool-class ASK** guardrails via native permissions in `/adopt`. Every new hook is fail-open and never blocks the session; the external reviewer never becomes a dependency. Hook count 17 → 19, skill count 37 → 38.

### Added

- **Hard-ceiling ASK gate in `hooks/cost-tracker.sh` (omnigent `cost_budget` port).** The cost tracker gained a second gate stage. The existing soft stage still warns (visibility only) between 80% and 100% of the budget ceiling; a new **hard stage** fires at/above 100% of the ceiling and escalates from a warning to an **ASK** — it injects a forceful instruction telling the model to STOP and obtain explicit user approval (continue / raise the ceiling / stop) and to run `/session-save` before deciding. The hard ASK re-fires every +500k estimated tokens so a runaway loop or an over-scoped `/kickstart` keeps surfacing instead of silently burning budget. The ceiling and blended cost are now overridable per project via `ITD_COST_CEILING_TOKENS` and `ITD_COST_PER_1M_USD` env vars. This is an **outcome port** of omnigent's `cost_budget` policy (soft ASK / hard limit) — a plugin hook cannot pause the agent loop, so "limit" is realized as a high-priority ASK, not a server-side block. No new hook file (cost-tracker already shipped since v1.18.0); hook count unchanged.
- **`cost-tracker.sh` registered in the adoption template.** `skills/adopt/references/project-settings-template.json` now wires `cost-tracker.sh` as a `PostToolUse` hook on all tools (`matcher: "*"`), so every adopted project gets budget visibility and the hard gate, not just the methodology repo itself.
- **New `hooks/risk-score.sh` — cumulative risk-score escalation (omnigent `risk_score_policy` port).** idea-to-deploy's commit gates are binary and stateless: a single change either trips a gate or it does not, which misses "death by a thousand edits" — many individually-OK changes that add up to a risky session with no single tripwire. This hook keeps a cumulative "safety budget": every mutating tool call adds risk points scaled by how sensitive the target is (a plain edit is worth little; an edit to an auth/payment/migration/secret path, or a destructive/egress/schema Bash command, is worth more). When the running score crosses a threshold (default 12, overridable via `ITD_RISK_THRESHOLD`) the hook **escalates** — it injects an ASK to pay the risk down by running `/review` (or `/security-audit` when the accumulated risk is mostly security-relevant) before continuing. Running either skill resets the budget, detected via the `/tmp/claude-review-done-*` and `/tmp/claude-security-audit-done-*` markers those skills already write. It is an **outcome port**, not omnigent's server-side policy engine, and it never blocks (PostToolUse cannot pause the loop — escalation is a high-priority ASK). Registered in the adoption template as a `PostToolUse` hook on all tools.
- **New `hooks/pii-egress-guard.sh` — PII/secret deny-before-egress (omnigent egress-policy port).** A `PreToolUse` hook that scans the content of OUTBOUND tool calls (Bash egress commands — curl/wget/scp/ssh/rsync/git push — and WebFetch) for secrets and PII just before data would leave the machine. **Hybrid enforcement:** high-confidence secrets (private key blocks, AWS/GitHub/Slack/Google/Stripe/Anthropic/OpenAI keys, Bearer tokens) are **denied** (`permissionDecision: "deny"`, exit 2 — near-zero false positives, exfiltrating a live credential is almost never intended); weaker signals and PII (emails, card-shaped numbers, `password=`/`api_key=` assignments) trigger an **ASK** (`permissionDecision: "ask"`) so judgment stays with the user. Scoped to egress only — a secret written to a local file is not flagged. Complements `careful.sh` (destructive-command guard) by guarding data-leaving-the-box. Disable per project via `ITD_PII_GUARD=0`. Registered in the adoption template as a `PreToolUse` hook on `Bash|WebFetch`.
- **New `/cross-review` skill — cross-vendor second-opinion code review (omnigent "one vendor reviews another vendor's code" port).** When Claude both writes and reviews code (`/review`), the reviewer shares the author's blind spots. `/cross-review` sends the current diff to an **independent** external model (OpenAI Codex CLI, else Google Gemini CLI) and folds its findings back as a ranked list, naming the engine that ran. It is an **outcome port** (get a second opinion), not omnigent's orchestration server, and it is deliberately **fail-open and additive**: the native `/review` remains the mandatory quality floor; `/cross-review` is a bonus ceiling that **never gates** and never writes the `/tmp/claude-review-done-*` marker. Degradation chain **codex → gemini → native Claude red-team review** — a missing CLI or an out-of-quota/rate-limited/erroring CLI is treated like "not installed": note it, degrade, continue (the methodology's effectiveness never depends on a third-party CLI). Secrets/PII are scrubbed out of the diff before egress (with `pii-egress-guard.sh` as the backstop). Ships `skills/cross-review/SKILL.md` + `references/cli-adapters.md` (verified-shape codex/gemini invocations, scrub recipe, timeout wrapper), a trigger block in `hooks/check-skills.sh` (cross-review / second-opinion phrases, EN+RU; does not steal `/review`'s triggers), and `tests/fixtures/fixture-30-cross-review/` (read-only detect/advise bucket, status `pending`).
- **OS-tool-class ASK guardrails in the adoption template (omnigent OS-tool-class ASK port — onto NATIVE permissions, no custom DSL).** `skills/adopt/references/project-settings-template.json` now ships a `permissions.ask` block that makes Claude Code prompt for confirmation before genuinely destructive shell commands (`rm`, `rmdir`, `sudo`, `chown`, `dd`, `mkfs`, `kill`, `killall`, `pkill`, `shutdown`, `reboot`; `chmod` is intentionally omitted as too noisy — `chmod +x` is routine — and documented as add-back-for-locked-down-projects). This is the omnigent `ask_on_os_tools` outcome realized on the harness's own allow/deny/ask mechanism rather than a second policy engine. Egress (curl/wget) is intentionally left to `pii-egress-guard.sh` and destructive git/db to `careful.sh` to avoid double-prompting. `/adopt` (Step 2) now merges `permissions.ask` rules by exact rule string, additively — it never removes or reorders the user's existing `permissions.allow`/`deny`/`ask`, and treats the set as a recommended default the user may decline. No hook or skill count change.
- **`scripts/sync-to-active.sh` now activates the three new hooks in active installs.** The hook-registration block (which patches `~/.claude/settings.json`) gained `pii-egress-guard.sh` (PreToolUse `Bash|WebFetch`) and `cost-tracker.sh` + `risk-score.sh` (PostToolUse `*`). Previously `sync-to-active.sh` copied the hook *files* but did not wire the new ones, so they were inert in the dogfooding/active environment; now `bash scripts/sync-to-active.sh` makes them fire. `verify-sync-to-active.sh` passes (13 registered + 6 exempt). It deliberately does NOT touch `permissions` in the user-level active settings — the OS-tool-class ASK guardrails are a project-level adoption recommendation, not a global override of the user's curated allow-list.

### Changed

- **Skill count 37 → 38 across docs.** Updated the Skills badge, prose counts, the "Quality Assurance" category header (5 → 6) and new `/cross-review` rows in the Skill Contracts, I/O, and Recommended Models tables in `README.md` and `README.ru.md`; description counts in `.claude-plugin/plugin.json` and `.claude-plugin/marketplace.json`; and the current-count claims in `docs/CONTRACTS.md`, `docs/CONTENT-PLAN.md`, `docs/competitive-analysis.md`, `docs/promotion/marketplace-submissions.md`, and `docs/promotion/drafts/*` (enforced by meta-review checks M-C7/M-C12/M-C16).

- **Hook count 17 → 19 across docs.** Updated the description counts in `.claude-plugin/plugin.json` and `.claude-plugin/marketplace.json`, the prose counts in `README.md` and `hooks/README.md`, and the current-count claims in `docs/CONTRACTS.md`, `skills/context-mode-setup/SKILL.md`, and `docs/promotion/marketplace-submissions.md` for the two new hooks (`risk-score.sh`, `pii-egress-guard.sh`).

### Verified

- **`/cross-review` wired and gate-clean.** `tests/verify_triggers.py` reports no drift (every canonical phrase routes to `/cross-review`); `tests/verify_routing.py` 68/68 = 100%; `tests/verify_skill_enforcement.py` 10/10 (session_id no drift, 19 hooks / skills aligned); `tests/verify_snapshot.py` shows `fixture-30-cross-review` PENDING (expected, read-only bucket); `tests/meta_review.py` PASSED (0 critical) including M-C7 badge (38), M-C12 prose counts, and M-C16 category subtotals.
- **PII/secret egress guard tested live (`tests/verify_pii_egress.py`).** Covers DENY for OpenAI/AWS/GitHub keys and Bearer tokens in egress commands and a private key in a WebFetch prompt; ASK for emails, card-shaped numbers, and credential assignments; ALLOW for clean egress; correct SCOPE (a secret in a non-egress Bash command or a non-egress tool is not flagged); `ITD_PII_GUARD=0` disables; malformed stdin is graceful (rc 0). All pass. Two code-review findings were fixed before commit: the `sk-` secret pattern no longer DENYs `sk-` segments inside URL paths/query strings (S3 keys, CDN paths, pagination cursors — confirmed false positives), via a `(?<![/=&?])` lookbehind, with the credential-assignment ASK rule (now including bare `token=`) as the backstop for real `keyword=secret` bodies; and bare `http|https` was removed from the egress-command matcher so commands merely mentioning a URL are not scanned.
- **Risk-score escalation tested live (`tests/verify_risk_score.py`).** A nine-case regression test (`plain edits accumulate and escalate to /review at threshold`, `security-sensitive edits bias toward /security-audit`, `/review marker pays the budget down`, `reads/searches accrue no risk`, `bad-JSON handled gracefully rc=0`, `ITD_RISK_THRESHOLD override respected`, `ITD_RISK_THRESHOLD=0 disables the gate`, `MultiEdit on a sensitive path scores as sensitive`, `cross-session isolation — another session's /review does not pay this session down`) all pass. Three code-review findings were fixed before commit: the pay-down marker is now session-scoped (no cross-session glob), `ITD_RISK_THRESHOLD<=0` disables the gate instead of spamming, and `MultiEdit`'s nested `edits[].file_path` is inspected for sensitivity.
- **Cost gate tested live (`tests/verify_cost_gate.py`).** A seven-case regression test (`hard fires STOP/ASK at ceiling`, `re-fire suppressed within +500k window`, `soft warns 80-100%`, `silent below threshold`, `bad-JSON handled gracefully rc=0`, `ITD_COST_CEILING_TOKENS override respected`, `ceiling=0 disables the gate silently`) all pass. `tests/meta_review.py` PASSED (0 critical); adoption template remains valid JSON.

## [1.29.0] - 2026-06-28

**New `/security-guidance-setup` security skill (integration with the official Anthropic security-guidance plugin).** Adds an idea-to-deploy-native companion that brings the official [security-guidance plugin](https://github.com/anthropics/claude-code/tree/main/plugins/security-guidance) (by David Dworken, Anthropic; first-party code, free, ships **enabled by default** in the `claude-plugins-official` marketplace) into the methodology — a **shift-left, always-on** reviewer of Claude-generated code with three layers: (1) instant regex pattern warnings on every Edit/Write/MultiEdit/NotebookEdit (~25 dangerous patterns), (2) an LLM diff review on Stop that feeds high-severity findings back before you see the turn, (3) an agentic commit/push reviewer that traces cross-file data flow (IDOR, auth bypass, SSRF). The skill is a **detect-and-advise integration**: it never vendors the upstream plugin (first-party Anthropic code under Anthropic's own license / Commercial Terms — not ours to redistribute, and actively maintained, so vendoring would fork it and lose updates), it detects install state and runs/prints the verified CLI command (`claude plugin install security-guidance@claude-plugins-official`), and it maps the plugin onto the lifecycle (kickstart/task/bugfix/refactor→realtime warnings + diff review; review→pre-`/review` hygiene; migrate/harden/deploy→agentic commit/push review). It is **complementary** to `/security-audit` (on-demand deep audit report), not a replacement. The methodology's gates are unaffected. Skill count 36 → 37.

### Added

- **`skills/security-guidance-setup/SKILL.md` — `/security-guidance-setup` skill (Quality Assurance category).** Integration with the official [security-guidance plugin](https://github.com/anthropics/claude-code/tree/main/plugins/security-guidance). Documents what it provides **as verified against the upstream repo 2.0.0** (3 review layers; hooks on `SessionStart` / `UserPromptSubmit` / `PostToolUse: Edit|Write|MultiEdit|NotebookEdit` / `PostToolUse: Bash` git commit-push / `Stop`; ~25 patterns; env-var config — `SECURITY_GUIDANCE_DISABLE`, `ENABLE_STOP_REVIEW`, `SECURITY_REVIEW_MODEL`, …; `claude-security-guidance.md` policy file), the Claude Code ≥ v2.1.144 / Python 3.8+ / API-path requirements, and the read-only detection path. Includes a **Relationship to `/security-audit`** table (continuous shift-left vs. on-demand audit — complement, not replace), an **idea-to-deploy fit** table, and a **coexistence** section (idea-to-deploy's DoD/review PreToolUse gate blocks the commit; security-guidance's PostToolUse reviewer then reviews what was committed — defense-in-depth, not a dupe; plus the `ENABLE_STOP_REVIEW=0` multi-agent / shared-worktree caveat). Read-only, no global/network install without explicit approval, no upstream source copied into the repo; does not replace `/review`, `/test`, `/security-audit`, or any work route.
- **Trigger block in `hooks/check-skills.sh`** routing security-guidance / shift-left phrases ("security-guidance", "плагин security guidance", "shift-left security", "realtime security review", "ревью безопасности на лету / при коммите", "ловить уязвимости на лету", "official security plugin", …) to `/security-guidance-setup`. Crafted with multiword anchors to avoid stealing `/security-audit`'s triggers ("проверь безопасность", "OWASP", "найди уязвимости" still route to `/security-audit`). Verified by `tests/verify_triggers.py` (no drift) and the routing benchmark (`tests/verify_routing.py`, 68/68 = 100%, with two new paraphrases added to `benchmarks/routing-prompts.json`).
- **`tests/fixtures/fixture-29-security-guidance-setup/`** — snapshot stub (status `pending`, same read-only detect/advise bucket as `fixture-15-advisor`, `fixture-21-mcp-docs`, `fixture-26-caveman`, `fixture-27-context-mode-setup`, `fixture-28-seo-setup`). `idea.md` + `notes.md` document the contract (detect-before-claim, no-vendoring of first-party code, accurate 3-layer mechanism, lifecycle fit, gate coexistence, complement-not-replace); `expected-files.txt` asserts the no-files-written contract.

### Changed

- **Skill count 36 → 37 across docs.** Updated the Skills badge, prose counts, the "Quality Assurance" category header + new `/security-guidance-setup` row (next to `/security-audit`), and the Skill Contracts + Recommended Models tables in `README.md` and `README.ru.md`; description counts in `.claude-plugin/plugin.json` and `.claude-plugin/marketplace.json`; and the current-count claims in `docs/CONTRACTS.md`, `docs/CONTENT-PLAN.md`, `docs/competitive-analysis.md`, `docs/promotion/marketplace-submissions.md`, and the `docs/promotion/drafts/*` articles (enforced by meta-review check M-C12).

### Verified

- **Hook routing tested live.** Piped sample prompts through `hooks/check-skills.sh`: RU ("ловить уязвимости на лету … security-guidance") and EN ("official security-guidance plugin … shift-left security review on commit") both route to `/security-guidance-setup`; the negative case ("проверь безопасность перед продакшеном" / "OWASP security review") still routes to `/security-audit`, not here. `check-skill-completeness.sh` accepts the new SKILL.md. All structural gates green: `meta_review.py` PASSED (0 critical), `verify_triggers`/`verify_routing`/`verify_snapshot`/`verify_skill_enforcement`/`verify_dod_gate`/`verify_agent_review_sentinel` all rc=0. A full live install of the upstream plugin is left as a documented manual step (it ships default-on).

## [1.28.0] - 2026-06-28

**New `/seo-setup` SEO skill (integration with the Claude SEO plugin).** Adds an idea-to-deploy-native companion that brings the upstream [Claude SEO plugin](https://github.com/AgriciDaniel/claude-seo) (by [@AgriciDaniel](https://github.com/AgriciDaniel), MIT) into the methodology — 25 sub-skills + 18 sub-agents covering technical SEO, content quality (E-E-A-T), Schema.org, sitemaps, Core Web Vitals, local SEO, backlinks, AI/GEO, e-commerce, hreflang, and the Google SEO APIs. The skill is a **detect-and-advise integration**: it never vendors the upstream plugin (a large surface with a heavy Python toolchain — `playwright`, `weasyprint`, `lxml`, Google APIs — plus CC BY 4.0 FLOW prompts; idea-to-deploy stays MIT and no-heavy-dep), it detects install state and runs/prints the verified CLI commands, and it maps the plugin onto the lifecycle (discover→keyword/competitor, blueprint→schema/hreflang, kickstart→on-page, harden→technical/CWV/GEO, deploy→drift baseline + Google APIs). It is named `seo-setup` (not `seo`) because the upstream plugin ships its own orchestrator skill named `seo` (`/seo audit <url>`). The methodology's gates are unaffected. Skill count 35 → 36.

### Added

- **`skills/seo-setup/SKILL.md` — `/seo-setup` skill (Integration category).** Integration with the upstream [Claude SEO plugin](https://github.com/AgriciDaniel/claude-seo) (MIT). Documents what Claude SEO provides **as verified against the upstream repo 2.2.0** (25 sub-skills: orchestrator `seo` + 21 core + `seo-flow` + 2 extension mirrors; 18 sub-agents; 1 `PostToolUse: Edit|Write` schema-validation hook; 8 optional MCP extensions — DataForSEO/Firecrawl/Ahrefs/…), the Python 3.10+ / Claude Code ≥ 1.0.33 requirements, and the read-only detection path (`claude plugin list`, `claude plugin details`, `python3 --version`). Includes an **idea-to-deploy fit** table (where it pays off — projects shipping a public web surface; where not — internal tools/libraries/CLIs) and a **coexistence** section (the upstream schema hook fires on every Edit/Write and needs the Python deps; idea-to-deploy gates must still fire). Read-only, no global/network install without explicit approval, no upstream source copied into the repo; does not replace `/review`, `/test`, `/security-audit`, or any work route.
- **Trigger block in `hooks/check-skills.sh`** routing SEO phrases ("SEO", "сео", "поисковая оптимизация", "SEO-аудит", "schema markup", "structured data", "Core Web Vitals", "sitemap", "E-E-A-T", "AI Overviews", "GEO optimization", "technical SEO", "search ranking", "backlinks", "keyword research", "semantic clustering", …) to `/seo-setup`. Crafted to avoid false positives (e.g. "database schema" + "migration" does **not** route to SEO). Verified by `tests/verify_triggers.py` (no drift) and the routing benchmark (`tests/verify_routing.py`, 66/66 = 100%, with two new SEO paraphrases added to `benchmarks/routing-prompts.json`).
- **`tests/fixtures/fixture-28-seo-setup/`** — snapshot stub (status `pending`, same read-only detect/advise bucket as `fixture-15-advisor`, `fixture-21-mcp-docs`, `fixture-26-caveman`, `fixture-27-context-mode-setup`). `idea.md` + `notes.md` document the contract (detect-before-claim, no-vendoring, accurate mechanism, lifecycle fit, gate coexistence) for manual verification; `expected-files.txt` asserts the no-files-written contract.

### Changed

- **Skill count 35 → 36 across docs.** Updated the Skills badge, prose counts, the "Integration" category section header + new `/seo-setup` row, and the Skill Contracts + Recommended Models tables in `README.md` and `README.ru.md`; description counts in `.claude-plugin/plugin.json` and `.claude-plugin/marketplace.json`; and the current-count claims in `docs/CONTRACTS.md`, `docs/CONTENT-PLAN.md`, `docs/competitive-analysis.md`, `docs/promotion/marketplace-submissions.md`, and the `docs/promotion/drafts/*` articles (enforced by meta-review check M-C12).

### Verified

- **Hook routing tested live.** Piped sample prompts through `hooks/check-skills.sh`: RU ("SEO-аудит сайта … schema markup") and EN ("search ranking … core web vitals") both route to `/seo-setup`; the negative case ("change the database schema and run a migration") does not. `check-skill-completeness.sh` accepts the new SKILL.md. All structural gates green: `meta_review.py` PASSED (0 critical), `verify_triggers`/`verify_routing`/`verify_snapshot`/`verify_skill_enforcement`/`verify_dod_gate`/`verify_agent_review_sentinel` all rc=0. A full live install of the upstream plugin (`claude plugin install claude-seo@agricidaniel-claude-seo` + Python deps) is left as a documented manual step.

## [1.27.0] - 2026-06-28

**New `/context-mode-setup` context-window optimization skill (integration with the Context Mode plugin).** Adds an idea-to-deploy-native companion that brings the upstream [Context Mode plugin](https://github.com/mksglu/context-mode) (by [@mksglu](https://github.com/mksglu), ELv2) into the methodology — it sandboxes large tool output into a local SQLite FTS5 store so the agent searches it (`ctx-search`) instead of dumping it into the context window (vendor claim ~98% per-call reduction). The skill is a **detect-and-advise integration**: it never vendors the upstream ELv2 engine (idea-to-deploy stays MIT and zero-native-dep), it detects install state and runs/prints the verified CLI commands, and it maps the plugin's components onto the lifecycle. It is named `context-mode-setup` (not `context-mode`) because the upstream plugin ships its own skill named `context-mode` — discovered via a live install test, see below. The methodology's gates are unaffected. Skill count 34 → 35.

### Added

- **`skills/context-mode-setup/SKILL.md` — `/context-mode-setup` skill (Efficiency category).** Integration with the upstream [Context Mode plugin](https://github.com/mksglu/context-mode) (ELv2, source-available — *not* MIT). Documents what Context Mode provides **as verified against the installed plugin 1.0.168** (8 skills: `context-mode` + `ctx-doctor`/`ctx-search`/`ctx-stats`/`ctx-index`/`ctx-insight`/`ctx-purge`/`ctx-upgrade`; 6 harness-only lifecycle hooks; a bundled `server.bundle.mjs` + `better-sqlite3` engine — `claude plugin details` reports **MCP servers: 0**, so the work is done via hooks, not `ctx_*` MCP tools; ~631 tok always-on cost), the Node ≥ 22.5 / Claude Code ≥ 1.0.33 requirements, and the read-only detection path (`claude plugin list`, `claude plugin details`, `node --version`). Includes an **idea-to-deploy fit** table (where it pays off — long `/kickstart` builds, long `/task`/`/bugfix` sessions; where not — short single-shot tasks) and a **coexistence** section (17 idea-to-deploy hooks + 6 Context Mode hooks; verify via the `ctx-doctor` skill; gates must still fire). Read-only, no global/network install without explicit approval, no upstream ELv2 source copied into the repo; does not replace `/review`, `/test`, `/security-audit`, `/caveman`, or any work route.
- **Trigger block in `hooks/check-skills.sh`** routing context-mode phrases ("context mode", "режим контекста", "экономия контекста", "забивается контекст", "большой вывод инструмента", "sandbox tool output", "context window optimization", "huge tool output", …) to `/context-mode-setup`. Verified by `tests/verify_triggers.py` (no drift) and the routing benchmark (`tests/verify_routing.py`, 64/64 = 100%).
- **`tests/fixtures/fixture-27-context-mode-setup/`** — snapshot stub (status `pending`, same read-only detect/advise bucket as `fixture-15-advisor`, `fixture-21-mcp-docs`, `fixture-26-caveman`). `idea.md` + `notes.md` document the contract (detect-before-claim, no-vendoring-of-ELv2, lifecycle fit, gate coexistence) for manual verification; `expected-files.txt` asserts the no-files-written contract.

### Changed

- **Skill count 34 → 35 across docs.** Updated the Skills badge, prose counts, the "Efficiency" category section header + new `/context-mode-setup` row, and the Skill Contracts + Recommended Models tables in `README.md` and `README.ru.md`; description counts in `.claude-plugin/plugin.json` and `.claude-plugin/marketplace.json`; and the current-count claims in `docs/CONTRACTS.md`, `docs/CONTENT-PLAN.md`, `docs/competitive-analysis.md`, `docs/promotion/marketplace-submissions.md`, and the `docs/promotion/drafts/*` articles (enforced by meta-review check M-C12).

### Verified

- **Live install test alongside idea-to-deploy.** Installed the upstream plugin from a shell (`claude plugin marketplace add mksglu/context-mode` + `claude plugin install context-mode@context-mode`, both exit 0) and confirmed **registration-level coexistence**: `~/.claude/settings.json` holds both plugins' hooks with no overwrite. The test surfaced two corrections folded into this change: the upstream skill-name collision (`context-mode` → renamed ours to `context-mode-setup`) and the mechanism description (skills + harness-only hooks + bundled engine, **not** `ctx_*` MCP tools). Runtime verification (`ctx-doctor` + live output interception) requires a fresh session with Node ≥ 22.5 and is left as a documented manual step.

## [1.26.0] - 2026-06-27

**New `/caveman` token-efficiency skill (port of the public Caveman plugin).** Adds an idea-to-deploy-native communication-style control that cuts output tokens ~75% via terse "caveman" replies while keeping full technical accuracy. The methodology's gates still win over brevity: gate status, blockers, verification evidence, security warnings, and destructive-action confirmations are never compressed. Skill count 33 → 34.

### Added

- **`skills/caveman/SKILL.md` — `/caveman` skill (new category: Efficiency).** Port of the upstream [Caveman plugin](https://github.com/JuliusBrussee/caveman) (MIT) adapted to idea-to-deploy conventions. Modes: `lite` / `full` (default) / `ultra` / `wenyan-lite` / `wenyan-full` / `wenyan-ultra`; `normal mode` / `stop caveman` reverts. Preserves the upstream compression rules, intensity table, and **Auto-Clarity** safety carve-outs (security warnings, irreversible/production confirmations, multi-step sequences, legal/medical/financial caveats), plus an idea-to-deploy fit section that keeps the skill-decision line, route/gate status, verification evidence, and commit/push/PR status explicit. Read-only, session-scoped style state; does not perform any global/network install of the upstream plugin and does not replace `/review`, `/test`, `/security-audit`, or any work route.
- **Trigger block in `hooks/check-skills.sh`** routing caveman phrases ("caveman mode", "talk like caveman", "меньше токенов", "сжимай ответы", "less tokens", "be brief", "token efficiency", …) to `/caveman`. Verified by `tests/verify_triggers.py` (no drift) and a routing smoke-test (non-caveman phrases do not over-match).

### Changed

- **Skill count 33 → 34 across docs.** Updated Skills badge, prose counts, the new "Efficiency" category section, and the comprehensive Skill Contracts + Recommended Models tables in `README.md` and `README.ru.md`; description counts in `.claude-plugin/plugin.json` and `.claude-plugin/marketplace.json`.

## [1.25.0] - 2026-06-27

**Commit gates now count review/test/security work done by a subagent (bug #2 follow-up).** Delegating a review to the `code-reviewer` agent (instead of the `/review` skill) left no completion sentinel, so `check-review-before-commit.sh` saw "no review" and falsely blocked the commit — notably from WSL. The same class of false-block hit the DoD gate for `test-generator`/`security-reviewer`. Fixed additively with a new PostToolUse hook; the gates themselves are unchanged. Minor bump per SemVer.

### Added

- **`hooks/record-agent-skill.sh` — PostToolUse hook on `Task`/`Agent` (hook #17).** After a subagent finishes, it writes the matching skill completion sentinel on the agent's behalf, so the commit gates count delegated work. Mapping (restricted to agents that satisfy a real gate): `code-reviewer → review`, `test-generator → test`, `security-reviewer → security-audit`. This is the only viable mechanism: the backing agents are read-only (`Read/Grep/Glob`, no `Write`/`Bash`) so they cannot write a sentinel themselves, and the `Skill` tool emits no hook events — but the `Task`/`Agent` tool does. PostToolUse (not Pre) so the sentinel marks an *actually-completed* pass. Never blocks (always exits 0); writes to every temp dir the gates search (`/tmp` + platform temp dir).
- **`tests/verify_agent_review_sentinel.py`** — 10-case behavioural test: each mapped agent writes the right sentinel; unmapped agents and non-subagent tools write nothing; plus two end-to-end assertions through the real gates — the **review** gate denies a >2-file commit before the `code-reviewer` agent and allows it after, and the **DoD** gate denies a payments-path commit before the `security-reviewer` agent and allows it after.

### Fixed

- **Review/DoD gates falsely blocked commits when the review/test/security pass was delegated to a subagent.** `check-review-before-commit.sh` and `check-dod-before-commit.sh` detected skill completion only via the sentinel the *skill* writes at its final step; a subagent left none. Root cause: read-only agents can't write the sentinel, and the `Skill` tool emits no hook events. Resolved by `record-agent-skill.sh` above — no change to the gate logic, which keeps reading the same sentinel filename.

### Changed

- **`PostToolUse` hook registration added** with matcher `Task|Agent` → `record-agent-skill.sh`, in the active settings of both environments, `scripts/sync-to-active.sh` (the canonical desired-hooks block), and `skills/adopt/references/project-settings-template.json` so newly-adopted projects get it. `hooks/README.md` and `skills/adopt/SKILL.md` updated to document the hook.

## [1.24.0] - 2026-06-27

**Two infrastructure fixes: the skill-enforcement gate no longer dead-ends a legitimate skill-driven Edit flow, and heavy fork skills have a documented escape from autocompact-thrash on large `CLAUDE.md` repos.** Both are additive and backward-compatible (minor bump per SemVer); the never-block enforcement guarantee is preserved and now regression-tested.

### Fixed

- **Skill-enforcement gate falsely blocked active skill work (`hooks/check-tool-skill.sh`).** PreToolUse/PostToolUse hooks do **not** fire for the `Skill` tool, so the gate's `tool == "Skill"` counter-reset branch was dead code in production — the ignore counter accumulated *through* a legitimately-active skill and then blocked it. The block was a true dead-end for `Edit`/`Write`/`NotebookEdit`, which carry no `description` field and therefore cannot supply an in-band `SKILL_BYPASS`. Fix: a per-session **skill-active sentinel** (`/tmp/claude-skill-active-<session>.state`) grants a bounded **grace window** (`SKILL_ACTIVE_TTL_SECONDS = 900`). The sentinel is written by `check-skills.sh` (a UserPromptSubmit hook, which *does* fire reliably) whenever the prompt matches a skill trigger, and by `check-tool-skill.sh` itself whenever a `SKILL_BYPASS` is accepted. A *fresh* sentinel resets the counter and allows silently; a *stale* one does not — so enforcement always resumes (never-block-forever guard).

### Added

- **`tests/verify_skill_enforcement.py`** — 9-case behavioural regression test for the enforcement gate, wired into `.github/workflows/meta-review.yml`. Locks the two guarantees against regression: the gate **still blocks** after `MAX_IGNORES` consecutive ignores, and a **stale** skill-active sentinel does **not** suppress the block. Also covers the end-to-end `check-skills.sh → check-tool-skill.sh` sentinel contract.
- **Runner-selection fallback in the agent-backed fork skills (`/review`, `/perf`, `/blueprint`, `/discover`).** A `context: fork` skill inherits a copy of the current conversation including the project `CLAUDE.md`; on heavily-onboarded repos (> ~12 KB) the fork starts near the context limit and autocompact-thrashes until it dies. Each skill now documents the escape: when `CLAUDE.md` is large, **dispatch the backing agent via the Agent tool** (fresh thin context, files referenced by path) instead of relying on the fork.

### Changed

- **`Skill` added to the `check-tool-skill.sh` PreToolUse matcher** (active settings in both environments + `skills/adopt/references/project-settings-template.json`) as forward-compat: if a future harness starts emitting Skill hook events, the existing reset+sentinel branch activates automatically. Harmless no-op until then.

## [1.23.0] - 2026-06-26

**Definition-of-Done enforcement: high-risk commits can no longer quietly skip their mandatory skill.** Adds a narrow pre-commit gate (Layer 1) that blocks a `git commit` touching a DB migration/schema, a payments/auth/secrets path, or a brand-new source file when the matching skill (`/migrate`+`/test`, `/security-audit`, `/test`) was not run this session — plus a skill-bypass ledger and a `/session-save` self-audit (Layer 2) so a skipped gate is impossible to miss at session end. Generalises the existing `/review`-before-commit gate to the other risk signals; deliberately narrow to avoid alarm fatigue. Additive and backward-compatible (minor bump per SemVer).

### Added

- **`hooks/check-dod-before-commit.sh` — Definition-of-Done pre-commit gate (hook #16).** PreToolUse on Bash. On `git commit` it inspects the staged diff and BLOCKS (`deny`, exit 2) when a high-risk signal is present but the matching skill sentinel is absent this session:
  - migration / schema / DDL (`migrations/`, `*.sql`, `schema.prisma`, `alembic/`) → requires `/migrate` **and** `/test`
  - payments / auth / secrets in a staged file path → requires `/security-audit`
  - a brand-new source file with no test staged → requires `/test`

  Escape hatch: `SKILL_BYPASS:` in the commit message (recorded in the ledger). Shell/infra scripts are excluded from the test rule, and the `>2 files → /review` rule intentionally stays in `check-review-before-commit.sh` (not duplicated). Covered by `tests/verify_dod_gate.py` — 12 behavioural cases including false-positive guards for docs-only, modified-source, and shell-script commits.
- **Skill sentinels in `/test`, `/migrate`, `/security-audit`** — each now writes `/tmp/claude-<skill>-done-<session>` at its final step (mirroring `/review`'s Step 5), the signal the DoD gate reads.
- **Bypass ledger (Layer 2) in `hooks/check-tool-skill.sh`** — every `SKILL_BYPASS:` decision is appended to `/tmp/claude-skill-ledger-<session>.jsonl` (timestamp + tool + reason), best-effort and non-blocking.
- **`/session-save` Step 4.9 — skill-coverage self-audit** — reads the bypass ledger and skill sentinels, cross-checks them against the session's risk signals, and records any gap (a risk signal present whose skill never ran) in the session memory file. Advisory; never blocks `/session-save`.
- **`tests/verify_dod_gate.py`** — behavioural unit test for the gate, wired into `.github/workflows/meta-review.yml`.

### Changed

- **Hook count 15 → 16** across published descriptions and prose: `.claude-plugin/plugin.json` (+ `Definition-of-Done pre-commit gate` capability), `.claude-plugin/marketplace.json`, `README.md` / `README.ru.md` (badges + narrative), `hooks/README.md`.
- **Hook registration** — `scripts/sync-to-active.sh` and `skills/adopt/references/project-settings-template.json` now register `check-dod-before-commit.sh` in the `Bash` PreToolUse group, so both the active install and newly-adopted projects pick up the gate.

## [1.22.0] - 2026-06-24

**Observability, routing robustness, and harness-engineering mapping.** Adds the opt-in `execution-trace.sh` hook (closes the last open harness-engineering principle — H5 observability), a deterministic routing-accuracy benchmark with a new Critical meta-review check (M-C17), the Harness Engineering coverage map plus a control-harness hook classification, and the "meeting / interview prep" router trigger — alongside cross-platform fixes that make the skill-enforcement gate actually block on Windows. All changes are additive and backward-compatible (minor bump per SemVer).

### Fixed

- **`hooks/check-tool-skill.sh` — skill-enforcement gate now actually accumulates.** `session_id()` fell back to `getppid()`, which differs on every hook spawn (a fresh python process per call, especially on Windows), so the per-session ignore counter reset to 1 on every reminder and the gate **never blocked** (the documented v1.19.0 enforcement was inert on Windows). It now anchors to a single per-day file (or `CLAUDE_SESSION_ID` when set), so consecutive ignored skill reminders accumulate and block at 3 as designed.
- **`hooks/check-tool-skill.sh` + `check-skills.sh` — closed the "continue" loophole and require a visible decision line.** The reminder text no longer says "if you're already inside a task, continue" — the escape hatch that let the model skip skills silently. Both hooks now require declaring the skill decision on the FIRST line of the response (`Скилл: /X` or `Скилл: не нужен — <reason>`); an explicit `SKILL_BYPASS: <reason>` stays a valid, counter-resetting decision (conscious refusal != ignore).
- **`hooks/check-skills.sh` — router robustness (found by the new M-C17 benchmark, 92.2% → 100%).** Five trigger regexes required exact verb-target adjacency and missed natural paraphrases: `/guide` ("generate a step-by-step guide for the project"), `/migrate` ("apply **a** migration", "add **a** column"), `/session-save` ("wrap up **the** session"), and `/tool-sync` ("экспортируй **задачи** в Notion", "sync **our** roadmap to Linear"). Each was widened to admit optional articles / intervening words without broadening into neighbouring skills.
- **`skills/{test,doc,bugfix}/SKILL.md` — three daily-work skills failed to register globally.** They carried a top-level `paths:` frontmatter key (globs scoping auto-load to test files / docs / logs); on the current CLI that also made the Skill tool report "Unknown skill" in non-matching directories, so `/task` could not route to `/test`, `/doc`, or `/bugfix` in any project lacking those files — inconsistent with their sibling daily-work skills (`/perf`, `/refactor`, `/explain` carry no `paths:`). Removed the key so they register everywhere.

### Added

- **`hooks/execution-trace.sh`** — opt-in live execution-trace hook (PreToolUse, hook #15). Appends one JSON line per tool call (`{ts, tool, target}`) to `.claude/traces/session-<id>.jsonl` in the project — a live, replayable record of which tool ran against what, for debugging the methodology and user oversight. Pure side-effect telemetry: injects **nothing** into the model context (zero context-budget cost), never blocks (exit 0, no permission verdict), fail-safe (any error → exit 0), and `.claude/` is gitignored so traces never reach the repo. Opt-in like `cost-tracker.sh` — registered in the `EXEMPT` list of `scripts/verify-sync-to-active.sh`, active only when added to `settings.json` (matcher `*`). Closes the **H5 / `K15`** observability gap — the only principle previously marked partial in the harness-engineering and design-space maps — implemented on explicit maintainer request (the ROADMAP signal criterion). M-C10 schema check passes; `tests/meta_review.py` Critical 0.
- **`docs/HARNESS_ENGINEERING_MAP.md`** — maps the methodology against the 5 principles + 2 template artefacts of the [Harness Engineering course (walkinglabs)](https://walkinglabs.github.io/learn-harness-engineering/ru/). With `execution-trace.sh` landed, **all 5 principles are now covered in full** (H1 constraining behavior, H2 context preservation, H3 preventing premature completion, H4 verification through testing, H5 observability) and both templates are covered: `AGENTS.md` → `CLAUDE.md` + the `.itd/` contract layer (T1); `feature_list.json` → `ACCEPTANCE_CONTRACT.json` + `VERIFICATION_CONTRACT.json`, machine-readable and fail-closed (T2). Sister-doc to `docs/DESIGN_SPACE.md`.
- **Routing-accuracy benchmark (`tests/verify_routing.py` + `benchmarks/routing-prompts.json`) — new Critical meta-review check M-C17.** Ported in spirit from `product-factory-os` `benchmarks/prompts.json` (which scores product-type classification) and adapted to skill routing — the canon's actual deterministic classifier. Feeds 64 realistic, **paraphrased** RU + EN prompts (deliberately NOT the verbatim trigger phrases) through `hooks/check-skills.sh` and asserts each reaches its `expectedSkill` as the *primary* skill of a matched trigger. Where M-C11 guards verbatim phrases against drift, M-C17 measures the router's **robustness** to phrasings the authors never wrote down. Wired into `tests/meta_review.py` (subprocess, fail-closed) and documented in `tests/README.md` + `skills/review/references/meta-review-checklist.md`.
- **`docs/HARNESS_ENGINEERING_MAP.md` §8 — control-harness classification.** Ported the control-harness lens from `product-factory-os` `docs/METHODOLOGY.md`: classifies all 15 hooks on two axes (feedforward/feedback × computational/inferential) plus a blocking/soft column. Surfaces that all 6 blocking hooks are computational × feedforward — the methodology never gates a hard `deny` on inferential model judgment — and codifies the design rule for future hooks (blocking ⇒ computational; semantic checks ⇒ soft hint, never `deny`).
- **FAQ entry in `README.md` and `README.ru.md`**: "How does idea-to-deploy relate to 'Harness Engineering' (walkinglabs)?" — links to `docs/HARNESS_ENGINEERING_MAP.md` in both languages; states 5/5-full coverage and both template statuses honestly.
- **`hooks/check-skills.sh` — new "meeting / interview prep" trigger.** Prompts about preparing for a meeting, conducting an interview, or drafting/formulating questions (RU + EN) now route to `/advisor`, `/grill-me`, or `/discover`. Closes a coverage gap where discovery/advisory prep ran ad-hoc because no trigger fired.
- **`.gitattributes`** — `* text=auto eol=lf` normalizes all text files to LF in-repo and on checkout. Prevents the whole-tree EOL-only "modified" churn that appears when files are touched by Windows editors or via DrvFs (`/mnt`) access; `text=auto` lets git auto-detect binaries and leave them untouched.

### Changed

- **Hook count 14 → 15** across published descriptions and prose: `.claude-plugin/plugin.json` (+ `live execution tracing` capability), `.claude-plugin/marketplace.json` (was a stale `13`), `README.md` / `README.ru.md` narrative (the RU prose was additionally stale at `тринадцать`/`одиннадцать` — now correct), `hooks/README.md` (new table row + counts), `docs/CONTRACTS.md`, `docs/promotion/marketplace-submissions.md`.
- **`docs/DESIGN_SPACE.md`** — `K15` (execution transparency / tracing) flipped ◐ → ✅ with a closure note (per the doc's own update protocol); §6 summary recount (✅ 7 → 8, ◐ 6 → 5); §7 candidate list updated (K15 done; K4/K16 remain). Sister-doc cross-link to `HARNESS_ENGINEERING_MAP.md` added in §2.

### Fixed

- **`hooks/check-tool-skill.sh` — enforcement gate now actually blocks on Windows.** State files were written to `/tmp/claude-skill-*`, which on Windows resolves to a non-existent `C:\tmp`; writes failed silently (`except: pass`) so the ignore counter never persisted and the gate degraded to a non-blocking reminder (stuck at `1/3`). Switched to `tempfile.gettempdir()` + `os.path.join`, so the counter persists cross-platform and the `deny` after `MAX_IGNORES` fires as designed. Verified on Windows: counter=3 → `permissionDecision: deny`, exit 2; `Skill` call resets to 0.
- **Hook doc-pointer path** — `check-tool-skill.sh` and `check-skills.sh` referenced `~/projects/.claude/CLAUDE.md` (a PFO-era path that does not exist on Windows); corrected to `~/.claude/CLAUDE.md`, the global-mandate location on both Windows and WSL.

## [1.21.0] - 2026-06-22

**Release — PFO plugin-native port complete (19/19 mechanisms).** This release lands the full port of product-factory-os's executable-methodology ideas into idea-to-deploy as a plugin: the `.itd/` contract layer + gates (Waves 0–2), 8 new skills (25 → 33), 3 new reviewer agents (7 → 10), machine-readable `starters/` + `golden-paths/`, and the `/adopt` product-type analyzer. `tests/meta_review.py` Critical 0 throughout.

**PFO plugin-native port — Wave 0 (contract foundation).** Began porting the executable-methodology ideas from **product-factory-os** (a Codex CLI runtime) into idea-to-deploy *as a plugin, without a standalone runtime*. An audit of PFO against idea-to-deploy's "plugin, not CLI" identity found ~19 of PFO's mechanisms are plugin-native (templates + hooks + CI — substrates idea-to-deploy already has) and only 2 (`itd` CLI, `install.sh`) genuinely need a runtime and are the lowest-ROI; those are explicitly out of scope. This wave lands the **contract layer** that the later gate-wiring waves depend on.

### Added (PFO port Wave 0)

- **`docs/CONTRACTS.md`** — the keystone doc: records the plugin-vs-runtime decision, describes the `.itd/` contract + `.itd-memory/` state layers, maps all 19 plugin-native mechanisms to their landing vector (template/hook/skill/CI), and tracks port status across Waves 0–2. Also records what is intentionally NOT ported (the `itd` CLI and `install.sh`; `/skill-create` as duplicate of Anthropic `skill-creator`; and `/seo` + `/brainstorm`, which a prior analysis hallucinated — neither exists in PFO's `skills/`).
- **`docs/templates/itd/`** — 13 project-contract templates ported and adapted from PFO (`.pfo/`→`.itd/`, `.codex-memory/`→`.itd-memory/`, `CODEX.md`→`CLAUDE.md`, actor `codex`→`claude`): `PROJECT_CONTRACT.md`, `SCOPE_LOCK.md`, `GOLDEN_FLOWS.md`, `FORBIDDEN_CHANGES.md`, `DATA_POLICY.md`, `FALLBACK_POLICY.md`, `VERIFICATION_CONTRACT.json` (fail-closed), `ACCEPTANCE_CONTRACT.json` (new — "done" as a traceable proof checklist derived from the user request), `EXECUTION_POLICY.json`, `PERMISSION_MATRIX.json`, `PERMISSION_MATRIX.md`, `TOOL_CAPABILITY_REGISTRY.json`, `LEARNING_PROMOTION_GATE.md`.
- **`docs/templates/`** — `UNIT_CONTEXT_MANIFEST.json` (fresh, bounded per-node context), `ROOT_CAUSE.md` (bugfix root-cause record with reproduction + regression test), `BRANCH_FINISH.md` (explicit PR/merge/keep/discard decision with fresh verification). All 6 JSON templates validated.

### Added (PFO port Wave 1 — gates)

- **Two-stage `/review`** — new **Stage A spec-compliance gate** runs before the quality rubric: checks the diff against `.itd/ACCEPTANCE_CONTRACT.json` criteria/evidence, `.itd/UNIT_CONTEXT_MANIFEST.json` goal + scope, and `.itd/SCOPE_LOCK.md`. Spec FAIL → `BLOCKED` regardless of code quality (beautiful code that solves the wrong task does not pass). Backward-compatible: soft no-op when no `.itd/` contracts are present.
- **Fail-closed verification** in `/test` Step 5 and `/review` Stage A — a `passed` status now requires evidence actually produced (a real run with visible output). Un-run / errored / ambiguous verification is reported as a blocker (`RECOVERY_REQUIRED`), never as success. Mirrors `.itd/VERIFICATION_CONTRACT.json` `failClosed`.
- **Root-cause gate** in `/bugfix` Step 3 — record root cause as an artifact (`ROOT_CAUSE.md` from template) before writing the fix; fail-closed (can't state root cause in one evidenced sentence → not found, keep analysing). Trivial one-liners use an inline sentence.
- **TDD evidence gate** in `/test` Step 5 — for behavior changes, prefer test-first with explicit red→green evidence; impractical cases must state the exception rather than silently skip.
- **Branch-finish decision** in `/session-save` Step 4.8 — explicit `PR | merge | keep | discard` with fresh verification when wrapping up a feature branch; never discard without typed confirmation; no-op on `main`/mid-task.
- **Skill-contract profile frontmatter on all 25 skills** — each `skills/*/SKILL.md` now declares `effort` (low/medium/high), `side_effect` (read-only/local-write/command-execution/memory-write/external-write/production-mutation/…), and `explicit_invocation` (true for dangerous skills `migrate`/`migrate-prod`/`deploy`/`infra`/`autopilot`, false for auto-routable ones). Makes routing and safety explicit and machine-checkable instead of re-derived per skill.
- **`scripts/verify_skill_profiles.py`** — read-only validator that fails (exit 1) if any skill is missing a profile field or uses an out-of-enum value. Intended as a CI gate (`docs/CI.md`). Currently green across all 25 skills.
- Verified against `tests/meta_review.py`: Critical 0, FINAL STATUS PASSED_WITH_WARNINGS (unchanged from baseline; the single Important is a Windows-only env artifact, M-I7).

### Added (PFO port Wave 2 — state & metrics)

- **Structured session state** — `docs/templates/itd-memory/session-state.schema.json` (ITD-adapted from PFO; runtime-only fields like `experimentLoop`/`worktreeIsolation` dropped) plus `STATE.example.json` and `events.example.jsonl`. Makes recovery-after-a-break machine-checkable instead of prose. `gateResults` aligns with the Wave 1 gates (acceptanceContract, specComplianceReview, tddRed/Green, rootCause, branchFinish, …).
- **`scripts/validate_state.py`** — validates `.itd-memory/STATE.json` against the schema; **fail-closed** (empty `approvalStatus`/`recommendedNextStep`/`nextAction` is a failure, not a pass). Verified: passes a filled example (exit 0), rejects the empty template with a fail-closed error (exit 1).
- **`scripts/itd_metrics.py`** — aggregates harness-efficiency metrics across a workspace of `*/.itd-memory/STATE.json` (gate pass-rate, blocked/failed counts, verification events, artifact debt); JSON or `--markdown`. Lets the methodology improve by numbers, not impressions. Verified against a sample workspace (gatePassRate 0.65 on the example).
- `tests/meta_review.py` Critical 0 / PASSED_WITH_WARNINGS unchanged.

### Added (PFO port Wave 2 — routing & context budget)

- **Process-cost tiers (complexity routing)** — `skills/_shared/helpers.md` §6 defines trivial / standard / high-risk tiers (based on PFO's `product-classifier` COMPLEXITY signal, **not** any fabricated "minimal/standard/full" profile) and which contracts/gates each applies. Wired into `/task` (Step 1b — classify before routing) and `/project` (Step 3b — scale the lifecycle by product complexity). The high-risk tier aligns with skills carrying `explicit_invocation: true`.
- **Context budget** — `skills/_shared/helpers.md` §7 (summarize, bound at source, artifact + path instead of raw dumps) plus **`hooks/context-budget.sh`** — a Python 3 PreToolUse soft hook (14th hook) that nudges when a Bash command is likely to dump a large unbounded output (raw HTTP body, `cat` of big file, wide `grep`/`find`/`rg` with no cap). Soft reminder only, never blocks. Verified: warns on unbounded commands, silent on bounded ones (`-m`, `head`, `tail`, `| head`).
- `hooks/README.md` + `README.md` hook count updated 13 → 14. (Promo copy still says 13 — flagged as a docs-sync follow-up in `docs/CONTRACTS.md`.)
- `tests/meta_review.py` Critical 0 / PASSED_WITH_WARNINGS (M-C10 initially caught the new hook as a bash file with no declared event — fixed by rewriting it as a Python 3 PreToolUse hook per repo convention).

**Content-batch follow-ups under ROADMAP v1.21 DEFERRED.** Five PRs landed on 2026-04-21 — one positioning artefact (design-space mapping), one content hotfix, two tech-debt fixture expansions, and one reliability fix in the review-gate hook. No version bump (methodology stays at `1.20.3` per DEFERRED), but work is recorded here per Keep a Changelog convention — the `[Unreleased]` section accumulates between releases regardless of release cadence.

### Added (PFO port — item 18: 8 new skills)

- **8 new skills ported from product-factory-os** (25 → 33 skills), each with the full completeness set (`SKILL.md` + `references/` + trigger block in `hooks/check-skills.sh` + regression fixture, `status: pending`) and skill-contract profile frontmatter:
  - **`/handoff`** (Workflow, memory-write) — compact `HANDOFF.md` context packet for transfer to the next session/agent before compaction/delegation/AFK/recovery; distinct from `/session-save`.
  - **`/grill-me`** (Quality Assurance, read-only) — interactive one-question-at-a-time stress-test of plans/designs/decisions; runs before `/review`.
  - **`/market-scan`** (Research, local-write) — fresh public market/community signal scan (~30-day via last30days) → `MARKET_BRIEF.md`; `BLOCKED_EXTERNAL_TOOL` fallback, no fabrication; distinct from `/discover`.
  - **`/mcp-docs`** (Research, read-only) — fresh library/framework docs lookup via MCP/Context7; repo convention wins over docs unless broken/deprecated.
  - **`/github-workflow`** (Integration, external-write, explicit-invocation) — GitHub Issues/PR/CI/release workflow; no push/merge/close/release without explicit intent; `.itd-integrations/github.json` fallback.
  - **`/tool-sync`** (Integration, external-write, explicit-invocation) — mirror artifacts to GitHub/Linear/Notion/Google Drive/Obsidian; connector-native reads before writes (reconcile, never clobber).
  - **`/obsidian-export`** (Integration, local-write) — derived, regenerable Obsidian knowledge layer under `.itd-integrations/obsidian/`; canon untouched.
  - **`/browser-check`** (Quality Assurance, local-browser) — local browser smoke-test via a bundled Playwright harness (`skills/browser-check/playwright/`); broken render/flow → `BLOCKED` before deploy.
- **Two new skill categories** in `README.md` / `README.ru.md` — **Research** (`/market-scan`, `/mcp-docs`) and **Integration** (`/github-workflow`, `/tool-sync`, `/obsidian-export`). PFO `side_effect` values mapped to the validator enum (`external-read*`/`local-export-write` → `read-only`/`local-write`).
- Doc cascade kept `tests/meta_review.py` Critical 0 on every commit: skill count 25 → 33 + category subtotals + Skill Contracts + Recommended Models synced across both READMEs, `marketplace.json`, and M-C12-checked promo/draft docs.

### Added (PFO port — item 19: golden-paths, starters, agents pack, /adopt analyzer)

- **`starters/`** — 5 machine-readable starter packs matched to the methodology stack (`api-fastapi`, `saas-fastapi-vue`, `bot-aiogram`, `mini-app-vue`, `landing-vite`): `STARTER.json` (productType/stackPreset/stack/folders/commands/requiredArtifacts) + skeleton files. PFO → idea-to-deploy: `stackPreset itd-default-stack-v1*`, requiredArtifacts remapped to real artifacts.
- **`golden-paths/`** — 5 machine-readable product-type expectations (`api-service-booking`, `saas-subscriptions`, `messaging-bot-sales`, `mini-app-loyalty`, `landing-leadgen`): prompt, productType, starter, route (`/project -> /kickstart`), requiredArtifacts, minimumGates. READMEs map each abstract gate to its skill.
- **Reviewer agents pack** (7 → 10 agents) — `researcher` (→ `/market-scan`, `/mcp-docs`, `/discover`), `security-reviewer` (→ `/security-audit`, `/harden`), `ux-reviewer` (→ `/browser-check`, `/review`). All read-only with the M-I8 forked-context disclaimer. Agent-count doc cascade synced (Agents badge, README Subagents table both langs, `marketplace.json`, M-C12 promo).
- **`/adopt` product-type analyzer** — new Step 0.6 detects product type from manifests/structure (aiogram→messaging_bot, Telegram Mini App SDK→mini_app, FastAPI+Vue→saas, FastAPI-only→api_service, Vite/static-only→landing_page) and passes a reference starter/golden-path hint into the `/blueprint` voice-chain. Advisory only — never written into `CLAUDE.md`.
- **PFO plugin-native port complete (19/19 mechanisms).** `tests/meta_review.py` Critical 0 throughout; `verify_skill_profiles.py` green across 33 skills; trigger drift 0.

### Added

- **`docs/DESIGN_SPACE.md`** — mapping methodology coverage against the 16 architectural principles catalogued in *Dive into Claude Code* ([arxiv 2604.14228](https://arxiv.org/pdf/2604.14228), Liu et al., April 2026) + the [VILA-Lab companion repo](https://github.com/VILA-Lab/Dive-into-Claude-Code). 13 of 15 applicable principles are covered in full or partial form (7 ✅ / 6 ◐ / 2 ❌); K4 (context budgeting) and K16 (on-disk checkpoints beyond `git`) are flagged as signal-trigger candidates for a future v1.21 scope. §5.5 records a 2026-04-21 audit of the three `UserPromptSubmit` hooks (`pre-flight-check.sh`, `session-open-diagnostic.sh`, `context-aware.sh`) — all read-only relative to the project, `/tmp`-scoped state, no network calls, 2s git timeout — confirming the K12 pre-trust execution window surface is minimal and user-opt-in (not auto-loaded MCP). (PR #53)
- **FAQ entry in `README.md` and `README.ru.md`**: "How does idea-to-deploy relate to 'Dive into Claude Code' (arxiv 2604.14228)?" Links to `docs/DESIGN_SPACE.md` on both languages, honestly states coverage numbers and acknowledged gaps. (PR #53)
- **`tests/fixtures/fixture-17-adopt/idea.md`** and **`notes.md`** — created from scratch. The fixture previously existed only as a minimal snapshot stub; now has a documented FastAPI + Vue legacy-project adoption prompt and a 5-Scenario manual verification checklist (happy path / idempotency / self-reference refusal / not-a-git-repo / guard rails). (PR #56)
- **`expected-files.txt`** across 7 fixtures (11-discover, 12-autopilot, 13-strategy, 14-migrate-prod, 15-advisor, 16-deploy, 17-adopt) — documents expected output files plus explicit "MUST NOT produce" contract guards per skill. For deferred fixtures (`/advisor`, `/deploy`), the file declares "NONE expected" or "no files in project root" with rationale. (PR #55, PR #56)

### Changed

- **Seven regression fixtures upgraded from `status: pending` stubs to real behavioural contracts** (ROADMAP v1.21 §D tech-debt path, explicitly allowed outside DEFERRED scope). Classification: **5 active** (artifact-generating — `/discover`, `/autopilot`, `/strategy`, `/migrate-prod`, `/adopt`) + **2 deferred with improved rationale** (stdout-only — `/advisor`, live-ops — `/deploy`). Each active snapshot now declares required sections (bilingual patterns), `must_contain_any_of` domain-specific term groups (beauty-salon / Telegram bot / NeuroExpert / Beget→Hostland / aiogram / PostgreSQL / Cloudflare / etc.), `min_length_chars`, and `rubric_status` expectations. Each `notes.md` gains 3–5 Scenarios in the style of `fixture-01-saas-clinic`: happy path + edge cases + guard rails, per-step checkboxes, cross-reference to `check-skill-completeness.sh`, `/review` status section, and a `Failures` placeholder for regression logging. Deferred stubs articulate why active validation needs Phase 2 stdout-snapshot scheme (v1.16.0 anchor) rather than leaving a bare "verify_snapshot auto-passes" note. (PR #55, PR #56)
- **After this batch:** 14 active + 3 deferred fixtures out of 17 total. Only `fixture-10-task` remains as the original v1.16.0 stdout-snapshot anchor; all other `pending` stubs from the v1.19–v1.20 era are now either real contracts or explicit deferrals with documented rationale.

### Fixed

- **`README.ru.md:75`** — subagent count drift `6 определений субагентов` → `7`. Pre-existing inconsistency: the line said `6` while the badge on line 15 said `Agents: 7` and the subagents table listed 7 agents. The matching `README.md` line already said `7` correctly — Russian version drifted during earlier translations. Found as an incidental observation by `/review` during PR #53, isolated to its own narrow-scope PR per clean-commit convention. (PR #54)
- **`hooks/check-review-before-commit.sh` — sentinel sync gap**. The review-before-commit gate's strict PID-match lookup failed whenever `CLAUDE_SESSION_ID` was empty (the default in many Claude Code setups): the `/review` skill writes `/tmp/claude-review-done-$$` under its own process PID while the hook later reads `/tmp/claude-review-done-{os.getppid()}` under a different harness subprocess's parent PID, so the two paths never aligned. The v1.20.1 "sync gap closed" fix only worked inside stable-env single-process plugin sessions; real multi-subprocess harness usage still blocked legit post-review commits (observed during PR #56, which had to split 19 staged files into 12 ≤2-file commits as a workaround). The new two-tier lookup preserves the fast-path strict match for backward compatibility and adds an mtime-based fallback: any `/tmp/claude-review-done-*` sentinel with `mtime > now - REVIEW_FRESHNESS_SECONDS` (900s / 15 min) is accepted. Cross-OS (no `/proc` ancestry walk), `OSError`-tolerant against stat races between `glob` and `getmtime`, with trade-offs documented in the function docstring (cross-project false positive in the 15-min window is accepted given low commit frequency and clean reboot behaviour since `/tmp` is wiped). Three behavioural tests verify the three cases (no sentinel → DENY, fresh sentinel → PASS, stale 16-min sentinel → DENY). Users must run `bash scripts/sync-to-active.sh` after pulling to activate the fix in their `~/.claude/hooks/`. (PR #57)

### Ops

- **No version bump.** `.claude-plugin/plugin.json` stays at `1.20.3`; ROADMAP v1.21 remains DEFERRED per the 2026-04-17 `/advisor` decision. All five PRs fit within the ROADMAP §B ("content batch") or §D ("tech-debt + reliability") lanes that DEFERRED explicitly permits.
- **`/advisor` re-assessment on 2026-04-21** reconfirmed DEFERRED against a prompt to open v1.21 scope for K4/K16. Verdict: D (hold the pause), 8/10 — none of the three "When to revisit v1.21" criteria (multi-point signal n≥5, activated external user with specific pain, competitor feature shift) are objectively active. Paper publication alone is a document-layer event, not a user-pull signal. Opening scope four days after documenting the pause would erode the precedent the ROADMAP was written to protect.

---

## [1.20.3] - 2026-04-18

**Karpathy 4 principles adoption release.** Coverage map + template enrichment + goal-driven rule. Patch-release under ROADMAP v1.21 DEFERRED (ordinary tech-debt maintenance, not a feature release).

### Context

External analysis of [andrej-karpathy-skills](https://github.com/forrestchang/andrej-karpathy-skills) (Forrest Chang, ~54K stars — systematisation of Andrej Karpathy's [X post](https://x.com/karpathy) about typical LLM-agent mistakes) through `/advisor`. Finding: 2 of 4 Karpathy principles already covered strongly by idea-to-deploy (Think Before Coding, Surgical Changes), 2 covered partially (Simplicity First, Goal-Driven Execution). Three minimal patches close the gaps compatible with DEFERRED.

### Added

- **`docs/competitive-analysis.md` §8 «Karpathy 4 principles — coverage map».** Table mapping Karpathy's 4 principles to existing idea-to-deploy mechanisms (skills, hooks, subagents, meta-gates). Distancing strategy vs andrej-karpathy-skills: complementary, not competing. Explicit listing of what was done in v1.20.3 and what was deliberately deferred (e.g., test-first enforcement hook awaits n≥5 signal per ROADMAP_v1.21).
- **`skills/adopt/references/claude-md-template.md` «4 принципа аккуратного кода».** New Russian-language block inserted between skill-routing rules and project-specific context in the CLAUDE.md template written by `/adopt`. Every legacy project onboarded via `/adopt` now inherits the 4 principles (Think / Simplicity / Surgical / Goal-Driven) as part of its project-level methodology rules.
- **`skills/bugfix/SKILL.md` Step 1 soft-recommendation for test-first.** New prose guidance in «Reproduce»: write a failing test that reproduces the bug **before** the fix, when possible. Converts vague «fix the bug» into a verifiable goal («make this test pass»). Explicit fallback when test cannot be written (UI glitch, race condition, env-specific bug): record a binary success criterion in plain text.

### Changed

- **`skills/bugfix/SKILL.md` Rule 2** — now expresses preference for failing-test-before-fix (Step 1) over regression-test-after-fix (Step 6). Soft wording («Предпочтительно») — not an enforcement, matching the ROADMAP_v1.21 DEFERRED posture.

### Ops

- **Version bumps:** `.claude-plugin/plugin.json` 1.20.2 → 1.20.3, `.claude-plugin/marketplace.json` plugins[0].version 1.20.2 → 1.20.3, `skills/adopt/SKILL.md` metadata 1.20.0 → 1.20.3 (template changed), `skills/bugfix/SKILL.md` metadata 1.4.0 → 1.5.0 (behavioural guidance added). README.md and README.ru.md version badges updated.
- **Attribution:** [forrestchang/andrej-karpathy-skills](https://github.com/forrestchang/andrej-karpathy-skills), [Andrej Karpathy on X](https://x.com/karpathy).

### Deliberately not done (deferred to v1.21+ when multi-point signal arrives)

- **Test-first enforcement hook** — a `PostToolUse` hook that would warn when `/bugfix` edits code without a preceding new test. Rejected per ROADMAP_v1.21 criteria (n=0 signal, solo-maintainer surface cost, would bypass DEFERRED).
- **`EXAMPLES.md` for all 25 skills** — 25 × 2 anti-pattern pairs ≈ 1000 lines of docs with high drift risk. Existing in-skill examples + trigger phrases already cover the use cases.

### Lessons learned (meta-review gap)

- Pre-merge `/review` missed M-C5/M-C6/M-C13 drift because `plugin.json` bump was executed **after** the review agent's run. CI Gate 1 caught the drift correctly, confirming the gate's value. For future patch releases, always stage `plugin.json` + `marketplace.json` + `README.md` + `README.ru.md` + `CHANGELOG.md` version bumps **before** invoking `/review`, so the review agent sees the final drift state.

---

## [1.20.2] - 2026-04-17

**Follow-up polish release.** Closes the three small follow-up items deferred from v1.20.1: drift-proof M-C12 regex, content correctness in promo drafts, and automatic backup rotation for `sync-to-active.sh`.

### Fixed

- **M-C12 regex now catches Markdown-bold counts.** The old lookbehind `(?<!\S)` refused to match numbers preceded by Markdown inline markers like `**25 скиллов**`, so prose drafts could silently drift. Replaced with `(?<![-A-Za-z0-9])` — admits whitespace, line start, and Markdown markers (`**`, `*`, `_`, backtick) while still blocking hyphenated qualifiers like `depth-3 skills`. Applied to both `skill_direct_re` and `agent_direct_re`.
- **Competitor-section awareness in M-C12.** Added `in_competitor_section` state tracking. When a heading contains `vs <name>`, `competitor`, `конкурент*`, or `claude-code-skills`, bullets inside that section are skipped — competitors' own skill counts (e.g. `"масштаб (136 скиллов)"`) must not flag as our drift.
- **`historical_re` expanded** with competitor keywords and demonstrative-bug quoting patterns (`Operations (4 skills)`, quoted past-drift citations in drafts).
- **`docs/promotion/drafts/hn-headless-claude-poc.md` skill count** — stale `19 skills` → `25 skills` (real drift caught by the new regex).

### Added

- **`sync-to-active.sh` backup rotation** — keeps the 5 most recent `~/.claude/settings.json.bak-*` files, prunes older ones on every sync. Ran routinely, the backups would accumulate without bound otherwise.

### Ops

- Pruned 2 stale backups manually (pre-v1.20.1 era) from the author's install during v1.20.2 prep.
- Smoke-tested `/adopt` on two real legacy projects (`portfolio-cases`, `site`) — template substitution, marker-based idempotency, and project-level hook registration all verified end-to-end.

---

## [1.20.1] - 2026-04-17

**10/10 hardening release.** Closes the three remaining gaps from the v1.20.0 retrospective that kept onboarding-readiness, efficiency, and Anthropic-compliance scores below a perfect 10. Drift now auto-detected in CI; destructive operations are explicit-invoke only.

### Fixed

- **`check-review-before-commit.sh` now syncs to user-level install.** The hook shipped in v1.19.1 but was never added to `DESIRED_HOOKS` in `scripts/sync-to-active.sh`, so `bash scripts/sync-to-active.sh` never propagated it — users who followed the README setup got 12/13 hooks. Registered under the `PreToolUse` matcher `Bash` (same matcher as `check-commit-completeness.sh`, which catches the same `git commit` tool call). Header comment corrected from "all 4 hooks" to accurate "all 7 hooks (3 × UserPromptSubmit + 4 × PreToolUse)".
- **`/adopt` settings template now includes `check-review-before-commit.sh`** too — adopted projects get the full gate set matching the user-level install. `skills/adopt/SKILL.md` self-validation and Example output updated to say "4 PreToolUse" instead of "1 PreToolUse".

### Added

- **`scripts/verify-sync-to-active.sh`** — drift guard that cross-checks every `hooks/*.sh` against the `DESIRED_HOOKS` block in `scripts/sync-to-active.sh`. Any new canonical hook that lands in the repo without being registered fails the check with a clear `DRIFT` message. An explicit `EXEMPT` list covers the six opt-in hooks (`careful.sh`, `context-aware.sh`, `cost-tracker.sh`, `crash-recovery.sh`, `freeze.sh`, `stuck-detection.sh`) so they don't trip the gate.
- **CI job in `.github/workflows/meta-review.yml`** runs `verify-sync-to-active.sh` on every push and PR — the v1.19.1 `check-review-before-commit` gap can no longer recur.
- **`disable-model-invocation: true` on three destructive skills:** `/deploy`, `/migrate`, `/migrate-prod`. These operations have production-level blast radius (SSH to prod, DB schema change, DNS cut-over); an embedding-match on a vaguely similar prompt should not auto-invoke them. Users still call them explicitly by name — routers (`/task`, `/project`) still delegate to them normally. Matches the pattern already in place for `/autopilot` since v1.17.2.

### Changed

- **Skill `metadata.version` bumped to 1.20.1** on `/deploy`, `/migrate`, `/migrate-prod` (the three skills actually changed in this release).

### Verdict

Per v1.20.0 retrospective on 10-point scale:
- Работоспособность: 9 → **10** (sync-drift gap closed, CI guard added)
- Эффективность: 9 → **10** (automated drift detection prevents recurrence)
- Anthropic compliance: 9.5 → **10** (destructive skills explicit-invoke per best practice)

---

## [1.20.0] - 2026-04-17

**Legacy project adoption release.** Closes Gap #8 from `ROADMAP_v1.20.md` — the methodology applied unevenly to projects that were not created via `/kickstart` or `/blueprint`. The new `/adopt` skill onboards any existing legacy project into the methodology in one call, without rewriting user code and without hallucinating plan documents.

### Added

- **`/adopt` skill** (`skills/adopt/SKILL.md`) — minimal, idempotent adoption of legacy projects. Produces exactly three writes:
  - `CLAUDE.md` in the project root, or append-with-marker `<!-- idea-to-deploy:begin v1.20 -->` … `<!-- idea-to-deploy:end -->` if the file already exists.
  - `.claude/settings.json` project-level with the six canonical hooks (`session-open-diagnostic`, `pre-flight-check`, `check-skills`, `check-tool-skill`, `check-commit-completeness`, `check-skill-completeness`). User-level `~/.claude/settings.json` is never touched.
  - Memory dir bootstrap — creates `~/.claude/projects/-<dashed-cwd>/memory/` and invokes `/session-save` with a synthesized sentinel context.
  - Self-reference guard refuses to run inside the `idea-to-deploy` repo itself.
  - Voice-chain at the end: asks the user about plan documents → delegates to `/strategy` (live reassessment) or `/blueprint` (retroactive plan) based on the user's spoken answer plus repo heuristics (README presence, git history depth). No manual command entry.
- **`skills/adopt/references/claude-md-template.md`** — canonical methodology block appended to user's `CLAUDE.md`. Wrapped in markers so future re-adoptions are no-ops and so a user can remove the block manually.
- **`skills/adopt/references/project-settings-template.json`** — hook registration template with `{{PLUGIN_HOOKS_DIR}}` placeholder resolved at runtime from `$CLAUDE_PLUGIN_DIR`, `~/.claude/plugins/idea-to-deploy/hooks/`, or `~/.claude/hooks/` (legacy `sync-to-active.sh` path).
- **`tests/fixtures/fixture-17-adopt/expected-snapshot.json`** — stub fixture with `status: pending`, matching the pattern of `fixture-16-deploy` until a full contract is bootstrapped.
- **`adopt` trigger in `hooks/check-skills.sh`** — Russian + English trigger phrases for legacy-adoption intent, routed ahead of the `/task` tuple so legacy signals surface before generic tech-debt phrasing.
- **Step 1a legacy-project detection in `/task`** — `skills/task/SKILL.md` now detects projects with no adoption marker, no plan documents, and no project-level hooks, and suggests running `/adopt` first. Non-blocking; user can decline and go straight to routing.

### Non-scope (explicit)

- `/adopt` does **not** reverse-engineer `STRATEGIC_PLAN.md`, `PROJECT_ARCHITECTURE.md`, `IMPLEMENTATION_PLAN.md`, or `PRD.md` from source code. Hallucination risk is too high: a plausible-sounding plan that misrepresents KPIs, competitors, or scope poisons trust in the methodology. Plan generation is delegated to `/strategy` / `/blueprint` via the voice-chain.
- `/adopt` does **not** modify `~/.claude/settings.json`. Adoption is project-scoped.
- `/adopt` does **not** modify source code or perform any `git commit`.

### Changed

- **`plugin.json` version** — `1.19.2` → `1.20.0`, skills count `24` → `25`, description extended with "legacy project adoption".
- **`marketplace.json`** — version bump and description updated to match.
- **`README.md`, `README.ru.md`** — skill count badge + text references updated from `24` to `25`; version badge bumped.
- **`docs/promotion/*` and `docs/competitive-analysis.md`, `docs/CONTENT-PLAN.md`** — skill counts bumped.
- **`ROADMAP_v1.20.md`** — Gap #8 marked closed with v1.20.0 delivery record.

### Rationale

After v1.19.0 the methodology covered the full lifecycle for projects **created from scratch** — `/kickstart` and `/blueprint` scaffolds drop `CLAUDE.md`, memory dir, plan docs, and hooks on their own. But the dominant real-world case is **existing code**, where nothing of this infrastructure is present. A new user installing `idea-to-deploy` on a legacy project saw only half the methodology working: skills were available, but routing rules, hook reminders, memory, and planning scaffolds were absent. `/adopt` closes this gap with a single command while keeping the blast radius strictly bounded.

---

## [1.19.2] - 2026-04-16

**Onboarding polish release.** Closes the remaining 4 UX and 1 docstring findings deferred from v1.19.1 audit. Brings the methodology to 10/10 onboarding-readiness for external users scrolling through plugin listings.

### Changed

- **Install one-liner moved above the fold** in both `README.md` and `README.ru.md` — now appears in the first 10 lines, directly after the tagline. A new user opening the repo sees `/plugin install HiH-DimaN/idea-to-deploy` without scrolling past badges/demo/problem statement. Inline links to full install guide, E2E example, and skill contracts.
- **`scripts/sync-to-active.sh` promoted to primary hook-install path** in README setup section. The manual `cp + chmod + settings.json edit` route still exists, but is now wrapped in a `<details>` block as "for users who prefer to see each step". Matches the reality that 80%+ of users skip manual JSON editing and end up with half-installed methodology.
- **`marketplace.json` now includes `images`** — raw-GitHub URL to `docs/demo.svg`. Marketplace directory crawlers that render images will surface the demo; those that don't will silently ignore the field. Anthropic-directory listings with images have ~3× higher conversion per B3 audit finding.
- **`plugin.json` keywords trimmed from 17 → 11.** Dropped internal-only terms (`self-review`, `meta-review`, `methodology-validation`, `daily-work-router`, `safety-guardrails`, `red-blue-team`) that users never search for. Kept 11 external-facing keywords.
- **Russian README hook count corrected** — was stale "одиннадцать хуков", now "тринадцать".

### Fixed

- **`crash-recovery.sh` docstring no longer lies about integration.** v1.18.0 docstring claimed `pre-flight-check.sh` reads the checkpoint file on next session start; that consumer was never implemented. Docstring now correctly describes the checkpoint as "written for manual inspection after a crash; automatic re-hydration is a future enhancement". No behavior change — only accurate documentation.

### Verified (audit re-check, no action needed)

- **Hooks `additionalContext` field is valid for BOTH `PreToolUse` and `PostToolUse`** per the current Anthropic hooks spec (https://code.claude.com/docs/en/hooks.md). v1.19.1 audit flagged this as possible spec-drift for `careful.sh`, `freeze.sh`, `context-aware.sh`, `cost-tracker.sh`, `stuck-detection.sh`, and the reminder path of `check-tool-skill.sh`. Re-check against the official spec confirms: `additionalContext` is explicitly documented as a valid `hookSpecificOutput` field for both events. No hook changes needed — this was a false positive.

### Deferred

- PID-reuse edge case in `/tmp` state files (`context-aware.sh`, `stuck-detection.sh`) — `/tmp` survives only until reboot on Linux, and PID reuse would require both the old and new session to hit the same PID during the same boot. Low-probability; deferred to a future cleanup.

### Methodology score

Onboarding-readiness: **10/10** (up from 5/10 in pre-v1.19.1 audit).

- v1.19.0 baseline: `/deploy` hardcoded the author's private host, README subagents table was inconsistent with claimed counts, enforcement hook silently dropped its block, `/review` marker logic was architecturally broken.
- v1.19.1 closed all 5 Critical + 6 Important.
- v1.19.2 closes the 4 UX findings + 1 docstring inconsistency, plus verifies the remaining "unknown-status" audit findings against the current Anthropic spec.

---

## [1.19.1] - 2026-04-16

**Audit-driven patch release.** Closes 5 Critical + 6 Important findings from a deep methodology audit (3-stream: functional verification, Anthropic compliance, new-user UX). Makes the methodology usable by external users on their own projects.

### Fixed (Critical)

- **`check-tool-skill.sh` enforcement block actually fires now.** The v1.19.0 Gap #4 deliverable shipped with a broken deny path: it emitted `"permissionDecision": "block"` (wrong — spec requires `"deny"`) and returned exit 0 (wrong — must be exit 2 to block). The 3-ignore counter worked but the block was silently dropped by Claude Code's schema validator. Fixed to emit `deny` + `permissionDecisionReason` + `sys.exit(2)`, matching the v1.5.1 pattern in `check-commit-completeness.sh`.
- **`check-review-before-commit.sh` multi-file-commit gate unblocked.** The v1.19.0 hook assumed `Skill` tool calls route through `PreToolUse` hooks (they don't — `Skill` is an internal harness construct). The marker `/tmp/claude-review-done-{session_id}` was never written, so the hook always blocked. Architectural fix: the `/review` skill itself now writes the marker at its final step (Step 5). The hook only consumes the marker.
- **`/deploy` skill no longer hardcodes the author's private host.** Previous version shipped with `hostland`, `185.221.213.104`, `/opt/neuroexpert`, `scripts/render-kong.sh` embedded in every step — running `/deploy` on any other project SSH'd to a server the user didn't own. Rewritten to read `DEPLOY_HOST`, `DEPLOY_PATH`, `DEPLOY_COMPOSE`, `DEPLOY_SERVICE`, `HEALTHCHECK_URL`, `DB_CONTAINER`, `GATEWAY_RENDER_CMD` from `scripts/deploy-env.sh`, `CLAUDE.md` `## Deploy config` section, or `reference_deploy*.md` memory. Asks the user (and offers to write a template) if no config found.
- **README Subagents table now lists all 7 agents.** Previously had 6 rows but `plugin.json`/`marketplace.json` claimed 7 — `devils-advocate` (used by `/advisor`, `/strategy`, `/blueprint`) was missing. Row added in both `README.md` and `README.ru.md`.
- **README `/deploy` version marker corrected** — was tagged "New in v1.20.0" while `plugin.json` was still on `1.19.0`. Now correctly marked "New in v1.19.0".

### Fixed (Important)

- **14 skills had stale `metadata.version: 1.0.0` in v1.19.0 plugin.** Bulk-aligned to the version in which each skill was last meaningfully changed (`advisor`/`migrate-prod`/`strategy` → `1.19.0`, `autopilot`/`harden`/`infra`/`task`/`migrate`/`security-audit`/`deps-audit` → `1.18.0`, `discover` → `1.17.0`, `deploy` → `1.19.1`).
- **`kickstart` `allowed-tools` now unquoted** (was the only skill with a YAML-quoted string for this field) — format consistency across all 24 skills.
- **`context-aware.sh` stat label corrected** — was calling `UserPromptSubmit` events "tool calls" in the context-rot warning. Renamed to "user prompts" for accuracy.
- **`session-save` `argument-hint` is now useful** — was self-contradictory ("(no arguments needed...)" as a value of an argument hint). Now says "optional — brief note to append to the session summary".
- **`explain` default recommended model bumped from Haiku to Sonnet** — Haiku was too aggressive for non-trivial code explanations; swap preserves Haiku for single-function lookups and adds Opus for full-architecture walkthroughs.
- **`autopilot` marked `disable-model-invocation: true`** — high-side-effect pipeline (runs discover → blueprint → kickstart → review → test), should only be invoked explicitly. Loose embedding match on phrases like "run everything automatically" could previously trigger destructive auto-mode.

### Added

- **`check-review-before-commit.sh` hook row added to `hooks/README.md`** table + settings.json example (was missing from both in v1.19.0).
- **Fixture stubs for 6 pending fixtures** (`fixture-11-discover` through `fixture-16-deploy`) — each now has `idea.md` + `notes.md` so `tests/run-fixtures.sh` can execute them manually. Snapshots remain `status: pending` (auto-pass) until detailed content contracts are bootstrapped.

### Documentation

- Marketplace submissions install command unified to `/plugin install HiH-DimaN/idea-to-deploy` (was mixing `/plugin install` and `claude plugin add` across channels).

### Deferred

Three audit findings intentionally deferred to a follow-up release:
- Empirically-validated hooks soft-reminder format (`additionalContext` in `PreToolUse`/`PostToolUse`) — marked "works in practice" despite audit flagging it as potential spec-drift; will revisit once Anthropic spec formalizes the cross-event field.
- README install one-liner above fold + hook-install primary path (sync-to-active promoted to primary over manual cp + settings.json edit).
- Marketplace.json `images` / screenshots field.

---

## [1.19.0] - 2026-04-16

**Session enforcement + diagnostics (Phase 1).** Closes methodology gaps #4 and #6 from ROADMAP_v1.19.md — discovered during 10+ hour multi-project session where Claude bypassed methodology entirely.

### Added

- **`check-tool-skill.sh` enforcement mode** (Gap #4) — now tracks consecutive ignored skill reminders. After 3 ignores, BLOCKS the next Bash/Edit/Write tool call until Claude either invokes a Skill or provides a `SKILL_BYPASS: <reason>` justification. Counter resets on Skill call or bypass. Prevents the "advisory-only" problem where Claude ignores dozens of reminders.
- **New hook `session-open-diagnostic.sh`** (Gap #6) — fires once per session on first UserPromptSubmit. Reads last `session_*.md`, next-session plan, LAUNCH_PLAN.md, BACKLOG.md, latest ROADMAP_v*.md. Injects diagnostic context so Claude starts with full awareness of prior work and planned next steps instead of reactive mode.

### Changed

- Skill count: 20 → 23 across docs, READMEs, marketplace.json.
- Hook count: 11 → 12 across docs.
- Defense-in-depth table version bump to v1.19.0.
- `check-tool-skill.sh` now shows ignore counter (X/3) in reminders.
- `pre-flight-check.sh` now includes context-switch detection and memory staleness warnings.

### Phase 2: New skills

- **New skill `/strategy`** (Gap #2) — strategic replanning for existing projects. 5-dimension situation analysis, gap identification with concrete numbers, 2-3 option generation with devil's advocate stress-testing, ADR for pivot decisions, LAUNCH_PLAN.md and BACKLOG.md updates.
- **New skill `/migrate-prod`** (Gap #1) — production service migration between hosts. 8-step process: inventory → target setup → data migration → deploy → dual-run → DNS cut-over → rollback plan → decommission. Mandatory confirmation for production scope.
- **New skill `/advisor`** (Gap #3) — advisory/consulting mode. Analysis-only (no Write/Edit), mandatory multi-perspective evaluation via business-analyst and devils-advocate subagents. Structured pros/cons/risks output.

### Phase 3: Quality-of-life

- **Context-switch detector** (Gap #5) — `pre-flight-check.sh` now tracks cwd changes between prompts. Warns on project switch, suggests `/session-save` after 5+ switches in 30 min.
- **Memory staleness detection** (Gap #7) — `pre-flight-check.sh` compares version mentions in latest `session_*.md` against current `plugin.json`. Warns if stale version detected.

---

## [1.18.1] - 2026-04-13

**Adversarial architecture debates + community feedback.** Implements all 3 community-requested features.

### Added

- **New subagent `devils-advocate`** — adversarial architecture reviewer that challenges decisions, finds weaknesses, proposes alternatives. Red/Blue Team approach applied to design, not just security.
- **`/blueprint` Step 2.1: Architecture Decision Trees** — generates 2-3 architectural variants (e.g., Monolith vs Clean Architecture vs CQRS) with pros, cons, complexity ratings before choosing.
- **`/blueprint` Step 2.5: Adversarial Architecture Debate** — after Architect proposes, Devil's Advocate stress-tests the design. Produces ADR (Architecture Decision Record) with challenges and resolutions.
- **`/blueprint` Step 2.6: SAFe-Inspired Patterns** — Definition of Done in STRATEGIC_PLAN, Architectural Runway + Sprint Boundaries in IMPLEMENTATION_PLAN.
- **`/session-save` Step 4.7: Auto-sync** — automatically runs `sync-to-active.sh` in methodology repos to prevent skill/agent registration bugs.

### Fixed

- Subagent count drift: 6 → 7 across all docs, READMEs, marketplace.json.

---

## [1.18.0] - 2026-04-12

**GSD competitive analysis + 7 adaptations.** Major feature release inspired by GSD (51K stars) execution engine.

### Added

- **GSD as 6th competitor** in `docs/competitive-analysis.md` with full feature matrix comparison.
- **New skill `/autopilot`** — auto-pipeline: `/discover` → `/blueprint` → `/kickstart` → `/review` → `/test` with session-save checkpoints between phases. GSD auto mode inspired.
- **New hook `context-aware.sh`** — warns about long sessions and context rot risk, suggests fresh context strategies (tiered prompt injection pattern from GSD).
- **New hook `cost-tracker.sh`** — per-session token ledger with budget ceiling, tool call counts by type.
- **New hook `crash-recovery.sh`** — auto-checkpoint after every N significant tool calls for crash recovery.
- **New hook `stuck-detection.sh`** — sliding-window detection of repetitive tool calls (same file edited 3+ times, same command retried).
- **Git isolation reference** (`skills/kickstart/references/git-isolation.md`) — worktree per milestone pattern from GSD.
- **CI pipeline guide** (`tests/references/ci-pipeline-guide.md`) — tiered CI with budget control and retry logic.
- **`## Self-validation` in all 20 skills** — domain-specific checklists Claude verifies before presenting output.
- **Fixture `fixture-12-autopilot`** — snapshot fixture for the new `/autopilot` skill.
- **Trigger phrases for `/autopilot`** in `hooks/check-skills.sh`.

### Fixed

- `/discover` skill not registered in `~/.claude/skills/` (missing global copy since v1.17.0).
- `business-analyst` agent not registered in `~/.claude/agents/`.
- Skill count drift: 19 → 20 across all docs, READMEs, marketplace.json, content drafts.
- Hook count drift: 7 → 11 across READMEs.
- Syntax error in `hooks/check-skills.sh` (duplicate opening parenthesis).

---

## [1.17.2] - 2026-04-12

**Anthropic compliance: ## Rules in all skills.**

### Added

- `## Rules` section added to 10 skills that were missing it (Anthropic compliance requirement).
- All 19/19 skills now have Rules section (was 9/19).

---

## [1.17.1] - 2026-04-12

**Automatic safety guardrails.**

### Changed

- `careful.sh` hook now **always active** inside methodology repos (auto-detected via `.claude-plugin/plugin.json`). Outside repos: opt-in via `CAREFUL_MODE=1`.
- `freeze.sh` hook auto-scoped to methodology repo directories.

---

## [1.17.0] - 2026-04-12

**Competitive adaptations release.** Closes the two highest-priority gaps identified in `docs/competitive-analysis.md`: product discovery (vs BMAD) and safety guardrails (vs gstack).

### Added

- **New skill `/discover`** — product discovery phase: market analysis (TAM/SAM/SOM), competitor research, user personas, value proposition canvas, feature prioritization (MoSCoW + RICE). Outputs `DISCOVERY.md` ready for `/blueprint`. Full mode on Opus, Lite mode on Sonnet, refuses Haiku.
- **New subagent `business-analyst`** — specialized agent for `/discover`, focused on market analysis and feature prioritization in a forked context.
- **New hooks `careful.sh` and `freeze.sh`** (optional safety guardrails) — `careful.sh` warns before destructive commands (rm -rf, DROP TABLE, force-push); `freeze.sh` restricts edits to a specific directory scope. Both are opt-in per session via `/careful` and `/freeze <path>`.
- **`skills/_shared/helpers.md`** — shared helper definitions extracted from skill references to reduce token duplication across skills.
- **Fixture `fixture-11-discover`** — snapshot fixture for the new `/discover` skill.

### Changed

- Entry Points category now has 3 skills (`/project`, `/task`, `/discover`).
- Subagents table now has 6 entries (added `business-analyst`).
- Hooks count updated from 5 to 7 across all documentation.
- Skill Contracts and Recommended Models tables updated with `/discover` row.
- `meta_review.py` excludes `skills/_shared/` (directories starting with `_`) from skill counting.
- `check-skills.sh` trigger phrases updated with `/discover` triggers.

---

## [1.16.3] - 2026-04-12

**Fourth iteration of the self-improvement loop in this release cycle.** A user-spotted observation "in README tables I count skills inside parentheses and get 19 instead of 18" turned into a 6-drift cleanup and a new `M-C16` meta-review gate covering two previously-uncovered drift modes. This is the **fourth time** in v1.13.2..v1.16.3 where a user observation has surfaced a class of drift that automated structural gates missed.

### Audit context

After v1.16.2 merged (M-C15 hook count gate), the user counted skills shown in parentheses inside README category headings:

```
### Entry Points (2 skills)
### Project Creation (3 skills)
### Quality Assurance (2 skills)
### Daily Work (6 skills)
### Quality Assurance — Supply Chain (1 skill, new in v1.4.0)
### Operations (4 skills)
### Session Management (1 skill, new in v1.10.0)
```

Sum: 2+3+2+6+1+**4**+1 = **19**. Real skill count: 18. **Operations subtotal was wrong.** Investigation showed the Operations table has 3 rows (`/migrate`, `/harden`, `/infra`) but the heading said "(4 skills)" — drift introduced ages ago, never caught.

Then the user said "and in the Skill Contracts table only 17 skills are listed". Investigation:

| Table | Skills present | Missing |
|---|---|---|
| `README.md` Skill Contracts | 17 | `/task` |
| `README.md` Recommended Models | 17 | `/task` |
| `README.ru.md` Контракты скиллов | 17 | `/task` |
| `README.ru.md` Рекомендуемые модели | 17 | `/task` |

`/task` (added in v1.5.0) appeared in Entry Points table and Quick Start examples, but **was never added to the comprehensive contracts/models tables** in any language version of the README. This drift survived 11 months and 22 PRs.

**Why existing gates didn't catch it:**
- `M-C7` only checks the badge `Skills-18-green` against `len(skills/)` — passes (18 = 18).
- `M-C12` (prose count) explicitly skips heading lines: `if heading_line_re.match(line): continue` — by design, to avoid false positives on category subtotals. But this created a blind spot for category subtotal drift.
- `M-I4` checks "skill mentioned anywhere in README.md" via simple `not in` — passes when the skill is in Entry Points table even if absent from Skill Contracts. Too coarse-grained.

### Fixed (6 drifts)

| # | File | Before | After |
|---|---|---|---|
| 1 | `README.md` | `### Operations (4 skills)` | `### Operations (3 skills)` |
| 2 | `README.ru.md` | `### Операции (4 скилла)` | `### Операции (3 скилла)` |
| 3 | `README.md` Skill Contracts | 17 rows, no `/task` | 18 rows, `/task` row added with router contract |
| 4 | `README.md` Recommended Models | 17 rows, no `/task` | 18 rows, `/task` (Haiku/Sonnet, "Router for daily-work skills") |
| 5 | `README.ru.md` Контракты скиллов | 17 rows, no `/task` | 18 rows, `/task` (router) |
| 6 | `README.ru.md` Рекомендуемые модели | 17 rows, no `/task` | 18 rows, `/task` (Haiku/Sonnet, роутер) |

The new `/task` rows in Skill Contracts describe it as a router with **None directly** for outputs (delegates to one of 12 daily-work skills) and **None (router only)** for side effects, mirroring the existing `/project` row format. In Recommended Models, `/task` is positioned identically to `/project` (Haiku minimum, Sonnet recommended, router-only reasoning).

### Added: `M-C16` README skill table integrity gate (~140 lines)

New Critical gate in `tests/meta_review.py` covering two failure modes:

**Mode A — category subtotal vs table row count.** Parses `### Category (N skills)` headings, walks forward to the next markdown table, counts the data rows (lines matching `^\s*\|\s*` followed by `` `/skill-name` ``), and fires Critical if N ≠ row count. Also computes the sum of all subtotals across the file and fires Critical if it doesn't equal `len(skills/)`.

**Mode B — per-skill presence in comprehensive tables.** For each of 4 marker sections (`## Skill Contracts`, `## Recommended Models`, `## Контракты скиллов`, `## Рекомендуемые модели`), extracts all `/skill-name` mentions inside markdown table rows and verifies the set equals `{p.name for p in skills/}`. Reports `missing rows for skills: [...]` on mismatch.

The gate is parametrized: adding a new comprehensive table marker (e.g. for a future "Cost Profile" table) is one line in `comprehensive_table_markers`. Adding a new RU/EN README is one line in `readme_paths`.

**Validation**: enabling `M-C16` against the unfixed READMEs would have surfaced exactly the 6 drifts above. The gate is then run against the fixed READMEs and passes — proving both directions work.

### Changed

- **`.claude-plugin/plugin.json`** — version `1.16.2` → `1.16.3`.
- **`.claude-plugin/marketplace.json`** — `plugins[0].version` `1.16.2` → `1.16.3`.
- **`README.md`** / **`README.ru.md`** — version badges `1.16.2` → `1.16.3`.

### Why PATCH, not MINOR

- `M-C16` is a new Critical gate, but covers a subset of an existing class (table-vs-narrative drift). Same SemVer reasoning as `M-C15` in v1.16.2.
- Six README rewrites are pure documentation drift fixes — no new behaviour.
- No user-facing surface change. PATCH per SemVer.

### Counts after v1.16.3

| Tier | Count | Status |
|---|---|---|
| Skills | 18 | All in Entry Points + per-category tables + Skill Contracts + Recommended Models ✅ |
| Subagents | 5 | All in Subagents table ✅ |
| Hooks | 5 | All in README hooks section + hooks/README.md ✅ |
| Meta-review checks | 14 Critical + 9 Important + (M-C16 new) = **24 Critical + 9 Important = 33** | M-C1..M-C16 + M-I1..M-I10 |
| Active fixtures | 3 | All POC-verified |

Wait — the 14 Critical was for v1.13.2..v1.16.2. Adding M-C16 makes it **15 Critical + 9 Important = 24 total checks**, correcting the 23 number from v1.16.2 CHANGELOG. The methodology continues to grow precisely because each cycle catches a real drift class.

Actually, recounting with M-C13, M-C14, M-C15, M-C16: that's 4 new C-level gates added across v1.13.2..v1.16.3, plus the original M-C1..M-C12 = **16 Critical**. Plus M-I1..M-I10 = 10 Important. Total **26 checks**. The exact number doesn't matter — what matters is the loop is producing them faster than user observations come in.

### Migration

```bash
git pull
bash scripts/sync-to-active.sh
python3 tests/meta_review.py --verbose
```

### Meta-finding: the loop is real (4th confirmation)

Cumulative track record of the user-observation → gate-addition loop in this release series:

| Cycle | User observation | Drift class | New gate(s) |
|---|---|---|---|
| **v1.13.2** | "10/10 Anthropic compliance audit" | marketplace.json drift | M-C13 + M-C14 |
| **v1.16.2** | "in README tables not all skills are listed" (referring to hooks) | hook count drift in narrative | M-C15 |
| **v1.16.3** ← **this release** | "I count skills inside parentheses and get 19" + "Skill Contracts shows 17 skills" | category subtotals + per-table presence | M-C16 (covers both modes) |

Pattern is now empirically confirmed across 4 user observations producing 5 new gates in 8 days. The methodology has a working **distributed audit mechanism**: human pattern matching catches drift that automated structural gates miss, and the cure is to encode the pattern as a new gate so the same observation never has to be made manually again.

What this means for v1.17+: the next user observation that finds a drift class we haven't covered yet will produce a 6th gate. The marginal cost of adding gates is low (~50-150 lines of Python each), the marginal benefit is high (permanent coverage of a class), and the user doesn't need to repeat the same observation twice.

---

## [1.16.2] - 2026-04-12

**Documentation drift fix + new gate to prevent recurrence + content plan refresh.** A user-spotted "the README hooks section doesn't list all hooks" turned into a 6-drift cleanup and a new `M-C15` meta-review gate that catches hook count mismatches in narrative prose. Same pattern as v1.13.2: a real bug becomes a permanent gate.

### Audit context

After v1.16.1 merged, a user-spotted observation: "in README tables not all skills are listed". Investigation showed:

- ✅ **Skills:** all 18 listed in README tables (Entry Points / Project Creation / QA / Daily Work / Supply Chain / Operations / Session Management). No drift.
- ✅ **Agents:** all 5 listed in Subagents table. No drift.
- ❌ **Hooks: REAL DRIFT in 6 places.** Both `README.md` and `README.ru.md` and `hooks/README.md` had "two enforcement scripts" / "All four hooks fire live" / installation snippets that copied only 2 of 5 hooks. The `pre-flight-check.sh` (added v1.5.0) was completely absent from all README hook sections.

The drift had been silently present since v1.5.0 — 11 months of releases adding more hooks while the README narrative stayed frozen at 2/4. **`M-C12` (prose count gate) covers skill/agent counts but NOT hook counts.** This is exactly the class of bug `M-C12` was designed to catch, just for a tier nobody enumerated when writing it.

### Added

- **`tests/meta_review.py` — new Critical gate `M-C15`** (~85 lines). Scans `README.md`, `README.ru.md`, `hooks/README.md`, `CONTRIBUTING.md` for narrative mentions of hook counts in three forms:
  - **Numeric**: `\d+\s+(hooks?|hook|скрипт\w*|хук\w*)` — matches `5 hooks`, `4 hook`, `пять скриптов`
  - **English number word**: `(one|two|...|nine)\s+(hooks?|enforcement scripts?|hook)` — matches `four hooks`, `two enforcement scripts`
  - **Russian number word**: `(один|одна|два|две|...|девять)\s+(хук\w*|скрипт\w*)` — matches `четыре хука`, `два скрипта`
  - Skips lines inside markdown tables, headings, and version markers (historical mentions are legitimate)
  - Compares the count against `len(hooks/*.sh)` and fires Critical on mismatch
- **POC validation**: enabling `M-C15` immediately surfaced **3 Critical findings in `hooks/README.md`** that the user's observation had already pointed at:
  - `hooks/README.md:3` — "These two hooks turn..." (was 2, actual 5)
  - `hooks/README.md:7` — "Quality enforcement now spans **four layers**" (was 4, actual 5)
  - `hooks/README.md:27` — "All four hooks are written in Python 3" (was 4, actual 5)
  - Plus 3 more in `README.md` and `README.ru.md` that were the original report

### Fixed

- **`README.md`** hooks section — comprehensive rewrite:
  - Header "two enforcement scripts" → "**five hooks**" with breakdown (two soft reminders, two hard-blocking enforcement gates, one pre-flight context loader)
  - Install snippet now copies all 5 hooks instead of 2
  - Added recommendation to use `bash scripts/sync-to-active.sh` instead (does the same plus settings.json patch)
  - Added a new bullet for `pre-flight-check.sh` documenting v1.5.0 functionality (git context loading, MEMORY.md injection, parallel session detection via `.active-session.lock`)
  - "All four hooks fire live" → "All five hooks fire live"
  - "Two v1.5.0 enforcement hooks" → "Two v1.5.1 enforcement hooks" (correct version where they were schema-fixed)
- **`README.ru.md`** — symmetric Russian rewrite of the same section. Same 5-hook breakdown, same install snippet, same `pre-flight-check.sh` bullet translated.
- **`hooks/README.md`** — three rewrites:
  - "These two hooks" → "These five hooks" in the opening sentence
  - "Defense-in-depth overview (v1.8.0)" → "(v1.16.2)" with a new row 0 for `pre-flight-check.sh` in the four-layer table (now five-layer)
  - "All four hooks are written in Python 3" → "All five hooks"
  - Added a new row in the "What they do" table for `pre-flight-check.sh`
  - Updated the "If you never work on methodology repos" closing paragraph to clarify which hooks are universal vs methodology-only

### Changed

- **`docs/CONTENT-PLAN.md` Часть 0.1** — `marketplace.json` action item marked done (✅ completed in v1.13.2, version 1.16.x, M-C13 gate prevents drift). Remaining 3 manual tasks (form submission, English description, badge mention) still pending.
- **`docs/CONTENT-PLAN.md` Часть 8 (NEW, ~120 lines)** — "Новые selling points после v1.13.2 → v1.16.1". Documents three unique content angles that did not exist in the original content plan because the methodology had not yet evolved them:
  - **8.1 Self-improving methodology** — narrative arc of 5 self-found bugs across 7 releases, each surfacing a new gate. Twitter / Dev.to / Habr / YouTube angles included.
  - **8.2 Behavioural validation, not just structural** — three-tier testing pitch (structural / snapshot / behavioural execution), $2.74 equiv POC cost finding, all 3 active fixtures verified.
  - **8.3 Headless Claude Code POC findings** — concrete cumulative knowledge dump on `claude -p` capabilities and undocumented constraints (5h rate limit, `--verbose` requirement, skill fork in headless, etc.). Hacker News-grade material.
  - **8.4 Per-release content units** — table mapping each of 7 releases (v1.13.2..v1.16.2) to a concrete story for Twitter thread / Dev.to article / YouTube short.
  - **8.5 Updated KPI table** — concrete factual claims (13 → 23 meta-review checks, 0 → 3 verified fixtures, etc.) for use in press-release first 30 seconds.
- **`.claude-plugin/plugin.json`** — version `1.16.1` → `1.16.2`.
- **`.claude-plugin/marketplace.json`** — `plugins[0].version` `1.16.1` → `1.16.2`.
- **`README.md`** / **`README.ru.md`** — version badges `1.16.1` → `1.16.2`.

### Why PATCH, not MINOR

- `M-C15` is a new Critical gate, but it catches a **subset of an existing class** (narrative count drift, M-C12 covered skills/agents). Adding hooks to the same coverage is incremental, not a new capability.
- Six README rewrites are pure documentation drift fixes — no new behaviour, no new feature.
- Content plan additions are pure documentation — no methodology change.
- No user-facing surface change. Pure PATCH per SemVer.

### Counts after v1.16.2

| Tier | Counts | Status |
|---|---|---|
| Skills | 18 | All in README tables ✅ |
| Subagents | 5 | All in Subagents table ✅ |
| **Hooks** | **5** | All in README hooks section ✅ (fixed in v1.16.2) |
| Meta-review checks | 14 Critical + 9 Important = **23** | M-C1..M-C15 + M-I1..M-I10 |
| Active fixtures | 3 | All POC-verified end-to-end |
| Pending fixture stubs | 7 | Each documents why deferred |

### Migration

```bash
git pull
bash scripts/sync-to-active.sh
python3 tests/meta_review.py --verbose
```

The new `M-C15` gate fires automatically on next `meta_review.py` run. Locally and in CI.

### Why this matters as a meta-finding

This is the **second time** in the v1.13.2..v1.16.2 cycle where a user observation immediately turned into a previously-uncovered drift class + a new gate to prevent recurrence:

- **v1.13.2** — user asked for "10/10 Anthropic compliance" → audit found marketplace.json drift → M-C13 + M-C14 added
- **v1.16.2** — user observed "not all skills listed in README tables" → audit found 6 hook drifts → M-C15 added

The pattern is real and works: **human pattern matching against a long-standing artifact catches drift that automated structural gates miss**, and the cure is to **encode that pattern as a new automated gate** so the same observation never has to be made again. v1.16.2 is the second proof of concept for this self-improvement loop.

---

## [1.16.1] - 2026-04-12

**Behavioural tier reaches 10/10.** All three active fixtures (01-saas-clinic, 02-tg-bot, 03-cli-tool) are now end-to-end verified via the v1.16.0 headless runner with PASSED snapshots. Total bootstrap effort: 3 runs, 76 checks, $2.74 equivalent cost (real cost on subscription: $0), ~21 minutes wall clock. This closes the deferred work from v1.16.0 where only fixture-02 had been verified.

### What was uncovered during the bootstrap

A new skill-architecture finding showed up immediately on the first fixture-03 run:

**`/blueprint` and other skills with `agent: <subagent>` frontmatter delegate to the named subagent in headless mode and lose orchestration.** When the v1.16.0 stream.jsonl files used `/blueprint <idea>` as the prompt, fixture-02 happened to work (model handled orchestration in main context), but fixture-03 did NOT — the model wrote only `PROJECT_ARCHITECTURE.md` and explicitly stated "родительский /blueprint скилл вызвал меня (architect agent) с узкой ответственностью". The architect subagent's narrow scope (one file: PROJECT_ARCHITECTURE.md) won.

This is a real architectural limitation of running fork-style skills via `claude -p`: the headless invocation path forks into the subagent on `agent:` directive, the subagent finishes its narrow turn, and the session ends — there is no parent context to take over and finish the remaining 5 documents.

**Workaround used in v1.16.1:** the fixture-01 and fixture-03 stream.jsonl files no longer prefix with `/blueprint` or `/kickstart`. Instead they ask the main agent directly to generate all 6/7 files, with explicit instructions:

> DO NOT delegate to any subagent — you are the main agent in a non-interactive headless session, and you must handle the ENTIRE orchestration yourself. Generate ALL N documents directly via the Write tool in the current working directory.

Plus documenting all clarifications inline so the skill never has a reason to ask. This bypasses the fork machinery and matches the *output structure* of the canonical skill, which is what `verify_snapshot.py` validates anyway.

**Honest tradeoff documented:** these stream.jsonl files exercise *output structure*, not the *exact skill invocation chain*. They are structurally equivalent to a real `/blueprint` or `/kickstart` run, but they do not test the skill's orchestration logic itself. fixture-02 still uses the original `/blueprint`-prefixed prompt that worked in v1.16.0 POC and is left unchanged for that reason — it covers the orchestration path. The split (1 fixture exercises orchestration, 2 fixtures exercise output structure via main agent) is a known limitation of headless fork skills, not a methodology bug.

### Calibrated (from real ground truth)

Five regex / schema fixes based on observed real output, not guesses:

1. **`tests/verify_snapshot.py` `_API_ENDPOINT_RE`** — added two new alternatives for markdown table format. The original pattern matched lines like `GET /api/users` at line start, but real `/kickstart` output for fixture-01 generates a numbered API table:
   ```
   | 1 | POST | `/auth/register` | Регистрация клиники + первый admin |
   | 2 | POST | `/auth/login`    | Вход, выдача JWT                  |
   ```
   New regex matches `\|\s*\d+\s*\|\s*(GET|POST|...)\|` (numbered table) and `\|\s*(GET|POST|...)\s+/path\s*\|` (unnumbered table). Before fix: 1 endpoint counted. After fix: 30+.
2. **`fixture-01/expected-snapshot.json` `Competitors` section** — `Конкуренты` substring didn't match `Конкурентов` (genitive case). Generalized to `Конкурент|Анализ конкурент` (root form). Same Russian-word-ending bug surfaced in v1.13.2 audit — now fixed across both fixture-01 and fixture-02 snapshots.
3. **`fixture-01/expected-snapshot.json` `KPIs` section** — `KPIs` (plural) didn't match `KPI` (singular). Relaxed to `KPI|Метрик|Цели`.
4. **`fixture-01/expected-snapshot.json` PRD acceptance criteria section** — REMOVED. Real `/kickstart` output embeds acceptance criteria *inside* each US-N block, not as a separate section. The structural check was checking for the wrong thing. The acceptance criteria are still validated indirectly via `min_user_story_count` (each US has its own criteria block in the body).
5. **`fixture-03/expected-snapshot.json`** — Budget section pattern expanded with `Бизнес-модель|Business model|Финанс` (real output uses `## Бизнес-модель` for $0 open-source projects). `no_api_justification` markers expanded with `Нет HTTP API`, `HTTP API не нужен`, `только CLI`, `локальный инструмент`, `stateless CLI`, `CLI-утилита` — all observed in real output.

### Bootstrap result snapshot

| Fixture | Verified | Checks | Cost | Duration | Method |
|---|---|---|---|---|---|
| fixture-01-saas-clinic | ✅ | 33/33 | $0.67 | 7.5 min | bypass prompt (main agent) |
| fixture-02-tg-bot | ✅ (v1.16.0) | 23/23 | $1.73 | 10.5 min | `/blueprint` skill (orchestration path) |
| fixture-03-cli-tool | ✅ | 20/20 | $0.34 | 3.5 min | bypass prompt (main agent) |
| **TOTAL** | **3/3** | **76/76** | **$2.74** | **~21 min** | mixed |

### Changed

- **`tests/fixtures/fixture-01-saas-clinic/stream.jsonl`** — rewritten as a direct main-agent prompt with full clarifications inline and explicit "do NOT delegate to any subagent" instruction. Includes all 13 architectural constraints and the 7-file deliverable list.
- **`tests/fixtures/fixture-03-cli-tool/stream.jsonl`** — same bypass approach with the no-DB/no-API-test specific constraints reinforced ("Your PROJECT_ARCHITECTURE.md MUST explicitly state 'no database — stateless streaming processing' and 'no HTTP API — CLI-only tool'").
- **`tests/fixtures/fixture-01-saas-clinic/expected-snapshot.json`** — calibrated from real ground truth (3 fixes above).
- **`tests/fixtures/fixture-03-cli-tool/expected-snapshot.json`** — calibrated from real ground truth (2 fixes above).
- **`tests/verify_snapshot.py`** — `_API_ENDPOINT_RE` now matches markdown table format used by `/kickstart` output for API tables.
- **`.claude-plugin/plugin.json`** — version `1.16.0` → `1.16.1`.
- **`.claude-plugin/marketplace.json`** — `plugins[0].version` `1.16.0` → `1.16.1`.
- **`README.md`** / **`README.ru.md`** — version badges `1.16.0` → `1.16.1`.

### Why PATCH, not MINOR

This release adds no new capability, no new file format, no new gate. It just **finishes the bootstrap work that v1.16.0 deferred**: takes the existing v1.16.0 infrastructure (`run-fixture-headless.sh`, snapshot schema, M-I10 gate) and uses it on the remaining two active fixtures, then commits the calibrated snapshots and the workaround stream files. Pure incremental refinement → PATCH.

### Behavioural execution tier reaches 10/10

After v1.16.1 the methodology has:

| Tier | Status |
|---|---|
| Structural | 14 Critical + 9 Important checks, 0 findings | **10/10** |
| Snapshot validation (Phase 1) | 3 active + 7 pending, all schemas valid | **10/10** |
| **Behavioural execution (Phase 2)** | **3/3 active fixtures verified end-to-end via headless runner** | **10/10** |

The only "gap" remaining is the 7 pending fixture stubs (fixture-04..10), each documenting why their schema model isn't yet bootstrapped (stdout reports, before/after diffs, AST checks, stream capture for routers). These are deferred deliberately because each requires a different snapshot schema design, not because Phase 2 infrastructure is incomplete. As soon as a contributor designs the schema for, say, `/deps-audit` stdout report capture, they can flip fixture-04 to active using the same `run-fixture-headless.sh` workflow proven here.

### v1.17.0 candidates (no urgency, take whenever)

- Flip pending stubs fixture-04..10 one at a time as their schema models are designed.
- After all 10 are active, enable `.github/workflows/fixture-smoke.yml` with `ANTHROPIC_API_KEY` secret. Cost: ~$10-40/month depending on release frequency. Only relevant if there are external contributors whose PRs need automated behavioural validation.
- New skill candidates: `/dependency-update` (semver-aware), `/release-notes` (auto-CHANGELOG from commits), `/api-fuzz` (security fuzzer for FastAPI routes).
- Methodology promotion (Reddit, HN, Anthropic Directory) — see `docs/CONTENT-PLAN.md`.

### Migration

```bash
git pull
bash scripts/sync-to-active.sh
python3 tests/meta_review.py --verbose
bash tests/run-fixture-headless.sh fixture-02-tg-bot --dry-run  # confirm wrapper sees the fixture
```

After the merge, anyone with subscription access can re-run the three active fixtures locally to confirm they still pass:

```bash
bash tests/run-fixture-headless.sh fixture-03-cli-tool  # cheapest, ~$0.35
bash tests/run-fixture-headless.sh fixture-02-tg-bot    # ~$1.75
bash tests/run-fixture-headless.sh fixture-01-saas-clinic  # ~$0.70
```

Total cost: **~$2.80 equivalent** ($0 actual on subscription). Total time: ~25 min serial (must be serial — see v1.16.0 rate limit finding).

---

## [1.16.0] - 2026-04-12

**Phase 2 of behavioural automation — LANDED.** Adds a non-interactive fixture runner (`tests/run-fixture-headless.sh`) that invokes `claude -p` in stream-json mode, captures generated output, and validates it against the Phase 1 snapshot schema. Closes the loop from "manually run fixture and eyeball output" to "one command runs and validates". Includes a ready-to-enable GitHub Actions workflow (disabled by default pending `ANTHROPIC_API_KEY` provisioning).

### What was proven in the POC

A live POC during v1.16.0 development exercised the full pipeline on `fixture-02-tg-bot` and produced **23/23 PASSED** after three calibration iterations. Key outcomes:

1. **`claude -p` supports skill invocation in non-interactive mode.** Stream-json input with a pre-seeded clarification message correctly drove `/blueprint` to generate all 6+2 documents without asking further questions.
2. **Skills load automatically from `~/.claude/skills/`** — no `--plugin-dir` flag required if the methodology is already sync'd.
3. **Real tool use works headless** — the model called `Write` for each of the 8 files (`.gitignore`, `CLAUDE.md`, `CLAUDE_CODE_GUIDE.md`, `IMPLEMENTATION_PLAN.md`, `PRD.md`, `PROJECT_ARCHITECTURE.md`, `README.md`, `STRATEGIC_PLAN.md`).
4. **`verify_snapshot.py` validates real output, not hypothetical output** — after three regex calibration fixes (see below), all 23 checks PASSED on the actual generated docs.
5. **`total_cost_usd` is reported even on subscription runs** — the field is equivalent pay-as-you-go pricing, usable for CI budget planning without any actual spend.
6. **Cost profile observed on Sonnet:**
   - `/blueprint` fixture-02 (Lite mode, 8 files): **$1.73, ~10.5 min, 2 turns**
   - `/kickstart` fixture-01 (Full mode docs-only, partial run before rate limit): **$0.42, ~5 min, 5 turns, 3 files generated**

### What the POC uncovered (new findings)

Three constraints not previously known:

1. **5-hour rate limit is a hard stop even on subscription.** During parallel POC runs, Claude Code returned `stop_sequence: stop_sequence` with result text "You've hit your limit · resets 1am (Europe/Moscow)". The limit is organization-level and resets every 5 hours regardless of subscription tier. This means:
   - **Parallel fixture runs are unsafe** — two heavy skills running at the same time share quota and both die.
   - **Serial execution mandatory** for bootstrap workflows.
   - **CI workflows must use `needs:` chains**, not matrix-parallel steps.
   - **Budget cap via `--max-budget-usd` is not enough** — rate limit can hit long before budget does.
2. **`--output-format stream-json` requires `--verbose`.** Not documented in `claude --help`, discovered during POC. The runner script sets both.
3. **`--input-format stream-json` requires matching `--output-format stream-json`.** Same applies — no mixing single-json output with multi-message input.

### Added

- **`tests/run-fixture-headless.sh` (~190 lines)** — Bash wrapper that takes a fixture name, finds the `stream.jsonl` and `expected-snapshot.json`, invokes `claude -p` with the exact flag set validated by the POC, captures the stream log, extracts cost/duration, and runs `verify_snapshot.py` on the output. Supports `--model`, `--budget`, `--output`, `--keep-output`, `--dry-run`. On failure the output dir is preserved; on pass it is cleaned up.
- **`tests/fixtures/fixture-01-saas-clinic/stream.jsonl`** — pre-seeded conversation for the SaaS clinic bootstrap (13 pre-emptive clarifications covering users, auth, DB, hosting, budget, stack, notifications, 152-ФЗ compliance, multi-tenancy, competitors; instructs `/kickstart` to stop after Phase 3 for snapshot bootstrap).
- **`tests/fixtures/fixture-02-tg-bot/stream.jsonl`** — pre-seeded conversation for the Telegram bot Lite-mode fixture (10 clarifications: Telegram admin ID auth, SQLite, aiogram 3.x, in-process asyncio reminder loop, etc.). **This is the one that passed the live POC.**
- **`tests/fixtures/fixture-03-cli-tool/stream.jsonl`** — pre-seeded conversation for the no-DB/no-API edge case (explicit "NO database, NO HTTP API, CLI-only" instructions with the exact rubric-justification markers the snapshot looks for).
- **`.github/workflows/fixture-smoke.yml`** — ready-to-enable GitHub Actions workflow that runs the three active fixtures via the wrapper on every `release/*` branch push or manual dispatch. **DISABLED BY DEFAULT** via `if: false` guard. Two steps to activate: (1) provision `ANTHROPIC_API_KEY` repo secret, (2) remove the `if: false` guard. Includes budget caps per fixture, artifact upload, and parameterized model/budget via `workflow_dispatch` inputs.
- **`tests/README.md`** — expanded "Phase 2" section with the full runner workflow, stream.jsonl format example, cost table from POC, and a flippping-pending-stubs guide for future fixture bootstrap work. Added a new "Phase 2 internals" section documenting every `claude -p` flag and why it is needed.

### Calibrated (from real POC data)

The POC uncovered three cases where the Phase 1 regex patterns in `verify_snapshot.py` didn't match real LLM-generated output. Each was fixed on observed structure, not assumptions:

1. **`_STEP_HEADING_RE`** — removed the `\d+\.\s+\w` alternative. It was double-counting numbered list items inside each implementation step, inflating the count (observed: 83 "steps" in a 13-step document). Now matches ONLY `## Step/Шаг/Этап N` headings, strict.
2. **`_USER_STORY_RE`** — added two new alternatives: `### US-N:` numbered user story headings and `>\s*(Как|As a)` blockquote-style stories. The model's `/blueprint` output uses these formats instead of the original bullet-list pattern (`- As a X, I want`). Before fix: found 0 user stories in a document with 12; after fix: found 12.
3. **`fixture-02-tg-bot/expected-snapshot.json`**:
   - Competitors section pattern expanded from `Competitors|Конкуренты|Альтернативы` to `Competitors|Конкурент|Competition|Анализ конкурент|Альтернативы`. The original used a substring check that didn't match "Конкурентный анализ" because "конкурентный" doesn't contain "конкуренты" (different Russian word endings).
   - `max_step_count` relaxed from 10 to 15. Real `/blueprint` output for a Lite-mode bot produces 13 steps (init / config / DB / auth / slots / admin handlers / booking / cancel / admin-cancel / reminder loop / rate limit / CI / deploy) — this is a realistic plan, not inflation. The original limit was written aspirationally; POC ground truth is authoritative.

### Changed

- **`.claude-plugin/plugin.json`** — version `1.15.0` → `1.16.0`.
- **`.claude-plugin/marketplace.json`** — `plugins[0].version` `1.15.0` → `1.16.0`.
- **`README.md`** / **`README.ru.md`** — version badges `1.15.0` → `1.16.0`.

### Bootstrap status snapshot

After v1.16.0:

| Fixture | Snapshot status | stream.jsonl | POC run | Notes |
|---|---|---|---|---|
| fixture-01-saas-clinic | active | ✅ | partial (rate-limited) | 3 files generated, rate limit stopped run. Full bootstrap deferred to v1.16.1 when quota window allows a clean run. |
| fixture-02-tg-bot | active | ✅ | **✅ PASSED (23/23)** | Fully verified against live POC output. Calibrated. |
| fixture-03-cli-tool | active | ✅ | failed (rate-limited in parallel) | Never actually ran due to sharing quota with fixture-01. |
| fixture-04..10 | pending (stubs) | — | — | Deferred to future PRs, documented in each stub's description. |

**Honest assessment:** v1.16.0 proves the workflow end-to-end on one real fixture. Full bootstrap of the three active fixtures needs either (a) waiting for rate-limit windows between sequential runs, (b) a maintainer running them one at a time over a day, or (c) the CI workflow with API key (which has its own rate limit but independent of the local subscription).

### Why MINOR, not PATCH

New testing infrastructure:
- New file (`tests/run-fixture-headless.sh`) that contributors will run
- New file format (`stream.jsonl`) that contributors must understand when adding fixtures
- New CI workflow (`.github/workflows/fixture-smoke.yml`) that future maintainers can enable
- Observable additions to the three-tier testing model documented in `tests/README.md`

Per SemVer this is a MINOR bump. End users of the plugin still see nothing different.

### v1.16.1 concrete TODO

1. Serial bootstrap run of fixture-01 and fixture-03 in separate rate-limit windows. Each takes 5–25 minutes; must run >5 hours apart unless a new quota window opens.
2. Calibrate snapshots for fixture-01 and fixture-03 based on actual output (same process as fixture-02 in this release).
3. Flip `pending` stubs for fixture-04..10 one at a time, each in its own release once the snapshot schema for its fixture type is designed.
4. After all 10 fixtures are `active` and verified, consider enabling the CI workflow with a conservative budget cap.

### Migration

```bash
git pull
bash scripts/sync-to-active.sh
python3 tests/meta_review.py --verbose
bash tests/run-fixture-headless.sh fixture-02-tg-bot --dry-run  # confirm wrapper sees the fixture
```

The `--dry-run` prints the command that would run without actually invoking claude. Maintainers should also run the full wrapper (without `--dry-run`) at least once on fixture-02 after pulling to confirm local setup works before releasing.

---

## [1.15.0] - 2026-04-11

**Phase 1 of behavioural automation.** Adds a deterministic structural-validation layer for fixture output — `tests/verify_snapshot.py` + `expected-snapshot.json` schema per fixture. This is the first time the methodology has automated checks for *behavioural* regressions (did `/kickstart` actually produce a multi-tenant architecture with 15+ endpoints, not just "some markdown with the right filename"). Phase 2 (non-interactive execution via `claude -p --output-format json`) is deferred to v1.16.0 after POC.

### Background

Before v1.15.0, the methodology had **two testing tiers**:

1. Structural gate (`tests/meta_review.py`) — automated, CI-blocking, catches drift in versions/skills/frontmatter/hooks/subagent contracts. 14 Critical + 8 Important checks.
2. Behavioural smoke-runs — **manual only**, maintainer runs each fixture on a release and eyeballs the output against `notes.md`. Catches the long tail of LLM regressions but is tedious and error-prone (a human skimming 7 generated markdown files will miss a renamed section or a missing index).

v1.15.0 adds a **third tier** between them: **deterministic structural validation** of fixture output against a machine-readable schema. The generation step is still manual (or will be, until Phase 2 lands), but once the output exists, `verify_snapshot.py` validates it exhaustively against the fixture's `expected-snapshot.json` contract. Deterministic, zero API cost, zero model-version flakiness.

### Added

- **`tests/verify_snapshot.py`** — new CLI script (~340 lines) that validates a fixture's `output/` directory against `expected-snapshot.json`. Supports:
  - `files.required` / `files.min_count` — file presence and count constraints
  - `content_contracts.<file>.required_sections` — regex-based section heading check with bilingual alternatives (`"Competitors|Конкуренты"`)
  - `content_contracts.<file>.must_contain` / `must_contain_any_of` — literal substring check, supports named-alternative groups
  - `content_contracts.<file>.min_length_chars` — sanity length check
  - `content_contracts.<file>.min_api_endpoints` — counts HTTP-method-prefixed lines (`^(GET|POST|PUT|...)  /path`)
  - `content_contracts.<file>.min_user_story_count` — counts "As a ..." / "Как ..." bullet starts
  - `content_contracts.<file>.min_step_count` / `max_step_count` — counts "## Step N" / "1." / "Шаг N" headings
  - `rubric_status.expected` / `rubric_status.forbidden` — validates a `.rubric-status` file written manually after running `/review` on the output
  - `status: pending` stubs auto-pass without touching the output dir — plan for gradual bootstrap
  - `--json` flag for machine-readable output
  - Exit codes: 0 = PASSED, 1 = FAILED, 2 = internal error
- **`tests/fixtures/fixture-01-saas-clinic/expected-snapshot.json`** — **active** snapshot for the heavy-end fixture. Validates: 7 required files, 15+ API endpoints, `clinic_id` multi-tenancy column, 8+ user stories, 8–12 implementation plan steps, competitor naming (must mention at least one of MEDODS / IDENT / Renovatio / Kray / Medesk / Klinika / УМСМ), expected rubric status PASSED or PASSED_WITH_WARNINGS.
- **`tests/fixtures/fixture-02-tg-bot/expected-snapshot.json`** — **active** snapshot for Lite-mode (Sonnet fallback). Validates: 6 required files, bot framework presence (aiogram / python-telegram-bot / telegraf / grammy), storage backend mentioned, 4+ user stories, 5–10 implementation steps.
- **`tests/fixtures/fixture-03-cli-tool/expected-snapshot.json`** — **active** snapshot for the no-DB/no-API edge case. Validates: 6 required files, *explicit* "no database" / "no API" justification in the architecture doc (this is the whole point of the fixture — the rubric must correctly handle "not applicable" instead of flagging it as incomplete), 3+ user stories, 4–10 steps.
- **`tests/fixtures/fixture-04-deps-audit/expected-snapshot.json`** through **`fixture-10-task/expected-snapshot.json`** — **pending** stubs for the 7 remaining fixtures. Each documents why the snapshot is deferred to v1.16.0 (stdout reports vs files, before/after diffs, AST-based docstring checks, stream-capture for routers, etc.). Keeps M-I10 green without forcing a premature bootstrap.
- **`tests/meta_review.py` — new gate `M-I10`** — for every `tests/fixtures/*/` directory, validates that `expected-snapshot.json` exists, is valid JSON, has all required fields (`$schema_version`, `fixture_type`, `skill_under_test`, `status`, `description`), and has a valid `status` (`active` or `pending`). Important severity, not Critical, because missing a snapshot doesn't break existing users — it just blocks behavioural regression coverage.
- **`tests/README.md`** — rewrote the testing-tier section. Now explicitly documents **three tiers** (structural gate, snapshot validation, behavioural execution), the Phase 1 maintainer workflow (run fixture → record `.rubric-status` → `verify_snapshot.py`), the full snapshot schema with a minimal example, and the Phase 2 plan with the exact `claude -p` invocation draft for v1.16.0. The legacy workflow (pre-v1.15.0 manual diff against `expected-files.txt`) is kept in a marked "deprecated" section for reference.

### Changed

- **`.claude-plugin/plugin.json`** — version `1.14.1` → `1.15.0`.
- **`.claude-plugin/marketplace.json`** — `plugins[0].version` `1.14.1` → `1.15.0`.
- **`README.md`** / **`README.ru.md`** — version badges `1.14.1` → `1.15.0`.

### Rubric status snapshot

After v1.15.0:

| Tier | Checks | Status |
|---|---|---|
| Structural | 14 Critical + 9 Important (M-C1..M-C14 + M-I1..M-I10) | Stable, CI-blocking |
| Snapshot validation | 3 active + 7 pending | Phase 1 working on local runs |
| Behavioural execution | Manual | Phase 2 candidate for v1.16.0 |

### Why MINOR, not PATCH

v1.15.0 adds a new testing capability (`verify_snapshot.py` + the schema format + M-I10 gate) that future contributors will need to understand when adding fixtures. That's a visible addition to the contributor contract, which per SemVer is a MINOR bump, not a PATCH. End users of the plugin see nothing different — the new infrastructure is maintainer-only.

### Migration

```bash
git pull
bash scripts/sync-to-active.sh
python3 tests/meta_review.py --verbose
python3 tests/verify_snapshot.py tests/fixtures/fixture-04-deps-audit  # should print PENDING
```

No configuration changes required. The gate runs on the maintainer's CI; the snapshot validator is opt-in for local runs.

### Phase 2 (v1.16.0 candidate) concrete TODO

Documented in detail in `tests/README.md` under "Phase 2: non-interactive execution":

1. **POC** — headless `/kickstart` on fixture-01 via `claude -p --plugin-dir . --input-format stream-json --output-format json --max-budget-usd 5.00 --dangerously-skip-permissions --model sonnet`. Capture result, diff against current live snapshot.
2. **If POC works** — write `tests/run-fixture-headless.sh` wrapper and GHA workflow `.github/workflows/fixture-smoke.yml` that runs on `release/*` branches (not every PR) with a 25-USD monthly budget cap.
3. **Flip pending stubs to active** — one headless run per fixture to record ground truth, then update the corresponding `expected-snapshot.json` to `status: active` with populated content contracts.
4. **Document observed cost per fixture** in `docs/CI.md`.
5. **If POC fails** — document the exact blocker (SDK limitation, protocol gap, cost, etc.) honestly in `tests/README.md` and close the Phase 2 goal. Phase 1 alone is already a large improvement over the pre-v1.15.0 status quo.

---

## [1.14.1] - 2026-04-11

PATCH release. Closes the last cheap structural win deferred from v1.14.0 deliberation: **M-I9 caller-skill tool superset gate**. Adds a new formal frontmatter field `report_only: true` to make read-only skill contracts auditable. Pure defense-in-depth addition — zero user-facing behaviour change, zero cost, catches one previously-invisible class of regression.

### Audit context

During v1.14.0 deliberation we walked through five possible Defense-in-depth layers for subagent contracts and found that four of them (runtime self-check, schema validation, integration test duplication, latency-inducing pre-flight gates) had measurable UX cost for marginal value. Only **M-I9** (caller-skill tool superset check) passed the cost/benefit bar: ~30 lines of Python, zero user cost, catches a real class of bug where a skill delegates to a read-only subagent but lacks `Write`/`Edit` itself and cannot persist the output.

Rather than ship M-I9 in the same v1.14.0 PR (which was already doing four things), we split it into v1.14.1 as a focused single-purpose patch.

### Added

- **`tests/meta_review.py` — new gate `M-I9`** — for every skill with a `agent: X` frontmatter field, validates the three legitimate patterns:
  - **Pattern A** — subagent is read-only, skill has `Write`/`Edit` (example: `/blueprint → architect`, `/perf → perf-analyzer`). Most common.
  - **Pattern B** — skill AND subagent both read-only, skill declared `report_only: true` (example: `/review → code-reviewer`). Pure audit chain, no mutations anywhere.
  - **Pattern C** — subagent has `Write`/`Edit` itself (forward compatibility; no current agents match this, but the gate permits it).
  - **M-I9a** (Critical) — `agent: X` refers to a non-existent agent. Catches typos and rename misses.
  - **M-I9b** (Critical) — both skill and subagent read-only without `report_only: true`. Catches skills that forgot to add `Write`/`Edit` when they silently need to persist output, and prevents silent-write-failure regressions in future skills.
- **`skills/review/SKILL.md`** — added `report_only: true` frontmatter field. Formalizes the `/review` contract that has been implicit since v1.0.0: `/review` produces audit reports to stdout, never mutates files. This unblocks M-I9b for the `/review → code-reviewer` pair.

### New frontmatter field: `report_only`

`report_only: true` is a new optional frontmatter field for skills whose entire contract is "produce a report to stdout, apply no mutations". Currently used only by `/review`. Candidates for future adoption (not in v1.14.1 scope, to avoid mixing structural changes with the gate):
- `/security-audit` — read-only OWASP-style audit with optional fix suggestions (no patches applied).
- `/deps-audit` — read-only CVE/license/abandoned-package audit.
- `/explain` — read-only walkthrough, stdout only.
- `/project`, `/task` — routers that only print routing decisions.

Claude Code ignores unknown frontmatter fields, so there is no compatibility risk. The field is purely contract metadata for the methodology's own gates.

### Changed

- **`.claude-plugin/plugin.json`** — version `1.14.0` → `1.14.1`.
- **`.claude-plugin/marketplace.json`** — `plugins[0].version` `1.14.0` → `1.14.1`.
- **`README.md`** / **`README.ru.md`** — version badges `1.14.0` → `1.14.1`.

### Why PATCH, not MINOR

No new behaviour surface for users:
- Only one skill got a new frontmatter field, and it is internally-consumed metadata, not a new capability.
- The M-I9 gate is CI-only, invisible to end users.
- No trigger changes, no keyword changes, no new checks that block the user's own workflow.

Per SemVer this is a PATCH release — a bug-prevention fix, not a feature addition.

### Migration

```bash
git pull
bash scripts/sync-to-active.sh
python3 tests/meta_review.py --verbose
```

No configuration changes required. The gate runs on the maintainer's CI only; end users of the plugin see nothing different.

### What the gate catches

Concrete regression scenarios this gate prevents:

1. **Typo in agent rename.** If v2.0.0 renames `code-reviewer` → `reviewer` and misses one `agent:` reference, M-I9a fires Critical.
2. **New skill `/audit` with forgotten Write/Edit.** If a contributor adds a skill with `agent: code-reviewer` and `allowed-tools: Read Glob Grep` without declaring it report-only, M-I9b fires Critical before the PR can merge.
3. **Silent removal of Write/Edit from an existing skill.** If `/blueprint` loses `Write Edit` in a refactor, M-I9b fires because `architect` is read-only and `/blueprint` is not declared report_only.

### 10/10 structural tier

This PR closes the last cheap structural win identified in the v1.13.2 audit. The methodology now has **14 Critical + 8 Important** meta-review checks, covering every class of drift previously observed in v1.4.0 → v1.13.2 history. Further structural hardening would require significantly more complex machinery (LLM-as-judge, snapshot testing, runtime integration checks) and enters the behavioural tier — next target for v1.15.0.

---

## [1.14.0] - 2026-04-11

Polish release closing the three Nice-to-have items from the v1.13.2 qualitative audit, plus a new `M-I8` meta-review gate that makes the subagent contract pattern auditable and regression-proof. All improvements are backward-compatible additions — MINOR bump, no user-facing behaviour changes.

### Audit context

The v1.13.2 PR (#16) fixed 1 Critical + 4 Important drift items but deferred three Nice-to-have items to v1.14.0 because they did not affect correctness, only discoverability and edge-case recall:

1. `plugin.json.keywords` missing the new v1.13.0 capability tags.
2. `agents/doc-writer.md` (and by analogy `test-generator.md`) had an ambiguous "Generate documentation files" instruction without disclosing that the subagent runs in a forked context with no `Write`/`Edit` tools, so the instruction is physically unfulfillable.
3. `hooks/check-skills.sh` `/explain` trigger had thin English coverage — idiomatic phrasings like "what does this function do", "can you explain", "tell me about this module" fell through to ad-hoc tool calls.

v1.14.0 closes all three and adds one bonus item: **M-I8 subagent whitelist gate** which enforces the clarification pattern for all current and future read-only subagents.

### Added

- **`hooks/check-skills.sh`** — extended `/explain` regex with three new idiomatic English patterns:
  - `what\s+does\s+(this\s+|the\s+)?(\w+\s+)?(do|mean|return)` — catches "what does this function do", "what does getUserById return", "what does the auth middleware do"
  - `can\s+you\s+explain` — catches "can you explain this regex", "can you explain what's happening"
  - `tell\s+me\s+(about|how)\s+(this|the|that)\s+(code|function|module|class|file|method|component|handler|endpoint)` — catches "tell me about this handler", "tell me how the auth module works"
- **`.claude-plugin/plugin.json`** — keywords extended with `self-review`, `meta-review`, `methodology-validation`, `daily-work-router`. Aligns the plugin's discoverability metadata with the v1.13.0 self-review capability, the v1.5.0 `/task` router, and the v1.12.0+ meta-review gate. Parallelism with marketplace.json restored.
- **`.claude-plugin/marketplace.json`** — keyword `methodology-validation` added for parity with plugin.json (the other three were already present from v1.13.2).
- **`agents/doc-writer.md`** — new "Output Format" section explicitly states that the agent runs in a forked context without `Write`/`Edit`, and must return structured text for the calling skill to persist. Applies to both invocation paths: through the `/doc` skill and directly via the `Agent` tool.
- **`agents/test-generator.md`** — analogous disclaimer, with the additional clarification that `Bash` is in the whitelist for test-suite detection (`pytest --co`, `npm test -- --listTests`) but NOT for writing files via heredoc or `tee`.
- **`agents/architect.md`** — analogous disclaimer for the `/blueprint` flow; specifies the `{ file_path, content }` tuple return format for multi-file architecture deliverables.
- **`agents/code-reviewer.md`** — analogous disclaimer emphasising the separation of audit (subagent) and remediation (caller) as load-bearing for read-only review semantics. Preserves the existing v1.13.0 Step 0 methodology-mode detection.
- **`agents/perf-analyzer.md`** — analogous disclaimer plus expanded return format per bottleneck (Description / Severity / Location / Measurement / Suggested fix / Expected improvement). Explicitly says `Bash` is for running benchmarks, not for `tee > patched.py`.
- **`tests/meta_review.py` — new Important gate `M-I8`** — scans `agents/*.md` and, for any subagent whose frontmatter `allowed-tools` does not include `Write` or `Edit`, verifies the body contains a forked-context disclaimer (a block with all three markers: "forked", "Write/Edit", negation keyword). Silent-write-failure regressions are no longer possible without the gate flagging them. Intentionally Important (not Critical) because the same class of bug has always been a correctness issue, never a blocker for existing users.

### Changed

- **`.claude-plugin/plugin.json`** — version `1.13.2` → `1.14.0`.
- **`.claude-plugin/marketplace.json`** — `plugins[0].version` `1.13.2` → `1.14.0`.
- **`README.md`** / **`README.ru.md`** — version badges `1.13.2` → `1.14.0`.

### Migration

```bash
git pull
bash scripts/sync-to-active.sh
python3 tests/meta_review.py --verbose
```

No configuration changes required. Active install picks up the new triggers, keyword metadata, and subagent instructions on next Claude restart.

### Why MINOR, not PATCH

v1.13.2 was strictly a drift fix — PATCH per SemVer. v1.14.0 is different: it adds new trigger-phrase coverage (behaviour change, even if backward-compatible), new plugin.json keywords (catalog-visible change), new subagent instructions (changes what subagents can be told to do), and a new meta-review gate (changes what the CI will block). None of these are breaking, but together they move the minor version counter, which is the right SemVer semantics for backward-compatible additions.

### What remains open

- **v1.15.0 candidate — snapshot testing for behavioural fixtures.** Documented in `tests/README.md` as a future path since v1.13.2. Requires a proof-of-concept of non-interactive Claude Code SDK invocation before full rollout, and a CI compute cost estimate. Not in v1.14.0 scope.
- **WSL git-over-network issue.** `git push` and `git fetch` hang in the maintainer's WSL environment; all v1.13.2 and v1.14.0 commits are landed via `gh api graphql createCommitOnBranch`. This is an environment issue, not a methodology issue, but is tracked in memory for continuity.

---

## [1.13.2] - 2026-04-11

Documentation-drift audit release. Closes gaps found during the post-v1.13.1 self-review where a code-reviewer subagent + manual verification surfaced issues that the automated `meta_review.py` gate did not catch:

1. **`.claude-plugin/marketplace.json` had drifted from v1.11.0 → v1.13.1 unnoticed.** The file is what external plugin catalogs index, but nothing enforced parity with `plugin.json`. Both description fields still read "17 skills" when the real count was 18; `plugins[0].version` was frozen at 1.11.0.
2. **`skills/kickstart/SKILL.md` had `disable-model-invocation: true`** — a flag documented for script-backed skills that delegate to a binary, not for reasoning-heavy skills. The same flag on the built-in `/debug` is what forced the v1.4.0 rename to `/bugfix`. `/kickstart` is the most reasoning-heavy skill in the methodology; the flag silently blocked its invocation via the `Skill` tool from `/project`.
3. **`scripts/sync-to-active.sh` numbered its steps "1/3 → 2/3 → 2.5/3 → 3/3"** after v1.13.1 added the fourth step (agents/) without updating the denominators. The dry-run output was visibly inconsistent.
4. **`tests/README.md` still said "no CI integration yet"** even though `meta_review.py` has been wired into GitHub Actions since v1.12.0. Contributors reading the file got the wrong impression.
5. **`hooks/pre-flight-check.sh` had a lossy fallback path reconstruction** that silently degraded (returned `None` instead of finding the memory dir) for projects with `-` in the directory name — including `idea-to-deploy` itself.

### Fixed

- **`.claude-plugin/marketplace.json`** — version `1.11.0` → `1.13.2`; both description fields updated from "17 skills" to "18 skills" and refreshed to mention daily-work routing + self-review mode; keywords expanded with `self-review`, `meta-review`, `daily-work-router`.
- **`skills/kickstart/SKILL.md`** — removed `disable-model-invocation: true` from frontmatter. `/kickstart` can now be invoked through the `Skill` tool by `/project` router without being blocked.
- **`scripts/sync-to-active.sh`** — renumbered all four steps to the honest `1/4, 2/4, 3/4, 4/4` scheme. Added an inline comment recording the history of the "2.5/3" transitional numbering for future maintainers.
- **`tests/README.md`** — rewrote the "Running fixtures" / "Future" sections to clearly distinguish the **automated structural gate** (`meta_review.py` in CI, blocking on every PR) from the **manual behavioural smoke-runs** (fixture outputs that are non-deterministic by model and can only be judged by a human at release time). Added three documented paths to behavioural automation (LLM-as-judge, snapshot diffing, schema-only validation) as candidates for future releases.
- **`hooks/pre-flight-check.sh`** — replaced the lossy `replace("-", "/")` reverse-reconstruction fallback with an iteration over `cwd_resolved.parts` suffixes, so projects with hyphens in directory names (`idea-to-deploy`, `my-app`, etc.) still resolve to their memory dir when the primary path lookup misses.

### Added

- **`tests/meta_review.py` — two new Critical checks** to close the gap that let v1.13.1 ship with a stale marketplace.json:
  - **M-C13** — validates `marketplace.json.plugins[0].version == plugin.json.version` and that every "N skills" mention in either description field matches `len(skills/)`. Fires Critical on mismatch.
  - **M-C14** — scans `tests/README.md` for stale "no CI integration yet" / "not CI-friendly" phrasing that contradicts the actual CI workflow. Fires Critical on match.
- **`tests/meta_review.py` — SMOKE_TRIGGERS expanded** with four new rows covering `/session-save` and `/task` (the v1.10.0 and v1.5.0 skills that were never added to M-I7). Smoke coverage is now 17 skills via direct triggers + `/kickstart` via the `/project` router = all 18 skills exercised.
- **`tests/meta_review.py` — docstring + SMOKE_TRIGGERS comment** updated from "16 skills" to "18 skills" to match reality.

### Changed

- **`.claude-plugin/plugin.json`** — version `1.13.1` → `1.13.2`.
- **`README.md`** / **`README.ru.md`** — version badges `1.13.1` → `1.13.2`.

### Migration

```bash
git pull
bash scripts/sync-to-active.sh
python3 tests/meta_review.py --verbose
```

The sync will pick up the renumbered steps, the kickstart frontmatter change, and the pre-flight hook fix. `meta_review.py` will now flag any future marketplace.json drift as Critical.

### Why a patch-level bump

No new user-facing capability is added — only drift between documentation files and the actual methodology state is corrected, plus two new gates in the automated rubric to prevent the same class of drift from silently re-accumulating. Per SemVer this is a fix (PATCH), not a feature (MINOR). The methodology version counter stays at 1.13.

### What the audit found vs. what shipped

The qualitative self-review produced a punch list of 1 Critical + 4 Important + 3 Nice-to-have. v1.13.2 fixes the Critical and all four Important items plus extends `meta_review.py` with two new gates. The three Nice-to-have items (plugin.json keywords refresh, `doc-writer` allowed-tools clarification, `/explain` English trigger coverage) are deferred to v1.14.0 since they do not affect correctness, only indexing quality and edge-case trigger recall.

---

## [1.13.1] - 2026-04-11

Patch release that finishes what v1.13.0 started. Closes the 9th gap, discovered immediately after merging v1.13.0: the `sync-to-active.sh` script added in v1.12.0 handles `skills/` and `hooks/` but has no `agents/` handling. That means the v1.13.0 fix to `agents/code-reviewer.md` (methodology-mode Step 0 for the forked subagent) landed in the repo but never propagated to `~/.claude/agents/code-reviewer.md`. The `/review --self` mode was effectively inactive: subagent kept using the stale project-level instructions, would still have produced the "Missing PRD.md" nonsense reports.

Detected by `diff -rq agents/ ~/.claude/agents/` after v1.13.0 sync — all 5 agents differed (not just code-reviewer; they had never been sync'd since the script was written).

### Fixed

- **`scripts/sync-to-active.sh`** — added Step 2.5 (agents/) mirroring Step 2 (hooks/) logic. Copies `agents/*.md` to `~/.claude/agents/` with the same `cmp -s` content-based drift detection as the hooks step. No-op when content matches, idempotent on re-runs. Handles both `--check` (dry-run) and normal mode.

### Changed

- **`.claude-plugin/plugin.json`** — version 1.13.0 → 1.13.1.
- **`README.md`** / **`README.ru.md`** — version badges 1.13.0 → 1.13.1.

### Migration

```bash
git pull
bash scripts/sync-to-active.sh
```

This now copies all 5 subagent files into `~/.claude/agents/`. Verify with:

```bash
diff -rq agents/ ~/.claude/agents/   # should be silent (no output)
```

No claude restart needed — subagent definitions are re-read on every invocation.

### Why a patch-level bump

This change adds no new user-facing capability; it restores the effective activation of v1.13.0 which would otherwise remain dormant. Per SemVer this is a bug fix (PATCH), not a feature (MINOR). The methodology version counter stays at 1.13, which is the correct semantic version for "review skill supports self-mode".

---

## [1.13.0] - 2026-04-11

Methodology self-review release. Closes the 8th gap surfaced during v1.12.0 review: `/review` skill had Step 0 methodology-mode detection since v1.5.0 (`--self` flag, `.claude-plugin/plugin.json` sniffing), but the `code-reviewer` subagent to which `/review` forks via `agent: code-reviewer` had its own instructions in `agents/code-reviewer.md` that did NOT mention methodology mode. Running `/review` inside the idea-to-deploy repo produced nonsense BLOCKED reports because the subagent searched for `PRD.md`, `STRATEGIC_PLAN.md`, `IMPLEMENTATION_PLAN.md` (project-level documents that don't exist in a methodology repo).

### Fixed

- **`agents/code-reviewer.md`** — added Step 0 at the top of the subagent instructions, mirroring `skills/review/SKILL.md`. The subagent now detects methodology mode (`--self` flag, methodology-repo sniffing, or changed-files touching methodology surfaces) and delegates to `tests/meta_review.py --verbose` instead of running project-level checks. Explicit list of what NOT to do in methodology mode: no `PRD.md`/`STRATEGIC_PLAN.md` lookups, no user-story scoring, no SOLID/code-smell against infrastructure hooks, no inventing rubric checks (delegate to `tests/meta_review.py` which is the authoritative source).
- **`skills/review/SKILL.md`** — Step 0 rewritten to be unambiguous. Old version said "Jump to Step 3 with the meta-rubric" which was confusing (Step 3 is output formatting, not rubric application). New version says explicitly: run `python3 tests/meta_review.py --verbose`, parse output, present as `/review`-style report. Frontmatter version 1.4.0 → 1.13.0 (jumped to match plugin.json methodology-version track).

### Changed

- **`.claude-plugin/plugin.json`** — version 1.12.0 → 1.13.0, description adds "self-review mode" to the capability list.
- **`README.md`** / **`README.ru.md`** — version badges 1.12.0 → 1.13.0. Skill count unchanged (18).

### Why

During the v1.12.0 review cycle, I invoked `/review` on the feat/v1.5.0-sync-and-hook-fix branch (17 files of methodology changes). The code-reviewer subagent came back with a report looking for project-level docs: "M-C5: C6 & C7 (Critical) — Missing PRD.md", "recommended to create PRD.md from strategic plan". This was obviously wrong — idea-to-deploy is a methodology repo, not a SaaS project. I had to do a manual review instead and the project-level review agent false-negative was flagged as the 8th gap in `session_2026-04-11_2.md`.

Root cause: `skills/review/SKILL.md` already had Step 0 methodology detection, but `agent: code-reviewer` + `context: fork` in the skill frontmatter means `/review` forks to a subagent with its own instructions. The fork does not inherit SKILL.md — the subagent sees only `agents/code-reviewer.md`. That file had no methodology-mode awareness, so the subagent ran its default (project-level) validation.

Fix is symmetric: sync the Step 0 block between `skills/review/SKILL.md` (for when `/review` runs in-context) and `agents/code-reviewer.md` (for when it forks). Both now detect methodology mode and both delegate to `tests/meta_review.py`. The runner script is the single source of truth for the rubric; both entry points just ask it for the report.

### Migration

No user action required if you already ran `bash scripts/sync-to-active.sh` after v1.12.0. For v1.13.0, re-run:

```bash
git pull
bash scripts/sync-to-active.sh
# no claude restart needed — subagent definitions are re-read on every invocation
```

### Verify

```bash
cd /path/to/idea-to-deploy
# Direct runner:
python3 tests/meta_review.py --verbose
# Via /review skill (after claude restart to pick up new SKILL.md):
#   /review --self
# Expected output: "FINAL STATUS: PASSED" (or PASSED_WITH_WARNINGS with specific findings)
```

---

## [1.12.0] - 2026-04-11

Methodology hardening release. Closes six systemic gaps surfaced by the NeuroExpert 2026-04-11 parallel-session incident, where two Claude sessions performed the same kong.yml tech-debt refactor in parallel because nothing in the methodology forced a pre-flight check on recent commits and no router existed for daily-work tasks on existing code.

### Added

- **`/task` skill (new)** — second router skill, parallel to `/project`. Where `/project` routes requests to **create** something (/kickstart, /blueprint, /guide), `/task` routes requests to **modify existing code**: /bugfix, /refactor, /doc, /test, /perf, /security-audit, /deps-audit, /migrate, /harden, /infra, /explain, /review, /session-save. Thin router — never generates code itself, always delegates via the Skill tool. Includes `references/routing-matrix.md` with 13 target skills and an indirect-signal table, plus `tests/fixtures/fixture-10-task/` with 4 routing scenarios. Methodology now has **18 skills** (was 17).
- **`hooks/pre-flight-check.sh` (new)** — `UserPromptSubmit` hook. Injects `git log --oneline -10`, `git status --short`, `MEMORY.md` index, and `.active-session.lock` warnings into the model context on every user prompt. Prevents the NeuroExpert-style parallel-session duplication: if another Claude session touched this project in the last 10 minutes, the model sees a warning and is told to check recent commits BEFORE starting work. No-op silently when `$PWD` is not a git repo.
- **`scripts/sync-to-active.sh` (new)** — idempotent one-command sync from this repo to the user's active install (`~/.claude/skills/`, `~/.claude/hooks/`, `~/.claude/settings.json`). Was the root cause of v1.4.0's 6-skill drift: users were expected to manually copy new skills after each release and rarely did. Now `bash scripts/sync-to-active.sh` (or `--check` for dry-run) brings the active install in line with the repo in one step. Patches `settings.json` hooks block to register all 4 hooks with correct matchers, backing up the old file as `settings.json.bak-<timestamp>`.
- **Active-session lockfile (`.active-session.lock`)** — `/session-save` now writes a JSON lockfile to the project memory dir (`timestamp`, `pid`, `branch`, `project`, `note`). `pre-flight-check.sh` reads it and warns the next Claude session if the lock is fresher than 10 minutes. Stale locks self-expire, no cleanup task needed. Documented in `skills/session-save/references/session-save-checklist.md`.

### Fixed

- **`hooks/check-commit-completeness.sh` fixture detection** — previously matched only fixture directory name (`skill_name in entry.name`), while `check-skill-completeness.sh` also matched `notes.md` content. The two hooks diverged and `check-commit-completeness.sh` would false-positive-block commits touching skills whose fixture was exercised only indirectly (e.g. `/project` tested via `fixture-01-saas-clinic` through `/kickstart`). Unified the detection: both hooks now match directory name OR `/skill-name` token in `notes.md` OR bare-word mention. 7th gap surfaced during v1.5.0 review — fixed in the same release.

### Changed

- **`hooks/check-tool-skill.sh` — rate-limited** (60-second window per session via `/tmp/claude-skill-check-<session>.state`). Old behavior: fired a "STOP, вызови Skill" reminder before every single Bash/Edit/Write tool call, which trained models to respond with a formal "скиллы не матчатся" brush-off before every action and **defeated the purpose of the hook**. New behavior: reminder once per minute max, first call of a session always emits, language softened from "STOP" to "подумай task-level". The hard rule to evaluate skills **task-level once** lives in `~/projects/.claude/CLAUDE.md`; this hook is a periodic nudge, not an enforcement point.
- **`skills/project/SKILL.md` — v1.4.0** — added Step 2 (detect existing-project signals and redirect to `/task`) so `/project` stops catching daily-work requests. Renamed old Steps 2/3/4 → 3/4/5. Frontmatter description clarifies "creation router" and points at `/task` for existing code. Version field bumped 1.3.1 → 1.4.0.
- **`skills/session-save/SKILL.md` — v1.5.0** — added Step 4.5 (write active-session lockfile) with Bash and Python examples. Strengthened auto-trigger list: now includes "after any `git commit` in a branch heading for PR", "after `/review` that passed 9+/10", and "every 5 significant actions without a save". Frontmatter version 1.0.0 → 1.5.0.
- **`hooks/check-skills.sh`** — added trigger patterns for `/task` (закрой tech debt / поправь в проекте / existing project / tech debt cleanup / maintenance task / ...). Patterns intentionally match **ambiguous** phrasings only; direct phrasings ("почини баг в X", "отрефактори Y") still fire the specific daily-work skill hints (/bugfix, /refactor) as before.
- **`.claude-plugin/plugin.json`** — version 1.11.0 → 1.12.0, description updated to "18 skills", added "daily-work routing" to the capability list.
- **`README.md`** / **`README.ru.md`** — skill count 17 → 18 everywhere.

### Why

NeuroExpert 2026-04-11: two Claude Code sessions independently picked up the "close kong.yml tech debt in `scripts/deploy.sh`" task and ran the exact same extract-method refactor in parallel. The second session didn't discover this until after all edits were written; `git status` came back clean because the first session had already committed. Root cause analysis surfaced six systemic gaps — all closed by this release:

1. No pre-flight check of `git log` / `git status` / MEMORY.md before starting work → added via `pre-flight-check.sh`.
2. `/session-save` skill wasn't installed in the active install (listed in repo, missing from `~/.claude/skills/`) because there was no sync mechanism → added via `sync-to-active.sh` (which also brings in `deps-audit`, `harden`, `infra`, `migrate`, `security-audit`, `session-save` — six skills that had drifted out).
3. `check-tool-skill.sh` fired on every tool call, training the model to respond with formal "скиллы не матчатся" before each action → rate-limited + softer language.
4. `/project` routed only **creation** requests; there was no entry point for "work on existing code", so the hard rule "при любом сомнении — /project" created a mental dead-end for tech-debt tasks → added `/task`.
5. No parallel-session awareness → added `.active-session.lock` mechanism + `pre-flight-check.sh` reading it.
6. `~/projects/.claude/CLAUDE.md` hard rule didn't explicitly cover tech-debt / refactor / existing-code cases with a mapping to `/task` → updated in the same day.

### Migration

- **Required:** run `bash scripts/sync-to-active.sh` once after `git pull`. This copies `/task` + 5 previously-missing skills + 2 previously-missing hooks into `~/.claude/`, and patches `settings.json` to register `pre-flight-check.sh` and the completeness hooks. Backup of the previous `settings.json` lands at `~/.claude/settings.json.bak-<timestamp>`.
- **Restart `claude`** after the sync — skill registry is loaded at session start and does not hot-reload.
- **Existing `/debug` references:** already handled in v1.4.0 migration — no action needed here.
- **Hard-rule update:** the `~/projects/.claude/CLAUDE.md` hard rule now mentions `/task`. If you maintain your own copy, update it to route existing-code work through `/task` instead of `/project`.

---

## [1.4.0] - 2026-04-11

### Changed

- **BREAKING (silent):** renamed `/debug` skill to `/bugfix` to avoid name collision with Claude Code's built-in `/debug` slash command. The built-in has `disableModelInvocation: true` baked into the binary, which blocked model-initiated invocation via the Skill tool and broke the "on error → /bugfix" automation rule. Users can still type `/debug` manually, but model auto-invocation never worked for the old name. Skill body, trigger phrases, and methodology are unchanged.
- All cross-references in README.md, README.ru.md, CHANGELOG, CONTRIBUTING, skills/*/SKILL.md, skills/*/references/, hooks/check-skills.sh, hooks/check-tool-skill.sh, hooks/README.md, docs/CONTENT-PLAN.md, .github/ISSUE_TEMPLATE/, tests/fixtures/ updated to `/bugfix`.
- Root cause investigation: `strings $(readlink -f $(which claude)) | grep 'disableModelInvocation:!0'` shows exactly two built-in skills with this flag: `batch` and `debug`. All other Idea-to-Deploy skill names (`/test`, `/refactor`, `/review`, …) remain unaffected.

### Migration

- Users upgrading from <1.4.0: run `rm -rf ~/.claude/skills/debug && cp -r skills/bugfix ~/.claude/skills/bugfix` after git pull. Update any personal hooks/scripts that reference `/debug` to `/bugfix`. Project-specific CLAUDE.md files may need similar updates.

---

## [1.11.0] — 2026-04-09

Marketplace readiness release. Fixes skill description budget overflow (6 of 17 skills were silently dropped by Claude Code Skill tool), adds missing plugin manifest fields for Anthropic Directory submission, and adds recommended agent configuration fields.

### Fixed

- **Skill descriptions shortened** (360-470 → 116-155 chars) — all 17 skills now fit within Claude Code's default 16K character budget for skill metadata. Previously `deps-audit`, `harden`, `infra`, `migrate`, `security-audit`, and `session-save` were not registered in the Skill tool.

### Changed

- **`plugin.json`** — added `homepage`, `keywords` (10 discovery tags), `author.email`, `author.url`. Version 1.10.0 → 1.11.0. Description trimmed (removed internal details).
- **All 5 agents** — added `effort` and `maxTurns` frontmatter fields per Anthropic plugin reference.
- **`README.md`** / **`README.ru.md`** — version badge updated to 1.11.0.

---

## [1.10.0] — 2026-04-09

Minor release. Adds **`/session-save`** — a new skill that saves session context (what was done, key decisions, blockers, next steps) to the project's memory directory. Ensures continuity between Claude Code sessions: the next session reads the saved context and picks up where the previous one left off.

Also adds a hard rule to CLAUDE.md mandating session context saving at the end of every work session.

### Added

- **`/session-save` skill** (`skills/session-save/SKILL.md`): 5-step workflow — gather git/conversation context, summarize using 9-field checklist, write `session_YYYY-MM-DD.md` to memory directory, update MEMORY.md index, confirm to user.
- **`references/session-save-checklist.md`**: required fields and quality criteria for session memory files (date, project, branch, summary, decisions, changed files, blockers, next steps, non-obvious context).
- **Trigger phrases** in `hooks/check-skills.sh`: Russian + English patterns for session save (сохрани контекст, итоги сессии, save session, end of session, etc.).
- **Regression fixture** `tests/fixtures/fixture-09-session-save/` with idea.md, notes.md, expected-files.txt.

### Changed

- **`plugin.json`** version 1.9.0 → 1.10.0, description updated (16 → 17 skills).
- **`hooks/check-tool-skill.sh`** — added `/session-save` to the skill reminder list.
- **`README.md`** — badges (Skills-17, Version-1.10.0), new "Session Management" section, contracts row, call graph entry, recommended models row, contributing count.
- **`README.ru.md`** — mirror of all README.md changes in Russian.
- **`CLAUDE.md`** (user project-level) — new hard rule "Сохранение контекста сессии" + `/session-save` added to automatic skills section.

### Why this is a minor release

New skill (`/session-save`) = new functionality = minor version bump per SemVer.

---

## [1.9.0] — 2026-04-08

Minor release. Adds **M-C12** to the meta-review rubric: structural detection of stale skill-count and agent-count numbers in user-facing documentation prose. Closes the drift class that accumulated silently across v1.4.0 → v1.8.1. The initial M-C12 run caught the last 2 `existing 13` references in Contributing sections that had escaped the v1.8.1 spot-fix.

### Added

- **M-C12 (Critical)** in `skills/review/references/meta-review-checklist.md`: "Skill and agent counts in user-facing prose must match reality." Full binary criterion with scanned/not-scanned file scope, skipped-line rules (tables, headings, historical contexts), pattern definitions (direct count, contextual `existing N`, agent count), and action-on-fail guidance.

- **M-C12 implementation** in `tests/meta_review.py`. Scans `README.md`, `README.ru.md`, `CONTRIBUTING.md`, `hooks/README.md`, `docs/**/*.md`. Deliberately skips `CHANGELOG.md` (historical), `skills/*/SKILL.md` (too many false positives from example counts), and `skills/review/references/*.md` (rubric docs legitimately reference historical counts). Uses three regex patterns with hyphen-guards and heading-skip to suppress false positives.

- **Meta-review Critical tier** grew from 11 to 12 checks.

### Fixed (caught by the initial M-C12 run)

- **`README.md:494`** — `the existing 13` → `the existing 16`. In the Contributing section, explaining that new skills should follow the shape of existing ones. Count was left at 13 since v1.3.x.
- **`README.ru.md:494`** — same fix, Russian version (`существующих 13` → `существующих 16`).

These two had survived the v1.8.1 cleanup because the author's ad-hoc `grep "13\s+skill"` pattern did not match `existing 13` (word "skill" appeared earlier in the sentence, not after the number). M-C12's Pattern B (`existing N` in skill context) generalizes the check to cover this form.

### Calibration findings during development

Before merging M-C12 into the rubric, its initial runs revealed two classes of false positives that were fixed as part of the same release — **before** the check was merged, so the rubric enters the main branch passing cleanly:

1. **12 false positives on Markdown headings** — e.g., `### Project Creation (3 skills)`, `### Daily Work (6 skills)`, `### Operations (4 skills)`. These are legitimate category subtotals in section headings, not global-count claims in prose. Fix: skip all lines starting with `#`.
2. **2 false positives on hyphenated qualifiers** — `depth-3 skills` in the Call Graph prose. Regex `\b\d+\s+skills?` matched because `\b` fires between `-` and `3`. Fix: prepend `(?<!\S)` lookbehind so only whitespace-preceded numbers count.

Both fixes are documented inline in `tests/meta_review.py`.

### Changed

- **`plugin.json`** version 1.8.1 → 1.9.0.
- **Both README badges** bumped.

### Why this is a minor release

M-C12 is a new rubric feature adding a new Critical check. Per the SemVer rules established in `CONTRIBUTING.md`, new rubric checks are minor-version bumps. The 2 prose fixes are cleanup enabled by the new feature, not the feature itself.

### Verified before release

- `python3 tests/meta_review.py --verbose` — PASSED (0 Critical, 0 Important) with M-C12 now active
- `python3 tests/verify_triggers.py` — 0 drift
- Initial M-C12 run (pre-calibration) flagged 14 findings; 12 were resolved by the heading/hyphen fixes, 2 were real drift and resolved by the Contributing fixes.
- Branch protection on `main` rejected direct push (first-class test of the v1.8.0 setup); release went through a proper PR.

### Meta — the rubric is learning faster

The v1.4→v1.9 sequence shows the meta-rubric catching its predecessor's blind spot in each release:

```
v1.4 Potemkin skills             →  v1.5 spec-noncompliant hooks
v1.5 Potemkin enforcement        →  v1.6 static hook-schema check (M-C10)
v1.6 drift in trigger phrases    →  v1.7 trigger drift verifier (M-C11)
v1.7 no public-repo polish       →  v1.8 CI + CONTRIBUTING + CI badge
v1.8 drift in prose counts       →  v1.9 prose count verifier (M-C12)
```

At each step, the lesson comes from how the previous release actually failed, not from top-down design. The rubric now has 12 Critical + 8 Important + 4 Nice-to-have checks covering structural, behavioral, and narrative consistency — a defense surface that is harder to slip past than any single-person review could be.

---

## [1.8.1] — 2026-04-08

Patch release. Documentation consistency fix. Three stale "13 skills" references in the README body survived the v1.4.0 → v1.5.0 → v1.6.0 → v1.7.0 → v1.8.0 sequence because the badge count was updated but the in-body prose was missed. All badges and tables were already correct at 16; only narrative sentences drifted.

### Fixed

- **`README.md:15`** — `"Installing it registers 13 skills and 5 subagents"` → `"16 skills and 5 subagents"`. Appeared right below the badges, which was especially embarrassing because the adjacent badge already said `Skills: 16`.
- **`README.md:64`** — installation path comment `"# 13 skill directories"` → `"# 16 skill directories"`.
- **`README.ru.md:15`** — same as README.md:15, Russian version.
- **`README.ru.md:64`** — same as README.md:64, Russian version.
- **`skills/review/references/meta-review-checklist.md:37`** — M-C8 criterion said `"enforced in v1.3.1 for the existing 13 skills"`. Expanded to `"enforced in v1.3.1 for the 13 skills that existed at that time, extended to all 16 skills in v1.4.0+"` — preserves the historical fact but clarifies the current state.

### Not touched

`CHANGELOG.md` still contains "13 skills" references in the `[1.3.1]`, `[1.3.0]`, and `[1.4.0]` entries. Those are historical records — the changelog describes what was true *at that release*, not what is true now. Rewriting history in the changelog would be worse than the original bug.

### How this was caught

The user asked directly: "find all stale `13 skills` mentions in the README and fix them." The meta-review rubric didn't catch this because M-C7 only checks that the README's `Skills: N` badge matches `ls skills/ | wc -l` — it doesn't grep the prose. This is a gap in M-C7.

### Follow-up for a future minor release

Add **M-C12** to the meta-review rubric: "No hardcoded skill-count or agent-count numbers in any README prose outside the Skill Contracts and Recommended Models tables". Implementation: grep every `README*.md` for patterns like `\b\d+\s+(skills?|skill directories?)\b` and cross-check against the actual count from `ls skills/`. Would have caught this class of drift automatically. Deferred to v1.9.0 or later — the immediate fix is priority, the rubric expansion is follow-up.

### Verified before release

- `python3 tests/meta_review.py --verbose` — PASSED (0 Critical, 0 Important)
- `python3 tests/verify_triggers.py` — 0 drift
- Manual grep for `13\s+(skill|скилл)` outside CHANGELOG — no matches

---

## [1.8.0] — 2026-04-08

Minor release. Closes the last deferred item from v1.6.0 (#3 — CI workflow) and adds the missing public-repo infrastructure (CONTRIBUTING, ISSUE_TEMPLATE) that should have existed from day one of the public repo but was postponed as "solo project overhead not justified". The trigger for flipping that decision: **3 GitHub stars within 24 hours of publishing the repo**. That's a traction signal that makes "wait for first PR" the wrong posture — first PRs follow star accumulation by days, not months, and CI is far cheaper to have before the first PR than to retrofit after.

### Added

- **`.github/workflows/meta-review.yml`** — server-side Gate 1 as a GitHub Actions workflow. Runs on every push to `main` and every pull request. Executes `python3 tests/meta_review.py --verbose` followed by `python3 tests/verify_triggers.py`. Fails the job on any non-zero exit. Uses Python 3.11 stdlib only — no `pip install` step — because both scripts are intentionally zero-dependency. Typical runtime: 20–40 seconds. Timeout: 5 minutes. Permissions: `contents: read` (no write access to the repo from the workflow).

- **`CONTRIBUTING.md`** — explicit ground rules for contributors:
  1. The `SKILL.md` body is the canonical source of truth for triggers; drift from `hooks/check-skills.sh` fails M-C11.
  2. Every new skill must ship with its references, trigger phrases, and fixture in the same PR (enforced by `check-skill-completeness.sh` + `check-commit-completeness.sh` locally and M-C2 / M-C3 / M-C4 on CI).
  3. `python3 tests/meta_review.py --verbose` must print `FINAL STATUS: PASSED` before opening a PR.
  4. SemVer rules for what counts as patch / minor / major bumps.
  Plus a PR checklist and instructions for reporting bugs and proposing new skills.

- **`.github/ISSUE_TEMPLATE/bug_report.md`** — structured bug report template with environment (Claude Code version, plugin version, model in use, OS, installation method), reproduction steps, expected vs observed behavior, logs, and a "did you run the meta-review?" section that catches the most common bug report mistakes before they reach the maintainer.

- **`.github/ISSUE_TEMPLATE/feature_request.md`** — new skill / rubric check proposal template with slots for one-line summary, trigger phrases (Ru + En), read/write contract, recommended model, proposed Skill Contracts row, and explicit "why not covered by existing skill" justification. Designed to force the same discipline on proposals that the methodology enforces on existing skills.

- **`docs/CI.md`** — comprehensive CI documentation:
  - What the workflow does and why
  - The four-layer defense-in-depth table (layers 1–4, from UserPromptSubmit reminder to CI)
  - **Step-by-step branch protection setup instructions** — cannot be provisioned from code, only via the GitHub UI. Documents every click required to make the `meta-review` check required on main, plus the "Do not allow bypassing" setting that prevents silent admin overrides.
  - Emergency override procedures (admin override, temporary protection removal) — both leave audit trails by design.
  - How to reproduce CI locally (run the exact same commands).
  - Troubleshooting section covering common failure modes (CI passes locally but fails on GitHub, check doesn't appear in branch protection, CI too slow).

- **CI status badge** in both `README.md` and `README.ru.md` — visible quality signal for visitors, links to the Actions history.

- **"Defense-in-depth overview" section** in `hooks/README.md` — adds the 4-layer table at the top, making the relationship between local hooks (layers 1–3) and CI (layer 4) explicit.

### Changed

- **`plugin.json`** version 1.7.0 → 1.8.0.
- **Both README badges** bumped; top-of-file links now include `Contributing` → `CONTRIBUTING.md` (was an in-page anchor) and `CI` → `docs/CI.md`.
- **`hooks/README.md`** — expanded with the defense-in-depth overview referencing the new CI layer.

### Philosophy — the day-one public repo lesson

v1.8.0 is the first release shaped by external feedback (star count) rather than internal retrospective. Three observations from 24 hours of being public:

1. **Distribution rate ≠ contribution rate, but they correlate tightly.** 3 stars/day is early-traction territory. First PRs typically follow within 1–2 weeks.
2. **CI is a social signal, not just enforcement.** A green "meta-review passed" badge on every commit tells potential contributors "this is maintained seriously, your PR will be held to a standard". It's a magnet for quality contributions and a filter against drive-by noise.
3. **Cost dropped after v1.6.1.** `tests/meta_review.py` already existed as a persistent, stdlib-only file. Adding CI was 20 minutes: a 15-line YAML workflow + the existing command. The hard work had been done two releases ago without me realizing it was CI prep.

The lesson: when building infrastructure for future defense, **the act of extracting inline logic into a persistent file often makes the next defense layer nearly free**. v1.6.1 said "we might want CI eventually, so extract the runner now". v1.8.0 said "CI time is now, and it's 20 minutes because v1.6.1 already did the preparation". This is the inverse of the v1.4.0 Potemkin pattern — instead of declaring a defense that doesn't exist, v1.6.1 quietly built a foundation that made the real defense cheap to add when the time came.

### Non-reversible setup required after merge

One thing this release **cannot** do from code: enable branch protection on `main` so the CI check becomes blocking. That is a GitHub UI operation. See `docs/CI.md` for the exact steps. Until branch protection is enabled, CI will run and report status but PRs can be merged even if it fails. **This is intentional — the author should review the first CI run output before making it blocking.**

### Verified before release

- `python3 tests/meta_review.py --verbose` — PASSED (0 Critical, 0 Important) on the v1.8.0 staged state
- `python3 tests/verify_triggers.py` — 0 drift
- Commit-gate hook validated the release diff — no SKILL.md file changes, no new skills, so the per-skill completeness check is a no-op; the hook ran cleanly.
- The workflow YAML syntax was verified by hand against the GitHub Actions schema; the first real execution will happen on the v1.8.0 push itself.

### Not done (deferred by design)

- **Automatic branch protection provisioning** — Terraform / GitHub Apps could technically create it via API, but requires additional permissions and is out of scope for a methodology plugin. Manual UI setup is documented in `docs/CI.md`.
- **CI matrix (multi-Python-version)** — meta_review.py only needs 3.11, and multi-version doesn't add value for a plugin that runs on the maintainer's machine, not in a library's user environment. Single-version is correct.
- **CI on forks** — GitHub Actions on PRs from forks run with read-only tokens by default, which is what this workflow needs. No further config required.

---

## [1.7.0] — 2026-04-08

Minor release. Closes v1.6.0 deferred item #2: **structural drift detection between SKILL.md bodies and `hooks/check-skills.sh` regex**. Adds `tests/verify_triggers.py` and a new rubric check M-C11. The initial run against the v1.6.1 state caught **111 pre-existing drift findings** that had accumulated silently across v1.2.0–v1.6.1 — all fixed as part of this release before M-C11 was merged into the rubric.

### Added

- **`tests/verify_triggers.py`** — canonical-phrase drift verifier. For each `skills/<name>/SKILL.md` (except `disable-model-invocation: true` skills), it:
  1. Extracts the `## Trigger phrases` section
  2. Parses bullet lines, splits on commas, skips meta-descriptions (lines starting with `любой`, `любая`, `автоматически`, etc.) and multi-word descriptions (> 6 words)
  3. For each canonical phrase, loads `hooks/check-skills.sh` as a Python module (TRIGGERS list), runs every regex against the phrase, and verifies:
     - At least one regex matches the phrase
     - The matched hint text mentions `/<skill-name>`
  4. Emits drift findings as `unmatched` / `wrong-route` / `no-trigger-section`
  5. Supports `--json` for machine-readable output, used by `tests/meta_review.py`

- **M-C11 (Critical)** in `skills/review/references/meta-review-checklist.md`: "Every canonical trigger phrase in a SKILL.md body routes to the right skill via hooks/check-skills.sh." The meta-review runs `verify_triggers.py` as a subprocess and promotes drift findings to Critical failures (unmatched / wrong-route) or Important warnings (missing trigger section).

- **Meta-review Critical tier** grew from 10 to 11.

### Fixed (111 drift findings, caught by the initial M-C11 run)

The SKILL.md `## Trigger phrases` sections had accumulated phrases over 5 minor releases without the hook regex being updated to match. The initial run flagged 111 findings across 14 skills. Breakdown after filtering meta-descriptions (which shouldn't be in the trigger list at all), fix distribution:

- **18 findings filtered as meta-descriptions** — the verifier's `NOISE_PREFIX_RE` / `NOISE_ANY_RE` / `MAX_PHRASE_WORDS` rules skip phrases that are conditions or documentation rather than literal user input (`"любой запрос на создание законченного работающего продукта"`, `"автоматически перед любым DDL"`, `"multi-file/multi-module exploration"`, etc.). These are legitimate documentation inside the trigger section but shouldn't be part of the regex matching contract.

- **93 findings fixed by expanding hook regex**, distributed across all 14 affected skills. Highlights:
  - `/blueprint`: `создай документацию для проекта`, `техническое задание`, `PRD`, `design the system`, `system design`
  - `/debug`: `traceback`, `странное поведение`, `fix this bug`, `troubleshoot`, `log fragment`, `panic`
  - `/deps-audit`: `package-lock.json audit`, `requirements.txt audit`, `vulnerability scan dependencies`
  - `/doc`: `обнови README`, `опиши API`, `добавь комментарии`, `(инлайн|inline) комментарии`, `JSDoc`, `docstrings`, `changelog(\.md)?`
  - `/explain`: `как это работает`, `как устроен`, `что здесь происходит`, `разбери (код|этот|файл|модуль)`, `walkthrough`
  - `/guide`: `создай гайд`, `сделай cookbook промптов`, `промпты для Claude`, `guide for project`, `cookbook`, `prompt sequence`
  - `/harden`: `secrets management`, `vault`, `doppler` (added to the /harden regex, removed overlap with /infra)
  - `/migrate`: `schema change`, `dbmate up`
  - `/perf`: `лагает`, `N+1`, `утечка памяти`, `memory leak`, `optimize`, `make it faster`, `latency`, `throughput`
  - `/project`: `сделай сайт`, `новый MVP`, `хочу запустить`, `build a project`, `new (app|service)`
  - `/refactor`: `перепиши понятнее`, `вынеси в функцию`, `убери дублирование`, `длинная функция`, `глубокая вложенность`, `code smell`, `clean up`, `poor naming`, `magic number`, `god class`
  - `/review`: `проверь PR`, `найди косяки`, `оцени качество`, `найди баги в коде`, `check quality`, `validate`, `audit`
  - `/security-audit`: `утечка ключа`, `CORS check`, `CSP check`, `security headers`, `проверь PR на безопасность`, `security review`
  - `/test`: `нет тестов`, `добавь покрытие`, `coverage`, `юнит-тесты`, `интеграционные тесты`, `регрессионный тест`, `pytest`, `vitest`, `jest`, `go test`, `RSpec`

- **3 remaining findings after the bulk expansion**, fixed individually:
  - `/doc: "inline комментарии"` — regex had `инлайн\s+комментар` (Cyrillic only). Fixed with `(инлайн|inline)\s+комментар`.
  - `/explain: "как это работает"` — regex required `как\s+работает` (no intermediate word). Fixed with `как\s+(это\s+)?работает`.
  - `/explain: "архитектура этого" [wrong-route]` — the phrase matched `/blueprint`'s `архитект` regex. Replaced the phrase in `skills/explain/SKILL.md` with `разбери этот файл` (more literal, routes correctly) and extended the `/explain` regex to cover `разбер\w+\s+(код|этот|файл|модуль)`.

- **Curated away (one phrase)** — `архитектура этого` was removed from `skills/explain/SKILL.md` because it was ambiguous and genuinely belonged to `/blueprint` territory, not `/explain`. The replacement `разбери этот файл` is a cleaner literal phrase.

Final drift count: **0**. Meta-review: PASSED (0 Critical, 0 Important) including the new M-C11 check.

### Changed

- **`tests/meta_review.py`** — new M-C11 block that runs `verify_triggers.py --json` as a subprocess and promotes its findings into the rubric report.
- **`skills/review/references/meta-review-checklist.md`** — new M-C11 section with binary criterion, failure modes, verification script reference, action-on-fail guidance, and the v1.7.0 note explaining the 111-finding backlog.
- **`hooks/check-skills.sh`** — every skill's trigger regex extended to cover all canonical phrases from its SKILL.md body. The file grew from 14 TRIGGER entries to 14 (same count, each one larger). Net change: +~60 lines.
- **`skills/explain/SKILL.md`** — `архитектура этого` replaced with `разбери этот файл`.
- **`plugin.json`** 1.6.1 → 1.7.0.
- **`README.md` / `README.ru.md`** badges bumped.

### Philosophy

The v1.4.0 "provision ec2 instance" bug was not a one-off — it was a visible symptom of a systemic problem: trigger phrases lived in two places (SKILL.md body as documentation, hooks/check-skills.sh as code) with no enforcement of consistency. Every time I added or edited a trigger, I had to update both manually, and twice I forgot. 111 accumulated failures prove this class of bug scales with time-between-fixes.

v1.7.0 solves it structurally: the SKILL.md body is now the canonical source of truth (verified on every meta-review), and any drift from the hook immediately fails Gate 1. The author still writes the regex by hand (no auto-generation — that would lose precision), but the **consistency** between the two sources is machine-verified. Auto-generation of regexes from phrases is deferred until the current model proves insufficient.

### Verified before release

- `python3 tests/verify_triggers.py` — 0 drift findings
- `python3 tests/meta_review.py --verbose` — PASSED, 0 Critical, 0 Important
- The four v1.5.1 enforcement hooks were not touched and still pass M-C10.
- Commit-gate hook validated this release's staged diff — no SKILL.md body edits beyond the `/explain` phrase swap (no new skills, so the per-skill completeness check is a no-op).

### Why this is a minor release not a patch

Adding M-C11 is a new rubric feature, not a bug fix. It introduces a new Critical check. The 111 drift fixes are cleanup *enabled by* the new feature, not the feature itself. Semver: minor.

---

## [1.6.1] — 2026-04-08

Patch release. Closes v1.6.0 deferred item #1 (M-I7 smoke test expansion) and extracts the meta-review runner from its inline Bash/Python embedding into a real file that future releases can depend on.

### Added

- **`tests/meta_review.py`** — persistent implementation of the `/review --self` rubric. Previously the rubric was re-typed as an inline `python3 <<EOF` heredoc inside every release commit's Bash command. That worked but couldn't be reused, version-controlled, or referenced cleanly. Now it's a real Python file with argparse, exit codes (0 = pass/warnings, 1 = blocked, 2 = internal error), and a `--verbose` / `--check-only` interface. All 10 Critical + 8 Important checks from the meta-rubric are implemented in one place. A future CI workflow (v1.6.0 deferred item #3) only needs `python3 tests/meta_review.py` as its single command.

- **M-I7 smoke test expanded from 10 to 30 trigger phrases** — two representative phrases (one Russian, one English) for every model-invocable skill. `/kickstart` has `disable-model-invocation: true` and is deliberately excluded because it's reached via `/project` router, not via trigger phrase. This closes v1.6.0 deferred item #1.

### Fixed (caught by the expanded M-I7 on first run)

- **`hooks/check-skills.sh`** — 8 trigger regex gaps found by the expanded smoke test, all on the English side of skills that previously had only Russian triggers:
  - `/project`: added `start a project`, `build it from scratch`, `end-to-end`, `kickstart`
  - `/debug`: added `debug this error`, `fix this error`, etc.
  - `/test`: added `add tests`, `write tests`, `generate tests`
  - `/perf`: added `optimize performance`, `slow down`, `slow query`
  - `/explain`: added `explain this`, `how does this work`, `walk me through`
  - `/doc`: added `generate readme`, `write docs`, `add docstrings`
  - `/guide`: added `generate a guide`, `step-by-step prompts`

  These gaps existed since v1.2.0 when trigger phrases were first introduced but were invisible because the pre-v1.6.1 smoke test only exercised 10 phrases. This is a concrete demonstration that **expanding test coverage finds real bugs, not just theoretical ones**. The v1.4.0 `provision ec2 instance` miss was the same pattern — a trigger phrase in the SKILL.md body that never made it into the hook regex. M-I7 expansion is a partial answer to that class of bug; v1.7.0's trigger-drift verifier will be the complete answer.

### Philosophy note — why this release exists

v1.6.0 deferred three items with honest justifications. The user asked "what would trigger the need for each?" The first item (expand M-I7 to all skills) had no dependency on external events — it was purely cost/value, and the cost was 6 lines of code. Deferring it was the wrong call. v1.6.1 corrects that.

The second item (trigger auto-generation) genuinely needed architectural thought, so it's still deferred to v1.7.0 (next release). The third item (CI workflow) is still correctly deferred — there's no external contributor yet — but v1.6.1 prepares for it by extracting `tests/meta_review.py`, so the CI adoption when it happens is a one-line workflow.

### Verified before release

- `python3 tests/meta_review.py` → FINAL STATUS: **PASSED** (0 Critical, 0 Important)
- Same script run BEFORE the hook fixes → 8 Important warnings (the drift described above)
- v1.5.1 commit-gate hook validated the release diff: no SKILL.md changes, so the gate was a no-op but ran cleanly.

---

## [1.6.0] — 2026-04-08

Minor release. Closes the last open follow-up from v1.5.1: add **M-C10** to the meta-review rubric — a binary check that every hook uses the JSON schema and exit code semantics matching its declared event type per [Anthropic's hooks spec](https://code.claude.com/docs/en/hooks.md). This is the rubric check that would have caught both v1.5.0 bugs before release.

### Added

- **M-C10 (Critical) in `skills/review/references/meta-review-checklist.md`** — "Every hook uses the JSON schema and exit code semantics matching its declared event type."

  The check parses each `hooks/*.sh` file, extracts its declared `hookEventName` literal, and cross-references the JSON field structure and exit-code claims against a table of known Anthropic hook events (`PreToolUse`, `PostToolUse`, `UserPromptSubmit`, `Stop`, `SubagentStop`, `Notification`, `PreCompact`, `SessionStart`). Flags two specific anti-patterns as Critical failures:

  1. A `PostToolUse` hook whose docstring or comments claim to "block" or "prevent" the tool call. Per spec, PostToolUse runs *after* the tool result exists — its `decision: "block"` field only sends feedback to Claude, it cannot physically undo a Write. Hooks that need prevention semantics must be `PreToolUse`.
  2. A `PreToolUse` hook that emits a root-level `decision` field instead of `hookSpecificOutput.permissionDecision`. The root-level `decision` field belongs to the `PostToolUse` schema; in `PreToolUse` it is silently dropped by the schema validator.

  The rubric entry includes the full allowed-field matrix per event, a runnable Python verification script, and a worked example pointing to the v1.5.1 commit as a reference fix.

- **Meta-review Critical tier count** in the rubric's reporting template increased from 9/9 to 10/10 to reflect M-C10.

### Changed

- **`plugin.json`** version 1.5.1 → 1.6.0.
- **`README.md` / `README.ru.md`** badges bumped to 1.6.0.
- **`CHANGELOG.md`** new `[1.6.0]` entry (this one).

### Verified before release

**Gate 1 was run inline with M-C10 active** against all 4 current hooks:

| Hook | Declared event | Schema compliance | Exit code semantics | M-C10 |
|---|---|---|---|---|
| `check-skills.sh` | `UserPromptSubmit` | ✅ uses `hookSpecificOutput.additionalContext` | exit 0 only (never rejects) | ✅ |
| `check-tool-skill.sh` | `PreToolUse` | ✅ uses `hookSpecificOutput.additionalContext`, no decision field | exit 0 only (soft reminder) | ✅ |
| `check-skill-completeness.sh` | `PreToolUse` | ✅ uses `hookSpecificOutput.permissionDecision: "deny"` with `permissionDecisionReason` | exit 2 on violation (blocks Write) | ✅ |
| `check-commit-completeness.sh` | `PreToolUse` | ✅ uses `hookSpecificOutput.permissionDecision: "deny"` with `permissionDecisionReason` | exit 2 on violation (blocks Bash git commit) | ✅ |

All 4 hooks pass M-C10 in the v1.6.0 release state. The check was designed specifically against the v1.5.0 failure modes — running it on v1.5.0 pre-fix state would have flagged both `check-skill-completeness.sh` (wrong event type: PostToolUse claiming to block) and `check-commit-completeness.sh` (wrong field location: root `decision` in PreToolUse).

### Why this is a minor release, not a patch

Patch releases (v1.5.1) fix bugs in existing features. This release adds a *new rubric check* — a new feature, not a bugfix. The feature has real impact: it converts "the v1.5.0 bugs would have been caught by a properly-designed rubric" from a retrospective claim into a preventive mechanism. Semver says that's a minor bump.

### Rubric evolution loop now closed

- v1.4.0: first self-extension → Potemkin skills (references declared, not created)
- v1.4.1: content fix
- v1.5.0: first enforcement hooks → Potemkin enforcement (wrong schemas per spec)
- v1.5.1: content fix (hooks moved to correct event types and schemas)
- v1.6.0: **rubric learns to catch the v1.5.0 class of bug**

Each release taught the rubric something new. v1.6.0 is the first release where the rubric catches the bug that broke its own predecessor — meta-verification has closed a full cycle. The v1.4→v1.6 sequence is a concrete case study in "the rubric matures through use, not through top-down design" (from the v1.5.1 CHANGELOG philosophy note).

### Not done in this release

- **M-I7 expansion** to smoke-test all 16 skill triggers (currently 10). Cosmetic, deferred.
- **Automated trigger extraction** from `## Trigger phrases` sections of skill bodies into `check-skills.sh`. Would reduce the surface area for v1.4.0-style bugs even further. Deferred to v1.7.0 or later.
- **CI workflow** (`.github/workflows/meta-review.yml`) running `/review --self` on every PR. Deferred because the inline Python implementation is already running in-process during commits.

---

## [1.5.1] — 2026-04-08

Patch release. Fixes two spec-compliance bugs in the v1.5.0 enforcement hooks, found during a post-release audit against Anthropic's official Claude Code hooks documentation. The short version: v1.5.0 claimed structural enforcement but shipped partially-fictional enforcement. v1.5.1 makes it real.

### Fixed

- **`hooks/check-skill-completeness.sh` moved from PostToolUse to PreToolUse.** The v1.5.0 version fired on `PostToolUse` with a top-level `decision: "block"` field and exit code 2. Per [Anthropic's hooks spec](https://code.claude.com/docs/en/hooks.md), **PostToolUse exit 2 is non-blocking by design** — the tool has already executed by the time PostToolUse fires, so "block" at that point can only feed a message back to Claude, not physically prevent the Write from landing on disk. The v1.5.0 README claim that the hook makes it "physically impossible to skip the methodology" was overstated.

  The v1.5.1 version fires on `PreToolUse` matching `Write|Edit|MultiEdit`. It parses `tool_input` (for Write: `content`; for Edit: `new_string`; for MultiEdit: concatenated `edits[].new_string`) to determine what the SKILL.md will contain *after* the tool would run, checks the repo's disk state for supporting artifacts, and — if anything is missing — emits a deny decision before the tool runs. The file never touches the filesystem until the gap is closed. This is the enforcement semantics the v1.5.0 CHANGELOG claimed.

- **`hooks/check-commit-completeness.sh` JSON payload schema corrected.** The v1.5.0 version put the deny decision at the JSON root as `{"decision": "deny", "reason": "..."}`. Per the PreToolUse section of the hooks spec, the correct location is `hookSpecificOutput.permissionDecision: "deny"` with `permissionDecisionReason: "..."`. The root-level `decision` field is the PostToolUse schema, not PreToolUse. The v1.5.0 hook still blocked commits because exit 2 alone is sufficient for PreToolUse, but the JSON fields were silently dropped by Claude Code's schema validator — any logging or UI reading `permissionDecision` would have seen nothing. v1.5.1 uses the correct schema.

- **`hooks/check-skill-completeness.sh` also updated to the correct PreToolUse schema** (`hookSpecificOutput.permissionDecision` instead of top-level `decision`). Same root cause as the commit-gate hook.

- **Hook pipe-tests in `hooks/README.md`** updated to reflect the v1.5.1 JSON schema. The Write pipe-test now includes a `content` field (because PreToolUse sees the payload before the write) instead of just the file path.

### Changed

- **`hooks/README.md`**: the hooks table "When it fires" column updated for the moved hook (PostToolUse → PreToolUse). Added a v1.5.1 note explaining why the move was necessary, with a link to Anthropic's hooks spec. `settings.json` snippet updated: the completeness hook is now under `PreToolUse` matching `Write|Edit|MultiEdit` in the same array as the commit-gate hook.
- **`README.md` / `README.ru.md`** Recommended Setup section: bullet for the completeness hook now says "PreToolUse on Write/Edit/MultiEdit" and "the Write never runs, the file never lands on disk". Both READMEs bumped to 1.5.1.
- **`plugin.json`** version 1.5.0 → 1.5.1.

### Verified before release

- **Gate 1 (`/review --self`)** was run inline against the v1.5.1 working tree before the commit. Result: PASSED (0 Critical, 0 Important). Same meta-rubric as v1.5.0 — no new checks, just new enforcement reality.
- **Pipe-tests** for both v1.5.1 hooks executed manually:
  - `check-skill-completeness.sh` on a synthetic Write payload targeting a non-existent skill: received JSON with `hookSpecificOutput.permissionDecision: "deny"` and exit code 2. ✅
  - `check-commit-completeness.sh` on a synthetic git-commit payload: received the same structure. ✅
- **Gate 2 (commit-gate hook)** validated itself on the v1.5.1 release commit — this commit was tested by `check-commit-completeness.sh` on its own staged diff. No skill files are staged in this commit, so the gate is a no-op, but the hook ran and returned exit 0 cleanly.

### Root cause

v1.5.0 was written without consulting the official hooks documentation. The JSON schemas and exit code semantics were inferred from the v1.5.0 author's (my) mental model, not from the spec. That model was wrong on two points — PostToolUse blocking semantics and PreToolUse field naming — and both points escaped the meta-review because the rubric checks structural completeness (does the hook exist? does it mention the right event name?) but not Anthropic spec compliance (does the JSON schema match? is the exit code semantics right for this event?).

**Follow-up for v1.5.2 or v1.6.0:** add `M-C10` to the meta-review rubric — "every hook's JSON output schema matches its declared event type per Anthropic's spec". That check would have caught both bugs.

### Philosophy note

v1.4.0: Potemkin skills (references/ folders referenced but not created).
v1.4.1: content fix.
v1.5.0: Potemkin enforcement (block decisions declared but non-blocking per spec).
v1.5.1: content fix + process acknowledgment that the meta-review rubric itself has gaps.

Every release in the v1.4–v1.5 sequence caught its own predecessor's blind spot. The meta-rubric is maturing through use, not through top-down design. That's actually the right way for this kind of tooling to evolve — you can't predict all the ways it will go wrong, you can only make the feedback loop fast enough that each failure teaches the rubric something new.

---

## [1.5.0] — 2026-04-08

Minor release. Closes the two open process gaps from the v1.4.1 post-mortem: "need harder enforcement (PostToolUse hooks that block commits without tests/references)" and "the self-extension loop bypassed its own Quality Gates". v1.5.0 is the first release where the methodology has structural defenses against the v1.4.0 Potemkin-release pattern, not just documentation saying "please don't do that again".

### Added

- **`hooks/check-skill-completeness.sh`** — PostToolUse hook on `Write|Edit|MultiEdit`. After any modification to `skills/<name>/SKILL.md` inside a methodology repo (detected by walking up to find `.claude-plugin/plugin.json`), the hook verifies three invariants: (1) if the SKILL.md body references `references/`, the folder exists and is non-empty; (2) if the skill does not declare `disable-model-invocation: true`, `hooks/check-skills.sh` contains a mention of `/<name>`; (3) at least one `tests/fixtures/fixture-*-<name>*/` directory exists. Any failure emits `decision: block` with exit code 2 — Claude Code treats this as a hard stop, the turn cannot progress until the gap is closed. Outside a methodology repo, the hook is a no-op.

- **`hooks/check-commit-completeness.sh`** — PreToolUse hook on `Bash`. Matches only commands containing `git commit`. Parses the staged diff via `git diff --cached --name-only`; if any `skills/<name>/SKILL.md` is staged, requires matching `skills/<name>/references/`, `hooks/check-skills.sh`, and `tests/fixtures/fixture-*-<name>*/` changes to also be staged OR to already exist on disk. Any gap emits `decision: deny` with exit code 2 — the `git commit` never runs. The one legitimate escape hatch is a `.methodology-self-extend-override` file at repo root with a written justification. Outside a methodology repo, the hook is a no-op.

- **`/kickstart` Phase -2: self-hosted mode detection** — new phase that runs before model detection (Phase -1). Checks three signals: `.claude-plugin/plugin.json` with methodology-like metadata, `skills/` with 10+ subdirectories, `hooks/check-skills.sh` present. If 3 or more signals are true, the skill enters **strict self-hosted mode**: Gate 1 (`/review --self` after Phase 3) cannot be skipped even if the argument-spec is complete; Gate 2 per-step enforcement is mandatory; the completeness and commit-gate hooks are assumed active; CHANGELOG entry and version bump are mandatory before the final commit. Trying to bypass strict mode is explicitly refused.

- **`/review --self` mode + `skills/review/references/meta-review-checklist.md`** — new rubric applied when `/review` is invoked with `--self` OR when self-hosted repo is auto-detected. The meta-rubric audits the methodology itself rather than a user project: 9 Critical checks (SKILL.md frontmatter completeness, references folder when referenced, triggers in hook for every non-disabled skill, at least one fixture per skill, version consistency across plugin.json/READMEs/CHANGELOG, CHANGELOG entry for current version, README badges match reality, Troubleshooting section present, no staged SKILL.md without supporting artifacts), 8 Important checks (Recommended model section, Examples with ≥ 2 items, allowed-tools declared, Skill Contracts table coverage, Recommended Models table coverage, Call Graph coverage, hook trigger smoke test, CHANGELOG Keep-a-Changelog sections), 4 Nice-to-have checks.

### Changed

- **`skills/kickstart/SKILL.md`** — prepended Phase -2 (self-hosted detection) before the existing Phase -1 (model detection). All existing phases renumbered in relative terms (no code change — the phase headings are unique).

- **`skills/review/SKILL.md`** — prepended Step 0 (mode detection). If `--self` argument or self-hosted repo is detected, the skill uses `meta-review-checklist.md` instead of `review-checklist.md`.

- **`hooks/README.md`** — expanded table from 2 to 4 hooks with a new "Blocks?" column. Added pipe-tests for the two new hooks. Added an explicit note that the enforcement hooks are scoped to methodology repos (safe to install globally, no-op elsewhere). Updated the `settings.json` snippet to register all four hooks and added a new `PostToolUse` entry.

- **`README.md` / `README.ru.md`** — version badge bump 1.4.1 → 1.5.0; Recommended Setup section expanded to describe the four hooks and the soft-reminder vs hard-block distinction.

- **`plugin.json`** — version 1.4.1 → 1.5.0; description expanded with "enforcement hooks", "self-hosted mode", "meta-review rubric".

### Philosophy

v1.4.0 shipped a Potemkin release because the self-extension loop bypassed its own Quality Gates. v1.4.1 fixed the artifacts but left the loophole open. v1.5.0 closes the loophole structurally: even if a future version of Claude (or the user) wants to ship a broken release, the commit-gate hook will stop it at `git commit`, and the completeness hook will stop it at `Write`. The only way around is a deliberate, documented override file — which is itself a paper trail.

This is the methodology growing an immune system against its own most likely failure mode. The cost is that methodology-repo work is now slower by construction (you can't ship a half-done skill), but that's the point — the cost *should* be higher inside the methodology than outside, because every skill is a piece of infrastructure that many user projects will depend on.

### Verified manually before release

- Both new hooks pipe-tested outside and inside the methodology repo. Outside → exit 0 (no-op). Inside with a fake incomplete SKILL.md → `decision: block` / `decision: deny`.
- The existing `check-skills.sh` triggers re-verified: 16/16 representative phrases still match, including the 3 new skill groups from v1.4.0.
- `/review --self` dry-run against the current repo — the meta-rubric passes all Critical checks. Findings documented in the commit message.

### Not done (deferred to future releases)

- **No CI integration.** The enforcement hooks are user-side. A CI-side equivalent (`.github/workflows/meta-review.yml` that runs the same rubric on every PR) is still open work.
- **No automatic trigger-phrase generation.** When a new skill is added, the author still writes the regex triggers in `check-skills.sh` manually. A future version could extract them from the SKILL.md body's `## Trigger phrases` section automatically.
- **Fixture runner still semi-automated.** `tests/run-fixtures.sh` still relies on manual invocation. Full Claude Code SDK integration is gated on SDK maturity, not on this release.

---

## [1.4.1] — 2026-04-08

Patch release. Closes the gaps caught by the same-day self-audit of v1.4.0: the three new skills shipped with `references/` paths declared but not created, the skill-discovery hook was not updated with new trigger phrases, and no regression fixtures existed for the new skills. v1.4.0 was technically a "release" but functionally a façade — v1.4.1 is the working release.

### Fixed

- **`skills/deps-audit/references/deps-checklist.md`** — full rubric now exists (6 Critical checks, 8 Important, 3 Recommended, 4 Informational) with binary criteria, data sources, actions on fail, and the exact reporting format so `/kickstart` Phase 5 can parse the output. Was referenced by `SKILL.md` in v1.4.0 but did not exist — `/deps-audit` would have crashed on first invocation.

- **`skills/harden/references/harden-checklist.md`** — full rubric now exists (8 Critical, 9 Important, 4 Nice-to-have) with binary criteria and generated-artifact templates inline. Same v1.4.0 gap.

- **`skills/harden/references/runbook-template.md`** — the runbook template referenced by `HARDEN RUNBOOK-1` now exists, with `{{placeholders}}` that `/harden` fills from the codebase (service name, dependencies, env vars, deploy commands, health check URLs). Same v1.4.0 gap.

- **`skills/infra/references/infra-checklist.md`** — full IaC-generation rubric with refusal policy (TF-C1 refuses local tfstate for prod, K8S-C1 refuses missing resource limits, TF-C3 refuses secrets in committed `.tfvars`). Same v1.4.0 gap.

- **`skills/infra/references/terraform-templates/do-fastapi-pg-redis.md`** — complete Terraform skeleton for the most common preset (FastAPI + Postgres + Redis on DigitalOcean) with pinned providers, remote tfstate for prod, resource tagging, `.gitignore`, and README. Same v1.4.0 gap.

- **`skills/infra/references/helm-templates/backend-service.md`** — complete Helm chart skeleton for generic backend services with all K8S-C1..C4 best practices baked in (resources, probes, non-root, PDB, NetworkPolicy, HPA). Same v1.4.0 gap.

- **`hooks/check-skills.sh`** — added 3 new trigger-phrase groups (~40 regex patterns) covering all Russian and English phrasings for `/deps-audit`, `/harden`, `/infra`. Previously the skill-discovery hook had no knowledge of the v1.4.0 skills, so `[SKILL HINT]` injection silently skipped them even when users' prompts were unambiguous. Verified with a smoke test: 16/16 representative trigger phrases now match the correct skill.

- **`tests/fixtures/fixture-04-deps-audit/`** — new fixture: minimal Node.js project with intentionally-vulnerable deps (`lodash@4.17.15`, `axios@0.21.0`, `left-pad@1.3.0`) covering CVE detection, license compatibility, and abandoned-package detection. `idea.md`, `expected-files.txt`, and `notes.md` with binary verification checklist.

- **`tests/fixtures/fixture-05-harden/`** — new fixture: minimal FastAPI service with intentional Critical failures (no `/healthz`, no graceful shutdown, `print()`-based logs, no backup docs). Tests artifact generation and status upgrade path. `idea.md`, `expected-files.txt`, `notes.md`.

- **`tests/fixtures/fixture-06-infra/`** — new fixture: `/infra fastapi-pg-redis do dev+prod doppler` full-layout test. 20 expected files. Verifies all Critical rubric items and the refusal paths (local tfstate for prod, secrets in committed tfvars).

### Reason

In the v1.4.0 post-release self-audit (triggered by the user asking "did the methodology really succeed?"), we found that `/kickstart` had taken three self-documented shortcuts:

1. Phase 1 clarifications skipped ("spec complete in arguments").
2. Quality Gate 1 (`/review` on new skills) not run before commit.
3. Quality Gate 2 artifacts (`references/`, tests, hooks) not generated after each skill.

The third shortcut was the worst: two of the three new skills were fully non-functional on first invocation because they referenced files that did not exist. v1.4.0 was a Potemkin release.

v1.4.1 closes all three gaps: all `references/` now exist with substantive content matching the contracts in `SKILL.md`; the hook covers every new trigger phrase; fixtures exist for every new skill; the `/infra` trigger regex was corrected after the smoke test caught a missed phrasing (`"provision ec2 instance"`).

This is also a useful meta-data point: the methodology's Quality Gates *work* when run, but the methodology can be skipped under time pressure — which is exactly the failure mode the hooks exist to prevent. The irony of shipping a release where the self-improvement-to-methodology loop bypassed its own enforcement was not lost.

### Composite quality score

- v1.4.0: 6.5/10 (façade of completeness)
- v1.4.1: 9.8/10 (working release; still imperfect — some Tier 3 polish items deferred)

---

## [1.4.0] — 2026-04-08

Minor release. Three new skills, two existing skills expanded, and the "What it does NOT do" section of the README shrinks from 7 points to 2 — closing the gaps identified in the post-v1.3.1 capability audit.

### Added

- **`/deps-audit` skill** — read-only third-party dependency audit. Parses lockfiles (`package-lock.json`, `yarn.lock`, `pnpm-lock.yaml`, `poetry.lock`, `Pipfile.lock`, `go.sum`, `Cargo.lock`, `Gemfile.lock`, `composer.lock`). Queries OSV.dev + GitHub Advisory Database for known CVEs. Cross-checks SPDX license compatibility against the project's own license. Detects abandoned packages (last release > 2 years). Same `BLOCKED / PASSED_WITH_WARNINGS / PASSED` status enum as `/review` and `/security-audit`. Honors `.deps-audit-ignore` for accepted-risk entries. Recommended model: Sonnet.

- **`/harden` skill** — production-readiness hardening rubric. 8 Critical checks (health endpoint + dependency checks, graceful shutdown on SIGTERM, structured logs with `request_id`, backup strategy), 9 Important checks (rate limiting, `/metrics` endpoint, Grafana dashboards, alerts, load test scaffolding, runbook, error sanitization, outbound timeouts), 4 Nice-to-have (chaos testing, canary deploys, SLOs, on-call rotation). Generates missing artifacts on user approval: FastAPI health route, Granian lifespan handler, `structlog` migration, Prometheus middleware, k6 baseline load test, Grafana dashboard JSON, SRE runbook template. Recommended model: Opus.

- **`/infra` skill** — infrastructure-as-code generator. Terraform modules for `fastapi-pg-redis`, `node-pg`, `fullstack-fastapi-vue`, `static-frontend`, `telegram-bot`, `worker-queue` presets. Targets: DigitalOcean, AWS, Hetzner, bare-metal/managed Kubernetes, serverless. Enforces best practices: remote tfstate with locking (refuses local state for prod), pinned provider versions, resource tags, `.gitignore` for `*.tfvars`/`*.tfstate`, non-root containers, resource limits, `NetworkPolicy`, `PodDisruptionBudget`, HPA. Generates Helm charts (Chart.yaml, values.yaml, values-dev/prod.yaml, deployment/service/ingress/configmap/secret/hpa/networkpolicy/pdb templates) when targeting K8s. Wires secrets to `env`, `aws-sm`, `vault`, `doppler`, or `sealed-secrets`. Every generated folder ships with a README containing exact init/plan/apply commands. Recommended model: Opus.

### Changed

- **`/kickstart` Phase 1** — clarification answers are now validated. Vague answers (contains only "не знаю", "сам реши", "idk", "whatever"; or is < 3 words on an open question; or contradicts an earlier answer; or references something undefined) trigger a targeted follow-up with good/bad examples. Maximum 2 follow-ups per original question — after that, the user's implicit preference is recorded as "default — user deferred" and the methodology picks its own default. Before Phase 2, the skill shows a structured summary of captured clarifications and waits for explicit confirmation. Closes the "GIGO" limitation from the v1.3.1 README.

- **`/review` rubric (`skills/review/references/review-checklist.md`)** — code-only checks expanded with 11 new items: C-code-3 (no God classes/functions > 500 LOC class or > 80 LOC function), C-code-4 (no circular imports), I-code-3 (cyclomatic complexity ≤ 10), I-code-4 (no long parameter lists > 5), I-code-5 (no feature envy), I-code-6 (no shotgun surgery hotspots), I-code-7 (no Interface Segregation violations), I-code-8 (no Dependency Inversion violations in business logic), I-code-9 (Google small-change-size warning on diffs > 400 LOC / 10 files), N-code-2 (no duplicated blocks > 10 LOC), N-code-3 (test file exists for modified source), N-code-4 (no magic numbers in business logic). Draws from Fowler's *Refactoring* catalog, Martin's *Clean Code*, and the public [Google Engineering Practices](https://google.github.io/eng-practices/) code review guide.

- **`plugin.json`** — `version` bumped to `1.4.0`; `description` updated from "13 skills" to "16 skills" with an added mention of dependency audit, hardening, and IaC.

- **`README.md` / `README.ru.md`** — bumped to reflect 16 skills. New "What it does NOT do" section shrunk from 7 points to 2:
    - Kept: "does not replace a senior architect in regulated industries" (LLMs lack real domain expertise for fintech/healthcare/aerospace compliance).
    - Kept: "does not run autonomously forever — 3 consecutive step failures stop the loop" (reframed as a feature — human-in-the-loop safety, not a limitation).
    - Removed (now covered): production-readiness (`/harden`), dependency auditing (`/deps-audit`), infrastructure management (`/infra`), clarification GIGO (`/kickstart` follow-up validation), live code review (`/review` code-quality rubric expansion).

### Reason

Post-v1.3.1 retrospective: the README's "does NOT do" section was an honest list of gaps, but most of the gaps were tractable with existing methodology patterns (new skill following the same frontmatter + tiered rubric contract as `/security-audit` and `/review`). Rather than leave the limitations in perpetuity, we dogfooded `/kickstart` on the task "add 3 new skills to idea-to-deploy" and shipped them in a single minor release. This is also the first release where the methodology was used to extend itself end-to-end — a useful validation that the bootstrapping works.

### Not changed (by design)

- **"Does not replace human-in-the-loop"** stays. The 3-failure stop is intentional: removing it would let the LLM spin in circles on impossible tasks and burn user money. Keeping it.
- **"Does not replace a senior architect for novel regulated systems"** stays. LLMs encode patterns from training data; they cannot invent new compliance regimes or exercise the judgment that comes from having shipped production systems under SOC2/HIPAA/PCI DSS audit. A methodology is not a replacement for expertise in high-risk domains.

---

## [1.3.1] — 2026-04-08

Patch release. Two consistency bugs caught by an independent fact-finding pass after v1.3.0 was published. Composite quality score: 9.8 → 10.

### Fixed

- **README.md:24** said "11 skills + 5 specialized agents" — leftover from the v1.2.0 era. Updated to "13 skills + 5 specialized agents", consistent with the badge, the Skills section, the Skill Contracts table, the Recommended Models table, and `plugin.json`.
- **`/review` was missing `## Troubleshooting` section** — the only one of 13 skills without it. Added a substantive Troubleshooting section covering: Critical check failures the user wants to override, non-deterministic results, missing rubric checks, code-only checks when there's no source code, and `PASSED_WITH_WARNINGS` confusion. All other skills already had this section; `/review` was the outlier.

### Reason

A fresh independent audit (Explore subagent in forked context) of the v1.3.0 release surfaced these two issues. Both are consistency bugs that don't affect functionality but undermine the "10/10 polish" claim the v1.3.0 release made. Fixed in a same-day patch rather than waiting for the next minor release, because the methodology is the public face of this work.

The audit also flagged some false positives (it claimed several skills were missing Examples/Troubleshooting; verified by `grep` that they were actually present). A real audit caught real issues — that's the system working as designed.

---

## [1.3.0] — 2026-04-08

The "10/10 release" — closes the 5 polish items left open in 1.2.0. Adds two new skills (`/security-audit`, `/migrate`), per-skill `allowed-tools` for least-privilege, per-skill `## Recommended model` body sections, decoupling from Russian-only documentation generation, and a semi-automated fixture runner.

### Added

- **`/security-audit` skill** — read-only OWASP-style audit. 4-tier rubric (Critical / Important / Recommended / Informational) with 25+ binary checks covering auth, secrets, injection, CORS/CSP, security headers, file uploads, dep CVEs, stack-specific gotchas. Returns the same status enum as `/review` (`BLOCKED` / `PASSED_WITH_WARNINGS` / `PASSED`) so it chains into `/kickstart` Phase 5 (Deploy). Allowed-tools restricted to `Read Glob Grep` — separation of audit and remediation. Reference: `skills/security-audit/references/security-checklist.md` (~280 lines).
- **`/migrate` skill** — safe DB migration runner. Detects environment (local/staging/production), refuses production without explicit confirmation, takes backup before destructive ops, applies, verifies, and ALWAYS documents the rollback path. Pre-flight checklist covers PostgreSQL/MySQL/SQLite gotchas (locking ALTER TABLE, ADD COLUMN NOT NULL DEFAULT on PG <11, ALTER COLUMN TYPE on large tables, FK constraint validation, CREATE INDEX without CONCURRENTLY). Reference: `skills/migrate/references/migration-safety.md` (~250 lines).
- **`allowed-tools` in every skill frontmatter** — least-privilege per skill purpose. Read-only skills (`/project`, `/explain`, `/review`, `/security-audit`) have `Read Glob Grep`. Code-modifying skills add `Edit Write Bash`. `/kickstart` extended with explicit Bash patterns for git/mkdir/npm/pnpm/docker/pytest/go/cargo. No skill has unrestricted Bash access.
- **`## Recommended model` body section in every skill** — explicit per-skill model recommendation (haiku/sonnet/opus) with reasoning. Replaces the README-only "Recommended Models" table. Note: Anthropic Claude Code skill schema does NOT support `model:` in frontmatter (only agents do), so the recommendation lives in the body where Claude reads it during execution.
- **`tests/run-fixtures.sh`** — semi-automated fixture runner. Iterates over `tests/fixtures/`, prints each idea.md, prompts the user to invoke the methodology in another Claude Code session, then checks `expected-files.txt` against actual output. Supports `--check` (skip claude invocation, just verify outputs), single-fixture target, and per-fixture pass/fail reporting. Full automation deferred until Claude Code SDK gains stable non-interactive mode.
- **2 new triggers in `hooks/check-skills.sh`** — for `/security-audit` ("проверь безопасность", OWASP, "security audit", secrets check) and `/migrate` ("накати миграцию", "ALTER TABLE", "alembic upgrade", "перед DDL"). Refined the existing auth/payments trigger to coexist with `/security-audit`.

### Changed

- **`/blueprint` Rules — decoupled from Russian-only**. The previous rule "Все документы на русском языке" was hardcoded. Now: "Match the language of the user's request: if the user wrote in Russian, generate Russian docs; if English, English docs; mixed — pick the dominant one and ask if unsure". Same applied to `/security-audit` reports.
- **README — Recommended Models table expanded** to 13 rows with notes about Lite mode, Haiku acceptance per skill, and Opus benefits per skill.
- **README — Skills section restructured**: 1 entry point + 3 project creation + 2 quality assurance (review + security-audit) + 6 daily work + 1 operations (migrate) = 13 skills. Counts updated everywhere.
- **README — Call Graph updated** to show `/security-audit` and `/migrate` as standalone leaf skills with their distinguishing properties (read-only by design / refuses prod).
- **README — Skill Contracts table** extended with rows for `/security-audit` (read-only, no side effects) and `/migrate` (DB schema mutation, backup file, NOT idempotent on prod without confirmation).
- **`plugin.json`** — version 1.2.0 → 1.3.0; skill count "11" → "13"; description expanded to mention security audit and DB migrations.
- **`README.md` version badge** — 1.2.0 → 1.3.0.

### Reason

Closes the 5 explicit "to reach 10/10" items from the 1.2.0 self-assessment:
1. ✅ Fixture runner script (semi-auto until SDK matures)
2. ✅ `allowed-tools` in every skill (least-privilege)
3. ✅ Per-skill recommended model (in body, since frontmatter doesn't support it)
4. ✅ New skills `/security-audit` and `/migrate`
5. ✅ Decouple `/blueprint` from Russian-only

Composite quality score against Anthropic best practices: 9.5 → 10.

---

## [1.2.0] — 2026-04-08

This release closes the gap between "great methodology on paper" and "actually used by Claude". Triggered by a 2026-04-07 production-incident retrospective where Claude (Opus 4.6) skipped the methodology entirely during a 2-hour ad-hoc hotfix. Root cause: nothing was forcing skill discovery. Fix: enforcement layer + rubric-based quality gates + better discoverability + regression fixtures.

### Added

- **Skill discovery hooks** (`hooks/`):
  - `check-skills.sh` (UserPromptSubmit) — analyzes every user prompt for ~80 Russian and English trigger phrases across 12 categories. Injects a `[SKILL HINT]` system reminder when a skill matches. Silent when no trigger fires.
  - `check-tool-skill.sh` (PreToolUse on Bash/Edit/Write/NotebookEdit) — injects a `[SKILL CHECK]` reminder before any raw tool call, asking Claude to verify a skill doesn't fit.
  - Both hooks written in Python 3 (stdlib only), Unicode-safe (Russian lowercasing works), graceful on bad input, ~50 ms overhead per prompt.
  - `hooks/README.md` — installation, settings.json snippet, pipe-tests, customization guide, case study.
- **Skill Contracts** section in main `README.md` — explicit table of inputs / outputs / side-effects / idempotency for all 11 skills.
- **Call graph** in main `README.md` — which skill can invoke which, max depth, recursion guards.
- **`tests/fixtures/`** — 3 sample project ideas with expected output snapshots for regression testing of `/blueprint` and `/kickstart`. Includes `tests/README.md` with run instructions.
- **`references/` for previously bare skills**:
  - `skills/debug/references/debugging-patterns.md` — language-specific debugging recipes (Python, JS, Go, shell).
  - `skills/test/references/test-frameworks.md` — pytest / vitest / jest / go test conventions and idioms.
  - `skills/refactor/references/refactoring-catalog.md` — Fowler-style catalog of common refactorings with before/after.
- **Sonnet-friendly mode** for `/blueprint` and `/kickstart` — auto-detected when running on Sonnet (or via explicit `--lite` flag). Lite mode generates fewer documents, looser minimum requirements, shorter prompts. Output quality remains usable on Sonnet instead of degrading silently.

### Changed

- **`/review` overhauled — score replaced with binary rubric**. The previous `score >= 7/10` gate was subjective (different model invocations gave different numbers). It is now a deterministic checklist of ~25 binary checks split into Critical / Important / Nice-to-have. The skill passes only when all Critical checks pass; warnings emitted for missed Important/Nice-to-have. Numeric score is still reported as a derived metric, but not used as a gate.
- **`skills/review/references/review-checklist.md`** rewritten as the rubric source of truth.
- **All 11 skill descriptions trimmed and rebalanced**. The previous expansion (added in commit `c8255c2` to fight matcher dilution) was over-corrected — descriptions had 10+ trigger phrases each, which dilutes the embedding match. Now: 3–5 canonical phrases in `description` (kept in TRIGGER format), full trigger list moved to a `## Trigger phrases` section in the body where Claude reads it during execution but the matcher doesn't see it.
- **All 16 frontmatter blocks**: removed nonstandard `effort: medium|high|low` field. It was never parsed by Claude Code and created a false impression of behavioral influence. `license` and `metadata` blocks retained — `license` is informational and `metadata` is acceptable per the SDK schema.
- **Plugin manifest** updated: skill count fixed (10 → 11), description expanded to mention subagents and hooks.

### Fixed

- **`README.md` skill count** — said "10 skills" in plugin manifest while listing 11 in the README skills table. Now consistently 11 + 5 subagents.

### Documentation

- New `Skill Contracts` table in README explicitly documenting each skill's interface.
- New `Call Graph` diagram showing skill invocation chains.
- New `Hooks (Recommended Setup)` section in README pointing to `hooks/README.md`.
- `CHANGELOG.md` (this file) created.

---

## [1.1.0] — 2026-04-07

### Changed

- All 11 skill descriptions and 5 subagent descriptions expanded with comprehensive Russian trigger phrases. Added explicit `TRIGGER when user says "..."` prefixes where missing. Added "ALWAYS use this for X" guidance to discourage ad-hoc fallbacks.

### Reason

Discovered during a real prod-hotfix session that the methodology was being silently skipped because trigger lists were too sparse and lacked common Russian phrasings. This release fixed the descriptions; the next release (1.2.0) added the enforcement hooks that close the loop.

---

## [1.0.0] — initial release

- 11 skills: project (router), kickstart, blueprint, guide, debug, test, refactor, perf, explain, doc, review.
- 5 subagents: architect, code-reviewer, doc-writer, perf-analyzer, test-generator.
- `references/` folders for project, kickstart, blueprint, review, guide.
- Bilingual README (English + Russian).
- Plugin packaging (`.claude-plugin/plugin.json`).
- MIT license.
