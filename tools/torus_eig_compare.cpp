/// \file
/// Eigensolve comparison on the lattice-gauge-solvers setup (periodic 3-torus,
/// uniform magnetic field): our gauge-MG Rayleigh-quotient eigensolver vs the
/// SLEPc Lanczos baseline for the smallest eigenpair of the U(1) connection
/// Laplacian. Both solve the SAME operator (asserted: the assembled CooMatrix
/// the Lanczos path uses is the real embedding of the matrix-free lattice the
/// covMG-LOBPCG path preconditions), to the same tolerance; we report the eigenvalue
/// (must agree), outer iterations, and wall-clock.
///
/// It also reports a SINGLE gauge-MG linear solve and, from it, the estimated
/// cost of a classical (shift-and-invert) backward/inverse iteration =
/// per-solve time x outer iterations -- so the eigensolve numbers can be read
/// off the linear-solve timings, as requested.
///
/// Usage: torus_eig_compare [n] [nPhi]   (defaults 16 4 = the uniform-field example)
#include <chrono>
#include <cmath>
#include <complex>
#include <cstdio>
#include <cstdlib>
#include <vector>

#include <slepc.h>

#include "BenchTiming.h"
#include "grid/CooMatrix.h"
#include "solvers/EigenSolver.h"
#include "solvers/GaugeEigen.h"
#include "solvers/GaugeMultigrid.h"

using bochner::GaugeLattice;
using benchstat::medianMs;
using cd = std::complex<double>;

namespace {

// The lattice-gauge-solvers Examples::uniformField: nPhi flux quanta through the
// x-y torus in the Landau/seam gauge, as bochner forward links.
GaugeLattice uniformFluxLattice(int n, int nPhi, double h) {
  const double phi_p = 2.0 * M_PI * nPhi / (double(n) * n);
  const std::size_t N = static_cast<std::size_t>(n) * n * n;
  std::vector<double> lkx(N, 0.0), lky(N, 0.0), lkz(N, 0.0);
  const auto idx = [&](int i, int j, int k) { return (i * n + j) * n + k; };
  for (int i = 0; i < n; ++i)
    for (int j = 0; j < n; ++j)
      for (int k = 0; k < n; ++k) {
        lkx[idx(i, j, k)] = -phi_p * j;
        if (j == n - 1) lky[idx(i, j, k)] = 2.0 * M_PI * nPhi * i / double(n);
      }
  return bochner::gaugeLatticePeriodic(n, n, n, 1.0 / (h * h), lkx, lky, lkz);
}

// Assemble the same periodic operator as a real 2N CooMatrix (the Lanczos input),
// matching applyConnectionLaplacian: diagonal 6w, off-diagonal -w e^{-i theta}.
bochner::CooMatrix assemblePeriodic(const GaugeLattice& L) {
  const int n = static_cast<int>(L.numNodes());
  bochner::CooMatrix A(2 * n, 2 * n);
  const auto blk = [&](int a, int b, double re, double im) {
    A.add(2 * a, 2 * b, re);
    A.add(2 * a, 2 * b + 1, -im);
    A.add(2 * a + 1, 2 * b, im);
    A.add(2 * a + 1, 2 * b + 1, re);
  };
  const auto lnk = [&](int a, int b, double th) {
    blk(a, a, L.w, 0.0);
    blk(b, b, L.w, 0.0);
    blk(a, b, -L.w * std::cos(th), L.w * std::sin(th));   // -w e^{-i th}
    blk(b, a, -L.w * std::cos(th), -L.w * std::sin(th));  // conj
  };
  const auto id = [&](int i, int j, int k) { return (i * L.ly + j) * L.lz + k; };
  for (int i = 0; i < L.lx; ++i)
    for (int j = 0; j < L.ly; ++j)
      for (int k = 0; k < L.lz; ++k) {
        const int c = id(i, j, k);
        lnk(c, id((i + 1) % L.lx, j, k), L.lkx[c]);
        lnk(c, id(i, (j + 1) % L.ly, k), L.lky[c]);
        lnk(c, id(i, j, (k + 1) % L.lz), L.lkz[c]);
      }
  return A;
}

// --- Chebyshev-Davidson (Zhou & Saad 2007, single lowest eigenpair) ----------
// 2026-08-15 survey round: the Davidson-shaped sibling of the cheb-LOBPCG
// baseline, to test whether the polynomial cell's cost is outer-loop-dependent.
// Same fairness conventions as BOCHNER_CHEB_SWEEP: filter interval [b/ratio, b]
// with b the Gershgorin bound (zero setup), degree x ratio swept, best
// converged config reported. The filter amplifies components below a relative
// to [a, b]; the outer loop grows an orthonormal basis, Rayleigh-Ritz, thick
// restart. No preconditioner slot exists in this method.

// y = T_m(Amap) x, Amap = (2L - (b+a)I)/(b-a), with joint rescaling of the
// recurrence pair each step (a scalar on BOTH iterates preserves the
// polynomial's direction while preventing overflow of the cosh growth).
std::vector<cd> chebFilterVec(const GaugeLattice& lat, const std::vector<cd>& x, int m, double a,
                              double b) {
  const std::size_t N = x.size();
  const double c = 0.5 * (b + a), e = 0.5 * (b - a);
  auto amap = [&](const std::vector<cd>& v) {
    std::vector<cd> y = bochner::applyConnectionLaplacian(lat, v);
    for (std::size_t i = 0; i < N; ++i) y[i] = (y[i] - c * v[i]) / e;
    return y;
  };
  std::vector<cd> tPrev = x, tCur = amap(x);
  for (int k = 2; k <= m; ++k) {
    std::vector<cd> tNext = amap(tCur);
    for (std::size_t i = 0; i < N; ++i) tNext[i] = 2.0 * tNext[i] - tPrev[i];
    tPrev = std::move(tCur);
    tCur = std::move(tNext);
    double mx = 0.0;
    for (const cd& z : tCur) mx = std::max(mx, std::abs(z));
    if (mx > 1e100) {
      const double s = 1.0 / mx;
      for (cd& z : tCur) z *= s;
      for (cd& z : tPrev) z *= s;
    }
  }
  return tCur;
}

// Smallest eigenpair of an m x m complex-Hermitian matrix by cyclic Jacobi
// (general-size version of GaugeEigen's 3x3 helper; m <= kMaxBasis).
constexpr int kMaxBasis = 24;
void hermJacobiSmallest(int m, std::vector<cd>& H /* m*m row-major */, double& lam,
                        std::vector<cd>& y) {
  std::vector<cd> V(static_cast<std::size_t>(m) * m, cd(0, 0));
  for (int i = 0; i < m; ++i) V[i * m + i] = cd(1, 0);
  auto D = [&](int i, int j) -> cd& { return H[i * m + j]; };
  auto Vv = [&](int i, int j) -> cd& { return V[i * m + j]; };
  for (int sweep = 0; sweep < 60; ++sweep) {
    double off = 0.0;
    for (int p = 0; p < m; ++p)
      for (int q = p + 1; q < m; ++q) off += std::norm(D(p, q));
    if (off < 1e-28) break;
    for (int p = 0; p < m; ++p)
      for (int q = p + 1; q < m; ++q) {
        const cd dpq = D(p, q);
        if (std::abs(dpq) < 1e-16) continue;
        const double app = D(p, p).real(), aqq = D(q, q).real(), mag = std::abs(dpq);
        const cd g = std::exp(cd(0.0, -std::arg(dpq)));
        const double th = 0.5 * std::atan2(2.0 * mag, app - aqq);
        const double cc = std::cos(th), ss = std::sin(th);
        const cd U00(cc, 0.0), U01(-ss, 0.0), U10 = g * ss, U11 = g * cc;
        const cd c00 = std::conj(U00), c01 = std::conj(U01), c10 = std::conj(U10),
                 c11 = std::conj(U11);
        for (int i = 0; i < m; ++i) {
          const cd dip = D(i, p), diq = D(i, q);
          D(i, p) = dip * U00 + diq * U10;
          D(i, q) = dip * U01 + diq * U11;
        }
        for (int j = 0; j < m; ++j) {
          const cd dpj = D(p, j), dqj = D(q, j);
          D(p, j) = c00 * dpj + c10 * dqj;
          D(q, j) = c01 * dpj + c11 * dqj;
        }
        for (int i = 0; i < m; ++i) {
          const cd vip = Vv(i, p), viq = Vv(i, q);
          Vv(i, p) = vip * U00 + viq * U10;
          Vv(i, q) = vip * U01 + viq * U11;
        }
      }
  }
  int jmin = 0;
  for (int j = 1; j < m; ++j)
    if (D(j, j).real() < D(jmin, jmin).real()) jmin = j;
  lam = D(jmin, jmin).real();
  y.assign(m, cd(0, 0));
  for (int i = 0; i < m; ++i) y[i] = Vv(i, jmin);
}

struct ChebDavResult {
  double eigenvalue = 0.0;
  double residual = 0.0;
  int filterApplies = 0;  // outer iterations = filter applications
  bool converged = false;
  std::vector<cd> vector;
};

// Single lowest eigenpair by Chebyshev-Davidson with thick restart: basis grows
// by one filtered vector per outer step; Rayleigh-Ritz each step; restart to
// the `keep` best Ritz vectors at kMaxBasis. Constant start (the same start
// the covMG/cheb-LOBPCG rows use on this operator family).
ChebDavResult chebDavidsonSmallest(const GaugeLattice& lat, int deg, double ratio, double tol,
                                   int maxOuter) {
  const std::size_t N = static_cast<std::size_t>(lat.numNodes());
  const double b = 12.0 * lat.w;  // Gershgorin (2 x diagScale), as chebPrecondition
  const double a = b / std::max(1.0, ratio);
  const int keep = 3;
  std::vector<std::vector<cd>> V, W;  // basis and its images W = L V
  auto cdot = [&](const std::vector<cd>& u, const std::vector<cd>& v) {
    cd s(0, 0);
    for (std::size_t i = 0; i < N; ++i) s += std::conj(u[i]) * v[i];
    return s;
  };
  auto nrm = [&](const std::vector<cd>& v) { return std::sqrt(cdot(v, v).real()); };
  // Orthonormalize v against V (two MGS passes); returns false if it vanishes.
  auto addToBasis = [&](std::vector<cd> v) {
    for (int pass = 0; pass < 2; ++pass)
      for (const auto& q : V) {
        const cd p = cdot(q, v);
        for (std::size_t i = 0; i < N; ++i) v[i] -= p * q[i];
      }
    const double nv = nrm(v);
    if (nv < 1e-12) return false;
    for (cd& z : v) z /= nv;
    W.push_back(bochner::applyConnectionLaplacian(lat, v));
    V.push_back(std::move(v));
    return true;
  };
  std::vector<cd> x(N, cd(1, 0));
  {
    const double nx = nrm(x);
    for (cd& z : x) z /= nx;
  }
  addToBasis(x);
  ChebDavResult res;
  double theta = 0.0;
  for (int it = 1; it <= maxOuter; ++it) {
    const int mB = static_cast<int>(V.size());
    std::vector<cd> H(static_cast<std::size_t>(mB) * mB);
    for (int i = 0; i < mB; ++i)
      for (int j = 0; j < mB; ++j) H[i * mB + j] = cdot(V[i], W[j]);
    std::vector<cd> y;
    hermJacobiSmallest(mB, H, theta, y);
    std::vector<cd> xr(N, cd(0, 0)), wr(N, cd(0, 0));
    for (int i = 0; i < mB; ++i)
      for (std::size_t t = 0; t < N; ++t) {
        xr[t] += y[i] * V[i][t];
        wr[t] += y[i] * W[i][t];
      }
    std::vector<cd> r(N);
    for (std::size_t t = 0; t < N; ++t) r[t] = wr[t] - theta * xr[t];
    res.eigenvalue = theta;
    res.residual = nrm(r) / std::max(std::abs(theta), 1e-300);
    res.vector = xr;
    res.filterApplies = it - 1;
    if (res.residual < tol) {
      res.converged = true;
      return res;
    }
    // Thick restart: keep the `keep` lowest Ritz vectors of the current basis.
    if (mB >= kMaxBasis) {
      std::vector<std::vector<cd>> ritz;
      std::vector<cd> Hr(static_cast<std::size_t>(mB) * mB);
      for (int i = 0; i < mB; ++i)
        for (int j = 0; j < mB; ++j) Hr[i * mB + j] = cdot(V[i], W[j]);
      // Peel off the `keep` lowest pairs by repeated smallest-eig + deflation
      // (Jacobi returns one pair; deflate by shifting it up).
      for (int kkeep = 0; kkeep < keep; ++kkeep) {
        std::vector<cd> Hc = Hr;
        double lk;
        std::vector<cd> yk;
        hermJacobiSmallest(mB, Hc, lk, yk);
        std::vector<cd> rv(N, cd(0, 0));
        for (int i = 0; i < mB; ++i)
          for (std::size_t t = 0; t < N; ++t) rv[t] += yk[i] * V[i][t];
        ritz.push_back(std::move(rv));
        const double shift = 12.0 * lat.w * (kkeep + 1);
        for (int i = 0; i < mB; ++i)
          for (int j = 0; j < mB; ++j) Hr[i * mB + j] += shift * yk[i] * std::conj(yk[j]);
      }
      V.clear();
      W.clear();
      for (auto& rv : ritz) addToBasis(std::move(rv));
    }
    // Filter the current Ritz vector and append.
    std::vector<cd> t = chebFilterVec(lat, xr, deg, a, b);
    ++res.filterApplies;
    if (!addToBasis(std::move(t))) break;  // filtered vector already in span
  }
  return res;
}

}  // namespace

int main(int argc, char** argv) {
  SlepcInitialize(&argc, &argv, nullptr, nullptr);
  const int n = argc > 1 ? std::atoi(argv[1]) : 16;
  const int nPhi = argc > 2 ? std::atoi(argv[2]) : 4;
  // 2026-08-04 revision experiments: BOCHNER_EIG_TOL overrides the certified
  // eigen rtol for the tolerance sweep (revision-plan §6.5). Unset = 1e-7,
  // the published tables' setting, bit-identical behavior.
  const double tol = [] {
    const char* e = std::getenv("BOCHNER_EIG_TOL");
    return e ? std::atof(e) : 1e-7;
  }();

  const GaugeLattice lat = uniformFluxLattice(n, nPhi, 1.0 / n);
  const bochner::CooMatrix A = assemblePeriodic(lat);

  // Operator-equivalence guard: A (real 2N) == the matrix-free lattice.
  std::vector<cd> probe(lat.numNodes());
  for (std::size_t c = 0; c < probe.size(); ++c) probe[c] = cd(std::cos(0.7 * c), std::sin(0.3 * c));
  const std::vector<cd> yLat = bochner::applyConnectionLaplacian(lat, probe);
  const std::vector<double> yA = [&] {
    std::vector<double> xr = bochner::toInterleaved(probe), yr(xr.size(), 0.0);
    for (const auto& t : A.compressed()) yr[t.row] += t.value * xr[t.col];
    return yr;
  }();
  const std::vector<cd> yAc = bochner::toComplex(yA);
  double mismatch = 0.0;
  for (std::size_t c = 0; c < yLat.size(); ++c) mismatch = std::max(mismatch, std::abs(yLat[c] - yAc[c]));

  std::printf("\n#### uniform field, n=%d (%d DOFs), nPhi=%d, tol=%.0e ####\n", n, 2 * n * n * n, nPhi,
              tol);
  std::printf("   operator mismatch (assembled vs matrix-free) = %.2e\n\n", mismatch);

  // SLEPc Lanczos baseline.
  bochner::EigenPair L;
  const double msL = medianMs([&] { L = bochner::smallestEigenpairLanczos(A, tol); });

  // Our gauge-MG Rayleigh-quotient eigensolver (no SLEPc), from a cold constant start.
  bochner::GaugeEigenOptions eo;
  eo.tol = tol;
  bochner::GaugeEigenResult R;
  const double msR = medianMs([&] { R = bochner::smallestEigenpairGaugeMG(lat, nullptr, eo); });

  // A single gauge-MG linear solve, for the backward/inverse-iteration estimate.
  bochner::MgOptions mo;
  mo.tol = tol;
  std::vector<cd> b = bochner::applyConnectionLaplacian(lat, probe), x(lat.numNodes(), cd(0, 0));
  bochner::MgResult one;
  const double msSolve = medianMs([&] {
    std::fill(x.begin(), x.end(), cd(0, 0));  // every repeat solves from zero
    one = bochner::vcycleSolve(lat, b, x, mo);
  });

  std::printf("%-26s | %12s | %6s | %10s\n", "method", "eigenvalue", "iters", "wall ms");
  std::printf("--------------------------------------------------------------------\n");
  std::printf("%-26s | %12.6f | %6d | %10.1f\n", "SLEPc Lanczos", L.value, L.iterations, msL);
  std::printf("%-26s | %12.6f | %6d%s | %9.1f  res=%.1e\n", "covMG-LOBPCG (ours)", R.eigenvalue,
              R.iterations, R.converged ? "" : "!",
              msR, R.residual);
  std::printf("   |eigenvalue difference|    = %.2e\n", std::abs(L.value - R.eigenvalue));

  // 2026-08-15 survey round: Chebyshev-preconditioned LOBPCG baseline (identical
  // outer loop, preconditioner swapped to the zero-setup polynomial).
  // BOCHNER_CHEB_SWEEP="1" = default degree x ratio grid; or a comma-separated
  // deg:ratio list. Unset = published behavior, bit-identical.
  if (const char* chebEnv = std::getenv("BOCHNER_CHEB_SWEEP")) {
    std::vector<std::pair<int, double>> configs;
    const std::string s(chebEnv);
    if (s.find(':') != std::string::npos) {
      for (std::size_t p = 0; p < s.size();) {
        std::size_t q = s.find(',', p);
        if (q == std::string::npos) q = s.size();
        const std::string tok = s.substr(p, q - p);
        p = q + 1;
        const std::size_t colon = tok.find(':');
        if (colon != std::string::npos)
          configs.emplace_back(std::atoi(tok.substr(0, colon).c_str()),
                               std::atof(tok.substr(colon + 1).c_str()));
      }
    } else {
      for (int deg : {2, 4, 8, 16, 32, 64})
        for (double ratio : {10.0, 30.0, 100.0}) configs.emplace_back(deg, ratio);
    }
    std::printf("\ncheb-LOBPCG (same outer loop, polynomial preconditioner), tol %.0e:\n", tol);
    double bestMs = 1e300;
    int bestDeg = 0;
    double bestRatio = 0.0;
    for (const auto& cfg : configs) {
      bochner::GaugeEigenOptions ce;
      ce.tol = tol;
      ce.chebDegree = cfg.first;
      ce.chebRatio = cfg.second;
      bochner::GaugeEigenResult C;
      const double msC = medianMs([&] { C = bochner::smallestEigenpairGaugeMG(lat, nullptr, ce); });
      std::printf("  deg %2d ratio %5.0f | %12.6f | %4d%s | %9.1f ms  res=%.1e\n", cfg.first,
                  cfg.second, C.eigenvalue, C.iterations, C.converged ? "" : "!", msC, C.residual);
      if (C.converged && msC < bestMs) {
        bestMs = msC;
        bestDeg = cfg.first;
        bestRatio = cfg.second;
      }
    }
    if (bestDeg)
      std::printf("  best converged: deg %d ratio %.0f  %.1f ms  (covMG-LOBPCG: %.1f ms)\n",
                  bestDeg, bestRatio, bestMs, msR);
    else
      std::printf("  best converged: NONE within the iteration cap\n");
  }

  // 2026-08-15 survey round: Chebyshev-Davidson sweep, same conventions.
  // BOCHNER_CHEBDAV="1" = default grid; or a deg:ratio list. Unset = published
  // behavior, bit-identical.
  if (const char* cdEnv = std::getenv("BOCHNER_CHEBDAV")) {
    std::vector<std::pair<int, double>> configs;
    const std::string s(cdEnv);
    if (s.find(':') != std::string::npos) {
      for (std::size_t p = 0; p < s.size();) {
        std::size_t q = s.find(',', p);
        if (q == std::string::npos) q = s.size();
        const std::string tok = s.substr(p, q - p);
        p = q + 1;
        const std::size_t colon = tok.find(':');
        if (colon != std::string::npos)
          configs.emplace_back(std::atoi(tok.substr(0, colon).c_str()),
                               std::atof(tok.substr(colon + 1).c_str()));
      }
    } else {
      for (int deg : {8, 16, 32, 64})
        for (double ratio : {30.0, 100.0, 300.0, 1000.0}) configs.emplace_back(deg, ratio);
    }
    std::printf("\ncheb-Davidson (polynomial filter, Davidson outer, no preconditioner slot),"
                " tol %.0e:\n", tol);
    double bestMs = 1e300;
    int bestDeg = 0;
    double bestRatio = 0.0;
    for (const auto& cfg : configs) {
      ChebDavResult C;
      const double msC = medianMs(
          [&] { C = chebDavidsonSmallest(lat, cfg.first, cfg.second, tol, /*maxOuter=*/500); });
      std::printf("  deg %2d ratio %5.0f | %12.6f | %4d%s | %9.1f ms  res=%.1e\n", cfg.first,
                  cfg.second, C.eigenvalue, C.filterApplies, C.converged ? "" : "!", msC,
                  C.residual);
      if (C.converged && msC < bestMs) {
        bestMs = msC;
        bestDeg = cfg.first;
        bestRatio = cfg.second;
      }
    }
    if (bestDeg)
      std::printf("  best converged: deg %d ratio %.0f  %.1f ms  (covMG-LOBPCG: %.1f ms)\n",
                  bestDeg, bestRatio, bestMs, msR);
    else
      std::printf("  best converged: NONE within the outer cap\n");
  }

  // 2026-08-15 survey round: the hybrid -- covMG-LOBPCG with the V-cycle's
  // red-black GS swapped for a degree-k Chebyshev smoother (reduction-free;
  // MgOptions::chebSmootherDegree). BOCHNER_HYBRID = deg:ratio list ("1" =
  // default grid). Unset = published behavior, bit-identical.
  if (const char* hyEnv = std::getenv("BOCHNER_HYBRID")) {
    std::vector<std::pair<int, double>> configs;
    const std::string s(hyEnv);
    if (s.find(':') != std::string::npos) {
      for (std::size_t p = 0; p < s.size();) {
        std::size_t q = s.find(',', p);
        if (q == std::string::npos) q = s.size();
        const std::string tok = s.substr(p, q - p);
        p = q + 1;
        const std::size_t colon = tok.find(':');
        if (colon != std::string::npos)
          configs.emplace_back(std::atoi(tok.substr(0, colon).c_str()),
                               std::atof(tok.substr(colon + 1).c_str()));
      }
    } else {
      for (int deg : {2, 3, 4, 6, 8})
        for (double ratio : {4.0, 6.0, 15.0, 30.0}) configs.emplace_back(deg, ratio);
    }
    std::printf("\nhybrid covMG-LOBPCG (Chebyshev smoother inside the V-cycle), tol %.0e:\n", tol);
    double bestMs = 1e300;
    int bestDeg = 0;
    double bestRatio = 0.0;
    for (const auto& cfg : configs) {
      bochner::GaugeEigenOptions he;
      he.tol = tol;
      he.mg.chebSmootherDegree = cfg.first;
      he.mg.chebSmootherRatio = cfg.second;
      bochner::GaugeEigenResult Hh;
      const double msH = medianMs([&] { Hh = bochner::smallestEigenpairGaugeMG(lat, nullptr, he); });
      std::printf("  deg %2d ratio %5.0f | %12.6f | %4d%s | %9.1f ms  res=%.1e\n", cfg.first,
                  cfg.second, Hh.eigenvalue, Hh.iterations, Hh.converged ? "" : "!", msH,
                  Hh.residual);
      if (Hh.converged && msH < bestMs) {
        bestMs = msH;
        bestDeg = cfg.first;
        bestRatio = cfg.second;
      }
    }
    if (bestDeg)
      std::printf("  best converged: deg %d ratio %.0f  %.1f ms  (GS-smoothed covMG-LOBPCG: %.1f ms)\n",
                  bestDeg, bestRatio, bestMs, msR);
    else
      std::printf("  best converged: NONE\n");
  }

  // Eigenvector comparison as the DISTANCE BETWEEN THE TWO COMPLEX LINES that the
  // eigenvectors span (the ray C*psi), which is exactly the phase-invariant object
  // an eigenvector is. For unit vL, vR the distance between the lines span(vL) and
  // span(vR) is the CHORDAL projective distance sin(theta), theta the
  // principal angle = arccos|<vL,vR>| (the Fubini-Study geodesic distance
  // is theta itself; sin(theta) = ||P_L - P_R||_2 and agrees to 2nd order)
  //     d = sqrt(1 - |<vL,vR>|^2) = sin(theta) = || P_vL - P_vR ||_2
  // (theta = principal angle, P the rank-1 projectors); d = 0 iff the same line,
  // independent of each vector's global phase. We also report the pointwise |psi|
  // difference and each vector's own Rayleigh residual (both are true eigenvectors).
  std::vector<cd> vL = bochner::toComplex(L.vector), vR = R.vector;
  const auto unit = [](std::vector<cd>& v) {
    double s = 0.0;
    for (const cd& z : v) s += std::norm(z);
    s = std::sqrt(s);
    if (s > 0) for (cd& z : v) z /= s;
  };
  unit(vL);
  unit(vR);
  cd ov(0, 0);
  for (std::size_t c = 0; c < vL.size(); ++c) ov += std::conj(vL[c]) * vR[c];
  const double overlap = std::min(1.0, std::abs(ov));  // |<vL,vR>| in [0,1]
  const double lineDist = std::sqrt(std::max(0.0, 1.0 - overlap * overlap));  // sin(theta)
  const double angleDeg = std::acos(overlap) * 180.0 / M_PI;
  double maxMag = 0.0, magNum = 0.0, magDen = 0.0;
  for (std::size_t c = 0; c < vL.size(); ++c) {
    const double a = std::abs(vR[c]), b = std::abs(vL[c]);
    maxMag = std::max(maxMag, std::abs(a - b));
    magNum += (a - b) * (a - b);
    magDen += b * b;
  }
  const double relMag = magDen > 0 ? std::sqrt(magNum / magDen) : 0.0;
  const auto eigResidual = [&](const std::vector<cd>& v) {
    const std::vector<cd> Ev = bochner::applyConnectionLaplacian(lat, v);
    cd rq(0, 0);
    for (std::size_t c = 0; c < v.size(); ++c) rq += std::conj(v[c]) * Ev[c];
    double num = 0.0;
    for (std::size_t c = 0; c < v.size(); ++c) num += std::norm(Ev[c] - rq * v[c]);
    return std::sqrt(num) / std::abs(rq.real());
  };
  std::printf("\neigenvector = distance between the complex lines span(vL), span(vR):\n");
  std::printf("   line distance sqrt(1-|<vL,vR>|^2) = %.2e   (0 = same line, phase-invariant)\n",
              lineDist);
  std::printf("   |<vL,vR>| = %.6f  ->  principal angle = %.3f deg\n", overlap, angleDeg);
  std::printf("   pointwise |psi| relative diff     = %.2e  (max %.2e)\n", relMag, maxMag);
  std::printf("   eigen-residual   Lanczos = %.1e, covMG-LOBPCG = %.1e  (both true eigenvectors)\n",
              eigResidual(vL), eigResidual(vR));
  if (lineDist > 1e-3)
    std::printf("   NOTE: lambda_min is degenerate here (nPhi=%d Landau level); the two solvers\n"
                "         return different lines of the SAME eigenspace -- both residuals tiny.\n"
                "         Use nPhi=1 for a simple (non-degenerate) mode: the lines then coincide.\n",
                nPhi);

  std::printf("\nspeedup (Lanczos / ours)      = %.1fx\n", msR > 0 ? msL / msR : 0.0);
  std::printf("single gauge-MG linear solve  = %.2f ms (%d cycles)\n", msSolve, one.cycles);
  std::printf("=> est. backward iteration    ~ %.1f ms  (%.2f ms/solve x %d covMG-LOBPCG steps)\n",
              msSolve * R.iterations, msSolve, R.iterations);
  std::printf("   (covMG-LOBPCG folds the solve + Rayleigh step into each of its %d steps)\n", R.iterations);

  benchstat::printTimingSummary();
  SlepcFinalize();
  return 0;
}
