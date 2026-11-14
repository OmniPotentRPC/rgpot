#pragma once
// MIT License
// Copyright 2023--present rgpot developers
//
// One neighbour layer for the classical potentials: cell binning, the
// minimum image, an optional Verlet list, a streaming walk that does not
// store pairs, and a deterministic OpenMP split.

#include "rgpot/nlist/MinimumImage.hpp"

#include <algorithm>
#include <array>
#include <cstring>
#include <cmath>
#include <cstddef>
#include <cstdint>
#include <vector>

#if defined(_OPENMP)
#include <omp.h>
#endif

namespace rgpot::nlist {

/// How the minimum image is formed. Round is the orthorhombic truncation
/// used by the pair kernels. Half is one correction about the half-box,
/// used after coordinates have been wrapped into the cell. General is
/// MinimumImage, for a non-orthogonal cell or a periodic side shorter
/// than the search.
enum class Image : std::uint8_t { Round, Half, General };

#if defined(__GNUC__) || defined(__clang__)
#define RGPOT_IMAGE_COLD __attribute__((noinline, cold))
#elif defined(_MSC_VER)
#define RGPOT_IMAGE_COLD __declspec(noinline)
#else
#define RGPOT_IMAGE_COLD
#endif

namespace {

/// Non-finite coordinates and shifts outside a signed 64-bit integer.
/// Kept out of the pair loop: every finite value inside (-2^62, 2^62)
/// is handled by orthorhombicImageIndex.
RGPOT_IMAGE_COLD double orthorhombicImageIndexCold(double t) noexcept {
  if (!std::isfinite(t)) {
    return 0.0;
  }
  const double shifted = t + std::copysign(0.5, t);
  if (!std::isfinite(shifted) || shifted >= 9223372036854775808.0 ||
      shifted <= -9223372036854775808.0) {
    return 0.0;
  }
  return static_cast<double>(static_cast<long long>(shifted));
}

} // namespace

#undef RGPOT_IMAGE_COLD

/// Orthorhombic image index, `trunc(t + copysign(0.5, t))`.
///
/// A non-finite reduced coordinate, or a shift that does not fit in a
/// signed 64-bit integer, is 0. Every finite value inside (-2^62, 2^62)
/// takes that expression directly. The returned bits match the careful
/// path, which stays out of line.
inline double orthorhombicImageIndex(double t) noexcept {
  constexpr double kSpan = 0x1p62;
  if (t > -kSpan && t < kSpan) {
    return static_cast<double>(static_cast<long long>(t + std::copysign(0.5, t)));
  }
  return orthorhombicImageIndexCold(t);
}

/// Stored keeps a Verlet list of candidate pairs. Stream walks the cells
/// and stores nothing beyond the atoms and the bins. Auto stores when the
/// candidate index array fits in the memory the OS reports as available,
/// and streams otherwise.
enum class Mode : std::uint8_t { Auto, Stored, Stream };

struct Spec {
  double cutoff = 0;
  double skin = 0;
  std::array<bool, 3> periodic{{true, true, true}};
  Image image = Image::Round;
  Mode mode = Mode::Auto;
};

struct Range {
  std::int64_t begin = 0;
  std::int64_t end = 0;
};

/// Thread count from OMP_NUM_THREADS. Unset, empty, or a non-positive
/// value is one thread, so a call that does not ask for threads matches
/// the serial pair order.
[[nodiscard]] int threadsRequested();

/// Contiguous slice of `n` items for `thread` in `[0, nthreads)`. The
/// slices cover `n` without overlap, in thread order.
[[nodiscard]] Range partition(std::int64_t n, int thread, int nthreads);

// Pair chunks for a deterministic reduction. The count follows the atom
// count alone, so one thread and many threads add the same buffers.
// A cluster below 256 atoms uses eight chunks; 256 and above use 16.
[[nodiscard]] inline int fixedChunks(std::int64_t n) noexcept {
  if (n < 2) {
    return 1;
  }
  if (n < 256) {
    return n < 8 ? static_cast<int>(n) : 8;
  }
  return 16;
}

/// Bytes the process may still allocate, from MemAvailable. Zero when
/// that figure is not reported.
[[nodiscard]] std::uint64_t availableBytes();

/// True when every atom has moved by at most half of `skin` from
/// `reference`. Skin 0 is true only when the coordinates match. The same
/// test decides `Builder::update`'s reused flag.
[[nodiscard]] inline bool withinSkin(const double *reference, const double *current,
                                     std::size_t n, double skin) noexcept {
  const double limit2 = 0.25 * skin * skin;
  for (std::size_t a = 0; a < n; ++a) {
    const double dx = current[3 * a] - reference[3 * a];
    const double dy = current[3 * a + 1] - reference[3 * a + 1];
    const double dz = current[3 * a + 2] - reference[3 * a + 2];
    if (dx * dx + dy * dy + dz * dz > limit2) {
      return false;
    }
  }
  return true;
}

/// Candidate pairs around one configuration.
///
/// A stored list is reused while every atom has moved by at most half
/// the skin, and the cell, the count and the spec are unchanged. Skin 0
/// reuses the list only when the coordinates and the cell match. An
/// orthorhombic stored list keeps each pair's image index beside the
/// cell ids. The walk subtracts the box length times that index while
/// the coordinates still match the reference, and also after a move
/// inside the skin when that move cannot reach a half-box boundary.
/// A pair that can change image is rounded again. A sheared cell keeps
/// the rounded coefficients of MinimumImage the same way, and only when
/// that rounded image is the one the search returns. A move that can
/// reach another image, or a pair the search corrected, is folded again.
class Neighbours {
public:
  void update(const double *xyz, std::size_t n, const double *box9,
              const Spec &spec);

  [[nodiscard]] Mode mode() const noexcept { return mode_; }
  [[nodiscard]] bool streaming() const noexcept { return streaming_; }
  /// True when the last update kept the previous list. The displacement
  /// test is `withinSkin`, the same one `Builder::update` uses.
  [[nodiscard]] bool reused() const noexcept { return reused_; }
  [[nodiscard]] std::uint64_t builds() const noexcept { return builds_; }
  /// Stored pair index. A stream leaves this empty.
  [[nodiscard]] std::size_t slots() const noexcept { return nbr_.size(); }
  [[nodiscard]] const std::vector<std::int32_t> &offsets() const noexcept {
    return off_;
  }
  [[nodiscard]] const std::vector<std::int32_t> &neighbours() const noexcept {
    return nbr_;
  }
  /// Coordinates last passed to `update`, in the caller's layout.
  [[nodiscard]] const double *coordinates() const noexcept { return xyz_; }
  /// True when a stored pair vector is the raw coordinate difference.
  /// Only a free orthogonal cell qualifies. A periodic pair can cross the
  /// boundary even when the search sphere is shorter than half the box:
  /// atoms at 0.1 and L-0.1 are 0.2 apart under the minimum image and L-0.2
  /// apart as a raw difference. A sheared cell keeps the general fold.
  [[nodiscard]] bool rawSeparation() const noexcept {
    return !use_general_ && !periodic_[0] && !periodic_[1] && !periodic_[2];
  }

  /// Directed pairs for atoms in `[begin, end)`. `dx` is `r_i - r_j`
  /// after the selected image. `r2` is the squared length of that vector.
  /// Candidates lie inside the cutoff plus the skin; the caller drops the
  /// rest. In stored mode the partners of each atom are in increasing
  /// index order.
  template <typename Fn>
  void forDirected(std::int64_t begin, std::int64_t end, Fn &&fn) const {
    if (streaming_) {
      walkCells(begin, end, fn, false);
    } else {
      walkStored(begin, end, fn, false);
    }
  }

  /// The pairs of `forDirected` with `j > i` only. Geometry for `j <= i`
  /// is not computed. A serial two-pass potential uses this so each
  /// unordered pair is visited once per pass.
  template <typename Fn>
  void forHalf(std::int64_t begin, std::int64_t end, Fn &&fn) const {
    if (streaming_) {
      walkCells(begin, end, fn, true);
    } else {
      walkStored(begin, end, fn, true);
    }
  }

  /// MSVC rejects `#pragma omp` inside a lambda (C2760, token PRAGMA_OMP).
  /// The region lives in this method; the lambdas only supply the body.
  template <typename Body>
  void withTeam(int nthreads, Body &&body) const {
#if defined(_OPENMP)
#pragma omp parallel num_threads(nthreads)
#endif
    {
#if defined(_OPENMP)
      const int thread = omp_get_thread_num();
#else
      const int thread = 0;
#endif
      body(thread);
    }
  }

  /// One walk of the directed pairs, split by cell across `nthreads`.
  /// The bins are built once and shared. `fn(thread, i, j, dx, dy, dz, r2)`.
  /// A thread owns a contiguous run of cells, so concatenating the threads
  /// in order is the serial cell walk. The runs carry equal estimated
  /// work: an equal count of cells leaves the last, nearly empty, slab
  /// on one thread.
  template <typename Fn>
  void forCellTeam(bool half, int nthreads, Fn &&fn) const {
    if (nthreads < 1) {
      nthreads = 1;
    }
    const auto ncells = static_cast<std::size_t>(nx_) * static_cast<std::size_t>(ny_) *
                        static_cast<std::size_t>(nz_);
    std::vector<std::int64_t> cut(static_cast<std::size_t>(nthreads) + 1, 0);
    for (int t = 0; t <= nthreads; ++t) {
      cut[static_cast<std::size_t>(t)] =
          static_cast<std::int64_t>(ncells) * t / nthreads;
    }
    if (nthreads > 1 && ncells > 0 && cell_start_.size() == ncells + 1) {
      std::vector<std::uint64_t> prefix(ncells + 1, 0);
      for (std::size_t c = 0; c < ncells; ++c) {
        const int cell = static_cast<int>(c);
        const int iz = cell % nz_;
        const int iy = (cell / nz_) % ny_;
        const int ix = cell / (nz_ * ny_);
        const auto atoms =
            static_cast<std::uint64_t>(cell_start_[c + 1] - cell_start_[c]);
        std::uint64_t around = 0;
        if (atoms != 0) {
          int seen[27];
          int nseen = 0;
          for (int ox = -1; ox <= 1; ++ox) {
            for (int oy = -1; oy <= 1; ++oy) {
              for (int oz = -1; oz <= 1; ++oz) {
                const int id = cellId(ix + ox, iy + oy, iz + oz);
                if (id < 0) {
                  continue;
                }
                bool dup = false;
                for (int s = 0; s < nseen; ++s) {
                  if (seen[s] == id) {
                    dup = true;
                    break;
                  }
                }
                if (dup) {
                  continue;
                }
                seen[nseen++] = id;
                const auto nb = static_cast<std::size_t>(id);
                around += static_cast<std::uint64_t>(cell_start_[nb + 1] - cell_start_[nb]);
              }
            }
          }
        }
        const std::uint64_t weight = atoms == 0 ? 0 : atoms * (around == 0 ? 1 : around);
        prefix[c + 1] = prefix[c] + weight;
      }
      const auto total = prefix[ncells];
      if (total > 0) {
        std::size_t t = 1;
        for (std::size_t c = 0; c < ncells && t < static_cast<std::size_t>(nthreads); ++c) {
          while (t < static_cast<std::size_t>(nthreads) &&
                 prefix[c + 1] * static_cast<std::uint64_t>(nthreads) >=
                     total * static_cast<std::uint64_t>(t)) {
            cut[t] = static_cast<std::int64_t>(c + 1);
            ++t;
          }
        }
        while (t <= static_cast<std::size_t>(nthreads)) {
          cut[t] = static_cast<std::int64_t>(ncells);
          ++t;
        }
      }
    }
    if (!fastTiles([&](const auto &tile, const auto &neigh, const auto &nneigh,
                       const std::int32_t *head, std::size_t tiles,
                       bool cell_shift, double search2, double L0, double L1, double L2, double i0,
                       double i1, double i2, bool p0, bool p1, bool p2) {
          withTeam(nthreads, [&](int thread) {
            const auto begin = static_cast<std::size_t>(cut[static_cast<std::size_t>(thread)]);
            const auto end = static_cast<std::size_t>(cut[static_cast<std::size_t>(thread) + 1]);
            auto accept = [&](std::int32_t i, std::int32_t j, double dx, double dy, double dz,
                              double r2) { fn(thread, i, j, dx, dy, dz, r2); };
            if (head != nullptr) {
              visitTiles<true>(tile, neigh, nneigh, head, begin, end, 0, n_, half, cell_shift,
                               search2, L0, L1, L2, i0, i1, i2, p0, p1, p2, accept);
            } else {
              visitTiles<false>(tile, neigh, nneigh, head, begin, end, 0, n_, half, cell_shift,
                                search2, L0, L1, L2, i0, i1, i2, p0, p1, p2, accept);
            }
          });
          (void)tiles;
        })) {
      withTeam(nthreads, [&](int thread) {
        const auto range = partition(static_cast<std::int64_t>(n_), thread, nthreads);
        auto adapt = [&](std::int32_t i, std::int32_t j, double dx, double dy, double dz,
                         double r2) { fn(thread, i, j, dx, dy, dz, r2); };
        if (half) {
          forHalf(range.begin, range.end, adapt);
        } else {
          forDirected(range.begin, range.end, adapt);
        }
      });
    }
  }

  /// Half pairs whose lower atom lies in `[begin, end)`. The visit order is
  /// the cell walk of that atom range, independent of the thread count.
  template <typename Fn>
  void forHalfAtoms(std::int64_t begin, std::int64_t end, Fn &&fn) const {
    walkCells(begin, end, fn, true);
  }

  /// Neighbours of one atom from the bins already built. Does not allocate
  /// the tile stencil. A three-body stream uses this so the scratch is one
  /// atom, not every bond.
  template <typename Fn>
  void forAtom(std::int32_t i, Fn fn) const {
    // One atom, often from several threads. The cached stencil is built
    // once for a whole walk; this call does not touch it.
    walkCellsScattered(static_cast<std::int64_t>(i), static_cast<std::int64_t>(i) + 1, fn, false,
                       search_ * search_);
  }

private:
  struct SpecKey {
    double cutoff = 0;
    double skin = 0;
    Image image = Image::Round;
    Mode mode = Mode::Auto;
    std::array<bool, 3> periodic{{true, true, true}};
    bool operator==(const SpecKey &o) const {
      return cutoff == o.cutoff && skin == o.skin && image == o.image &&
             mode == o.mode && periodic == o.periodic;
    }
  };

  void buildCells(const double *xyz, std::size_t n);
  void buildStored(const double *xyz, std::size_t n);
  [[nodiscard]] std::uint64_t candidateBound() const;
  [[nodiscard]] bool reusable(const double *xyz, std::size_t n,
                              const double *box9, const Spec &spec) const;
  void fold(double &dx, double &dy, double &dz) const;

  // Out of line so the orthorhombic pair loops keep the code they had
  // before the general-cell path existed.
  template <typename Fn>
#if defined(__GNUC__) || defined(__clang__)
  __attribute__((noinline))
#endif
  void walkGeneral(std::int64_t begin, std::int64_t end, Fn &fn, bool half,
                   const std::int32_t *shift, const unsigned char *unstable) const {
    const double *xyz = xyz_;
    const std::int32_t *nbr = nbr_.data();
    auto emit = [&](std::int32_t i, std::int32_t j, double dx, double dy, double dz) {
      const double r2 = dx * dx + dy * dy + dz * dz;
      fn(i, j, dx, dy, dz, r2);
    };
    auto first = [&](std::int64_t i, std::int32_t lo, std::int32_t hi) {
      const std::int32_t *row = nbr + lo;
      const std::int32_t *stop = nbr + hi;
      if (!half) {
        return row;
      }
      return std::upper_bound(row, stop, static_cast<std::int32_t>(i));
    };
    for (std::int64_t i = begin; i < end; ++i) {
      const auto a = static_cast<std::size_t>(i);
      const auto lo = off_[a];
      const auto hi = off_[a + 1];
      const std::int32_t *row = first(i, lo, hi);
      const auto p0 = static_cast<std::size_t>(row - nbr);
      const std::int32_t *sh = shift + 3 * p0;
      const auto ui = a * 3;
      const double xi = xyz[ui];
      const double yi = xyz[ui + 1];
      const double zi = xyz[ui + 2];
      for (std::size_t p = p0; p < static_cast<std::size_t>(hi); ++p, sh += 3) {
        const auto j = nbr[p];
        double dx = 0;
        double dy = 0;
        double dz = 0;
        if (unstable != nullptr && unstable[p] != 0) {
          foldPair(static_cast<std::int32_t>(i), j, dx, dy, dz);
        } else {
          const auto uj = static_cast<std::size_t>(j) * 3;
          dx = xi - xyz[uj];
          dy = yi - xyz[uj + 1];
          dz = zi - xyz[uj + 2];
          general_.subtractRounded(sh[0], sh[1], sh[2], dx, dy, dz);
        }
        emit(static_cast<std::int32_t>(i), j, dx, dy, dz);
      }
    }
  }

  template <typename Fn>
  void walkStored(std::int64_t begin, std::int64_t end, Fn &fn, bool half) const {
    const double *xyz = xyz_;
    const std::int32_t *nbr = nbr_.data();
    if (nbr == nullptr) {
      return;
    }
    bool tiny = false;
    bool general = false;
    const unsigned char *unstable = nullptr;
    const std::int32_t *shift = nullptr;
    if ((image_ == Image::Round && !use_general_) || use_general_) {
      shift = roundShifts(tiny, unstable, general);
    }
    auto emit = [&](std::int32_t i, std::int32_t j, double dx, double dy, double dz) {
      const double r2 = dx * dx + dy * dy + dz * dz;
      fn(i, j, dx, dy, dz, r2);
    };
    // Partners of one atom are sorted. The half list is the suffix j > i.
    auto first = [&](std::int64_t i, std::int32_t lo, std::int32_t hi) {
      const std::int32_t *row = nbr + lo;
      const std::int32_t *stop = nbr + hi;
      if (!half) {
        return row;
      }
      return std::upper_bound(row, stop, static_cast<std::int32_t>(i));
    };
    if (shift != nullptr && general) {
      walkGeneral(begin, end, fn, half, shift, unstable);
      return;
    }
    if (shift != nullptr && unstable != nullptr) {
      const double L0 = len_[0];
      const double L1 = len_[1];
      const double L2 = len_[2];
      const double c0[3] = {-L0, 0.0, L0};
      const double c1[3] = {-L1, 0.0, L1};
      const double c2[3] = {-L2, 0.0, L2};
      const bool p0p = periodic_[0];
      const bool p1p = periodic_[1];
      const bool p2p = periodic_[2];
      const bool lut = tiny && p0p && p1p && p2p;
      for (std::int64_t i = begin; i < end; ++i) {
        const auto a = static_cast<std::size_t>(i);
        const auto lo = off_[a];
        const auto hi = off_[a + 1];
        const std::int32_t *row = first(i, lo, hi);
        const auto p0 = static_cast<std::size_t>(row - nbr);
        const std::int32_t *sh = shift + 3 * p0;
        const auto ui = a * 3;
        const double xi = xyz[ui];
        const double yi = xyz[ui + 1];
        const double zi = xyz[ui + 2];
        for (std::size_t p = p0; p < static_cast<std::size_t>(hi); ++p, sh += 3) {
          const auto j = nbr[p];
          double dx = 0;
          double dy = 0;
          double dz = 0;
          if (unstable[p] != 0) {
            foldPair(static_cast<std::int32_t>(i), j, dx, dy, dz);
          } else {
            const auto uj = static_cast<std::size_t>(j) * 3;
            dx = xi - xyz[uj];
            dy = yi - xyz[uj + 1];
            dz = zi - xyz[uj + 2];
            if (lut) {
              dx -= c0[static_cast<std::size_t>(sh[0] + 1)];
              dy -= c1[static_cast<std::size_t>(sh[1] + 1)];
              dz -= c2[static_cast<std::size_t>(sh[2] + 1)];
            } else {
              if (p0p) {
                dx -= L0 * static_cast<double>(sh[0]);
              }
              if (p1p) {
                dy -= L1 * static_cast<double>(sh[1]);
              }
              if (p2p) {
                dz -= L2 * static_cast<double>(sh[2]);
              }
            }
          }
          emit(static_cast<std::int32_t>(i), j, dx, dy, dz);
        }
      }
      return;
    }
    if (shift != nullptr && periodic_[0] && periodic_[1] && periodic_[2]) {
      const double L0 = len_[0];
      const double L1 = len_[1];
      const double L2 = len_[2];
      // {-1, 0, 1} is every image of an in-box pair. The table is the
      // product the rounding used to form, so the subtraction matches it.
      const double c0[3] = {-L0, 0.0, L0};
      const double c1[3] = {-L1, 0.0, L1};
      const double c2[3] = {-L2, 0.0, L2};
      for (std::int64_t i = begin; i < end; ++i) {
        const auto a = static_cast<std::size_t>(i);
        const auto lo = off_[a];
        const auto hi = off_[a + 1];
        const std::int32_t *row = first(i, lo, hi);
        const auto p0 = static_cast<std::size_t>(row - nbr);
        const std::int32_t *sh = shift + 3 * p0;
        const auto ui = a * 3;
        const double xi = xyz[ui];
        const double yi = xyz[ui + 1];
        const double zi = xyz[ui + 2];
        if (tiny) {
          for (std::size_t p = p0; p < static_cast<std::size_t>(hi); ++p, sh += 3) {
            const auto j = nbr[p];
            const auto uj = static_cast<std::size_t>(j) * 3;
            double dx = xi - xyz[uj];
            double dy = yi - xyz[uj + 1];
            double dz = zi - xyz[uj + 2];
            dx -= c0[static_cast<std::size_t>(sh[0] + 1)];
            dy -= c1[static_cast<std::size_t>(sh[1] + 1)];
            dz -= c2[static_cast<std::size_t>(sh[2] + 1)];
            emit(static_cast<std::int32_t>(i), j, dx, dy, dz);
          }
        } else {
          for (std::size_t p = p0; p < static_cast<std::size_t>(hi); ++p, sh += 3) {
            const auto j = nbr[p];
            const auto uj = static_cast<std::size_t>(j) * 3;
            double dx = xi - xyz[uj];
            double dy = yi - xyz[uj + 1];
            double dz = zi - xyz[uj + 2];
            dx -= L0 * static_cast<double>(sh[0]);
            dy -= L1 * static_cast<double>(sh[1]);
            dz -= L2 * static_cast<double>(sh[2]);
            emit(static_cast<std::int32_t>(i), j, dx, dy, dz);
          }
        }
      }
      return;
    }
    if (shift != nullptr) {
      const double L0 = len_[0];
      const double L1 = len_[1];
      const double L2 = len_[2];
      const bool p0p = periodic_[0];
      const bool p1p = periodic_[1];
      const bool p2p = periodic_[2];
      for (std::int64_t i = begin; i < end; ++i) {
        const auto a = static_cast<std::size_t>(i);
        const auto lo = off_[a];
        const auto hi = off_[a + 1];
        const std::int32_t *row = first(i, lo, hi);
        const auto p0 = static_cast<std::size_t>(row - nbr);
        const std::int32_t *sh = shift + 3 * p0;
        const auto ui = a * 3;
        const double xi = xyz[ui];
        const double yi = xyz[ui + 1];
        const double zi = xyz[ui + 2];
        for (std::size_t p = p0; p < static_cast<std::size_t>(hi); ++p, sh += 3) {
          const auto j = nbr[p];
          const auto uj = static_cast<std::size_t>(j) * 3;
          double dx = xi - xyz[uj];
          double dy = yi - xyz[uj + 1];
          double dz = zi - xyz[uj + 2];
          if (p0p) {
            dx -= L0 * static_cast<double>(sh[0]);
          }
          if (p1p) {
            dy -= L1 * static_cast<double>(sh[1]);
          }
          if (p2p) {
            dz -= L2 * static_cast<double>(sh[2]);
          }
          emit(static_cast<std::int32_t>(i), j, dx, dy, dz);
        }
      }
      return;
    }
    for (std::int64_t i = begin; i < end; ++i) {
      const auto a = static_cast<std::size_t>(i);
      const auto lo = off_[a];
      const auto hi = off_[a + 1];
      const std::int32_t *row = first(i, lo, hi);
      const std::int32_t *stop = nbr + hi;
      for (const std::int32_t *it = row; it != stop; ++it) {
        const auto j = *it;
        double dx = 0;
        double dy = 0;
        double dz = 0;
        foldPair(static_cast<std::int32_t>(i), j, dx, dy, dz);
        emit(static_cast<std::int32_t>(i), j, dx, dy, dz);
      }
    }
  }

  /// True when one materialised 27-slot stencil per cell is no larger than
  /// the pair index it stands in for. A short cutoff makes one bin per atom
  /// and that stencil no longer fits; the same cache then keeps only the
  /// cells that hold a pair inside the search.
  [[nodiscard]] bool tileStencilFits() const {
    const auto ncells = static_cast<std::size_t>(nx_) * static_cast<std::size_t>(ny_) *
                        static_cast<std::size_t>(nz_);
    const double per_cell =
        static_cast<double>(n_) / static_cast<double>(ncells > 0 ? ncells : 1);
    const double list_bytes = per_cell * 27.0 * static_cast<double>(n_) * 4.0;
    const double tile_bytes =
        static_cast<double>(ncells) * 27.0 * 32.0 + static_cast<double>(n_) * 32.0;
    return !(tile_bytes > list_bytes);
  }

  template <typename Loop>
  bool fastTiles(Loop &&loop) const {
    // Half is the same orthorhombic minimum image once coordinates sit in
    // the cell. A sheared box stays on the scattered walk.
    if (use_general_ || (image_ != Image::Round && image_ != Image::Half) || n_ < 2) {
      return false;
    }
    // One stencil. A 27-slot entry per cell is reused while the coordinates
    // are unchanged. When that array is larger than the pair index, the same
    // cache keeps only the cells that hold a pair inside the search. A stored
    // list does not take the compact form; it walks the index.
    const bool dense = tileStencilFits();
    if (!dense && !streaming_) {
      return false;
    }
    const auto ncells = static_cast<std::size_t>(nx_) * static_cast<std::size_t>(ny_) *
                        static_cast<std::size_t>(nz_);
    const bool cell_shift = (!periodic_[0] || nx_ >= 5) && (!periodic_[1] || ny_ >= 5) &&
                            (!periodic_[2] || nz_ >= 5);
    struct Nbor {
      int id;
      double sx;
      double sy;
      double sz;
    };
    struct Tile {
      double x;
      double y;
      double z;
      std::int32_t id;
    };
    // The stencil depends only on the coordinates. A warm call with
    // the same positions reuses it.
    struct Cache {
      const Neighbours *owner = nullptr;
      int nx = 0;
      int ny = 0;
      int nz = 0;
      double search = 0;
      std::vector<double> xyz;
      std::vector<Nbor> neigh;
      std::vector<int> nneigh;
      std::vector<Tile> tile;
      bool compact = false;
      std::vector<std::int32_t> head;
    };
    // One stencil per thread. The cache is process-wide otherwise, and two
    // evaluations then rewrite the same vectors.
    thread_local Cache cache;
    // The stored evaluation rebuilds its stencil. A stream keeps one and
    // reuses it when the coordinates are unchanged.
    const bool same_grid = cache.owner == this && cache.nx == nx_ && cache.ny == ny_ &&
                           cache.nz == nz_ && cache.search == search_ && cache.compact == !dense;
    // update() already compared the coordinates when it reused the bins.
    const bool reuse =
        streaming_ && same_grid &&
        (reused_ || (cache.xyz.size() == n_ * 3 &&
                     std::memcmp(cache.xyz.data(), xyz_, n_ * 3 * sizeof(double)) == 0));
    if (!reuse) {
    if (!dense) {
      cache.compact = true;
      cache.neigh.clear();
      cache.nneigh.assign(ncells, 0);
      cache.head.assign(ncells + 1, 0);
      cache.tile.clear();
      const double search2 = search_ * search_;
      const auto cap = ncells * 2;
      bool overflow = ncells < 1 || ncells > static_cast<std::size_t>(0x7fffffff) / 2;
      for (std::size_t c = 0; c < ncells && !overflow; ++c) {
        cache.head[c] = static_cast<std::int32_t>(cache.neigh.size());
        if (cell_start_[c] == cell_start_[c + 1]) {
          continue;
        }
        const int cell = static_cast<int>(c);
        const int iz = cell % nz_;
        const int iy = (cell / nz_) % ny_;
        const int ix = cell / (nz_ * ny_);
        int seen[27];
        int nseen = 0;
        for (int ox = -1; ox <= 1 && !overflow; ++ox) {
          for (int oy = -1; oy <= 1 && !overflow; ++oy) {
            for (int oz = -1; oz <= 1; ++oz) {
              int jx = ix + ox;
              int jy = iy + oy;
              int jz = iz + oz;
              int sa = 0;
              int sb = 0;
              int sc = 0;
              if (periodic_[0]) {
                if (jx < 0) {
                  jx += nx_;
                  sa = -1;
                } else if (jx >= nx_) {
                  jx -= nx_;
                  sa = 1;
                }
              } else if (jx < 0 || jx >= nx_) {
                continue;
              }
              if (periodic_[1]) {
                if (jy < 0) {
                  jy += ny_;
                  sb = -1;
                } else if (jy >= ny_) {
                  jy -= ny_;
                  sb = 1;
                }
              } else if (jy < 0 || jy >= ny_) {
                continue;
              }
              if (periodic_[2]) {
                if (jz < 0) {
                  jz += nz_;
                  sc = -1;
                } else if (jz >= nz_) {
                  jz -= nz_;
                  sc = 1;
                }
              } else if (jz < 0 || jz >= nz_) {
                continue;
              }
              const int id = (jx * ny_ + jy) * nz_ + jz;
              bool dup = false;
              for (int s = 0; s < nseen; ++s) {
                if (seen[s] == id) {
                  dup = true;
                  break;
                }
              }
              if (dup) {
                continue;
              }
              seen[nseen++] = id;
              const auto nb = static_cast<std::size_t>(id);
              if (cell_start_[nb] == cell_start_[nb + 1]) {
                continue;
              }
              bool hit = false;
              for (std::int32_t q = cell_start_[c]; q < cell_start_[c + 1] && !hit; ++q) {
                const auto i = cell_atoms_[static_cast<std::size_t>(q)];
                for (std::int32_t r = cell_start_[nb]; r < cell_start_[nb + 1]; ++r) {
                  const auto j = cell_atoms_[static_cast<std::size_t>(r)];
                  if (j == i) {
                    continue;
                  }
                  double dx = 0;
                  double dy = 0;
                  double dz = 0;
                  foldPair(i, j, dx, dy, dz);
                  if (dx * dx + dy * dy + dz * dz <= search2) {
                    hit = true;
                    break;
                  }
                }
              }
              if (!hit) {
                continue;
              }
              if (cache.neigh.size() >= cap) {
                overflow = true;
                break;
              }
              cache.neigh.push_back(Nbor{id, sa * len_[0], sb * len_[1], sc * len_[2]});
              ++cache.nneigh[c];
            }
          }
        }
      }
      if (!overflow) {
        cache.head[ncells] = static_cast<std::int32_t>(cache.neigh.size());
        const double per_cell = static_cast<double>(n_) / static_cast<double>(ncells);
        const double list_bytes = per_cell * 27.0 * static_cast<double>(n_) * 4.0;
        const double csr_bytes =
            static_cast<double>(cache.neigh.size()) * 32.0 +
            static_cast<double>(ncells + 1) * static_cast<double>(sizeof(std::int32_t));
        if (csr_bytes > list_bytes) {
          overflow = true;
        }
      }
      if (overflow) {
        cache.owner = nullptr;
        cache.neigh.clear();
        cache.head.clear();
        cache.nneigh.clear();
        return false;
      }
      if (!cache.neigh.empty()) {
        cache.tile.resize(n_);
        for (std::size_t q = 0; q < n_; ++q) {
          const auto j = cell_atoms_[q];
          const auto u = static_cast<std::size_t>(j) * 3;
          cache.tile[q] = Tile{xyz_[u], xyz_[u + 1], xyz_[u + 2], j};
        }
      }
    } else {
    cache.compact = false;
    cache.head.clear();
    auto &neigh = cache.neigh;
    auto &nneigh = cache.nneigh;
    neigh.assign(ncells * 27, Nbor{});
    nneigh.assign(ncells, 0);
    for (std::size_t c = 0; c < ncells; ++c) {
      const int cell = static_cast<int>(c);
      int iz = cell % nz_;
      int iy = (cell / nz_) % ny_;
      int ix = cell / (nz_ * ny_);
      int seen[27];
      int nseen = 0;
      for (int ox = -1; ox <= 1; ++ox) {
        for (int oy = -1; oy <= 1; ++oy) {
          for (int oz = -1; oz <= 1; ++oz) {
            int jx = ix + ox;
            int jy = iy + oy;
            int jz = iz + oz;
            int sa = 0;
            int sb = 0;
            int sc = 0;
            if (periodic_[0]) {
              if (jx < 0) {
                jx += nx_;
                sa = -1;
              } else if (jx >= nx_) {
                jx -= nx_;
                sa = 1;
              }
            } else if (jx < 0 || jx >= nx_) {
              continue;
            }
            if (periodic_[1]) {
              if (jy < 0) {
                jy += ny_;
                sb = -1;
              } else if (jy >= ny_) {
                jy -= ny_;
                sb = 1;
              }
            } else if (jy < 0 || jy >= ny_) {
              continue;
            }
            if (periodic_[2]) {
              if (jz < 0) {
                jz += nz_;
                sc = -1;
              } else if (jz >= nz_) {
                jz -= nz_;
                sc = 1;
              }
            } else if (jz < 0 || jz >= nz_) {
              continue;
            }
            const int id = (jx * ny_ + jy) * nz_ + jz;
            bool dup = false;
            for (int s = 0; s < nseen; ++s) {
              if (seen[s] == id) {
                dup = true;
                break;
              }
            }
            if (dup) {
              continue;
            }
            seen[nseen] = id;
            neigh[c * 27 + static_cast<std::size_t>(nseen)] =
                Nbor{id, sa * len_[0], sb * len_[1], sc * len_[2]};
            ++nseen;
          }
        }
      }
      nneigh[c] = nseen;
    }
    auto &tile = cache.tile;
    tile.resize(n_);
    for (std::size_t q = 0; q < n_; ++q) {
      const auto j = cell_atoms_[q];
      const auto u = static_cast<std::size_t>(j) * 3;
      tile[q] = Tile{xyz_[u], xyz_[u + 1], xyz_[u + 2], j};
    }
    }
    if (streaming_) {
      cache.owner = this;
      cache.nx = nx_;
      cache.ny = ny_;
      cache.nz = nz_;
      cache.search = search_;
      cache.xyz.assign(xyz_, xyz_ + n_ * 3);
    }
    }
    if (cache.compact && cache.neigh.empty()) {
      return true;
    }
    loop(cache.tile, cache.neigh, cache.nneigh, cache.compact ? cache.head.data() : nullptr, ncells,
         cell_shift, search_ * search_, len_[0], len_[1], len_[2], inv_[0], inv_[1], inv_[2],
         periodic_[0], periodic_[1], periodic_[2]);
    return true;
  }

  template <bool Compact, typename Tile, typename Nbor, typename Fn>
  void visitTiles(const std::vector<Tile> &tile, const std::vector<Nbor> &neigh,
                  const std::vector<int> &nneigh, const std::int32_t *head, std::size_t c0,
                  std::size_t c1,
                  std::int64_t atom0, std::size_t atom1, bool half, bool cell_shift,
                  double search2, double L0, double L1, double L2, double i0, double i1,
                  double i2, bool p0, bool p1, bool p2, Fn &&fn) const {
    auto round_axis = [](double delta, double inv, double length, bool periodic, int &shift) {
      if (!periodic) {
        shift = 0;
        return delta;
      }
      const double t = delta * inv;
      if (!(t > -1.0e15 && t < 1.0e15)) {
        shift = 0;
        return delta;
      }
      const double shifted = t + std::copysign(0.5, t);
      const auto image = static_cast<long long>(shifted);
      shift = static_cast<int>(image);
      return delta - length * static_cast<double>(image);
    };
    for (std::size_t c = c0; c < c1; ++c) {
      const auto a0 = cell_start_[c];
      const auto a1 = cell_start_[c + 1];
      if (a0 == a1) {
        continue;
      }
      const int nn = nneigh[c];
      if constexpr (Compact) {
        if (nn == 0) {
          continue;
        }
      }
      const Nbor *nb;
      if constexpr (Compact) {
        nb = neigh.data() + static_cast<std::size_t>(head[c]);
      } else {
        nb = neigh.data() + c * 27;
      }
      for (std::int32_t q = a0; q < a1; ++q) {
        const Tile &a = tile[static_cast<std::size_t>(q)];
        if (a.id < atom0 || static_cast<std::size_t>(a.id) >= atom1) {
          continue;
        }
        for (int k = 0; k < nn; ++k) {
          const Nbor &src = nb[k];
          const auto b0 = static_cast<std::size_t>(cell_start_[static_cast<std::size_t>(src.id)]);
          const auto b1 =
              static_cast<std::size_t>(cell_start_[static_cast<std::size_t>(src.id) + 1]);
          // Atom ids increase inside a cell, so a half pair starts at the
          // first neighbour with a larger id and does not test the rest.
          const std::size_t rstart = [&]() {
            if (!half) {
              return b0;
            }
            const auto begin = tile.begin() + static_cast<std::ptrdiff_t>(b0);
            const auto end = tile.begin() + static_cast<std::ptrdiff_t>(b1);
            const auto found = std::lower_bound(
                begin, end, a.id, [](const Tile &atom, std::int32_t id) { return atom.id < id; });
            auto next = found;
            if (next != end && next->id == a.id) {
              ++next;
            }
            return static_cast<std::size_t>(next - tile.begin());
          }();
          for (std::size_t r = rstart; r < b1; ++r) {
            const Tile &b = tile[r];
            if (!half && b.id == a.id) {
              continue;
            }
            double dx;
            double dy;
            double dz;
            if (cell_shift) {
              dx = (a.x - b.x) - src.sx;
              dy = (a.y - b.y) - src.sy;
              dz = (a.z - b.z) - src.sz;
            } else {
              int sa = 0;
              int sb = 0;
              int sc = 0;
              dx = round_axis(a.x - b.x, i0, L0, p0, sa);
              dy = round_axis(a.y - b.y, i1, L1, p1, sb);
              dz = round_axis(a.z - b.z, i2, L2, p2, sc);
            }
            const double r2 = dx * dx + dy * dy + dz * dz;
            if (r2 <= search2) {
              fn(a.id, b.id, dx, dy, dz, r2);
            }
          }
        }
      }
    }
  }

  template <typename Fn>
  void walkCells(std::int64_t begin, std::int64_t end, Fn &fn, bool half) const {
    const double search2 = search_ * search_;
    if (!fastTiles([&](const auto &tile, const auto &neigh, const auto &nneigh,
                       const std::int32_t *head, std::size_t ncells, bool cell_shift,
                       double search2_fast, double L0, double L1, double L2, double i0, double i1,
                       double i2, bool p0, bool p1, bool p2) {
          if (head != nullptr) {
            visitTiles<true>(tile, neigh, nneigh, head, 0, ncells, begin,
                             static_cast<std::size_t>(end), half, cell_shift, search2_fast, L0, L1,
                             L2, i0, i1, i2, p0, p1, p2, fn);
          } else {
            visitTiles<false>(tile, neigh, nneigh, head, 0, ncells, begin,
                              static_cast<std::size_t>(end), half, cell_shift, search2_fast, L0, L1,
                              L2, i0, i1, i2, p0, p1, p2, fn);
          }
        })) {
      walkCellsScattered(begin, end, fn, half, search2);
    }
  }

  template <typename Fn>
  void walkCellsScattered(std::int64_t begin, std::int64_t end, Fn &fn, bool half,
                          double search2) const {
    const SearchBound bound = searchBound();
    for (std::int64_t i = begin; i < end; ++i) {
      const auto a = static_cast<std::size_t>(i);
      const int cell = cell_of_[a];
      int iz = cell % nz_;
      int iy = (cell / nz_) % ny_;
      int ix = cell / (nz_ * ny_);
      int seen[27];
      int nseen = 0;
      for (int ox = -1; ox <= 1; ++ox) {
        for (int oy = -1; oy <= 1; ++oy) {
          for (int oz = -1; oz <= 1; ++oz) {
            const int id = cellId(ix + ox, iy + oy, iz + oz);
            if (id < 0) {
              continue;
            }
            bool dup = false;
            for (int s = 0; s < nseen; ++s) {
              if (seen[s] == id) {
                dup = true;
                break;
              }
            }
            if (dup) {
              continue;
            }
            seen[nseen++] = id;
            const auto c = static_cast<std::size_t>(id);
            const auto a0 = cell_start_[c];
            const auto a1 = cell_start_[c + 1];
            for (std::int32_t q = a0; q < a1; ++q) {
              const auto j = cell_atoms_[static_cast<std::size_t>(q)];
              if (j == static_cast<std::int32_t>(i)) {
                continue;
              }
              if (half && !(j > static_cast<std::int32_t>(i))) {
                continue;
              }
              const auto uj = static_cast<std::size_t>(j) * 3;
              const auto ui = a * 3;
              const double dx0 = xyz_[ui] - xyz_[uj];
              const double dy0 = xyz_[ui + 1] - xyz_[uj + 1];
              const double dz0 = xyz_[ui + 2] - xyz_[uj + 2];
              // Same bound as the stored rebuild: a fractional coordinate
              // past the search cannot fall inside the cutoff ball.
              if (outsideSearch(bound, dx0, dy0, dz0)) {
                continue;
              }
              double dx = 0;
              double dy = 0;
              double dz = 0;
              foldPair(static_cast<std::int32_t>(i), j, dx, dy, dz);
              const double r2 = dx * dx + dy * dy + dz * dz;
              if (r2 <= search2) {
                fn(static_cast<std::int32_t>(i), j, dx, dy, dz, r2);
              }
            }
          }
        }
      }
    }
  }

  void foldPair(std::int32_t i, std::int32_t j, double &dx, double &dy,
                double &dz) const;
  [[nodiscard]] int cellId(int ix, int iy, int iz) const;
  // Image indices live past the per-atom cell ids. The class does not
  // grow a member for them. `tiny` is true when every index is -1, 0 or 1.
  // `unstable` is one byte per pair when a skin move can change that pair's
  // index; a null pointer means every stored index still matches rounding.
  void installRoundShifts(const std::int32_t *shift, std::size_t npairs, bool tiny,
                          bool all_stable, bool general, const std::uint8_t *unstable);
  void noteShiftFresh(bool fresh) noexcept;
  // `general` selects MinimumImage coefficients. Those are folded again,
  // even on the reference coordinates, when the pair was not coded.
  [[nodiscard]] const std::int32_t *roundShifts(bool &tiny, const unsigned char *&unstable,
                                                bool &general) const noexcept;

  // Fractional columns of H^{-1}. `on` is false for an orthogonal cell
  // and for a singular cell, which keeps the old fold.
  struct SearchBound {
    double inv[9]{};
    double dual[3]{};
    bool on = false;
  };
  [[nodiscard]] SearchBound searchBound() const;
  // |v| >= |f_k| / ||column of H^{-1}||. True only when that lower bound
  // already exceeds the search.
  [[nodiscard]] bool outsideSearch(const SearchBound &bound, double dx, double dy,
                                   double dz) const noexcept;

  std::vector<std::int32_t> off_;
  std::vector<std::int32_t> nbr_;
  std::vector<std::int32_t> cell_of_;
  std::vector<std::int32_t> cell_start_;
  std::vector<std::int32_t> cell_atoms_;
  std::vector<double> ref_;
  double box_[9]{};
  double len_[3]{};
  double inv_[3]{};
  bool periodic_[3]{};
  int nx_ = 1;
  int ny_ = 1;
  int nz_ = 1;
  double search_ = 0;
  Image image_ = Image::Round;
  Mode mode_ = Mode::Auto;
  SpecKey key_{};
  MinimumImage general_;
  bool use_general_ = false;
  bool streaming_ = true;
  bool built_ = false;
  bool reused_ = false;
  std::size_t n_ = 0;
  std::uint64_t builds_ = 0;
  const double *xyz_ = nullptr;
};

inline bool Neighbours::outsideSearch(const SearchBound &bound, double dx, double dy,
                                      double dz) const noexcept {
  if (!bound.on) {
    return false;
  }
  const double r[3] = {dx, dy, dz};
  for (int k = 0; k < 3; ++k) {
    double f = r[0] * bound.inv[k] + r[1] * bound.inv[3 + k] + r[2] * bound.inv[6 + k];
    if (periodic_[k]) {
      f -= std::round(f);
    }
    if (std::abs(f) > search_ * bound.dual[k] * (1.0 + 1e-5)) {
      return true;
    }
  }
  return false;
}

inline void Neighbours::fold(double &dx, double &dy, double &dz) const {
  if (use_general_) {
    general_.fold(dx, dy, dz);
    return;
  }
  if (image_ == Image::Half) {
    const double h0 = 0.5 * len_[0];
    const double h1 = 0.5 * len_[1];
    const double h2 = 0.5 * len_[2];
    if (periodic_[0]) {
      if (dx > h0) {
        dx -= len_[0];
      } else if (dx < -h0) {
        dx += len_[0];
      }
    }
    if (periodic_[1]) {
      if (dy > h1) {
        dy -= len_[1];
      } else if (dy < -h1) {
        dy += len_[1];
      }
    }
    if (periodic_[2]) {
      if (dz > h2) {
        dz -= len_[2];
      } else if (dz < -h2) {
        dz += len_[2];
      }
    }
    return;
  }
  if (periodic_[0]) {
    dx -= len_[0] * orthorhombicImageIndex(dx * inv_[0]);
  }
  if (periodic_[1]) {
    dy -= len_[1] * orthorhombicImageIndex(dy * inv_[1]);
  }
  if (periodic_[2]) {
    dz -= len_[2] * orthorhombicImageIndex(dz * inv_[2]);
  }
}

inline void Neighbours::foldPair(std::int32_t i, std::int32_t j, double &dx, double &dy,
                                 double &dz) const {
  const auto ui = static_cast<std::size_t>(i) * 3;
  const auto uj = static_cast<std::size_t>(j) * 3;
  dx = xyz_[ui] - xyz_[uj];
  dy = xyz_[ui + 1] - xyz_[uj + 1];
  dz = xyz_[ui + 2] - xyz_[uj + 2];
  fold(dx, dy, dz);
}

inline int Neighbours::cellId(int ix, int iy, int iz) const {
  if (periodic_[0]) {
    if (ix < 0) {
      ix += nx_;
    } else if (ix >= nx_) {
      ix -= nx_;
    }
  } else if (ix < 0 || ix >= nx_) {
    return -1;
  }
  if (periodic_[1]) {
    if (iy < 0) {
      iy += ny_;
    } else if (iy >= ny_) {
      iy -= ny_;
    }
  } else if (iy < 0 || iy >= ny_) {
    return -1;
  }
  if (periodic_[2]) {
    if (iz < 0) {
      iz += nz_;
    } else if (iz >= nz_) {
      iz -= nz_;
    }
  } else if (iz < 0 || iz >= nz_) {
    return -1;
  }
  return (ix * ny_ + iy) * nz_ + iz;
}

} // namespace rgpot::nlist
