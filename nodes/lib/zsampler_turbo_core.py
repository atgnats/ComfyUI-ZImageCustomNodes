"""
File    : lib/zsampler_turbo_core.py
Purpose : The new version of the "Z-Sampler Turbo" code.
Author  : Martin Rizzo | <martinrizzo@gmail.com>
Date    : Mar 16, 2026
Repo    : https://github.com/martin-rizzo/ComfyUI-ZImagePowerNodes
License : MIT
- - - - - - - - - - - - - - - - - - - - - - - - - - - - - - - - - - - - - - -
                          ComfyUI-ZImagePowerNodes
         ComfyUI nodes designed specifically for the "Z-Image" model.
_ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _ _
"""
import torch
import numpy as np
import comfy.utils
import comfy.sample
import comfy.samplers
import comfy.sampler_helpers
from typing         import Any
from .progress_bar  import ProgressPreview



def zsampler_turbo(latent_input             : dict[str, Any],
                   model                    : Any,
                   positive                 : list,
                   *,
                   seed                     : int,
                   steps                    : int,
                   noise_estimation_method  : str,
                   noise_estimation_size    : str | int | None,
                   noise_bias_scale         : float,
                   noise_amplitude_scale    : float,
                   noise_overdose           : float,
                   sigma_offsets            : list[float] | None = None,
                   sigma_limits             : list[float] | tuple[float,float] | None = None,
                   progress_preview         : ProgressPreview
                   ) -> dict[str, Any]:
    """
    Perform the three-stage denoising process on a latent input.

    Args:
        latent_input            : A dict with the initial latent input to be denoised.
        model                   : The comfyui model to be used for denoising.
        positive                : Positive conditioning for the denoising process.
        seed                    : The seed used for random number generation.
        steps                   : The total number of denoising steps. This value will
                                  be used internally to determine the sigmas values.
        noise_estimation_method : The name of method used for estimating initial noise ("accurate", "experimental" or "none").
        noise_estimation_size   : Size of the sample for noise bias/amplitude estimation.
        noise_bias_scale        : The level of adjustament from the calculated noise bias to
                                  apply before the first denoising step.
                                  0.0 = no noise bias adjustment;
                                  1.0 = using the 100% calculated bias
        noise_amplitude_scale   : The level of adjustament from the calculated noise amplitude to
                                  apply before the first denoising step.
                                  0.0 = no noise amplitude adjustment;
                                  1.0 = using the 100% calculated amplitude.
        noise_overdose          : The level of overamplitude in the initial noise generation.
                                  0.0 = standard noise level;
                                  positive values will increase the amplitude, e.g: 0.1 = 10% increment;
                                  negative values will reduce the amplitude, e.g: -0.1 = 10% decrement.
        sigma_offsets           : Optional list of offsets to be applied to the calculated sigma values.
        sigma_limits            : Optional tuple with minimum and maximum limits for sigma values.
        progress_preview        : A `ProgressPreview` object for displaying progress during the denoising process.

    Returns:
        A dict with the denoised latent output.
    """
    if sigma_limits is not None and len(sigma_limits)<2:
        raise ValueError("sigma_limits must be a tuple or list with at least two elements")

    # check if the process should start from pure noise, this is usually
    # the case during image generation, but other processes like inpainting
    # usually require starting from an input image
    start_from_pure_noise = not sigma_limits  or  max(sigma_limits[0],sigma_limits[1]) >= 1.0

    # for some reason that I don't fully understand
    # the "accurate" estimation method has a more sensitive scale
    if noise_estimation_method == "accurate":
        noise_bias_scale /= 2

    # only "euler" sampler has been tested with this technique
    sampler = comfy.samplers.sampler_object("euler")

    # `forced_size` is noise_bias_size converted to integer (pixels)
    # or None if "source" option was selected
    forced_size = None
    if isinstance(noise_estimation_size, str) and noise_estimation_size.endswith("px"):
        forced_size = int(noise_estimation_size[:-2])
    elif isinstance(noise_estimation_size, (int,float)):
        forced_size = int(noise_estimation_size)


    # Sigmas are divided into 3 stages:
    #
    #   Stages 1 and 2 combined function similarly to a standard denoising process,
    #   but with two key conditions:
    #     - stage 1 always has 2 steps and fixed sigmas, regardless of the total number of steps used.
    #     - there's a jump-back in sigmas between stage 1 and stage 2, there's no continuity. I'm not
    #       sure why it works, but after hundreds of tests where the final image consistently had better
    #       quality, I had to accept that this was a rule and it needed to be this way.
    #
    #   Once stages 1 and 2 are complete (acting as a standard denoising process), stage 3 begins.
    #   This is essentially a refining stage, where we go back with the sigmas, add the corresponding
    #   noise, and then do denoising from there.
    #
    #   The transition from Stage 2 to Stage 3 can also be thought of as applying an "Euler-ancestral"
    #   sampling method instead of the standard "Euler", but only for that single step between stages.
    #
    if steps>=9:
        #sigmas1 = [0.990, 0.981, 0.911]                #< 2 steps
        sigmas1  = [0.988, 0.981, 0.911]                #< 2 steps
        #sigmas2 = [0.943, 0.850, 0.775, 0.640, 0.000]  #< 4 steps (=6 generation steps)
        sigmas2  = [0.936, 0.858, 0.725, 0.540, 0.000]  #< 4 steps (=6 generation steps)
        #sigmas3 = [0.608, 0.486, 0.270, 0.000]         #< 3 steps (+3 refiner steps)
        sigmas3  = [0.708, 0.586, 0.270, 0.000]         #< 3 steps (+3 refiner steps)

    elif steps==8:
        sigmas1  = [0.990, 0.981, 0.911]                #< 2 steps
        sigmas2  = [0.943, 0.850, 0.775, 0.640, 0.000]  #< 4 steps (=6 generation steps)
        sigmas3  = [0.608, 0.202, 0.000]                #< 2 steps (+2 refiner steps)

    elif steps==7:
        sigmas1  = [0.990, 0.981, 0.911]                #< 2 steps
        sigmas2  = [0.943, 0.842, 0.660, 0.000]         #< 3 steps (=5 generation steps)
        sigmas3  = [0.608, 0.202, 0.000]                #< 2 steps (+2 refiner steps)

    elif steps==6:
        sigmas1  = [0.990, 0.981, 0.911]                #< 2 steps
        sigmas2  = [0.943, 0.842, 0.660, 0.000]         #< 3 steps (=5 generation steps)
        sigmas3  = [0.630, 0.000]                       #< 1 step  (+1 refiner step)

    elif steps==5:
        sigmas1  = [0.990, 0.981, 0.911]                #< 2 steps
        sigmas2  = [0.941, 0.770, 0.000]                #< 2 steps (=4 generation steps)
        sigmas3  = [0.520, 0.000]                       #< 1 step  (+1 refiner step)

    elif steps==4:
        sigmas1  = [0.990, 0.981, 0.911]                #< 2 steps
        sigmas2  = [0.939, 0.000]                       #< 1 step  (=3 generation steps)
        sigmas3  = [0.780, 0.000]                       #< 1 step  (+1 refiner step)

    elif steps<=3:
        sigmas1  = [0.989, 0.981, 0.911]                #< 2 steps
        sigmas2  = [0.929, 0.000]                       #< 1 step  (=3 generation steps)
        sigmas3  = None                                 #< (no refiner)

    # sigma0 is used only for estimating the initial noise bias (optional first step)
    # (denoising for that estimation step goes from sigma0 to sigmas1[0])
    sigma0 = 1.000

    # add the values of sigmas_offset to each sigma in the 3 lists
    if sigma_offsets:
        offset_iter = iter(sigma_offsets)
        sigma0 = min(1.000, sigma0 + next(offset_iter, 0.0))
        if isinstance(sigmas1, list):
            for i in range( len(sigmas1) ):
                sigmas1[i] += next(offset_iter, 0.0)
        if isinstance(sigmas2, list):
            for i in range(len(sigmas2) - 1):
                sigmas2[i] += next(offset_iter, 0.0)
        if isinstance(sigmas3, list):
            for i in range(len(sigmas3) - 1):
                sigmas3[i] += next(offset_iter, 0.0)


    # if the first step was truncated (or discarded) by a forced limit
    # of the sigmas, then the first two stages are combined into one.
    # (this proved to be effective when `denoising < 1` during inpainting,
    #  it would be nice to do some tests to see if it doesn't bring problems
    #  in other situations)
    if not start_from_pure_noise:
        sigmas1 = sigmas1[:-1] if sigmas1 else []
        sigmas1.extend( sigmas2 )
        sigmas2 = None


    # these parameters determine the bias and amplitude of the initial noise added
    # to the latent space. vaguely speaking, they can be thought of as modifiers
    # influencing brightness and contrast/saturation of the final image.
    # given that the first sigma value is always set to "0.991", these values
    # play a role in supplementing the very low-frequency component that might
    # be lacking in the early stages of image generation.
    initial_noise_bias      = 0
    initial_noise_amplitude = 1

    # `initial_noise_bias/initial_noise_amplitude` are calculated ONLY if the user
    # set a non-zero scale (because this calculation adds an extra step to the process)
    if noise_bias_scale != 0 and noise_amplitude_scale != 0 and noise_estimation_method != "none" and start_from_pure_noise:
        bias, amplitude = estimate_initial_noise_features(
                                      latent_input, model, seed, positive, positive,
                                      sampler     = sampler,
                                      sigmas      = [sigma0, sigmas1[0]],
                                      method      = noise_estimation_method,
                                      forced_size = forced_size,
                                      progress_preview = ProgressPreview( 100, parent=(progress_preview,0,100//steps) ),
                                      )
        initial_noise_bias      = (bias      * noise_bias_scale     )
        initial_noise_amplitude = (amplitude * noise_amplitude_scale) + (1-noise_amplitude_scale)

    # applies the noise overdose if it was required
    if noise_overdose:
        initial_noise_amplitude *= 1+noise_overdose if noise_overdose>=0 else 1/(1-noise_overdose)

    # execute the 3-stage denoising process
    latent_output = execute_3_stage_denoising(latent_input,
                                              model, seed, 1.0, positive, positive,
                                              sampler                 = sampler,
                                              sigmas1                 = sigmas1,
                                              sigmas2                 = sigmas2,
                                              sigmas3                 = sigmas3,
                                              sigma_limits            = sigma_limits,
                                              initial_noise_bias      = initial_noise_bias,
                                              initial_noise_amplitude = initial_noise_amplitude,
                                              progress_preview = ProgressPreview( 100, parent=(progress_preview,100//steps,100) ),
                                              )
    return latent_output


    #----------------------------------------------------------------------------
    # Alternative 8/7-step sigma sequences discarded in the early stages of development
    # if steps==8:
    #     sigma0  = 1.000
    #     sigmas1 = [0.991, 0.980, 0.920]
    #     sigmas2 = [0.935, 0.8916, 0.7895, 0.000],
    #     sigmas3 = [0.6582, 0.3019, 0.0000]
    # if steps==7:
    #     sigma0  = 1.000
    #     sigmas1 = [0.991, 0.980, 0.920]
    #     sigmas2 = [0.935, 0.770, 0.000]
    #     sigmas3 = [0.6582, 0.3019, 0.0000]
    #----------------------------------------------------------------------------


def execute_3_stage_denoising(latent_image,
                                model    : Any,
                                seed     : int,
                                cfg      : float,
                                positive : list,
                                negative : list,
                                *,
                                sampler      : comfy.samplers.KSAMPLER,
                                sigmas1      : torch.Tensor | list | None,
                                sigmas2      : torch.Tensor | list | None,
                                sigmas3      : torch.Tensor | list | None,
                                sigma_limits : list[float] | tuple[float,float] | None,
                                initial_noise_bias     : torch.Tensor | float | int | None = None,
                                initial_noise_amplitude: torch.Tensor | float | int | None = 1.0,
                                progress_preview       : ProgressPreview,
                                ):
    """
    Executes a three-stage denoising process on the provided latent image.

    Args:
        latent_image: Dictionary containing data about the initial latent image to be processed.
                        Includes keys like "samples" and optional "noise_mask", "batch_index".
        model       : ComfyUI object representing the model to use for denoising.
        seed        : The seed used to generate random noise.
        cfg (float) : Classifier-free guidance scale that controls the influence of negative prompts.
                        A value of 1.0 means the negative prompt has no effect on generation.
        positive    : Positive prompts or conditioning applied to the model during denoising.
        negative    : Negative prompts or conditioning applied to the model during denoising.
        sampler     : ComfyUI object representing the sampler used for each denoising step.
        sigmas1     : Sigma values for the first stage of denoising. Can be a tensor, list, or None.
        sigmas2     : Sigma values for the second stage of denoising. Can be a tensor, list, or None.
        sigmas3     : Sigma values for the third stage of denoising. Can be a tensor, list, or None.
        initial_noise_bias: An optional constant bias applied to the initial noise.
                            Can be a tensor, scalar, or None.
                            If tensor, it must have shape [batch_size, channels, 1, 1].
                            (0.0 or None = no bias)
        initial_noise_amplitude: An optional amplitude factor applied to the initial noise.
                                    Can be a tensor, scalar, or None.
                                    If tensor, it must have shape [batch_size, channels, 1, 1].
                                    (0.0 = nothing ; 1.0 = standard deviation)

    Returns:
        A dictionary with the updated latent image data after all three denoising stages.
    """

    # if sigmas is a list then convert it to pytorch tensor
    if isinstance(sigmas1, list):
        sigmas1 = torch.tensor(sigmas1, device='cpu')
    if isinstance(sigmas2, list):
        sigmas2 = torch.tensor(sigmas2, device='cpu')
    if isinstance(sigmas3, list):
        sigmas3 = torch.tensor(sigmas3, device='cpu')

    if isinstance(sigma_limits, (list,tuple)):
        sigmas1 = truncate_sigmas(sigmas1, sigma_limits)
        sigmas2 = truncate_sigmas(sigmas2, sigma_limits)
        sigmas3 = truncate_sigmas(sigmas3, sigma_limits)

    # calculate the progress level for each step
    prog0 = 0
    prog1 = prog0 + (sigmas1.shape[-1] - 1 if sigmas1 is not None else 0)
    prog2 = prog1 + (sigmas2.shape[-1] - 1 if sigmas2 is not None else 0)
    total = prog2 + (sigmas3.shape[-1] - 1 if sigmas3 is not None else 0)



    #-- THREE-STAGE PROCESS ---------------------------

    if sigmas1 is not None:
        add_noise = True
        latent_image = execute_sampler(latent_image,
                            model, seed, cfg, positive, negative,
                            sampler          = sampler,
                            sigmas           = sigmas1,
                            noise_bias       = initial_noise_bias,
                            noise_amplitude  = initial_noise_amplitude if add_noise else 0.0,
                            keep_masked_area = True,
                            progress_preview = ProgressPreview( prog1-prog0,
                                    parent=(progress_preview, 100*prog0//total, 100*prog1//total)),
                            )



    if sigmas2 is not None:
        add_noise = False
        # normally this stage should NOT add noise (stage1 and stage2 must behave
        # as a single donoise process) but if no first stage was executed then
        # this stage is the first and therefore it must add noise
        if sigmas1 is None: add_noise = True
        latent_image = execute_sampler(latent_image,
                        model, seed, cfg, positive, negative,
                        sampler          = sampler,
                        sigmas           = sigmas2,
                        noise_bias       = 0,
                        noise_amplitude  = 1.0 if add_noise else 0.0,
                        keep_masked_area = True,
                        progress_preview = ProgressPreview( prog2-prog1,
                                   parent=(progress_preview, 100*prog1//total, 100*prog2//total)),
                        )


    if sigmas3 is not None:
        add_noise = True
        latent_image = execute_sampler(latent_image,
                        model, 696969, cfg, positive, negative,
                        sampler          = sampler,
                        sigmas           = sigmas3,
                        noise_bias       = 0,
                        noise_amplitude  = 1.0 if add_noise else 0.0,
                        keep_masked_area = True,
                        progress_preview = ProgressPreview( total-prog2,
                                parent=(progress_preview, 100*prog2//total, 100*total//total)),
                        )
    return latent_image



def execute_sampler(latent_image    : dict[str, Any],
                    model           : Any,
                    noise_seed      : int,
                    cfg             : float,
                    positive        : list,
                    negative        : list,
                    *,
                    sampler         : comfy.samplers.KSAMPLER,
                    sigmas          : list | torch.Tensor,
                    noise_bias      : torch.Tensor | float | int | None,
                    noise_amplitude : torch.Tensor | float | int | None,
                    keep_masked_area: bool = False,
                    fix_empty_latent: bool = True,
                    progress_preview: ProgressPreview | None = None,
                    ) -> dict[str, Any]:
    """
    Emulates comfyui's 'SamplerCustom' node with some extra functionality.
    Args:
        latent_image: Dictionary containing data about the initial latent image to denoise.
                        (contains keys like "samples" and optional "noise_mask", "batch_index").
        model       : ComfyUI object representing the model to use for denoising.
        noise_seed  : The seed used to generate random noise.
        cfg         : Classifier-free guidance scale that controls the strength of negative prompts.
                        A value of 1.0 means the negative prompt has no effect on generation.
        positive    : Positive prompts or conditioning applied to the model during denoising.
        negative    : Negative prompts or conditioning applied to the model during denoising.
        sampler     : ComfyUI object representing the sampler used for each denoising step.
        sigmas      : Sigma values for each diffusion process step (can be list or torch.Tensor).
        noise_bias  : A constant bias applied to the initial noise.
                        If it is a tensor, it must have shape [batch_size, channels, 1, 1].
                        Can also be a scalar value or None.
        keep_masked_area: If True, the masked area of the latent image will be kept unchanged.
                            Comfyui tries to keep masked area unchanged when there's a mask active
                            but activating this flag we're sure that no change will happen at all.
        noise_amplitude : The amplitude of noise added to the latent image before denoising.
                            (0.0 = no noise ; 1.0 = standard deviation)
        progress_preview: Optional callback for tracking progress. Defaults to None.

    Returns:
        A dictionary with the updated latent image data after denoising,
        including "samples" and any other relevant information.

    Notes:
        - If `sigmas` is provided as a list, it will be converted to a torch.Tensor.
        - The function automatically handles cases where `noise_bias` or `noise_amplitude` are zero scalars.
        - The initial noise is scaled using `noise_amplitude`, and then the bias from `noise_bias` is applied.
    """

    # if sigmas is a list then convert it to tensor
    if isinstance(sigmas, list):
        sigmas = torch.tensor(sigmas, device='cpu')

    # if `noise_bias` is a torch.Tensor
    # then it should have shape [batch_size, channels, 1, 1]
    if isinstance(noise_bias, torch.Tensor):
        if noise_bias.ndim != 4 or noise_bias.shape[2:] != (1, 1):
            raise ValueError(f"Invalid `noise_bias` shape: expected [batch_size, channels, 1, 1], "
                                f"but got {list(noise_bias.shape)}")

    # if `noise_amplitude` is a torch.Tensor
    # then it should have shape [batch_size, channels, 1, 1]
    if isinstance(noise_amplitude, torch.Tensor):
        if noise_amplitude.ndim != 4 or noise_amplitude.shape[2:] != (1, 1):
            raise ValueError(f"Invalid `noise_amplitude` shape: expected [batch_size, channels, 1, 1], "
                                f"but got {list(noise_amplitude.shape)}")

    # if `noise_bias` or `noise_amplitude` is zero scalar then ignore it
    if isinstance(noise_bias, (float,int)) and noise_bias == 0:
        noise_bias = None
    if isinstance(noise_amplitude, (float,int)) and noise_amplitude == 0:
        noise_amplitude = None


    # extract all info that comes packaged in the `latent_image` dictionary
    latent     : dict                = latent_image.copy()
    samples    : torch.Tensor        = latent["samples"]
    noise_mask : torch.Tensor | None = latent.get("noise_mask")
    batch_index: int| None           = latent.get("batch_index")
    steps      : int                 = int( sigmas.shape[-1] )
    if fix_empty_latent:
        samples = comfy.sample.fix_empty_latent_channels(model, samples)

    # store original values in case the user is doing inpainting with a mask
    original_samples : torch.Tensor | None = samples
    original_mask    : torch.Tensor | None = noise_mask

    # scale initial noise using `noise_amplitude`.
    # (0.0 results in no noise; 1.0 represents standard unit variance)
    if noise_amplitude is None:
        noise = torch.zeros(samples.shape,
                            dtype   = samples.dtype,
                            layout  = samples.layout,
                            device  = "cpu")
    else:
        print("##>>------------------")
        print("##>> GENERATING NOISE!!")
        print("##>>------------------")
        noise = generate_noise(noise_seed,
                               samples.shape,
                               dtype   = samples.dtype,
                               layout  = samples.layout,
                               device  = "cpu",
                               noise_bias      = noise_bias,
                               noise_amplitude = noise_amplitude,
                               batch_subseeds  = batch_index,
                               )
        #noise = comfy.sample.prepare_noise(samples, noise_seed, batch_index) * noise_amplitude

    ## apply a constant bias using `noise_bias`
    #if noise_bias is not None:
    #    noise = noise + noise_bias

    # this wrapper increments by 1 the steps count reported by comfyui.
    # comfyui reports the end of the first denoising step as 0 (0% completion)
    # breaking internal ProgressPreview calculation, the wrapper solves that
    progress_wrapper = ProgressPreview( steps, parent=(progress_preview, 1, steps+1) )

    # generates the denoised latent using a native function from comfyui.
    disable_pbar = not comfy.utils.PROGRESS_BAR_ENABLED
    samples = comfy.sample.sample_custom(model, noise, cfg, sampler, sigmas, positive, negative,
                                            samples, noise_mask=noise_mask, callback=progress_wrapper,
                                            disable_pbar=disable_pbar, seed=noise_seed)

    # when there's an inpainting mask, it seems like comfyui does not merge the
    # original image at the end of `sample_custom(..)`, so we manually merge it here
    if keep_masked_area and (original_mask is not None) and (original_samples is not None):
        original_mask = comfy.sampler_helpers.prepare_mask( original_mask, original_samples.shape, original_samples.device)
        if original_mask is not None:
            samples = samples * original_mask + ( 1.0 - original_mask ) * original_samples

    out = latent_image.copy()
    out["samples"] = samples
    return out


def generate_noise(seed           : int,
                   shape          : tuple[int, ...],
                   dtype          : torch.dtype,
                   layout         : torch.layout,
                   noise_bias     : torch.Tensor | float | int | None = None,
                   noise_amplitude: torch.Tensor | float | int | None = None,
                   batch_subseeds : list[int] | None                  = None,
                   device         : str | torch.device                = "cpu"
                   ):
    generator = torch.manual_seed(seed)
    return generate_noise_(generator, shape, dtype, layout, noise_bias, noise_amplitude, batch_subseeds, device)


def generate_noise_(generator      : torch.Generator,
                    shape          : tuple[int, ...],
                    dtype          : torch.dtype,
                    layout         : torch.layout,
                    noise_bias     : torch.Tensor | float | int | None = None,
                    noise_amplitude: torch.Tensor | float | int | None = None,
                    batch_subseeds : list[int] | None                  = None,
                    device         : str | torch.device                = "cpu"
                    ):
    """
    Generate batched noise with optional per-sample 'virtual' sub-seeds.

    Args:
        generator      : A `torch.Generator` object for generating random numbers.
        shape          : Noise shape. The first dimension is the batch size.
        dtype          : The floating-point dtype of the generated tensor.
        layout         : torch.strided or torch.sparse_coo, etc.
        noise_bias     : Constant offset added to every element in the noise.
        noise_amplitude: Scale factor applied to the raw normal noise.
        batch_subseeds : List of small integers (0, 1, 2, …) that act as virtual seeds for every
                         sample in the batch. Repetitions are allowed; repeated indices yield
                         identical noise for those samples. If `None` or empty, every sample
                         receives independent noise.
        device         : Target device for the generated tensor.

    Returns:
        A noise tensor of the requested shape, already biased and scaled.
    """

    print("##>> noise_bias:", noise_bias.shape if isinstance(noise_bias,torch.Tensor) else noise_bias if isinstance(noise_bias,(float,int)) else "None")
    print("##>> noise_amplitude:", noise_amplitude.shape if isinstance(noise_amplitude,torch.Tensor) else noise_amplitude if isinstance(noise_amplitude,(float,int)) else "None")

    if not batch_subseeds:
        noise = torch.randn(shape, dtype=dtype, layout=layout, generator=generator, device=device)
        if noise_amplitude is not None: noise *= noise_amplitude
        if noise_bias      is not None: noise += noise_bias
        return noise

    # en este punto batch_subseeds fue suministrado el cual es una lista que indica
    # que valor de seed virtual se usara para generar el ruido de cada elemento del
    # batch; deben ser siempre valores pequeños como [0,1,2,3] o [0,1,0,1] o
    # incluso [0,0,0,0] si se desea que todos los elementos del batch tengan el mismo ruido
    unique_subseeds, inverse = np.unique(batch_subseeds, return_inverse=True)
    max_subseed              = unique_subseeds.max()
    subnoise_shape           = [1] + list(shape)[1:]

    subnoises : list[torch.Tensor] = []
    for subseed in range(max_subseed+1):
        subnoise = torch.randn(subnoise_shape, dtype=dtype, layout=layout, generator=generator, device=device)
        if subseed in unique_subseeds:
            subnoises.append(subnoise)

    noise = torch.cat( [subnoises[i] for i in inverse] )
    if noise_amplitude is not None: noise *= noise_amplitude
    if noise_bias      is not None: noise += noise_bias
    return noise



def estimate_initial_noise_features(latent_image,
                           model    : Any,
                           seed     : int,
                           positive : list,
                           negative : list,
                           *,
                           sampler  : comfy.samplers.KSAMPLER,
                           sigmas   : list | torch.Tensor,
                           method   : str = 'accurate',  #< "accurate" or "experimental"
                           forced_size     : int | None = None,  #< optional, forced size of the sample
                           progress_preview: ProgressPreview
                           ) -> tuple[torch.Tensor, torch.Tensor]:
    """
    Calculates the denoised bias for a given sigma value.

    The bias and amplitude are determined by denoising a pure noise sample with
    the provided sigma values, then calculating the mean and standard deviation
    across each channel of the resulting latent image.

    Args:
        latent_image: Dictionary containing information about the initial latent image,
                        only its width and height are used.
        model       : ComfyUI object representing the model to use for denoising.
        seed        : The seed used to generate random noise.
        positive    : Positive prompts or conditioning applied to the model during denoising.
        negative    : Negative prompts or conditioning applied to the model during denoising.
        sampler     : ComfyUI object representing the sampler used for each denoising step.
        sigmas      : Sigma values for each diffusion process step (can be list or torch.Tensor).
        method      : Calculation method, can be 'accurate' or 'experimental'.
        progress_preview: An object for reporting progress.

    Returns:
        A tuple containing two tensors:
        - The calculated noise bias, tensor of shape [batch_size, channels, 1, 1].
        - The calculated noise amplitude, tensor of shape [batch_size, channels, 1, 1].
    """
    if method not in ['accurate', 'experimental']:
        raise ValueError(f'invalid bias calculation method: {method}')
    if isinstance(sigmas, list):
        sigmas = torch.tensor(sigmas, device='cpu')

    # calculate the number of diffusion steps (for the progress bar)
    steps = sigmas.shape[-1] - 1

    if isinstance(forced_size, (int, float)) and forced_size >= 8:
        samples : torch.Tensor = latent_image["samples"]
        samples_shape = samples.shape[:-2] + ( int(forced_size//8), int(forced_size//8) )
        latent_image  = latent_image.copy()
        latent_image["samples"] =  torch.zeros(samples_shape, dtype=samples.dtype, layout=samples.layout, device="cpu")


    # run the sampler on pure noise and calculate the mean of the result
    latent_image = execute_sampler(latent_image,
                                   model, seed, 1.0, positive, negative,
                                   sampler          = sampler,
                                   sigmas           = sigmas,
                                   noise_bias       = 0,
                                   noise_amplitude  = 1.0 if method=="accurate" else 0.1,
                                   progress_preview = ProgressPreview( steps,
                                        parent=(progress_preview, 0, 100)),
                                   )

    samples = latent_image["samples"]
    bias      = samples.mean(dim=[2, 3], keepdim=True)
    amplitude = samples.std (dim=[2, 3], keepdim=True)
    return bias, amplitude



def truncate_sigmas(sigmas : torch.Tensor | None,
                    limits : list[float] | tuple[float,float] | None,
                    ) -> torch.Tensor | None:
    """
    Truncates a *descending* tensor of sigmas inside a restricted range.

    The returned tensor keeps the original order and contains only the values
    that fall between `limits[0]` and `limits[1]`; if the original tensor
    is clipped at either end, the corresponding limit value is appended
    so that the final result always includes both boundaries.
    If no value satisfies this condition the function returns `None`.

    Args:
        sigmas:
            1-D tensor with sigma values sorted in **descending** order.
        limits:
            Sequence with at least two elements.
            The first and second elements are used as the `(min, max)` range
            that defines the interval for filtering.

    Returns:
        A new tensor with the sigmas that lie inside `[min, max]`.
        The tensor preserves the original descending order.
        If `sigmas` is `None` the function returns `None`.
        If `sigmas` is totally outside the limits, the function returns `None`.
    """
    if sigmas is None or sigmas.numel()==0:
        return None
    if limits is None:
        return sigmas
    if not isinstance(limits, (list, tuple)) or len(limits) < 2:
        raise ValueError("`limits` must be a list or tuple with at least 2 elements")
    if not (sigmas[0] >= sigmas[-1]):
        raise ValueError("`sigmas` must be sorted in descending order")

    # extract the lower and upper limits
    lower, upper = limits[0], limits[1]
    if lower > upper:
        lower, upper = upper, lower

    # if the range of sigmas is totally outside the limits
    # then none of the sigmas should be returned
    if sigmas[-1] > upper or lower > sigmas[0]:
        return None

    # create the mask to filter out values outside the range
    valid_mask = (upper > sigmas) & (sigmas > lower)
    if valid_mask.all():
        return sigmas

    # filter the tensor using the mask
    truncated_sigmas = sigmas[valid_mask]

    # add the lower/upper limits to the tensor if it was actually truncated
    if not valid_mask[0]:
        upper_sigma = torch.tensor([upper], dtype=sigmas.dtype, device=sigmas.device)
        truncated_sigmas = torch.cat((upper_sigma, truncated_sigmas))
    if not valid_mask[-1]:
        lower_sigma = torch.tensor([lower], dtype=sigmas.dtype, device=sigmas.device)
        truncated_sigmas = torch.cat((truncated_sigmas, lower_sigma))

    return truncated_sigmas
