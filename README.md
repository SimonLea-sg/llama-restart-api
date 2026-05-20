### W.I.P
#### This project is not finished and is currently undergoing development and testing.  Use at your own risk.

## Easy Llama (Llama-cpp, Turbo Quant, Docker with easy restart api)

### Overview:

An easy docker based setup for Llama.cpp with TurboQuant and an api for restarting llama-server.

Using http calls you can set llama.cpp startup options and restart llama-server without restarting the container.

#### This implementation is __not__ for Production use.  It is not hardened or exploit tested. ## Do not use it for anything other than private testing.

#### Note: This setup is utilising CUDA for Nvidia GPUs.  Other GPUs AI frameworks are not included as I only have a NVidia card to work with. 

### Technology Used:
* Docker
* Ubuntu24.04
* Cuda:12.8.1
* Python3
* llama.cpp with turboquant (Forked from: [llama-cpp-turboquant](https://github.com/TheTom/llama-cpp-turboquant))

### Basic instructions:

#### Setup

* Clone this repository to a Linux server
* cd llama-restart-api
* Copy ./docker/dot-env-example ./docker/.env
* If using authentication (default) then generate an APIKey.
  * A quick and easy way to generate an APIKey in Linux "openssl rand -hex 32"
* Edit ./docker/.env and set any environment variables on startup.
* Set your API key(s) to enable API authentication.

***Note***: To build an intermediate image for use with multiple app based on TheTom's version of llama.cpp with tubo quant and mtp, visit my [llama-tq-docker-build](https://github.com/SimonLea-sg/llama-tq-docker-build/tree/main) repo.

### Grab a model and put it in a place you will map in to the container.

Download a .gguf model from [HuggingFace](https://huggingface.co/models)

Default in the config.py file is mistralai_Mistral-Small-3.2-24B-Instruct-2506-Q4_K_M.gguf for no particular reason.

### Build the image (from scratch, remove  --no-cache for updating the build):

[Dockerfile]
- llama-server-api.Dockerfile: Builds llama.cpp llama-server app and installs the api app.
- llama-all-api.Dockerfile: Builds the full llama.cpp toolset and installs the api app.
- api-only.Dockerfile: Uses an intermediate llama.cpp image and adds the api app (much shorter build time).  

  See the ***note*** above for instructions to build the intermediate image.

`docker build  --no-cache -t llama-restart-api -f ./docker/[Dockerfile] .`

### Creating and Running a Container:

#### Start a container based on the image

* [Ext port] = Port number to connect to the api on
* [Ext port llama] = Port number to connect to llama-server on
* [Ext volume] = Docker volume name or physical volume path

`docker run -d --name easy-llama --gpus all -p [Ext port]:8000 -p [Ext port llama]:8080 -v [Ext volume]:/models easy-llama`

### Check the Docker logs:

#### Looks for "Starting server with" for details of the llama-server startup parameters.

`docker logs easy-llama`

#### Stopping the container

`docker stop easy-llama`

#### Deleting the container (ready for a new start with different parameters - see Run the image).

`docker container rm easy-llama`

### Calling the available endpoints:

### GET /health:

#### To verify the API service is running, you can call this endpoint without authentication (if keys are not configured):

`curl http://localhost:8000/health`

### GET /restart-status:

#### To monitor the restart progress of the subprocess, you must include the optional X-API-Key header if valid keys are defined in the .env file:

`curl http://localhost:8000/restart-status -H "X-API-Key: your_api_key"`

### POST /restartllama:

#### To restart the llama-server process with new parameters, you must provide a JSON payload. The X-API-Key header is required if the server-side keys are configured in the environment file (.env).

```
curl -X POST http://localhost:8000/restart-llama \
-H "X-API-Key: your_api_key" \
-H "Content-Type: application/json" \
-d '{
    "ngl": 36,
    "ctx_size": 4096,
    "no_mmap": false
}'
```

### llama-server commandline parameters available:

#### Put these in the -d '{}' section of the api call to set them and restart llama-server process. All are optional.  If not supplied the defaults will be used.

* "m": "/models/[model name]"
* "ngl": 99
* "nn_cpu_moegl": 0
* "cache_type_k": "turbo3"
  * (Extra TQ options: turbo2, turbo3, turbo4)
* "cache_type_v": "turbo4"
  * (Extra TQ options: turbo2, turbo3, turbo4)
* "no_mmap": [true/false]
* "mlock": [true/false]
* "jinja": [true/false]
* "ctx_size": 4096

### Permanently change the llama-server startup parameters:

#### Start the container and link ./docker/.env into the container after setting the values.
`docker run -d --name easy-llama --gpus all -p [Ext port]:8000 -v [Ext volume]:/models -p [Ext port llama]:8080 -v ./docker/.env:/app/.env:ro easy-llama`

#### Edit in the API code (correct option).

Amend ./api/config.py
Set the default values for each of the options you wish to change.
Delete the original image (if one exists).
Rebuild a new image.

#### Edit in the API code (possible but not recommended).

Alternatively, edit ./app/config.py and link the edited version back in to the container.
`-v ./api/config.py:/app/config.py:ro`

### Access the llama-server process as normal.

#### Curl to 'completion' endpoint.  For Open-AI compatibility use '/v1/completions'

```
curl --request POST \
    --url http://localhost:[Ext port llama]/completion \
    --header "Content-Type: application/json" \
    --data '{"prompt": "Building a website can be done in 10 simple steps:","n_predict": 128}'
```

#### For a lot more options, take a look at the ggml.org GitHub Llama Server [README](https://github.com/ggml-org/llama.cpp/blob/master/tools/server/README.md)

---

## llama.cpp with Turbo Quant source:

Thanks to Tom Turney for making his llama.cpp build with Turbo Quant available for use by all.

TheTom: [llama-cpp-turboquant](https://github.com/TheTom/llama-cpp-turboquant)

















