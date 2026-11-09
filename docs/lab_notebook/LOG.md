# LOG — <project>

Append-only. Newest at the top. One entry per unit of work (a PR, a campaign phase, a loop run, a decision).
Never edit or delete past entries; if one was wrong, add a new entry that says so.

Entry format (keep it to 3–8 lines):

```
## YYYY-MM-DD · <who> · <feat|fix|decision|loop-run|verify|revert> · <one-line title>
- What: <what changed / what was decided>
- Why: <the reason, in one line>
- Verified: <RAN/PASSED/CORRECT summary, or "not verified — why">
- Result: <kept | discarded | partial> · <link: PR #, commit, evidence path>
```

---

## 2026-11-08 · viz-simple · feat · process_viz: plain-English version + chapter 00 "The system"
- What: holo-neurochir/demo_live/process_viz/src_simple.html + build_simple.py -> holo-process-viz-simple.html (same 3D/animation, only displayed texts rewritten in plain English: floors, urge, checker, big brother; all numbers kept). New first chapter "00 · System" (inline SVG architecture diagram) added to both src.html and src_simple.html; consequences: CH[5]->CH[6] for the diagnosis cloud mix, Digit[1-9], NAMES.
- Why: Martin (via ares) asked for a non-specialist version and an architecture overview before the brain.
- Verified: Playwright + swiftshader screenshots of every chapter and of the details panels, no page errors; two fresh-context reviews (numbers, code integrity, overclaims); their fixes applied (Holo4 = replay only, Guard arm only, signed urge labels). Diagram facts (369 tasks, 1,271 episodes, ~30,700 steps, runners, GPUs, Devin monitor) taken as given by ares, not re-derived.
- Result: kept · published as argos artifacts holo-process-viz-simple.html and holo-process-viz.html

## 2026-11-03 — Recherche + vidéo computer use
- Deep research (5 axes) → reports/Computer use agents état de l art.md
- Vidéo narrée (voix Martin, 7,6 min) → video/computer-use-agents.html, publiée via argos artifact

## 2026-11-03 — Vidéo computer use, voix Andre
- Narration refaite en ElevenLabs v4 Andre via Higgsfield (76 phrases, ~70 crédits), v01 sans « c'est Martin ». narration-andre.json, audio-andre/, computer-use-agents-andre.html. build.py prend la narration en argument.
- 2026-11-04 : page « Toutes les idées » (12 idées du brainstorm + 10 opportunités + primitives H + comment gagner), reports/idees-hackathon.html, publiée par argos artifact.
- 2026-11-04 : ajout de 10 idées « frontier » (F1-F10) en tête de reports/idees-hackathon.html, republiée.
- 2026-11-04 : recherche « Problèmes frontier de H » (4 search-workers : retours utilisateurs, problèmes déclarés par H, mesures tierces, Gladia/Devin) → reports/problemes-frontier-h.html (8 problèmes, reco P1+P2), vérifiée contre les notes par un agent séparé (6 corrections appliquées), publiée.
- 2026-11-07 : pack de contexte complet (synthèse + problèmes frontier + toutes les idées + rapport état de l'art + toutes les notes brutes + script vidéo, ~364 k caractères) → reports/pack/ (build.mjs, pack-contexte.md/.html), publié en artifact claude.ai https://claude.ai/artifact/4pBuLKrCY1GE86siFrjFbh, bouton « Copier tout en Markdown ».

## 2026-11-07 · astra-08b · verify · Weight-space loop surgery pilot
- What: Isolated experiment in pod /workspace/astra, tmux astra; 22 candidate edits, identity and global-direction diagnostic, frozen patch and random controls; REPORT.md and independent VERIFY.md written.
- Why: Test whether a loop-associated residual direction can be removed by direct weight edits, without gradients or training.
- Verified: 27/50 replay batches counted including one failed batch; training-only L10 AUROC 0.904202; independent CPU audit passed hashes, selection, numerical results and replay regression. No candidate met the prespecified efficacy threshold.
- Result: Partial — /workspace/astra/REPORT.md. Final seed 6–7 comparison NOT RUN: no such rollouts present in diag, local copy or the old 0.8B archive. Candidate remains frozen; user asked for their location. Shared pod code/data and other tmux sessions untouched.

## 2026-11-07 — Astra Round 2 (pod, weight-space screening)

- What: 18 additional patch screens, full saved development comparison (415 steps), frozen patch and three-arm seeds 6–7 evaluation (48 rollouts, 142 steps), all under /workspace/astra on the pod.
- Why: test selective suppression of repeated actions without gradients; complete the reserved evaluation.
- Verified: independent CPU artifact audit; budget 50/50; immutable freeze before reserved data; targeted 1,966,080 weights; own GPU process exited. Final log-prob/token means (loop+, healthy): original (-0.07198938, -0.11248348), patch (-0.07429665, -0.12140671), random (-0.07328731, -0.11667309).
- Result: no selective patch validated; screening ratio 4.17 did not generalize (full-dev worst-healthy ratio 0.358, heldout 0.223). Pod REPORT.md Round 2 and VERIFY_ROUND2.md contain evidence. Initial git pull --rebase blocked by existing dirty changes, left intact; no local code changes or commits.

## 2026-11-07 — Astra Round 3 (behavioral causal screening)

- What: Real sampled replay generations (four per context, T=0.8), residual/MLP paired directions and centered PCA, all-layer steering, stronger/negative coefficients, random and identity controls; isolated pod /workspace/astra/r3.
- Why: Test causal suppression of repeated actions before editing weights, replacing teacher-forced log-prob screening.
- Verified: Independent raw-output audit, 1,224 saved generations, 23/40 charged batches. Baseline REPEAT 46/48 and HEALTH 36/48; best complete learned arm REPEAT 39/48 and HEALTH 28/48 fails both criteria. Nine candidates rejected by rigorous HEALTH upper bounds; two degenerate variants interrupted without full scores. Own GPU process exited, peak reserved 6.018 GiB. Final report SHA256 3fa27d1743e2e5e4ada57ceee131deb7d4f9c799d1c28bdec421ef86bbbeffaf.
- Result: No admissible causal intervention found; patch_spec null, zero weights changed. Compilation, heldout6–7 and online50–51 NOT RUN because causal gate failed. Pod REPORT.md Round3 and r3/VERIFY.md finalized. Existing local dirty changes left intact; initial pull blocked, no code commit.

## 2026-11-07 · astra-4b · experiment-preparation · False-success behavioral tooling
- What: Isolated pod /workspace/astra/4b, tmux astra4b, REPORT_4B.md; exact diagnostic replay preparation, sparse activation mapping, structured-thinking generation, conditional tool-token probe and budget ledger. No weights edited and no test split read.
- Why: Require generated behavior before any 4B weight surgery; avoid repeating 0.8B marker-versus-cause mistake.
- Verified: Independent CPU checks on 239 rows/57 tasks (fs+15, fs-42, healthy182), grammar/sampling, sparse mapping and aggregation. Corrected inherited production top_k20 with regression checks; 192-case real trim-function proof reinstates parse-error trajectories. Old synthetic aggregation fixture remains superseded/failing after seed-contract extension; new 8-case shard tests pass, no weakened check.
- Result: Partial, data threshold unmet and latency-limited. Budget4/60 (one wrong-top_k abort, one external latency pause counted). Original first false-success context answer4/4; resumed remaining20 samples, no causal conclusion/AUROC/patch. Production and shared source files untouched; initial pull blocked by pre-existing dirty changes.

## 2026-11-07 · astra-4b-x · resume/verify · Original 4B behavioral reference recovered
- What: Inherited lot4 and finish_report waiter finished naturally; recovered all20 resumed outputs plus4 preserved outputs. Corrected isolated direction preparation and paired metrics; installed checked runner only after both processes exited.
- Why: Establish an auditable behavioral reference before causal weight surgery, retaining top_k20, fixed labels, exact replay proof and production latency guard.
- Verified: Independent raw audit of24 outputs / six contexts / five tasks: fs+ answer8/8, fs- answer8/8, healthy valid non-answer8/8, invalid/truncated0. Preparation/metrics37 checks and runner19 new mocked checks plus existing CPU suite passed; no CUDA initialized by checks. All four reserved jobs' task exposures are covered by the pilot probe.
- Result: Partial mission — reference complete, budget4/60, own GPU idle. Local15/shared16 fs+ remain below40; no official AUROC, causal steering, edited weights or online improvement. Pod REPORT_4B.md and 4b/VERIFY_{RESUME,RUNNER_RESUME,PILOT_RESUME}.md preserve evidence and remaining confirmation/compilation requirements. Initial pull blocked by pre-existing changes; unrelated work left intact.

## 2026-11-07 18:55 UTC — daedalus : slide « banc de neurochirurgie » (skill Anatomy)
- Figure interactive isométrique (skill wheresryan22/anatomy) : baie de 32 tiroirs = couches du Holo-3.1-4B ; tiroir L15 ouvert, 70 aiguilles = vrais neurones de mlp.down_proj (poids lus sur HF par range request), règle = direction, portique = orthogonalisation.
- Données réelles : direction faux succès = exploratoire Astra fold 0 (pod /workspace/astra/4b, lecture seule, aucune AUROC calculée) ; 13/9216 neurones |cos| > 0,1 vs 0 pour une direction aléatoire ; la coupe retire 0,05 % de l'énergie d'écriture. Effet comportemental : « en mesure » (après la coupe : à remplir dans needles.json behaviour.after_cut).
- Fichiers : holo-neurochir/demo_banc/ (build.mjs à lancer depuis examples/banc d'un clone d'anatomy). Pages publiées : argos artifacts banc-neurochirurgie(.html / -clair.html).

## 2026-11-07 · astra-4b-x · provisional C interrupted by production guard
- What: Trained provisional matched directions on20 fs+/50 fs- with all five pilot tasks excluded (14 matched pairs); launched lot5 negative addition atL16. STOP_GPU interrupted the first fs- sample after8 healthy outputs; process exited naturally and released GPU. Raw output and log hashes preserved in the explicit aborted marker.
- Why: Test generated behavior out of task before weights; preserve exact work across external latency pauses without dropping, duplicating or selecting samples.
- Verified: All8 saved outputs valid non-answer,0 invalid/truncated; no complete terminal output. Independent pilot CPU tests17 plus prior19 passed; staged round2 hooks passed48 CPU tests after validation fixes. CPU numerical writer equivalence does not establish behavioral equivalence. Audit resolves all budget manifests and identifies45 diagnostic tasks untouched by either evaluation or direction construction.
- Result: Partial, budget5/60; no efficacy result, no official AUROC, no patch or online gain. STOP flag belongs to ares; no automatic relaunch. Exact resume and generic interruption finalization are staged for independent checks. Unrelated shared edits preserved.

## 2026-11-07 19:30 UTC · online-eval · validation en ligne d'un 4B patché, prête (aucune VM lancée)
- What: scripts/make_patched_ckpt.py (spec surgery ou steering compilé → checkpoint servable : snapshot HF d'origine, seuls les shards édités réécrits), scripts/check_ckpt_equiv.py, osworld/serve_patched.sh (pod :8011, car le :8001 du pod est le nginx Runpod), tmux orbit osw_tunnel2 (orbit 8001 → pod 8011), osworld/make_val_tasks.py → val_fs_tasks.json (33) + val_ok_tasks.json (15), osworld/run_patched_eval.sh, osworld/compare_val.py, osworld/probe_served.py, runbook osworld/ONLINE_EVAL.md.
- Verified: patch nul (alpha=0, 6 tenseurs réécrits) : 0/724 tenseurs différents, 3 prompts × (glouton, seed 0) identiques en HF. Servi par vLLM : 8001 stable et égal à la sortie HF ; la prod 8000 sous charge donne 2 réponses distinctes sur 4 appels identiques à T=0 (non-déterminisme de batch). Contrôle positif (alpha=1, L16, top-256) : exactement 1 tenseur différent. Relecture indépendante (verifier) : statistiques et preflight corrects.
- Result: serveur de test arrêté (demande d'ares). Les listes de tâches sont à régénérer quand results_diag2 aura fini. Les tâches fs sont celles du diag, d'où viennent les directions : la validation est in-sample.

## 2026-11-07 19:40 UTC · demo-osw · le dashboard IRM rejoue des épisodes OSWorld du 4B
- What: holo/osw_demo.py (épisode + acts + direction → demo JSON), options --only/--exclude dans holo.direction, S.DEMO_DIR = dashboard/demo, server/index adaptés (bras opéré absent, JPEG, verdict, note/thought). 5 démos (3 faux succès, 2 succès) dans dashboard/demo/.
- Verified: Playwright sur devcap :3141 : 5/5 replays terminés, 0 erreur console ; clic dessiné au bon endroit. Verifier indépendant : jauges recalculées depuis les npz (écart 0,0), images, coordonnées, verdicts et séquence WebSocket OK ; corrigé ensuite : header live sans has_patched, CRLF de direction.py restauré. Non testé : mode live, démos MiniWoB.
- Result: direction PROVISOIRE (L30 resid_post, AUROC CV 0,836 < baselines 0,870/0,880) ; jauge juste au pas answer sur 3/5 démos. Fichiers non commités (fichiers partagés avec des modifs d'autres sessions).

## 2026-11-07 · astra-4b-x · exact STOP resume and common confirmation reserve
- What: Added finalized STOP-shard provenance, exact pending-seed resume, protection-denominator carryover and generic interruption markers, including charged zero-output shards. Integrated previously checked multi-layer/writer hooks; resumed the unchanged L16 candidate manually as lot6 after ares latency7.9s/step and current flag absence.
- Why: Preserve every completed sample across external scheduling interruptions and prevent accidental cohort/intervention mixing. Canonical45-task confirmation pool from ares now excludes all prior construction and pilot tasks across passes.
- Verified: Independent105/105 CPU tests (20 new STOP-resume regressions plus85 existing), CPU1/CUDA uninitialized. Real dry audit preserves exactly8 healthy samples and16 pending. Installed runner SHA24eb845454aba5048e5af768d5a28c231782232ebc40925a26e19b3bdc9314bd. Canonical tasks-map SHA03726f07b411869a7a4004b0f3c89ba37d89e948f34ac19cb70e4bb0c3cb5bb7 verified against immutable train70/held5 metadata. Reports on pod VERIFY_STOP_RESUME_CPU.md and stop_resume_cpu_evidence.json.
- Result: Budget6/60; candidate still running, no completed fs+ efficacy measurement or weight edits. Manual refresh_status.py parses raw records strictly and exposes partial progress without admitting partial efficacy. Production and other GPU processes untouched.

## 2026-11-07 · astra-4b-x · L16 causal result rejected
- What: Completed the same L16 negative-addition candidate across preserved lot5 and resumed lot6; launched predeclared L24 as lot7 after current guard/resource review.
- Why: Evaluate actual generated tools on paired seeds while preserving all outputs across external STOP.
- Verified: Independent audit reparsed all48 baseline/candidate outputs with strict Step and recorded schema. Candidate: fs+ answer8/8, fs- answer8/8, healthy valid non-answer8/8, invalid/truncated0/24. All protections pass; both efficacy gates fail; no protected Pareto improvement. Evidence on pod VERIFY_L16_RESULT.md and pilot_c1_add_l16_independent_audit.json.
- Result: Scientific negative for this candidate, budget7/60; round1 still includes L24 and L28. Shared32 positives/go_fs=false; no official AUROC, weight patch or online gain. Current HF cache has exactly one pre-lot snapshot8c88265a5a159bfd1492db9243733dd2e6e04a6e; retrospective per-lot cryptographic identity was not recorded.

## 2026-11-07 · astra-4b-x · round1 negative, verified identity/reserve, bounded dose amendment
- What: Lot7 L24 completed naturally and independently failed efficacy, matching the earlier L16 binary results. Installed the independently checked identity/reserve/control runner after the GPU lock released. Lot8 multi-layer addition16/24/28 acquired fleet slot1 at20:27 UTC.
- Why: Preserve actual behavioral evidence, prevent confirmation leakage/model drift, and add ares-requested dose/random controls without exceeding12 candidates/19 exploratory ledger entries.
- Verified: Each completed candidate has fs+ answer8/8, fs- answer8/8, healthy valid non-answer8/8, invalid/truncated0/24; each paired48-output strict/schema audit passes. CPU138/138 and installed import smoke pass without CUDA. Two-hop HF cache topology defect fixed with a regression; metadata/version/link IDs/sizes attested, no tensor-content rehash. Canonical45 reserve retained even when44 IDs are absent from manifest. Fixed Gaussian control draw is reconstructed and checked before reservation.
- Result: No causal admission, weight patch or online gain. Round1 has no protected Pareto progress; round2 active within the pre-recorded dose amendment. Shared32 positives/go_fs=false, current local snapshot22 positives. Reports/provenance on pod REPORT_4B.md, VERIFY_L24_RESULT.md, VERIFY_IDENTITY_CPU.md and identity_install.json. Shared unrelated edits untouched; no commit/push from this unit.

## 2026-11-07 20:35 UTC · online-eval · validation hors échantillon, formats lm_head, test vLLM délié
- What: val_confirm_tasks.json = les 45 tâches figées de confirm_tasks.json (sha256 vérifié), avec un tag par tâche : fs 11 / ok 13 / other 21, et half sur sha1("domain/example_id"), 19 impaires. val_fs_insample_tasks.json reste un diagnostic secondaire. compare_val : --origin stuck|other obligatoire ; métriques succès, FS, pas moyens et part à 50 pas, appariées avec IC95. make_patched_ckpt : kind=lm_head (lignes += alpha*delta, checkpoint délié). check_ckpt_equiv : --device cpu --no_generate. probe_served --ref.
- Why: ares exige une validation hors échantillon, un levier global « moins pressé de dire fini » (astra-eager) et la règle de la moitié stuck (FLEET_ORDERS.md).
- Verified: lm_head nul : 0 tenseur différent et logits identiques (Δ 0,0) sur CPU ; servi par vLLM 0.23 sur :8011, 3/3 réponses identiques aux sorties de référence vLLM du checkpoint nul lié, sur deux passes. Contrôle positif : seule la ligne 8944 (« answer ») diffère, seul le logit 8944 bouge (+9,44). Serveur coupé ensuite.
- Result: la prod 8000 était bloquée de 19:34 à 20:30 UTC ; signalé, ares l'a relancée (chien de garde vllm_watchdog). Une édition de ligne lm_head agit à toutes les positions, pas seulement au nom d'outil. Une soustraction de vecteur constant n'est pas compilable en poids.

## 2026-11-07 20:43 UTC · astra-think · generated-thinking pilot, preempted and resumable
- What: Captured 16 original autoregressive reflections across all 32 residual layers on four construction tasks. Half-strength L31 addition completed 24 outputs on disjoint tasks: fs+ answer 8/8, fs- answer 8/8, healthy valid non-answer 8/8, invalid/truncated 0/24, identical binary rates to baseline. Full-strength addition was preempted by ares after six valid healthy outputs; seventh output unobserved, fs+/fs- not reached. Projections remain unrun.
- Why: Require generated behavioral change before weight editing and preserve partial evidence. Direction AUROC 1.0 is non-probative because context length and a lexical baseline also achieve 1.0 here. Explicit conclusion tokens do not establish internal decision time.
- Verified: Independent capture/direction/24-output audits; nine real CPU process tests reproduce the old orphan and validate the parent-death fix. R31=50.02117300961911 independently reproduced; random vector bit-exact. All 19 registered requests accepted, 82 mutations rejected without reservation. Exact resume preserves six keys and leaves 18; budget 5+1+2+12=20 maximum. No owned GPU process or tmux remains.
- Result: PAUSED by fleet preemption, 5/20 lots consumed, no admitted candidate, gradients, training, weight edits or test-split reads. Prepared jobs require PRIORITY readmission and verified shard aggregation. Pod: /workspace/astra/astra-think/REPORT.md, resume_plan.json, VERIFY_PARENT_DEATH.md, VERIFY_DOSE_PLAN.md. Local report: /tmp/astra-think/REPORT.md. Initial pull blocked by pre-existing dirty changes; unrelated edits preserved, no commit/push from this remote experiment unit.

## 2026-11-07 21:00 UTC · astra-4b-x · fleet preemption and partial behavioral audit
- What: Ares externally terminated lot8 multi-layer negative addition after22/24 complete outputs and removed4b from PRIORITY. The inherited original lot4 had already finished naturally. Preserved every raw byte; owned GPU PIDs191930/191418 are absent. Runtime status and pod REPORT_4B.md now say PAUSED, budget8/60.
- Why: Preserve valid partial evidence without inventing missing outcomes or mistaking an interrupted round for the two-round stop rule. Native SIGTERM bypassed the old runner exception path; honest finalization/resume support is staged separately for CPU verification.
- Verified: Independent46-record baseline/partial strict schema and boundary audit, candidate/model/reserve provenance, raw/log stability and process absence. Healthy8/8 valid nonanswers, fs-8/8 answers, fs+6/6 observed answers out of8planned, all six success claims;0invalid/22observed. Missing only second fs+ context seeds4002/4003. Even both missing nonanswers permit at most25%relative reduction, below required50%; full Pareto NOT COMPUTED. Evidence VERIFY_MULTI_EXTERNAL_INTERRUPTION.md and candidate partial/audit JSONs on pod.
- Result: No candidate admission, weights, patch or online gain. Writer projection and higher-dose/random controls remain NOT RUN. No automatic restart; ares owns fleet readmission. Raw SHAa87f6da4b8883fedc60e57b15ff102207921c98b62e4cb4fe9ba44965b07f924. Shared unrelated edits untouched; no commit/push from this unit.

## 2026-11-07 21:16 UTC · astra-4b-x · verified native interruption recovery and paused checkpoint
- What: Sealed lot8 external interruption at21:10:30 without altering raw/budget; installed signal-safe runner at21:13 under owned GPU lock. Added explicit launcher-parent identity before heavy imports, parent-death handling, deferred SIGTERM across nested/multithread record and budget commits, and strict external-evidence validation. Prepared optional exact22-retained/2-missing job, never launched. Updated pod PROTOCOL/REPORT and archived PREEMPTION_CHECKPOINT.json.
- Why: Native SIGTERM bypassed old Python exception handling. Reproductions also exposed malformed-evidence acceptance, early-import orphaning and a pthread-mask-only race with worker delivery; fixes address those causes without relaxing tests or scientific criteria.
- Verified:167/167 independent CPU checks (138 unchanged+29 focused), CUDA uninitialized. Actual installed-path import/resume smoke passes with22retained keys and only seeds4002/4003 missing, zero generation calls, budget unchanged. Independent final-report review found no substantive issue. At21:15 no owned GPU process or tmux child remained. Runner SHAb5131a2f9f7742c5893c6fb07249698dc1a64272c3a8087d0f71d339e5c6d04d; marker SHA791fc98f609c547a1cf783832081f9ab6975b1d85be3f448ad3b51a6ea6466c9. Signal timing on an actual CUDA model was not tested.
- Result: PAUSED by fleet;8/60 lots charged, no admission/weights/patch/online gain. Projectionwriters and larger-dose/random arms remain NOT RUN; the two-round stop rule has not been claimed satisfied. Shared status38 fs+/107 fs-, go_fs=false; fixed local snapshot22 positives. No automatic relaunch or scientific reason to spend another lot merely completing the already inadmissible partial candidate. Ares informed of checkpoint and required ASTRA_EXPECTED_PARENT_PID launch contract. No shared code reset/stash or commit/push.

## 2026-11-07 23:25 UTC · gh-runner2 · OSWorld on GitHub Actions
- Public repo martinbon39/holo-osworld-runner (workflow_dispatch osworld.yml, one VM per job, SSH tunnel to the pod via secrets). Pilot 1 job + pilot 3 parallel jobs: all result.txt present, setup 268-350 s per job.
- Test split (120 tasks) launched 23:21 UTC on ares's go: orig 42424827401, expo125 42424833725, prompt 42424839721 (6 jobs each). Collector puts results in ~/osw/results_test_gh_<arm>/. holo-neurochir/osworld/gh_collect.sh committed (6155361).

## 2026-11-08 00:09 UTC · astra-mit2 · conditional MLP verification circuit, interim
- What: Implemented real fixed two-neuron SwiGLU detector/writer edits (15,360 targeted weights each), six semantic-writer arms and one final-layer Wait/end arm. Own immutable runner, data manifest, budget ledger, specs and reports live on the pod in /workspace/astra/astra-mit2/.
- Why: Test a separate conditional verification path, without gradients or training, rather than assume that suppressing answer is useful. Final nine heldout task contents remain unread; canonical confirmation data and split_test.json were not opened.
- Verified: Independent reviews reject all seven weight arms after five observed fs+ outputs apiece; those are repeated paired positions on two screen tasks, not35 independent examples. No useful action; all protected outputs unobserved. Lexical arm emits one Wait in5/5 versus0/5 paired baseline, with no later pulse above5% alpha; Budget briefly recognizes the real date mismatch then retracts it and falsely finishes. Capture/cache fidelity and final-MLP cache isolation were independently checked.
- Result: No admitted candidate or online claim. Lot11 was charged despite zero forwards: a diagnostic-only raw generation_config.use_cache assertion was wrong (None resolves to True in installed Transformers). Failed artifacts are preserved; revised read-only pre/post cache-growth checks passed independent source/contract review. Lot12 is the restarted input-modified capacity diagnostic, not a weight-edit result. Budget12/40 reserved, research ongoing. Shared unrelated files/index untouched; no commit/push from this interim unit.

## 2026-11-08 00:10 UTC · astra-short · pilote de promotion globale de </think>
- What: Espace isolé pod `/workspace/astra/astra-short`, panel figé28 contextes/6 domaines (fs+5, fs−5, intermédiaires18),9 tâches locales hors construction ; une ligne de lm_head déliée (token248069), moyenne de356 états originaux. Protocole et grille12/16/20/24 enregistrés avant résultats du panel complet, après analyse CPU des marges.
- Why: Tester le raccourcissement global sans l'édition Wait de mit1, en mesurant la pertinence des actions plutôt que la seule validité du JSON.
- Verified: Deux lectures indépendantes couvrent tout le journal/papier et les rapports demandés. Audit runner et chemin lm_head PASSED ; prétraitement28/28 avec15 longueurs héritées exactes. Rubriques visuelles indépendantes28/28. Pilotes original et dose8 :12/12 sorties token-identiques, JSON12/12, mean think127 ;3 textes préservés. Budget3/25 réservé avec référence complète en cours.
- Result: Aucun candidat ; résultat nul du pilote8. Rapport vivant sur le pod `REPORT.md`. Aucun split test/confirm ouvert, aucun serveur partagé touché. Pull bloqué par changements préexistants ; fetch établit HEAD=origin/main, fichiers partagés préservés.

## 2026-11-08 00:15 UTC · astra-free · memory dynamics diagnostic closed
- What: Isolated work in /workspace/astra/astra-free; frozen development/heldout cohorts and 25-lot ledger. Tested original and slowed late DeltaNet decode memory, then stopped full freezing after first context collapsed. Prepared native Qwen restoration of only in_proj_a/b; independent CPU audit passed, behavioral run pending fleet slot.
- Why: Test whether self-generated reasoning overwrites task evidence, while separating useful repair from merely avoiding answer. All required history/reports read first; prior global A_log tests not repeated.
- Verified: Blinded54-output audit: baseline fs+ false claims8/8, useful0/8, true finishes8/8, healthy8/8, texts3/3. Slowing rho=.25: false claims7/8, useful0/8, true finishes6/8, healthy8/8, texts3/3. Frozen rho0:3/4 whitespace loops truncated at3072, remaining false answer; independent abort audit passed. Remaining5 contexts and3 text controls NOT RUN. Owned GPU process confirmed gone; peak reserved12.222GB.
- Result: H1 rejected, no candidate/online claim;3/25 lots charged including partial frozen run. No heldout/confirmation construction or split_test.json access. H2 CPU verification exactly matches48 matrices at both doses. Shared dirty checkout preserved; pull blocked by existing edits, no commit/push in this unit.

## 2026-11-08 00:36 UTC — astra-free H2 static artifact and external handoff

- What: Compiled gate_reversal1.json into complete /dev/shm/free_h2; uploaded to Modal holo-models:/ckpt/free_h2. Prepared H3 half/full native MLP specs and H5 boundary-row protocol.
- Why: Test fixed weight edits after H1 memory hooks produced no useful correction; ares redirected serving to Modal to avoid pod GPU contention.
- Verified: Independent full H2 checkpoint audit:48 changed matrices exactly Qwen,676 other tensors exactly Holo,724 keys/shapes/dtypes complete, unchanged HF assets,0 symlinks. H3 spec CPU review passed with explicitly bounded numerical coverage; no H3 behavioral claim.
- Result: Exploratory only, no admitted candidate.5/25 lots reserved/charged (3 local completed/partial,2 external reservations); external evaluation restricted to6 development contexts,8 paired seeds,3T0 text controls;9heldout contexts unopened. Remote REPORT.md and EXTERNAL_PROTOCOL.md record the handoff. Shared source files and production servers untouched.

## 2026-11-08 00:43 UTC — astra-mit2: conditional verification circuit, negative close

- What: implemented and evaluated seven fixed two-neuron SwiGLU edits (six semantic L19, one lexical L31), plus two separately labelled input-modified capacity diagnostics. Canonical report: pod /workspace/astra/astra-mit2/REPORT.md; verified local archive: holo-neurochir/astra-mit2/REPORT.md.
- Why: test whether an analytic completion detector can trigger useful verification and deactivate, without gradients or training.
- Verified: independent implementation, behavior, accounting and final-report reviews. Thirteen charged lots, 27250 forward calls; report SHA256 0adbc6d37e7834fabd498e5724a724291503a48a25ade46872ab49b1f5f2d3a9. All177 archived file hashes match the local copy. Last own GPU PID exited and launch lock released. Shared production services unchanged.
- Result: no accepted candidate. Seven weight arms produced35 false answers/35 observed attempts at the same five sample positions across two tasks, zero useful action;133 planned outputs missing, including all112 protected outputs. L31 triggers one Wait and sometimes transient error recognition, then rationalization. Both input-modified diagnostics fail useful-action screening. Final heldout stays unread; random, text and online checks were not run. Stopped at the predeclared two-mechanism bound, not an impossibility claim. No shared checkout cleanup, staging or commit performed.

- Journal timestamp correction (2026-11-08 00:41:25 UTC): the preceding astra-mit2 entry was appended before00:41UTC; its manually written00:43UTC heading is incorrect. Scientific counts and report hashes are unchanged. Future timestamps for this unit are generated from UTC at write time. Ares has received the final negative result.

## 2026-11-08 01:03 UTC — astra-free external measurement restart

- What: froze owned external runner and launch wrapper after independent review; transmitted exact commands for reserved lots5–8 to ares.
- Why: earlier external text controls differed from the frozen protocol; source/version/model and response completeness needed explicit evidence.
- Verified: independent probe PASS24 mocked assertions; wrapper PASS16 mocked paths/gates plus optimize/deadline/rsync checks; final six-context validate-only51 jobs, no API calls. Bundle SHA fb56411f49406266379e17a82ebf7070beff9acf1af082c3df875ab3077af2e7.
- Result: four existing reservations bound to reviewed execution, no new forward lot and no candidate claimed. Report remains /workspace/astra/astra-free/REPORT.md.

Timestamp correction for the preceding astra-free entry: the GO message was delivered at2026-11-08T01:01:16.316Z (chat message5864), not01:03. The report now reflects01:01; append-only log history is retained.

## 2026-11-08T01:03:01+00:00 — astra-free

- What: Corrected the preceding hand-entered timestamp from the recorded chat event and added record_unit.py for automatic UTC entry timestamps.
- Why: The GO message was at01:01:16Z; a manual report entry had incorrectly said01:03.
- Verified: Chat event5864 epoch1794099676316; report corrected; immutable log corrected by append. New entry timestamp generated from datetime.now(timezone.utc).
- Result: Gardener correction ladder: event timestamps generated by the owning writer; no behavioral data or forward-budget change.

## 2026-11-08T01:15:36+00:00 — astra-free

- What: Completed and independently audited original Modal,H2lambda1,H3half development measurements; reserved H3full as lot9. H5half measured with semantic audit pending. H6half CPU checkpoint built after independent small-artifact/compiler PASS.
- Why: Require actual useful correction, preserved controls and matched execution rather than tool suppression or changed prose.
- Verified: First153 complete outputs audited; eacharm16/16 false completion,0/16 useful,15/16 true completion,16/16 healthy,3/3text. Source/settings/token metadata conform. Original HF resolved revision proof requested. H6 exact BF16 targets/compiler extension PASS; fullcheckpoint verification remains pending.
- Result: H2lambda1/H3half rejected at development. Noheldout read and noCANDIDAT. Report includes scheduling-order deviation and tokenidentity comparison. Budget9/25 reserved/charged; noH6forward. A failed reservation invocation used the non-vLLM CPU interpreter and wrote no ledger entry; reserve_external.py now selects the required interpreter by its shebang and delegates to the unchanged runtime.reserve owner.

## 2026-11-08T01:25:11+00:00 — astra-free

- What: Reconciled unplanned external deployment generation with budget; completed H5blind audit and adjudication; H3full completed before stop request; H6half verified and uploaded.
- Why: Budget must include separately invoked deployment suites; useful behavior cannot be inferred from valid grammar or client exit0. Partial outputs should survive an interrupted measurement.
- Verified: Operator evidence5897:16 extra requests across5 suites plus1 manualcurl, charged as6 extra lots10–15. modal_probe.py refuses future generative smoke for astra-free models. H5all51 outputs audited, same0useful/16false/15true/16healthy/3text asoriginal. H3pilot2814/3072 repeatedtoken; complete51rawoutputs preserved. H6all724 tensors independently verified.
- Result: 15/25 lots charged,10remaining. Noheldout/noadmittedcandidate. Streaming-runner copy pending independent verification; no new forward untilfreezePASS. All raw/adjudicated audits and budget deviation recorded in REPORT.md.

## 2026-11-08T01:30:52+00:00 — astra-free

- What: H3full independently rejected; H6half lot16 reserved and GO sent after streaming-runner freeze.
- Why: Prevent generation collapse from consuming a complete lot; test full-attention query temperature with durable outputs.
- Verified: Streaming fake51/pilot failure/partial persistence/protocol guards PASS; real TRAIN validate-only51 jobs with no API; H6full checkpoint724 tensors PASS. H3full36/51 truncated,34/48 GUI invalid,2/3 text fail.
- Result: No candidate.16/25 charged or reserved,9 unreserved. H7 role selectivity premise fails; H8 attention-gate premise reading only.

## 2026-11-08T01:47:48+00:00 — astra-short: global end-of-thinking promotion, negative close

- What: evaluated additive end-think row promotion, original-row scaling and a projection away from observed JSON states on Holo-3.1-4B. Canonical report: pod /workspace/astra/astra-short/REPORT.md; local archive: holo-neurochir/astra-short/REPORT.md.
- Why: test whether a fixed weight edit can shorten reflection while preserving useful actions, true finishes, JSON and ordinary text, without gradients or training.
- Verified: independent blinded action audits and final CPU review PASS. Thirteen charged lots; 560 action outputs and 30 text controls persisted; 795 requests planned, with cancelled and possibly unpersisted execution explicitly distinguished. All 266 archived file hashes match. Final report SHA256 2bc64186175ec493a190173ecbcb110cbd3e6a4d6f9028fdcab41db08ed737d3. Own runner exited; peak reserved memory 12.222201856 GB; shared services untouched.
- Result: no candidate. Best complete safe arm phase12 reduces mean thinking 7.0174%, below the predeclared 25% gate; all 112 JSON valid, all 72 healthy outputs token-identical, three text finals identical, and semantic counts unchanged (fs+13/20 false finishes,3/20 useful). Stronger settings fail JSON or text. Phase16 full-panel attempt aborted after16 outputs/two invalids, blocking conditional phase20. Reserve and online evaluation unused. Ares received the final negative result. No shared checkout cleanup, staging or commit performed.

## 2026-11-08T01:50:49+00:00 — astra-free

- What: H6half paired semantic audit rejected; H8 flat checkpoint verified and uploaded; H6quarter built in owned workspace after shared-memory capacity refusal.
- Why: Distinguish useful continuation from changed tool choice and preserve accurate false-completion accounting.
- Verified: H6:102 outputs independently graded,51 paired metadata checks,13 false finished answers plus3 incorrect future-effect actions,0 useful,protected/text preserved. H8:724 tensors exhaustive PASS. Claim-scope contract independently tested.
- Result: No candidate.16/25 lots charged; next H6quarter awaits full verification, H8/H9 no forward. Historical verdicts and adjudications preserved.

## 2026-11-08 01:53 UTC · astra-merge · experiment · First distributed merge reaches online evaluation
- What: Built complete Holo +0.5(CUA-Lite-Qwen) language-only checkpoint; preserved vision/head and all Holo inference files. Uploaded Modal2; beta0.25 also built and independently verified. Source revisions, SHA256, tensor cosines, raw screening generations and audits journaled in pod /workspace/astra/astra-merge and local holo-neurochir/astra-merge.
- Why: Test distributed transfer after localized edits failed to move the completion decision, with no gradients, adapters or harness/prompt changes.
- Verified: Independent724-tensor exact arithmetic/layout/finite/hash checks PASS for both doses; beta0.5 vLLM smoke3text+JSON PASS within14min. DIAG k8: fs+ answer11/16 vsoriginal16/16; fs-2/16 vs16/16; healthy16/16, zero invalid/error/truncation. Cross-backend baseline limitation being checked on Modal1.
- Result: Partial research, no success-score claim. Extra verification behavior is observed but protection fails. Ares launched45-task online reserve evaluation on Modal2; no reserved episode content inspected or used to tune. Shared dirty work preserved; initial pull blocked, fetch showed no remote divergence.

## 2026-11-08T01:56:51+00:00 — astra-free

- What: H6 quarter checkpoint independently verified, uploaded and handed off as reserved lot17; H9 CPU construction started after static PASS; four closed shm checkpoints retired.
- Why: Complete the fixed attention-temperature dose sequence, test coordinated restoration without gradients, and release shared memory safely.
- Verified: H6 quarter exhaustive PASS:724 tensors,8 exact edited vectors,2047 changed values,716 untouched tensors; SHA manifests and non-weight assets archived for all four deleted own checkpoints.
- Result: 17/25 lots charged; no admitted candidate; H6 quarter behavioral results pending; H8 flat ready but unrun; three future validation lots preserved.

## 2026-11-08T02:02:40+00:00 — astra-ratio: narrow rationalization MLP edit, negative close

- What: completed the fixed MLP-output rationalization experiment on Holo-3.1-4B: layers17/20,64 down_proj columns each, doses0.5/1/1.5 plus preregistered6 and norm-matched random1/6. Canonical report: pod /workspace/astra/astra-ratio/REPORT.md; local [report](holo-neurochir/astra-ratio/REPORT.md).
- Why: test a static weight edit against verified useful continuation on fs+ rather than treating fewer answer calls as repair. Source p50c differences are explicit; this is the user-prescribed adaptation.
- Verified: independent final review confirms42 freeze-manifest entries,12 BF16 runtime tensors,10 charged lots/19 reserved batched requests,224 valid action proposals and21 texts.137 distinct proposals audited blindly; two terminal shortcuts remain unknown. Strict automatic text comparison remains FAILED for one random6 wording change; independent semantic review satisfies identical-or-equivalent. Report SHA256 5a1fb3aaa027872ccd22683c225d16d60a67c148e891e8b5cb502dd4a4c64236.
- Result: no candidate. All learned doses0/8 verified useful fs+; primary doses8/8 answer, dose6 and random6 each7/8 answer with the same unverified shortcut. Healthy12/12 everywhere, true finishes9–10/12 against10/12 baseline. No online evaluation or Modal upload. Owned GPU processes exited, locks released, peak13.002GB. Freed only our245MB runtime cache after shared volume quota blocked final transfer; restored report hash verified. No shared checkout cleanup, staging or commit.

## 2026-11-08T02:04:10+00:00 — astra-free

- What: Preserved H9 interrupted build, moved H6 quarter checkpoint to shm with exact file hashes, and launched one statically reviewed recovery.
- Why: Ares reported the individual workspace quota full during the H9 interruption; recover safely without changing the hypothesis or overwriting unverified artifacts.
- Verified: 17 copied checkpoint files have identical SHA256;10,373,069,528 bytes removed from workspace. Resume diff independently PASS;161 existing deltas must match recomputed FP32 values before reuse.
- Result: 17/25 lots charged, no new inference. H6 quarter external result pending. H9 one recovery running; second build failure will close H9 as NOT RUN behavior.

## 2026-11-08T02:11:27.243626+00:00 — astra-mit1 final archive integrity receipt

- What: Recomputed every hash and size in the 36-file compact archive manifest and wrote the explicitly excluded `FINAL_ARCHIVE_CHECK.json` receipt.
- Why: Close the local archive with an independently reproducible copy-integrity check without regrading findings or reading model outputs.
- Verified: 36/36 files, 523318 bytes, report/review binding, unique contiguous lots1–29 within cap40, closed/no-job/no-candidate/heldout-false state; receipt SHA256 c081627f9321f287988584ab1dd48c796495eb7ec3612908153f3531b5f46cba matches local, `/tmp`, and remote copies.
- Result: PASS, zero issues. Git synchronization was unavailable because the dirty shared checkout has no upstream configured; no unrelated file was changed.

## 2026-11-08T02:11:49.257018+00:00 — astra-mit1: weight-edit search, negative close

- What: Closed the bounded Holo-3.1-4B weight-edit search and archived the audited [report](holo-neurochir/astra-mit1/REPORT.md). Canonical experiment folder: pod `/workspace/astra/astra-mit1/`.
- Why: Require confirmed useful continuation on false-success contexts; fewer answer calls and corrective intentions alone do not meet the requested criterion. Earlier Budget/Pivot positives were withdrawn or marked unverified.
- Verified: Independent final report review PASS with no remaining findings; report SHA256 9362bf0257bdb71f82526c6fc46c9e89e48a51757cdb928376949ae2b526ac63. Registry contains 29 charged lots, including partial runs and failures. Evaluated edits show no confirmed fs+ useful-action gain. H7/H8 strong doses lose 12.5 points of true finishes. H10 failed its fixed CPU threshold; H12 passed CPU construction proof but behavior was not tested. Lot29 stopped after 4/40 GUI outputs and no text; those four match baseline tokens, but full fidelity is absent and the termination cause is undetermined. Archive integrity receipt is recorded in the preceding entry.
- Result: No candidate; no CANDIDAT message or online efficacy claim. H11 closed under its unique-restart rule; Qwen was not run and dependent H12 remains untested. Eleven budget lots unused; nine final heldout contexts unopened. Own GPU process exited and slot was reassigned. Final negative result and report hash delivered to ares. Shared dirty work left intact; no staging or commit.

## 2026-11-08 02:12 UTC — astra-merge: donor pilot and CUA dose sweep

- What: delivered full HF CUA beta0.25/0.5/1 and Fara beta0.25/0.5; all have independent exhaustive tensor checks and completed Modal uploads. Fara beta1 is building; the fixed two-donor mean/TIES/DARE grid follows.
- Why: transfer distributed post-trained donor capabilities using static weights only. All source shapes match; TMax excluded for missing vision. No harness/prompt modifications or reserve/test episode exposure.
- Verified: same-backend original and CUA0.25/CUA0.5/Fara0.5 each completed51 matched DIAG generations with coherent text and healthy JSON, no errors/truncation. Independent audits confirm fs+ answer16/15/11/16 and fs-16/11/2/14, respectively; healthy16/16 for each. Weight audits check all724 tensors,426 exact language formulas and298 unchanged vision/head tensors.
- Result: three healthy candidates handed to ares; CUA0.5 is in the45-task online evaluation. Static stopping changes do not establish OSWorld improvement. Complete evidence in holo-neurochir/astra-merge; root pod backup protects against shared workspace quota failures.

## 2026-11-08T02:18:34+00:00 — astra-free

- What: H6 quarter independently rejected on one truncated pilot; H8 flat reserved/GO as lot18; H9 deltas passed exhaustive independent verification; H9 alpha0.2 checkpoint compilation started.
- Why: Stop the failed attention-temperature family, measure the separate attention-output gate hypothesis, and test coordinated parent restoration only after exact artifact checks.
- Verified: H6 quarter1 attempt/1 output/3072 tokens,50 not sent,0 useful; H9 418 hashes and401 deltas with2 doses exact,0 FP32-vs-FP64 BF16 discrepancies. Reusable external metadata checker independently passed17 cases.
- Result: 18/25 lots charged;432 actual requests through partial lot17 including16 ancillary; no admitted candidate. Three validation lots preserved, H8 behavior pending, H9 model not yet inferred.

## 2026-11-08T02:20:39.307286+00:00 — astra-broad: distributed surgery pilot

- What: completed last-token replay swaps and compiled a projected ridge edit across all24 residual writers in layers12–23; complete HF p100 checkpoint uploaded to Modal1 /ckpt/broad_residual_p100.
- Why: test a distributed, gradient-free weight change after localized edits did not change stopping decisions. Two DIAG construction pairs, four preservation contexts and three texts; six disjoint DIAG evaluation tasks, reserve/test untouched.
- Verified: exact self-swap and final-residual swap logits; independent exhaustive724-tensor PASS,24 intended edits and700 untouched tensors. Canonical vLLM probe51 outputs each original/p100: fs+ answer15/16→8/16, labeled true-finish15/16→3/16, healthy16/16, no invalid/error/truncation. Three texts coherent.
- Result: p100 fails preservation; no OSWorld gain claimed. Visual audit sees benign/reverification or corrective intentions, including one suspect true-finish label; original frozen labels retained. Lower doses and realized-BF16 norm-matched random controls running sequentially; own p100 API stopped, local checkpoint released after durable upload.

## 2026-11-08 02:22 UTC — astra-evo : recherche de fusion lancée

- What: sealed40 DIAG contexts across40tasks,20construction/20validation; implemented16-coefficient weights-only grouped search and began GPU run under semaphore.
- Why: find a layer-dependent CUA/Qwen mixture with selective false-completion margin reduction after scalar merges reduced stopping globally.
- Verified: independent cohort PASS40taxonomy,200file+677image hashes,62HF/vLLM checks; independent4donorSHA PASS; CPU replay freeze40/40, static review GO.
- Result: running, no candidate or OSWorld gain yet. Report: holo-neurochir/astra-evo/REPORT.md. Reserve45 and split_test episode content untouched. Existing shared dirty checkout preserved.

## 2026-11-08 · astra-infeas · decision · Infeasibility wording gate rejected
- What: Audited 75 ares-allowlisted DIAG tasks; 139 episode directories, 137 complete, 11 infeasible episodes across 6 tasks. Full redacted final answers and exact scoring-contract provenance saved in holo-neurochir/astra-infeas/.
- Why: Test whether false success on infeasible tasks is merely an unrecognized inability formulation, without exposing reserve45 or test tasks.
- Verified: Independent CPU raw-source audit reproduced all counts and executed the real DesktopEnv.evaluate AST: 10 answers, 0 regex matches, 2 genuine inability answers on 1 Writer task; 8 answers claim success (including 1 mixed GIMP case). Exact regex flags checked; no weights or GPU.
- Result: Discarded at the >=3 unique-task gate: strict counterfactual gain 1 task / 2 runs; permissive upper bound 2 tasks. Ares notified at 02:18:31 UTC and requested closure. REPORT.md and VERIFY.md distinguish RealtimeGUI text regex, official Surfer-H text convention, and native OSWorld FAIL scoring. No model edit, k8 replay, checkpoint or upload.

## 2026-11-08 02:25 UTC — astra-merge: scope amendment and rejected high dose

- What: closed the initial branch at7 full HF builds following ares’s direction. CUA beta1 rejected; Fara0.25/1 and dualmean archived without behavioral screening. Replaced unbuilt TIES/DARE slots with CUA layers12–23 at beta0.5 then0.25 (global cap9). Scoped beta0.5 built.
- Why: ares prioritized selective CUA fusion and assigned RegMean to a separate agent. The middle block is an empirical hypothesis, not a uniquely localized false-success mechanism.
- Verified: CUA beta1 has16/48 invalid GUI outputs, including6 truncations; raw fs+answer2/16 is not improvement. An audit transcription error was corrected against unchanged raw outputs and summary; numeric reports are now generated mechanically. All4 model token mappings248077 IDs match exactly. Frozen builder v2 and independent verifier explicitly enforce selected layers and preservation of every unselected tensor.
- Result: scoped candidate8 is in exhaustive verification/upload; candidate9 remains beta0.25. No unrequested GPU job, prompt/harness change or reserve/test episode exposure.

## 2026-11-08T02:28:53+00:00 — astra-free

- What: H9 α0,2 vérifié et uploadé; lot19 réservé compte2; routage lot18 vérifié; checkpoints H6 clos archivés puis retirés.
- Why: Préparer les deux essais figés sans génération supplémentaire ni ambiguïté de réservation; libérer mémoire partagée.
- Verified: H9 contrôle indépendant724 tenseurs/418 fichiers PASS; routage V2 30/30 PASS; uploads exit0 et compte2 attesté par ares6197; SHA de tous les fichiers H6 avant retrait.
- Result: 19/25 lots engagés;432 requêtes observées jusque17;18–19 pas encore mesurés;0 candidat. 20 746 139 004octets shm libérés.

## 2026-11-08T02:29:07.706039+00:00 — astra-broad: visual audit correction

- What: withdrew prior visual label concern and no-destructive-action claim after identifying an off-by-one screenshot selection in the independent semantic audit.
- Why: row.t is a zero-based traj index; using filename step_t selected the previous screen. Correct current courrier image has all four recipients complete.
- Verified: direct inspection of traj[t].screenshot_file and correct images; canonical generation/replay already used this mapping, so numerical51-call results are unchanged. Audit now requires trajectory/hash-bound mapping.
- Result: p100 preservation failure remains; three extra prefix writes may regress a completed state, not repair it. Old label suspicion withdrawn. Corrected audit in progress; ares notified immediately.

## 2026-11-08 02:33 UTC — astra-merge: checkpoint delivery complete, runtime queue explicit

- What: completed9/9 full HF checkpoint constructions, independent exhaustive checks and Modal uploads. Final2 are CUA layers12–23 beta0.5 and0.25, ready account2. Published CHECKPOINTS.json with per-file hashes, serving paths and exact evidence.
- Why: finish the authorized weights-only deliverable and distinguish construction, static health and online success. Ares superseded the unused TIES/DARE slots with the scoped doses.
- Verified: every checkpoint724 tensors; full-language cases426 formulas/298 preserved, scoped cases159 formulas/565 preserved; allHFaux/config/processor checks pass. Three healthy static candidates, one rejected16-invalid dose; three unscreened after scope change; two queued. The first healthy CUA0.5 arrived about13min after start.
- Result: no OSWorld improvement established. Ares owns45/120 online evaluation and account2 service after H8; two scoped static screens remain pending. No owned GPU/dev server remains, no further construction is planned. All4 token mappings align; donors/references remain available read-only.

## 2026-11-08 02:34 UTC — astra-regmean: first overlap and centered checkpoint

- What: Froze19 fs+,19 true finishes,16 healthy DIAG contexts over38tasks plus3texts; captured57 exact writer-input replays at prefill/endthink before current JSON. Built centered RegMean checkpoint for24writers12–23.
- Why: Test selective donor transfer without deleting Holo outside observed key span; ares explicitly corrected numerator with epsilon*W_H.
- Verified: independent replay and math reviews PASS; capture token counts54/54,199seconds,14.35GBpeak. Principal-angle medians67°/69°; task-CV AUROC medians.704/.634; step baseline.852 reveals confounding. Tensor audit and behavior pending.
- Result: Partial research, no admitted candidate. CompleteHF /dev/shm/regmean_cua_centered built by02:32; original paired51calls running. Report: holo-neurochir/astra-regmean/REPORT.md.

## 2026-11-08 — astra-broad: independent generation audit

- What: Added [audit_generations.py](holo-neurochir/astra-broad/audit_generations.py) and wrote `holo-neurochir/astra-broad/audit_family.json`.
- Why: Independently validate cohort cardinality, canonical settings, parsed tool flags, per-row summaries, and separate user/fleet behavior gates without torch, GPU, episode, or image reads.
- Verified: `python3 -m py_compile holo-neurochir/astra-broad/audit_generations.py` and CPU audit of `evaluation_original` plus `evaluation_p100`; both arms PASS integrity with 48 GUI + 3 text records and exact summary recounts. Remaining five planned arms are pending.
- Result: Overall audit remains `pending`; p100 user gate FAIL (fs+ absolute drop 43.75 pp, fs− protection loss 75 pp) and fleet relative-50% gate FAIL (46.67% relative drop).

## 2026-11-08 — astra-broad: random100 generation audit extension

- What: Extended the independent audit to accept both legacy `evaluation_p100` and family `evaluation_broad_residual_*` directory names.
- Why: Include the completed random100 arm while preserving explicit pending states for the remaining dose arms.
- Verified: CPU audit and py_compile pass; original, p100, and random100 each have 51 records with exact 48 GUI/3 text shape and summary recounts.
- Result: Family audit remains `pending`; random100 has fs+ 16/16, fs− 16/16, healthy valid nonanswer 16/16, and fails both user and fleet gates because fs+ did not decrease.

## 2026-11-08 — astra-broad: gate semantics correction

- What: Separated structural text completeness from semantic text health in `audit_generations.py`.
- Why: Numeric user criteria cannot be promoted to a complete user gate without an independent semantic text review; fleet relative reduction is reported as a criterion only.
- Verified: py_compile and three-arm CPU audit pass; p100 and random100 remain numeric/user FAIL and fleet-relative FAIL.
- Result: No candidate receives a false user PASS from structurally complete text outputs.

## 2026-11-08T02:38:52+00:00 — astra-free

- What: Secondes doses H8 complément et H9 α0,4 compilées et vérifiées sur CPU.
- Why: Préparer les suites déjà fixées avant résultats, sans en autoriser l’inférence conditionnelle.
- Verified: Checkers indépendants: H8 724 tenseurs exacts,83 886 080 valeurs changées; H9 724 tenseurs exacts,3 140 770 486 valeurs changées; assets/ties/index inchangés; aucun forward.
- Result: 19/25 lots engagés inchangés;18–19 en attente; secondes doses non réservées; aucun candidat.

## 2026-11-08T02:44:18+00:00 — astra-free

- What: Audit indépendant du pilote H8flat terminé; familleH8 fermée; checkpoints temporaires H8 retirés après archive.
- Why: La première dose produit une sortie invalide, donc la seconde dose est interdite par le protocole antérieur.
- Verified: 1 tentative/1 sortie/3072tokens,95.4427% retoursligne+tirets,contenu vide,aucunJSON/outil/faussecomplétion;50NOTRUN;RouteV2/provenancePASS;SHAarchives avant retrait.
- Result: 19/25 lots engagés;433 requêtes observées jusque18;H9lot19 en attente;aucun candidat.20 748 037 913octets shm libérés.

## 2026-11-08T02:45:35.818024+00:00 — astra-broad: dose grid closed by orchestration redirect

- What: completed204 canonical responses (192 GUI +12 text) across original, learned100%, norm-matched random100%, learned50%; three patched HF checkpoints exhaustively verified/uploaded Modal1.
- Why: distinguish a directional behavior change from generic weight disturbance while preserving true finishes. Ares6235 prioritized factorized anchoring over remaining doses.
- Verified: independent generation integrity passes all four completed arms. fs+ / true-finish answer counts (/16):15/15 original,8/3 learned100,16/16 random100,12/9 learned50; healthy16/16, zero invalid/error/truncation, coherent texts. Random100 realized norms match learned100 within0.0093% per writer.
- Result: no candidate; no OSWorld gain claimed. Random050 was built but verification deliberately interrupted by ownedPID387964 before serving; its unverified manifest retained, temporary checkpoint removed. p025/random025 never constructed. Anchoring14-pass job queued through fleet semaphore; numeric gates unchanged. Report: holo-neurochir/astra-broad/REPORT.md.

## 2026-11-08T02:51:13+00:00 — astra-free

- What: H2 λ2 checkpoint vérifié/uploadé puis lot20 réservé compte2 après H9lot19.
- Why: Tester la seconde dose fixée initialement, après première dose sûre mais sans actionutile; préserver trois lots de validation.
- Verified: Contrôle indépendant724tenseursPASS:48cibles exactes,676intacts,3 739 810 valeurschangées;uploadexit0;affectation compte2 confirmée par Ares6254;réservation20 horodatée02:50:38.
- Result: 20/25 lots engagés;433requêtes observées jusque18;19–20 non encore mesurés;aucun candidat.

## Astra broad — 2026-11-08T02:55:12.567887+00:00
- What: completed anchoring A (14 forwards), common projection B (20 forwards), CPU key discrimination C. Launched bounded note-onset diagnostic per ares6258.
- Why: separate already-written conclusion anchoring from distributed writer geometry, then test earlier note position.
- Verified: source/hash and self-reconstruction assertions; fixed caps and exit0 for A/B; C training frozen before evaluation. Fresh independent diagnostics audit requested and not yet complete.
- Result: A flips both conditional margins with donor reason+JSON; B no admitted arm; C AUROC confounded by inputlength and step index (both AUROC1). No new checkpoint, no claimed OSWorld gain.

## 2026-11-08 — astra-broad: independent A/B/C diagnostics review

- What: Added `holo-neurochir/astra-broad/independent_diagnostics_review.md` and `.json`.
- Why: Independently verify completed anchoring, key-discrimination, and projection artifacts without GPU, generation, image audit, or implementation edits.
- Verified: Syntax, manifest/hash/cardinality checks, anchoring factor bindings and 14 forwards, key-probe task split and all 24 AUROC recomputations, projection basis/schema and 20 forwards, five failed projection gates, and report numerical consistency.
- Result: PASS with limitations. Key probe is fully confounded by length (train/evaluation length AUROC 1.0); projection selected no arm; post-process writer restoration was confirmed by source inspection but not rerun after process exit.
# 2026-11-08 — astra-regmean pool preflight

- What: Read-only manifest/hash/split/exclusion review for the RegMean diagnostic pool.
- Why: Check whether the reported 19/19/16 pool can feed the note-onset diagnostic without reserve or prior-broad overlap.
- Verified: Local manifest SHA, row/evaluation counts and labels, declared source hashes, reserve/evaluation exclusion relationships, and row-schema compatibility.
- Result: Pool is 54 rows plus six evaluation rows and is outside reserve/evaluation as required; one fs+ row overlaps broad construction `fs_1`, disclosed as exploratory cross-validation while retaining the exact ordered 19+19 pool. Report: `holo-neurochir/astra-broad/regmean_pool_preflight.md`.

## 2026-11-08T03:08:27.708430+00:00 — astra-regmean: two precision arms closed

- What: completed centered closed-form24-writer fusion, 57exact construction captures, grouped overlap/CV, two complete HF checkpoints and204 retained scored responses across paired originals/candidates.
- Why: test whether CUA's donor correction can suppress false completion while retaining true completion; FP16 follow-up authorized by ares isolates storage precision with a pairedFP16 baseline.
- Verified: independent math/replay/all724tensors/behavior audits PASS integrity. BF16 fs+15→13/16, true16→15/16; FP16 fs+15→16/16, true16→16/16;0invalid/error/truncation, healthy16/16 and3coherent texts. Earlier recorder failure cost51 additional submitted calls with0retained; total255submissions.
- Result: efficacyFAIL both; no reserve/test or online outcome measured. FullHFs archived Modal1; owned servers/tunnel stopped; 20746103045bytes shm released. Report: holo-neurochir/astra-regmean/REPORT.md.

## 2026-11-08 — astra-broad: D weighted LOTO/recovery preflight

- What: Added `holo-neurochir/astra-broad/D_cv_review.md` and `.json` covering weighted leave-one-task-out ridge and recovery controls.
- Why: Independently check the frozen method and recovery budget before any model run.
- Verified: Weighted primal/dual synthetic check max error `4.61e-15`; syntax compilation passed; source eligibility is 37 rows (18 fs+, 19 fs-) after exact `context_012` exclusion; full activation identity and 112/114 forward accounting are correct by code.
- Result: PASS with limitation pending outcomes. External pre-launch `timeout` evidence (`note_pool_deadline_evidence.json`) closes the operational deadline gap; the internal relative `Runner` timer reset remains disclosed. No GPU/model run or outcomes audit performed.

## 2026-11-08T03:09:22+00:00 — astra-free

- What: H9 lot19 independent semantic rejection; H10 numerical verification and half-dose build complete.
- Why: The fixed priority chooses H10 after zero H9 useful gain; candidate admission requires behavior, not tool suppression.
- Verified: H9 V2 metadata PASS; blinded102 exact coverage, claim-scope38/38+64/64, aggregate development_gate=false. H10 CPU511 PASS, full checkpoint compiler exit0; exhaustive checkpoint audit running.
- Result: H9: useful0/16, false completion16/16, true completion16/16, healthy16/16,text3/3. Budget20/25 reserved,484actual requests through19. No candidate. H10 forward NOT RUN.

## 2026-11-08 — astra-evo: evolutionary merge delivered

- What: completed weights-only search over8 layer/module groups on40 task-disjoint DIAG contexts;45 candidates,1000 objective forwards,26.5min,exit0; stopped at2 validation rounds without progress. Exported best a=.2,b=0 in layers12–27 mixer/MLP modules; uploaded complete HF to Modal1 holo-models:/ckpt/astra_evo_best.
- Why: test whether groupwise Holo/Qwen/CUA weight interpolation can lower false-finish margins while limiting true-finish and healthy-output damage. No gradient, LoRA, production prompt or harness change.
- Verified: independent cohort/provenance/search audits PASS; CPU724 tensors PASS,CUDA180/180 bitexact,147 tensors and1 466 114 226 values changed,544 outside scope identical. Three coherent greedy texts and one original-schema JSON action/EOS independently PASS. All15 local file hashes revalidated before32s upload,exit0; exact15 file listing on Modal. Remote shard hashes not downloaded again. No ownedGPU process left.
- Corrections: preserved firstCUDA failure (unsupported requirement that donor storage beBF16) and firstsmoke failure (unsupported note-string assertion, original action not persisted). Exact arithmetic gates unchanged; active dtype regression added. Original JSONschema is now sole field authority; accepted/rejected schema cases tested, action persisted before validation after PII gate; one corrected smoke run independently audited. No weight/prompt changes to satisfy checks. Upload wrapper bounds descendants to2 cores and redacts credential identifiers before logging.
- Result: validation score .332341; fs+8/8 and true6/6 still have positive answer margins. No demonstrated selectivity or OSWorld gain. Checkpoint and HANDOFF_ARES.md supplied for ares to serve/test online, including50-step guard not established offline (late successes only27–32 steps). Reserve/test episode content untouched. Evidence: holo-neurochir/astra-evo/REPORT.md and VERIFY.md. Shared checkout left intact, artifacts uncommitted; initial rebase blocked by existing changes.

## 2026-11-08 — astra-broad: independent D numerical results audit

- What: Added `holo-neurochir/astra-broad/D_results_review.md` and `.json` from saved D artifacts.
- Why: Verify reported AUROCs, task-fold accounting, continuation scores, capture hashes, and forward counts independently after recovery.
- Verified: Primary/step/length AUROCs `0.593567/0.785088/0.795322`; all 24 secondary AUROCs reproduced; continuation AUROCs `0.459064/0.450292/0.599415`; all 37 contexts had positive continuation margins in both labels; 112 forwards, exact hashes, metadata, and zero branch-difference fields.
- Result: PASS with limitations. This is descriptive teacher-forced evidence; persisted captures retain one canonical branch tensor, so branch equality relies on runtime assertions and summary. No GPU/model rerun or classifier refit.

## Astra broad — 2026-11-08T03:16:35.037515+00:00
- What: completed note-onset pilot and expanded original-weight diagnostic; closed experimental unit and cleaned owned processes/tunnel.
- Why: test ares6258/6275 hypothesis that false-success discrimination improves before note text begins.
- Verified: source/allowlist/reserve/eval exclusions; explicit null-note eligibility37/38 before any fit;36 interrupted+76 recovery=112≤114 forwards; two standalone and37 branch-prefix exact runtime checks; originaldeadline externalwrapper; transported capturehashes; independent primal/dual math check and final AUROC/fold/weight/count/metadata audit. Only one canonical activationbranch saved, so branch equality relies on runtime assertions.
- Result: primaryAUROC0.593567, step0.785088, length0.795322; gateFAIL. All37 fixedcontinuations prefer completed. No addedcheckpoint or claimedonlinegain. Initial failure and all artifacts retained; allowned launch PIDs ended, SSH233871 stopped. Three earlier verifiedstaticcheckpoints remain onModal1; no admittedcandidate. Report holo-neurochir/astra-broad/REPORT.md.

## 2026-11-08T03:17:42+00:00 — astra-free

- What: H2lambda2 lot20 semantic rejection; H10half full checkpoint verified, uploaded and reserved aslot21; GO sent to Ares.
- Why: Preregistered priority after H9zero useful gain and H2failure; retain3validation lots and atmost1furtherexploration.
- Verified: H2metadataPASS, blind102 semanticcoverage+claimscopePASS, gatefalse. H10full724:8exacttargets716unchanged,2047changed. Historical checkerfailures retained, no frozencriteria orweightschanged; uploadexit0. Canonical reservation verified from append-onlyledger; stdout log was not treated asJSON after parsing failed.
- Result: H2useful0/16,false16/16,true15/16,healthy16/16,text3/3. Budget21/25,535actualrequeststhrough20. Lot21notyetmeasured; no candidate.

## 2026-11-08T03:23:28+00:00 — astra-free

- What: Lot21 rerouted account2 toaccount1 before launch; V3 independent verification passed and newGO sent.
- Why: Ares6345 announced account2locked until04:50 and offered availableaccount1; Ares6350confirmed no21launch.
- Verified: Same reservedlot21, checkpoint/spec/sampler/probe unchanged; separateamendment, immutableV2, canonicalledger unchanged. IndependentV3 32/32 oneexecution. Account1uploadexit0; CPUconfig/index/shards hashed.
- Result: Budget21/25 unchanged;535actualrequests through20. Lot21waiting execution; no candidate. H2lambda2/H9a020 temporaryshm checkpoints retired afterallfileSHAandmanifests archived:20785950066bytes.

## 2026-11-08 03:24 UTC — astra-tact: bounded TACT reproduction closed

- What: froze audited DIAG labels (239 construction states), replayed actual END activations at32 layers, built task-balanced OT/OA axes and tested Gate, literal Add, residual-scaled Add and a matched random literal control. Small artifacts are in `holo-neurochir/astra-tact/`; large activation caches remain on the pod.
- Why: test whether model-internal steering can reduce false completion while retaining healthy behavior, without training or prompt/harness changes in a delivered model.
- Verified: independent quantitative/runtime/semantic audits RAN/PASSED/CORRECT for integrity; seven complete arms392 GUI+21 text, partial Gate8 GUI,421 retained outputs; all copied artifacts hash checked and privacy scan clear. OT development AUROC0.98279 vs position0.88303; only2 paired OT tasks and1 OA task.
- Result: no candidate. Every learned arm retains fs+15/16 answer; strong residual dose corrupts3/3 texts and leaves23/24 useful healthy actions. Ten starts; random-scaled startup stopped by owned PID after text collapse, zero outputs. No weight edit/checkpoint/upload/online OSWorld; reserve/test content unopened. Owned GPU lock free and research processes ended. Shared checkout preserved; ares coordinates Git archival.

## 2026-11-08T03:32:32+00:00 — astra-free

- What: Restored original account2/V2 GO for lot21 after Ares withdrew account1 availability; prepared H10zero and matched random controls onCPU.
- Why: Keep original sampling/route/budget while external evaluator waits; complete frozen validation artifacts before seeing H10 behavior.
- Verified: H10zero fullcheckpoint PASS firstattempt,724tensors/8targets/716unchanged/2047changed and exactzeroRoPEgain. Uploaddefaultaccount2exit0. Independent REPORT review2 PASS after3wordingcorrections. Randomartifacts built/frozen, independent CPUcheckpending; noforward.
- Result: Lot21still0calls, expected~04:50 onoriginalaccount2,V2noamendment. Budget21/25reserved,535requestscountedthrough20. Zero/controlforward conditional, no candidate.

## 2026-11-08T03:41:05+00:00 — astra-free

- What: Completed independent H10random CPU verification and regression guard for audit requirement taxonomy.
- Why: Prepare matched negative control before any H10behavior; prevent invented supplementary diagnostics becoming undocumented acceptance conditions.
- Verified: All16randomdraw/target/delta/replays exact; half2044changes10negativegains, zero2047changes74negativegains. Required8/8PASS; versionequality diagnostic remainsFAILnonacceptance, attempts preserved. Requirementcontract13/13 independent casesPASS.
- Result: No new forwards or reservations. Lot21waiting originalaccount2/V2 around04:50,535requests through20,21/25reserved. All H10CPUpreparation ready; no candidate.

## 2026-11-08T03:46:18+00:00 — astra-free

- What: Mapped the already-frozen final validation requirements and independently reviewed execution readiness.
- Why: Keep heldout sampling, admission criteria and unopened data separate from the construction-only inference chain.
- Verified: Independent VERIFY_VALIDATION_READINESS.md: no threshold changes, train 51 requests, heldout 39 per arm, current lot21 V2 route unchanged. No heldout or API access.
- Result: Development random control is runnable conditionally. Heldout requires a separate frozen chain only if a development candidate emerges. Budget unchanged:21 reserved,535 requests through20,lot21 zero requests.

## 2026-11-08 04:40 UTC · online-eval · nuit : comparaisons en ligne, mesures externes, branchement apparié
- What: bras confirm orig/lm40 (arrêté)/expo125/prompt/lmscale16 (invalidé : vLLM 8012 figé de 00:44 à 03:22) ; test GitHub expo125 contre orig sur 120 tâches ; lots astra-free 5-9 et 16-21 via ses wrappers figés (/health + vérification du nom servi avant chaque lancement) ; nouveaux formats de spec lm_head, lm_head_scale et delta ; branch_runner.py (rejeu cadencé puis K continuations) ; watch_servers détecte un moteur figé.
- Why: ares. Résultats appariés, sans aucune action irréversible lancée par moi.
- Verified: test 120 paires, expo125 contre orig, succès 0,592 contre 0,608 (Δ -0,017, IC95 [-0,09, +0,06]) ; poolé avec confirm, 164 paires, Δ -0,018 [-0,08, +0,04]. Rejeu de 10 vrais succès : 9/10. Pilote de branchement, 20 branches et 0 erreur : orig 5/10, merge_cua_b050 4/10, 1 épisode écarté sur 5 (web dynamique), 251 s par branche.
- Result: aucune édition n'améliore OSWorld à ce stade. Leçon : un argos send lancé dans tmux échoue sans ARGOS_SESSION_ID (passer -e), ce qui a fait perdre des alertes pendant plusieurs heures.

## 2026-11-08 04:45 UTC · ares (orchestrateur) · nuit de chirurgie OSWorld : bilan d'étape
- What: coordination de ~25 agents (Astra codex, Claude) sur la chirurgie de poids de Holo-3.1-4B. Pistes testées : directions et ablations, steering, lm_head, circuits de neurones, MIT p50c (astra-ratio), TACT (astra-tact), promotion de </think> (short), H2-H10 (astra-free : portes DeltaNet, MLP vers Qwen, q_norm, gates d'attention), ExPO, chirurgie large AlphaEdit (astra-broad), RegMean contrastif (astra-regmean), fusion évolutive (astra-evo), fusions CUA-Lite/Fara (astra-merge), infaisables (astra-infeas). Infra : 2 H100 Modal, GitHub Actions, branchement apparié (online-eval).
- Why: objectif de Martin « +10 points prouvés sur OSWorld par édition des poids seule ».
- Verified: deux relectures adversariales à contexte frais (report/REDTEAM_0305.md, REDTEAM2_0335.md) ; vérifieurs indépendants par agent ; recalcul des comparaisons en ligne depuis les result.txt, identique.
- Result: aucun gain significatif à ce stade. Meilleur : fusion CUA β=0,5, réserve de 45, à serveur identique (Modal) : +6,6 points [IC95 −6,7 ; +22,1]. Le test de 120 tâches (fusion contre original Modal) est en cours. Règle de décision fixée avant résultat (journal, 03:36). Journal complet : holo-neurochir/JOURNAL.md ; index : holo-neurochir/report/INDEX_PAPIER.md.

## 2026-11-08T04:56:18+00:00 — astra-free

- What: Completed H10 half-dose lot21 metadata and independent blinded semantic audits, then reserved final exploration lot22 H10zero.
- Why: Half-dose produced no useful gain but preserved protected and text controls, satisfying the pre-frozen condition for the second dose.
- Verified: 51 complete requests; metadata PASS; 102 blinded outputs reviewed; contracts38/38 and64/64 PASS; half-dose0/16 useful,16/16 false completions,15/16 true completions,16/16 healthy,3/3 texts. Volume config+2shard SHA match CPU; index unrecorded, resident GPU identity not cryptographically attested.
- Result: Half-dose rejected. Lot22 reserved at04:55:13UTC, exact V2 GO account2 sent; no heldout opening or weight adaptation.22/25 reserved,586 requests through21. H9a.4 and H10half own temporary checkpoints retired after manifests; all specs/deltas/results preserved.

## 2026-11-08T05:05:44+00:00 — astra-free

- What: Completed final H10zero lot22 metadata and independent blinded semantic audits; closed exploration and retired the last owned temporary checkpoint.
- Why: The frozen second dose produces no useful fs+ behavior and loses12.5 percentage points in both protected categories, exceeding the user limit.
- Verified: 51 attempts and51 outputs; metadata PASS with3 truncations. Blind contracts38/38 and64/64 PASS; aggregate0/16 useful,8/16 false completions,13/16 true completions,14/16 healthy,3/3 texts. CPU Volume config and2shard hashes match; index not recorded, no GPU attestation. No owned temporary checkpoints remain in/dev/shm; Ares6424 confirms Modal account2 closed after exit0.
- Result: No candidate;22/25 lots reserved and executed/charged,637 requests currently reconciled pending final independent accounting;3 validation lots unused. No heldout behavior opened, no further forwards planned. Final report under independent review.

## 2026-11-08T05:08:48+00:00 — astra-free

- What: Published the independently reviewed final astra-free report and closed the research run without a candidate.
- Why: No tested edit meets useful-behavior construction criteria; H10zero also exceeds the protected-loss limit. Frozen stop conditions prohibit further exploration.
- Verified: VERIFY_FINAL_REPORT PASS; VERIFY_FINAL_BUDGET PASS,22 reservations and637 requests=621 main+16 ancillary with recorded evidence limits. Published report differs from reviewed snapshot only by automatic UTC timestamp; SHA8aa8ea9df23b42caaa105e199a287bbdc37de1da0e371895354e0e3b3611b512. All owned temporary checkpoints removed; no own GPU/server left active.
- Result: No CANDIDAT signal. Three validation lots unused; no heldout behavioral evaluation or further requests. Final REPORT.md and all evidence preserved in /workspace/astra/astra-free and local /tmp/astra-free-work.

## 2026-11-08T05:50:49.919043+00:00 — astra-preamble

- What: Closed weights-only preamble experiment on the24 designated Holo3.1-4B layer12–23 writers. Original, learned dose2 and norm-matched random each generated27 complete offline responses; ares6456 cancelled dose1 during construction.
- Why: Frozen gates fail: exact preamble+verification0/8 (<6); healthy full text14/16 and exact tool-call11/16 differ (>1). Generic Before7/8 adds no verification action.
- Verified: Independent numerical/tensor/provenance audits PASS;81/81 outputs,72/72 GUI JSON valid,0errors/truncations,3/3 text controls each.158/160 capture forwards. Data allowlisted before read, evaluation task-disjoint; reserve/test contents untouched. Exact differences are not all demonstrated semantic regressions; only one original sample per context.
- Result: No admitted checkpoint or online run. Owned GPU/API, CPU builder and tunnel stopped;41,492,037,065 temporary-checkpoint bytes freed, captures/factors retained on pod. Evidence: holo-neurochir/astra-preamble/REPORT.md and /workspace/astra/astra-preamble. No continuation; ares owns fleet Git archival.

## 2026-11-08T07:35:08.656848+00:00 — astra-power

- What: Measured A original, B CUA beta0.5, C AlphaEdit broad_residual_p100 and D matched random on one frozen55-task cohort, four common seeds each; completed880 requests before07:29UTC and obtained final independent audit before07:35UTC.
- Why: Replace the prior single-context feasible-false-success evidence with task-level inference and a random-edit comparison. Exact prescribed sources supply19 admissible FS tasks, not20; all19 included without reserve/test exposure.
- Verified: Independent checkpoint67/67 PASS and final PASS: raw880/880 valid,1536 fields agree within1e-13,112 bootstrap endpoints exactly equal. No transport errors/truncations. Strict scores and feasible evaluators checked; known construction overlap sensitivity reported. Canonical mirror211 file hashes match. Owned research processes stopped, production healthy and unchanged.
- Result: C suppresses FS answer17.1pp (95%taskCI6.6–28.9pp), versus8.8pp estimated suppression on true finishes; selective benefit versus A remains unresolved. B estimate−10.5pp includes0; D increases FS answer15.8pp. No online gain or general impossibility claim. REPORT.md/RESULT.json and audited evidence under holo-neurochir/astra-power and /workspace/astra/astra-power. Ares notified; no further run or own Git commit.

## 2026-11-08 07:52 UTC — feci-guard
- Built holo-neurochir/feci_guard (commit aa5907f): external verifier on the agent answer (claude -p Sonnet or any OpenAI-compatible judge; passive or active NEED_CHECK mode), guarded copy of run_holo (--guard on|off), guard.md/guard.jsonl per episode, feci_guard.check() for the duel and verif-study; synced to holo-osworld-runner 2f1f38a for GitHub runs. Independent review fixed the stale screenshot, rule enforcement, timeout.
- 1-task VM run impress/550ce7e7: the guard refused a visibly incomplete answer with correct evidence, the agent repaired it, the evaluator still scored 0 (difference not visible on screen). Blind 60 packet and the 45-task online run were cancelled by ares; offline = verif-study 268 episodes, repair = with online-eval.

## 2026-11-08T07:53:27.368733+00:00 — verif-study

- What: Measured the exact requirement-by-requirement final-screen prompt on 268 deduplicated feasible final-answer episodes: original Holo at T=0 plus three T=.8 replicates, 1,072 complete HTTP responses with raw reasoning retained. Excluded partial scores and official infeasible evaluators; reported repeated-task and invalid-output sensitivities.
- Why: Test whether explicit verification detects the model's own false successes using existing saved episodes, without any new rollout or weight edit.
- Verified: Independent corpus and screenshot reconstruction, all request/body/model hashes, raw response accounting, Wilson intervals, task-cluster sensitivity, stability, requirement correction map, branch simulation and report assertions PASS WITH LIMITATIONS. Six maker parser tests and four independent tests pass. No retries; max concurrency 4; 16 invalid/truncated final verdicts retained and reported. Local/pod 389-file mirror verified by SHA256; all 268 images and task references match the frozen manifest.
- Result: T=0 detection 35/66=53.03% versus true-success rejection 97/202=48.02%; majority 40/66 versus 98/202. Difference uncertainty spans zero. Requirement counts 493/95/126 (yes/no/cannot tell), not requirement-level accuracy. Feasible branch 0/2 repairs; naive 1/4 nontransferable. No measured OSWorld gain; V2 not run because no stronger independent cached VLM exists. REPORT.md, RESULT.json and audit delivered locally and at /workspace/astra/verif-study before 10:30 UTC. No running owned server, new experimental continuation or own Git commit.

## 2026-11-08 — moon-combo — fusion CUA + protection done

- What: U12, U32 et K32 construits, vérifiés et criblés sur Power gelé (3 × 220 tirages + 9 textes).
- Why: tester si la projection de la fusion protège les vrais fini sans perdre son signal sur fs+.
- Verified: contrôles indépendants des 724 tenseurs par checkpoint, six captures hors cohorte et audits comportementaux ; JSON 660/660, textes 9/9 ; nettoyage attesté.
- Result: trois REJECT à 2026-11-08T08:00:52.467865+00:00 ; vrais fini 65/80 pour chaque variante vs A75/80 et B66/80. Aucun passage en ligne. Rapport holo-neurochir/moon-combo/REPORT.md, données RESULT.json. Aucun fichier d'un autre chercheur modifié ; pull initial bloqué par modifications partagées préexistantes, laissées intactes.

## 2026-11-08 · moon-rl · decision · RL donor and anti-posttraining offline screen
- What: Four fixed full-language weight edits tested on the frozen astra-power cohort, k=4, plus original A; 1,100 GUI generations and 15 text controls.
- Why: Test whether terminal RL transfer or partial removal of Qwen chat posttraining reduces false success.
- Verified: Independent exact-formula/provenance and raw-output audits PASS; 427 formula tensors, 297 preserved vision tensors per checkpoint. No numeric fs+ improvement. Anti .5 admitted only through a narrow, reviewed next-action quality exception; adverse PDF finish and healthy diagnostics retained.
- Result: RL .5/RL 1/Anti .25 rejected; Anti .5 full HF `/dev/shm/moon_rl_anti_b050` handed to ares at 08:02 UTC for online45+120. Own server/tunnel stopped; three rejected checkpoints removed. Evidence: `holo-neurochir/moon-rl/REPORT.md`, `FINAL_AUDIT.md`, `DECISIONS.json`.

- moon-combo clôture 08:05 UTC : revue finale indépendante PASS (20 contrôles, 1100 lignes), miroir pod 77/77 SHA conformes ; décision auditée transmise à ares.

## 2026-11-08T08:07:05.439587+00:00 — moon-vision

- What: Built and independently verified three full HF checkpoints editing only297 visual tensors, including merger; all427 other tensors byte-identical to Holo. CUA−Qwen visual norm1.28010 is nonzero; tested CUA beta0.5/1.0, plus Holo gamma0.25 explicitly added by ares before candidate outputs.
- Why: Test whether perceptual weight adaptation reduces premature completion while preserving the language tower, prompts and harness.
- Verified: Frozen55-task astra-power cohort, k4 and exact generation settings; 660 new GUI plus9 text responses, A220 reused verbatim. All JSON valid, no errors/truncations. Independent exhaustive tensor/SHA and statistics/bootstrap audits PASS; screenshot-grounded semantic reviews completed. Reserve45/split_test untouched.
- Result: No admission: FS+ answers57/54/57 versus55/76 A, required≤43. No convincing qualitative improvement; E025 healthy next-action preservation PASS, V05/V10 uncertain. Servers/tunnel stopped, rejected weights removed (31,119,988,803 bytes), sources/evidence preserved. REPORT.md and DECISION.json in holo-neurochir/moon-vision and pod workspace. No own Git commit; ares handles shared archival.

## 2026-11-08T08:07:16Z — proof-anchor

- What: Completed four-condition anchoring on39 strictly feasible tasks and captured six residual layers at three positions;72 primary LOTO probes, matched metadata baselines,1000 task-label permutations, oracle power and one declared MLP optimization sensitivity.
- Why: Replace n=1/2 paper evidence with task-level estimates while distinguishing margin attenuation from tool decisions and lack of evidence from information absence.
- Verified: Independent final numerical audit RAN/PASSED/CORRECT,10098 checks,exit0; separate model/replay/capture/source audits PASS,156/156 forwards and39 residual arrays. Pod/orbit manifest verifies81/81 file hashes. REPORT SHA d1ada976f4979755cc8e4f369a385e8eb90dd9ff392c8596fe5034c3965cc0f5; RESULT SHA00525ab78b91af451c5c812c3dc446c7939e52f739e70a7c6db25e7e311511fd.
- Result: Neutralization attenuates about80% of raw margin in both strata, yet answer stays favored37/39; attenuation interaction−.461[−2.362;1.499],p=.645. Best exploratoryAUROC.639[.466;.803] versus rawstep.704, correctedp=1; no robust discriminator or proof of absent information. Artifacts local holo-neurochir/proof_anchor and pod /workspace/astra/proof-anchor. Ares notified; all owned compute exited, no generation/deploy/paper edits.

## 2026-11-08 08:29 UTC — moon-leak: offline NO-GO

- What: Completed39-context head/DeltaNet attribution and four targeted o_proj head edits plus two matched random controls on the frozen55-task astra-power cohort, k4.
- Why: Test whether weight-only attenuation of note/thought-reading heads selectively reduces false completion.
- Verified: Independent fresh review reconstructs all1320 new GUI outputs and paired statistics; JSON100%, zero errors/truncations. Lowest targeted fs+ count56/76 versusA55/76, with true finishes71/80 versus75/80. No arm reduces fs+ answer. All six724-tensor audits and data audits PASS; original+six arms each have3 text controls, with common translation failure. Attribution6435 main forwards,7426 attempted including debugging, under8500; the two-failure stop-rule audit explicitly FAILS and is disclosed.
- Result: NO-GO recorded08:20UTC, before09:45. Ares notified; no online request. All14 owned process IDs absent, GPU/checkpoint directories clear. Report, decision, raw evidence, frozen snapshot and independent final review: holo-neurochir/moon-leak/. No mixed shared-checkout commit.

## 2026-11-08 · rescue-bench · experiment-preparation · Frozen-Guard Holo4 escalation
- What: Added rescue_runner.py, preregistered 12-episode K2 paired study, fixed-parity two-worker scheduling, reproducible metadata prevalence, and episode-cluster analysis under rescue_bench/.
- Why: Test whether stronger-agent escalation repairs feasible false completions after the frozen Claude Guard refuses them.
- Verified: Independent runner and scheduling CPU reviews PASS; statistical synthetic checks PASS provisionally; one recorded-state Holo4 tool JSON valid. First live guarded pilot replay valid, official score0; full pilot remains running. Frozen Guard/harness hashes unchanged.
- Result: partial — holo-neurochir/rescue_bench/REPORT.md; no gain claim. Only own new artifacts edited; shared dirty work preserved.
- 2026-11-08 09:24 UTC feci-guard: repair measure done (guard 5/18 vs 2/18, paired +17 pts [0,+44], not distinguishable from zero; independent recompute OK; best case calc/1de60575, demo in ~/osw/feci_demo/). Rescue harness run_holo_guard_rescue.py pushed to holo-osworld-runner (b1cd76d) and tested on 1 real task: refusal -> Holo4-27B -> COMPLETE, official 0 (invisible .pptx difference). Commits 1206f3c, 8862d4a. VM released.

## 2026-11-08 09:39 UTC — rescue-bench analysis correction
- What: separated official score1 from action-qualified repair credit; preserved historical and completed Holo3.1 references; added reusable independent analysis checks and first Calc pairing audit.
- Why: immediate-answer positives reveal replay-state drift and must not inflate predicted repair.
- Verified: independent stats review provisional PASS; verify_analysis.py exit0; independent Calc k0 audit confirms official Guard1/control0 with strict-valid replay; frozen runner unchanged.
- Result: collection ongoing in two shards, no final cohort or online-gain claim.

## 2026-11-08 09:55 UTC — first replicated Holo4 repairs
- What: completed K2 on Calc376 and Impress70bca: each Guard+Holo4 [1,1] versus Holo4-only [0,0]. Published independent raw-evaluator audit.
- Why: distinguish actual GUI corrections and official evaluations from claimed completion.
- Verified: all eight paired replays and boundaries valid; real edits/saves; no setup, model, getter or evaluator failures; independent MEASURED_REPAIRS_REVIEW.md.
- Result: five complete episodes currently yield Guard4/10/control0/10, cluster95 [0,.80] for difference .40. Collection remains partial; no online-gain claim.

## 2026-11-08 10:18 UTC — repo-ready: jury-ready repository
- README (EN + FR summary): problem, diagnosis, Feci Guard, mermaid architecture, results table with n and CIs, criteria → evidence, quickstart, levels 2-3, links, how we worked, limitations. AGENTS.md (for the AI judge: commands, claim → evidence, measured vs running), llms.txt, docs/REPO_MAP.md, LICENSE (Apache-2.0).
- New CPU quickstart, no key: jury_kit/replay_guard.py (frozen feci_guard.check on the 268 real screenshots, recorded verdicts: 45/66, 21/202, +58 [+41, +74]), jury_kit/recount_judges.py (3 judges from raw responses), jury_kit/guard_live.py (level 2, CLI path run, --api not run), jury_kit/quickstart.sh; CI workflow quickstart (green). Proof from fresh clones: docs/QUICKSTART_PROOF.md.
- Committed per ares: 50 experiment summaries (4c8b1ab), demo_live/repair_calc.html; untracked per ares: devin/README.md, pitch/PITCH.md, committed .pyc.
- Two fresh-context jury reviews: 6.85/10 then 7.3/10 (finalist yes). Open: online Guard result (report/ONLINE_GUARD_RESULT.md ~11:15), rescue_bench final (PR #1), final paper PDFs before 12:15.

## 2026-11-08 · design-pass · the 4 pitch pages in one editorial style
- What: rebuilt the pitch (holo-pitch-system, 10 screens), the repair replay (holo-guard-repair = demo_live/repair_calc.html, now English first, French second), the cockpit (style only) and the team dashboard (style only) on one shared sheet, holo-neurochir/pitch_design/style.css. It has a paper ground, EB Garamond, Inter and mono, and one orange accent for the refused requirement. Four isometric Hairline figures: claim, guard, absent, repair.
- Why: Martin asked for one minimal visual style modelled on skills.wheresryan.sh/anatomy.
- Verified: every Hairline figure passes look.mjs (frame, read-out, console, no flicker). All pages have no console error or horizontal overflow at 1600×900 and 390×844 (pitch_design/shoot.mjs). quickstart.sh is OK. An independent reviewer checked every number against the sources and the old pages: no number changed. Its claim fixes were applied: softer slide-3 and slide-9 wording, the strict-replay CI and "rejeu conditionnel" on slide 6, the prompt caveat on slide 5, and the small-sample label on slide 4.
- Result: published under the same names. Interim rescue numbers are read from rescue_bench/REPORT.md at build time (`python3 holo-neurochir/pitch_design/build.py pages/pitch.html out/pitch.html`, then republish). Pre-existing cockpit inconsistencies were left as they are: Holo4 "47 % / 24 %" vs RESULTS "47 % / 31 %" (a different prompt column), and Guard cost "~0,03 $" vs "~0,04 $".

## 2026-11-08 · infra-doc · feat · docs/RESEARCH_SYSTEM.md (how the research was run)
- What: one English page for the AI judge: agent team (orchestrator, workers, prereg table, red teams, fresh-eyes rounds, verifiers, journal), compute (H200 pod, its ~09:30 loss and Modal failover, 2 Modal accounts, budget guard, recorded spend), OSWorld VMs (VPS Docker+KVM, GitHub KVM runners, pre-run model check, one-port Guard relay key), eval method (splits, paired bootstrap, prior rule, noise, branch replay), timeline, reproduce table. 4 mermaid diagrams.
- Why: show the system is real, understandable and reproducible; every number cites path:line at 8e50b47.
- Verified: fresh-context fact-check agent, ~95 claims, 17 problems found, all fixed (wrong lines, 42→22 deploy names, unsupported counterfactuals removed, level numbering aligned with README); level-0 commands re-run exit 0. No secrets/IPs.
- Result: kept · commit 296b882. README link to be added by repo-ready (asked via ares).

## devin-infra — 2026-11-08 10:35 UTC
- Intégration API Devin installée et authentifiée (GET /v1/sessions?limit=1, lecture seule, clé apk_ v1). Mission M4 (contrôleur GPU gpu_ctl.py) écrite et testée en dry-run. AUCUNE session lancée (0 ACU), sur consigne de Martin via ares. Commit 3cc2173. Page : argos artifact devin-lab.html.

## 2026-11-08 10:50 UTC — hypnos: English pitch script, 3 min, 3 speakers
- What: holo-neurochir/pitch/PITCH_EN_3MIN.md + pitch_en_3min.html (published as holo-pitch-en-3min.html): A (problem) → B (weight surgery, negative) → C (Guard, recorded repair demo, close), ~370 words, two handoffs, Q&A, pre-stage update list.
- Verified: independent fact-check against README, rescue_bench/REPORT.md, RUN-OF-SHOW, feci_guard/RESULTS.md (+ replay_guard.py, verify_results.py exit 0); 3 overstatements fixed (absent signal, Holo4 detection gap, "official evaluator").
- Open: "11/18 vs 2/18" moves while rescue_bench runs; live duel kept optional (timing unproven in 3 min).

## 2026-11-08 10:46 UTC — rescue-bench completed 48-branch escalation experiment

- What: completed12 registered feasible false-completion recordings ×2 arms ×K2, official OSWorld evaluator; archived48 outcomes in holo-neurochir/rescue_bench/data/ with REPORT.md, RESULT.json and reproducible analysis. New rescue_runner.py imports frozen Guard/harness sources unchanged. Both workers exited0 and owned VMs closed at10:41; ares informed.
- Why: test whether a frozen Claude Guard refusal followed by Holo4-27B can repair failures against Holo4 continuation without Guard, capped20 new turns; separate actual replay outcomes from predicted reserve/test online gain.
- Verified: independent raw audit48 unique outcomes/result payloads, identical archived journal bytes and call counts; no recorded branch/model/verifier errors. Five missing required-output getter events retained as official zeros and disclosed. Numerical reviewer independently reproduced primary, strict/all-complete sensitivities,20k episode bootstraps, conditional repair and prediction scenarios; FINAL_REVIEW.md PASSED/CORRECT. verify_analysis.py and repository quickstart exit0. Nine frozen source hashes unchanged.
- Result: primary9 replay-valid episodes official11/18 versus2/18, after-action9 versus0, paired+50.0pp CI95[22.2,77.8]. Strict8 episodes+50.0pp[12.5,87.5]. All12+33.3pp[4.2,62.5], retaining genuine control f5 repair. Conditional after-refusal repair9/11[42.9%,100%]. Two no-action positives per arm receive zero repair credit. Predictions only: reserve+2.73..6.20pp/test+6.42..11.62pp under loss1..0; neither split rerun. Historical Holo3.1 0/10 is distinguished from its completed nonrandomized reference.
- Delivery: feat/rescue-bench, PR https://github.com/martinbon39/ComputerUseHackaton/pull/1 ; final raw evidence stays in /home/orbit/osw/rescue_bench/. No endpoint/VM job remains owned by rescue-bench.

## 2026-11-08 10:55 UTC · gh-runner2 · OSWorld arms on GitHub Actions (night + morning)
- Arms collected in ~/osw (compare_val layout): test orig, expo125, merge_cua_b050, orig_modal_test, orig_guard_claude (120/120, 3 runs, RUNS.txt); reserve orig_confirm, merge_cua_b050, broad_residual_p100, orig_modal_confirm; prompt test PARTIAL; lmscale16 INVALID (pod 8012 frozen).
- Workflow (martinbon39/holo-osworld-runner): base_url (Modal, MODAL_KEY), Feci Guard judge/rescue inputs, keyless relay via tunnel_host=orbit, setup-uv retries, VM-wait race fixed. gh_collect.sh NO_PNG=1.
- Orbit: restricted SSH key gh-runner-relay-hackathon-0811 (port 9911 only) added with Martin's OK; removal steps in holo-neurochir/report/CLEANUP.md. Freed 8.76 GB of report.html in my results_*_gh_* dirs.

## 2026-11-08 11:25 UTC — demo-director : démo live du pitch
- Livrables : holo-neurochir/demo_live/RUN-OF-SHOW.md (déroulé minute par minute, live central, plans B/C), CHECKLIST_JOUR_J.md (checklist + Q&R sourcé), cockpit (restylé par design-pass), page holo-guard-repair.
- 3 répétitions live en modal_guard (online-eval, 11:00-11:20) : calc/1de60575, arc complet (faux succès à gauche, refus du Guard, réparation, score 1 à droite) en R1 et R3, en ~4:03 ; R2 inversée (gauche réussit, droite erre 50 pas). Stratégie : live lancé à 0:00, décision à 3:30, sinon replay R1 (20261108-110023…).
- Deux relectures indépendantes : 14 défauts corrigés, puis 1 excès (5/18 contre 2/18 = 3 vraies réparations contre 0, signalé à ares).
- Risques ouverts pour Martin : connexion du CLI claude sur orbit (« can end until 2026-11-10 »), dépôt GitHub privé (kit jury), pod 8000 hors service (live sur Modal, réveil à T−3 min).

## process-viz — 2026-11-08 11:22 UTC
- holo-neurochir/demo_live/process_viz/ : boucle three.js immersive (8 chapitres, ~3 min) remplaçant les slides du pitch. src.html + build.py (inline des captures) -> holo-process-viz.html. Espace = pause, flèches/0-7 = chapitres, ?ch=N&t=S pour sauter.
- Ch0 vrai faux succès gimp/77b8ab4d (export.jpg.jpg, score 0, bras orig_pod) ; ch2 C1 = L19 H15, L23 H1, L31 H14 + neurones L30/L31 (circuit/REPORT.md) ; ch6 refus réel calc/1de60575.
- Relecture fraîche : ~75 chaînes, 0 chiffre faux ; 7 formulations corrigées (pas de « l'information n'est pas dedans », « aucun gain détecté » au lieu d'« inchangé », contrôle aléatoire α=0,5, poids d'attention non causaux).
- URL : https://argos.martinbonan.com/artifacts/holo-process-viz.html

## 2026-11-08 11:46 UTC · devin-review
- Devin M4 (session devin-13e97ca8…705b): gpu_ctl.zip/.patch downloaded (api.devin.ai/v1/attachments), 4 sha256 OK, reviewed, 39/39 tests on argos, dry run, real read-only `status` on both Modal accounts (22.9 $ / 24.1 $). Committed unmodified as 3363a03, review in infra/DEVIN_SESSION.md (99c683b), pushed. ACU not exposed by API v1.

## 2026-11-08 12:05 UTC — repo-ready: final jury corrections
- Correction of an earlier entry: a Devin API session WAS launched at 10:51 UTC (finished 11:05); it wrote `holo-neurochir/infra/gpu_ctl.py` after the reported experiments; see `holo-neurochir/infra/DEVIN_SESSION.md`. No reported number depends on it.
- README/AGENTS/llms.txt: online false-done breakdown corrected (7 of 19 avoided became successes, 12 ended without answering, 5 new false done, net 27 → 13); online arm = Holo-3.1 + refusal only, escalation measured in replay only; weight-edit and rule-timing claims aligned with paper §5.5–5.6; limitations added. Jury simulations: 6.85 → 7.3 → 7.6 → 7.8 → 7.7 (ares' jury-ai). Quickstart and link check green.
- 2026-11-08 12:45 UTC ares : soumission prête. Dépôt public ; README avec le papier, la page Try live (/try), la page des duels, les vidéos de 2 min (ElevenLabs et voix de Martin) ; quickstart vert ; 132 liens relatifs OK ; CI links et quickstart vertes. Résultats : en ligne, faux done 22,5 % → 10,8 % (significatif, score inchangé de façon mesurable) ; escalade vers Holo4 en rejeu +50 pts [+22 ; +78]. À FAIRE APRÈS LE JURY : révoquer la clé Devin (passée en clair), changer ~/.duel_key et arrêter les tmux duel_tunnel, guard_tunnel et guard_server, retirer la clé SSH gh-runner-relay-hackathon-0811 (report/CLEANUP.md), arrêter holo-jury-probe et modal-orig, relancer voice-api sur son port.
