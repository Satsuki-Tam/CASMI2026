#  Lessons from ~30 submissions: where the MRR actually goes
topic 743254 | by **Udam Liyanage** (https://www.kaggle.com/udamliyanage) | posted 2026-09-25 | votes 13 | comments 4 | https://www.kaggle.com/competitions/enveda-CASMI26-molecule-id-mass-spectra/discussion/743254

We've spent a lot of submissions learning what does and doesn't move the score in this competition. No code or solution here, just measurements and pitfalls that might save others some time.

- Don't analyse the visible test file. As the data page says, test.parquet is a placeholder drawn from train.parquet, and submissions are re-run on a hidden file. Statistics or outputs computed on the visible file tell you nothing about the score. We lost two submissions to this before re-reading the data page.

- Evaluate exactly like the metric. Matching is on InChIKey14 after RDKit tautomer canonicalisation. Deduplicate your candidate list with the metric's key, not raw InChIKeys, or you waste slots on tautomers of the same structure. On our holdout, about 8% of molecules had a tautomer copy of the truth under a different PubChem key.

- Most database-route errors are isomer errors. When the true structure is in our candidate list but not ranked first, the wrong winner has the same molecular formula about 98% of the time. Formula scoring and mass windows aren't the lever; separating constitutional isomers is. A small "same-formula isomer panel" (truth plus its best-scoring isomers) made a much more sensitive development metric than overall MRR.

- Mass window width barely matters on timsTOF. On instrument-matched timsTOF spectra, 99% of precursor masses were within about 5 ppm. Going from 8.5 to 10 ppm left candidate counts essentially unchanged: the window is full of exact-mass isomers anyway.

- Curated NP databases didn't add coverage beyond PubChem ∪ COCONUT for us. For public-library molecules missing from PubChem ∪ COCONUT, ChEBI, LIPID MAPS and NPAtlas contained none of them. Membership flags in curated databases also looked great on public holdouts and hurt on the leaderboard (holdout molecules are over-represented in curated DBs).

- Be careful with "novel molecule" simulations. Deleting the true structure from the database and asking whether a derivative generator recovers it overstated reach about 3× for us, compared with molecules that are genuinely absent from the databases. Validate novelty work on real absent molecules. In our hands, adding generated candidates to the final list has not yet paid off on the leaderboard, even when only inserted for molecules predicted to be novel.

- Know your noise floor. One test molecule is worth about 0.0025 MRR. Retraining the same GBDT ranker with a different random seed moved our holdout MRR by up to ±0.007. Compare averages over several seeds, and don't chase differences below about 0.005.

- Your two best proxies can disagree. We track a public-library class-2-style holdout and a small timsTOF natural-product panel. For one change the public holdout predicted the leaderboard gain while timsTOF was flat. For another, the reverse. When a change targets natural-product chemistry specifically, the timsTOF panel was the better predictor for us. Watch both.

- For database candidates, the remaining errors are about connectivity. Once the formula is right, similarity signals that don't "see" how atoms connect plateau quickly. Evidence that depends on the structure itself (in-silico fragmentation and similar) is where we found gains.

Good luck everyone, and happy to discuss.

## Comments (1 top-level)

- **NeckBeard** (2026-09-29, votes 0)
  Thank you for this — the isomer-panel point in particular changed what we work on. Three questions, and some measurements of our own in return.
  
  1. How do you construct the same-formula isomer panel?
  
  You describe it as "truth plus its best-scoring isomers". We currently use all same-formula candidates from our pool (median 46 per molecule, 90th percentile 168). Do you cap it to a small top-N, and scored by which channel? We are unsure whether a small panel is more sensitive because it removes easy decoys, or whether it risks selecting for whatever channel was used to pick the isomers.
  
  2. Did your in-silico fragmentation gains show up on the leaderboard, or only offline?
  
  We improved our fragmentation scorer and measured +0.065 MRR (0.324 to 0.388, paired t = 4.6, n = 241) on our isomer panel. Given a leaderboard noise band of roughly ±0.02, a single submission cannot tell us whether that transferred — ours moved 0.341 to 0.336, i.e. nothing. Did an offline fragmentation gain of comparable size move your leaderboard score, and by roughly how much?
  
  3. Is PubChem net-positive in your candidate pool?
  
  You mention "PubChem ∪ COCONUT". Our pool is training structures ∪ COCONUT only, so Class-2 molecules present in PubChem but not COCONUT are unreachable for us. A public measurement here reports full-PubChem expansion (top-50 isomers by a fingerprint model) dropping LB from 0.335 to 0.205. Do you find PubChem net-positive, and if so what keeps the extra decoys from eating the recall gain — a curated subset, a formula constraint, or ranking changes?
  
  What we measured, in exchange. Isomer panel, 241 enveda-np-examples molecules, all same-formula candidates, paired t-tests. Baseline is the common MetFrag-lite formulation: all cleavages equal, sqrt intensity, 0.01 Da tolerance, H shifts -2..+2.
  
  What helped:
  
  change
  dMRR
  t
  
  down-weight 2-bond cleavages (x0.6 vs 1-bond)
  +0.030
  +2.6
  
  linear intensity instead of sqrt
  +0.017
  +2.0
  
  tolerance 0.005 Da instead of 0.01
  +0.005
  +1.0
  
  H shifts -2..+3 instead of -2..+2
  +0.010
  +1.2
  
  all four combined
  +0.065
  +4.6
  
  What did not help:
  
  change
  dMRR
  t
  
  bond-cleavage propensity weights
  -0.002
  -0.1
  
  allowing 3-bond cleavages
  -0.031
  -2.1
  
  penalising fragments reachable many ways
  -0.015
  -2.3
  
  subtracting a chance-match baseline
  ~0
  -
  
  The propensity weights were hand-written from ordinary fragmentation chemistry: aromatic bonds nearly unbreakable, heteroatom-adjacent bonds favoured, benzylic and carbonyl-alpha positions favoured, ring bonds discounted. They did nothing, and they diluted the parsimony effect when combined with it. The pattern we read is that parsimony helps and hand-written cleavage chemistry does not — the useful signal is "how few cleavages does this candidate need", not "which bond should break".
  
  On isotopes. The MS2 peak lists retain the precursor and its M+1 / M+2, since peaks up to precursor + 2 Da are kept. Restricted to spectra where the precursor is above 30% of the base peak and the collision energy is low, log(observed M+1/M0) = 0.998 * log(theoretical) - 0.083 with residual sd 0.251 — essentially unbiased, so carbon count is recoverable to about +-25%. But it is usable for only ~41% of molecules and adds only +0.011 MRR on top of precursor mass alone, so we dropped it. M+2 is suppressed about 9x and is unusable.
    - **Udam Liyanage** (2026-09-29, votes 0)
      Thanks for sharing this, and especially for publishing the ablation with t-values. Answers below as far as I can.
      
      - Panel construction. Ours is the truth plus its best-scoring wrong same-formula candidates, capped at a few dozen and ordered by our first-stage ranking. Yes, the small panel is more sensitive: it drops the easy decoys that dilute differences between scorers. You're right about the risk, though. Whatever channel picks the rivals biases the panel toward that channel's blind spots. We deal with it by never trusting one panel: the same change has to hold on panels built from different datasets, and on the full candidate lists, before we believe it.
      
      - Offline vs leaderboard. Fragmentation gains did reach the leaderboard for us, but only the large ones, confirmed on held-out molecules the scorer never saw. Our rule of thumb: offline gains below about 0.03 were invisible on the public leaderboard, and several panel gains shrank a lot once combined with our other features. So your 0.341 → 0.336 doesn't surprise me. With about 130 public molecules, one submission can't separate +0.02 from zero. We rely on held-out molecules much more than on the leaderboard.
      
      - Candidate pool. Net positive for us, but only together with a ranking step that can handle same-formula decoys. A bigger pool raises recall and makes the isomer problem harder at the same time, so how much it helps depends mostly on how well you rank within a formula. Adding many decoys without that step can easily cost more than it gains, which fits the number you quote.
      
      Your parsimony finding matches ours: "how few cleavages does this candidate need" carried more signal than hand-written bond-propensity rules. Thanks also for the isotope analysis. It's a neat result, even if the payoff turned out small.
        - **NeckBeard** (2026-09-29, votes 0)
          Thank you — this was more useful than I expected, and one sentence of it made us go back and re-measure.
          
          Your "held-out molecules the scorer never saw" caught a real mistake of ours. We had tuned four fragmentation hyperparameters (cleavage-count weight, intensity exponent, mass tolerance, H-shift range) by grid search on the same 241-molecule panel we then reported the t-value from. So our +0.065 was a selected maximum, not an out-of-sample gain.
          
          We rebuilt panels from four other query sets, kept the configuration frozen, and re-ran:
          
          panel
          baseline MRR
          ours
          dMRR
          t
          n
          
          enveda-np-examples (tuning set)
          0.324
          0.388
          +0.065
          4.60
          241
          
          gnps
          0.576
          0.607
          +0.031
          1.99
          250
          
          riken
          0.406
          0.427
          +0.020
          1.66
          250
          
          mona + msdial
          0.385
          0.424
          +0.039
          2.82
          250
          
          massbank
          0.474
          0.481
          +0.008
          0.64
          250
          
          pooled, held out
          
          +0.023 ± 0.007
          3.45
          1000
          
          So tuning on the evaluation panel inflated the effect by about 2.8x. The direction holds on all four held-out panels, so the improvement is real, but it is +0.023, not +0.065.
          
          That lands right under your threshold — and it predicts our leaderboard result exactly. We submitted the change and went 0.341 to 0.336, i.e. nothing. Your rule of thumb ("below about 0.03 was invisible") and our honest held-out number agree, which is the most reassuring thing we've measured in this competition so far.
          
          One follow-up, if you don't mind: is your ~0.03 threshold measured on the isomer panel scale, or on full candidate lists / a predicted-LB scale? Panel MRR and full-list MRR differ by a lot in our setup (0.32 vs 0.37 for the same scorer, and panel size varies 10x between query sets), so we're not sure we're comparing against the same yardstick.
          
          On the candidate pool. Your point that a bigger pool only pays off "together with a ranking step that can handle same-formula decoys" is something we had set ourselves up to miss: we deliberately submitted the pool change and the fragmentation change as separate single-variable experiments, which by your account should show nothing for either. We have just added PubChemLite CC0 (+385,760 structures not already in COCONUT, pool 712k -> 1,074k) and will test it both alone and combined with the fragmentation scorer. Will report both numbers here.
          
          Thanks also for the panel-construction detail. We will add a capped, first-stage-ranked variant alongside the all-candidates one, and adopt your rule of requiring a change to hold on several panels before believing it. That rule alone would have saved us a submission.
        - **Udam Liyanage** (2026-09-29, votes 0)
          Great follow-up, and an honest re-measurement. The drop from +0.065 to +0.023 once the tuning panel is excluded is exactly the kind of thing that's easy to miss.
          
          On the yardstick: our ~0.03 is on the leaderboard's scale, meaning full candidate lists scored end to end, not panel MRR. It mostly reflects the public leaderboard's noise. With roughly 130 molecules, the standard error of the difference between two submissions is around 0.016, so anything much below two of those can't be told apart from zero.
          
          A panel gain shrinks twice before it reaches that scale:
          
          - Dilution. Only the molecules whose outcome is actually decided among same-formula isomers can move. In our setup that's roughly a third, so a +0.03 panel gain is worth on the order of +0.01 overall.
          
          - Overlap. Part of a new scorer's signal is usually already carried by the rest of the pipeline, so the combined gain is smaller than the gain alone.
          
          Your +0.023 held-out panel gain landing on 0.341 → 0.336 is therefore what we'd expect. As a rough conversion, multiply a panel gain by the share of your molecules that are isomer-limited, then discount for overlap.
          
          Good luck with the PubChemLite test. Testing it together with the fragmentation change is the right call.
