/*****************************************************************************\
* (c) Copyright 2018-2020 CERN for the benefit of the LHCb Collaboration      *
*                                                                             *
* This software is distributed under the terms of the Apache License          *
* version 2 (Apache-2.0), copied verbatim in the file "LICENSE".              *
*                                                                             *
* In applying this licence, CERN does not waive the privileges and immunities *
* granted to it by virtue of its status as an Intergovernmental Organization  *
* or submit itself to any jurisdiction.                                       *
\*****************************************************************************/
#pragma once

#include "SciFiDefinitions.cuh"
#include "ParKalmanMath.cuh"
#include "BackendCommon.h"
#include <limits.h>

namespace VertexFit {

  constexpr unsigned max_svs = 1000;
  constexpr unsigned max_sv_track_combinations = 1000;
  constexpr unsigned max_tracks_per_sv =
    4; // harcoded as the multi-track vertexing has not been tested for more than 4 tracks

  struct TrackMVAVertex {
    // Fit results.
    float px = 0.0f;
    float py = 0.0f;
    float pz = 0.0f;
    float x = 0.0f;
    float y = 0.0f;
    float z = 0.0f;
    float chi2 = -1.0f;

    float cov00 = 0.0f;
    float cov10 = 0.0f;
    float cov11 = 0.0f;
    float cov20 = 0.0f;
    float cov21 = 0.0f;
    float cov22 = 0.0f;

    // Store enough info to calculate masses on demand.
    float p1 = 0.f;
    float p2 = 0.f;
    float cos = 1.f;

    float vertex_ip = std::numeric_limits<float>::quiet_NaN();
    float dz = 0.0f;
    float doca = -1.f;
    float vertex_clone_sin2 = 0.0f;

    // Additional variables for MVA lines.
    // Sum of track pT.
    float sumpt = 0.0f;
    // FD chi2.
    float fdchi2 = std::numeric_limits<float>::quiet_NaN();
    // Mass assuming dimuon hypothesis.
    float mdimu = 0.0f;
    // Corrected mass.
    float mcor = 0.0f;
    // PV -> SV eta.
    float eta = 0.0f;
    // Minimum IP chi2 of the tracks.
    float minipchi2 = 0.0f;
    // IP of the two tracks
    float ip1 = 0.0f;
    float ip2 = 0.0f;
    // Minimum IP of the tracks.
    float minip = 0.0f;
    // Minimum pt of the tracks.
    float minpt = 0.0f;
    // Number of tracks associated to a PV (min IP chi2 < 16).
    int ntrks16 = 0;
    // cos DIRA
    float dira = 0.0f;

    // Degrees of freedom.
    int ndof = 0;

    // Track indices.
    unsigned trk1 = 0;
    unsigned trk2 = 0;

    // Muon ID.
    bool trk1_is_muon;
    bool trk2_is_muon;
    bool is_dimuon;

    __device__ __host__ float pt() const { return sqrtf(px * px + py * py); }
    __device__ __host__ float m(float m1, float m2) const
    {
      const float E1 = sqrtf(p1 * p1 + m1 * m1);
      const float E2 = sqrtf(p2 * p2 + m2 * m2);
      return sqrtf(m1 * m1 + m2 * m2 + 2 * E1 * E2 - 2 * p1 * p2 * cos);
    }
  };

  struct MiniVertex {
    // Track indices.
    unsigned trk1 = 0;
    unsigned trk2 = 0;
    // SV properties
    float px = 0.0f;
    float py = 0.0f;
    float pz = 0.0f;
    float x = 0.0f;
    float y = 0.0f;
    float z = 0.0f;
    float Armenteros_x = 0;
    float Armenteros_y = 0;
    // BuSca variables
    float helicity = 0.f;
    // DOCA
    float doca = 0.f;
    float quality = 0.f;
  };

} // namespace VertexFit
