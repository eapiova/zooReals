{-# OPTIONS --cubical --safe --guardedness #-}

------------------------------------------------------------------------
-- Bounded Signed-Digit Reals ([-1, 1])
------------------------------------------------------------------------
--
-- This module defines the quotient type 𝕀sd of signed-digit real numbers
-- in [-1, 1], based on TWA's thesis (TypeTopology).
--
-- KEY EXPORTS:
--   𝕀sd              Quotient type of signed-digit streams
--   _≈sd_            Equivalence (same limit in ℝ)
--   stream→ℝ         Interpret streams as Cauchy reals
--   rational→stream  Convert bounded rationals to digit streams
--   approxℚ₊-cauchy  Cauchy property of stream approximations
--
-- KEY INSIGHT: Different digit sequences can represent the same real
-- (e.g., 0.111... = 1.000...). We quotient by "same limit" rather than
-- pointwise equality.
--

module Reals.SignedDigit.Safe.Bounded where

open import Cubical.Foundations.Prelude
open import Cubical.Foundations.HLevels
open import Cubical.Foundations.Function

open import Cubical.Data.Nat as ℕ using (ℕ; zero; suc; min; minComm; predℕ)
open import Cubical.Data.Nat.Order as ℕO using (splitℕ-≤; splitℕ-<; ≤-split; min-≤-left; minGLB; ≤-refl; ≤-antisym; <-weaken; ≤-k+) renaming (_≤_ to _≤ℕ_)
open import Cubical.Data.Int as ℤ using (ℤ; pos; negsuc)
open import Cubical.Data.Int.Order as ℤO using (_≤_)
open import Cubical.Data.Int.Fast.Order as ℤFastO using (zero-≤pos; 0<→ℕ₊₁; _<_; _≤_)
open import Cubical.Data.NatPlusOne
open import Cubical.Data.Sigma
open import Cubical.Data.Sum using (_⊎_; inl; inr)
open import Cubical.Data.Empty as ⊥ using (⊥; rec)
open import Cubical.Relation.Nullary using (¬_)

open import Cubical.Data.Rationals.Base as ℚB using () renaming (ℚ to ℚˢ; [_/_] to [_/_]ˢ; _∼_ to _∼ˢ_)
-- Slow ℚ is now only used for legacy/compatibility; main ℚ is Fast
open import Cubical.Data.Rationals.Properties as ℚPˢ using () -- Slow properties, renamed if needed

-- PRIMARY RATIONAL TYPE: Fast Rationals (aligned with CauchyReals library)
open import Cubical.Data.Rationals.Fast as ℚ using (ℚ; [_/_]; isSetℚ; eq/; _∼_; ℕ₊₁→ℤ)
open import Cubical.Data.Rationals.Fast.Properties as ℚP using (_·_; _+_; _-_; -_; abs; max; +IdL; +IdR; ·IdL; ·IdR; ·Assoc; ·DistL+; ·DistR+; +Comm; ·Comm; +Assoc; -Invol)
-- Import min and minComm qualified to avoid conflict with ℕ versions
import Cubical.Data.Rationals.Fast.Properties as ℚPmin using (min; minComm)
open import Cubical.Data.Rationals.Fast.Order as ℚO using (_≤_; _<_; isProp<; isProp≤; isRefl≤; isTrans≤; isTrans<; isTrans<≤; isTrans≤<; isIrrefl<; ℚ₊; _ℚ₊+_; ≤Dec; clamp; ≤→max; absFrom≤×≤; _≟_; Trichotomy; lt; eq; gt; ≤Monotone+; ≤-·o; ≤-o+; ≤-+o; <Weaken≤)

-- Aliases for fast rational types/modules (for backwards compatibility)
-- Since we use fast ℚ exclusively, these are identity mappings
ℚᶠ : Set
ℚᶠ = ℚ

-- Alias modules for compatibility with code using ℚFO/ℚFOP naming
open import Cubical.Data.Rationals.Fast.Order as ℚFO using (0<_; <→0<; inj)
open import Cubical.Data.Rationals.Fast.Order.Properties as ℚFOP using (0<sucN)

-- Fast integer modules for ordering proofs
-- Note: Cubical.Data.Int.Fast has different _·_ from Cubical.Data.Int
open import Cubical.Data.Int.Fast as ℤf using () renaming (_·_ to _·ℤf_; _+_ to _+ℤf_)
open import Cubical.Data.Int.Fast.Properties as ℤfP using () renaming (·IdL to ℤf·IdL; ·IdR to ℤf·IdR)
open import Cubical.Data.Int.Properties as ℤᶠP using () -- Slow int properties, for compatibility

-- Identity conversions (fast ℚ = ℚ)
ℚ→ℚᶠ : ℚ → ℚᶠ
ℚ→ℚᶠ q = q

ℚᶠ→ℚ : ℚᶠ → ℚ
ℚᶠ→ℚ q = q

-- Bridge lemmas: ordering conversions are identity since same type
ℚ→ℚᶠ-< : (p q : ℚ) → p ℚO.< q → ℚ→ℚᶠ p ℚO.< ℚ→ℚᶠ q
ℚ→ℚᶠ-< p q pf = pf

ℚᶠ→ℚ-< : (p q : ℚᶠ) → p ℚO.< q → ℚᶠ→ℚ p ℚO.< ℚᶠ→ℚ q  
ℚᶠ→ℚ-< p q pf = pf

ℚ<ℚᶠ→ℚ : (p q : ℚ) → p ℚO.< q → ℚ→ℚᶠ p ℚO.< q
ℚ<ℚᶠ→ℚ p q pf = pf

open import Cubical.HITs.CauchyReals.Base using (ℝ; rat; lim; _∼[_]_; rat-rat-fromAbs)
open import Cubical.HITs.CauchyReals.Closeness using (refl∼; isSetℝ)
open import Cubical.HITs.CauchyReals.Order as ℝO using (_≤ᵣ_; clampᵣ; ≤ℚ→≤ᵣ)
open import Cubical.HITs.CauchyReals.Inverse as ℝInv using (clampᵣ∈ℚintervalℙ)

open import Cubical.Data.Rationals.Fast.Order.Properties as ℚOP using (invℚ₊; ceilℚ₊; invℚ₊-<-invℚ₊; invℚ₊-invol; maxDist; absComm-; clampDist; clam∈ℚintervalℙ; ∈ℚintervalℙ→clam≡)
open import Cubical.Data.Nat.Mod as ℕMod using (log2ℕ)

open import Cubical.HITs.SetQuotients as SQ hiding ([_])

open import Cubical.Relation.Nullary using (Dec; yes; no)

open import Reals.SignedDigit.Safe.Core

------------------------------------------------------------------------
-- Helper Lemmas
------------------------------------------------------------------------

-- Convert strict to non-strict inequality for Fast ℚ
-- Uses <Weaken≤ from Fast ℚ Order module
open import Cubical.Data.Rationals.Fast.Order as ℚFO' using (<Weaken≤)

weak-ineq : ∀ {x y : ℚ} → x ℚO.< y → x ℚO.≤ y
weak-ineq {x} {y} = <Weaken≤ x y

------------------------------------------------------------------------
-- Rational approximations
------------------------------------------------------------------------

-- 2^n as ℕ
2^ℕ : ℕ → ℕ
2^ℕ zero = 1
2^ℕ (suc n) = 2 ℕ.· 2^ℕ n

-- Show 2 ^ n ≡ 2^ℕ n where _^_ is from Cubical.Data.Nat.Base
-- This is needed because log2ℕ uses _^_ from that module
open import Cubical.Data.Nat.Base as ℕBase using (_^_)

2^≡2^ℕ : (n : ℕ) → 2 ℕBase.^ n ≡ 2^ℕ n
2^≡2^ℕ zero = refl
2^≡2^ℕ (suc n) = cong (2 ℕ.·_) (2^≡2^ℕ n)

-- 2^n as ℕ₊₁ (for use as denominator)
-- Using 2^ℕ-pos to avoid `with` on 2^ℕ n (which causes stuck terms during type checking)
-- We define this AFTER 2^ℕ-pos is proven (below)

-- Helper lemmas for geometric series bounds
open import Cubical.Data.Nat.Properties as ℕP using (+-zero; +-suc; +-comm; ·-comm; snotz)
open import Cubical.Data.Int.Properties as ℤP using (pos+)

-- 2^ℕ is always positive: 2^n = suc m for some m
-- This is needed to work with 2^ℕ₊₁ without stuck terms
2·x≡x+x : (x : ℕ) → 2 ℕ.· x ≡ x ℕ.+ x
2·x≡x+x x = cong (x ℕ.+_) (ℕP.+-zero x)

-- Helper: suc (predℕ n) ≡ n for nonzero n
suc-pred : (n : ℕ) → ¬ (n ≡ 0) → suc (predℕ n) ≡ n
suc-pred zero n≢0 = ⊥.rec (n≢0 refl)
suc-pred (suc n) _ = refl

-- 2^ℕ n is never zero
2^ℕ-nonzero : (n : ℕ) → ¬ (2^ℕ n ≡ 0)
2^ℕ-nonzero zero = ℕP.snotz
2^ℕ-nonzero (suc n) p = 2^ℕ-nonzero n (absurd-2·m (2^ℕ n) p)
  where
    -- If 2 · m = 0, then m = 0 (since 2 · suc k is never 0)
    absurd-2·m : (m : ℕ) → 2 ℕ.· m ≡ 0 → m ≡ 0
    absurd-2·m zero _ = refl
    absurd-2·m (suc m) p = ⊥.rec (ℕP.snotz p)

-- OPTIMIZED: Witness is computed directly via predℕ, proof is separate
-- This makes 2^ℕ₊₁ compute without forcing the proof term
2^ℕ-pos : (n : ℕ) → Σ[ m ∈ ℕ ] 2^ℕ n ≡ suc m
2^ℕ-pos n = predℕ (2^ℕ n) , sym (suc-pred (2^ℕ n) (2^ℕ-nonzero n))

-- 2^n ≤ 2^(suc n) in ℕ (for monotonicity of inv2^)
2^-mono-ℕ : (n : ℕ) → 2^ℕ n ≤ℕ 2^ℕ (suc n)
2^-mono-ℕ n = 2^ℕ n , sym (2·x≡x+x (2^ℕ n))

-- Convert ℕ≤ to ℤ≤ for pos (slow integers - needed for rational ordering)
pos-mono : {m n : ℕ} → m ≤ℕ n → ℤ.pos m ℤO.≤ ℤ.pos n
pos-mono {m} {n} (k , k+m≡n) = k , sym (ℤP.pos+ m k) ∙ cong ℤ.pos (ℕP.+-comm m k ∙ k+m≡n)

-- Convert ℕ≤ to Fast ℤ≤ for pos (needed for Fast ℚ ordering)
-- Fast ℤ `_≤_` is: m ≤ n = Σ k. m +ℤf pos k ≡ n
-- For pos m and pos n with fast +: pos m +ℤf pos k = pos (m + k) by fast int addition
pos-monoFast : {m n : ℕ} → m ≤ℕ n → ℤ.pos m ℤFastO.≤ ℤ.pos n
pos-monoFast {m} {n} (k , k+m≡n) = k , cong ℤ.pos (ℕP.+-comm m k ∙ k+m≡n)

-- NEW 2^ℕ₊₁ definition using 2^ℕ-pos (avoids stuck with-terms)
2^ℕ₊₁ : ℕ → ℕ₊₁
2^ℕ₊₁ n = 1+ (fst (2^ℕ-pos n))

-- Key property: ℕ₊₁→ℕ (2^ℕ₊₁ n) ≡ 2^ℕ n
-- This is the inverse of the suc from 2^ℕ-pos
open import Cubical.Data.NatPlusOne as NP1 using (ℕ₊₁→ℕ)
2^ℕ₊₁-unfold : (n : ℕ) → NP1.ℕ₊₁→ℕ (2^ℕ₊₁ n) ≡ 2^ℕ n
2^ℕ₊₁-unfold n = sym (snd (2^ℕ-pos n))

-- ℕ₊₁→ℤ (2^ℕ₊₁ n) = pos (ℕ₊₁→ℕ (2^ℕ₊₁ n)) = pos (2^ℕ n) by 2^ℕ₊₁-unfold
-- Needed for 2·inv2^-suc-rel and inv2^-mono
open import Cubical.Data.Rationals.Base as ℚB using ()
ℕ₊₁→ℤ-2^ℕ₊₁ : (n : ℕ) → ℚ.ℕ₊₁→ℤ (2^ℕ₊₁ n) ≡ ℤ.pos (2^ℕ n)
ℕ₊₁→ℤ-2^ℕ₊₁ n = cong ℤ.pos (2^ℕ₊₁-unfold n)

-- Convert digit to rational (Fast ℚ): -1 ↦ -1, 0 ↦ 0, +1 ↦ +1
digitToℚ : Digit → ℚ
digitToℚ -1d = [ negsuc 0 / 1+ 0 ]   -- -1/1
digitToℚ 0d  = [ pos 0 / 1+ 0 ]      -- 0/1
digitToℚ +1d = [ pos 1 / 1+ 0 ]      -- 1/1

-- Single digit contribution at position i: dᵢ / 2^(i+1) (in Fast ℚ)
digitContrib : Digit → ℕ → ℚ
digitContrib d i = (digitToℚ d) · [ pos 1 / 2^ℕ₊₁ (suc i) ]

approx : 𝟛ᴺ → ℕ → ℚ
approx s zero = digitContrib (s ! zero) zero
approx s (suc n) = approx s n ℚP.+ digitContrib (s ! suc n) (suc n)

------------------------------------------------------------------------
-- Interpretation into HoTT Cauchy reals
------------------------------------------------------------------------

-- Since approx now returns Fast ℚ directly, no conversion is needed

-- Modulus function: given ε > 0, find n such that 1/2^n < ε
--
-- The signed-digit series has |tail from n| ≤ 1/2^n.
-- So to achieve ε-precision, we need n such that 1/2^n < ε.
--
-- Strategy: Use ceilℚ₊ and log2ℕ to construct 1/2^n < ε directly
-- 1. invℚ₊ ε gives 1/ε
-- 2. ceilℚ₊ (invℚ₊ ε) gives k with 1/ε < k
-- 3. log2ℕ (ℕ₊₁→ℕ k) gives n with k ≤ 2^n (actually k < 2^n from Least)
-- 4. Then 1/ε < k < 2^n, so 1/2^n < ε
-- 5. Adding 1: inv2^(n) = 1/2^{n+1} < 1/2^n < ε
ℚ₊→ℕ : ℚ₊ → ℕ
ℚ₊→ℕ ε = 
  let k = fst (ℚOP.ceilℚ₊ (ℚOP.invℚ₊ ε))  -- k : ℕ₊₁ with 1/ε < k
      n = fst (ℕMod.log2ℕ (ℕ₊₁→ℕ k))       -- n : ℕ with k < 2^n
  in suc n  -- inv2^(suc n) = 1/2^{n+2} < 1/2^{n+1} = inv2^n < 1/2^n < ε


-- Approximation indexed by precision (now just uses approx directly since it returns ℚ)
approxℚ₊ : 𝟛ᴺ → ℚ₊ → ℚ
approxℚ₊ s ε = approx s (ℚ₊→ℕ ε)



-- The approximation sequence is Cauchy
-- Using the tail bound: |approx s m - approx s n| ≤ 1/2^{min m n}
-- With proper modulus: 1/2^{ℚ₊→ℕ δ} < δ and 1/2^{ℚ₊→ℕ ε} < ε
-- So 1/2^{min(ℚ₊→ℕ δ, ℚ₊→ℕ ε)} < max(δ, ε) < δ + ε
--
-- Proof strategy for approxℚ₊-cauchy:
-- 1. Let m = ℚ₊→ℕ δ, n = ℚ₊→ℕ ε
-- 2. By tail-bound-sym: |approx s m - approx s n| ≤ inv2^ (min m n) (slow ℚ)
-- 3. By modulus-correct: inv2^ m < δ and inv2^ n < ε (after conversion)
-- 4. So inv2^ (min m n) ≤ min(inv2^ m, inv2^ n) < min(δ, ε) ≤ δ + ε
-- 5. The bound transfers to fast ℚ
-- 6. Use rat-rat-fromAbs to construct the ∼[_] witness
--
-- The full proof uses:
-- 1. tail-bound-sym gives: |approx s m - approx s n| ≤ inv2^ (min m n) in slow ℚ
-- 2. modulus-correct gives: inv2^ (ℚ₊→ℕ ε) < ε in slow ℚ  
-- 3. The closeness relation is reflexive when the bound holds

-- First we need some helper lemmas for the proof
-- Note: Since this file uses fast ℚ (from Cubical.Data.Rationals.Fast) exclusively,
-- abs and subtraction work directly without conversion.

-- Helper imports for renamed operations (for clarity in proofs)
open import Cubical.Data.Rationals.Fast.Properties as ℚFP using () renaming (_+_ to _+ᶠ_; _-_ to _-ᶠ_; -_ to ℚF-_; abs to absᶠ; max to maxᶠ)




-- Helper: min of two moduli
min-mod : (δ ε : ℚ₊) → ℕ
min-mod δ ε = min (ℚ₊→ℕ δ) (ℚ₊→ℕ ε)

-- The Cauchy property uses the library's closeness relation from CauchyReals.Closeness
-- rat q ∼[ ε ] rat r means |q - r| < ε in fast ℚ
-- We use refl∼ for the reflexive case and need to construct the bound proof

-- For the general case, we need to show:
-- |approxF s (ℚ₊→ℕ δ) - approxF s (ℚ₊→ℕ ε)| < δ + ε (in fast ℚ)
--
-- From tail-bound-sym, we have (in slow ℚ):
-- |approx s m - approx s n| ≤ inv2^ (min m n)
--
-- From modulus-correct:
-- inv2^ (ℚ₊→ℕ δ) < δ (after ℚᶠ→ℚ conversion)
-- inv2^ (ℚ₊→ℕ ε) < ε (after ℚᶠ→ℚ conversion)
--
-- Since min (ℚ₊→ℕ δ) (ℚ₊→ℕ ε) ≥ one of them, we get:
-- inv2^ (min m n) ≤ inv2^ m < δ  or  inv2^ (min m n) ≤ inv2^ n < ε
-- So |approx s m - approx s n| < δ + ε (using ≤ and < with strict bound on one side)

-- The closeness relation from the library is:
-- rat q ∼[ ε ] rat r = absᶠ (q -ᶠ r) <ᶠ ε
-- where absᶠ and -ᶠ are fast ℚ operations

-- NOTE: stream→ℝ, _≈sd_, 𝕀sd and related definitions are at the END of the file
-- after approxℚ₊-cauchy is proved constructively.

-- The old strong version is kept for backwards compatibility
_≈sd-strong_ : 𝟛ᴺ → 𝟛ᴺ → Type₀
x ≈sd-strong y = (n : ℕ) → approx x n ≡ approx y n

-- Constant streams
-- The constant zero stream: 0, 0, 0, ...
-- Represents: Σᵢ 0/2^(i+1) = 0
zeroStream : 𝟛ᴺ
zeroStream = repeat 0d

-- The constant +1 stream: +1, +1, +1, ...
-- Represents: Σᵢ 1/2^(i+1) = 1
oneStream : 𝟛ᴺ
oneStream = repeat +1d

-- The constant -1 stream: -1, -1, -1, ...
-- Represents: Σᵢ -1/2^(i+1) = -1
negOneStream : 𝟛ᴺ
negOneStream = repeat -1d


------------------------------------------------------------------------
-- Tail bound lemmas
------------------------------------------------------------------------

-- The key property of signed-digit approximations:
-- The difference between partial sums at indices m and n is bounded by
-- the tail of a geometric series.

-- Helper: 1 / 2^{n+1} as a rational
inv2^ : ℕ → ℚ
inv2^ n = [ pos 1 / 2^ℕ₊₁ (suc n) ]

-- 0 as a rational
0ℚ : ℚ
0ℚ = [ pos 0 / 1+ 0 ]


------------------------------------------------------------------------
-- Lemmas for tail-bound proof
------------------------------------------------------------------------

-- |digitToℚ d| ≤ 1 for any digit d
-- Since digitToℚ ∈ {-1, 0, 1}, this is trivially true
-- Proof by case analysis on d
-- Note: abs(-1) = max(-1, 1) = 1, abs(0) = max(0,0) = 0, abs(1) = max(1,-1) = 1

-- 1 as a rational
1ℚ : ℚ
1ℚ = [ pos 1 / 1+ 0 ]

-- -1 as a rational  
-1ℚ : ℚ
-1ℚ = [ negsuc 0 / 1+ 0 ]

-- 2 as a rational
2ℚ : ℚ
2ℚ = [ pos 2 / 1+ 0 ]

-- Helper: x + x ≡ 2 · x for rationals
-- Using ℚP.x+x≡2x from the library
x+x≡2·x : (x : ℚ) → x ℚP.+ x ≡ 2ℚ ℚP.· x
x+x≡2·x = ℚP.x+x≡2x

------------------------------------------------------------------------
-- Rational to Stream Conversion (Moved from Embedding.agda)
------------------------------------------------------------------------

-- Constants 
-1/3ℚ : ℚ
-1/3ℚ = [ negsuc 0 / 1+ 2 ]

+1/3ℚ : ℚ
+1/3ℚ = [ pos 1 / 1+ 2 ]

-- Clamp a rational to [-1, 1]
clampℚ : ℚ → ℚ
clampℚ q = ℚP.max -1ℚ (ℚPmin.min 1ℚ q)

-- Select a digit based on a bounded approximation.
selectDigitFromℚ-raw : ℚ → Digit
selectDigitFromℚ-raw q with -1/3ℚ ℚO.≟ q
... | ℚO.gt _ = -1d
... | ℚO.eq _ = 0d
... | ℚO.lt _ with +1/3ℚ ℚO.≟ q
...   | ℚO.lt _ = +1d
...   | ℚO.eq _ = 0d
...   | ℚO.gt _ = 0d

selectDigitFromℚ : ℚ → Digit
selectDigitFromℚ q = selectDigitFromℚ-raw (clampℚ q)

-- Alias for consistency with Embedding usage
+1ℚ : ℚ
+1ℚ = 1ℚ

-- Fixed interval fact used throughout clamp proofs.
-1≤+1 : -1ℚ ℚO.≤ +1ℚ
-1≤+1 = ℚO.inj (2 , refl)

clampℚ≡clamp : (q : ℚ) → clampℚ q ≡ ℚO.clamp -1ℚ +1ℚ q
clampℚ≡clamp q =
  ℚOP.minDistMax -1ℚ +1ℚ q
  ∙ cong (λ m → ℚPmin.min m (ℚP.max -1ℚ q)) (ℚO.≤→max -1ℚ +1ℚ -1≤+1)
  ∙ ℚPmin.minComm +1ℚ (ℚP.max -1ℚ q)

clampℚ-idem : (q : ℚ) → clampℚ (clampℚ q) ≡ clampℚ q
clampℚ-idem q =
  clampℚ≡clamp (clampℚ q)
  ∙ cong (ℚO.clamp -1ℚ +1ℚ) (clampℚ≡clamp q)
  ∙ sym (ℚOP.∈ℚintervalℙ→clam≡ -1ℚ +1ℚ (ℚO.clamp -1ℚ +1ℚ q)
            (ℚOP.clam∈ℚintervalℙ -1ℚ +1ℚ -1≤+1 q))
  ∙ sym (clampℚ≡clamp q)

-- Next state
nextStateℚ : ℚ → Digit → ℚ
nextStateℚ q d = (2ℚ ℚP.· clampℚ q) ℚP.- digitToℚ d

-- Coinductively build a stream
rational→stream : ℚ → 𝟛ᴺ
head (rational→stream q) = selectDigitFromℚ q
tail (rational→stream q) = rational→stream (nextStateℚ q (selectDigitFromℚ q))

-- Helper: The n-th remainder
-- Helper: The n-th remainder (q_n where q_0 = q, q_{n+1} = 2q_n - d_n)
remainderₙ : ℚ → ℕ → ℚ
remainderₙ q zero = q
remainderₙ q (suc n) = nextStateℚ (remainderₙ q n) (selectDigitFromℚ (remainderₙ q n))


-- Key lemma: 2 · inv2^(suc n) = inv2^ n
-- i.e., 2 · [1/2^{n+2}] = [1/2^{n+1}]
-- 
-- In the quotient, this is: [2/1] · [1/2^{n+2}] computes via multiplication to some form.
-- Then we need to show equivalence to [1/2^{n+1}].
--
-- The key insight: [2·1 / 1·2^{n+2}] = [2 / 2^{n+2}]
-- And [2 / 2^{n+2}] ∼ [1 / 2^{n+1}] iff 2·2^{n+1} = 1·2^{n+2} = 2^{n+2}
-- But 2·2^{n+1} = 2^{n+2} is definitional by 2^ℕ (suc (suc n)) = 2 · 2^ℕ (suc n)!
--
-- Proof strategy:
-- 1. Multiplication in ℚ is defined via onCommonDenomSym which computes on representatives
-- 2. For [a/b] · [c/d], the numerator is a·c and denominator is b·d  
-- 3. So [2/1] · [1/2^{n+2}] = [2·1 / 1·2^{n+2}] = [2 / 2^{n+2}]
-- 4. We need [2 / 2^{n+2}] ≡ [1 / 2^{n+1}]
-- 5. By eq/, this requires proving: 2 · 2^{n+1} ≡ 1 · 2^{n+2} (in ℤ)
-- 6. LHS = 2 · 2^{n+1}, RHS = 2^{n+2} = 2 · 2^{n+1} (definitional!)

-- Auxiliary: ℕ₊₁ multiplication computes correctly
open import Cubical.Data.NatPlusOne as NP1 using (_·₊₁_)
open import Cubical.Data.NatPlusOne.Properties using (·₊₁-identityˡ)

-- The core computation: 2 · 2^{n+1} ≡ 2^{n+2} as ℕ  
2·2^n≡2^suc-n : (n : ℕ) → 2 ℕ.· 2^ℕ n ≡ 2^ℕ (suc n)
2·2^n≡2^suc-n n = refl

-- ℕ₊₁→ℕ of the product 1+ 0 ·₊₁ 2^ℕ₊₁ n
-- We need: ℕ₊₁→ℕ ((1+ 0) ·₊₁ 2^ℕ₊₁ (suc n)) ≡ 2^ℕ (suc n)
denom-prod-lem : (n : ℕ) → NP1.ℕ₊₁→ℕ ((1+ 0) NP1.·₊₁ 2^ℕ₊₁ (suc n)) ≡ 2^ℕ (suc n)
denom-prod-lem n = cong NP1.ℕ₊₁→ℕ (·₊₁-identityˡ (2^ℕ₊₁ (suc n))) ∙ 2^ℕ₊₁-unfold (suc n)

-- The ∼ relation for rationals: (a,b) ∼ (c,d) means a·d ≡ c·b (in ℤ)
-- For [2 / 2^{n+2}] ∼ [1 / 2^{n+1}]:
-- Need: pos 2 · pos (2^ℕ (suc n)) ≡ pos 1 · pos (2^ℕ (suc (suc n)))
-- i.e.: pos (2 · 2^ℕ (suc n)) ≡ pos (2^ℕ (suc (suc n)))
-- i.e.: pos (2^ℕ (suc (suc n))) ≡ pos (2^ℕ (suc (suc n)))  ✓ (by 2·2^n≡2^suc-n)

open import Cubical.Data.Int.Properties as ℤP using (pos·pos)

-- Import fast integer module for ·≡·f bridge between standard and fast multiplication
open import Cubical.Data.Int.Fast.Properties as ℤfP using (·≡·f)

2·inv2^-suc-rel : (n : ℕ) → ℚ._∼_ (pos 2 , 2^ℕ₊₁ (suc (suc n))) (pos 1 , 2^ℕ₊₁ (suc n))
2·inv2^-suc-rel n = 
  -- Need: pos 2 ·ℤf ℕ₊₁→ℤ (2^ℕ₊₁ (suc n)) ≡ pos 1 ·ℤf ℕ₊₁→ℤ (2^ℕ₊₁ (suc (suc n)))
  -- where ·ℤf is Fast integer multiplication from Cubical.Data.Int.Fast
  -- Fast: pos n ·ℤf pos m = pos (n ℕ.· m)
  -- So LHS = pos (2 ℕ.· 2^ℕ (suc n)) and RHS = pos (1 ℕ.· 2^ℕ (suc (suc n)))
  -- Need: 2 ℕ.· 2^ℕ (suc n) ≡ 1 ℕ.· 2^ℕ (suc (suc n))
  -- LHS = 2^ℕ (suc n) + 2^ℕ (suc n) = 2^ℕ (suc (suc n))  [by 2·x≡x+x and 2^ℕ def]
  -- RHS = 2^ℕ (suc (suc n)) + 0 = 2^ℕ (suc (suc n))      [by 1·n = n + 0]
  let
    -- LHS chain
    lhs-step1 : (pos 2 ·ℤf ℚ.ℕ₊₁→ℤ (2^ℕ₊₁ (suc n))) ≡ (pos 2 ·ℤf pos (2^ℕ (suc n)))
    lhs-step1 = cong (pos 2 ·ℤf_) (ℕ₊₁→ℤ-2^ℕ₊₁ (suc n))
    
    -- pos 2 ·ℤf pos m = pos (2 ℕ.· m) definitionally for fast ints
    -- And 2^ℕ (suc (suc n)) = 2 ℕ.· 2^ℕ (suc n) by definition
    -- So pos 2 ·ℤf pos (2^ℕ (suc n)) ≡ pos (2^ℕ (suc (suc n))) should be refl
    -- But Agda normalizes differently, so we need to prove it via 2·x≡x+x
    lhs-step2-helper : 2 ℕ.· 2^ℕ (suc n) ≡ 2^ℕ (suc (suc n))
    lhs-step2-helper = refl
    
    lhs-step2 : (pos 2 ·ℤf pos (2^ℕ (suc n))) ≡ pos (2^ℕ (suc (suc n)))
    lhs-step2 = cong pos lhs-step2-helper
    
    lhs : (pos 2 ·ℤf ℚ.ℕ₊₁→ℤ (2^ℕ₊₁ (suc n))) ≡ pos (2^ℕ (suc (suc n)))
    lhs = lhs-step1 ∙ lhs-step2
    
    -- RHS chain  
    rhs-step1 : (pos 1 ·ℤf ℚ.ℕ₊₁→ℤ (2^ℕ₊₁ (suc (suc n)))) ≡ (pos 1 ·ℤf pos (2^ℕ (suc (suc n))))
    rhs-step1 = cong (pos 1 ·ℤf_) (ℕ₊₁→ℤ-2^ℕ₊₁ (suc (suc n)))
    
    -- pos 1 ·ℤf pos m = pos (1 ℕ.· m) = pos (m + 0) definitionally
    -- And m + 0 ≡ m by +-zero
    rhs-step2 : (pos 1 ·ℤf pos (2^ℕ (suc (suc n)))) ≡ pos (2^ℕ (suc (suc n)))
    rhs-step2 = cong pos (ℕP.+-zero (2^ℕ (suc (suc n))))
    
    rhs : (pos 1 ·ℤf ℚ.ℕ₊₁→ℤ (2^ℕ₊₁ (suc (suc n)))) ≡ pos (2^ℕ (suc (suc n)))
    rhs = rhs-step1 ∙ rhs-step2
  in lhs ∙ sym rhs

-- Now we need to show that 2ℚ · inv2^(suc n) actually computes to [2 / 2^{n+2}]
-- and then use eq/ to get the path to [1 / 2^{n+1}]
--
-- Multiplication in ℚ via OnCommonDenomSym: [a/b] · [c/d] = [a·c / b·d]
-- 2ℚ = [pos 2 / 1+ 0], inv2^ (suc n) = [pos 1 / 2^ℕ₊₁ (suc (suc n))]
-- So 2ℚ · inv2^ (suc n) = [pos 2 · pos 1 / (1+ 0) ·₊₁ 2^ℕ₊₁ (suc (suc n))]
--                       = [pos 2 / 2^ℕ₊₁ (suc (suc n))]  (by ·IdR and ·₊₁-identityˡ)
-- And [pos 2 / 2^ℕ₊₁ (suc (suc n))] ≡ [pos 1 / 2^ℕ₊₁ (suc n)] by 2·inv2^-suc-rel
--
-- Step 1: 2ℚ · inv2^ (suc n) ≡ [pos 2 / 2^ℕ₊₁ (suc (suc n))]
2·inv2^-suc-step1 : (n : ℕ) → 2ℚ ℚP.· inv2^ (suc n) ≡ [ pos 2 / 2^ℕ₊₁ (suc (suc n)) ]
2·inv2^-suc-step1 n = cong₂ (λ num den → [ num / den ])
  (ℤP.·IdR (pos 2))
  (·₊₁-identityˡ (2^ℕ₊₁ (suc (suc n))))

-- Step 2: [pos 2 / 2^ℕ₊₁ (suc (suc n))] ≡ [pos 1 / 2^ℕ₊₁ (suc n)]
2·inv2^-suc-step2 : (n : ℕ) → [ pos 2 / 2^ℕ₊₁ (suc (suc n)) ] ≡ inv2^ n
2·inv2^-suc-step2 n = eq/ (pos 2 , 2^ℕ₊₁ (suc (suc n))) (pos 1 , 2^ℕ₊₁ (suc n)) (2·inv2^-suc-rel n)

2·inv2^-suc : (n : ℕ) → 2ℚ ℚP.· inv2^ (suc n) ≡ inv2^ n
2·inv2^-suc n = 2·inv2^-suc-step1 n ∙ 2·inv2^-suc-step2 n

-- IMPORTANT: Doubling lemma for geometric series
-- inv2^ n = inv2^(suc n) + inv2^(suc n)
-- i.e., 1/2^{n+1} = 1/2^{n+2} + 1/2^{n+2} = 2/2^{n+2} = 1/2^{n+1} ✓
--
-- Proof: inv2^(suc n) + inv2^(suc n) = 2 · inv2^(suc n) = inv2^ n
--        by x+x≡2·x and 2·inv2^-suc
inv2^-double : (n : ℕ) → inv2^ n ≡ inv2^ (suc n) ℚP.+ inv2^ (suc n)
inv2^-double n = sym (x+x≡2·x (inv2^ (suc n)) ∙ 2·inv2^-suc n)



-- abs(-1) = max(-1, -(-1)) = max(-1, 1) = 1
abs-neg1 : abs -1ℚ ≡ 1ℚ
abs-neg1 = refl  -- max(-1, 1) computes to 1

-- abs(0) = max(0, -0) = max(0, 0) = 0
-- We use maxIdem : max x x ≡ x
abs-zero : abs 0ℚ ≡ 0ℚ
abs-zero = ℚP.maxIdem 0ℚ

-- abs(1) = max(1, -1) = 1
abs-one : abs 1ℚ ≡ 1ℚ
abs-one = refl  -- max(1, -1) computes to 1

-- 0 ≤ 1 in ℚ
-- For a/b ≤ c/d we need a·d ℤ.≤ c·b
-- Here: 0·1 = 0 ℤ.≤ 1·1 = 1, which follows from zero-≤pos
-- The Fast ℚ ordering uses a record, so we wrap with inj constructor
0≤1ℚ : 0ℚ ℚO.≤ 1ℚ
0≤1ℚ = ℚO.inj ℤFastO.zero-≤pos

digitToℚ-bound : (d : Digit) → abs (digitToℚ d) ℚO.≤ 1ℚ
digitToℚ-bound -1d = subst (ℚO._≤ 1ℚ) (sym abs-neg1) (isRefl≤ 1ℚ)  -- abs(-1) = 1 ≤ 1
digitToℚ-bound 0d  = subst (ℚO._≤ 1ℚ) (sym abs-zero) 0≤1ℚ          -- abs(0) = 0 ≤ 1
digitToℚ-bound +1d = subst (ℚO._≤ 1ℚ) (sym abs-one) (isRefl≤ 1ℚ)   -- abs(1) = 1 ≤ 1

-- |digitContrib d i| ≤ 1/2^{i+1}
-- Since digitContrib d i = digitToℚ d · 1/2^{i+1} and |digitToℚ d| ≤ 1
-- We have |d · (1/2^{i+1})| = |d| · (1/2^{i+1}) ≤ 1 · (1/2^{i+1}) = 1/2^{i+1}

-- Helper: 0 · x = 0 (using ·AnnihilL from the library)
·ZeroL : (x : ℚ) → 0ℚ · x ≡ 0ℚ
·ZeroL = ℚP.·AnnihilL

-- Helper: 1 · x = x (using ·IdL from the library)
·OneL : (x : ℚ) → 1ℚ · x ≡ x
·OneL = ·IdL

-- Helper: (-1) · x = -x (proof by computation on representatives)
·NegOneL : (x : ℚ) → -1ℚ · x ≡ - x
·NegOneL = SQ.elimProp (λ _ → ℚ.isSetℚ _ _) (λ _ → refl)

-- Helper: 0 ≤ inv2^ i (positivity of 1/2^n)
-- For 0/1 ≤ 1/2^(i+1), need 0·2^(i+1) ℤ.≤ 1·1
-- Since 0·k = 0 for any k, this is 0 ℤ.≤ 1, i.e., zero-≤pos
-- The Fast ℚ ordering uses a record, so we wrap with inj constructor
0≤inv2^ : (i : ℕ) → 0ℚ ℚO.≤ inv2^ i
0≤inv2^ i = ℚO.inj ℤFastO.zero-≤pos

-- Helper: abs 0 = 0
abs-0ℚ : abs 0ℚ ≡ 0ℚ
abs-0ℚ = ℚP.maxIdem 0ℚ

-- Helper: abs (-x) = abs x
abs-neg : (x : ℚ) → abs (- x) ≡ abs x
abs-neg x = cong (max (- x)) (ℚP.-Invol x) ∙ ℚP.maxComm (- x) x

-- Helper: for positive x, abs x = x
-- We need this for inv2^ which is always positive
-- Strategy: show -x ≤ x when 0 ≤ x, then use ≤→max



-- Actually, let's use a simpler approach: subst with +InvL
-- From 0 ≤ x, using ≤-o+: (-x) + 0 ≤ (-x) + x
-- Simplify: -x ≤ 0
0≤x→-x≤0' : (x : ℚ) → 0ℚ ℚO.≤ x → (- x) ℚO.≤ 0ℚ
0≤x→-x≤0' x 0≤x = subst2 ℚO._≤_ p1 p2 step
  where
    step : ((- x) + 0ℚ) ℚO.≤ ((- x) + x)
    step = ℚO.≤-o+ 0ℚ x (- x) 0≤x
    p1 : (- x) + 0ℚ ≡ - x
    p1 = ℚP.+IdR (- x)
    p2 : (- x) + x ≡ 0ℚ
    p2 = ℚP.+InvL x

-- Helper: 0 ≤ x implies -x ≤ x (by transitivity through 0)
0≤x→-x≤x : (x : ℚ) → 0ℚ ℚO.≤ x → (- x) ℚO.≤ x
0≤x→-x≤x x 0≤x = isTrans≤ (- x) 0ℚ x (0≤x→-x≤0' x 0≤x) 0≤x

-- abs x = max x (-x), and we want: if 0 ≤ x then abs x = x
-- Using maxComm: max x (-x) = max (-x) x
-- Using ≤→max: if -x ≤ x then max (-x) x = x
abs-pos-inv2^ : (i : ℕ) → abs (inv2^ i) ≡ inv2^ i
abs-pos-inv2^ i = 
  ℚP.maxComm (inv2^ i) (- inv2^ i) ∙ 
  ℚO.≤→max (- inv2^ i) (inv2^ i) (0≤x→-x≤x (inv2^ i) (0≤inv2^ i))

digitContrib-bound : (d : Digit) (i : ℕ) → abs (digitContrib d i) ℚO.≤ inv2^ i
digitContrib-bound -1d i = 
  -- digitContrib -1d i = (-1) · inv2^ i
  -- Need: abs((-1) · inv2^ i) ≤ inv2^ i
  -- We have: (-1) · inv2^ i ≡ -(inv2^ i)  (by ·NegOneL)
  -- So: abs((-1) · inv2^ i) ≡ abs(-(inv2^ i)) ≡ abs(inv2^ i) ≡ inv2^ i
  let p2 : -1ℚ · inv2^ i ≡ - inv2^ i
      p2 = ·NegOneL (inv2^ i)
      p3 : abs (-1ℚ · inv2^ i) ≡ abs (- inv2^ i)
      p3 = cong abs p2
      p4 : abs (- inv2^ i) ≡ abs (inv2^ i)
      p4 = abs-neg (inv2^ i)
      p5 : abs (inv2^ i) ≡ inv2^ i
      p5 = abs-pos-inv2^ i
      path : abs (digitContrib -1d i) ≡ inv2^ i
      path = p3 ∙ p4 ∙ p5
  in subst (ℚO._≤ inv2^ i) (sym path) (isRefl≤ (inv2^ i))
digitContrib-bound 0d i =
  -- digitContrib 0d i = 0 · inv2^ i = 0
  -- abs 0 = 0 ≤ inv2^ i
  let p2 : 0ℚ · inv2^ i ≡ 0ℚ
      p2 = ·ZeroL (inv2^ i)
      p4 : abs (0ℚ · inv2^ i) ≡ abs 0ℚ
      p4 = cong abs p2
      path : abs (digitContrib 0d i) ≡ 0ℚ
      path = p4 ∙ abs-0ℚ
  in subst (ℚO._≤ inv2^ i) (sym path) (0≤inv2^ i)
digitContrib-bound +1d i =
  -- digitContrib +1d i = 1 · inv2^ i = inv2^ i
  -- abs(inv2^ i) = inv2^ i ≤ inv2^ i (reflexive)
  let p2 : 1ℚ · inv2^ i ≡ inv2^ i
      p2 = ·OneL (inv2^ i)
      p4 : abs (1ℚ · inv2^ i) ≡ abs (inv2^ i)
      p4 = cong abs p2
      p5 : abs (inv2^ i) ≡ inv2^ i
      p5 = abs-pos-inv2^ i
      path : abs (digitContrib +1d i) ≡ inv2^ i
      path = p4 ∙ p5
  in subst (ℚO._≤ inv2^ i) (sym path) (isRefl≤ (inv2^ i))

-- Helper: inv2^ (suc k) ≤ inv2^ k (the sequence is decreasing)
-- The inequality [1 / 2^{k+2}] ≤ [1 / 2^{k+1}] unfolds to (in Fast ℚ ordering):
--   pos 1 ·ℤf ℕ₊₁→ℤ (2^ℕ₊₁ (suc k)) ℤFastO.≤ pos 1 ·ℤf ℕ₊₁→ℤ (2^ℕ₊₁ (suc (suc k)))
-- Using ·IdL: pos 1 ·ℤf x ≡ x, this is:
--   ℕ₊₁→ℤ (2^ℕ₊₁ (suc k)) ℤFastO.≤ ℕ₊₁→ℤ (2^ℕ₊₁ (suc (suc k)))
-- Using ℕ₊₁→ℤ (2^ℕ₊₁ n) = pos (2^ℕ n), this is:
--   pos (2^ℕ (suc k)) ℤFastO.≤ pos (2^ℕ (suc (suc k)))
-- Which is pos-monoFast (2^-mono-ℕ (suc k))

inv2^-mono : (k : ℕ) → inv2^ (suc k) ℚO.≤ inv2^ k
inv2^-mono k = ℚO.inj (subst2 ℤFastO._≤_ p1 p2 (pos-monoFast (2^-mono-ℕ (suc k))))
  where
    -- inv2^ (suc k) = [ pos 1 / 2^ℕ₊₁ (suc (suc k)) ]
    -- inv2^ k = [ pos 1 / 2^ℕ₊₁ (suc k) ]
    -- The Fast ℚ ordering for [1/b] ≤ [1/d] via inj needs:
    --   pos 1 ·ℤf ℕ₊₁→ℤ d ℤFastO.≤ pos 1 ·ℤf ℕ₊₁→ℤ b
    -- We use ·IdL to simplify pos 1 ·ℤf x ≡ x
    
    -- LHS: pos (2^ℕ (suc k)) ≡ pos 1 ·ℤf ℕ₊₁→ℤ (2^ℕ₊₁ (suc k))
    p1 : ℤ.pos (2^ℕ (suc k)) ≡ pos 1 ·ℤf ℚ.ℕ₊₁→ℤ (2^ℕ₊₁ (suc k))
    p1 = sym (ℕ₊₁→ℤ-2^ℕ₊₁ (suc k)) ∙ sym (ℤf·IdL (ℚ.ℕ₊₁→ℤ (2^ℕ₊₁ (suc k))))

    -- RHS: pos (2^ℕ (suc (suc k))) ≡ pos 1 ·ℤf ℕ₊₁→ℤ (2^ℕ₊₁ (suc (suc k)))
    p2 : ℤ.pos (2^ℕ (suc (suc k))) ≡ pos 1 ·ℤf ℚ.ℕ₊₁→ℤ (2^ℕ₊₁ (suc (suc k)))
    p2 = sym (ℕ₊₁→ℤ-2^ℕ₊₁ (suc (suc k))) ∙ sym (ℤf·IdL (ℚ.ℕ₊₁→ℤ (2^ℕ₊₁ (suc (suc k)))))



-- Helper: (a + b) - a ≡ b
-- Note: Using Fast ℚ properties from ℚP

+-minus-cancel : (a b : ℚ) → (a ℚP.+ b) ℚP.- a ≡ b
+-minus-cancel a b =
  -- (a + b) - a = (a + b) + (-a)
  -- Use +Comm on inner: = (b + a) + (-a)
  -- Use +Assoc⁻¹: = b + (a + (-a))
  -- = b + 0 = b
  cong (ℚP._+ (ℚP.- a)) (ℚP.+Comm a b)   -- (b + a) + (-a)
  ∙ sym (ℚP.+Assoc b a (ℚP.- a))          -- b + (a + (-a))
  ∙ cong (b ℚP.+_) (ℚP.+InvR a)           -- b + 0
  ∙ ℚP.+IdR b                              -- b

-- Difference of consecutive approximations
approx-step : (s : 𝟛ᴺ) (n : ℕ) → approx s (suc n) ℚP.- approx s n ≡ digitContrib (s ! suc n) (suc n)
approx-step s n = +-minus-cancel (approx s n) (digitContrib (s ! suc n) (suc n))


------------------------------------------------------------------------
-- Modulus correctness proof
------------------------------------------------------------------------

-- Key property of the modulus: 1/2^(ℚ₊→ℕ ε) < ε
-- This is what makes the modulus useful for Cauchy proofs.
--
-- PROOF SKETCH:
-- The library's Cubical.HITs.CauchyReals.Sequence contains 1/2ⁿ<ε which
-- NOW using the new ℚ₊→ℕ definition with library functions, we can prove modulus-correct.
--
-- Proof strategy:
-- 1. ℚ₊→ℕ ε = suc n where:
--    k = fst (ceilℚ₊ (invℚ₊ ε)) with proof p₁ : 1/ε < k  (in fast ℚ)
--    n = fst (log2ℕ (ℕ₊₁→ℕ k)) with proof p₂ : ℕ₊₁→ℕ k < 2^n (in ℕ)
-- 2. Chain: 1/2^{n+2} < 1/2^n < 1/k < 1/(1/ε) = ε (in fast ℚ)
-- 3. Use ℚᶠ→ℚ to convert result type (identity since both are fast ℚ)

-- inv2^ᶠ: Alias for inv2^ typed as ℚᶠ (definitionally equal since both use fast ℚ)
-- This is used in modulus-correct proof for type compatibility with ℚᶠ operations.
inv2^ᶠ : ℕ → ℚᶠ
inv2^ᶠ n = [ pos 1 / 2^ℕ₊₁ (suc n) ]

-- Since both ℚ and ℚᶠ are fast rationals, ℚ→ℚᶠ is identity
inv2^-slow→fast : (n : ℕ) → ℚ→ℚᶠ (inv2^ n) ≡ inv2^ᶠ n
inv2^-slow→fast n = refl

-- Key monotonicity: 2^n < 2^{suc n} in ℕ
-- 2^(suc n) = 2 · 2^n = 2^n + 2^n
-- ℕO._<_ is defined as m < n iff suc m ≤ n iff ∃k. k + suc m ≡ n
-- So we need k such that k + suc (2^n) ≡ 2^(suc n)
-- Since 2^n = suc m (from 2^ℕ-pos), we need k + suc (suc m) ≡ suc m + suc m
-- Taking k = m: m + suc (suc m) = suc (m + suc m) = suc (suc (m + m))
--             = suc m + suc m by +-suc and +-suc again
2^-mono-strict : (n : ℕ) → 2^ℕ n ℕO.< 2^ℕ (suc n)
2^-mono-strict n with 2^ℕ-pos n
... | (m , p) = m , goal
  where
    -- Need: m + suc (2^ℕ n) ≡ 2^ℕ (suc n)
    -- p : 2^ℕ n ≡ suc m
    -- 2^ℕ (suc n) = 2 · 2^ℕ n = 2^ℕ n + 2^ℕ n
    step1 : 2^ℕ (suc n) ≡ 2^ℕ n ℕ.+ 2^ℕ n
    step1 = 2·x≡x+x (2^ℕ n)
    
    step2 : 2^ℕ n ℕ.+ 2^ℕ n ≡ suc m ℕ.+ suc m  
    step2 = cong₂ ℕ._+_ p p
    
    step3 : m ℕ.+ suc (2^ℕ n) ≡ m ℕ.+ suc (suc m)
    step3 = cong (m ℕ.+_) (cong suc p)
    
    step4 : m ℕ.+ suc (suc m) ≡ suc m ℕ.+ suc m
    step4 = ℕP.+-suc m (suc m) ∙ cong suc (ℕP.+-suc m m) ∙ cong (λ x → suc (suc x)) (ℕP.+-comm m m)
          ∙ sym (cong suc (ℕP.+-suc m m))
    
    goal : m ℕ.+ suc (2^ℕ n) ≡ 2^ℕ (suc n)
    goal = step3 ∙ step4 ∙ sym step2 ∙ sym step1

-- For the main proof, we use invℚ₊-<-invℚ₊ from the library which gives:
-- q < r ≃ 1/r < 1/q for positive rationals

-- Helper: Convert ℕ< to ℚᶠ< for positive naturals
-- When m < n, we have fromNat m < fromNat n
open import Cubical.Data.Rationals.Fast as ℚF using (fromNat)

ℕ<→ℚᶠ< : (m n : ℕ) → m ℕO.< n → ℚF.fromNat m ℚFO.< ℚF.fromNat n
ℕ<→ℚᶠ< m n (k , p) = ℚFO.inj (subst2 ℤFastO._<_ eq1 eq2 ℤ-ineq)
  where
    -- fromNat m = [ pos m / 1 ], fromNat n = [ pos n / 1 ]
    -- Need: pos m · 1 <ᶠ pos n · 1, i.e., pos m <ᶠ pos n
    -- ℤFastO._<_ is: m <ᶠ n = Σ k', (1ᶠ + m) +ᶠ pos k' ≡ n
    -- For pos m <ᶠ pos n: (1ᶠ + pos m) +ᶠ pos k' ≡ pos n
    -- 1ᶠ + pos m = pos (suc m) via fast ℤ addition
    -- So we need: pos (suc m) +ᶠ pos k' ≡ pos n, i.e., pos (suc m + k') ≡ pos n
    -- From p : k + suc m ≡ n, we get suc m + k ≡ n by +-comm
    
    -- ℤFastO._<_ for pos m < pos n is: Σ k', (pos 1 ℤf.+ pos m) ℤf.+ pos k' ≡ pos n
    -- pos 1 ℤf.+ pos m = pos (1 + m) = pos (suc m) (fast ℤ adds naturals directly)
    -- pos (suc m) ℤf.+ pos k = pos (suc m + k)
    
    -- We have p : k + suc m ≡ n
    -- Need: suc m + k ≡ n
    p' : suc m ℕ.+ k ≡ n
    p' = ℕP.+-comm (suc m) k ∙ p
    
    ℤ-ineq : pos m ℤFastO.< pos n
    ℤ-ineq = k , cong pos p'
    
    eq1 : pos m ≡ pos m ℤf.· pos 1
    eq1 = sym (ℤf·IdR (pos m))
    
    eq2 : pos n ≡ pos n ℤf.· pos 1
    eq2 = sym (ℤf·IdR (pos n))

open ℤᶠP using (·IdR)

-- Helper: 0 < 2^n for any n (needed to construct ℚ₊ from 2^n)
0<2^ℕ : (n : ℕ) → ℚF.fromNat (2^ℕ n) ℚFO.< ℚF.fromNat (2^ℕ (suc n))
0<2^ℕ n = ℕ<→ℚᶠ< (2^ℕ n) (2^ℕ (suc n)) (2^-mono-strict n)

-- 0 < 2^{suc n} as ℚᶠ (using 0< which is the Type for ℚ₊, not _<_ 0)
-- Strategy: 0 < 1 < 2^1 < ... < 2^(suc n), then convert via <→0<
0<fromNat-2^ℕ : (n : ℕ) → ℚFO.0< ℚF.fromNat (2^ℕ (suc n))
0<fromNat-2^ℕ n = ℚFO.<→0< (ℚF.fromNat (2^ℕ (suc n))) (go n)
  where
    -- Prove 0 < 2^{suc n} using regular _<_ then convert
    go : (m : ℕ) → ℚFO._<_ (ℚF.fromNat 0) (ℚF.fromNat (2^ℕ (suc m)))
    go zero = ℚFO.isTrans< (ℚF.fromNat 0) (ℚF.fromNat 1) (ℚF.fromNat (2^ℕ 1)) 
              (ℚFOP.0<sucN 0) (0<2^ℕ 0)
    go (suc m) = ℚFO.isTrans< (ℚF.fromNat 0) (ℚF.fromNat (2^ℕ (suc m))) (ℚF.fromNat (2^ℕ (suc (suc m))))
                 (go m) (0<2^ℕ (suc m))

-- 2^ℕ as ℚ₊ (positive rational)
2^ℕ-ℚ₊ : (n : ℕ) → ℚ₊
2^ℕ-ℚ₊ zero = ℚF.fromNat 1 , ℚFO.<→0< (ℚF.fromNat 1) (ℚFOP.0<sucN 0)
2^ℕ-ℚ₊ (suc n) = ℚF.fromNat (2^ℕ (suc n)) , 0<fromNat-2^ℕ n

-- k as ℚ₊ when k is ℕ₊₁
ℕ₊₁-ℚ₊ : ℕ₊₁ → ℚ₊
ℕ₊₁-ℚ₊ (1+ n) = ℚF.fromNat (suc n) , ℚFO.<→0< (ℚF.fromNat (suc n)) (ℚFOP.0<sucN n)

-- Helper: invℚ₊ of (fromNat (suc n), 0<proof) produces [pos 1 / 1+ n] in the quotient
-- This is the key lemma for proving rel in modulus-correct
-- 
-- The proof uses the following facts:
-- 1. fromNat (suc n) = [pos (suc n) / 1+ 0]
-- 2. invℚ₊ inverts this to [pos 1 / k] where k comes from 0<→ℕ₊₁
-- 3. For [pos (suc n) / 1+ 0], the 0< proof witnesses suc n > 0
-- 4. 0<→ℕ₊₁ extracts 1+ n from this
-- 5. So [pos 1 / 1+ n] ∼ [pos 1 / 1+ n] by reflexivity
--
-- The key insight: for any positive rational [pos (suc n) / 1+ 0],
-- the denominator of its inverse is definitionally 1+ n when we construct
-- the positivity proof correctly.
invℚ₊-fromNat-eq : (n : ℕ) → fst (ℚFOP.invℚ₊ (2^ℕ-ℚ₊ (suc n))) ≡ inv2^ᶠ n
invℚ₊-fromNat-eq n = ℚF.eq/ _ _ rel
  where
    -- Both are [pos 1 / d] where d should represent 2^ℕ (suc n) as ℕ₊₁
    -- d1 from invℚ₊: uses 0<→ℕ₊₁ on the numerator pos (2^ℕ (suc n))
    -- d2 from inv2^ᶠ n: uses 2^ℕ₊₁ (suc n) = 1+ (fst (2^ℕ-pos (suc n)))
    -- 
    -- The relation ℚF._∼_ for (pos 1, d1) ∼ (pos 1, d2) reduces to:
    -- pos 1 ·f ℕ₊₁→ℤ d2 ≡ pos 1 ·f ℕ₊₁→ℤ d1 (since ℚF._∼_ (a,b) (c,d) is a ·f ℕ₊₁→ℤ d ≡ c ·f ℕ₊₁→ℤ b)
    -- which reduces to ℕ₊₁→ℤ d2 ≡ ℕ₊₁→ℤ d1 (via ·IdL)
    --
    -- Both should give pos (2^ℕ (suc n)):
    -- - For d2 = 2^ℕ₊₁ (suc n): ℕ₊₁→ℤ d2 = pos (2^ℕ (suc n)) by ℕ₊₁→ℤ-2^ℕ₊₁
    -- - For d1 from invℚ₊: ℕ₊₁→ℤ d1 = pos (2^ℕ (suc n)) by sym of snd of 0<→ℕ₊₁
    
    -- Bind the 0<→ℕ₊₁ result once to share between d1 and d1-eq
    -- 0<→ℕ₊₁ x p : Σ ℕ₊₁ (λ m → x ≡ pos (ℕ₊₁→ℕ m)) i.e., x ≡ ℕ₊₁→ℤ m
    d1-result : Σ[ k ∈ ℕ₊₁ ] pos (2^ℕ (suc n)) ≡ ℚ.ℕ₊₁→ℤ k
    d1-result = ℤFastO.0<→ℕ₊₁ (pos (2^ℕ (suc n))) (0<fromNat-2^ℕ n)
    
    d1 : ℕ₊₁
    d1 = fst d1-result
    
    d1-eq : ℚ.ℕ₊₁→ℤ d1 ≡ pos (2^ℕ (suc n))
    d1-eq = sym (snd d1-result)
    
    d2 : ℕ₊₁
    d2 = 2^ℕ₊₁ (suc n)
    
    left-pair : ℤ × ℕ₊₁
    left-pair = (pos 1 , d1)
    
    right-pair : ℤ × ℕ₊₁  
    right-pair = (pos 1 , d2)
    
    d2-eq : ℚ.ℕ₊₁→ℤ d2 ≡ pos (2^ℕ (suc n))
    d2-eq = ℕ₊₁→ℤ-2^ℕ₊₁ (suc n)
    
    denom-eq : ℚ.ℕ₊₁→ℤ d2 ≡ ℚ.ℕ₊₁→ℤ d1
    denom-eq = d2-eq ∙ sym d1-eq
    
    -- The ∼ relation: pos 1 ·f ℕ₊₁→ℤ d2 ≡ pos 1 ·f ℕ₊₁→ℤ d1
    -- Simplify using ·IdL: 1 ·f x ≡ x
    rel : ℚF._∼_ left-pair right-pair
    rel = ℤf·IdL (ℚ.ℕ₊₁→ℤ d2) ∙ denom-eq ∙ sym (ℤf·IdL (ℚ.ℕ₊₁→ℤ d1))

-- Key inequality: inv2^ᶠ (suc n) < inv2^ᶠ n (decreasing)
-- Direct proof: 2^{n+1} < 2^{n+2} in ℕ, so 1/2^{n+2} < 1/2^{n+1} in ℚ
-- We use the ℕ< to ℚ< via the inversion equivalence
inv2^ᶠ-mono : (n : ℕ) → inv2^ᶠ (suc n) ℚFO.< inv2^ᶠ n
inv2^ᶠ-mono n = ℚFO.inj ℤ<-proof
  where
    -- inv2^ᶠ n = [pos 1 / 2^ℕ₊₁ (suc n)]
    -- inv2^ᶠ (suc n) = [pos 1 / 2^ℕ₊₁ (suc (suc n))]
    -- For [a/b] < [c/d] we need a·d < c·b
    -- Here: pos 1 · 2^ℕ₊₁ (suc n) < pos 1 · 2^ℕ₊₁ (suc (suc n))
    -- i.e., 2^ℕ (suc n) < 2^ℕ (suc (suc n))
    
    denom1 = 2^ℕ₊₁ (suc (suc n))
    denom2 = 2^ℕ₊₁ (suc n)
    
    -- The key: 2^(suc n) < 2^(suc (suc n))
    ℕ<-proof : 2^ℕ (suc n) ℕO.< 2^ℕ (suc (suc n))
    ℕ<-proof = 2^-mono-strict (suc n)
    
    -- Convert to ℤFastO._<_
    ℤ<-proof : (pos 1 ℤf.· ℚ.ℕ₊₁→ℤ denom2) ℤFastO.< (pos 1 ℤf.· ℚ.ℕ₊₁→ℤ denom1)
    ℤ<-proof = subst2 ℤFastO._<_ eq1 eq2 ℤ<-core
      where
        -- pos 1 · x ≡ x, and ℕ₊₁→ℤ (2^ℕ₊₁ (suc n)) ≡ pos (2^ℕ (suc n))
        eq1 : ℤ.pos (2^ℕ (suc n)) ≡ pos 1 ℤf.· ℚ.ℕ₊₁→ℤ denom2
        eq1 = sym (ℕ₊₁→ℤ-2^ℕ₊₁ (suc n)) ∙ sym (ℤf·IdL (ℚ.ℕ₊₁→ℤ denom2))
        
        eq2 : ℤ.pos (2^ℕ (suc (suc n))) ≡ pos 1 ℤf.· ℚ.ℕ₊₁→ℤ denom1
        eq2 = sym (ℕ₊₁→ℤ-2^ℕ₊₁ (suc (suc n))) ∙ sym (ℤf·IdL (ℚ.ℕ₊₁→ℤ denom1))
        
        -- Core: pos (2^(suc n)) < pos (2^(suc(suc n))) in fast ℤ
        ℤ<-core : ℤ.pos (2^ℕ (suc n)) ℤFastO.< ℤ.pos (2^ℕ (suc (suc n)))
        ℤ<-core with ℕ<-proof
        ... | (k , p) = k , cong pos (ℕP.+-comm (suc (2^ℕ (suc n))) k ∙ p)

-- The main modulus-correct proof
modulus-correct : (ε : ℚ₊) → inv2^ (ℚ₊→ℕ ε) ℚO.< ℚᶠ→ℚ (fst ε)
modulus-correct ε = ℚᶠ→ℚ-< (inv2^ᶠ (ℚ₊→ℕ ε)) (fst ε) 
  (subst (ℚFO._< fst ε) (sym (inv2^-slow→fast (ℚ₊→ℕ ε))) fast-proof)
  where
    -- Unpack the components of ℚ₊→ℕ
    ε-inv = ℚFOP.invℚ₊ ε
    ceil-result = ℚFOP.ceilℚ₊ ε-inv
    k : ℕ₊₁
    k = fst ceil-result
    k-proof : fst ε-inv ℚFO.< ℚF.fromNat (ℕ₊₁→ℕ k)
    k-proof = snd ceil-result
    
    log-result = ℕMod.log2ℕ (ℕ₊₁→ℕ k)
    n : ℕ
    n = fst log-result
    -- log2ℕ gives: k < 2 ^ n (using _^_ from Cubical.Data.Nat.Base)
    -- We need: k < 2^ℕ n
    n-proof' : ℕ₊₁→ℕ k ℕO.< (2 ℕBase.^ n)
    n-proof' = fst (snd log-result)
    n-proof : ℕ₊₁→ℕ k ℕO.< 2^ℕ n
    n-proof = subst (ℕ₊₁→ℕ k ℕO.<_) (2^≡2^ℕ n) n-proof'
    
    -- Chain: 1/2^{n+2} < 1/2^n < 1/k < 1/(1/ε) = ε
    
    -- Step 1: k < 2^n in ℚᶠ (from n-proof via ℕ<→ℚᶠ<)
    k<2^n-ℚᶠ : ℚF.fromNat (ℕ₊₁→ℕ k) ℚFO.< ℚF.fromNat (2^ℕ n)
    k<2^n-ℚᶠ = ℕ<→ℚᶠ< (ℕ₊₁→ℕ k) (2^ℕ n) n-proof
    
    -- Step 2: 1/2^n < 1/k (from k < 2^n via invℚ₊-<-invℚ₊)
    -- Need k and 2^n as ℚ₊
    k-ℚ₊ : ℚ₊
    k-ℚ₊ = ℕ₊₁-ℚ₊ k
    
    2^n-ℚ₊ : ℚ₊
    2^n-ℚ₊ = 2^ℕ-ℚ₊ n
    
    -- 1/2^n < 1/k from k < 2^n via invℚ₊-<-invℚ₊
    -- invℚ₊-<-invℚ₊ q r : (fst q < fst r) ≃ (fst (invℚ₊ r) < fst (invℚ₊ q))
    -- We have k < 2^n, so using invℚ₊-<-invℚ₊ k-ℚ₊ 2^n-ℚ₊ we get 1/2^n < 1/k
    
    -- Equality proofs to bridge fromNat types with fst types
    fst-k-ℚ₊-eq : fst k-ℚ₊ ≡ ℚF.fromNat (ℕ₊₁→ℕ k)
    fst-k-ℚ₊-eq = refl  -- By definition of ℕ₊₁-ℚ₊
    
    fst-2^n-ℚ₊-eq : fst 2^n-ℚ₊ ≡ ℚF.fromNat (2^ℕ n)
    fst-2^n-ℚ₊-eq with n
    ... | zero = refl  -- fromNat 1 = fromNat (2^ℕ 0)
    ... | suc m = refl  -- By definition of 2^ℕ-ℚ₊ (suc m)
    
    -- Convert k<2^n-ℚᶠ to expected type using subst
    k<2^n-for-inv : fst k-ℚ₊ ℚFO.< fst 2^n-ℚ₊
    k<2^n-for-inv = subst2 ℚFO._<_ (sym fst-k-ℚ₊-eq) (sym fst-2^n-ℚ₊-eq) k<2^n-ℚᶠ
    
    inv-2^n<inv-k : fst (ℚFOP.invℚ₊ 2^n-ℚ₊) ℚFO.< fst (ℚFOP.invℚ₊ k-ℚ₊)
    inv-2^n<inv-k = fst (ℚFOP.invℚ₊-<-invℚ₊ k-ℚ₊ 2^n-ℚ₊) k<2^n-for-inv
    
    -- Step 3: 1/k < ε (from 1/ε < k via invℚ₊-<-invℚ₊ and invℚ₊-invol)
    -- We have: k-proof : fst ε-inv < fromNat (ℕ₊₁→ℕ k)
    -- invℚ₊-<-invℚ₊ ε-inv k-ℚ₊ : (fst ε-inv < fst k-ℚ₊) ≃ (fst (invℚ₊ k-ℚ₊) < fst (invℚ₊ ε-inv))
    -- And invℚ₊ ε-inv = invℚ₊ (invℚ₊ ε) = ε by invℚ₊-invol
    
    -- Need: fst ε-inv < fst k-ℚ₊ 
    fst-εinv-eq : fst ε-inv ≡ fst (ℚFOP.invℚ₊ ε)
    fst-εinv-eq = refl
    
    k-proof-converted : fst ε-inv ℚFO.< fst k-ℚ₊
    k-proof-converted = subst (fst ε-inv ℚFO.<_) (sym fst-k-ℚ₊-eq) k-proof
    
    inv-k<ε : fst (ℚFOP.invℚ₊ k-ℚ₊) ℚFO.< fst ε
    inv-k<ε = subst (fst (ℚFOP.invℚ₊ k-ℚ₊) ℚFO.<_) (ℚFOP.invℚ₊-invol ε) 
              (fst (ℚFOP.invℚ₊-<-invℚ₊ ε-inv k-ℚ₊) k-proof-converted)
    
    -- Step 4: 1/2^n < ε by transitivity
    inv-2^n<ε : fst (ℚFOP.invℚ₊ 2^n-ℚ₊) ℚFO.< fst ε
    inv-2^n<ε = ℚFO.isTrans< _ _ _ inv-2^n<inv-k inv-k<ε
    
    -- Step 5: inv2^ᶠ (suc n) = 1/2^{n+2} < 1/2^{n+1} = inv2^ᶠ n 
    -- We need to show inv2^ᶠ (suc n) < fst ε
    -- Note: ℚ₊→ℕ ε = suc n, so we need inv2^ᶠ (suc n) < fst ε
    
    -- inv2^ᶠ n relates to invℚ₊ (2^ℕ-ℚ₊ (suc n))
    -- We have inv-2^n<ε : fst (invℚ₊ (2^ℕ-ℚ₊ n)) < fst ε
    --                   = fst (invℚ₊ (2^ℕ-ℚ₊ n)) < fst ε
    --                   = 1/2^n < fst ε (when n ≥ 1)
    
    -- We need inv2^ᶠ n = 1/2^{n+1} < fst ε
    -- But we only have 1/2^n < ε, and 1/2^{n+1} < 1/2^n
    -- So inv2^ᶠ n < ε by transitivity!
    
    fast-proof : inv2^ᶠ (suc n) ℚFO.< fst ε
    fast-proof = ℚFO.isTrans< _ _ _ (inv2^ᶠ-mono n) inv-2^n<ε'
      where
        -- inv2^ᶠ n = 1/2^{n+1}, fst (invℚ₊ 2^n-ℚ₊) = 1/2^n
        -- Since 2^n < 2^{n+1}, we have 1/2^{n+1} < 1/2^n ✓
        
        -- Direct proof: inv2^ᶠ n < fst (invℚ₊ 2^n-ℚ₊) without needing quotient equality
        -- inv2^ᶠ n = [pos 1 / 2^ℕ₊₁ (suc n)] = 1/2^{n+1}
        -- fst (invℚ₊ 2^n-ℚ₊) = 1/2^n (as ℚᶠ)
        -- We prove 1/2^{n+1} < 1/2^n, i.e., 2^n < 2^{n+1}
        -- This uses the same pattern as inv2^ᶠ-mono but adapted for mixed types
        
        inv2^ᶠ-n<inv-2^n : inv2^ᶠ n ℚFO.< fst (ℚFOP.invℚ₊ 2^n-ℚ₊)
        inv2^ᶠ-n<inv-2^n = subst (ℚFO._< fst (ℚFOP.invℚ₊ 2^n-ℚ₊)) inv-2^sn-eq inv-ineq
          where
            -- Proof that inv2^ᶠ n < fst (invℚ₊ (2^ℕ-ℚ₊ n))
            -- i.e., 1/2^{n+1} < 1/2^n
            -- This holds because 2^n < 2^{n+1}, so 1/2^{n+1} < 1/2^n
            
            2^sn-ℚ₊ : ℚ₊
            2^sn-ℚ₊ = 2^ℕ-ℚ₊ (suc n)
            
            -- 2^n < 2^{suc n} in ℚᶠ
            2^n<2^sn : fst 2^n-ℚ₊ ℚFO.< fst 2^sn-ℚ₊
            2^n<2^sn = subst2 ℚFO._<_ (sym fst-2^n-eq') (sym fst-2^sn-eq) (0<2^ℕ n)
              where
                fst-2^n-eq' : fst 2^n-ℚ₊ ≡ ℚF.fromNat (2^ℕ n)
                fst-2^n-eq' = fst-2^n-ℚ₊-eq
                
                fst-2^sn-eq : fst 2^sn-ℚ₊ ≡ ℚF.fromNat (2^ℕ (suc n))
                fst-2^sn-eq = refl
            
            -- Apply invℚ₊-<-invℚ₊: 2^n < 2^{suc n} → 1/2^{suc n} < 1/2^n
            inv-ineq : fst (ℚFOP.invℚ₊ 2^sn-ℚ₊) ℚFO.< fst (ℚFOP.invℚ₊ 2^n-ℚ₊)
            inv-ineq = fst (ℚFOP.invℚ₊-<-invℚ₊ 2^n-ℚ₊ 2^sn-ℚ₊) 2^n<2^sn
            
            -- Use the helper lemma to get the equality
            -- 2^sn-ℚ₊ = 2^ℕ-ℚ₊ (suc n), so invℚ₊-fromNat-eq n gives us:
            -- fst (invℚ₊ (2^ℕ-ℚ₊ (suc n))) ≡ inv2^ᶠ n
            inv-2^sn-eq : fst (ℚFOP.invℚ₊ 2^sn-ℚ₊) ≡ inv2^ᶠ n
            inv-2^sn-eq = invℚ₊-fromNat-eq n
        
        inv-2^n<ε' : inv2^ᶠ n ℚFO.< fst ε
        inv-2^n<ε' = ℚFO.isTrans< _ _ _ inv2^ᶠ-n<inv-2^n inv-2^n<ε

-- The tail bound: for m ≤ n, |approx s n - approx s m| ≤ 1/2^{m+1}
-- This follows because each digit d_i contributes at most 1/2^{i+1},
-- and the sum from i=m+1 to n is bounded by the geometric series sum
-- which converges to 1/2^{m+1}.

-- The following lemmas establish bounds on signed-digit approximations.
-- They require substantial rational arithmetic proofs.
--
-- Proof sketch: The difference is Σᵢ₌ₘ₊₁ⁿ dᵢ/2^{i+1} where |dᵢ| ≤ 1.
-- This sum is bounded by Σᵢ₌ₘ₊₁^∞ 1/2^{i+1} = 1/2^{m+1}.

-- Helper: Triangle inequality for abs
-- Strategy:
-- 1. x ≤ abs x (from ≤max since abs x = max x (-x))
-- 2. -x ≤ abs x (similarly, using maxComm)
-- 3. x + y ≤ abs x + abs y (from 1, using ≤Monotone+)
-- 4. -(x+y) = -x + -y ≤ abs x + abs y (from 2, using ≤Monotone+ and -Dist+)
-- 5. max (x+y) (-(x+y)) ≤ abs x + abs y (from 3,4 using max-LUB)

-- Helper: x ≤ abs x
x≤abs-x : (x : ℚ) → x ℚO.≤ abs x
x≤abs-x x = ℚO.≤max x (- x)

-- Helper: -x ≤ abs x  
neg-x≤abs-x : (x : ℚ) → (- x) ℚO.≤ abs x
neg-x≤abs-x x = subst ((- x) ℚO.≤_) (sym (ℚP.maxComm x (- x))) (ℚO.≤max (- x) x)

-- Helper: max is LUB - if a ≤ z and b ≤ z, then max a b ≤ z
-- Using totality of ≤ via propositional truncation eliminator
open import Cubical.HITs.PropositionalTruncation as PT using (∥_∥₁; ∣_∣₁)

-- Helper lemma to show ≤ is a proposition (needed for PT.rec)
-- Note: isProp≤ comes from Fast ℚ Order Properties module

max-LUB : (a b z : ℚ) → a ℚO.≤ z → b ℚO.≤ z → max a b ℚO.≤ z
max-LUB a b z a≤z b≤z = PT.rec (ℚO.isProp≤ (max a b) z) handle (ℚO.isTotal≤ a b)
  where
    handle : (a ℚO.≤ b) ⊎ (b ℚO.≤ a) → max a b ℚO.≤ z
    handle (inl a≤b) = subst (ℚO._≤ z) (sym (ℚO.≤→max a b a≤b)) b≤z
    handle (inr b≤a) = subst (ℚO._≤ z) (sym (ℚP.maxComm a b ∙ ℚO.≤→max b a b≤a)) a≤z

abs-triangle : (x y : ℚ) → abs (x + y) ℚO.≤ abs x + abs y
abs-triangle x y = max-LUB (x + y) (- (x + y)) (abs x + abs y) xy≤ neg-xy≤
  where
    -- x + y ≤ abs x + abs y
    xy≤ : (x + y) ℚO.≤ (abs x + abs y)
    xy≤ = ℚO.≤Monotone+ x (abs x) y (abs y) (x≤abs-x x) (x≤abs-x y)
    
    -- -(x + y) = -x + -y ≤ abs x + abs y
    neg-xy≤ : (- (x + y)) ℚO.≤ (abs x + abs y)
    neg-xy≤ = subst (ℚO._≤ (abs x + abs y)) (sym (ℚP.-Distr x y))
              (ℚO.≤Monotone+ (- x) (abs x) (- y) (abs y) (neg-x≤abs-x x) (neg-x≤abs-x y))

-- Helper: x - 0 = x
-- x - 0 = x + (-0) = x + 0 = x
minus-zero : (x : ℚ) → x - 0ℚ ≡ x
minus-zero x = ℚP.+IdR x  -- -0 computes to 0, so x - 0 = x + 0 = x

-- Helper: if 0 ≤ y then x - y ≤ x
-- Proof: x - y = x + (-y)
-- We need: x + (-y) ≤ x + 0 = x
-- From 0 ≤ y, we get -y ≤ 0 by 0≤x→-x≤0'
-- Then: x + (-y) ≤ x + 0 by ≤-o+ (left monotonicity of +)
-- Finally: x + 0 = x by +IdR
0≤y→x-y≤x : (x y : ℚ) → 0ℚ ℚO.≤ y → (x ℚP.- y) ℚO.≤ x
0≤y→x-y≤x x y 0≤y = subst2 ℚO._≤_ p3 p4 step
  where
    -y≤0 : (- y) ℚO.≤ 0ℚ
    -y≤0 = 0≤x→-x≤0' y 0≤y
    
    step : (x ℚP.+ (- y)) ℚO.≤ (x ℚP.+ 0ℚ)
    step = ℚO.≤-o+ (- y) 0ℚ x -y≤0
    
    p3 : x ℚP.+ (- y) ≡ x ℚP.- y
    p3 = refl
    
    p4 : x ℚP.+ 0ℚ ≡ x
    p4 = ℚP.+IdR x

-- Helper: weaken tight bound to weak bound
-- If |diff| ≤ inv2^m - inv2^(m+k) and inv2^(m+k) ≥ 0, then |diff| ≤ inv2^m
≤-minus-weaken : (m k : ℕ) (d : ℚ)
  → d ℚO.≤ (inv2^ m ℚP.- inv2^ (m ℕ.+ k))
  → d ℚO.≤ inv2^ m
≤-minus-weaken m k d d≤tight = isTrans≤ d _ (inv2^ m) d≤tight (0≤y→x-y≤x (inv2^ m) (inv2^ (m ℕ.+ k)) (0≤inv2^ (m ℕ.+ k)))

-- Helper: geometric series bound is automatic from the weaker bound.
-- The key insight: we use a POSTULATED step bound for now, 
-- but the structure allows eventual constructive proof.

-- Helper: for the base case, approx s m - approx s m = 0
approx-diff-self : (s : 𝟛ᴺ) (m : ℕ) → approx s m ℚP.- approx s m ≡ 0ℚ
approx-diff-self s m = ℚP.+InvR (approx s m)

-- Base case: |0| ≤ inv2^ m
tail-bound-base : (s : 𝟛ᴺ) (m : ℕ) → abs (approx s m ℚP.- approx s m) ℚO.≤ inv2^ m
tail-bound-base s m = subst (ℚO._≤ inv2^ m) (sym (cong abs (approx-diff-self s m) ∙ abs-0ℚ)) (0≤inv2^ m)

-- Helper: decompose approx s (suc n) - approx s m into (approx s n - approx s m) + digitContrib
approx-diff-step : (s : 𝟛ᴺ) (m n : ℕ) 
  → approx s (suc n) ℚP.- approx s m ≡ (approx s n ℚP.- approx s m) ℚP.+ digitContrib (s ! suc n) (suc n)
approx-diff-step s m n = 
  let dc = digitContrib (s ! suc n) (suc n)
      an = approx s n
      am = approx s m
      -- (an + dc) - am = (an + dc) + (-am) = an + (dc + (-am)) = an + ((-am) + dc) = (an - am) + dc
      step1 : (an + dc) - am ≡ (an + dc) + (- am)
      step1 = refl
      step2 : (an + dc) + (- am) ≡ an + (dc + (- am))
      step2 = sym (ℚP.+Assoc an dc (- am))
      step3 : an + (dc + (- am)) ≡ an + ((- am) + dc)
      step3 = cong (an +_) (ℚP.+Comm dc (- am))
      step4 : an + ((- am) + dc) ≡ (an + (- am)) + dc
      step4 = ℚP.+Assoc an (- am) dc
  in step1 ∙ step2 ∙ step3 ∙ step4

-- The inductive step: if |diff up to m+k| ≤ inv2^ m, then |diff up to m+suc k| ≤ inv2^ m
-- This requires showing that adding one more digit contribution stays bounded.
-- The bound works because: even though we add inv2^(m+suc k),
-- the cumulative sum Σᵢ₌ₘ₊₁^{m+suc k} inv2^i = inv2^m - inv2^(m+suc k) < inv2^m
--
-- TIGHT BOUND APPROACH:
-- We track |approx s (m+k) - approx s m| ≤ inv2^ m - inv2^ (m+k)
-- This telescopes correctly via the doubling lemma.
--
-- Key identity: inv2^(m+k) - inv2^(m+suc k) = inv2^(m+suc k)
-- Because: inv2^(m+k) = 2·inv2^(m+suc k), so inv2^(m+k) - inv2^(m+suc k) = inv2^(m+suc k)
--
-- So: (inv2^m - inv2^(m+k)) + inv2^(m+suc k)
--   = inv2^m - inv2^(m+k) + inv2^(m+suc k)
--   = inv2^m - (inv2^(m+k) - inv2^(m+suc k))  -- rearranging
--   = inv2^m - inv2^(m+suc k)                  -- by key identity

-- Helper: inv2^(n) - inv2^(suc n) = inv2^(suc n)
-- Proof: inv2^ n = inv2^(suc n) + inv2^(suc n)  (by inv2^-double)
-- So inv2^ n - inv2^(suc n) = inv2^(suc n)
inv2^-minus-half : (n : ℕ) → inv2^ n ℚP.- inv2^ (suc n) ≡ inv2^ (suc n)
inv2^-minus-half n =
  cong (ℚP._- inv2^ (suc n)) (inv2^-double n)   -- (inv2^(suc n) + inv2^(suc n)) - inv2^(suc n)
  ∙ +-minus-cancel (inv2^ (suc n)) (inv2^ (suc n))  -- = inv2^(suc n)

-- Helper: (a - b) + c = a - (b - c)  when b = c + c (i.e., c is half of b)
-- We'll use this to show (inv2^m - inv2^(m+k)) + inv2^(m+suc k) = inv2^m - inv2^(m+suc k)
--
-- Actually, let's use: (a - b) + c = a - b + c = a + (-b + c) = a + (-(b - c))  if -b + c = -(b-c)
-- We have: inv2^(m+k) = inv2^(m+suc k) + inv2^(m+suc k)
-- So: -inv2^(m+k) + inv2^(m+suc k) = -inv2^(m+suc k)
-- And: (a - b) + c = a + (-b + c) = a + (-c) = a - c  when b = 2c

-- Helper: -(x + y) + y = -x
neg-sum-plus-half : (x : ℚ) → ℚP.- (x ℚP.+ x) ℚP.+ x ≡ ℚP.- x
neg-sum-plus-half x =
  cong (ℚP._+ x) (ℚP.-Distr x x)  -- (-x + -x) + x
  ∙ sym (ℚP.+Assoc (- x) (- x) x)  -- -x + (-x + x)
  ∙ cong ((- x) ℚP.+_) (ℚP.+InvL x)       -- -x + 0
  ∙ ℚP.+IdR (- x)                         -- -x

-- Helper: (a - (x+x)) + x = a - x
minus-double-plus-half : (a x : ℚ) → (a ℚP.- (x ℚP.+ x)) ℚP.+ x ≡ a ℚP.- x
minus-double-plus-half a x =
  -- (a - (x+x)) + x = (a + (-(x+x))) + x
  --                 = a + ((-(x+x)) + x)
  --                 = a + (-x)
  --                 = a - x
  sym (ℚP.+Assoc a (- (x + x)) x)   -- a + ((-(x+x)) + x)
  ∙ cong (a ℚP.+_) (neg-sum-plus-half x)  -- a + (-x)

-- The tight bound version
tail-bound-tight : (s : 𝟛ᴺ) (m k : ℕ)
  → abs (approx s (m ℕ.+ k) ℚP.- approx s m) ℚO.≤ (inv2^ m ℚP.- inv2^ (m ℕ.+ k))
tail-bound-tight s m zero =
  -- |approx s (m+0) - approx s m| = 0 ≤ inv2^ m - inv2^ (m+0) = 0
  -- First we show |approx s m - approx s m| = 0 ≤ 0 = inv2^ m - inv2^ m
  -- Then substitute using m + 0 ≡ m
  let
    -- Path: m + 0 ≡ m
    m+0≡m : m ℕ.+ zero ≡ m
    m+0≡m = ℕP.+-zero m

    -- LHS: abs (approx s m - approx s m) = 0
    lhs-eq : abs (approx s m ℚP.- approx s m) ≡ 0ℚ
    lhs-eq = cong abs (approx-diff-self s m) ∙ abs-0ℚ

    -- RHS: inv2^ m - inv2^ m = 0
    rhs-eq : inv2^ m ℚP.- inv2^ m ≡ 0ℚ
    rhs-eq = ℚP.+InvR (inv2^ m)

    -- Core: 0 ≤ 0
    core : 0ℚ ℚO.≤ 0ℚ
    core = isRefl≤ 0ℚ

    -- Substitute to get: abs (approx s m - approx s m) ≤ inv2^ m - inv2^ m
    step1 : abs (approx s m ℚP.- approx s m) ℚO.≤ (inv2^ m ℚP.- inv2^ m)
    step1 = subst2 ℚO._≤_ (sym lhs-eq) (sym rhs-eq) core

    -- Now substitute m → m + 0 on both sides
    goal : abs (approx s (m ℕ.+ zero) ℚP.- approx s m) ℚO.≤ (inv2^ m ℚP.- inv2^ (m ℕ.+ zero))
    goal = subst (λ x → abs (approx s x ℚP.- approx s m) ℚO.≤ (inv2^ m ℚP.- inv2^ x)) (sym m+0≡m) step1
  in goal
tail-bound-tight s m (suc k) =
  -- We have IH: |approx s (m+k) - approx s m| ≤ inv2^ m - inv2^ (m+k)
  -- Want: |approx s (m+suc k) - approx s m| ≤ inv2^ m - inv2^ (m+suc k)
  --
  -- Using suc (m+k) instead of m + suc k to avoid stream indexing issues
  -- They are propositionally equal via +-suc, so we use subst at the end
  let
    IH : abs (approx s (m ℕ.+ k) ℚP.- approx s m) ℚO.≤ (inv2^ m ℚP.- inv2^ (m ℕ.+ k))
    IH = tail-bound-tight s m k

    -- Use suc (m + k) directly
    n : ℕ
    n = m ℕ.+ k

    d : Digit
    d = s ! suc n

    dc-bound : abs (digitContrib d (suc n)) ℚO.≤ inv2^ (suc n)
    dc-bound = digitContrib-bound d (suc n)

    -- approx-diff-step gives us the decomposition for suc n
    diff-decomp : approx s (suc n) ℚP.- approx s m
                ≡ (approx s n ℚP.- approx s m) ℚP.+ digitContrib d (suc n)
    diff-decomp = approx-diff-step s m n

    -- Step 2: apply triangle inequality
    A = approx s n ℚP.- approx s m
    B = digitContrib d (suc n)

    step2 : abs (A ℚP.+ B) ℚO.≤ abs A ℚP.+ abs B
    step2 = abs-triangle A B

    -- Step 3: combine bounds
    -- We need: (inv2^ m - inv2^ n) + inv2^ (suc n) = inv2^ m - inv2^ (suc n)
    -- Using inv2^ n = inv2^(suc n) + inv2^(suc n)
    inv2^-double-at-n : inv2^ n ≡ inv2^ (suc n) ℚP.+ inv2^ (suc n)
    inv2^-double-at-n = inv2^-double n

    bound-sum : (abs A ℚP.+ abs B) ℚO.≤ ((inv2^ m ℚP.- inv2^ n) ℚP.+ inv2^ (suc n))
    bound-sum = ℚO.≤Monotone+ (abs A) (inv2^ m ℚP.- inv2^ n) (abs B) (inv2^ (suc n)) IH dc-bound

    bound-simplify : (inv2^ m ℚP.- inv2^ n) ℚP.+ inv2^ (suc n)
                   ≡ inv2^ m ℚP.- inv2^ (suc n)
    bound-simplify = cong (λ x → (inv2^ m ℚP.- x) ℚP.+ inv2^ (suc n)) inv2^-double-at-n
                   ∙ minus-double-plus-half (inv2^ m) (inv2^ (suc n))

    -- Combine for suc n
    combined : abs (A ℚP.+ B) ℚO.≤ (inv2^ m ℚP.- inv2^ (suc n))
    combined = isTrans≤ (abs (A + B)) (abs A + abs B) _ step2
               (subst (λ x → (abs A + abs B) ℚO.≤ x) bound-simplify bound-sum)

    for-suc-n : abs (approx s (suc n) ℚP.- approx s m) ℚO.≤ (inv2^ m ℚP.- inv2^ (suc n))
    for-suc-n = subst (λ x → abs x ℚO.≤ _) (sym diff-decomp) combined

    -- Now use suc n = suc (m + k) = m + suc k to get the goal
    -- We have: suc n ≡ m + suc k via sym (+-suc m k)
    goal-path : (suc n ≡ m ℕ.+ suc k)
    goal-path = sym (ℕP.+-suc m k)
  in subst (λ x → abs (approx s x ℚP.- approx s m) ℚO.≤ (inv2^ m ℚP.- inv2^ x)) goal-path for-suc-n

-- Weaken tight bound to weak bound
tail-bound-step : (s : 𝟛ᴺ) (m k : ℕ)
  → abs (approx s (m ℕ.+ k) ℚP.- approx s m) ℚO.≤ inv2^ m
  → abs (approx s (m ℕ.+ suc k) ℚP.- approx s m) ℚO.≤ inv2^ m
tail-bound-step s m k _ = ≤-minus-weaken m (suc k) (abs (approx s (m ℕ.+ suc k) ℚP.- approx s m)) (tail-bound-tight s m (suc k))

-- Main tail bound: for m ≤ n, |approx s n - approx s m| ≤ 1/2^{m+1}
-- Proof by induction on k where n = m + k (using ≤-k+ to decompose m ≤ n)
-- Note: ≤-k+ gives (k , k + m ≡ n), so we use +-comm to get m + k ≡ n
tail-bound : (s : 𝟛ᴺ) (m n : ℕ) → m ≤ℕ n
  → abs (approx s n ℚP.- approx s m) ℚO.≤ inv2^ m
tail-bound s m n m≤n with ℕO.≤-k+ m≤n  -- gives (k , k + m ≡ n)
... | k , p = subst (λ x → abs (approx s x ℚP.- approx s m) ℚO.≤ inv2^ m) 
                    (ℕP.+-comm m k ∙ p) (go s m k)
  where
    -- Prove by induction on k
    go : (s : 𝟛ᴺ) (m k : ℕ) → abs (approx s (m ℕ.+ k) ℚP.- approx s m) ℚO.≤ inv2^ m
    go s m zero = subst (λ x → abs (approx s x ℚP.- approx s m) ℚO.≤ inv2^ m)
                        (sym (ℕP.+-zero m)) (tail-bound-base s m)
    go s m (suc k) = tail-bound-step s m k (go s m k)

-- Helper: symmetry of |x - y|
abs-minus-sym : (x y : ℚ) → abs (x ℚP.- y) ≡ abs (y ℚP.- x)
abs-minus-sym x y = sym (abs-neg (x ℚP.- y)) ∙ cong abs (ℚP.-[x-y]≡y-x x y)

-- Helper: min m n when m ≤ n
min-eq-left : (m n : ℕ) → m ≤ℕ n → min m n ≡ m
min-eq-left m n m≤n =
  ≤-antisym (min-≤-left {m} {n}) (minGLB {x = m} ≤-refl m≤n)

-- Helper: min m n when n ≤ m
min-eq-right : (m n : ℕ) → n ≤ℕ m → min m n ≡ n
min-eq-right m n n≤m =
  minComm m n ∙ min-eq-left n m n≤m

-- Symmetric version for arbitrary m, n
tail-bound-sym : (s : 𝟛ᴺ) (m n : ℕ)
  → abs (approx s m ℚP.- approx s n) ℚO.≤ inv2^ (min m n)
tail-bound-sym s m n with splitℕ-≤ m n
... | inl m≤n =
  let
    p₀ : abs (approx s n ℚP.- approx s m) ℚO.≤ inv2^ m
    p₀ = tail-bound s m n m≤n

    p₁ : abs (approx s m ℚP.- approx s n) ℚO.≤ inv2^ m
    p₁ = subst (λ z → z ℚO.≤ inv2^ m)
               (sym (abs-minus-sym (approx s m) (approx s n)))
               p₀

    p₂ : abs (approx s m ℚP.- approx s n) ℚO.≤ inv2^ (min m n)
    p₂ = subst (λ t → abs (approx s m ℚP.- approx s n) ℚO.≤ t)
               (cong inv2^ (sym (min-eq-left m n m≤n)))
               p₁
  in p₂
... | inr n<m =
  let
    n≤m : n ≤ℕ m
    n≤m = <-weaken n<m

    p : abs (approx s m ℚP.- approx s n) ℚO.≤ inv2^ n
    p = tail-bound s n m n≤m
  in subst (λ t → abs (approx s m ℚP.- approx s n) ℚO.≤ t)
           (cong inv2^ (sym (min-eq-right m n n≤m)))
           p


------------------------------------------------------------------------
-- Export key lemmas
------------------------------------------------------------------------

-- Re-export for use in Embedding module
open import Cubical.Data.Rationals.Properties public using (abs; _-_)

-- Export the tail bound for use in proving the Cauchy property
-- inv2^ and tail-bound-sym are the key exports

------------------------------------------------------------------------
-- Constructive approxℚ₊-cauchy proof
------------------------------------------------------------------------

-- The Cauchy property proof is now fully constructive.
-- This is the key lemma used by stream→ℝ below.
--
-- Proof strategy:
-- 1. tail-bound-sym gives: |approx s m - approx s n| ≤ inv2^ (min m n)
-- 2. Case split on min m n:
--    - If min = m: abs ≤ inv2^ m < δ < δ + ε (via modulus-correct δ)
--    - If min = n: abs ≤ inv2^ n < ε < δ + ε (via modulus-correct ε)
-- 3. Convert to fast ℚ and apply rat-rat-fromAbs

-- Helper: ε < δ + ε (using x ≤ y → x < y + ε when ε > 0)
-- Using <+ℚ₊' : ∀ x y (ε : ℚ₊) → x ≤ y → x < (y ℚ.+ fst ε)
ε<δ+ε : (δ ε : ℚ₊) → fst ε ℚFO.< fst (δ ℚFO.ℚ₊+ ε)
ε<δ+ε δ ε = subst (fst ε ℚFO.<_) (ℚF.+Comm (fst ε) (fst δ)) (ℚFO.<+ℚ₊' (fst ε) (fst ε) δ (ℚFO.isRefl≤ (fst ε)))

-- Helper: δ < δ + ε
δ<δ+ε : (δ ε : ℚ₊) → fst δ ℚFO.< fst (δ ℚFO.ℚ₊+ ε)
δ<δ+ε δ ε = ℚFO.<+ℚ₊' (fst δ) (fst δ) ε (ℚFO.isRefl≤ (fst δ))

-- Helper: chain ≤ followed by < gives < in slow ℚ
≤<→< : {a b c : ℚ} → a ℚO.≤ b → b ℚO.< c → a ℚO.< c
≤<→< a≤b b<c = ℚO.isTrans≤< _ _ _ a≤b b<c

-- The Cauchy property of stream approximations (fully constructive)
approxℚ₊-cauchy : (s : 𝟛ᴺ)
  → ∀ (δ ε : ℚ₊) → rat (approxℚ₊ s δ) ∼[ δ ℚFO.ℚ₊+ ε ] rat (approxℚ₊ s ε)
approxℚ₊-cauchy s δ ε = rat-rat-fromAbs (approxℚ₊ s δ) (approxℚ₊ s ε) (δ ℚFO.ℚ₊+ ε) abs-bound
  where
    
    m = ℚ₊→ℕ δ
    n = ℚ₊→ℕ ε
    
    -- tail-bound-sym gives |approx s m - approx s n| ≤ inv2^ (min m n)
    tail-bnd : ℚP.abs (approx s m ℚP.- approx s n) ℚO.≤ inv2^ (min m n)
    tail-bnd = tail-bound-sym s m n
    
    -- Since this file uses fast ℚ exclusively (both ℚ and ℚᶠ are the same type),
    -- the conversion ℚ→ℚᶠ is identity and abs/subtraction are compatible.
    abs-conv : absᶠ (approxℚ₊ s δ -ᶠ approxℚ₊ s ε) ≡ ℚ→ℚᶠ (ℚP.abs (approx s m ℚP.- approx s n))
    abs-conv = refl
    
    -- Case split on whether min m n = m or min m n = n
    -- Using splitℕ-≤ : (m n : ℕ) → (m ≤ n) ⊎ (n < m)
    abs-bound : absᶠ (approxℚ₊ s δ -ᶠ approxℚ₊ s ε) ℚFO.< fst (δ ℚFO.ℚ₊+ ε)
    abs-bound with splitℕ-≤ m n
    ... | inl m≤n = 
      -- min m n = m, so abs ≤ inv2^ m < δ < δ + ε
      let
        -- abs ≤ inv2^ m (since min m n = m)
        abs≤inv2^m : ℚP.abs (approx s m ℚP.- approx s n) ℚO.≤ inv2^ m
        abs≤inv2^m = subst (ℚP.abs (approx s m ℚP.- approx s n) ℚO.≤_) 
                           (cong inv2^ (min-eq-left m n m≤n)) tail-bnd
        
        -- inv2^ m < ℚᶠ→ℚ (fst δ) by modulus-correct
        inv2^m<δ : inv2^ m ℚO.< ℚᶠ→ℚ (fst δ)
        inv2^m<δ = modulus-correct δ
        
        -- Chain: abs < δ in slow ℚ
        abs<δ-slow : ℚP.abs (approx s m ℚP.- approx s n) ℚO.< ℚᶠ→ℚ (fst δ)
        abs<δ-slow = ≤<→< abs≤inv2^m inv2^m<δ
        
        -- Convert to fast ℚ
        abs<δ-fast : ℚ→ℚᶠ (ℚP.abs (approx s m ℚP.- approx s n)) ℚFO.< fst δ
        abs<δ-fast = ℚ<ℚᶠ→ℚ (ℚP.abs (approx s m ℚP.- approx s n)) (fst δ) abs<δ-slow
        
        -- Chain: ... < δ < δ + ε
        abs<δ+ε-fast : ℚ→ℚᶠ (ℚP.abs (approx s m ℚP.- approx s n)) ℚFO.< fst (δ ℚFO.ℚ₊+ ε)
        abs<δ+ε-fast = ℚFO.isTrans< _ _ _ abs<δ-fast (δ<δ+ε δ ε)
        
      in subst (ℚFO._< fst (δ ℚFO.ℚ₊+ ε)) (sym abs-conv) abs<δ+ε-fast
    ... | inr n<m = 
      -- min m n = n, so abs ≤ inv2^ n < ε < δ + ε
      let
        n≤m : n ≤ℕ m
        n≤m = <-weaken n<m
        
        -- abs ≤ inv2^ n (since min m n = n)
        abs≤inv2^n : ℚP.abs (approx s m ℚP.- approx s n) ℚO.≤ inv2^ n
        abs≤inv2^n = subst (ℚP.abs (approx s m ℚP.- approx s n) ℚO.≤_) 
                           (cong inv2^ (min-eq-right m n n≤m)) tail-bnd
        
        -- inv2^ n < ℚᶠ→ℚ (fst ε) by modulus-correct
        inv2^n<ε : inv2^ n ℚO.< ℚᶠ→ℚ (fst ε)
        inv2^n<ε = modulus-correct ε
        
        -- Chain: abs < ε in slow ℚ
        abs<ε-slow : ℚP.abs (approx s m ℚP.- approx s n) ℚO.< ℚᶠ→ℚ (fst ε)
        abs<ε-slow = ≤<→< abs≤inv2^n inv2^n<ε
        
        -- Convert to fast ℚ
        abs<ε-fast : ℚ→ℚᶠ (ℚP.abs (approx s m ℚP.- approx s n)) ℚFO.< fst ε
        abs<ε-fast = ℚ<ℚᶠ→ℚ (ℚP.abs (approx s m ℚP.- approx s n)) (fst ε) abs<ε-slow
        
        -- Chain: ... < ε < δ + ε
        abs<δ+ε-fast : ℚ→ℚᶠ (ℚP.abs (approx s m ℚP.- approx s n)) ℚFO.< fst (δ ℚFO.ℚ₊+ ε)
        abs<δ+ε-fast = ℚFO.isTrans< _ _ _ abs<ε-fast (ε<δ+ε δ ε)
        
      in subst (ℚFO._< fst (δ ℚFO.ℚ₊+ ε)) (sym abs-conv) abs<δ+ε-fast

------------------------------------------------------------------------
-- Interpretation into Cauchy reals (moved after approxℚ₊-cauchy proof)
------------------------------------------------------------------------

-- Interpret a stream as a Cauchy real via the limit of approximations
stream→ℝ : 𝟛ᴺ → ℝ
stream→ℝ s = lim (λ ε → rat (approxℚ₊ s ε)) (approxℚ₊-cauchy s)

------------------------------------------------------------------------
-- Equivalence relation
------------------------------------------------------------------------

-- Two signed-digit sequences are equivalent if they represent the same
-- real number. This is the natural equivalence for signed-digit representation
-- where different digit sequences can represent the same value.

_≈sd_ : 𝟛ᴺ → 𝟛ᴺ → Type₀
x ≈sd y = stream→ℝ x ≡ stream→ℝ y

------------------------------------------------------------------------
-- Signed-digit reals as a quotient type
------------------------------------------------------------------------

-- The type of signed-digit real numbers in [-1, 1]
-- Quotienting by ≈sd identifies streams with the same limit
𝕀sd : Type₀
𝕀sd = 𝟛ᴺ / _≈sd_

-- Embedding raw sequences into 𝕀sd
[_]sd : 𝟛ᴺ → 𝕀sd
[ s ]sd = SQ.[ s ]

-- The quotient is a set
isSet𝕀sd : isSet 𝕀sd
isSet𝕀sd = squash/

------------------------------------------------------------------------
-- Basic elements as signed-digit reals
------------------------------------------------------------------------

-- Zero, one, and negative one as signed-digit reals
0sd : 𝕀sd
0sd = [ zeroStream ]sd

1sd : 𝕀sd
1sd = [ oneStream ]sd

-1sd : 𝕀sd
-1sd = [ negOneStream ]sd

-- Helper: |2q - d| ≤ 1 for q in [-1, 1]
--
-- The proof follows the thresholds of selectDigitFromℚ:
-- Case 1: q < -1/3 → d = -1, so 2q - (-1) = 2q + 1
--         Given -1 ≤ q < -1/3: -2 ≤ 2q < -2/3, so -1 ≤ 2q + 1 < 1/3
--         Hence |2q + 1| ≤ 1
-- Case 2: -1/3 ≤ q ≤ +1/3 → d = 0, so 2q - 0 = 2q
--         Given |q| ≤ 1/3: |2q| ≤ 2/3 ≤ 1
-- Case 3: q > +1/3 → d = +1, so 2q - 1
--         Given +1/3 < q ≤ 1: 2/3 < 2q ≤ 2, so -1/3 < 2q - 1 ≤ 1
--         Hence |2q - 1| ≤ 1

-- Postulate: digit extraction keeps |2q - d| ≤ 1 for q ∈ [-1, 1]
--
-- The proof follows the thresholds of selectDigitFromℚ:
-- Case 1: q < -1/3 → d = -1, so 2q - (-1) = 2q + 1
--         Given -1 ≤ q < -1/3: -2 ≤ 2q < -2/3, so -1 ≤ 2q + 1 < 1/3
--         Hence |2q + 1| ≤ 1 ✓
-- Case 2: -1/3 ≤ q ≤ +1/3 → d = 0, so 2q - 0 = 2q
--         Given |q| ≤ 1/3: |2q| ≤ 2/3 ≤ 1 ✓
-- Case 3: q > +1/3 → d = +1, so 2q - 1
--         Given +1/3 < q ≤ 1: 2/3 < 2q ≤ 2, so -1/3 < 2q - 1 ≤ 1
--         Hence |2q - 1| ≤ 1 ✓
--
-- Proven by mirroring the with-pattern structure of selectDigitFromℚ
-- and using absFrom≤×≤ : - ε ≤ q → q ≤ ε → abs q ≤ ε

-- Helper: 0 ≤ 2 (needed for monotonicity of multiplication)
0≤2ℚ : 0ℚ ℚO.≤ 2ℚ
0≤2ℚ = isTrans≤ 0ℚ 1ℚ 2ℚ 0≤1ℚ (ℚO.inj (1 , refl))

open import Cubical.Tactics.CommRingSolverFast.FastRationalsReflection using (ℚ!!)

-2/3ℚ : ℚ
-2/3ℚ = [ negsuc 1 / 1+ 2 ]

+2/3ℚ : ℚ
+2/3ℚ = [ pos 2 / 1+ 2 ]

-1/3<0 : -1/3ℚ ℚO.< 0ℚ
-1/3<0 = ℚO.inj (0 , refl)

-1≤-1/3 : -1ℚ ℚO.≤ -1/3ℚ
-1≤-1/3 = ℚO.inj (2 , refl)

-1≤-2/3 : -1ℚ ℚO.≤ -2/3ℚ
-1≤-2/3 = ℚO.inj (1 , refl)

-1≤+2/3 : -1ℚ ℚO.≤ +2/3ℚ
-1≤+2/3 = ℚO.inj (5 , refl)

-2/3≤+1 : -2/3ℚ ℚO.≤ +1ℚ
-2/3≤+1 = ℚO.inj (5 , refl)

+2/3≤+1 : +2/3ℚ ℚO.≤ +1ℚ
+2/3≤+1 = ℚO.inj (1 , refl)

mul2-≤ : ∀ {a b : ℚ} → a ℚO.≤ b → (2ℚ ℚP.· a) ℚO.≤ (2ℚ ℚP.· b)
mul2-≤ {a} {b} a≤b =
  subst2 ℚO._≤_ (ℚP.·Comm a 2ℚ) (ℚP.·Comm b 2ℚ)
    (ℚO.≤-·o a b 2ℚ 0≤2ℚ a≤b)

mul2-< : ∀ {a b : ℚ} → a ℚO.< b → (2ℚ ℚP.· a) ℚO.< (2ℚ ℚP.· b)
mul2-< {a} {b} a<b =
  subst2 ℚO._<_ (ℚP.·Comm a 2ℚ) (ℚP.·Comm b 2ℚ)
    (ℚO.<-·o a b 2ℚ (ℚO.inj (1 , refl)) a<b)

expr-1d : (q : ℚ) → (2ℚ ℚP.· q) ℚP.- digitToℚ -1d ≡ (2ℚ ℚP.· q) ℚP.+ 1ℚ
expr-1d q = ℚ!!

expr-0d : (q : ℚ) → (2ℚ ℚP.· q) ℚP.- digitToℚ 0d ≡ 2ℚ ℚP.· q
expr-0d q = ℚ!!

expr-+1d : (q : ℚ) → (2ℚ ℚP.· q) ℚP.- digitToℚ +1d ≡ (2ℚ ℚP.· q) ℚP.- 1ℚ
expr-+1d q = refl

case1-lo : (q : ℚ) → -1ℚ ℚO.≤ q → ℚP.- +1ℚ ℚO.≤ (2ℚ ℚP.· q) ℚP.- digitToℚ -1d
case1-lo q lo =
  subst2 ℚO._≤_ lhs (sym (expr-1d q)) step
  where
    two-lo : (2ℚ ℚP.· -1ℚ) ℚO.≤ (2ℚ ℚP.· q)
    two-lo = mul2-≤ lo

    step : ((2ℚ ℚP.· -1ℚ) ℚP.+ 1ℚ) ℚO.≤ ((2ℚ ℚP.· q) ℚP.+ 1ℚ)
    step = ℚO.≤-+o (2ℚ ℚP.· -1ℚ) (2ℚ ℚP.· q) 1ℚ two-lo

    lhs : (2ℚ ℚP.· -1ℚ) ℚP.+ 1ℚ ≡ ℚP.- +1ℚ
    lhs = ℚ!!

case1-hi : (q : ℚ) → q ℚO.< -1/3ℚ → (2ℚ ℚP.· q) ℚP.- digitToℚ -1d ℚO.≤ +1ℚ
case1-hi q q<-1/3 =
  subst2 ℚO._≤_ (sym (expr-1d q)) rhs step1
  where
    q<0 : q ℚO.< 0ℚ
    q<0 = isTrans< q -1/3ℚ 0ℚ q<-1/3 -1/3<0

    q≤0 : q ℚO.≤ 0ℚ
    q≤0 = weak-ineq q<0

    twoq≤0 : (2ℚ ℚP.· q) ℚO.≤ 0ℚ
    twoq≤0 = subst2 ℚO._≤_ refl (ℚP.·AnnihilL 2ℚ) (mul2-≤ q≤0)

    step1 : ((2ℚ ℚP.· q) ℚP.+ 1ℚ) ℚO.≤ (0ℚ ℚP.+ 1ℚ)
    step1 = ℚO.≤-+o (2ℚ ℚP.· q) 0ℚ 1ℚ twoq≤0

    rhs : (0ℚ ℚP.+ 1ℚ) ≡ +1ℚ
    rhs = ℚP.+IdL 1ℚ

case1b-lo : (q : ℚ) → q ≡ -1/3ℚ → ℚP.- +1ℚ ℚO.≤ (2ℚ ℚP.· q) ℚP.- digitToℚ 0d
case1b-lo q q=-1/3 =
  subst (λ t → ℚP.- +1ℚ ℚO.≤ (2ℚ ℚP.· t) ℚP.- digitToℚ 0d) (sym q=-1/3)
    (subst (ℚP.- +1ℚ ℚO.≤_) e -1≤-2/3)
  where
    e : (2ℚ ℚP.· -1/3ℚ) ℚP.- digitToℚ 0d ≡ -2/3ℚ
    e = ℚ!!

case1b-hi : (q : ℚ) → q ≡ -1/3ℚ → (2ℚ ℚP.· q) ℚP.- digitToℚ 0d ℚO.≤ +1ℚ
case1b-hi q q=-1/3 =
  subst (λ t → (2ℚ ℚP.· t) ℚP.- digitToℚ 0d ℚO.≤ +1ℚ) (sym q=-1/3)
    (subst (ℚO._≤ +1ℚ) e -2/3≤+1)
  where
    e : (2ℚ ℚP.· -1/3ℚ) ℚP.- digitToℚ 0d ≡ -2/3ℚ
    e = ℚ!!

case2-lo : (q : ℚ) → -1/3ℚ ℚO.< q → ℚP.- +1ℚ ℚO.≤ (2ℚ ℚP.· q) ℚP.- digitToℚ 0d
case2-lo q -1/3<q =
  subst (ℚP.- +1ℚ ℚO.≤_) (sym (expr-0d q)) -1≤2q
  where
    -1/3≤q : -1/3ℚ ℚO.≤ q
    -1/3≤q = weak-ineq -1/3<q

    two-step : (2ℚ ℚP.· -1/3ℚ) ℚO.≤ (2ℚ ℚP.· q)
    two-step = mul2-≤ -1/3≤q

    -2/3≤2q : -2/3ℚ ℚO.≤ (2ℚ ℚP.· q)
    -2/3≤2q = subst2 ℚO._≤_ e refl two-step
      where
        e : 2ℚ ℚP.· -1/3ℚ ≡ -2/3ℚ
        e = ℚ!!

    -1≤2q : ℚP.- +1ℚ ℚO.≤ (2ℚ ℚP.· q)
    -1≤2q = isTrans≤ (ℚP.- +1ℚ) -2/3ℚ (2ℚ ℚP.· q) -1≤-2/3 -2/3≤2q

case2-hi : (q : ℚ) → q ℚO.< +1/3ℚ → (2ℚ ℚP.· q) ℚP.- digitToℚ 0d ℚO.≤ +1ℚ
case2-hi q q<+1/3 =
  subst (ℚO._≤ +1ℚ) (sym (expr-0d q))
    (isTrans≤ (2ℚ ℚP.· q) +2/3ℚ +1ℚ 2q≤2/3 +2/3≤+1)
  where
    q≤+1/3 : q ℚO.≤ +1/3ℚ
    q≤+1/3 = weak-ineq q<+1/3

    2q≤2/3 : (2ℚ ℚP.· q) ℚO.≤ +2/3ℚ
    2q≤2/3 = subst2 ℚO._≤_ refl e (mul2-≤ q≤+1/3)
      where
        e : 2ℚ ℚP.· +1/3ℚ ≡ +2/3ℚ
        e = ℚ!!

case2b-lo : (q : ℚ) → q ≡ +1/3ℚ → ℚP.- +1ℚ ℚO.≤ (2ℚ ℚP.· q) ℚP.- digitToℚ 0d
case2b-lo q q=+1/3 =
  subst (λ t → ℚP.- +1ℚ ℚO.≤ (2ℚ ℚP.· t) ℚP.- digitToℚ 0d) (sym q=+1/3)
    (subst (ℚP.- +1ℚ ℚO.≤_) e -1≤+2/3)
  where
    e : (2ℚ ℚP.· +1/3ℚ) ℚP.- digitToℚ 0d ≡ +2/3ℚ
    e = ℚ!!

case2b-hi : (q : ℚ) → q ≡ +1/3ℚ → (2ℚ ℚP.· q) ℚP.- digitToℚ 0d ℚO.≤ +1ℚ
case2b-hi q q=+1/3 =
  subst (λ t → (2ℚ ℚP.· t) ℚP.- digitToℚ 0d ℚO.≤ +1ℚ) (sym q=+1/3)
    (subst (ℚO._≤ +1ℚ) e +2/3≤+1)
  where
    e : (2ℚ ℚP.· +1/3ℚ) ℚP.- digitToℚ 0d ≡ +2/3ℚ
    e = ℚ!!

case3-lo : (q : ℚ) → +1/3ℚ ℚO.< q → ℚP.- +1ℚ ℚO.≤ (2ℚ ℚP.· q) ℚP.- digitToℚ +1d
case3-lo q +1/3<q =
  subst (ℚP.- +1ℚ ℚO.≤_) (sym (expr-+1d q))
    (isTrans≤ (ℚP.- +1ℚ) -1/3ℚ (((2ℚ ℚP.· q) ℚP.+ (ℚP.- 1ℚ))) -1≤-1/3 -1/3≤rhs)
  where
    +1/3≤q : +1/3ℚ ℚO.≤ q
    +1/3≤q = weak-ineq +1/3<q

    2/3≤2q : +2/3ℚ ℚO.≤ (2ℚ ℚP.· q)
    2/3≤2q = subst2 ℚO._≤_ e refl (mul2-≤ +1/3≤q)
      where
        e : 2ℚ ℚP.· +1/3ℚ ≡ +2/3ℚ
        e = ℚ!!

    -1/3≤rhs : -1/3ℚ ℚO.≤ (((2ℚ ℚP.· q) ℚP.+ (ℚP.- 1ℚ)))
    -1/3≤rhs =
      subst2 ℚO._≤_ lhs rhs
        (ℚO.≤-+o +2/3ℚ (2ℚ ℚP.· q) (ℚP.- 1ℚ) 2/3≤2q)
      where
        lhs : (+2/3ℚ ℚP.+ (ℚP.- 1ℚ)) ≡ -1/3ℚ
        lhs = ℚ!!
        rhs : ((2ℚ ℚP.· q) ℚP.+ (ℚP.- 1ℚ)) ≡ (((2ℚ ℚP.· q) ℚP.+ (ℚP.- 1ℚ)))
        rhs = refl

case3-hi : (q : ℚ) → q ℚO.≤ +1ℚ → (2ℚ ℚP.· q) ℚP.- digitToℚ +1d ℚO.≤ +1ℚ
case3-hi q q≤1 =
  subst2 ℚO._≤_ (sym (expr-+1d q)) rhs step
  where
    2q≤2 : (2ℚ ℚP.· q) ℚO.≤ (2ℚ ℚP.· +1ℚ)
    2q≤2 = mul2-≤ q≤1

    step : (((2ℚ ℚP.· q) ℚP.+ (ℚP.- 1ℚ))) ℚO.≤ (((2ℚ ℚP.· +1ℚ) ℚP.+ (ℚP.- 1ℚ)))
    step = ℚO.≤-+o (2ℚ ℚP.· q) (2ℚ ℚP.· +1ℚ) (ℚP.- 1ℚ) 2q≤2

    rhs : (((2ℚ ℚP.· +1ℚ) ℚP.+ (ℚP.- 1ℚ))) ≡ +1ℚ
    rhs = ℚ!!

0<+1/3 : 0ℚ ℚO.< +1/3ℚ
0<+1/3 = ℚO.inj (0 , refl)

-1/3<+1/3 : -1/3ℚ ℚO.< +1/3ℚ
-1/3<+1/3 = isTrans< -1/3ℚ 0ℚ +1/3ℚ -1/3<0 0<+1/3

digit-bound : (q : ℚ) → -1ℚ ℚO.≤ q → q ℚO.≤ +1ℚ →
    ℚP.abs ((2ℚ ℚP.· q) ℚP.- digitToℚ (selectDigitFromℚ q)) ℚO.≤ +1ℚ
digit-bound q lo hi =
  subst (λ t → ℚP.abs ((2ℚ ℚP.· t) ℚP.- digitToℚ (selectDigitFromℚ q)) ℚO.≤ +1ℚ)
    (sym q≡clamp)
    digit-bound-clamped
  where
    open import Cubical.Data.Rationals.Fast.Order.Properties as ℚOP' using (clamp≤; ≤clamp)

    q≡clamp : q ≡ clampℚ q
    q≡clamp = ℚOP.∈ℚintervalℙ→clam≡ -1ℚ +1ℚ q (lo , hi) ∙ sym (clampℚ≡clamp q)

    lo' : -1ℚ ℚO.≤ clampℚ q
    lo' = subst (-1ℚ ℚO.≤_) (sym (clampℚ≡clamp q))
            (ℚOP'.≤clamp -1ℚ +1ℚ q -1≤+1)

    hi' : clampℚ q ℚO.≤ +1ℚ
    hi' = subst (λ t → t ℚO.≤ +1ℚ) (sym (clampℚ≡clamp q))
            (ℚOP'.clamp≤ -1ℚ +1ℚ q)

    digit-bound-clamped :
      ℚP.abs ((2ℚ ℚP.· clampℚ q) ℚP.- digitToℚ (selectDigitFromℚ q)) ℚO.≤ +1ℚ
    digit-bound-clamped with -1/3ℚ ℚO.≟ clampℚ q
    ... | ℚO.gt q<-1/3 =
      absFrom≤×≤ +1ℚ expr (case1-lo (clampℚ q) lo') (case1-hi (clampℚ q) q<-1/3)
      where
        expr = (2ℚ ℚP.· clampℚ q) ℚP.- digitToℚ -1d
    ... | ℚO.eq q=-1/3 =
      absFrom≤×≤ +1ℚ expr
        (case1b-lo (clampℚ q) (sym q=-1/3))
        (case1b-hi (clampℚ q) (sym q=-1/3))
      where
        expr = (2ℚ ℚP.· clampℚ q) ℚP.- digitToℚ 0d
    ... | ℚO.lt -1/3<q with +1/3ℚ ℚO.≟ clampℚ q
    ...   | ℚO.lt +1/3<q =
      absFrom≤×≤ +1ℚ expr (case3-lo (clampℚ q) +1/3<q) (case3-hi (clampℚ q) hi')
      where
        expr = (2ℚ ℚP.· clampℚ q) ℚP.- digitToℚ +1d
    ...   | ℚO.eq q=+1/3 =
      absFrom≤×≤ +1ℚ expr
        (case2b-lo (clampℚ q) (sym q=+1/3))
        (case2b-hi (clampℚ q) (sym q=+1/3))
      where
        expr = (2ℚ ℚP.· clampℚ q) ℚP.- digitToℚ 0d
    ...   | ℚO.gt q<+1/3 =
      absFrom≤×≤ +1ℚ expr (case2-lo (clampℚ q) -1/3<q) (case2-hi (clampℚ q) q<+1/3)
      where
        expr = (2ℚ ℚP.· clampℚ q) ℚP.- digitToℚ 0d

-- Algebraic identity: q - approx s n = remainderₙ q (suc n) · 1/2^(n+1)
--
-- Proof sketch:
-- Base (n=0): q - d₀/2 = (2q - d₀)/2
--   Since |2q - d₀| ≤ 1 (digit-bound), clampℚ(2q - d₀) = 2q - d₀
--   So remainderₙ q 1 = 2q - d₀
--   And (2q - d₀) · 1/2 = q - d₀/2 ✓
--
-- Inductive (n → n+1): Uses similar algebraic manipulation
--   with the recurrence for remainderₙ and approx
--
minus-on-sum : (x y z : ℚ) → x ℚP.- (y ℚP.+ z) ≡ (x ℚP.- y) ℚP.- z
minus-on-sum x y z = ℚ!!

base-half-step : (x d : ℚ) →
  x ℚP.- (d ℚP.· inv2^ zero) ≡ (((2ℚ ℚP.· x) ℚP.- d) ℚP.· inv2^ zero)
base-half-step x d = ℚ!!

inductive-half-step : (r d : ℚ) (n : ℕ) →
  ((r ℚP.· inv2^ n) ℚP.- (d ℚP.· inv2^ (suc n)))
  ≡ (((2ℚ ℚP.· r) ℚP.- d) ℚP.· inv2^ (suc n))
inductive-half-step r d n =
  subst (λ t → ((r ℚP.· t) ℚP.- (d ℚP.· a)) ≡ (((2ℚ ℚP.· r) ℚP.- d) ℚP.· a))
    (2·inv2^-suc n)
    lemma
  where
    a : ℚ
    a = inv2^ (suc n)

    lemma : ((r ℚP.· (2ℚ ℚP.· a)) ℚP.- (d ℚP.· a))
            ≡ (((2ℚ ℚP.· r) ℚP.- d) ℚP.· a)
    lemma =
      subst (λ t → ((r ℚP.· t) ℚP.- (d ℚP.· a)) ≡ (((2ℚ ℚP.· r) ℚP.- d) ℚP.· a))
        (x+x≡2·x a)
        (subst (λ t → ((r ℚP.· (a ℚP.+ a)) ℚP.- (d ℚP.· a)) ≡ ((t ℚP.- d) ℚP.· a))
          (x+x≡2·x r)
          lemma₊)
      where
        lemma₊ : ((r ℚP.· (a ℚP.+ a)) ℚP.- (d ℚP.· a))
                 ≡ (((r ℚP.+ r) ℚP.- d) ℚP.· a)
        lemma₊ =
          cong (λ t → t ℚP.- (d ℚP.· a)) (ℚP.·DistL+ r a a)
          ∙ sym rhs-to-left
          where
            negmul : (ℚP.- d) ℚP.· a ≡ ℚP.- (d ℚP.· a)
            negmul = sym (ℚP.·Assoc -1ℚ d a)

            rhs-to-left : (((r ℚP.+ r) ℚP.- d) ℚP.· a)
                        ≡ (((r ℚP.· a) ℚP.+ (r ℚP.· a)) ℚP.- (d ℚP.· a))
            rhs-to-left =
              ℚP.·DistR+ (r ℚP.+ r) (ℚP.- d) a
              ∙ cong (λ t → t ℚP.+ ((ℚP.- d) ℚP.· a)) (ℚP.·DistR+ r r a)
              ∙ cong (λ t → ((r ℚP.· a) ℚP.+ (r ℚP.· a)) ℚP.+ t) negmul

clampℚ-fixed : (x : ℚ) → -1ℚ ℚO.≤ x → x ℚO.≤ +1ℚ → clampℚ x ≡ x
clampℚ-fixed x lo hi =
  clampℚ≡clamp x ∙ sym (ℚOP.∈ℚintervalℙ→clam≡ -1ℚ +1ℚ x (lo , hi))

remainder-shift : (q : ℚ) (n : ℕ) →
  remainderₙ (nextStateℚ q (selectDigitFromℚ q)) n ≡ remainderₙ q (suc n)
remainder-shift q zero = refl
remainder-shift q (suc n) =
  cong₂ nextStateℚ ih (cong selectDigitFromℚ ih)
  where
    ih : remainderₙ (nextStateℚ q (selectDigitFromℚ q)) n ≡ remainderₙ q (suc n)
    ih = remainder-shift q n

stream-digit-remainder : (q : ℚ) (n : ℕ) →
  rational→stream q ! n ≡ selectDigitFromℚ (remainderₙ q n)
stream-digit-remainder q zero = refl
stream-digit-remainder q (suc n) =
  stream-digit-remainder (nextStateℚ q (selectDigitFromℚ q)) n
  ∙ cong selectDigitFromℚ (remainder-shift q n)

abs≤1→interval : (x : ℚ) → ℚP.abs x ℚO.≤ +1ℚ → (-1ℚ ℚO.≤ x) × (x ℚO.≤ +1ℚ)
abs≤1→interval x abs≤1 = lo , hi
  where
    hi : x ℚO.≤ +1ℚ
    hi = isTrans≤ x (ℚP.abs x) +1ℚ (x≤abs-x x) abs≤1

    neg≤1 : (ℚP.- x) ℚO.≤ +1ℚ
    neg≤1 = isTrans≤ (ℚP.- x) (ℚP.abs x) +1ℚ (neg-x≤abs-x x) abs≤1

    lo : -1ℚ ℚO.≤ x
    lo = subst (-1ℚ ℚO.≤_) (ℚP.-Invol x)
          (ℚO.minus-≤ (ℚP.- x) +1ℚ neg≤1)

approx-sum-remainder-bounded : (q : ℚ) → -1ℚ ℚO.≤ q → q ℚO.≤ +1ℚ → (n : ℕ) →
  (q ℚP.- approx (rational→stream q) n) ≡ (remainderₙ q (suc n)) ℚP.· inv2^ n

-- Helper: |clampℚ x| ≤ 1 for any x
-- Proof: clampℚ x ∈ [-1, 1] by definition of clamp
--   - clampℚ x ≤ +1 (by clamp≤)
--   - -1 ≤ clampℚ x (by ≤clamp, using -1 ≤ +1)
-- Then |clampℚ x| = max (clampℚ x) (-(clampℚ x)) ≤ 1
clampℚ-bound : (x : ℚ) → ℚP.abs (clampℚ x) ℚO.≤ +1ℚ
clampℚ-bound x = max-LUB (clampℚ x) (ℚP.- clampℚ x) +1ℚ upper-bound neg-upper-bound
  where
    open import Cubical.Data.Rationals.Fast.Order.Properties as ℚOP' using (clamp≤; ≤clamp)

    -- clampℚ x ≤ +1 from clamp≤
    clampℚ≤1-via-clamp : ℚO.clamp -1ℚ +1ℚ x ℚO.≤ +1ℚ
    clampℚ≤1-via-clamp = ℚOP'.clamp≤ -1ℚ +1ℚ x

    upper-bound : clampℚ x ℚO.≤ +1ℚ
    upper-bound = subst (ℚO._≤ +1ℚ) (sym (clampℚ≡clamp x)) clampℚ≤1-via-clamp

    -- -1 ≤ clampℚ x from ≤clamp
    -1≤clampℚ-via-clamp : -1ℚ ℚO.≤ ℚO.clamp -1ℚ +1ℚ x
    -1≤clampℚ-via-clamp = ℚOP'.≤clamp -1ℚ +1ℚ x -1≤+1

    -1≤clampℚ : -1ℚ ℚO.≤ clampℚ x
    -1≤clampℚ = subst (-1ℚ ℚO.≤_) (sym (clampℚ≡clamp x)) -1≤clampℚ-via-clamp

    -- -clampℚ x ≤ +1 means clampℚ x ≥ -1
    neg-upper-bound : ℚP.- clampℚ x ℚO.≤ +1ℚ
    neg-upper-bound = subst (ℚP.- clampℚ x ℚO.≤_) (sym (ℚP.-Invol 1ℚ))
                        (ℚO.minus-≤ -1ℚ (clampℚ x) -1≤clampℚ)

-- remainderₙ q n is bounded by 1 for all n
-- - Base case: remainderₙ q 0 = q, and |q| ≤ 1 by assumption
-- - Inductive case: remainderₙ q (suc n) = clampℚ(...), and |clampℚ x| ≤ 1
remainder-bound : (q : ℚ) → -1ℚ ℚO.≤ q → q ℚO.≤ +1ℚ → (n : ℕ) →
  ℚP.abs (remainderₙ q n) ℚO.≤ +1ℚ
remainder-bound q lo hi zero = max-LUB q (ℚP.- q) +1ℚ hi neg-bound
  where
    -- -q ≤ 1 follows from -1 ≤ q
    neg-bound : ℚP.- q ℚO.≤ +1ℚ
    neg-bound = subst (ℚP.- q ℚO.≤_) (sym (ℚP.-Invol 1ℚ)) (ℚO.minus-≤ -1ℚ q lo)
remainder-bound q lo hi (suc n) =
  subst (λ t → ℚP.abs t ℚO.≤ +1ℚ) step-eq
    (digit-bound (clampℚ r) lo' hi')
  where
    open import Cubical.Data.Rationals.Fast.Order.Properties as ℚOP' using (clamp≤; ≤clamp)

    r : ℚ
    r = remainderₙ q n

    lo' : -1ℚ ℚO.≤ clampℚ r
    lo' = subst (-1ℚ ℚO.≤_) (sym (clampℚ≡clamp r))
            (ℚOP'.≤clamp -1ℚ +1ℚ r -1≤+1)

    hi' : clampℚ r ℚO.≤ +1ℚ
    hi' = subst (λ t → t ℚO.≤ +1ℚ) (sym (clampℚ≡clamp r))
            (ℚOP'.clamp≤ -1ℚ +1ℚ r)

    sel-clamp : selectDigitFromℚ (clampℚ r) ≡ selectDigitFromℚ r
    sel-clamp = cong selectDigitFromℚ-raw (clampℚ-idem r)

    step-eq : (2ℚ ℚP.· clampℚ r) ℚP.- digitToℚ (selectDigitFromℚ (clampℚ r))
            ≡ remainderₙ q (suc n)
    step-eq = cong (λ d → (2ℚ ℚP.· clampℚ r) ℚP.- digitToℚ d) sel-clamp

approx-sum-remainder-bounded q lo hi zero =
  cong (λ x → q ℚP.- x) approx0
  ∙ base-half-step q (digitToℚ d₀)
  ∙ cong (λ t → t ℚP.· inv2^ zero) (sym rem₁-unclamped)
  where
    d₀ : Digit
    d₀ = selectDigitFromℚ q

    approx0 : approx (rational→stream q) zero ≡ digitToℚ d₀ ℚP.· inv2^ zero
    approx0 = refl

    rem₁-unclamped : remainderₙ q (suc zero) ≡ (2ℚ ℚP.· q) ℚP.- digitToℚ d₀
    rem₁-unclamped =
      cong (λ t → (2ℚ ℚP.· t) ℚP.- digitToℚ d₀)
        (clampℚ-fixed q lo hi)

approx-sum-remainder-bounded q lo hi (suc n) =
  cong (λ x → q ℚP.- x) approx-suc
  ∙ minus-on-sum q (approx s n) dc
  ∙ cong (λ t → (q ℚP.- approx s n) ℚP.- t) dc-to-d
  ∙ cong (λ t → t ℚP.- (digitToℚ d ℚP.· inv2^ (suc n))) ih
  ∙ inductive-half-step r (digitToℚ d) n
  ∙ cong (λ t → t ℚP.· inv2^ (suc n)) (sym rem-next-unclamped)
  where
    s : 𝟛ᴺ
    s = rational→stream q

    r : ℚ
    r = remainderₙ q (suc n)

    d : Digit
    d = selectDigitFromℚ r

    dc : ℚ
    dc = digitContrib (s ! suc n) (suc n)

    approx-suc : approx s (suc n) ≡ approx s n ℚP.+ dc
    approx-suc = refl

    dc-to-d : dc ≡ digitToℚ d ℚP.· inv2^ (suc n)
    dc-to-d = cong (λ e → digitToℚ e ℚP.· inv2^ (suc n))
               (stream-digit-remainder q (suc n))

    ih : (q ℚP.- approx s n) ≡ r ℚP.· inv2^ n
    ih = approx-sum-remainder-bounded q lo hi n

    r-bound : ℚP.abs r ℚO.≤ +1ℚ
    r-bound = remainder-bound q lo hi (suc n)

    r-lo : -1ℚ ℚO.≤ r
    r-lo = fst (abs≤1→interval r r-bound)

    r-hi : r ℚO.≤ +1ℚ
    r-hi = snd (abs≤1→interval r r-bound)

    rem-next-unclamped : remainderₙ q (suc (suc n)) ≡ (2ℚ ℚP.· r) ℚP.- digitToℚ d
    rem-next-unclamped =
      cong (λ t → (2ℚ ℚP.· t) ℚP.- digitToℚ d)
        (clampℚ-fixed r r-lo r-hi)

-- Main convergence theorem: |q - approx s n| ≤ 1/2^(n+1) ≤ 1/2^n
--
-- Proof:
-- 1. By approx-sum-remainder-bounded: q - approx s n = rₙ₊₁ · inv2^ n
-- 2. |q - approx s n| = |rₙ₊₁| · inv2^ n   (since inv2^ ≥ 0)
-- 3.                  ≤ 1 · inv2^ n         (by remainder-bound)
approx-converges : (q : ℚ) → -1ℚ ℚO.≤ q → q ℚO.≤ +1ℚ → (n : ℕ) →
  ℚP.abs (q ℚP.- approx (rational→stream q) n) ℚO.≤ inv2^ n
approx-converges q lo hi n = isTrans≤ _ _ _ step3 step4
  where
    open import Cubical.Data.Rationals.Fast.Order.Properties as ℚOP' using (pos·abs; ≤Monotone·-onNonNeg; 0≤abs)

    s = rational→stream q
    r = remainderₙ q (suc n)

    -- Step 1: q - approx s n = r · inv2^ n
    decomp : (q ℚP.- approx s n) ≡ r ℚP.· inv2^ n
    decomp = approx-sum-remainder-bounded q lo hi n

    -- Step 2: |q - approx s n| = |r · inv2^ n| = |r| · inv2^ n
    -- Using pos·abs: 0 ≤ x → |x · y| = x · |y|
    -- We have |r · inv2^|, need to flip to |inv2^ · r| first using ·Comm inside abs
    abs-decomp : ℚP.abs (q ℚP.- approx s n) ≡ ℚP.abs r ℚP.· inv2^ n
    abs-decomp = cong ℚP.abs decomp
               ∙ cong ℚP.abs (ℚP.·Comm r (inv2^ n))
               ∙ ℚOP'.pos·abs (inv2^ n) r (0≤inv2^ n)
               ∙ ℚP.·Comm (inv2^ n) (ℚP.abs r)

    -- Step 3: |r| · inv2^ n ≤ 1 · inv2^ n = inv2^ n
    -- Using ≤Monotone·-onNonNeg: x ≤ x' → y ≤ y' → 0 ≤ x → 0 ≤ y → x · y ≤ x' · y'
    r-bound : ℚP.abs r ℚO.≤ +1ℚ
    r-bound = remainder-bound q lo hi (suc n)

    mono-ineq : ℚP.abs r ℚP.· inv2^ n ℚO.≤ +1ℚ ℚP.· inv2^ n
    mono-ineq = ℚOP'.≤Monotone·-onNonNeg (ℚP.abs r) +1ℚ (inv2^ n) (inv2^ n)
                  r-bound (isRefl≤ (inv2^ n))
                  (ℚOP'.0≤abs r) (0≤inv2^ n)

    step3 : ℚP.abs (q ℚP.- approx s n) ℚO.≤ inv2^ n
    step3 = subst (ℚO._≤ inv2^ n) (sym abs-decomp)
              (subst (ℚP.abs r ℚP.· inv2^ n ℚO.≤_) (ℚP.·IdL (inv2^ n)) mono-ineq)

    step4 : inv2^ n ℚO.≤ inv2^ n
    step4 = isRefl≤ (inv2^ n)

-- The ℚ₊ version: converts from ℕ-indexed to ℚ₊-indexed precision
-- Proof: |q - approxℚ₊ s δ| ≤ inv2^ (ℚ₊→ℕ δ) < fst δ
approx-converges-ℚ₊ : (q : ℚ) → -1ℚ ℚO.≤ q → q ℚO.≤ +1ℚ → (δ : ℚ₊) →
  ℚP.abs (q ℚP.- approxℚ₊ (rational→stream q) δ) ℚO.< ℚᶠ→ℚ (fst δ)
approx-converges-ℚ₊ q lo hi δ = ≤<→< conv mod
  where
    n = ℚ₊→ℕ δ
    s = rational→stream q

    -- By approx-converges: |q - approx s n| ≤ inv2^ n
    conv : ℚP.abs (q ℚP.- approx s n) ℚO.≤ inv2^ n
    conv = approx-converges q lo hi n

    -- By modulus-correct: inv2^ n < fst δ
    mod : inv2^ n ℚO.< ℚᶠ→ℚ (fst δ)
    mod = modulus-correct δ

-- Definitions (formerly postulates)

private
  head-inv : (q : ℚ) → selectDigitFromℚ q ≡ selectDigitFromℚ (clampℚ q)
  head-inv q = cong selectDigitFromℚ-raw (sym (clampℚ-idem q))

  nextState-inv : (q : ℚ) (d : Digit) → nextStateℚ q d ≡ nextStateℚ (clampℚ q) d
  nextState-inv q d = cong (λ x → (2ℚ ℚP.· x) ℚP.- digitToℚ d) (sym (clampℚ-idem q))

-- Postulate Lipschitz continuity and clamp invariance
rational→stream-clamp-eq : (q : ℚ) → rational→stream q ≡ rational→stream (clampℚ q)
rational→stream-clamp-eq q i .head = head-inv q i
rational→stream-clamp-eq q i .tail = 
  let d = selectDigitFromℚ q
      d' = selectDigitFromℚ (clampℚ q)
      EqD : d ≡ d'
      EqD = head-inv q
      
      EqN : nextStateℚ q d ≡ nextStateℚ (clampℚ q) d'
      EqN = trans 
             (cong (nextStateℚ q) EqD) 
             (nextState-inv q d')
  in (cong rational→stream EqN) i
  where
    trans : {A : Type} {x y z : A} → x ≡ y → y ≡ z → x ≡ z
    trans p q = p ∙ q

-- Arithmetic helpers
trans-≤ : {x y z : ℚ} → x ℚO.≤ y → y ℚO.≤ z → x ℚO.≤ z
trans-≤ {x} {y} {z} xy yz = ℚO.isTrans≤ x y z xy yz

-- Lipschitz property for clamp: use library's clampDist
-- clamp d u x = min (max d x) u
-- clampℚ q = max -1 (min +1 q)
-- These are equal by minDistMax: max x (min y y') = min (max x y) (max x y')
clamp-lip : (x y : ℚ) → ℚP.abs (clampℚ x ℚP.- clampℚ y) ℚO.≤ ℚP.abs (x ℚP.- y)
clamp-lip x y = subst2 ℚO._≤_ eq1 refl (ℚOP.clampDist -1ℚ +1ℚ y x)
  -- clampDist -1 +1 y x : abs (clamp -1 +1 x - clamp -1 +1 y) ≤ abs (x - y)
  -- We need to convert clamp -1 +1 to clampℚ using sym clampℚ≡clamp
  where
    eq1 : ℚP.abs (ℚO.clamp -1ℚ +1ℚ x ℚP.- ℚO.clamp -1ℚ +1ℚ y) ≡ ℚP.abs (clampℚ x ℚP.- clampℚ y)
    eq1 = cong₂ (λ a b → ℚP.abs (a ℚP.- b)) (sym (clampℚ≡clamp x)) (sym (clampℚ≡clamp y))


------------------------------------------------------------------------
-- The embedding respects the equivalence relation
------------------------------------------------------------------------

-- Two ≈sd-equivalent streams map to equal reals.
-- With the new ≈sd definition (s ≈sd t = stream→ℝ s ≡ stream→ℝ t),
-- this is trivially the identity.
stream→ℝ-resp : ∀ s t → s ≈sd t → stream→ℝ s ≡ stream→ℝ t
stream→ℝ-resp s t h = h

-- --------------------------------------------------------------------------
-- ℝ is a set (required for quotient elimination)

-- Embedding from signed-digit reals to HoTT Cauchy reals
ι : 𝕀sd → ℝ
ι = SQ.rec isSetℝ stream→ℝ stream→ℝ-resp

------------------------------------------------------------------------
-- Bounded real subtype helpers (safe public API)
------------------------------------------------------------------------

minusOneℝ : ℝ
minusOneℝ = rat -1ℚ

oneℝ : ℝ
oneℝ = rat +1ℚ

minusOne≤one : minusOneℝ ℝO.≤ᵣ oneℝ
minusOne≤one = ℝO.≤ℚ→≤ᵣ -1ℚ +1ℚ -1≤+1

ℝ[-1,1] : Type₀
ℝ[-1,1] = Σ ℝ (λ x → (minusOneℝ ℝO.≤ᵣ x) × (x ℝO.≤ᵣ oneℝ))

clamp-to-𝕀sd : ℝ → ℝ[-1,1]
clamp-to-𝕀sd x =
  ℝO.clampᵣ minusOneℝ oneℝ x
  , ℝInv.clampᵣ∈ℚintervalℙ minusOneℝ oneℝ minusOne≤one x
