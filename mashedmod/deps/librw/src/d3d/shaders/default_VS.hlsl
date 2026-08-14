#include "standardConstants.h"

struct VS_in
{
	float4 Position		: POSITION;
	float3 Normal		: NORMAL;
	float2 TexCoord		: TEXCOORD0;
	float4 Prelight		: COLOR0;
};

struct VS_out {
	float4 Position		: POSITION;
	float3 TexCoord0	: TEXCOORD0;	// also fog
	float4 Color		: COLOR0;
};


VS_out main(in VS_in input)
{
	VS_out output;

	output.Position = mul(combinedMat, input.Position);
	float3 Vertex = mul(worldMat, input.Position).xyz;
	float3 Normal = mul(normalMat, input.Normal);

	output.TexCoord0.xy = input.TexCoord;

	output.Color = input.Prelight;
	output.Color.rgb += ambientLight.rgb * surfAmbient;

	int i;
#ifdef DIRECTIONALS
	for(i = 0; i < numDirLights; i++)
		output.Color.xyz += DoDirLight(lights[i+firstDirLight], Normal)*surfDiffuse;
#endif
#ifdef POINTLIGHTS
	for(i = 0; i < numPointLights; i++)
		output.Color.xyz += DoPointLight(lights[i+firstPointLight], Vertex.xyz, Normal)*surfDiffuse;
#endif
#ifdef SPOTLIGHTS
	for(i = 0; i < numSpotLights; i++)
		output.Color.xyz += DoSpotLight(lights[i+firstSpotLight], Vertex.xyz, Normal)*surfDiffuse;
#endif
	// PS2 clamps before material color
	output.Color = clamp(output.Color, 0.0, 1.0);
	output.Color *= matCol;

	// MASHED LOCAL PATCH (P7) -- per-PIXEL fog. Upstream evaluates the whole fog
	// factor here, per VERTEX, and interpolates the CLAMPED result; D3D9 table fog
	// (D3DRS_FOGTABLEMODE = D3DFOG_LINEAR), which the hand-written D3D9 path uses,
	// evaluates it per pixel. Carry the raw eye depth instead and clamp in the PS.
	// TEXCOORD is perspective-correct, and perspective-correct interpolation of the
	// attribute w reconstructs the true per-pixel eye depth exactly, so this makes
	// the two models algebraically identical. See MASHED_PATCHES.md P7.
	output.TexCoord0.z = output.Position.w;

	return output;
}
