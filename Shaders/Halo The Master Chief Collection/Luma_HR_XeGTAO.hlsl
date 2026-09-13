#ifndef __XE_GTAO_HLSLI__
#define __XE_GTAO_HLSLI__

// XeGTAO implementation (stolen from BioShock Infinite mod)
// Source: https://github.com/GameTechDev/XeGTAO

#include "./Includes/Common.hlsl"
#pragma warning(disable : 3579)

/////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////
/////////////
// Defines //
/////////////

#if HALOR_AO == 0
    LET_THIS_BREAK;
#elif HALOR_AO == 1
    #define SLICE_COUNT 3.0
    #define STEPS_PER_SLICE 3.0
#elif HALOR_AO == 2
    #define SLICE_COUNT 4.0
    #define STEPS_PER_SLICE 3.0
#elif HALOR_AO == 3
    #define SLICE_COUNT 8.0
    #define STEPS_PER_SLICE 3.0
#elif HALOR_AO == 4
    #define SLICE_COUNT 16.0
    #define STEPS_PER_SLICE 3.0
#elif HALOR_AO == 5
    #define SLICE_COUNT 24.0
    #define STEPS_PER_SLICE 3.0
#endif

#define EFFECT_RADIUS 1 // Default 0.5
#define RADIUS_MULTIPLIER 0.4 // Default 1.457
#define EFFECT_FALLOFF_RANGE 0.615 // Default 0.615
#define EFFECT_RADIUS_DISTANCE_SCALE 0.0558
#define SAMPLE_DISTRIBUTION_POWER 1.0 // Default 2.0
#define THIN_OCCLUDER_COMPENSATION 0.0 // Default 0.0 
#define FINAL_VALUE_POWER 3.5 * GS.AmbientOcclusion // Default 2.2
#define DEPTH_MIP_SAMPLING_OFFSET 2 // Default 3.3
#define DENOISE_BLUR_BETA 1.2 // Default 1.2

#define XE_GTAO_PI 3.1415926535897932384626433832795
#define XE_GTAO_PI_OVER_360 0.00872664625997
#define XE_GTAO_PI_HALF 1.5707963267948966192313216916398

#define XE_GTAO_DEPTH_MIP_LEVELS 5.0
#define XE_GTAO_OCCLUSION_TERM_SCALE 1.0

#define XE_GTAO_NUMTHREADS_X 8
#define XE_GTAO_NUMTHREADS_Y 8

struct GTAOConstants
{
    float2 ViewportPixelSize;       // 1/fullTextureSize - for source texture UV calculations
    float2 RenderPixelSize;         // 1/actualRenderSize - for working texture UV calculations
    float2 ViewportSize;
    float2 NDCToViewMul;
    float2 NDCToViewAdd;
    float2 NDCToViewMul_x_PixelSize;
};

/////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////
//////////////
// Bindings //
//////////////

cbuffer HDAOPS : register(b0)
{
  float4 pixel_size : packoffset(c0);
  float4 scale : packoffset(c1);
  float4 corner_params : packoffset(c2);
  float4 bounds_params : packoffset(c3);
  float4 curve_params : packoffset(c4);
  float4 fade_params : packoffset(c5);
  float4 channel_scale : packoffset(c6);
  float4 channel_offset : packoffset(c7);
}

cbuffer SSAOLocalDepthPS : register(b1)
{
  float4 local_depth_constants : packoffset(c0);
}

SamplerState s0 : register(s0); //point 
SamplerState s1 : register(s1); //linear
Texture2D<float4> t0 : register(t0); 
Texture2D<float4> t1 : register(t1); 

RWTexture2D<float> out_working_depth_mip0 : register(u0);
RWTexture2D<float> out_working_depth_mip1 : register(u1);
RWTexture2D<float> out_working_depth_mip2 : register(u2);
RWTexture2D<float> out_working_depth_mip3 : register(u3);
RWTexture2D<float> out_working_depth_mip4 : register(u4);
RWTexture2D<unorm float2> ao_term_and_edges : register(u0); // Main Pass
RWTexture2D<unorm float2> final_output : register(u0); // Final Denoise Pass

/////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////
/////////////////////
// Depth PreFilter //
/////////////////////

// This is also a good place to do non-linear depth conversion for cases where one wants the 'radius' (effectively the threshold between near-field and far-field GI), 
// is required to be non-linear (i.e. very large outdoors environments).
float XeGTAO_ClampDepth(float depth)
{
    return clamp(depth, 0.0, 3.402823466e+38);
}

float XeGTAO_ScreenSpaceToViewSpaceDepth(float screenDepth)
{
    screenDepth = 1.0 / (screenDepth * local_depth_constants.y + local_depth_constants.x);
    return screenDepth;
}

// weighted average depth filter
float XeGTAO_DepthMIPFilter(float depth0, float depth1, float depth2, float depth3)
{
    float maxDepth = max(max(depth0, depth1), max(depth2, depth3));

    const float depthRangeScaleFactor = 0.75; // found empirically :)
    const float effectRadius = depthRangeScaleFactor * EFFECT_RADIUS * RADIUS_MULTIPLIER;
    const float falloffRange = EFFECT_FALLOFF_RANGE * effectRadius;
    const float falloffFrom = effectRadius * (1.0 - EFFECT_FALLOFF_RANGE);

    // fadeout precompute optimisation
    const float falloffMul = -1.0 / falloffRange;
    const float falloffAdd = falloffFrom / falloffRange + 1.0;

    float weight0 = saturate((maxDepth - depth0) * falloffMul + falloffAdd);
    float weight1 = saturate((maxDepth - depth1) * falloffMul + falloffAdd);
    float weight2 = saturate((maxDepth - depth2) * falloffMul + falloffAdd);
    float weight3 = saturate((maxDepth - depth3) * falloffMul + falloffAdd);

    float weightSum = weight0 + weight1 + weight2 + weight3;
    return (weight0 * depth0 + weight1 * depth1 + weight2 * depth2 + weight3 * depth3) * rcp(weightSum);
}

groupshared float g_scratchDepths[8][8];
void XeGTAO_PrefilterDepths16x16CS(uint2 dispatchThreadID, uint2 groupThreadID, Texture2D sourceNDCDepth, RWTexture2D<float> outDepth0, RWTexture2D<float> outDepth1, RWTexture2D<float> outDepth2, RWTexture2D<float> outDepth3, RWTexture2D<float> outDepth4)
{
    // MIP 0
    const uint2 baseCoord = dispatchThreadID;
    const uint2 pixCoord = baseCoord * 2;

    float4 depths4 = sourceNDCDepth.GatherRed(s0, float2(pixCoord), int2(1, 1));
    float depth0 = XeGTAO_ClampDepth(XeGTAO_ScreenSpaceToViewSpaceDepth(depths4.w));
    float depth1 = XeGTAO_ClampDepth(XeGTAO_ScreenSpaceToViewSpaceDepth(depths4.z));
    float depth2 = XeGTAO_ClampDepth(XeGTAO_ScreenSpaceToViewSpaceDepth(depths4.x));
    float depth3 = XeGTAO_ClampDepth(XeGTAO_ScreenSpaceToViewSpaceDepth(depths4.y));
    outDepth0[pixCoord + uint2(0, 0)] = depth0;
    outDepth0[pixCoord + uint2(1, 0)] = depth1;
    outDepth0[pixCoord + uint2(0, 1)] = depth2;
    outDepth0[pixCoord + uint2(1, 1)] = depth3;

    // MIP 1
    float dm1 = XeGTAO_DepthMIPFilter(depth0, depth1, depth2, depth3);
    outDepth1[baseCoord] = dm1;
    g_scratchDepths[groupThreadID.x][groupThreadID.y] = dm1;

    GroupMemoryBarrierWithGroupSync();

    // MIP 2
    [branch]
    if (all((groupThreadID.xy % 2) == 0)) {
        float inTL = g_scratchDepths[groupThreadID.x + 0][groupThreadID.y + 0];
        float inTR = g_scratchDepths[groupThreadID.x + 1][groupThreadID.y + 0];
        float inBL = g_scratchDepths[groupThreadID.x + 0][groupThreadID.y + 1];
        float inBR = g_scratchDepths[groupThreadID.x + 1][groupThreadID.y + 1];

        float dm2 = XeGTAO_DepthMIPFilter(inTL, inTR, inBL, inBR);
        outDepth2[baseCoord / 2] = dm2;
        g_scratchDepths[groupThreadID.x][groupThreadID.y] = dm2;
    }

    GroupMemoryBarrierWithGroupSync();

    // MIP 3
    [branch]
    if (all(( groupThreadID.xy % 4) == 0)) {
        float inTL = g_scratchDepths[groupThreadID.x + 0][groupThreadID.y + 0];
        float inTR = g_scratchDepths[groupThreadID.x + 2][groupThreadID.y + 0];
        float inBL = g_scratchDepths[groupThreadID.x + 0][groupThreadID.y + 2];
        float inBR = g_scratchDepths[groupThreadID.x + 2][groupThreadID.y + 2];

        float dm3 = XeGTAO_DepthMIPFilter(inTL, inTR, inBL, inBR);
        outDepth3[baseCoord / 4] = dm3;
        g_scratchDepths[groupThreadID.x][groupThreadID.y] = dm3;
    }

    GroupMemoryBarrierWithGroupSync();

    // MIP 4
    [branch]
    if (all((groupThreadID.xy % 8) == 0)) {
        float inTL = g_scratchDepths[groupThreadID.x + 0][groupThreadID.y + 0];
        float inTR = g_scratchDepths[groupThreadID.x + 4][groupThreadID.y + 0];
        float inBL = g_scratchDepths[groupThreadID.x + 0][groupThreadID.y + 4];
        float inBR = g_scratchDepths[groupThreadID.x + 4][groupThreadID.y + 4];

        float dm4 = XeGTAO_DepthMIPFilter(inTL, inTR, inBL, inBR);
        outDepth4[baseCoord / 8] = dm4;
        g_scratchDepths[ groupThreadID.x ][ groupThreadID.y ] = dm4;
    }
}

/////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////
////////////////////////
// Visibility & Edges //
////////////////////////

float4 XeGTAO_CalculateEdges(float centerZ, float leftZ, float rightZ, float topZ, float bottomZ)
{
	float4 edgesLRTB = float4(leftZ, rightZ, topZ, bottomZ) - centerZ;

	float slopeLR = (edgesLRTB.y - edgesLRTB.x) * 0.5;
	float slopeTB = (edgesLRTB.w - edgesLRTB.z) * 0.5;
	float4 edgesLRTBSlopeAdjusted = edgesLRTB + float4(slopeLR, -slopeLR, slopeTB, -slopeTB);
	edgesLRTB = min(abs(edgesLRTB), abs(edgesLRTBSlopeAdjusted));
	return saturate(1.25 - edgesLRTB * rcp(centerZ * 0.011));
}

// packing/unpacking for edges; 2 bits per edge mean 4 gradient values (0, 0.33, 0.66, 1) for smoother transitions!
float XeGTAO_PackEdges(float4 edgesLRTB)
{
	// integer version:
	// edgesLRTB = saturate(edgesLRTB) * 2.9.xxxx + 0.5.xxxx;
	// return (((uint)edgesLRTB.x) << 6) + (((uint)edgesLRTB.y) << 4) + (((uint)edgesLRTB.z) << 2) + (((uint)edgesLRTB.w));
	// 
	// optimized, should be same as above
	edgesLRTB = round(saturate(edgesLRTB) * 2.9);
	return dot(edgesLRTB, float4(64.0 / 255.0, 16.0 / 255.0, 4.0 / 255.0, 1.0 / 255.0));
}

// Inputs are screen XY and viewspace depth, output is viewspace position
// screenPos is pixel coordinate (0 to actualRenderSize)
float3 XeGTAO_ComputeViewspacePosition(float2 pixelPos, float viewspaceDepth, const GTAOConstants consts)
{
	float3 ret;
	// NDCToViewMul already includes 1/actualRenderSize, so we multiply by pixel position directly
	ret.xy = (consts.NDCToViewMul * pixelPos.xy + consts.NDCToViewAdd) * viewspaceDepth;
	ret.z = viewspaceDepth;
	return ret;
}

// http://h14s.p5r.org/2012/09/0x5f3759df.html, [Drobot2014a] Low Level Optimizations for GCN, https://blog.selfshadow.com/publications/s2016-shading-course/activision/s2016_pbs_activision_occlusion.pdf slide 63
float XeGTAO_FastSqrt(float x)
{
	return asfloat(0x1fbd1df5 + (asint(x) >> 1));
}

// input [-1, 1] and output [0, PI], from https://seblagarde.wordpress.com/2014/12/01/inverse-trigonometric-functions-gpu-optimization-for-amd-gcn-architecture/
float XeGTAO_FastACos(float inX)
{ 
	float x = abs(inX); 
	float res = -0.156583 * x + XE_GTAO_PI_HALF;
	res *= XeGTAO_FastSqrt(1.0 - x);
	return inX >= 0 ? res : XE_GTAO_PI - res;
}

float3 XeGTAO_CalculateNormal( const float4 edgesLRTB, float3 pixCenterPos, float3 pixLPos, float3 pixRPos, float3 pixTPos, float3 pixBPos )
{
    // Get this pixel's viewspace normal
    float4 acceptedNormals  = saturate( float4( edgesLRTB.x*edgesLRTB.z, edgesLRTB.z*edgesLRTB.y, edgesLRTB.y*edgesLRTB.w, edgesLRTB.w*edgesLRTB.x ) + 0.01 );

    pixLPos = normalize(pixLPos - pixCenterPos);
    pixRPos = normalize(pixRPos - pixCenterPos);
    pixTPos = normalize(pixTPos - pixCenterPos);
    pixBPos = normalize(pixBPos - pixCenterPos);

    float3 pixelNormal =  acceptedNormals.x * cross( pixLPos, pixTPos ) +
                        + acceptedNormals.y * cross( pixTPos, pixRPos ) +
                        + acceptedNormals.z * cross( pixRPos, pixBPos ) +
                        + acceptedNormals.w * cross( pixBPos, pixLPos );
    pixelNormal = normalize( pixelNormal );

    return pixelNormal;
}

float2 XeGTAO_MainPassCS(uint2 pixCoord, float2 localNoise, float3 viewspaceNormal, Texture2D sourceViewspaceDepth, SamplerState depthSampler, const GTAOConstants consts)
{
    float2 normalizedScreenPos = (pixCoord + 0.5.xx) * consts.ViewportPixelSize;
    
//     // // viewspace Z at the center
//     // float viewspaceZ = sourceViewspaceDepth.SampleLevel(depthSampler, normalizedScreenPos, 0).x;
//     // return viewspaceZ; //debug depth
// 
//
//     // Sample from working depth texture (our buffer - no viewport offset)
//     // float4 valuesUL = sourceViewspaceDepth.GatherRed(depthSampler, normalizedScreenPos);
//     // float4 valuesBR = sourceViewspaceDepth.GatherRed(depthSampler, normalizedScreenPos, int2(1, 1));
//     float4 valuesUL = sourceViewspaceDepth.Load(int3(pixCoord, 0)).xxxx;
//     float4 valuesBR = sourceViewspaceDepth.Load(int3(pixCoord + int2(1, 1), 0)).xxxx;
// 
//     // viewspace Zs left top right bottom
//     const float pixLZ = valuesUL.x;
//     const float pixTZ = valuesUL.z;
//     const float pixRZ = valuesBR.z;
//     const float pixBZ = valuesBR.x;

    // center
    float viewspaceZ  = XeGTAO_ScreenSpaceToViewSpaceDepth(sourceViewspaceDepth.SampleLevel(depthSampler, normalizedScreenPos, 0).x);

    // depth fade
    float final_pow_depth = saturate(InverseLerp(100, 0, viewspaceZ));
    if (final_pow_depth == 0) return float2(1.0, 0.0);

    // no prepass, so get each
    float pixLZ = XeGTAO_ScreenSpaceToViewSpaceDepth(sourceViewspaceDepth.SampleLevel(depthSampler, normalizedScreenPos + float2(-1,  0) * consts.ViewportPixelSize, 0).x);
    float pixRZ = XeGTAO_ScreenSpaceToViewSpaceDepth(sourceViewspaceDepth.SampleLevel(depthSampler, normalizedScreenPos + float2( 1,  0) * consts.ViewportPixelSize, 0).x);
    float pixTZ = XeGTAO_ScreenSpaceToViewSpaceDepth(sourceViewspaceDepth.SampleLevel(depthSampler, normalizedScreenPos + float2( 0, -1) * consts.ViewportPixelSize, 0).x);
    float pixBZ = XeGTAO_ScreenSpaceToViewSpaceDepth(sourceViewspaceDepth.SampleLevel(depthSampler, normalizedScreenPos + float2( 0,  1) * consts.ViewportPixelSize, 0).x);
    // return viewspaceZ;

    // Calculate edges
    float4 edgesLRTB  = XeGTAO_CalculateEdges(viewspaceZ, pixLZ, pixRZ, pixTZ, pixBZ);
    const float edges = XeGTAO_PackEdges(edgesLRTB);
    // const float edges = min(edgesLRTB.x, min(edgesLRTB.y, min(edgesLRTB.z, edgesLRTB.w)));
    // return edges;

    // float3 CENTER   = XeGTAO_ComputeViewspacePosition( normalizedScreenPos,                                             viewspaceZ, consts );
    // float3 LEFT     = XeGTAO_ComputeViewspacePosition( normalizedScreenPos + float2(-1,  0) * consts.ViewportPixelSize, pixLZ,      consts );
    // float3 RIGHT    = XeGTAO_ComputeViewspacePosition( normalizedScreenPos + float2( 1,  0) * consts.ViewportPixelSize, pixRZ,      consts );
    // float3 TOP      = XeGTAO_ComputeViewspacePosition( normalizedScreenPos + float2( 0, -1) * consts.ViewportPixelSize, pixTZ,      consts );
    // float3 BOTTOM   = XeGTAO_ComputeViewspacePosition( normalizedScreenPos + float2( 0,  1) * consts.ViewportPixelSize, pixBZ,      consts );
    // viewspaceNormal = XeGTAO_CalculateNormal( edgesLRTB, CENTER, LEFT, RIGHT, TOP, BOTTOM );
    // return viewspaceNormal.x * 0.5 + 0.5;

    // Move center pixel slightly towards camera to avoid imprecision artifacts due to depth buffer imprecision; offset depends on depth texture format used
    viewspaceZ *= 0.99999; // this is good for FP32 depth buffer

    const float3 pixCenterPos = XeGTAO_ComputeViewspacePosition(normalizedScreenPos, viewspaceZ, consts);
    const float3 viewVec = normalize(-pixCenterPos);
    // return viewVec.z * 0.5 + 0.5;

    // prevents normals that are facing away from the view vector - xeGTAO struggles with extreme cases, but in Vanilla it seems rare so it's disabled by default
    viewspaceNormal = normalize( viewspaceNormal + max( 0, -dot( viewspaceNormal, viewVec ) ) * viewVec );

    const float baseRadius = EFFECT_RADIUS + (viewspaceZ * EFFECT_RADIUS_DISTANCE_SCALE); // Distance scaled https://github.com/BarbatosBachiko/Reshade-Shaders/blob/main/Shaders/BaBa_XeGTAO.fx
    const float effectRadius = max(0, baseRadius * RADIUS_MULTIPLIER); 
    const float sampleDistributionPower = SAMPLE_DISTRIBUTION_POWER;
    const float thinOccluderCompensation = min(1, THIN_OCCLUDER_COMPENSATION + (viewspaceZ * 0.0067));
    const float falloffRange = EFFECT_FALLOFF_RANGE * effectRadius;
    const float falloffFrom = effectRadius * (1.0 - EFFECT_FALLOFF_RANGE);

    // fadeout precompute optimisation
    const float falloffMul = -1.0 / falloffRange;
    const float falloffAdd = falloffFrom / falloffRange + 1.0;

    float visibility = 0.0;

    // see "Algorithm 1" in https://www.activision.com/cdn/research/Practical_Real_Time_Strategies_for_Accurate_Indirect_Occlusion_NEW%20VERSION_COLOR.pdf
    {
        const float noiseSlice = localNoise.x;
        const float noiseSample = localNoise.y;

        // quality settings / tweaks / hacks
        const float pixelTooCloseThreshold = 1.3; // if the offset is under approx pixel size (pixelTooCloseThreshold), push it out to the minimum distance

        // approx viewspace pixel size at pixCoord; approximation of NDCToViewspace( normalizedScreenPos.xy + consts.ViewportPixelSize.xy, pixCenterPos.z ).xy - pixCenterPos.xy;
        const float2 pixelDirRBViewspaceSizeAtCenterZ = viewspaceZ.xx * consts.NDCToViewMul_x_PixelSize;
        // return pixelDirRBViewspaceSizeAtCenterZ.xy * 0.5 + 0.5;

        float screenspaceRadius = effectRadius * rcp(pixelDirRBViewspaceSizeAtCenterZ.x);

        // fade out for small screen radii 
        visibility += saturate((10.0 - screenspaceRadius) / 100.0) * 0.5;

        // this is the min distance to start sampling from to avoid sampling from the center pixel (no useful data obtained from sampling center pixel)
        const float minS = pixelTooCloseThreshold * rcp(screenspaceRadius);

        //[unroll]
        for (float slice = 0.0; slice < SLICE_COUNT; slice++) {
            float sliceK = (slice + noiseSlice) / SLICE_COUNT;
            // lines 5, 6 from the paper
            float phi = sliceK * XE_GTAO_PI;
            float cosPhi = cos(phi);
            float sinPhi = sin(phi);
            float2 omega = float2(cosPhi, -sinPhi); //lpfloat2 on omega causes issues with big radii

            // convert to screen units (pixels) for later use
            omega *= screenspaceRadius;

            // line 8 from the paper
            const float3 directionVec = float3(cosPhi, sinPhi, 0.0);

            // line 9 from the paper
            const float3 orthoDirectionVec = directionVec - (dot(directionVec, viewVec) * viewVec);

            // line 10 from the paper
            //axisVec is orthogonal to directionVec and viewVec, used to define projectedNormal
            const float3 axisVec = normalize(cross(orthoDirectionVec, viewVec));

            // alternative line 9 from the paper
            // float3 orthoDirectionVec = cross( viewVec, axisVec );

            // line 11 from the paper
            float3 projectedNormalVec = viewspaceNormal - axisVec * dot(viewspaceNormal, axisVec);

            // line 13 from the paper
            float signNorm = sign(dot(orthoDirectionVec, projectedNormalVec));

            // line 14 from the paper
            float projectedNormalVecLength = length(projectedNormalVec);
            float cosNorm = saturate(dot(projectedNormalVec, viewVec) * rcp(projectedNormalVecLength));

            // line 15 from the paper
            float n = signNorm * XeGTAO_FastACos(cosNorm);

            // this is a lower weight target; not using -1 as in the original paper because it is under horizon, so a 'weight' has different meaning based on the normal
            const float lowHorizonCos0 = cos(n + XE_GTAO_PI_HALF);
            const float lowHorizonCos1 = cos(n - XE_GTAO_PI_HALF);

            // lines 17, 18 from the paper, manually unrolled the 'side' loop
            float horizonCos0 = lowHorizonCos0; //-1;
            float horizonCos1 = lowHorizonCos1; //-1;

            [unroll]
            for (float step = 0.0; step < STEPS_PER_SLICE; step++) {
                // R1 sequence (http://extremelearning.com.au/unreasonable-effectiveness-of-quasirandom-sequences/)
                const float stepBaseNoise = (slice + step * STEPS_PER_SLICE) * 0.6180339887498948482; // <- this should unroll
                float stepNoise = frac(noiseSample + stepBaseNoise);

                // approx line 20 from the paper, with added noise
                float s = (step + stepNoise) / STEPS_PER_SLICE; // + (lpfloat2)1e-6f);

                // additional distribution modifier
                s = pow(s, sampleDistributionPower);

                // avoid sampling center pixel
                s += minS;

                // approx lines 21-22 from the paper, unrolled
                float2 sampleOffset = s * omega;

                float sampleOffsetLength = length(sampleOffset);

                // note: when sampling, using point_point_point or point_point_linear sampler works, but linear_linear_linear will cause unwanted interpolation between neighbouring depth values on the same MIP level!
                const float mipLevel = 0/* clamp(log2(sampleOffsetLength) - DEPTH_MIP_SAMPLING_OFFSET, 0.0, XE_GTAO_DEPTH_MIP_LEVELS) */;

                // Snap to pixel center (offset is in pixels)
                sampleOffset = round(sampleOffset) * consts.ViewportPixelSize;
                
                float2 sampleScreenPos0 = normalizedScreenPos + sampleOffset;
                float2 sampleScreenPos1 = normalizedScreenPos - sampleOffset;

                float SZ0 = sourceViewspaceDepth.SampleLevel(depthSampler, sampleScreenPos0, mipLevel).x;
                SZ0 = XeGTAO_ScreenSpaceToViewSpaceDepth(SZ0);
                float3 samplePos0 = XeGTAO_ComputeViewspacePosition(sampleScreenPos0, SZ0, consts);

                float SZ1 = sourceViewspaceDepth.SampleLevel(depthSampler, sampleScreenPos1, mipLevel).x;
                SZ1 = XeGTAO_ScreenSpaceToViewSpaceDepth(SZ1);
                float3 samplePos1 = XeGTAO_ComputeViewspacePosition(sampleScreenPos1, SZ1, consts);

                float3 sampleDelta0 = samplePos0 - pixCenterPos; // using lpfloat for sampleDelta causes precision issues
                float3 sampleDelta1 = samplePos1 - pixCenterPos; // using lpfloat for sampleDelta causes precision issues
                float sampleDist0 = length(sampleDelta0);
                float sampleDist1 = length(sampleDelta1);

                // approx lines 23, 24 from the paper, unrolled
                float3 sampleHorizonVec0 = sampleDelta0 * rcp(sampleDist0);
                float3 sampleHorizonVec1 = sampleDelta1 * rcp(sampleDist1);

                // any sample out of radius should be discarded - also use fallof range for smooth transitions; this is a modified idea from "4.3 Implementation details, Bounding the sampling area"
                // this is our own thickness heuristic that relies on sooner discarding samples behind the center
                float falloffBase0 = length(float3(sampleDelta0.x, sampleDelta0.y, sampleDelta0.z * (1.0 + thinOccluderCompensation)));
                float falloffBase1 = length(float3(sampleDelta1.x, sampleDelta1.y, sampleDelta1.z * (1.0 + thinOccluderCompensation)));
                float weight0 = saturate(falloffBase0 * falloffMul + falloffAdd);
                float weight1 = saturate(falloffBase1 * falloffMul + falloffAdd);

                // sample horizon cos
                float shc0 = dot(sampleHorizonVec0, viewVec);
                float shc1 = dot(sampleHorizonVec1, viewVec);

                // discard unwanted samples
                shc0 = lerp(lowHorizonCos0, shc0, weight0); // this would be more correct but too expensive: cos(lerp( acos(lowHorizonCos0), acos(shc0), weight0 ));
                shc1 = lerp(lowHorizonCos1, shc1, weight1); // this would be more correct but too expensive: cos(lerp( acos(lowHorizonCos1), acos(shc1), weight1 ));

                // thickness heuristic - see "4.3 Implementation details, Height-field assumption considerations"
#if 0   // (disabled, not used) this should match the paper
				float newhorizonCos0 = max(horizonCos0, shc0);
				float newhorizonCos1 = max(horizonCos1, shc1);
				horizonCos0 = horizonCos0 > shc0 ? lerp(newhorizonCos0, shc0, thinOccluderCompensation) : newhorizonCos0;
				horizonCos1 = horizonCos1 > shc1 ? lerp(newhorizonCos1, shc1, thinOccluderCompensation) : newhorizonCos1;
#elif 0 // (disabled, not used) this is slightly different from the paper but cheaper and provides very similar results
				horizonCos0 = lerp(max(horizonCos0, shc0), shc0, thinOccluderCompensation);
				horizonCos1 = lerp(max(horizonCos1, shc1), shc1, thinOccluderCompensation);
#else   // this is a version where thicknessHeuristic is completely disabled
				horizonCos0 = max(horizonCos0, shc0);
				horizonCos1 = max(horizonCos1, shc1);
#endif
			}

#if 1       // I can't figure out the slight overdarkening on high slopes, so I'm adding this fudge - in the training set, 0.05 is close (PSNR 21.34) to disabled (PSNR 21.45)
			projectedNormalVecLength = lerp(projectedNormalVecLength, 1.0, 0.05);
#endif

			// line ~27, unrolled
			float h0 = -XeGTAO_FastACos(horizonCos1);
			float h1 = XeGTAO_FastACos(horizonCos0);
#if 0       // we can skip clamping for a tiny little bit more performance
			h0 = n + clamp(h0 - n, -XE_GTAO_PI_HALF, XE_GTAO_PI_HALF);
			h1 = n + clamp(h1 - n, -XE_GTAO_PI_HALF, XE_GTAO_PI_HALF);
#endif
			float iarc0 = (cosNorm + 2.0 * h0 * sin(n) - cos(2.0 * h0 - n)) / 4.0;
			float iarc1 = (cosNorm + 2.0 * h1 * sin(n) - cos(2.0 * h1 - n)) / 4.0;
			float localVisibility = projectedNormalVecLength * (iarc0 + iarc1);
			visibility += localVisibility;
		}
        visibility /= SLICE_COUNT;

        float final_pow = FINAL_VALUE_POWER;
        final_pow *= sqrt(final_pow_depth);
		visibility = pow(visibility, final_pow); 

		visibility = max(0.03, visibility); // disallow total occlusion (which wouldn't make any sense anyhow since pixel is visible but also helps with packing bent normals)
    }

    visibility = saturate(visibility / XE_GTAO_OCCLUSION_TERM_SCALE);
    // outWorkingAOTermAndEdges[pixCoord] = float2(visibility, edges);
    return float2(visibility, edges);
}

//////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////
//////////////
// DENOISER //
//////////////

void XeGTAO_DecodeGatherPartial(float4 packedValue, out float outDecoded[4])
{
    for (int i = 0; i < 4; i++) {
    	outDecoded[i] = packedValue[i];
    }
}

float4 XeGTAO_UnpackEdges(float _packedVal)
{
	uint packedVal = uint(_packedVal * 255.5);
	float4 edgesLRTB;
	edgesLRTB.x = float((packedVal >> 6) & 0x03) / 3.0; // there's really no need for mask (as it's an 8 bit input) but I'll leave it in so it doesn't cause any trouble in the future
	edgesLRTB.y = float((packedVal >> 4) & 0x03) / 3.0;
	edgesLRTB.z = float((packedVal >> 2) & 0x03) / 3.0;
	edgesLRTB.w = float((packedVal >> 0) & 0x03) / 3.0;

	return saturate(edgesLRTB);
}

void XeGTAO_AddSample(float ssaoValue, float edgeValue, inout float sum, inout float sumWeight)
{
	float weight = edgeValue;

	sum += weight * ssaoValue;
	sumWeight += weight;
}

void XeGTAO_DenoiseCS(uint2 pixCoordBase, Texture2D sourceAOTermAndEdges, SamplerState texSampler, RWTexture2D<unorm float2> outputTexture, const GTAOConstants consts)
{
#if XE_GTAO_FINAL_APPLY
    const float blurAmount = DENOISE_BLUR_BETA;
#else
    const float blurAmount = DENOISE_BLUR_BETA / 5.0;
#endif

    const float diagWeight = 0.85 * 0.5;

    float aoTerm[2]; // pixel pixCoordBase and pixel pixCoordBase + int2( 1, 0 )
    float4 edgesC_LRTB[2];
    float weightTL[2];
    float weightTR[2];
    float weightBL[2];
    float weightBR[2];

//     // Gather edge and visibility quads from working AO texture (uses RenderPixelSize)
//     const float2 gatherCenter = float2(pixCoordBase.x, pixCoordBase.y) * consts.RenderPixelSize;
// 
//     float4 edgesQ0 = sourceAOTermAndEdges.GatherGreen(texSampler, gatherCenter, int2(0, 0));
//     float4 edgesQ1 = sourceAOTermAndEdges.GatherGreen(texSampler, gatherCenter, int2(2, 0));
//     float4 edgesQ2 = sourceAOTermAndEdges.GatherGreen(texSampler, gatherCenter, int2(1, 2));
// 
//     float visQ0[4];
//     XeGTAO_DecodeGatherPartial(sourceAOTermAndEdges.GatherRed(texSampler, gatherCenter, int2(0, 0)), visQ0);
//     float visQ1[4];
//     XeGTAO_DecodeGatherPartial(sourceAOTermAndEdges.GatherRed(texSampler, gatherCenter, int2(2, 0)), visQ1);
//     float visQ2[4];
//     XeGTAO_DecodeGatherPartial(sourceAOTermAndEdges.GatherRed(texSampler, gatherCenter, int2(0, 2)), visQ2);
//     float visQ3[4];
//     XeGTAO_DecodeGatherPartial(sourceAOTermAndEdges.GatherRed(texSampler, gatherCenter, int2(2, 2)), visQ3);

    // Gather edge and visibility quads from working AO texture
    const int2 pixCoordScaled = pixCoordBase;
    float4 edgesQ0 = sourceAOTermAndEdges.Load(int3(pixCoordScaled + int2(0, 0), 0)).y;
    float4 edgesQ1 = sourceAOTermAndEdges.Load(int3(pixCoordScaled + int2(2, 0), 0)).y;
    float4 edgesQ2 = sourceAOTermAndEdges.Load(int3(pixCoordScaled + int2(1, 2), 0)).y;

    float visQ0[4];
    float visQ1[4];
    float visQ2[4];
    float visQ3[4];
    XeGTAO_DecodeGatherPartial(sourceAOTermAndEdges.Load(int3(pixCoordScaled + int2(0, 0), 0)).x, visQ0);
    XeGTAO_DecodeGatherPartial(sourceAOTermAndEdges.Load(int3(pixCoordScaled + int2(2, 0), 0)).x, visQ1);
    XeGTAO_DecodeGatherPartial(sourceAOTermAndEdges.Load(int3(pixCoordScaled + int2(0, 2), 0)).x, visQ2);
    XeGTAO_DecodeGatherPartial(sourceAOTermAndEdges.Load(int3(pixCoordScaled + int2(2, 2), 0)).x, visQ3);

    // [unroll]
    for (int side = 0; side < 2; side++)
    {
        const int2 pixCoord = int2(pixCoordBase.x + side, pixCoordBase.y);

        float4 edgesL_LRTB = XeGTAO_UnpackEdges(side == 0 ? edgesQ0.x : edgesQ0.y);
        float4 edgesT_LRTB = XeGTAO_UnpackEdges(side == 0 ? edgesQ0.z : edgesQ1.w);
        float4 edgesR_LRTB = XeGTAO_UnpackEdges(side == 0 ? edgesQ1.x : edgesQ1.y);
        float4 edgesB_LRTB = XeGTAO_UnpackEdges(side == 0 ? edgesQ2.w : edgesQ2.z);

        edgesC_LRTB[side] = XeGTAO_UnpackEdges(side == 0 ? edgesQ0.y : edgesQ1.x);

        // Edges aren't perfectly symmetrical: edge detection algorithm does not guarantee that a left edge on the right pixel will match the right edge on the left pixel (although
        // they will match in majority of cases). This line further enforces the symmetricity, creating a slightly sharper blur. Works real nice with TAA.
        edgesC_LRTB[side] *= float4(edgesL_LRTB.y, edgesR_LRTB.x, edgesT_LRTB.w, edgesB_LRTB.z);

#if 1   // this allows some small amount of AO leaking from neighbours if there are 3 or 4 edges; this reduces both spatial and temporal aliasing
		const float leak_threshold = 2.5;
		const float leak_strength = 0.5;
		float edginess = (saturate(4.0 - leak_threshold - dot(edgesC_LRTB[side], 1.0)) * rcp(4.0 - leak_threshold)) * leak_strength;
		edgesC_LRTB[side] = saturate(edgesC_LRTB[side] + edginess);
#endif

		// for diagonals; used by first and second pass
		weightTL[side] = diagWeight * (edgesC_LRTB[side].x * edgesL_LRTB.z + edgesC_LRTB[side].z * edgesT_LRTB.x);
		weightTR[side] = diagWeight * (edgesC_LRTB[side].z * edgesT_LRTB.y + edgesC_LRTB[side].y * edgesR_LRTB.z);
		weightBL[side] = diagWeight * (edgesC_LRTB[side].w * edgesB_LRTB.x + edgesC_LRTB[side].x * edgesL_LRTB.w);
		weightBR[side] = diagWeight * (edgesC_LRTB[side].y * edgesR_LRTB.w + edgesC_LRTB[side].w * edgesB_LRTB.y);

		// first pass
		float ssaoValue = side == 0 ? visQ0[1] : visQ1[0];
		float ssaoValueL = side == 0 ? visQ0[0] : visQ0[1];
		float ssaoValueT = side == 0 ? visQ0[2] : visQ1[3];
		float ssaoValueR = side == 0 ? visQ1[0] : visQ1[1];
		float ssaoValueB = side == 0 ? visQ2[2] : visQ3[3];
		float ssaoValueTL = side == 0 ? visQ0[3] : visQ0[2];
		float ssaoValueBR = side == 0 ? visQ3[3] : visQ3[2];
		float ssaoValueTR = side == 0 ? visQ1[3] : visQ1[2];
		float ssaoValueBL = side == 0 ? visQ2[3] : visQ2[2];

		float sumWeight = blurAmount;
		float sum = ssaoValue * sumWeight;

		XeGTAO_AddSample(ssaoValueL, edgesC_LRTB[side].x, sum, sumWeight);
		XeGTAO_AddSample(ssaoValueR, edgesC_LRTB[side].y, sum, sumWeight);
		XeGTAO_AddSample(ssaoValueT, edgesC_LRTB[side].z, sum, sumWeight);
		XeGTAO_AddSample(ssaoValueB, edgesC_LRTB[side].w, sum, sumWeight);

		XeGTAO_AddSample(ssaoValueTL, weightTL[side], sum, sumWeight);
		XeGTAO_AddSample(ssaoValueTR, weightTR[side], sum, sumWeight);
		XeGTAO_AddSample(ssaoValueBL, weightBL[side], sum, sumWeight);
		XeGTAO_AddSample(ssaoValueBR, weightBR[side], sum, sumWeight);

		aoTerm[side] = sum * rcp(sumWeight);

#if XE_GTAO_FINAL_APPLY
        outputTexture[pixCoord] = float2(saturate(aoTerm[side] * XE_GTAO_OCCLUSION_TERM_SCALE), 0);
#else
        outputTexture[pixCoord] = float2(aoTerm[side], side == 0 ? edgesQ0.y : edgesQ1.x);
#endif
	}
}

//////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////////
////////////////////////////
// Implementation / Entry //
////////////////////////////

// From https://www.shadertoy.com/view/3tB3z3 - except we're using R2 here
#define XE_HILBERT_LEVEL 6U
#define XE_HILBERT_WIDTH (1U << XE_HILBERT_LEVEL)
#define XE_HILBERT_AREA (XE_HILBERT_WIDTH * XE_HILBERT_WIDTH)
uint HilbertIndex(uint posX, uint posY)
{
    uint index = 0U;
    [unroll]
    for (uint curLevel = XE_HILBERT_WIDTH / 2U; curLevel > 0U; curLevel /= 2U) {
        uint regionX = (posX & curLevel) > 0U;
        uint regionY = (posY & curLevel) > 0U;
        index += curLevel * curLevel * ((3U * regionX) ^ regionY);
        if (regionY == 0U) {
            if (regionX == 1U) {
                posX = XE_HILBERT_WIDTH - 1U - posX;
                posY = XE_HILBERT_WIDTH - 1U - posY;
            }
            uint temp = posX;
            posX = posY;
            posY = temp;
        }
    }
    return index;
}

// without TAA, temporalIndex is always 0
float2 SpatioTemporalNoise(uint2 pixCoord, uint temporalIndex)
{
    float2 noise;

    // Hilbert curve driving R2 (see https://www.shadertoy.com/view/3tB3z3)
    #ifdef XE_GTAO_HILBERT_LUT_AVAILABLE // load from lookup texture...
    uint index = g_srcHilbertLUT.Load(uint3(pixCoord % 64, 0)).x;
    #else // ...or generate in-place?
    uint index = HilbertIndex(pixCoord.x, pixCoord.y);
    #endif
    
    index += 288 * (temporalIndex % 64); // why 288? tried out a few and that's the best so far (with XE_HILBERT_LEVEL 6U) - but there's probably better :)
    
    // R2 sequence - see http://extremelearning.com.au/unreasonable-effectiveness-of-quasirandom-sequences/
    return float2(frac(0.5 + index * float2(0.75487766624669276005, 0.5698402909980532659114)));
}

[numthreads(8, 8, 1)] // <- hard coded to 8x8; each thread computes 2x2 blocks so processing 16x16 block: Dispatch needs to be called with (width + 16-1) / 16, (height + 16-1) / 16
void prefilter_depths16x16_cs(uint2 dtid : SV_DispatchThreadID, uint2 gtid : SV_GroupThreadID)
{
    // t0 = depth
    // s0 = point
    XeGTAO_PrefilterDepths16x16CS(dtid, gtid, t0, out_working_depth_mip0, out_working_depth_mip1, out_working_depth_mip2, out_working_depth_mip3, out_working_depth_mip4);
}

// See ao0 for main pass 
[numthreads(XE_GTAO_NUMTHREADS_X, XE_GTAO_NUMTHREADS_Y, 1)]
void main_pass_cs(uint2 dtid : SV_DispatchThreadID)
{

}

// See ao1 for denoise pass
[numthreads(XE_GTAO_NUMTHREADS_X, XE_GTAO_NUMTHREADS_Y, 1)]
void denoise_pass_cs(uint2 dtid : SV_DispatchThreadID)
{
    GTAOConstants c = (GTAOConstants)0;

    // Size
    float2 swapchainTexSize = LumaSettings.SwapchainSize;
    c.RenderPixelSize = rcp(swapchainTexSize);

    const uint2 pix_coord_base = dtid * uint2(2, 1); // we're computing 2 horizontal pixels at a time (performance optimization)
    XeGTAO_DenoiseCS(pix_coord_base, t0, s1, final_output, c);
}

#endif // __XE_GTAO_HLSLI__