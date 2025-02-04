//=======================================================================================
// ____          ____    __    ______     __________   __      __       __        __
// \    \       |    |  |  |  |   _   \  |___    ___| |  |    |  |     /  \      |  |
//  \    \      |    |  |  |  |  |_)   |     |  |     |  |    |  |    /    \     |  |
//   \    \     |    |  |  |  |   _   /      |  |     |  |    |  |   /  /\  \    |  |
//    \    \    |    |  |  |  |  | \  \      |  |     |   \__/   |  /  ____  \   |  |____
//     \    \   |    |  |__|  |__|  \__\     |__|      \________/  /__/    \__\  |_______|
//      \    \  |    |   ________________________________________________________________
//       \    \ |    |  |  ______________________________________________________________|
//        \    \|    |  |  |         __          __     __     __     ______      _______
//         \         |  |  |_____   |  |        |  |   |  |   |  |   |   _  \    /  _____)
//          \        |  |   _____|  |  |        |  |   |  |   |  |   |  | \  \   \_______
//           \       |  |  |        |  |_____   |   \_/   |   |  |   |  |_/  /    _____  |
//            \ _____|  |__|        |________|   \_______/    |__|   |______/    (_______/
//
//  This file is part of VirtualFluids. VirtualFluids is free software: you can
//  redistribute it and/or modify it under the terms of the GNU General Public
//  License as published by the Free Software Foundation, either version 3 of
//  the License, or (at your option) any later version.
//
//  VirtualFluids is distributed in the hope that it will be useful, but WITHOUT
//  ANY WARRANTY; without even the implied warranty of MERCHANTABILITY or
//  FITNESS FOR A PARTICULAR PURPOSE. See the GNU General Public License
//  for more details.
//
//  SPDX-License-Identifier: GPL-3.0-or-later
//  SPDX-FileCopyrightText: Copyright © VirtualFluids Project contributors, see AUTHORS.md in root folder
//
//! \addtogroup gpu_PreProcessor PreProcessor
//! \ingroup gpu_core core
//! \{
//! \author Martin Schoenherr
//=======================================================================================
#include "Calculation/Calculation.h" 
#include "Utilities/KernelUtilities.h"
#include "lbm/constants/D3Q27.h"
#include <basics/constants/NumericConstants.h>
#include <gpu/cuda_helper/CudaIndexCalculation.h>

using namespace vf::basics::constant;
using namespace vf::lbm::dir;

__global__ void InitAdvectionDiffusionIncompressible_Device(
    const uint* neighborX,
    const uint* neighborY,
    const uint* neighborZ,
    const uint* typeOfGridNode,
    const real* concentration,
    const real* velocityX,
    const real* velocityY,
    const real* velocityZ,
    unsigned long long numberOfLBnodes,
    real* distributionsAD,
    bool isEvenTimestep)
{
    const uint nodeIndex = vf::cuda::get1DIndexFrom2DBlock();

    //////////////////////////////////////////////////////////////////////////
    // run for all indices in size_Mat and fluid nodes
    if ((nodeIndex >= numberOfLBnodes) || (typeOfGridNode[nodeIndex] != GEO_FLUID))
        return;
    
    Distributions27 distAD = vf::gpu::getDistributionReferences27(distributionsAD, numberOfLBnodes, isEvenTimestep);

    const real conc = concentration[nodeIndex];
    const real  vx1 = velocityX[nodeIndex];
    const real  vx2 = velocityY[nodeIndex];
    const real  vx3 = velocityZ[nodeIndex];

    const vf::gpu::ListIndices indices(nodeIndex, neighborX, neighborY, neighborZ);

    //////////////////////////////////////////////////////////////////////////
    //! - Calculate the equilibrium and set the distributions
    //!
    const real cu_sq = c3o2*(vx1*vx1 + vx2*vx2 + vx3*vx3);

    (distAD.f[d000])[indices.k_000] = c8o27  * conc * (c1o1 - cu_sq);
    (distAD.f[dP00])[indices.k_000] = c2o27  * conc * (c1o1 + c3o1 * ( vx1            ) + c9o2 * ( vx1            ) * ( vx1            ) - cu_sq);
    (distAD.f[dM00])[indices.k_M00] = c2o27  * conc * (c1o1 + c3o1 * (-vx1            ) + c9o2 * (-vx1            ) * (-vx1            ) - cu_sq);
    (distAD.f[d0P0])[indices.k_000] = c2o27  * conc * (c1o1 + c3o1 * (       vx2      ) + c9o2 * (       vx2      ) * (       vx2      ) - cu_sq);
    (distAD.f[d0M0])[indices.k_0M0] = c2o27  * conc * (c1o1 + c3o1 * (     - vx2      ) + c9o2 * (     - vx2      ) * (     - vx2      ) - cu_sq);
    (distAD.f[d00P])[indices.k_000] = c2o27  * conc * (c1o1 + c3o1 * (             vx3) + c9o2 * (             vx3) * (             vx3) - cu_sq);
    (distAD.f[d00M])[indices.k_00M] = c2o27  * conc * (c1o1 + c3o1 * (           - vx3) + c9o2 * (           - vx3) * (           - vx3) - cu_sq);
    (distAD.f[dPP0])[indices.k_000] = c1o54  * conc * (c1o1 + c3o1 * ( vx1 + vx2      ) + c9o2 * ( vx1 + vx2      ) * ( vx1 + vx2      ) - cu_sq);
    (distAD.f[dMM0])[indices.k_MM0] = c1o54  * conc * (c1o1 + c3o1 * (-vx1 - vx2      ) + c9o2 * (-vx1 - vx2      ) * (-vx1 - vx2      ) - cu_sq);
    (distAD.f[dPM0])[indices.k_0M0] = c1o54  * conc * (c1o1 + c3o1 * ( vx1 - vx2      ) + c9o2 * ( vx1 - vx2      ) * ( vx1 - vx2      ) - cu_sq);
    (distAD.f[dMP0])[indices.k_M00] = c1o54  * conc * (c1o1 + c3o1 * (-vx1 + vx2      ) + c9o2 * (-vx1 + vx2      ) * (-vx1 + vx2      ) - cu_sq);
    (distAD.f[dP0P])[indices.k_000] = c1o54  * conc * (c1o1 + c3o1 * ( vx1       + vx3) + c9o2 * ( vx1       + vx3) * ( vx1       + vx3) - cu_sq);
    (distAD.f[dM0M])[indices.k_M0M] = c1o54  * conc * (c1o1 + c3o1 * (-vx1       - vx3) + c9o2 * (-vx1       - vx3) * (-vx1       - vx3) - cu_sq);
    (distAD.f[dP0M])[indices.k_00M] = c1o54  * conc * (c1o1 + c3o1 * ( vx1       - vx3) + c9o2 * ( vx1       - vx3) * ( vx1       - vx3) - cu_sq);
    (distAD.f[dM0P])[indices.k_M00] = c1o54  * conc * (c1o1 + c3o1 * (-vx1       + vx3) + c9o2 * (-vx1       + vx3) * (-vx1       + vx3) - cu_sq);
    (distAD.f[d0PP])[indices.k_000] = c1o54  * conc * (c1o1 + c3o1 * (       vx2 + vx3) + c9o2 * (       vx2 + vx3) * (       vx2 + vx3) - cu_sq);
    (distAD.f[d0MM])[indices.k_0MM] = c1o54  * conc * (c1o1 + c3o1 * (     - vx2 - vx3) + c9o2 * (     - vx2 - vx3) * (     - vx2 - vx3) - cu_sq);
    (distAD.f[d0PM])[indices.k_00M] = c1o54  * conc * (c1o1 + c3o1 * (       vx2 - vx3) + c9o2 * (       vx2 - vx3) * (       vx2 - vx3) - cu_sq);
    (distAD.f[d0MP])[indices.k_0M0] = c1o54  * conc * (c1o1 + c3o1 * (     - vx2 + vx3) + c9o2 * (     - vx2 + vx3) * (     - vx2 + vx3) - cu_sq);
    (distAD.f[dPPP])[indices.k_000] = c1o216 * conc * (c1o1 + c3o1 * ( vx1 + vx2 + vx3) + c9o2 * ( vx1 + vx2 + vx3) * ( vx1 + vx2 + vx3) - cu_sq);
    (distAD.f[dMMM])[indices.k_MMM] = c1o216 * conc * (c1o1 + c3o1 * (-vx1 - vx2 - vx3) + c9o2 * (-vx1 - vx2 - vx3) * (-vx1 - vx2 - vx3) - cu_sq);
    (distAD.f[dPPM])[indices.k_00M] = c1o216 * conc * (c1o1 + c3o1 * ( vx1 + vx2 - vx3) + c9o2 * ( vx1 + vx2 - vx3) * ( vx1 + vx2 - vx3) - cu_sq);
    (distAD.f[dMMP])[indices.k_MM0] = c1o216 * conc * (c1o1 + c3o1 * (-vx1 - vx2 + vx3) + c9o2 * (-vx1 - vx2 + vx3) * (-vx1 - vx2 + vx3) - cu_sq);
    (distAD.f[dPMP])[indices.k_0M0] = c1o216 * conc * (c1o1 + c3o1 * ( vx1 - vx2 + vx3) + c9o2 * ( vx1 - vx2 + vx3) * ( vx1 - vx2 + vx3) - cu_sq);
    (distAD.f[dMPM])[indices.k_M0M] = c1o216 * conc * (c1o1 + c3o1 * (-vx1 + vx2 - vx3) + c9o2 * (-vx1 + vx2 - vx3) * (-vx1 + vx2 - vx3) - cu_sq);
    (distAD.f[dPMM])[indices.k_0MM] = c1o216 * conc * (c1o1 + c3o1 * ( vx1 - vx2 - vx3) + c9o2 * ( vx1 - vx2 - vx3) * ( vx1 - vx2 - vx3) - cu_sq);
    (distAD.f[dMPP])[indices.k_M00] = c1o216 * conc * (c1o1 + c3o1 * (-vx1 + vx2 + vx3) + c9o2 * (-vx1 + vx2 + vx3) * (-vx1 + vx2 + vx3) - cu_sq);
}

//! \}
